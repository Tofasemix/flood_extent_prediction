# Multimodal Flood Susceptibility Prediction: Fusing 1D Atmospheric and 2D Topographic Data

This repository contains the source code and experimental framework for a doctoral-level research project on multimodal computer vision. The primary hypothesis explores the injection of 1D atmospheric tabular data (pressure, wind velocity) into the latent space of 2D Convolutional Neural Networks (CNNs) conditioning spatial predictions of flood susceptibility.

## Project Overview
Traditional flood prediction models often isolate satellite imagery from tabular atmospheric data. This project bridges that gap by fusing spatial topography/precipitation maps with physical tabular data inside the bottleneck of deep learning architectures. 

The repository evaluates two distinct approaches:
1. **Multimodal U-Net (Baseline):** Utilizes standard skip connections for precise pixel-to-pixel spatial reconstruction.
2. **Multimodal DeepLabV3+:** Employs Atrous Spatial Pyramid Pooling (ASPP) to capture broader global context via dilated convolutions.

### Architectural Approaches
**1. Multimodal U-Net**
![U-Net Architecture](unet_architecture.png)

**2. Multimodal DeepLabV3+**
![DeepLab Architecture](deeplab_architecture.png)

## Environment Setup & Hardware

The models were developed and trained using an NVIDIA RTX 4500 Ada Generation GPU, but inference can be executed on lower-tier hardware. To ensure complete reproducibility, the environment configuration is provided in two formats.

**Option 1: Conda (Recommended)**
```bash
conda env create -f environment.yml
conda activate flood_env
```

**Option 2: Pip**
```bash
pip install -r requirements.txt
```

## Repository Structure

The project has been structured for strict modularity and reproducibility:

```text
Flooding/
├── Dataset/                     # Original 2D spatial patches (8MB - included)
├── clean_tabular_data.csv       # 1D Atmospheric data mapped to spatial patches
├── models/                      # Architecture definitions
│   ├── multimodal_unet.py
│   └── multimodal_deeplab.py
├── utils/                       # Shared modules
│   └── data_loader.py           # Custom PyTorch Dataset handling fusion
├── MyUnet/                      # U-Net experiment tracking & execution
│   ├── train.py
│   ├── regional_evaluate.py
│   └── multimodal_flood_unet.pth # Pre-trained weights (~93.5 MB)
├── Deeplab/                     # DeepLabV3+ experiment tracking & execution
│   ├── train_deeplab.py
│   ├── evaluate_deeplab.py
│   └── multimodal_deeplab_v3_final.pth.zip # COMPRESSED WEIGHTS (Extract before use!)
├── comparative_training_curve.png # Training convergence visualization
└── inference_unet_final.py      # Final inference and visualization script
```

> **IMPORTANT NOTE ON DEEPLAB WEIGHTS:** Due to GitHub's 100MB file limit, the final DeepLabV3+ weights (`multimodal_deeplab_v3_final.pth.zip`) have been compressed. **You must unzip this file inside the `Deeplab/` directory before running the DeepLab evaluation script.**

## Methodology & The "Chimera Loss"
A significant challenge in flood prediction is extreme class imbalance (approx. 99.6% of the spatial data represents dry land). To combat *mode collapse*, we engineered a custom loss function tailored for class minorities:

* **Weighted BCE Loss:** Forces the network to aggressively search for the minority class (water) with a positive weight multiplier.
* **Dice Loss:** Enforces geometric overlap and spatial coherence.
* **Focal Loss (DeepLab only):** Penalizes false confidence in easy-to-predict "dry" pixels.
* **Boundary Loss (DeepLab only):** Refines topographic contour precision using morphological simulated operations.

## Results & Quantitative Evaluation

After rigorous training and ablation studies, the evaluation on a set of 150 regional cyclones yielded the following metrics (evaluated on 64x64 spatial patches):

| Metric | Multimodal U-Net (Baseline) | Multimodal DeepLabV3+ |
| :--- | :--- | :--- |
| **Precision** | **0.8243** | 0.6667 |
| **Recall** | **0.3395** | 0.2782 |
| **F1-Score (Regional)** | **0.4809** | 0.3926 |
| **IoU** | **0.3166** | 0.2443 |

### Key Academic Finding
Despite DeepLabV3+ being a fundamentally more complex architecture, the **Multimodal U-Net vastly outperformed it, achieving an 82.43% precision rate**. 

*Analysis:* The ASPP module in DeepLabV3+ seeks global context through large dilation rates, causing it to over-generalize and miss isolated, fine-grained flood pixels. Conversely, the U-Net's direct skip connections perfectly retain the high-resolution spatial features necessary for local disaster mapping. As such, the multimodal CNN functions phenomenally as a **Regional Early Warning System**, accurately drawing probability perimeters around at-risk coordinates.

## Execution Instructions

The pipeline is entirely self-contained. You can run the scripts directly from the root directory.

**1. Run Evaluation (U-Net Winner):**
```bash
python MyUnet/regional_evaluate.py
```

**2. Generate Visual Inference (5-Column Plot):**
This script randomly samples the dataset, performs a forward pass using the trained U-Net, and generates an academic plot displaying Topography, Precipitation, Ground Truth, Probability Map, and Final Prediction.
```bash
python inference_unet_final.py
```
