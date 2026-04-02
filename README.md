# 🛣️ RouteForge — Real-Time Drivable Space Segmentation

> Pixel-wise binary segmentation of drivable free space for Level 4 autonomous driving.

---

## 📌 Table of Contents

- [Project Overview](#-project-overview)
- [Model Architecture](#-model-architecture)
- [Dataset Used](#-dataset-used)
- [Setup & Installation Instructions](#-setup--installation-instructions)
- [How to Run the Code](#-how-to-run-the-code)
- [Example Outputs / Results](#-example-outputs--results)

---

## 🔍 Project Overview

**RouteForge** addresses one of the most critical challenges in Level 4 autonomous driving: identifying safe, drivable **"Free Space"** in complex urban environments — *without* relying on painted lane markings or map priors.

The system performs **pixel-wise semantic segmentation**, classifying each pixel of a front-facing camera frame as either:

| Class | Description |
|-------|-------------|
| `White` — Drivable | Road surface safe for vehicle traversal |
| `Black` — Non-Drivable | Sidewalks, curbs, obstacles, parked vehicles |

### Key Design Goals

- **Safety-Critical Latency:** The entire inference pipeline is optimized for real-time autonomous response, achieving **~1000 FPS** on a T4 GPU — well within the sub-millisecond reaction times required for AV systems.
- **Built From Scratch:** To comply with strict challenge constraints, **no pre-trained ImageNet weights** and **no pre-built library architectures** (e.g., torchvision models) were used. The network, training loop, and data pipeline were all developed from the ground-up.
- **Markings-Free Perception:** The model learns spatial and contextual cues from raw RGB images, making it robust to roads without visible lane markings — a common failure point for lane-detection approaches.

---

## 🧠 Model Architecture

The core of the perception engine is a custom-built **U-Net (Encoder-Decoder)** architecture, specifically designed for high-frequency binary segmentation tasks.


```
Input Image (3 × 128 × 128)
        │
┌───────▼───────┐
│   Encoder     │  ← Feature Extraction (Contraction Path)
│  Conv → Pool  │
│  Conv → Pool  │
│  Conv → Pool  │
└───────┬───────┘
        │  Skip Connections ──────────────────────┐
┌───────▼───────┐                                 │
│  Bottleneck   │  ← Deep Semantic Context        │
└───────┬───────┘                                 │
        │                                         │
┌───────▼───────┐                                 │
│   Decoder     │  ← Spatial Recovery  ◄──────────┘
│ TranspConv+Cat│
│ TranspConv+Cat│
│ TranspConv+Cat│
└───────┬───────┘
        │
┌───────▼───────┐
│  Output Head  │  1×1 Conv → Sigmoid → Binary Mask
└───────────────┘
Output Mask (1 × 128 × 128)
```

### Component Breakdown

#### 🔽 Encoder (Contraction Path)
- **3 progressive stages**, each consisting of:
  - Two `3×3` Convolutional layers
  - `ReLU` activation functions
  - `2×2` Max Pooling (halves spatial resolution)
- Learns increasingly abstract semantic representations of road surfaces, curbs, and obstacles.

#### 🔁 Bottleneck
- The deepest layer captures global scene context at the most compressed spatial resolution.
- Rich semantic features are extracted here before being upsampled back through the decoder.

#### ↗️ Skip Connections
- High-resolution feature maps from each encoder stage are **concatenated** directly into the corresponding decoder stage.
- This preserves fine-grained spatial details (e.g., precise road-to-curb boundary locations) that would otherwise be lost during downsampling — critical for safe ego-lane boundary estimation.

#### 🔼 Decoder (Expansion Path)
- **3 upsampling stages**, each using:
  - Learnable **Transposed Convolutions** (stride 2) to double spatial resolution
  - Concatenation with the corresponding encoder skip connection
  - Two `3×3` Convolutional layers with `ReLU`
- Gradually reconstructs the full-resolution feature map from compressed semantic representations.

#### 🎯 Output Head
- A final `1×1` Convolution collapses feature channels to a single-channel logit map.
- During inference, a **Sigmoid activation** converts logits to probabilities.
- A threshold of `> 0.5` produces the final binary segmentation mask.

### Training Details

| Parameter | Value |
|-----------|-------|
| Loss Function | Hybrid **BCE + Dice Loss** |
| Precision | Mixed Precision (`torch.amp`) |
| Input Resolution | 128 × 128 |
| Output | Binary Mask (Drivable / Non-Drivable) |

> The hybrid BCE + Dice Loss was chosen to handle the inherent **class imbalance** between road pixels and non-road pixels in urban scenes, enabling sharp and precise boundary detection.
> The system supports both lightweight (128×128) and high-resolution (256×512) training configurations for balancing speed and spatial accuracy.

---

## 📦 Dataset Used

### nuScenes v1.0-mini

| Property | Detail |
|----------|--------|
| **Source** | [nuScenes](https://www.nuscenes.org/) — `v1.0-mini` split |
| **Input Modality** | RGB frontal camera frames (`CAM_FRONT`) |
| **Ground Truth** | Binary segmentation masks (auto-generated) |
| **Resolution** | Resized to `128 × 128` pixels |
| **Split** | 80% Training / 20% Validation |
| **Normalization** | Standard pixel normalization applied |

### Ground Truth Mask Generation

Binary masks were **not manually annotated**. Instead, they were programmatically generated by:

1. Accessing nuScenes' relational database of **3D spatial vector maps**, which encode semantic map layers (drivable surface, walkways, etc.).
2. **Projecting these 3D map polygons** onto the 2D `CAM_FRONT` image plane using the camera's intrinsic and extrinsic calibration matrices.
3. Rasterizing the projected drivable-surface regions into a binary pixel mask aligned with the RGB frame.

This approach enables scalable, precise ground truth generation without the need for manual labeling effort.

### Validation Strategy

The 20% held-out validation set was used to monitor **Mean Intersection over Union (mIoU)** across epochs, ensuring the model generalizes to unseen road scenes and does not overfit to training data.

Mean Intersection over Union (mIoU) was taken to be our primary evaluation metric.
---

## ⚙️ Setup & Installation Instructions

### Prerequisites

- Python **3.8+**
- A **CUDA-compatible GPU** is strongly recommended (a Google Colab T4 GPU runtime works well)
- `pip` package manager

### Step 1 — Clone the Repository

```bash
git clone https://github.com/2306apk/RouteForge-Drivable-Space-Segmentation.git
cd RouteForge-Drivable-Space-Segmentation
```

### Step 2 — (Recommended) Create a Virtual Environment

```bash
# Using venv
python -m venv venv
source venv/bin/activate        # On Linux/macOS
venv\Scripts\activate           # On Windows
```

Or use a **Conda** environment:

```bash
conda create -n routeforge python=3.9
conda activate routeforge
```

### Step 3 — Install Dependencies

```bash
pip install torch torchvision opencv-python numpy matplotlib
```

> **Google Colab users:** All of the above packages are pre-installed in a standard Colab environment. Simply ensure you are using a **GPU runtime** (`Runtime → Change runtime type → T4 GPU`).

### Step 4 — Download the nuScenes Dataset

1. Register and download `v1.0-mini` from [https://www.nuscenes.org/download](https://www.nuscenes.org/download).
2. Extract and place the dataset folder at the path expected by `train.py` (update the `DATA_ROOT` variable in the script if needed).

### Verified Environment

| Dependency | Version |
|------------|---------|
| Python | 3.8+ |
| PyTorch | 1.12+ |
| torchvision | 0.13+ |
| OpenCV | 4.x |
| NumPy | 1.21+ |
| Matplotlib | 3.5+ |

---

## ▶️ How to Run the Code

### 1. Train the Model

Trains the custom U-Net from scratch on the nuScenes dataset. This script will:
- Load and preprocess `CAM_FRONT` frames and auto-generated binary masks
- Apply the 80/20 train/validation split
- Train using the hybrid BCE + Dice Loss with mixed precision
- Save the best-performing model weights to `model.pth`

```bash
# Train 128×128 model (fast)
python -m scripts.training.train_model

# Train 256×512 model (higher spatial accuracy)
python -m scripts.training.train_model_256x512
```

**Expected console output (per epoch):**
```
Epoch [1/50] | Train Loss: 0.4312 | Val mIoU: 0.7841
Epoch [2/50] | Train Loss: 0.3105 | Val mIoU: 0.8220
...
✅ Best model saved → unet_best.pth (Val mIoU: 0.9134)
                      unet_best_256x512.pth (Val mIoU: 0.8660)         
```

---

### 2. Run Inference

Loads the saved `model.pth` weights and runs inference on a sample image (Image can be of your own choice). Outputs the predicted binary mask, a colour overlay, and the measured FPS.

```bash
# Run inference (128 model)
python -m scripts.training.inference --size 128

# Run inference (256×512 model)
python -m scripts.training.inference --size 256
```

**Expected output:**
```
⚡ 30 FPS (real-time performance)
✅ Segmentation overlay saved → output.png
```

A matplotlib window will display:

| Panel | Content |
|-------|---------|
| Left | Original `CAM_FRONT` RGB frame |
| Centre | Predicted binary mask |
| Right | Drivable space overlay (Green highlight) |

---

## 📊 Example Outputs / Results

### Quantitative Results

| Metric | Value |
|--------|-------|
| **Inference Speed** | ~Real-time performance (~25–60 FPS depending on hardware) |
| **Optimization Technique** | Mixed Precision (`torch.amp`) |
| **Loss Function** | Hybrid BCE + Dice Loss |
| **Primary Metric** | Mean Intersection over Union (mIoU) |

### Qualitative Results

The model successfully learns to distinguish drivable asphalt from surrounding non-drivable regions across a variety of urban scenes:

- ✅ **Correctly segments** open road surfaces, intersections, and turning lanes
- ✅ **Correctly rejects** sidewalks, curbs, parked vehicles, pedestrians, and building facades
- ✅ **Sharp boundary detection** at road-to-kerb transitions, even without visible lane markings
- ✅ **Robust** to varying lighting conditions present in the nuScenes dataset

### Sample Visualization

```
┌─────────────────┬─────────────────┬─────────────────┐
│  Original Frame │  Predicted Mask │  Drivable Space │
│  (CAM_FRONT)    │  (Binary)       │  Overlay (Green)│
│                 │                 │                 │
│  🚗 [RGB img]   |⬜⬜⬜⬛⬛⬛  │  🟩🟩🟩🚗🚗  │
└─────────────────┴─────────────────┴─────────────────┘
```

> <img width="1017" height="224" alt="image" src="https://github.com/user-attachments/assets/b6628a4e-4138-4cbe-ba96-5e1dfba6d3c8" />


---

## 📁 Repository Structure

```
RouteForge-Drivable-Space-Segmentation/
│
├├── 📁 models/
│   ├── 📄 unet_best.pth              # 128×128 trained model
│   └── 📄 unet_best_256x512.pth      # 256×512 trained model      # Trained model weights
│
├── 📁 scripts/
│   │
│   ├── 📁 core/
│   │   ├── 📄 inference.py           # Inference & visualization script
│   │   ├── 📄 generate_masks_2.py    # Ground truth mask generation
│   │   ├── 📄 nuscenes_loader.py     # nuScenes data loading utilities
│   │   └── 📄 utils_projection.py    # 3D → 2D projection logic
│   │
│   └── 📁 training/
│       ├── 📄 train_model.py              # 128×128 training
├       ├── 📄 train_model_256x512.py      # 256×512 training
│       ├── 📄 model.py           # Custom UNet architecture
│       ├── 📄 dataset.py         # Dataset & preprocessing
│       └── 📄 utils.py           # Training utilities
│
└── 📄 README.md                  # Technical documentation
```

---

## 📄 License

This project was developed as part of an autonomous driving challenge. All model code and training pipelines were written from scratch without the use of pre-trained weights or pre-built architectures.

---

*Built with PyTorch | Dataset: nuScenes v1.0-mini | Architecture: Custom U-Net*
