# MAHE-Mobility
# 🦅 BEV-Mapper
### Bird's Eye View Mapping from Monocular Camera Images

> **Converting camera footage into real-time top-down spatial maps for autonomous navigation.**

![Python](https://img.shields.io/badge/Python-3.10+-3776AB?style=for-the-badge&logo=python&logoColor=white)
![PyTorch](https://img.shields.io/badge/PyTorch-2.0+-EE4C2C?style=for-the-badge&logo=pytorch&logoColor=white)
![OpenCV](https://img.shields.io/badge/OpenCV-4.8+-5C3EE8?style=for-the-badge&logo=opencv&logoColor=white)
![Status](https://img.shields.io/badge/Status-Active-38BDF8?style=for-the-badge)

---

## 📌 Table of Contents

- [What is This?](#-what-is-this)
- [Architecture](#-architecture)
- [Methodology](#-methodology)
- [Tech Stack](#-tech-stack)
- [Project Structure](#-project-structure)
- [Setup & Installation](#-setup--installation)
- [Usage](#-usage)
- [Pipeline Walkthrough](#-pipeline-walkthrough)
- [Results](#-results)
- [Team](#-team)

---

## 🧠 What is This?

**BEV-Mapper** is a computer vision system that takes a standard camera image (or video stream) and converts it into a **Bird's Eye View (BEV) occupancy map** — a top-down 2D representation of the surrounding environment showing where objects are in real-world space.

Think of it like transforming what your dashcam sees into a live version of Google Maps, built frame by frame in real time.

### The Core Problem

A camera captures a **perspective view** — objects close to the camera appear large, far objects appear small, and there's no direct way to measure real-world distances. Autonomous vehicles, delivery robots, and surveillance systems all need to know **where** objects are in physical space, not just what they look like in a photo.

### Our Solution

We solve this with a 6-stage pipeline:

1. Detect objects using deep learning (YOLO)
2. Estimate per-pixel depth from a single image (MiDaS)
3. Unproject pixels into 3D space using camera geometry
4. Transform to world coordinates using camera extrinsics
5. Filter to ground-level points
6. Bin everything into a 2D occupancy grid

---

## 🏗 Architecture

```
┌─────────────────────────────────────────────────────────────────────┐
│                         BEV-MAPPER PIPELINE                         │
└─────────────────────────────────────────────────────────────────────┘

  Camera Image (H × W × 3)
         │
         ▼
  ┌──────────────┐     ┌──────────────────┐
  │  Perception  │     │  Depth Estimator │
  │   (YOLOv8)   │     │    (MiDaS)       │
  │              │     │                  │
  │ Bounding     │     │ Depth Map        │
  │ Boxes +      │     │ (H × W × 1)      │
  │ Class Labels │     │                  │
  └──────┬───────┘     └────────┬─────────┘
         │                      │
         └──────────┬───────────┘
                    │
                    ▼
         ┌──────────────────────┐
         │   Camera Geometry    │
         │   (Intrinsics K,     │
         │    Extrinsics R, t)  │
         │                      │
         │  Pixel (u,v) + Depth │
         │  → 3D Point (X,Y,Z)  │
         └──────────┬───────────┘
                    │
                    ▼
         ┌──────────────────────┐
         │   3D Point Cloud     │
         │   (N × 3 points)     │
         │                      │
         │  World frame         │
         │  Ground filter       │
         └──────────┬───────────┘
                    │
                    ▼
         ┌──────────────────────┐     ┌─────────────────────┐
         │   Occupancy Grid     │◄────│  Temporal Fusion    │
         │   (200 × 200)        │     │  (previous frames)  │
         │                      │     └─────────────────────┘
         │  0 = Free            │
         │  1 = Occupied        │
         │  0.5 = Unknown       │
         └──────────────────────┘
                    │
                    ▼
            BEV MAP OUTPUT
         (Top-down spatial map)
```

### Two Supported Modes

| Mode | How It Works | Best For |
|------|-------------|----------|
| **Explicit Geometry** | Depth → 3D → BEV (our main pipeline) | Single camera, real-time |
| **Homography** | Direct image-to-ground warp via H matrix | Road surface only, fastest |

---

## 📐 Methodology

### Step 1 — Perception (Object Detection)

We use **YOLOv8** to detect objects in the image. Each detection gives us:
- A bounding box `[x1, y1, x2, y2]` in pixel coordinates
- A class label (`car`, `person`, `truck`, etc.)
- A confidence score

This tells us **what** is in the scene and roughly **where** in the image.

### Step 2 — Camera Geometry

Every camera has two sets of parameters:

**Intrinsics (K matrix)** — the camera's internal optical properties:
```
    | fx   0   cx |
K = |  0  fy   cy |
    |  0   0    1 |
```
Where `fx`, `fy` are focal lengths and `cx`, `cy` is the principal point (usually image centre).

**Extrinsics (R, t)** — the camera's position and orientation in the world:
- `R` (3×3 rotation matrix): which direction is the camera pointing?
- `t` (3×1 translation vector): where is the camera mounted? (e.g., 1.2m above ground)

These are determined once during **camera calibration** using a checkerboard pattern.

### Step 3 — Depth Estimation

We use **MiDaS** (Monocular Depth Estimation in the Wild) to predict a depth value for every pixel in the image from a single image — no stereo camera needed.

MiDaS outputs **relative depth** (near vs far). We convert to metric depth using:
```
depth_metric = scale_factor / (midas_output + ε)
```
Where `scale_factor` is estimated from known geometry (camera height, lane width, object size priors).

### Step 4 — 3D Unprojection

For each pixel `(u, v)` with depth `Z`, we compute its 3D position in camera space:
```
X_cam = (u - cx) × Z / fx
Y_cam = (v - cy) × Z / fy
Z_cam = Z
```

Then transform to world coordinates:
```
P_world = R^T × (P_cam - t)
```

### Step 5 — Ground Filtering

We keep only points near ground level (within ±0.3m of the expected ground height). This removes sky, building walls, and other non-navigable surfaces.

### Step 6 — Occupancy Grid

We divide the real-world area around the camera into a grid of 10cm × 10cm cells. Each 3D ground point votes for its corresponding cell, incrementing its occupancy probability using a **Bayesian log-odds update**:

```
log_odds_new = log_odds_old + log(p_sensor / (1 - p_sensor))
```

This makes the map more robust to sensor noise — a single noisy point won't falsely mark a cell as occupied.

### Temporal Fusion

Across multiple frames, we compensate for the camera's own movement (**ego-motion compensation** using IMU or wheel odometry), then merge point clouds from the last N frames. This fills in occluded regions and reduces noise significantly.

---

## 🛠 Tech Stack

| Category | Technology | Why We Chose It |
|----------|-----------|-----------------|
| **Language** | Python 3.10+ | Standard for ML/CV research |
| **Deep Learning** | PyTorch 2.0 | Industry standard, GPU support |
| **Object Detection** | YOLOv8 (Ultralytics) | Best speed/accuracy tradeoff for real-time |
| **Depth Estimation** | MiDaS (Intel) | State-of-the-art monocular depth, single image |
| **Computer Vision** | OpenCV 4.8 | Camera calibration, image warping, homography |
| **Numerical Computing** | NumPy | Vectorized point cloud operations |
| **Visualization** | Matplotlib | BEV map rendering and result plots |
| **3D Visualization** | Open3D | Point cloud inspection and debugging |
| **Advanced BEV** | BEVFormer (MMDet3D) | Transformer-based multi-view BEV (research mode) |
| **Experiment Tracking** | (optional) WandB | Logging metrics, depth accuracy, grid quality |

---

## 📁 Project Structure

```
bev-mapper/
│
├── data/
│   ├── raw/                    # original images/videos (git-ignored)
│   ├── processed/              # preprocessed inputs (git-ignored)
│   └── .gitkeep
│
├── notebooks/
│   ├── 01_camera_calibration.ipynb
│   ├── 02_depth_exploration.ipynb
│   └── 03_bev_visualization.ipynb
│
├── src/
│   ├── __init__.py
│   ├── perception/
│   │   ├── detector.py         # YOLOv8 wrapper
│   │   └── segmentor.py        # SegFormer wrapper
│   ├── geometry/
│   │   ├── camera.py           # Intrinsics, extrinsics, projection
│   │   └── homography.py       # Homography-based BEV
│   ├── depth/
│   │   └── estimator.py        # MiDaS depth estimation
│   ├── mapping/
│   │   ├── point_cloud.py      # 3D unprojection
│   │   ├── occupancy_grid.py   # Grid construction + Bayesian update
│   │   └── fusion.py           # Temporal + multi-view fusion
│   └── utils/
│       ├── visualize.py        # Plotting BEV maps
│       └── calibration.py      # Camera calibration tools
│
├── tests/
│   ├── test_geometry.py
│   ├── test_depth.py
│   └── test_occupancy_grid.py
│
├── configs/
│   └── config.yaml             # Camera params, grid size, model paths
│
├── outputs/                    # Results, saved grids (git-ignored)
│
├── .github/
│   └── workflows/
│       └── ci.yml              # Automated testing on push
│
├── .gitignore
├── requirements.txt
├── setup.py
└── README.md
```

---

## ⚙️ Setup & Installation

### Prerequisites

- Python 3.10+
- CUDA-enabled GPU recommended (works on CPU, slower)
- Git

### 1. Clone the Repository

```bash
git clone https://github.com/AvaneeshN/MAHE-Mobility.git
cd MAHE-Mobility
```

### 2. Create a Virtual Environment

```bash
python -m venv venv
source venv/bin/activate        # Linux/Mac
venv\Scripts\activate           # Windows
```

### 3. Install Dependencies

```bash
pip install --upgrade pip
pip install -r requirements.txt
```

### 4. Download Pre-trained Models

```bash
# YOLOv8 downloads automatically on first run
# MiDaS downloads automatically via torch.hub

# Or manually:
python scripts/download_models.py
```

### 5. Configure Camera Parameters

Edit `configs/config.yaml` with your camera's intrinsic values:

```yaml
camera:
  fx: 800.0         # focal length x (pixels)
  fy: 800.0         # focal length y (pixels)
  cx: 640.0         # principal point x
  cy: 360.0         # principal point y
  height: 1.2       # camera height above ground (metres)

grid:
  width_m: 20.0     # BEV map width in metres
  height_m: 20.0    # BEV map height in metres
  resolution: 0.1   # metres per cell (0.1 = 10cm)

models:
  yolo: yolov8n.pt  # nano=fastest, x=most accurate
  depth: MiDaS_small
```

---

## 🚀 Usage

### Run on a Single Image

```bash
python src/run.py --input data/raw/street.jpg --output outputs/
```

### Run on a Video

```bash
python src/run.py --input data/raw/drive.mp4 --output outputs/ --mode video
```

### Run with Homography (Fast Mode)

```bash
python src/run.py --input data/raw/road.jpg --mode homography
```

### Calibrate Your Camera

```bash
python src/utils/calibration.py --images data/calibration/ --pattern 8x6
```

### Run Tests

```bash
pytest tests/ -v
```

---

## 🔬 Pipeline Walkthrough

Here's exactly what happens when you run the pipeline on one image:

```python
# 1. Load image
image = cv2.imread("street.jpg")                  # shape: [720, 1280, 3]

# 2. Detect objects
detections = yolo(image)                           # list of [x1,y1,x2,y2, class, conf]

# 3. Estimate depth
depth_map = midas(image)                           # shape: [720, 1280], values in metres

# 4. Unproject every pixel to 3D
point_cloud = depth_to_pointcloud(depth_map, K)    # shape: [N, 3], in camera frame

# 5. Transform to world coordinates
points_world = camera_to_world(point_cloud, R, t)  # shape: [N, 3], in world frame

# 6. Filter to ground level
ground_pts = points_world[abs(points_world[:,1]) < 0.3]

# 7. Build occupancy grid
grid = OccupancyGrid(20, 20, resolution=0.1)
grid.fill(ground_pts)                              # shape: [200, 200]

# 8. Visualize
plot_bev(grid, detections)
```

---

## 📊 Results

| Metric | Value |
|--------|-------|
| Detection FPS (GPU) | ~45 FPS |
| Full Pipeline FPS (GPU) | ~12 FPS |
| Full Pipeline FPS (CPU) | ~3 FPS |
| Depth MAE (relative) | ~0.12 |
| Grid resolution | 10 cm/cell |
| Coverage area | 20 m × 20 m |

> Results measured on an NVIDIA RTX 3060, image resolution 1280×720.

---

## 👥 Team

| Name | Role |
|------|------|
| Avaneesh Nair | Perception & Object Detection |
| Alankryt Sharma | Camera Geometry & Calibration |
| Snigdha Sanjay | Depth Estimation & 3D Projection |
| Divya Vhavle | Occupancy Grid & Fusion |

---

## 📦 Dataset

This project uses the **nuScenes** dataset provided by the organizers.

> 📁 **Dataset Drive Link:** *https://drive.google.com/drive/folders/1g5KgxG0p8-MmTiXkNtCpoYSIkdBQprEm*

Once downloaded, place the data as follows:

```
data/
├── raw/          ← extract nuScenes samples here
└── processed/    ← auto-generated after preprocessing
```

> ⚠️ Do **not** commit dataset files to the repository. They are git-ignored by default.

---

## 📚 References

- [YOLOv8 — Ultralytics](https://github.com/ultralytics/ultralytics)
- [MiDaS — Intel ISL](https://github.com/isl-org/MiDaS)
- [BEVFormer — MIT + Horizon Robotics](https://github.com/fundamentalvision/BEVFormer)
- Ranftl et al., *Towards Robust Monocular Depth Estimation*, TPAMI 2022

---

