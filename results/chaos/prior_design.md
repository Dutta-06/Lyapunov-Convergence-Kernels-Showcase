# Proposition D‴.9: the leak toward a measure-valued prior, and the design of the window (`exp_prior_design.py`)

The three-bump instance of `exp_chaos_learning.py` (n = 1, a_max = 4.0, c_max = 3.0, s ∈ [0.3, 2.0], G = diag(1.0, 0.25, 0.25), (A, C, S) = [(1.0, -1.5, 0.5), (-0.7, 0.0, 0.4), (0.8, 1.5, 0.5)], x_m = 2 sin t, ρ on 256 times) at σ₀ = 0.15σ_crit = 0.00707, with the nearest-atom leak −σ₀(ϑ − ϑ⁰_{j(ϑ)}) toward a prior of three atoms placed at the exact representation (3A_k, C_k, S_k) and misplaced from it; the σ-modification (one atom at 0) for comparison. ϱ′ = 0.1; the floors are predicted for m = 64 against M = 2048.

## 1. Design table: the stationary three-atom measure under each prior

| prior | fit error of μ*_ν | atoms (a, c, s) | κ_R at the atoms (max) | κ_R over N_ϱ′ | margin κ = σ₀ − κ_R(N_ϱ′) | cell margin (min gap between the two nearest prior atoms; > 2ϱ′ needed) | ‖S_k‖ (whitened) | predicted E D_∞ (m = 64) | predicted E‖f̂₆₄ − f̂_M‖² |
|---|---|---|---|---|---|---|---|---|---|
| σ-modification, ϑ⁰ = 0 | 0.2439 | (2.450, -1.416, 0.829), (-2.288, 0.012, 0.701), (2.048, 1.343, 0.881) | +0.00411 | +0.00512 | +0.00196 | inf | 8.38, 4.66, 8.32 | 2.010e-01 | 4.287e-04 |
| mixture prior at the exact representation | 0.0000 | (3.000, -1.500, 0.500), (-2.100, 0.000, 0.400), (2.400, 1.500, 0.500) | +0.00000 | +0.00000 | +0.00707 | 6.26 | 13.01, 6.18, 8.91 | 3.227e-01 | 9.334e-04 |
| centres shifted by +0.15 | 0.0098 | (3.004, -1.495, 0.499), (-2.099, 0.004, 0.400), (2.394, 1.510, 0.501) | +0.00140 | +0.00157 | +0.00550 | 5.73 | 12.99, 6.18, 8.92 | 3.221e-01 | 9.397e-04 |
| centres shifted by +0.3 | 0.0200 | (3.007, -1.490, 0.498), (-2.097, 0.007, 0.400), (2.386, 1.521, 0.502) | +0.00298 | +0.00333 | +0.00374 | 5.17 | 12.97, 6.18, 8.92 | 3.216e-01 | 9.446e-04 |
| centres shifted by +0.45 | 0.0311 | (3.010, -1.485, 0.498), (-2.095, 0.010, 0.399), (2.376, 1.534, 0.504) | +0.00480 | +0.00534 | +0.00173 | 4.43 | 12.96, 6.18, 8.92 | 3.211e-01 | 9.482e-04 |
| centres shifted by +0.6 | 0.0436 | (3.012, -1.481, 0.497), (-2.092, 0.013, 0.399), (2.363, 1.550, 0.507) | +0.00698 | +0.00770 | -0.00063 | 3.64 | 12.94, 6.19, 8.92 | 3.206e-01 | 9.511e-04 |
| amplitudes ×0.5 | 0.0921 | (2.662, -1.524, 0.525), (-1.857, 0.000, 0.401), (2.201, 1.520, 0.512) | -0.00039 | -0.00033 | +0.00740 | 3.90 | 9.76, 5.01, 7.47 | 1.991e-01 | 7.106e-04 |
| amplitudes ×0.7 | 0.0624 | (2.762, -1.516, 0.518), (-1.946, -0.000, 0.401), (2.269, 1.513, 0.508) | -0.00028 | -0.00023 | +0.00731 | 4.74 | 10.59, 5.40, 7.92 | 2.303e-01 | 7.657e-04 |
| amplitudes ×1.2 | 0.0861 | (3.408, -1.479, 0.467), (-2.222, 0.002, 0.400), (2.530, 1.488, 0.492) | +0.03684 | +0.03875 | -0.03167 | 5.77 | 17.80, 6.96, 10.11 | 5.242e-01 | 1.802e-03 |
| widths ×0.7 | 0.2195 | (3.187, -1.531, 0.371), (-1.032, 0.137, 0.352), (2.629, 1.524, 0.364) | +0.03086 | +0.03316 | -0.02609 | 1.22 | 13.00, 2.82, 9.77 | 3.062e-01 | 1.716e-03 |
| widths ×1.5 | 0.0581 | (2.969, -1.420, 0.668), (-2.427, -0.022, 0.598), (2.360, 1.420, 0.688) | +0.00113 | +0.00126 | +0.00581 | 5.50 | 11.13, 7.19, 8.50 | 2.932e-01 | 7.459e-04 |
| widths ×2 | 0.1190 | (2.990, -1.409, 0.767), (-2.672, -0.028, 0.686), (2.369, 1.415, 0.819) | +0.00294 | +0.00306 | +0.00401 | 4.96 | 10.39, 7.27, 8.71 | 3.008e-01 | 6.148e-04 |

Reading of the table. The matching prior makes the exact representation stationary with zero residual (fit error 1.2e-16), hence κ_R = 0 and the maximal margin κ = σ₀ = 0.00707, 3.6 times the σ-modification's 0.00196 (relaxation time 1/κ = 141 against 511 slow units); the σ-modification's bias (fit error 0.244: amplitudes 2.45, -2.29, 2.05 against 3A_k = 3.0, -2.1, 2.4, widths 0.83, 0.70, 0.88 against 0.5, 0.4, 0.5) is removed. The floors move the other way: the weight sensitivities ‖S_k‖ are 13.01, 6.18, 8.91 against 8.38, 4.66, 8.32, the predicted parameter-level floor E D_∞(m = 64) is 3.227e-01 against 2.010e-01 (1.61×) and the function-level floor 9.334e-04 against 4.287e-04 (2.18×): at a stationary point under a leak the fitted configuration does not stay on the zero-residual manifold when the weights change (the leak pulls the amplitudes back), and the response of both the atoms and the fitted function to the weights grows with the amplitudes, which the σ-modification had biased down — bias against variance. Misplacing the prior brings the residual curvature back: the window closes (margin ≤ 0) for centres shifted by +0.6; amplitudes ×1.2; widths ×0.7; the largest margin in the table is 0.00740 (amplitudes ×0.5).

## 2. Admissible weights: the splitting margin σ₀ − max_k κ_R of the replicated weighted stationary configuration Θ*(w) (Proposition D‴.5(i), (iv)) under three priors

| weights w | σ-modification, ϑ⁰ = 0 | mixture prior at the exact representation | amplitudes ×0.7 |
|---|---|---|---|
| (0.4375, 0.3125, 0.2500) | +0.00257 (κ_R at the atoms +0.0045, -0.0030, -0.0011) | -0.00544 (κ_R at the atoms +0.0125, +0.0005, -0.0003) | +0.00733 (κ_R at the atoms -0.0003, -0.0003, -0.0010) |
| (0.5625, 0.2500, 0.1875) | -0.00219 (κ_R at the atoms +0.0093, -0.0056, -0.0057) | -0.00579 (κ_R at the atoms +0.0129, +0.0003, -0.0020) | +0.00570 (κ_R at the atoms +0.0014, -0.0004, -0.0027) |
| (0.6250, 0.1875, 0.1875) | -0.00377 (κ_R at the atoms +0.0108, -0.0075, -0.0068) | -0.00415 (κ_R at the atoms +0.0112, +0.0002, -0.0030) | +0.00536 (κ_R at the atoms +0.0017, -0.0004, -0.0035) |
| (0.5000, 0.3000, 0.2000) | -0.00062 (κ_R at the atoms +0.0077, -0.0039, -0.0039) | -0.00653 (κ_R at the atoms +0.0136, +0.0005, -0.0011) | +0.00663 (κ_R at the atoms +0.0004, -0.0003, -0.0019) |

Reading: the sign of the residual at a cluster decides the sign of its splitting curvature. A cluster that overshoots the plant (too much weight, or a prior with too large an amplitude) has a residual of the sign opposite to its kernel at the centre, where ∂²_{cc}Φ̃ = −aφ/s², so R > 0 and the cluster can split; one that undershoots has R < 0 and is stabilised. The matching prior puts the stationary configuration exactly on the plant, so any excess weight overshoots: its admissible set is the smallest of the three; the σ-modification undershoots the amplitudes and tolerates (7, 5, 4)/16 but not (9, 4, 3)/16; the shrunk prior (amplitudes ×0.7) undershoots at every cluster and keeps all four weight vectors admissible with margins at or above σ₀ — a shrinkage prior enlarges the admissible set, lowers both floors and keeps the window's margin maximal, at the price of a fit error of 0.06.

Splitting margins at the realised cluster weights of the matching-prior coupled runs of section 3: m = 16, seed 0: -0.00052 (w = (0.3750, 0.3125, 0.3125)); m = 64, seed 0: +0.00493 (w = (0.2969, 0.3438, 0.3594)); m = 256, seed 0: +0.00422 (w = (0.3086, 0.3125, 0.3789)); m = 16, seed 1: +0.00056 (w = (0.3750, 0.2500, 0.3750)); m = 64, seed 1: -0.00296 (w = (0.4062, 0.2656, 0.3281)); m = 256, seed 1: +0.00569 (w = (0.3242, 0.3242, 0.3516)); m = 16, seed 2: +0.00056 (w = (0.3750, 0.2500, 0.3750)); m = 64, seed 2: +0.00390 (w = (0.3125, 0.2969, 0.3906)); m = 256, seed 2: +0.00609 (w = (0.3164, 0.3398, 0.3438)).

## 3. Coupled runs with the matching prior (m = 16, 64, 256 against M = 2048; warm start = the mixture of Gaussians of width 0.02 around the exact representation; 300 slow units = 2.1 relaxation times; 3 seeds)

Hypothesis along the run (κ_R over the spheres of radius ϱ′ around 256 reference particles, with the stationary residual r* = 0 and with the reference's own residual): max_s κ_R(r*) = 0.00000, max_s κ_R(r_ref) = 0.00488 (σ₀ = 0.00707); the reference's rms drift 3.6e-03 → 3.0e-05, fit error 0.0294 → 0.0082.

| m | max D_m on (0, 37.5] | max D_m on (37.5, 75] | max D_m on (75, 150] | max D_m on (150, 300] | mean D_m on (150, 300] | mean ‖f̂_Θ − f̂_ref‖ on the last window | predicted E D_∞ | predicted E‖f̂_m − f̂_M‖² |
|---|---|---|---|---|---|---|---|---|
| 16 | 1.143e-01 ± 1.2e-02 | 1.931e-01 ± 1.6e-02 | 2.391e-01 ± 1.6e-02 | 2.500e-01 ± 1.7e-02 | 2.467e-01 ± 1.7e-02 | 2.750e-02 ± 1.6e-03 | 1.322e+00 | 3.824e-03 |
| 64 | 9.537e-02 ± 5.6e-02 | 1.574e-01 ± 9.7e-02 | 1.902e-01 ± 1.2e-01 | 1.971e-01 ± 1.2e-01 | 1.951e-01 ± 1.2e-01 | 2.048e-02 ± 5.6e-03 | 3.227e-01 | 9.334e-04 |
| 256 | 9.328e-03 ± 6.1e-03 | 1.402e-02 ± 8.6e-03 | 1.661e-02 ± 9.7e-03 | 1.732e-02 ± 1.0e-02 | 1.711e-02 ± 9.9e-03 | 6.110e-03 ± 2.3e-03 | 7.287e-02 | 2.108e-04 |

Slope of the last-window maximum of D_m against m: -1.23 ± 0.40 (−1 for the mean square); of the function-level distance: -0.63 ± 0.21 (−0.5). Ratios of the last to the first window maxima: 2.19, 2.07, 1.86; last to the one before: 1.05, 1.04, 1.04.

Inadmissible realised weights (saddles): m = 16, seed 0, m = 64, seed 1 — their plateaus are saddles' and would be left on a longer horizon (Proposition D‴.5(iv)).

Per seed at s = 300, predicted from the realised cluster weights → measured (parameter level Σ_k w^m_k‖S̃_k(w^m − w^M)‖², function level ‖F(w^m − w^M)‖²_{L²(ρ)}): m = 16, seed 0: D 2.380e-01 → 2.163e-01; ‖f̂_Θ − f̂_ref‖² 7.172e-04 → 5.700e-04; m = 16, seed 1: D 2.645e-01 → 2.649e-01; ‖f̂_Θ − f̂_ref‖² 7.736e-04 → 8.364e-04; m = 16, seed 2: D 2.686e-01 → 2.688e-01; ‖f̂_Θ − f̂_ref‖² 7.214e-04 → 8.085e-04; m = 64, seed 0: D 2.900e-02 → 3.229e-02; ‖f̂_Θ − f̂_ref‖² 1.035e-04 → 1.750e-04; m = 64, seed 1: D 5.399e-01 → 4.348e-01; ‖f̂_Θ − f̂_ref‖² 1.558e-03 → 9.534e-04; m = 64, seed 2: D 1.495e-01 → 1.243e-01; ‖f̂_Θ − f̂_ref‖² 2.850e-04 → 2.641e-04; m = 256, seed 0: D 4.371e-02 → 3.563e-02; ‖f̂_Θ − f̂_ref‖² 8.506e-05 → 8.034e-05; m = 256, seed 1: D 1.078e-03 → 1.033e-03; ‖f̂_Θ − f̂_ref‖² 2.444e-06 → 2.590e-06; m = 256, seed 2: D 1.472e-02 → 1.528e-02; ‖f̂_Θ − f̂_ref‖² 4.612e-05 → 5.614e-05. Ratios measured/predicted: parameter level 0.91, 1.00, 1.00, 1.11, 0.81, 0.83, 0.82, 0.96, 1.04; function level 0.79, 1.08, 1.12, 1.69, 0.61, 0.93, 0.94, 1.06, 1.22.

## 4. The function-level law for the σ-modification against `exp_chaos_learning.py`'s warm runs (M = 2048, last window)

| m | predicted RMS (1/m − 1/M)^{1/2}(tr FC̃Fᵀ/N)^{1/2} | measured mean ‖f̂_Θ − f̂_ref‖ on (450, 900] | ratio |
|---|---|---|---|
| 16 | 4.191e-02 | 3.073e-02 ± 9.7e-03 | 0.73 |
| 64 | 2.071e-02 | 1.542e-02 ± 3.3e-03 | 0.74 |
| 256 | 9.839e-03 | 4.674e-03 ± 1.2e-03 | 0.48 |

The measured value is a mean of norms over the seeds (below the RMS by Jensen's inequality), and the prediction is the leading term in the weight fluctuation.

Numbers are produced by `experiments/exp_prior_design.py`; nothing is edited by hand.
