# 3D Reconstruction

## 🏗️ Overview

The 3D Reconstruction category represents the core extensions of DUSt3R that focus on improving quality, efficiency, and scalability of static scene reconstruction. These papers address various challenges including real-time processing, large-scale scenes, multi-view consistency, and achieving state-of-the-art performance.

## 📈 Research Timeline

```text
2024: Foundation laid with MASt3R-SLAM and early extensions
2025: Explosive growth with breakthrough methods
- Jan: VGGT introduces unified geometry (partial permutation equivariance)
- Feb: π³ (Pi3) achieves true permutation equivariance - Current SOTA
  - Eliminates ALL positional embeddings and reference frames
  - Architecture guarantees f(π(X)) = π(f(X))
  - Loss function purely for reconstruction quality
- Real-time systems: SLAM3R, Fast3R, MV-DUSt3R+
- Large-scale: Spann3R, REGIST3R, Pow3R
- Quality focus: MoGe, LoRA3D, Test3R, Dens3R
```

## 🎯 Key Research Directions

### 1. **State-of-the-Art Methods** ⭐

- **π³ (Pi3)**: True permutation-equivariant learning - Current SOTA
  - Eliminates positional embeddings and reference frames completely
  - Near-zero order variance (0.003 vs VGGT's 0.033)
  - Loss function focuses on quality while architecture ensures equivariance
- **VGGT**: Visual geometry grounded transformer - Previous SOTA
  - Still uses reference frame (first view special)
  - Partial permutation equivariance only
- **Dens3R**: Unified geometric dense prediction

### 2. **Real-time Systems** ⚡

- **SLAM3R**: Dense reconstruction from monocular RGB videos
- **Fast3R**: 1000+ images in one forward pass
- **MASt3R-SLAM**: Real-time SLAM with 3D priors
- **MV-DUSt3R+**: 2-second reconstruction with cross-reference fusion

### 3. **Large-scale & Multi-view** 🌍

- **Spann3R**: Spatial memory for unbounded scenes
- **MUSt3R**: O(N) complexity for 1000+ images (5.5cm ATE on TUM RGB-D)
- **REGIST3R**: Incremental registration with stereo foundation
- **Pow3R**: Universal flexibility - handles any combination of camera intrinsics, poses, depth

### 4. **Quality & Robustness** 🎨

- **MoGe**: Monocular geometry for open-domain images
- **LoRA3D**: Low-rank self-calibration of 3D models
- **Test3R**: Learning to reconstruct at test time
- **SPARS3R**: Semantic prior alignment for sparse reconstruction

### 5. **Specialized Approaches** 🔧

- **Light3R-SfM**: Feed-forward structure-from-motion
- **ReconX**: Video diffusion for sparse views
- **Spurfies**: Sparse surface reconstruction with local priors

## 📊 Performance Comparison

### State-of-the-Art Results

#### DTU Dataset

| Model             | Accuracy ↓ | Completeness ↓ | Overall ↓ | Speed    | Status                           |
| ----------------- | ---------- | -------------- | --------- | -------- | -------------------------------- |
| **Pow3R w/ K+RT** | **1.384**  | **0.846**      | **1.115** | 3.2 FPS  | **Best with priors**             |
| **π³ (Pi3)**      | **1.198**  | **1.849**      | -         | 57.4 FPS | **Permutation-equivariant SOTA** |
| VGGT              | 1.338      | 1.896          | -         | 43.2 FPS | Previous SOTA                    |
| Pow3R             | 2.116      | 1.370          | 1.743     | 3.7 FPS  | Universal flexibility            |
| DUSt3R            | 2.677      | 0.805          | 1.741     | ~3s      | Original                         |

#### Camera Pose (Sintel Zero-shot)

| Model        | ATE ↓     | RPE trans ↓ | RPE rot ↓ | Order Variance |
| ------------ | --------- | ----------- | --------- | -------------- |
| **π³ (Pi3)** | **0.074** | **0.040**   | **0.282** | **Near-zero**  |
| VGGT         | 0.167     | 0.062       | 0.491     | Partial        |
| CUT3R        | 0.217     | 0.070       | 0.636     | High           |
| Fast3R       | 0.371     | 0.298       | 13.75     | High           |

#### Universal Flexibility (Pow3R)

| Input Configuration | Co3Dv2 RRA@15↑ | RealEstate10K mAA(30)↑ | Speed (fps) | Key Benefit           |
| ------------------- | -------------- | ---------------------- | ----------- | --------------------- |
| RGB only            | 94.8           | 62.5                   | 3.2         | No calibration needed |
| RGB + Intrinsics    | 95.0           | 72.5                   | 30.1        | Consumer camera ready |
| RGB + All priors    | 95.0           | 72.5                   | 30.1        | Professional use      |

### Multi-View Performance (HM3D Dataset)

| Model          | 12 Views DAc ↑ | Speed     | Architecture | Key Innovation         |
| -------------- | -------------- | --------- | ------------ | ---------------------- |
| **MV-DUSt3R+** | **91.5%**      | **0.89s** | Single-stage | Cross-reference fusion |
| MV-DUSt3R      | 79.5%          | 0.15s     | Single-stage | Single reference       |
| DUSt3R         | 30.7%          | 8.28s     | Two-stage    | Pairwise matching      |
| Spann3R        | 0.0%           | 1.34s     | Sequential   | No global consistency  |

### Scalability Comparison

| Model      | Max Images | Complexity | Memory Growth  | Processing Time | Best For              |
| ---------- | ---------- | ---------- | -------------- | --------------- | --------------------- |
| DUSt3R     | 10-20      | O(N²)      | O(N²)          | ~10s/pair       | Small scenes          |
| MASt3R     | 20-50      | O(N²)      | O(N²)          | ~7s/pair        | Better matching       |
| Pow3R      | Any        | O(N²)      | O(N²)          | 3.7 FPS         | With auxiliary inputs |
| MUSt3R     | 1000+      | O(N)       | O(1) per image | 8.4 FPS         | Large multi-view      |
| MV-DUSt3R+ | 100+       | O(N)       | O(N)           | ~2s total       | Fast multi-view       |
| Fast3R     | 1500+      | O(N)       | Low            | 251 FPS         | Speed priority        |
| Spann3R    | Unlimited  | O(N)       | Constant       | Sequential      | Unbounded scenes      |

## 📚 Complete Paper List (18 papers)

### 🏆 State-of-the-Art Methods

1. [**π³ (Pi3)**: Scalable Permutation-Equivariant Visual Geometry Learning](pi3.md) ⭐ SOTA (no positional embeddings)
2. [**VGGT**: Visual Geometry Grounded Transformer](vggt.md) - ~0.2s 추론 (DUSt3R ~7s)
3. [**Pow3R**: Empowering Unconstrained 3D Reconstruction](pow3r.md) - Best with auxiliary inputs
4. [**Dens3R**: Unified Geometric Dense Prediction](dens3r.md)

### ⚡ Real-time Systems

1. [**SLAM3R**: Real-Time Dense Scene Reconstruction](slam3r.md)
2. [**Fast3R**: 3D Reconstruction of 1000+ Images](fast3r.md)
3. [**MASt3R-SLAM**: Real-Time Dense SLAM](mast3r-slam.md)
4. [**MV-DUSt3R+**: Single-Stage Scene Reconstruction](mv-dust3r-plus.md) - DUSt3R 대비 8~14×

### 🌍 Large-scale & Multi-view

1. [**MUSt3R**: Multi-view Stereo 3D Reconstruction (O(N) complexity)](must3r.md)
2. [**Spann3R**: 3D Reconstruction with Spatial Memory](spann3r.md)
3. [**Pow3R**: Universal 3D Reconstruction with Any Auxiliary Inputs](pow3r.md) - CVPR'25
4. [**REGIST3R**: Incremental Registration](regist3r.md)

### 🎨 Quality Enhancement

1. [**MoGe**: Monocular Geometry Estimation](moge.md)
2. [**LoRA3D**: Low-Rank Self-Calibration](lora3d.md)
3. [**Test3R**: Learning to Reconstruct at Test Time](test3r.md)
4. [**SPARS3R**: Semantic Prior Alignment](spars3r.md)

### 🔧 Specialized Methods

1. [**Light3R-SfM**: Feed-forward Structure-from-Motion](light3r-sfm.md)
2. [**ReconX**: Video Diffusion for Sparse Views](reconx.md)
3. [**Spurfies**: Sparse Surface Reconstruction](spurfies.md)

## 💡 Key Insights & Trends

### Major Breakthroughs

1. **True Permutation Equivariance** (Pi3): Complete elimination of positional embeddings and reference frames
2. **Unified Geometry** (VGGT): Joint estimation of all geometric properties (still order-dependent)
3. **Spatial Memory** (Spann3R): Unbounded scene reconstruction
4. **Single-Stage Pipeline** (MV-DUSt3R+): O(N) complexity with cross-reference fusion

### Technical Innovations

- **Memory Efficiency**: From O(N²) to O(N) complexity
- **Global Consistency**: Maintaining alignment across unlimited views
- **Test-Time Adaptation**: Learning scene-specific features
- **Foundation Model Integration**: Leveraging pre-trained knowledge

### Performance Evolution

```text
2024: DUSt3R baseline (~10s per pair, limited scale)
2025 Q1: VGGT (43.2 FPS, unified geometry, partial permutation equivariance)
2025 Q2: π³ (57.4 FPS, true permutation equivariance, current SOTA)
2025: Multiple specialized systems for different use cases
```

## 🚀 Getting Started

### Choose Based on Your Needs

**For Best Quality** 🏆

- Use **π³ (Pi3)** for state-of-the-art results with true permutation equivariance
  - Best when input order may vary or is unknown
  - Ideal for multi-camera systems with arbitrary arrangements
- Use **VGGT** if you have a consistent reference view
- Use **Dens3R** for unified dense prediction (depth + normals)

**For Real-time Applications** ⚡

- Use **SLAM3R** for live video processing
- Use **MV-DUSt3R+** for quick multi-view reconstruction
- Use **Fast3R** for massive image collections

**For Large Scenes** 🌍

- Use **Spann3R** for unbounded sequences
- Use **MUSt3R** for large multi-view collections
- Use **Pow3R** for unconstrained scenarios

**For Limited Data** 📸

- Use **MoGe** for single/few images
- Use **ReconX** with video diffusion priors
- Use **SPARS3R** for sparse views with semantics

## 🔮 Future Directions

1. **Beyond SOTA**: Building on π³'s true permutation-equivariant foundation (no positional embeddings)
2. **Symmetry-Aware Architectures**: Extending π³'s principles to other vision tasks
3. **Dynamic Integration**: Bridging static and dynamic reconstruction
4. **Uncertainty Quantification**: Confidence-aware predictions
5. **Cross-modal Fusion**: Integrating language and other modalities

---

_Last updated: July 2025 | 18 papers documented_
