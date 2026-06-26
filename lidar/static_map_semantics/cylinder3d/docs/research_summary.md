# Cylinder3D: Research Summary

## Citation

**Zhu, H., Zhou, H., Ma, J., Li, Y., Hu, J., Fang, L., & Quan, L.** (2021). *Cylindrical and Asymmetrical 3D Convolution Networks for LiDAR Segmentation.* In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 9939–9948.

- **arXiv:** [2011.10033](https://arxiv.org/abs/2011.10033)
- **Conference:** CVPR 2021
- **Affiliations:** The Hong Kong University of Science and Technology, Tsinghua University

---

## Core Idea

Cylinder3D addresses a fundamental mismatch in prior LiDAR segmentation methods: most approaches partition 3D space using **Cartesian voxels** (cubic grids), which poorly represent the inherently **non-uniform radial distribution** of LiDAR point clouds. Points are dense near the sensor and exponentially sparse at longer ranges, causing Cartesian grids to waste capacity on empty cells far from the sensor while over-compressing near-field detail.

Cylinder3D proposes three key innovations:

1. **Cylindrical partition** of the 3D space that naturally aligns with LiDAR geometry
2. **Asymmetrical 3D convolution networks** that handle the anisotropic nature of cylindrical voxels
3. **Dimension-decomposition based context modeling (DDCMod)** for efficient large-receptive-field feature extraction

---

## Cylindrical Coordinate Transform

The input point cloud coordinates are transformed from Cartesian to cylindrical:

```
(x, y, z) → (r, θ, z)

where:
  r     = sqrt(x² + y²)          radial distance from sensor vertical axis
  θ     = atan2(y, x)            azimuth angle
  z     = z                      height (unchanged)
```

The cylindrical space is then discretized into a 3D grid with dimensions:

| Axis | Range | Grid Size | Resolution |
|------|-------|-----------|------------|
| r (radial) | 0 – 50 m | 480 bins | ~10.4 cm |
| θ (azimuth) | 0 – 2π | 360 bins | 1° |
| z (height) | -3 – 1 m (typical) | 32 bins | ~12.5 cm |

This cylindrical partition ensures:
- **Near-field regions** (high point density) have proportionally more voxels
- **Far-field regions** (sparse points) use fewer voxels without loss
- The angular resolution matches the sensor's native beam spacing
- Vertical resolution captures ground-to-overhead structure

---

## Asymmetric 3D Convolution

Standard symmetric 3D convolutions (3x3x3) treat all spatial dimensions equally, but cylindrical voxels have fundamentally different semantics along each axis:

- **Radial axis (r):** captures depth layering (foreground/background)
- **Azimuth axis (θ):** captures lateral extent of objects
- **Height axis (z):** captures vertical structure

Cylinder3D introduces **asymmetric convolution blocks** that decompose the 3D kernel into complementary components:

```
Asymmetric Residual Block:
  Input → [3×1×3 conv] → [1×3×3 conv] → [3×3×3 conv] → Add(Input) → Output
```

Each sub-kernel captures different spatial relationships:
- **3×1×3:** radial-height plane (captures vertical structure at varying depths)
- **1×3×3:** azimuth-height plane (captures lateral extent and height)
- **3×3×3:** full 3D context (integrates all dimensions)

This decomposition reduces parameters while increasing the effective receptive field, as the combined kernel covers a larger spatial extent than a single 3×3×3 convolution.

---

## Dimension-Decomposition Based Context Modeling (DDCMod)

DDCMod extends the asymmetric convolution idea to explicitly model long-range context along each cylindrical dimension independently:

```
DDCMod Block:
  Input
    ├─→ [1×1×K conv] (height context, K=7 or larger)
    ├─→ [1×K×1 conv] (azimuth context)
    ├─→ [K×1×1 conv] (radial context)
    └─→ [1×1×1 conv] (point-wise transform)
  Concatenate all branches → [1×1×1 conv] → Output
```

This allows the network to capture:
- Long vertical columns (e.g., poles, trees, building facades)
- Wide azimuthal arcs (e.g., road boundaries, fences)
- Deep radial corridors (e.g., streets extending away from sensor)

---

## Comparison with State-of-the-Art Methods

### SemanticKITTI Test Set (single scan)

| Method | Type | mIoU (%) | Year |
|--------|------|----------|------|
| PointNet++ | Point-based | 20.1 | 2017 |
| RangeNet++/kNN | Range image | 52.2 | 2019 |
| 3D-MiniNet | Range + point | 55.8 | 2020 |
| SqueezeSegV3 | Range image | 55.9 | 2020 |
| PolarNet | Polar BEV | 54.3 | 2020 |
| RandLA-Net | Point-based | 55.9 | 2020 |
| KPConv | Point-based | 58.8 | 2019 |
| SPVNAS | Voxel (NAS) | 66.4 | 2020 |
| MinkowskiNet | Sparse voxel | 63.1 | 2019 |
| (AF)²-S3Net | Voxel + range | 62.2 | 2021 |
| **Cylinder3D** | **Cylindrical voxel** | **68.9** | **2021** |
| Cylinder3D (TTA) | Cylindrical voxel | 72.2* | 2021 |

*TTA = Test-Time Augmentation with ensemble

### nuScenes-lidarseg Validation Set

| Method | mIoU (%) |
|--------|----------|
| RangeNet++ | 65.5 |
| PolarNet | 71.0 |
| FIDNet | 71.8 |
| Salsanext | 72.2 |
| **Cylinder3D** | **76.1** |

### Per-Class IoU Highlights (SemanticKITTI test)

| Class | Cylinder3D IoU (%) | Notes |
|-------|-------------------|-------|
| Car | 97.1 | Best among all methods |
| Bicycle | 67.6 | Significant improvement |
| Motorcycle | 64.0 | +5% over prior best |
| Road | 91.4 | Competitive |
| Sidewalk | 75.5 | Strong |
| Vegetation | 84.3 | Competitive |
| Person | 69.4 | Notable improvement |
| Bicyclist | 75.5 | Notable improvement |

---

## Key Results Summary

| Benchmark | Metric | Score |
|-----------|--------|-------|
| SemanticKITTI test (single scan) | mIoU | **68.9%** |
| SemanticKITTI test (TTA ensemble) | mIoU | **72.2%** |
| nuScenes-lidarseg val | mIoU | **76.1%** |
| nuScenes-lidarseg test | mIoU | **77.2%** |

---

## Legacy and Impact

### Immediate Contributions
- **Demonstrated the importance of coordinate system choice** for LiDAR processing, inspiring subsequent polar/cylindrical methods
- **Set new SOTA** on both major LiDAR segmentation benchmarks at time of publication
- **Efficient design:** achieves superior results without requiring neural architecture search (unlike SPVNAS) or extremely large models

### Influence on Subsequent Work
1. **Coordinate-aware methods:** Cylinder3D inspired a wave of methods exploring non-Cartesian representations (e.g., CPGNet, 2DPASS, CENet)
2. **Asymmetric convolutions:** The dimension-decomposition idea was adopted in subsequent 3D perception works
3. **Multi-representation fusion:** Later works combined cylindrical features with range images or point-level features (e.g., RPVNet, PVKD)
4. **Industrial adoption:** The cylindrical partition concept has been incorporated into production autonomous driving stacks

### Limitations Acknowledged
- Fixed grid resolution may not optimally handle extreme range variations
- Cylindrical coordinates introduce singularities at the origin (r=0)
- The fixed 480×360×32 grid size requires tuning for different sensors (e.g., 32-beam vs 128-beam LiDAR)
- Does not natively handle multi-scan / temporal information

### Citation Count
As of 2024, Cylinder3D has been cited over **800 times**, making it one of the most influential works in outdoor LiDAR segmentation.

---

## Code and Resources

- **Official Repository:** [https://github.com/xinge008/Cylinder3D](https://github.com/xinge008/Cylinder3D)
- **Framework:** PyTorch
- **Dependencies:** spconv (sparse convolution library), numba, torch-scatter
