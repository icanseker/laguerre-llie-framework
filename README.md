# An Adaptive and Scalable Convolution Framework for Low-Light Image Enhancement via Analytic Functions Subordinate to Laguerre Polynomials

## Overview

This repository contains the full MATLAB implementation accompanying the paper:

> **"An Adaptive and Scalable Convolution Framework for Low-Light Image Enhancement via Analytic Functions Subordinate to Laguerre Polynomials"**

The proposed method leverages **coefficient bounds derived from bi-univalent Sakaguchi-type analytic functions**, where the subordinating function is expressed in terms of the **classical Laguerre polynomial family**. These coefficient bounds are used to construct **8-directional 3×3 spatial convolution kernels**, which are applied to very dark images. The parameters governing the coefficient formulas (ν and t) are not fixed — they are **dynamically optimized per image** using a two-phase strategy: a coarse grid search followed by Nelder-Mead simplex refinement, with Shannon entropy as the optimization criterion.

Nine established low-light enhancement algorithms serve as comparison baselines, each representing a fundamentally different algorithmic category. All experiments are conducted on the **LOL (Low-Light) paired dataset**. On LOL-15, the proposed method achieves the **Best NIQE (3.82)** among all 10 methods and **34/90 total metric wins** — the highest win count.

---

## Table of Contents

1. [Repository Structure](#repository-structure)
2. [Quick Start](#quick-start)
3. [Dataset](#dataset)
4. [Proposed Method — Laguerre](#proposed-method--laguerre)
   - [Mathematical Formulation](#mathematical-formulation)
   - [Coefficient Bounds](#coefficient-bounds)
   - [8-Directional Convolution Kernels](#8-directional-convolution-kernels)
   - [Dynamic Optimization — Two-Phase Strategy](#dynamic-optimization--two-phase-strategy)
   - [Pseudocode](#pseudocode)
5. [Comparison Algorithms](#comparison-algorithms)
6. [Evaluation Metrics](#evaluation-metrics)
7. [Output Structure](#output-structure)
8. [Configurable Parameters](#configurable-parameters)
9. [References](#references)

---

## Repository Structure

```
laguerre-llie-framework/
├── main.m                            # Main runner — orchestrates all algorithms,
│                                     # metrics computation, and file output
├── README.md                         # This file
│
├── algorithms/
│   │
│   │   ── Wrappers (one per algorithm, all at this level) ──
│   ├── run_laguerre.m                 # Proposed: Laguerre polynomial coefficient convolution
│   ├── run_HE.m                      # Comparison: Histogram Equalization
│   ├── run_SSR.m                     # Comparison: Single-Scale Retinex (sigma=80)
│   ├── run_gamma.m                   # Comparison: Gamma Correction (gamma=0.4)
│   ├── run_LIME.m                    # Comparison: LIME (alpha=0.15, gamma=0.8)
│   ├── run_dong.m                    # Comparison: Dong invert-dehaze-invert
│   ├── run_BIMEF.m                   # Comparison: BIMEF (Ying 2020)
│   ├── run_NPE.m                     # Comparison: NPE (Wang 2013)
│   ├── run_LECARM.m                  # Comparison: LECARM (Ying 2017)
│   ├── run_EnlightenGAN.m            # Comparison: EnlightenGAN (Jiang 2021)
│   │
│   │   ── Algorithm source / implementation folders ──
│   ├── _helpers/                     # Shared utilities for the proposed method
│   │   ├── apply_convolution.m       # Builds Master Kernel and applies it per channel
│   │   └── fast_neg_entropy.m        # Optimization objective — no conv2, uses precomputed img_d + I_edge
│   │
│   ├── bimef/                        # BIMEF official files (baidut/BIMEF, unchanged)
│   │   ├── BIMEF.m                   # Readable source code
│   │   └── BIMEF.p                   # Compiled version (used by MATLAB)
│   │
│   ├── lime/                         # LIME official files (estija/LIME, unchanged)
│   │   └── *.m                       # 12 files: lime.m, lime_main_module.m, ...
│   │
│   ├── npe/                          # NPE compiled .p files (baidut/BIMEF, unchanged)
│   │   ├── NPEA.p                    # Main entry point — full NPE pipeline
│   │   ├── BLT.p                     # Bi-log transformation
│   │   ├── BiFltL.p                  # Bright-pass filter
│   │   ├── Post.p                    # Synthesis: reflectance × mapped illumination
│   │   ├── cbright.p / getextpic.p / getlocalmax.p   # Helpers
│   │
│   ├── lecarm/                       # LECARM official source (unchanged, baidut/LECARM)
│   │   ├── LECARM.m                  # Main function (10 lines — pure elegance)
│   │   ├── CameraModel.m             # Abstract CRF base class
│   │   ├── limeEstimate.m            # Illumination smoother (LIME-based)
│   │   └── +CameraModels/            # MATLAB package: 5 CRF models
│   │       ├── Sigmoid.m             # Default (n=0.90, sigma=0.60)
│   │       ├── Beta.m
│   │       ├── BetaGamma.m
│   │       ├── Gamma.m
│   │       └── Preferred.m
│   │
│   └── enlightengan/                 # EnlightenGAN inference (arsenyinfo package)
│       ├── run_enlightengan.py       # CLI wrapper written by us
│       └── enlighten_inference/      # arsenyinfo package (copied from repo)
│
├── metrics/
│   ├── calc_NIQE.m                   # NIQE — Natural Image Quality Evaluator (no-reference)
│   └── ...                           # PSNR, MSE, SSIM, Entropy, CII helpers
│
├── source/
│   ├── low/                          # LOL eval set — 15 low-light images
│   └── high/                         # LOL eval set — 15 ground truth images
│
└── target/                           # Output directory (created on run)
    └── {AlgorithmName}/              # One subfolder per algorithm
        ├── {id}_enhanced.png         # Enhanced output image
        └── {id}_metrics.txt          # Metrics + optimal (nu, t) for Laguerre
```

---

## Quick Start

The repository ships with everything needed to reproduce the paper's results out of the box:
- `source/low/` and `source/high/` contain all 15 LOL evaluation image pairs

To **reproduce the experiments**, simply run `main.m` in MATLAB:

1. **Open MATLAB** and navigate (`cd`) to the root of this repository.
2. **Run** `main.m`.
3. **Inspect results** in `target/` — one subfolder per algorithm.

```matlab
% In MATLAB command window:
cd /path/to/laguerre-llie-framework
run('main.m')
```

To **run on your own images**, replace the contents of `source/low/` (and optionally `source/high/`) with your own files and re-run `main.m`. Supported formats: `.png`, `.jpg`, `.jpeg`, `.bmp`, `.tif`, `.tiff`

---

## Dataset

### LOL — Low-Light Paired Dataset

All experiments in the paper use the **LOL (Low-Light) dataset**, introduced by:

> Chen Wei, Wenjing Wang, Wenhan Yang, Jiaying Liu.  
> "Deep Retinex Decomposition for Low-Light Enhancement." *BMVC*, 2018.  
> Dataset: https://daooshee.github.io/BMVC2018website/

#### Why LOL?

The LOL dataset is one of the most widely adopted benchmarks in the low-light enhancement literature. It provides **real-world paired images** — each low-light image has a corresponding normally-exposed ground truth captured under the same scene. This pairing enables full-reference metric evaluation (PSNR, MSE, SSIM), which would otherwise be impossible. The images span indoor and outdoor scenes with diverse content and lighting conditions, making the benchmark representative and challenging.

#### Dataset Properties

| Property | Value |
|----------|-------|
| Type | Real-world paired (low-light + ground truth) |
| Resolution | 400 × 600 pixels |
| Evaluation set size | 15 image pairs |
| Format | PNG |

#### Images Included in This Repository

All 15 LOL evaluation images are included as defaults in `source/low/` and `source/high/`. Every image in the evaluation set has a mean intensity (I_mean) well below the threshold of 64, so all 15 are within the intended operating range of the proposed Laguerre method.

| Image ID | I_mean |
|----------|--------|
| 1 | 24.92 |
| 22 | 19.33 |
| 23 | 9.28 |
| 55 | 9.30 |
| 79 | 22.18 |
| 111 | 19.61 |
| 146 | 24.24 |
| 179 | 20.45 |
| 493 | 6.62 |
| 547 | 15.67 |
| 665 | 7.57 |
| 669 | 17.24 |
| 748 | 12.60 |
| 778 | 7.31 |
| 780 | 10.89 |

#### Using Your Own Images

You are not limited to the LOL dataset. You can place **any images** in `source/low/`. The algorithm will process whatever files it finds there:

- If a matching file exists in `source/high/`, full-reference metrics (PSNR, MSE, SSIM) will be computed.
- If no matching reference exists in `source/high/`, PSNR, MSE, and SSIM will be recorded as `N/A`. Entropy and CII will still be computed (they are no-reference metrics).
- The proposed Laguerre method will only apply convolution-based enhancement to images with **I_mean < 64**. Images above this threshold are logged as SKIPPED for the polynomial method (see below).
  - **Why 64?** 64 = 128/2: one exposure stop below the perceptually neutral midpoint (128). This is the standard photographic definition of the low-light boundary. Both the threshold (64) and the +50 brightness offset design derive from the same reference value 128, ensuring internal consistency.

---

## Proposed Method — Laguerre

### Mathematical Formulation

The method derives its enhancement kernel from the **coefficient bounds of a subclass of bi-univalent Sakaguchi-type analytic functions**, where the subordinating structure is built using **classical Laguerre polynomials**.

In the theory of geometric functions, a function f ∈ Σ (bi-univalent class) of the form:

```
f(z) = z + a₁z + a₂z² + a₃z³ + ...
```

belongs to a Sakaguchi-type family if certain subordination conditions hold. For this family, the coefficient bounds |a₁|, |a₂|, |a₃| can be derived analytically. These bounds serve as the **entries of the enhancement kernel**: a₁ = 1 (fixed by normalization), and a₂, a₃ are computed from the Laguerre-specific formulas as functions of the free parameters ν and t.

The key insight is that these mathematically-derived coefficient bounds carry **structural information** — when embedded in a directional convolution kernel, they produce an enhancement that preserves edges and local structure rather than applying a uniform global transformation.

### Coefficient Bounds

Given parameters ν > 0 and t ∈ [-1, 1), the Laguerre polynomial coefficient bounds are:

```
a₁ = 1   (fixed; bi-univalent normalization)

         ┌──────────────────────────────────────────────────────┐
         │             2·(1-ν)³                                 │
|a₂| ≤  │  ────────────────────────────────────────────────    │
         │  (1-t)·(ν² - t·ν·(2-ν) + 2(1-ν))                  │
         └──────────────────────────────────────────────────────┘
         (square root of the above expression)

           (1-ν)            (1-ν)²
|a₃| ≤  ────────────  +  ─────────────
          (1-t)(t+2)       (1-t)²
```

**Parameter constraints:**
- ν > 0 (strictly positive; this family is defined for all positive ν)
- t ∈ [-1, 1) (open on the right; t = 1 is excluded as it causes division by zero)
- The denominator of a₂ must be positive for the coefficient to be real and valid

**Scan range used in experiments:**
- ν ∈ [0.51, 0.99] (strictly open at both endpoints: ν=0.5 → degenerate numerator (1−ν)³=0.125 but denominator degenerates; ν=1.0 → (1−ν)=0 makes a₂=0)
- t ∈ [-1.0, 0.9]

### 8-Directional Convolution Kernels

Given (a₁, a₂, a₃), eight 3×3 kernels are constructed, each oriented in one of the eight principal directions:

```
Direction 0° (right):         Direction 45° (down-right):
  [ 0   0   0  ]                [ 0   0   a₃ ]
  [ a₁  a₂  a₃ ]                [ 0   a₂  0  ]
  [ 0   0   0  ]                [ a₁  0   0  ]

Direction 90° (down):          Direction 135° (down-left):
  [ 0   a₁  0  ]                [ a₁  0   0  ]
  [ 0   a₂  0  ]                [ 0   a₂  0  ]
  [ 0   a₃  0  ]                [ 0   0   a₃ ]

Direction 180° (left):         Direction 225° (up-left):
  [ 0   0   0  ]                [ a₃  0   0  ]
  [ a₃  a₂  a₁ ]                [ 0   a₂  0  ]
  [ 0   0   0  ]                [ 0   0   a₁ ]

Direction 270° (up):           Direction 315° (up-right):
  [ 0   a₃  0  ]                [ 0   0   a₁ ]
  [ 0   a₂  0  ]                [ 0   a₂  0  ]
  [ 0   a₁  0  ]                [ a₃  0   0  ]
```

Each kernel is applied separately to each color channel (R, G, B) via `conv2`. The eight results are **averaged** and a **+50 brightness offset** is added:

```
I_enhanced(x,y,c) = clip( (1/8) · Σᵢ₌₁⁸ conv2(I(·,·,c), hᵢ) + 50 , [0, 255] )
```

**Why 8 directions?** A single oriented kernel would emphasize edges in one direction and suppress others. By averaging over all 8 cardinal and diagonal directions, the enhancement becomes **isotropic** — edges and structures are lifted uniformly regardless of their orientation. This is the key mechanism behind the method's strong structural similarity (SSIM) performance.

**Brightness offset (+50):** After convolution, a fixed +50 is added to every pixel. This compensates for the low dynamic range of the input (I_mean < 64) and ensures a visually useful output brightness. The offset is fixed (not adaptive) to isolate the contribution of the mathematically-derived kernel from post-processing normalization. The value +50 was selected empirically: it outperforms adaptive additive and multiplicative alternatives on all primary metrics (SSIM, PSNR, NIQE) on the LOL evaluation set.

### Dynamic Optimization — Two-Phase Strategy

The parameters ν and t are not fixed globally. They are **optimized independently for each image** to find the (ν, t) pair that maximizes the Shannon entropy of the enhanced output. Maximum entropy corresponds to the richest distribution of pixel intensities — the most informative, detail-rich enhancement.

The optimization proceeds in two phases:

#### Phase 1 — Coarse Grid Search

A uniform grid over the (ν, t) parameter space is evaluated exhaustively:

- ν grid: `0.51 : nu_step : 0.99` — step depends on preset (0.030 / 0.050 / 0.100)
- t grid: `-1.0 : t_step : 0.9`   — step depends on preset (0.05 / 0.08 / 0.20)
- Total evaluations: ~663 (high_precision) / ~240 (balanced) / ~50 (fast)

For each (ν, t) pair:
1. Compute Laguerre coefficients a₂, a₃ — skip if invalid (denominator ≤ 0, non-finite)
2. Apply 8-directional convolution → get candidate enhanced image
3. Compute Shannon entropy of the result
4. Store (ν, t, entropy) in the results table

After the full grid scan, the top **n_candidates** pairs by entropy are retained as Phase 2 starting points. n_candidates = 6 / 4 / 2 for high_precision / balanced / fast. Higher n_candidates compensates for the narrow ν domain [0.51, 0.99].

#### Phase 2 — Nelder-Mead Simplex Refinement

Starting from each of the top `n_candidates` Phase 1 points, MATLAB's `fminsearch` (Nelder-Mead simplex algorithm) refines to **sub-grid precision**:

- **Objective**: minimize negative entropy (equivalent to maximizing entropy)
- **Tolerances and budget**: controlled by preset (see table above)
- **Boundary enforcement**: out-of-bounds or invalid (ν, t) pairs incur a large penalty (1e6), steering the optimizer back into the feasible region

The best (ν, t) found across all starting points is used to produce the final enhanced image.

**Why two phases?** The grid search provides coarse but globally-aware coverage of the parameter space, avoiding convergence to local optima. The Nelder-Mead refinement then achieves arbitrary precision around the best region identified by the grid. Using `n_candidates` starting points (rather than just the single best grid point) provides robustness against cases where the true optimum lies in a region whose best grid neighbor was not ranked #1 due to grid resolution.

**Tunable behavior:** All optimization parameters are controlled by the `optimization_preset` string in `main.m` — no individual parameter editing required. The preset scales Phase 1 grid density and Phase 2 Nelder-Mead tolerances together, ensuring meaningful speed/quality differentiation across the full pipeline.

### Pseudocode

```
Algorithm: Laguerre Low-Light Enhancement

INPUT:  Low-light color image I (H × W × 3, uint8)
        optimization_preset   -- 'high_precision' | 'balanced' | 'fast'
                                 (all grid + NM params resolved internally)
OUTPUT: Enhanced image I_enh (H × W × 3, uint8)
        Optimal parameters best_nu, best_t

─────────────────────────────────────────────────────────────────────
STEP 0: RESOLVE OPTIMIZATION PRESET  (inside run_laguerre.m)
─────────────────────────────────────────────────────────────────────
  switch optimization_preset:
    'high_precision' → nu_step=0.03, t_step=0.05, n_cand=6
                       TolFun=1e-6, TolX=1e-6, MaxFunEvals=1100
    'balanced'       → nu_step=0.05, t_step=0.08, n_cand=4
                       TolFun=1e-4, TolX=1e-4, MaxFunEvals=400
    'fast'           → nu_step=0.10, t_step=0.20, n_cand=2
                       TolFun=1e-2, TolX=1e-2, MaxFunEvals=100

─────────────────────────────────────────────────────────────────────
STEP 1: BRIGHTNESS GATE
─────────────────────────────────────────────────────────────────────
  Compute grayscale mean intensity: I_mean ← mean(double(I(:)))
  if I_mean >= 64:   // 64 = 128/2, one stop below neutral midpoint 128
      Mark image as SKIPPED for this method
      Write skip notice to metrics file
      RETURN  (no enhancement applied)

─────────────────────────────────────────────────────────────────────
STEP 2: PHASE 1 — COARSE GRID SEARCH
─────────────────────────────────────────────────────────────────────
  // Pre-compute Master Kernel once per (nu, t) — avoids 8 separate convs
  // K_master = (1/8) * sum(h₁..h₈) — exact algebraic identity (see below)

  Initialize results ← empty table
    for each nu in [0.51 : nu_step : 0.99]:   // nu_step from preset (Laguerre domain)
      for each t in [-1.0 : t_step : 0.9]:  // t_step from preset

          // Compute Laguerre coefficient bounds (Theorem 1)
          numer ← 2 · (1−nu)³
          denom ← (1−t)·(nu² − t·nu·(2−nu) + 2(1−nu))
          if denom <= 0: SKIP this (nu, t)
          a2 ← sqrt(numer / denom)

          td1 ← (1−t) · (t+2)
          td2 ← (1−t)²
          if td1 == 0 or td2 == 0: SKIP this (nu, t)
          a3 ← (1−nu) / td1 + (1−nu)² / td2

          if a2 or a3 is non-positive or non-finite: SKIP

          // Build Master Kernel (a1 = 1 fixed):
          //   [ 1+a3,  1+a3,  1+a3 ]
          //   [ 1+a3,  8·a2,  1+a3 ]   ÷ 8
          //   [ 1+a3,  1+a3,  1+a3 ]
          K_master ← build_master_kernel(a1=1, a2, a3)

          // Single convolution per channel (8× faster than naive loop)
          I_candidate ← apply_master_kernel(I, K_master)  // + brightness offset +50
          entropy ← shannon_entropy(I_candidate)

          Append (nu, t, entropy) to results

  Sort results by entropy descending
  Keep top n_candidates rows as starting_points   // n_candidates from preset

─────────────────────────────────────────────────────────────────────
STEP 3: PHASE 2 — NELDER-MEAD SIMPLEX REFINEMENT
─────────────────────────────────────────────────────────────────────
  best_entropy ← -∞
  best_nu ← starting_points[1].nu
  best_t  ← starting_points[1].t

  for k = 1 to n_candidates:   // n_candidates from preset
      x0 ← [starting_points[k].nu, starting_points[k].t]

      // fminsearch minimizes f(x) = -entropy(enhanced(x))
      // Penalty = 1e6 returned for infeasible (nu, t)
      // Tolerances and MaxFunEvals from preset (Step 0)
      [x_opt, f_opt] ← fminsearch( x → -entropy(enhance(I, x)), x0,
                                   TolFun, TolX, MaxFunEvals )

      // Clamp to valid range
      x_opt[1] ← clamp(x_opt[1], 0.51, 0.99)   // nu
      x_opt[2] ← clamp(x_opt[2], -1.0, 0.9)    // t

      if -f_opt > best_entropy:
          best_entropy ← -f_opt
          best_nu ← x_opt[1]
          best_t  ← x_opt[2]

─────────────────────────────────────────────────────────────────────
STEP 4: PRODUCE FINAL ENHANCED IMAGE
─────────────────────────────────────────────────────────────────────
  Compute final coefficients from (best_nu, best_t):
      a2, a3 ← laguerre_coefficients(best_nu, best_t)

  K_master ← build_master_kernel(a1=1, a2, a3)
  I_enh    ← apply_master_kernel(I, K_master)   // + brightness offset +50

─────────────────────────────────────────────────────────────────────
STEP 5: build_master_kernel(a1, a2, a3)
─────────────────────────────────────────────────────────────────────
  // Sum of 8 directional kernels h₁..h₈ (each entry counted by frequency):
  //   Corners appear in 2 kernels: a1 appears in 4 corners, a3 in 4 corners
  //   Edges appear in 2 kernels:   a1 appears in 4 edges, a3 in 4 edges
  //   Center appears in all 8:     a2 × 8
  //
  //   Sum = [ a1+a3,  a1+a3,  a1+a3 ]
  //         [ a1+a3,   8·a2,  a1+a3 ]
  //         [ a1+a3,  a1+a3,  a1+a3 ]
  //
  //   K_master = Sum / 8
  //
  //   With a1=1 fixed:
  //   K_master = [ (1+a3)/8,  (1+a3)/8,  (1+a3)/8 ]
  //              [ (1+a3)/8,    a2,       (1+a3)/8 ]
  //              [ (1+a3)/8,  (1+a3)/8,  (1+a3)/8 ]
  //
  // This is mathematically identical to 8 separate convolutions then averaging.
  // Reduces per-iteration convolution count from 8C → C  (C = 3 channels).

  edge ← (a1 + a3) / 8
  K_master ← [ edge,  edge,  edge  ]
               [ edge,  a2,    edge  ]
               [ edge,  edge,  edge  ]
  RETURN K_master

─────────────────────────────────────────────────────────────────────
STEP 6: apply_master_kernel(I, K_master)
─────────────────────────────────────────────────────────────────────
  for each channel c (R, G, B):
      out(:,:,c) ← conv2(I(:,:,c), K_master, 'same')

  result ← uint8( clamp(out + 50, [0, 255]) )
  RETURN result

─────────────────────────────────────────────────────────────────────
OUTPUT
─────────────────────────────────────────────────────────────────────
  Save I_enh  → target/Laguerre/{id}_enhanced.png
  Save metrics → target/Laguerre/{id}_metrics.txt
      (includes best_nu, best_t, PSNR, MSE, SSIM, Entropy, CII, NIQE)
```

---

## Comparison Algorithms

Nine algorithms representing different methodological categories are benchmarked alongside the proposed method. All comparison algorithms run with **fixed, standard parameters** — no per-image optimization — ensuring a fair comparison.

### 1. HE — Histogram Equalization

| Property | Value |
|----------|-------|
| MATLAB function | `histeq()` (built-in) |
| Parameters | None |
| Channels | Applied independently per R, G, B channel |
| Category | Global histogram-based |

Histogram equalization redistributes pixel intensities to span the full available range [0, 255], maximizing global contrast. It is the simplest and most widely used baseline. However, it treats all regions identically, which often causes over-enhancement in already-bright areas and can suppress local detail in very dark regions.

**Reference:** Gonzalez & Woods, *Digital Image Processing* (4th ed.), Chapter 3, 2018.

---

### 2. SSR — Single-Scale Retinex

| Property | Value |
|----------|-------|
| Formula | R(x,y) = log(I(x,y)) - log(G_σ ∗ I(x,y)) |
| Parameter | σ = 80 (standard value from original paper) |
| MATLAB function | `imgaussfilt()` + `log()` |
| Post-processing | Linear normalization per channel to [0, 255] |
| Category | Center/surround illumination estimation (Retinex) |

The Retinex model, inspired by the human visual system's color constancy, estimates the illumination component as a low-frequency (Gaussian-blurred) version of the image. The log-ratio between the input and its blurred version isolates the reflectance, yielding the enhanced output. SSR uses a single Gaussian scale (σ = 80) which provides a coarse estimate of the illumination envelope.

The output of SSR is in the logarithmic domain and may span a range that does not directly correspond to [0, 255]. Per-channel linear normalization is applied to map each channel's min/max to [0, 255].

**Reference:** Jobson, Rahman & Woodell. "Properties and Performance of a Center/Surround Retinex." *IEEE Transactions on Image Processing*, 6(3), 451–462, 1997.

---

### 3. Gamma Correction

| Property | Value |
|----------|-------|
| Formula | s = r^γ, where r ∈ [0, 1] |
| Parameter | γ = 0.4 (fixed) |
| Category | Point-wise power-law transformation |

Gamma correction is a pixel-wise nonlinear transformation. For γ < 1, it brightens darker pixels more aggressively than brighter ones (the power-law curve bends upward), effectively expanding the tonal range of dark images. The value γ = 0.4 is a standard low-light enhancement setting.

**Note on parameter choice:** An adaptive scheme (γ proportional to I_mean) was tested earlier but produced γ values in the range 0.06–0.30 for images with I_mean < 64, causing extreme over-brightening. A fixed γ = 0.4 provides consistent, fair baseline behavior.

**Reference:** Gonzalez & Woods, *Digital Image Processing* (4th ed.), Chapter 3, 2018.

---

### 4. LIME — Low-Light Image Enhancement via Illumination Map Estimation

| Property | Value |
|----------|-------|
| Parameters | α = 0.15 (smoothness weight), γ = 0.8 (illumination gamma) |
| Solver | ADMM (Alternating Direction Method of Multipliers) |
| Category | Structure-aware illumination map estimation |

LIME models image formation as L(x) = R(x) · T(x), where L is the observed low-light image, R is the desired reflectance (enhanced output), and T is the illumination map. The key innovation is the **structure-aware refinement** of T: the illumination map is refined by minimizing a weighted L1 total-variation objective that penalizes gradients in proportion to the local structure of T_hat (the initial illumination estimate). This structure-awareness is what distinguishes LIME from simpler illumination methods.

**Source:** estija/LIME — https://github.com/estija/LIME

Note: The official LIME code by the original authors is distributed as compiled `.p` files (source not readable). estija/LIME is a clean open-source MATLAB implementation of the same paper. All 12 algorithm files are copied unchanged into `algorithms/lime/`.

**Reference:** Guo X., Li Y., Ling H. "LIME: Low-Light Image Enhancement via Illumination Map Estimation." *IEEE Transactions on Image Processing*, 26(2), 982–993, 2017.

---

### 5. Dong — Inverted Dehazing

| Property | Value |
|----------|-------|
| MATLAB functions | `imcomplement()`, `imreducehaze()` |
| Parameters | Method = 'approxdcp', ContrastEnhancement = 'none' |
| Category | Dehazing-based (dark channel prior inversion) |

The key observation behind this method is that a low-light image, after inversion, resembles a hazy image: both are dominated by a bright, low-contrast veil. Dehazing algorithms are designed to remove exactly that kind of veil. The pipeline therefore: (1) inverts the low-light image, (2) applies a standard dehazing algorithm (approximate dark channel prior via `imreducehaze`), and (3) inverts the result back to recover the enhanced image.

`ContrastEnhancement = 'none'` is used strictly to follow the standard implementation and avoid double-processing: the dehazing step itself restores contrast, so additional contrast enhancement would be redundant and distorting.

**Reference:** Dong X., Pang Y., Wen J. "Fast Efficient Algorithm for Enhancement of Low Lighting Video." *ACM SIGGRAPH*, 2010. MATLAB official example: https://www.mathworks.com/help/images/low-light-image-enhancement.html

---

### 6. BIMEF — Bio-Inspired Multi-Exposure Fusion

| Property | Value |
|----------|-------|
| Implementation | From the original paper (see note below) |
| Parameters | μ = 0.5, a = −0.3293, b = 1.1258, k = auto-estimated per image |
| Category | Multi-exposure fusion (camera response model) |

BIMEF models low-light enhancement as a dual-exposure fusion problem. Given a single dark image, it synthesizes a well-exposed counterpart using a fitted camera response function (CRF), then blends the two using a pixel-wise weight map derived from the illumination distribution. Well-exposed pixels retain their original values; dark pixels receive more contribution from the synthetic image.

**Source:** https://github.com/baidut/BIMEF

The official repository provides `BIMEF.m` (full readable source code) and `BIMEF.p` (compiled version). Both are copied unchanged into `algorithms/bimef/`. MATLAB automatically uses the `.p` file when both are present. `run_BIMEF.m` calls `BIMEF()` directly with default parameters (μ=0.5, k=auto, a=−0.3293, b=1.1258) as defined in `BIMEF.m`. No custom implementation.

**Reference:** Ying Z., Li G., Gao W. "A Bio-Inspired Multi-Exposure Fusion Framework for Low-light Image Enhancement." *IEEE Transactions on Cybernetics*, 50(6), 2400–2414, 2020. arXiv: https://arxiv.org/abs/1711.00591

---

### 7. NPE — Naturalness Preserved Enhancement

| Property | Value |
|----------|-------|
| Implementation | Original compiled .p files from baidut/BIMEF (github.com/baidut/BIMEF) |
| Parameters | None — handled internally by NPEA.p |
| Category | Retinex-based illumination enhancement (naturalness-preserving) |

NPE is a Retinex-based method that explicitly addresses the over-enhancement problem of standard Retinex: pure reflectance extraction removes all illumination cues, producing images that look unnaturally flat. NPE instead reconstructs the enhanced image as `R × f(T)`, where R is the extracted reflectance and f(T) is a bi-log transformed illumination that preserves the global brightness trend of the scene.

The three-component pipeline is:
1. **Bright-pass filter** — Estimates illumination by frequency-weighted averaging of brighter neighbors in a local 15×15 patch (Eq. 5–12 in the paper). Ensures reflectance stays in [0, 1].
2. **Reflectance** — R_c(x) = I_c(x) / L_r(x) per channel, where L_r is the bright-pass filtered illumination.
3. **Bi-log transform** — Maps illumination via histogram specification with a log-shaped target histogram (Eq. 14–22), preserving lightness order while brightening dark regions.

**Parameters:** All parameters are handled internally by the compiled `.p` files. No user-configurable parameters are exposed.

**Why NPE is included as a comparison:** NPE directly targets naturalness preservation — the same objective measured by our NIQE metric. Including NPE allows the paper to demonstrate that the proposed Laguerre method achieves superior naturalness scores (NIQE) even compared to a method whose primary design goal is naturalness. Furthermore, BIMEF (another comparison in this work) explicitly benchmarks against NPE in its original paper, completing a transitive performance chain.

**References:**
- Wang S., Zheng J., Hu H.-M., Li B. "Naturalness Preserved Enhancement Algorithm for Non-Uniform Illumination Images." *IEEE Transactions on Image Processing*, 22(9), 3538–3548, 2013. DOI: 10.1109/TIP.2013.2261309
- Original code page: https://shuhangwang.wordpress.com/2015/12/14/naturalness-preserved-enhancement-algorithm-for-non-uniform-illumination-images/
- Note: The original NPE code is distributed exclusively as compiled `.p` files. The `.p` files in `algorithms/npe/` were obtained from baidut/BIMEF (https://github.com/baidut/BIMEF), the standard reference codebase for low-light enhancement benchmarking. Their authenticity was verified by running them on the paper's own test images and comparing entropy values against Table I of Wang 2013.

---

### 8. LECARM — Low-light Enhancement with Camera Response Model

| Property | Value |
|----------|-------|
| Implementation | Official source code, unchanged (see note) |
| Default Camera Model | `CameraModels.Sigmoid` (n = 0.90, σ = 0.60) |
| Parameters | ratioMax = 7, λ = 0.15, sigma = 2, sharpness = 0.001 |
| Category | Camera response model (CRF-based) |

LECARM enhances low-light images by modelling the camera response function (CRF). The key insight is that a low-light image can be brightened by simulating what the camera would have captured at a higher exposure. The per-pixel exposure ratio K is derived directly from the inverse of the illumination map: K = min(1/T, 7), meaning darker pixels receive a larger boost. The CRF then maps the input through the brightness transform function (BTF) using the chosen camera response model.

The pipeline: (1) T = max(R,G,B) per pixel; (2) T smoothed at half resolution via LIME's illumination solver; (3) K = min(1/T, ratioMax=7); (4) enhanced = cameraModel.btf(input, K).

**Parameter selection and justification:**

| Parameter | Value | Source | Rationale |
|-----------|-------|--------|-----------|
| Camera model | Sigmoid | Original LECARM.m default | The paper evaluates all five models; Sigmoid is the default in the released code, representing the authors' recommended choice. |
| n = 0.90 | Sigmoid shape exponent | CameraModels/Sigmoid.m | Controls the CRF curve shape. Value in the official source code. |
| σ = 0.60 | Sigmoid scale parameter | CameraModels/Sigmoid.m | Controls the knee of the sigmoid. Value in the official source code. |
| ratioMax = 7 | Exposure ratio cap | Original LECARM.m | Prevents unbounded brightening of near-zero pixels. Explicitly set in the original code. |
| λ = 0.15, sigma = 2 | LIME illumination solver | limeEstimate.m | These are the parameters passed from LECARM.m to limeEstimate.m in the original code. |

**Implementation note:** The official LECARM source code is used unchanged, from https://github.com/baidut/LECARM. The files are located unchanged in `algorithms/lecarm/`. `run_LECARM.m` calls `LECARM()` directly with the default Sigmoid model.

**References:**
- Ying Z., Li G., Ren Y., Wang R., Wang W. "A New Image Contrast Enhancement Algorithm Using Exposure Fusion Framework." *Computer Analysis of Images and Patterns (CAIP)*, 2017.
- Official code: https://github.com/baidut/LECARM

---

### 9. EnlightenGAN — Unsupervised Deep Light Enhancement

| Property | Value |
|----------|-------|
| Implementation | ONNX inference via arsenyinfo/EnlightenGAN-inference, called from MATLAB |
| Architecture | U-Net generator + global/local discriminators |
| Training | Unsupervised (no paired low/high images required) |
| Category | Deep learning — GAN-based |

EnlightenGAN is an unpaired generative adversarial network for low-light enhancement. It trains without paired low/high-light supervision using a global discriminator (overall brightness) and a self-regularized perceptual loss. A self feature preserving loss encourages the enhanced image to retain the structural content of the input. The generator is a U-Net with attention mechanism.

**Why EnlightenGAN over supervised DL methods:** Supervised methods such as RetinexNet are trained on paired datasets including LOL. Including them as comparisons would give them an unfair structural advantage on the LOL evaluation set. EnlightenGAN is unsupervised — it was not trained on LOL pairs — making the comparison fair. Both the proposed Laguerre method and EnlightenGAN operate without dataset-specific optimization, enabling a clean comparison of "training-free mathematical method vs. training-free neural network."

**Integration:** EnlightenGAN is Python-based. `run_EnlightenGAN.m` writes each image to a temporary file, calls `run_enlightengan.py` via `system()`, reads the result back, and returns it to `main.m` — identical to every other comparison algorithm. Python dependencies (`onnxruntime`, `opencv-python`) are checked and installed automatically when `main.m` starts.

**Source:** The `enlighten_inference/` package (arsenyinfo/EnlightenGAN-inference) is copied into `algorithms/enlightengan/enlighten_inference/`. Nothing was copied from the official VITA-Group/EnlightenGAN repository.

**References:**
- Jiang Y., Gong X., Liu D., Cheng Y., Fang C., Shen X., Yang J., Zhou P., Wang Z. "EnlightenGAN: Deep Light Enhancement without Paired Supervision." *IEEE Transactions on Image Processing*, 30, 2340–2349, 2021.
- arXiv: https://arxiv.org/abs/1906.06972
- Official code: https://github.com/VITA-Group/EnlightenGAN

---

### Algorithm Coverage Summary

| Algorithm | Category | Optimization | Parameters |
|-----------|----------|-------------|-----------|
| **Laguerre (Proposed)** | **Polynomial coefficient convolution** | **Per-image (ν, t) via entropy max.** | **Dynamic** |
| HE | Histogram-based | None | None |
| SSR | Retinex / center-surround | None | σ = 80 (fixed) |
| Gamma | Point-wise power-law | None | γ = 0.4 (fixed) |
| LIME | Illumination map estimation | None | α = 0.15, γ = 0.8 (fixed) |
| Dong | Dehazing-based | None | Method = approxdcp (fixed) |
| BIMEF | Multi-exposure fusion | Per-image k (auto) | μ = 0.5, a = −0.3293, b = 1.1258 |
| NPE | Retinex + bi-log illumination | None | Compiled .p (baidut/BIMEF) |
| LECARM | Camera response model | None | Sigmoid (n=0.90, σ=0.60), ratioMax=7 |
| EnlightenGAN | Unsupervised GAN | Trained (unpaired) | ONNX inference (CPU) |

---

## Evaluation Metrics

All metrics are computed in `metrics/` and reported in each `_metrics.txt` output file.

---

### SSIM — Structural Similarity Index

**Type:** Full-reference (requires ground truth)  
**Range:** [−1, 1] — higher is better; 1 = perfect structural similarity  
**Formula:**

```
SSIM(x, y) = [l(x,y)]^α · [c(x,y)]^β · [s(x,y)]^γ

where:
  l(x,y) = (2μₓμᵧ + C₁) / (μₓ² + μᵧ² + C₁)       -- luminance comparison
  c(x,y) = (2σₓσᵧ + C₂) / (σₓ² + σᵧ² + C₂)         -- contrast comparison
  s(x,y) = (σₓᵧ + C₃) / (σₓσᵧ + C₃)                -- structure comparison
  C₁, C₂, C₃ — small constants for numerical stability
```

SSIM captures **perceptual and structural fidelity** — how well the enhanced image preserves the textures, edges, and spatial structure of the ground truth, as opposed to just measuring pixel-level deviation. It is widely considered the most meaningful quality metric for image enhancement, because a low-MSE image can look visually wrong if it introduces structural distortions.

**Why NIQE is the primary metric in this paper:** The proposed Laguerre method achieves the best NIQE (3.82) among all 10 methods. The narrow ν domain [0.51, 0.99] produces conservative coefficient values — (1−ν)³ ≤ 0.125 for all valid ν — yielding a gentler kernel whose enhanced output closely matches natural image statistics. SSIM ranks third (0.7383), above the trained deep network EnlightenGAN (0.7285).

---

### PSNR — Peak Signal-to-Noise Ratio

**Type:** Full-reference  
**Range:** [0, ∞) dB — higher is better  
**Formula:**

```
PSNR = 10 · log₁₀(MAX² / MSE)

where MAX = 255 for 8-bit images
      MSE  = mean squared error between enhanced and reference
```

PSNR is the most commonly reported metric in the image processing literature and is directly derived from MSE. It measures pixel-level reconstruction fidelity in a logarithmic (decibel) scale. A difference of 3 dB corresponds roughly to a halving/doubling of the error power.

**Limitation:** PSNR treats all pixel errors equally and does not account for perceptual importance. Two images with the same PSNR can look very different to a human observer.

---

### MSE — Mean Squared Error

**Type:** Full-reference  
**Range:** [0, ∞) — lower is better  
**Formula:**

```
MSE = (1 / H·W·C) · Σ (I_enhanced(i,j,c) − I_reference(i,j,c))²
```

MSE measures the average squared pixel-level deviation from the ground truth, summed over all pixels and all color channels. It is the most direct measure of reconstruction error. PSNR is simply a log-scaled function of MSE.

---

### Entropy — Shannon Information Entropy

**Type:** No-reference (does not require ground truth)  
**Range:** [0, 8] bits — higher is better  
**Formula:**

```
H(X) = −Σ p(x) · log₂(p(x))
```

where p(x) is the empirical probability of pixel intensity x from the grayscale histogram (256 bins). Entropy quantifies how uniformly pixel intensities are distributed across the available range. A dark image with most pixels clustered near 0 has very low entropy. An enhanced image with well-spread intensity distribution has high entropy, indicating richer tonal content and detail.

**Important:** Entropy is also used as the **optimization criterion** during parameter search. Maximizing entropy drives the optimizer toward the (ν, t) pair that produces the most informationally rich enhancement. However, entropy alone is not sufficient as a standalone quality metric — it is entirely possible to maximize entropy in a way that over-enhances or distorts the image. This is why SSIM and PSNR (which compare against the ground truth) remain the primary evaluation metrics.

---

### CII — Contrast Improvement Index

**Type:** No-reference  
**Range:** [0, ∞) — higher is better; values > 1 indicate improvement  
**Formula:**

```
CII = mean(I_enhanced) / mean(I_original)
```

CII is a simple measure of how much the mean intensity has been lifted by the enhancement. A CII > 1 means the enhanced image is on average brighter than the input. It is a rough proxy for the degree of enhancement applied.

**Limitation:** CII only measures mean brightness, not contrast distribution or structural quality. An extreme over-brightening would yield a very high CII while being visually degraded.

---

### NIQE — Natural Image Quality Evaluator ⭐ Primary Metric

**Type:** No-reference (blind)
**Range:** [0, ∞) — **lower is better**; lower scores indicate higher perceptual naturalness
**Formula:**

```
NIQE(x) = sqrt( (μ₁ - μ₂)ᵀ · ((Σ₁ + Σ₂)/2)⁻¹ · (μ₁ - μ₂) )

where (μ₁, Σ₁) are the mean and covariance of patch features from the test image,
      (μ₂, Σ₂) are the mean and covariance of the pre-fitted natural image model.
```

NIQE measures how much the local patch statistics of an enhanced image deviate from a multivariate Gaussian model fitted to a large corpus of pristine natural images. It captures statistical regularities that the human visual system associates with natural, artifact-free images. No ground truth reference is required.

Enhancement artifacts that increase the NIQE score: noise amplification, halo ringing around edges, over-saturation, unnatural tonal shifts, and spatially uniform over-brightening. Methods that preserve the statistical structure of the scene score lower.

**Why NIQE complements the other metrics:**

| Metric | Measures | Can be "gamed" by |
|--------|----------|-------------------|
| SSIM | Structural similarity vs. reference | Blurring (reduces visible error but preserves structure) |
| Entropy | Information richness | Adding noise (noise = high entropy) |
| NIQE | Perceptual naturalness (no reference) | — (harder to game; penalizes both noise and over-smoothing) |

Including NIQE alongside SSIM and Entropy provides a more complete picture: an enhancement that maximizes Entropy by introducing noise will be penalized by NIQE, while a method that achieves high SSIM *and* low NIQE is genuinely producing natural, high-quality results.

**Implementation:** MATLAB Image Processing Toolbox built-in `niqe()` function. Applied to the grayscale (luminance) channel of the enhanced image.

**Reference:** Mittal A., Soundararajan R., Bovik A.C. "Making a 'Completely Blind' Image Quality Analyzer." *IEEE Signal Processing Letters*, 20(3), 209–212, 2013.

---

### Metric Summary Table

| Metric | Type | Range | Best | Requires Reference? | Primary Purpose |
|--------|------|-------|------|---------------------|----------------|
| SSIM | Full-reference | [−1, 1] | → 1 | Yes | Structural / perceptual fidelity |
| PSNR | Full-reference | [0, ∞) dB | Higher | Yes | Pixel fidelity (log scale) |
| MSE | Full-reference | [0, ∞) | Lower | Yes | Pixel error magnitude |
| Entropy | No-reference | [0, 8] bits | Higher | No | Information richness |
| CII | No-reference | [0, ∞) | > 1 | No | Brightness improvement ratio |
| NIQE ⭐ | No-reference (blind) | [0, ∞) | Lower | No | Perceptual naturalness |

---

## Output Structure

After running `main.m`, the `target/` directory is populated as follows:

```
target/
├── Laguerre/
│   ├── 1_enhanced.png
│   ├── 1_metrics.txt
│   ├── 23_enhanced.png
│   ├── 23_metrics.txt
│   └── ...
├── HE/
│   ├── 1_enhanced.png
│   ├── 1_metrics.txt
│   └── ...
├── SSR/
├── Gamma/
├── LIME/
├── Dong/
├── BIMEF/
├── NPE/
├── LECARM/
└── EnlightenGAN/
```

### metrics.txt Format — Proposed Method (Laguerre)

```
Image: 1.png
Algorithm: Laguerre
I_mean: 24.92
Status: PROCESSED
Optimal_nu: 0.7823
Optimal_t: -0.1542
Total_evals: 1204
Preset: high_precision
Processing_time_sec: 1.30

--- Metrics ---
Entropy: 6.9528
CII: 5.2215
PSNR: 23.6084
MSE: 283.2989
SSIM: 0.8782
```

**Field explanations:**
- `I_mean` — grayscale mean intensity of the raw input image (used for threshold decision)
- `Status` — `PROCESSED` if enhancement was applied; `SKIPPED` if I_mean ≥ 64
- `Optimal_nu` — best ν found by the two-phase optimization
- `Optimal_t` — best t found by the two-phase optimization
- `Total_evals` — total number of entropy evaluations (grid + all Nelder-Mead iterations)

### metrics.txt Format — When No Ground Truth Exists

```
Image: my_custom_image.png
Algorithm: Laguerre
I_mean: 18.41
Status: PROCESSED
Optimal_nu: 0.9853
Optimal_t: -0.2014
Total_evals: 873

--- Metrics ---
Entropy: 7.1234
CII: 4.8812
PSNR: N/A
MSE: N/A
SSIM: N/A
Note: No matching reference image found in source/high/.
      PSNR, MSE, SSIM require a ground truth reference image.
      Entropy and CII are no-reference metrics and computed above.
```

### metrics.txt Format — Skipped Image

```
Image: 748.png
Algorithm: Laguerre
I_mean: 78.50
Status: SKIPPED
Reason: I_mean (78.50) >= threshold (64).
Note: Low-light is defined as I_mean < 64 (= 128/2, one stop below neutral 128).
```

---

## Configurable Parameters

All tunable parameters are defined at the top of `main.m`:

```matlab
I_MEAN_THRESHOLD = 64;      % 64 = 128/2: one stop below neutral midpoint 128.
                             % Images at or above 64 are SKIPPED by the proposed
                             % method. Comparison algorithms run regardless.

optimization_preset = 'high_precision';
                             % Controls the ENTIRE optimization pipeline:
                             % Phase 1 grid density + Phase 2 Nelder-Mead
                             % tolerances are both resolved inside run_laguerre.m.
                             % Options: 'high_precision' | 'balanced' | 'fast'
                             % Change this one line to switch modes.
```

**Preset summary (all grid + Nelder-Mead parameters resolved inside `run_laguerre.m`):**

| Preset | Phase 1 Grid | Grid Evals | n_cand | NM TolFun/TolX | NM MaxEvals | ~Time/image | Use case |
|--------|-------------|-----------|--------|----------------|-------------|-------------|----------|
| `high_precision` | nu=0.03, t=0.05 (~663 pts) | ~663 | 6 | 1e-6 | 1100 | ~1.30 s | Published results |
| `balanced` | nu=0.05, t=0.08 (~240 pts) | ~240 | 4 | 1e-4 | 400 | ~0.58 s | Development |
| `fast` | nu=0.10, t=0.20 (~50 pts) | ~50 | 2 | 1e-2 | 100 | ~0.16 s | Real-time / live video |

All results in the paper were produced with `high_precision`. The `balanced` and `fast` presets demonstrate the framework's practical scalability across deployment contexts.

---

## Implementation Details — Master Kernel Formulation

The proposed method constructs 8 directional 3×3 kernels (h₁…h₈) from the coefficient triplet (a₁, a₂, a₃) and applies each to the input image independently. Due to the **linearity (distributive property) of the convolution operator**, these 8 passes can be mathematically collapsed into a single convolution with a pre-averaged **Master Kernel**:

$$\text{Output} = I * \left( \frac{1}{8} \sum_{i=1}^{8} h_i \right) = K_{\text{master}}$$

Substituting the known kernel entries:

```
Master Kernel:
[ a1+a3,  a1+a3,  a1+a3 ]
[ a1+a3,   8·a2,  a1+a3 ]
[ a1+a3,  a1+a3,  a1+a3 ]
```

Since a₁ = 1 (fixed), this simplifies to:

```
[ 1+a3,  1+a3,  1+a3 ]
[ 1+a3,  8·a2,  1+a3 ]
[ 1+a3,  1+a3,  1+a3 ]
```

This reformulation reduces the per-iteration convolution count from **8C to C** (where C is the number of color channels), yielding an **8× reduction in convolution overhead** with zero loss in numerical precision. This is not an approximation — it is an exact algebraic identity, and the implementation in `apply_convolution.m` uses the Master Kernel directly.

> This property can be stated in the paper as: *"Due to the linearity of the convolution operator, the eight directional kernels can be pre-averaged into a single representative kernel K_master = (1/8)·Σhᵢ without any loss of numerical precision. This reformulation reduces per-iteration computational cost from 8C to C convolutions, significantly accelerating the Nelder-Mead optimization phase."*

---

## Spatial Precomputation — Mathematical Decoupling

The Master Kernel decomposes into two parameter-independent components:

```
I * K_master  =  a₂ · img_d  +  (1+a₃)/8 · I_edge

where:
  img_d  = double(img_low)             — identity component, computed once
  I_edge = conv(img_d, H_edge)         — 8-neighbor sum, computed once
  H_edge = [1,1,1; 1,0,1; 1,1,1]      — static 3×3 kernel
```

This is an **exact algebraic identity**. Since `I_edge` depends only on the image — not on (ν, t) — it is computed once before all optimization loops. Each of the ~~663 grid evaluations (high_precision) reduces to two scalar multiplications and one element-wise addition — no `conv2` inside the loop.

**Complexity:** O(W·H·K²) precomputation + O(N·W·H) loop = O(W·H·K²) + O(N·W·H). The K²=9 sliding-window factor is paid once, not N times.

The fast evaluation is implemented in `_helpers/fast_neg_entropy.m`. `apply_convolution.m` is called once at the end for the final output.

---

## Optimization Presets

The **entire optimization pipeline** is controlled by a single `optimization_preset` string in `main.m`. All Phase 1 grid parameters and Phase 2 Nelder-Mead tolerances are resolved inside `run_laguerre.m`. No other edits are needed.

Spatial precomputation (I_edge computed once before all loops) makes finer grids possible at the same wall-clock time:

| Preset | nu_step | t_step | Grid pts | n_cand | TolFun/TolX | NM MaxEvals | ~Time/img | Use case |
|--------|---------|--------|---------|--------|-------------|------------|-----------|----------|
| **`high_precision`** | 0.03 | 0.05 | ~663 | 6 | 1e-6 | 1100 | ~1–2 s | Published results |
| **`balanced`** | 0.05 | 0.08 | ~240 | 4 | 1e-4 | 400 | ~0.5–1 s | Development |
| **`fast`** | 0.100 | 0.20 | ~50 | 2 | 1e-2 | 100 | ~0.16 s | Real-time / live video |

Switching presets: change one line in `main.m`:

```matlab
optimization_preset = 'high_precision';  % Options: 'high_precision' | 'balanced' | 'fast'
```

The preset is passed as a string to `run_laguerre`, which resolves all parameters including n_candidates. n_candidates is set to 6/4/2 to ensure adequate coverage of the narrow ν domain [0.51, 0.99].

```matlab
% run_laguerre.m — preset resolution:
switch lower(preset)
    case 'high_precision'
        nu_step=0.03; t_step=0.05; n_candidates=6;
        nm_TolFun=1e-6;  nm_TolX=1e-6;  nm_MaxFunEvals=1100;
    case 'balanced'
        nu_step=0.05; t_step=0.08; n_candidates=4;
        nm_TolFun=1e-4;  nm_TolX=1e-4;  nm_MaxFunEvals=400;
    case 'fast'
        nu_step=0.10; t_step=0.20; n_candidates=2;
        nm_TolFun=1e-2;  nm_TolX=1e-2;  nm_MaxFunEvals=100;
end
```
---

## Scalability — High-Resolution Parameter Estimation

The current implementation runs the full two-phase optimization (grid search + Nelder-Mead) on the original image at full resolution. For the LOL dataset (400×600), this is computationally tractable. However, for **high-resolution inputs (4K, 8K, or medical imaging)**, the per-iteration cost scales linearly with pixel count, making full-resolution optimization expensive.

### Thumbnail-Based Estimation

Since Shannon entropy is a **global statistical measure** (computed from the image histogram, not local spatial structure), the entropy landscape over the (ν, t) parameter space remains consistent across scales. This means the optimal (ν, t) found on a downsampled thumbnail will closely match the optimal found on the full-resolution image.

**Proposed strategy for high-resolution images:**

1. Downsample the input to 1/4 or 1/8 of its original resolution (e.g., `imresize(img, 0.25)`)
2. Run the full two-phase (ν, t) optimization on the thumbnail
3. Apply the resulting optimal (ν, t) directly to the full-resolution image

```matlab
% Example: Thumbnail-based optimization for high-resolution inputs
scale = 0.25;  % 1/4 resolution → 16× fewer pixels per convolution
img_thumb = imresize(img_low, scale);

% Run optimization on thumbnail (fast)
[~, best_nu, best_t, ~] = run_laguerre(img_thumb, optimization_preset);

% Apply optimal parameters to full-resolution image
[a2, a3, ~] = laguerre_coefficients(best_nu, best_t);
enhanced_fullres = apply_convolution(img_low, a2, a3);  % Single pass, full resolution
```

**Expected speedup:** Each convolution operation scales linearly with pixel count. At 1/4 scale, each evaluation is ~16× faster. Combined with the Master Kernel formulation, the total optimization speedup for a 4K image approaches **100×** relative to the naive 8-pass full-resolution baseline.

| Image Resolution | Thumbnail Scale | Optimization Speedup | Final Enhancement |
|-----------------|-----------------|---------------------|-------------------|
| 400 × 600 (LOL) | 1/1 (full) | 1× | Full resolution |
| 1920 × 1080 (FHD) | 1/4 | ~16× | Full resolution |
| 3840 × 2160 (4K) | 1/4 | ~64× | Full resolution |
| 3840 × 2160 (4K) | 1/8 | ~256× | Full resolution |

> The entropy landscape consistency across scales is an empirical observation supported by the global (histogram-based) nature of Shannon entropy. For images with extreme local tonal variation, a 1/2 scale may be preferable to 1/4 to ensure landscape fidelity.


---

## References

**LIME:**
> Guo X., Li Y., Ling H. "LIME: Low-Light Image Enhancement via Illumination Map Estimation." *IEEE Transactions on Image Processing*, 26(2), 982–993, 2017.  
> arXiv: https://arxiv.org/abs/1605.05034  
> IEEE: https://ieeexplore.ieee.org/document/7782813

**LIME reference implementation (used for validation):**
> estija. *LIME — Low-Light Image Enhancement*. GitHub, 2020.  
> https://github.com/estija/LIME

**LOL Dataset:**
> Chen Wei, Wenjing Wang, Wenhan Yang, Jiaying Liu. "Deep Retinex Decomposition for Low-Light Enhancement." *British Machine Vision Conference (BMVC)*, 2018.  
> arXiv: https://arxiv.org/abs/1808.04560  
> Dataset: https://daooshee.github.io/BMVC2018website/

**SSR (Single-Scale Retinex):**
> Jobson D.J., Rahman Z., Woodell G.A. "Properties and Performance of a Center/Surround Retinex." *IEEE Transactions on Image Processing*, 6(3), 451–462, 1997.

**Dong (Inverted Dehazing):**
> Dong X., Pang Y., Wen J. "Fast Efficient Algorithm for Enhancement of Low Lighting Video." *ACM SIGGRAPH Posters*, 2010.

**BIMEF (Bio-Inspired Multi-Exposure Fusion):**
> Ying Z., Li G., Gao W. "A Bio-Inspired Multi-Exposure Fusion Framework for Low-light Image Enhancement." *IEEE Transactions on Cybernetics*, 50(6), 2400–2414, 2020.  
> arXiv: https://arxiv.org/abs/1711.00591  
> Official source code: https://github.com/baidut/BIMEF (`lowlight/BIMEF.m`)  
> Official files `BIMEF.m` and `BIMEF.p` copied unchanged from the repo into `algorithms/bimef/`.


**NIQE (Natural Image Quality Evaluator):**
> Mittal A., Soundararajan R., Bovik A.C. "Making a 'Completely Blind' Image Quality Analyzer." *IEEE Signal Processing Letters*, 20(3), 209–212, 2013.

**NPE (Naturalness Preserved Enhancement):**
> Wang S., Zheng J., Hu H.-M., Li B. "Naturalness Preserved Enhancement Algorithm for Non-Uniform Illumination Images." *IEEE Transactions on Image Processing*, 22(9), 3538–3548, 2013.  
> DOI: 10.1109/TIP.2013.2261309  
> Original MATLAB code: https://shuhangwang.wordpress.com/2015/12/14/naturalness-preserved-enhancement-algorithm-for-non-uniform-illumination-images/

**LECARM (Camera Response Model Enhancement):**
> Ying Z., Li G., Ren Y., Wang R., Wang W. "A New Image Contrast Enhancement Algorithm Using Exposure Fusion Framework." *Computer Analysis of Images and Patterns (CAIP)*, 2017.  
> Official code: https://github.com/baidut/LECARM  
> Official source code used unchanged. Located at `algorithms/lecarm/`.

**EnlightenGAN (Unsupervised Deep Enhancement):**
> Jiang Y., Gong X., Liu D., Cheng Y., Fang C., Shen X., Yang J., Zhou P., Wang Z. "EnlightenGAN: Deep Light Enhancement without Paired Supervision." *IEEE Transactions on Image Processing*, 30, 2340–2349, 2021.  
> arXiv: https://arxiv.org/abs/1906.06972  
> Official code: https://github.com/VITA-Group/EnlightenGAN  
> Note: ONNX inference via arsenyinfo/EnlightenGAN-inference, called from MATLAB via system(). See `algorithms/enlightengan/`.

---

*This repository is provided for academic research purposes.*