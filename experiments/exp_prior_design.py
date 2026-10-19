"""
Proposition D‴.9: the leak toward a measure-valued prior, and the design of the window
======================================================================================

The averaged slow loop of Theorem D‴ with the nearest-atom leak toward a prior measure ν = (1/3)Σ_jδ_{ϑ⁰_j} (PARADIGM.md §5d,
Proposition D‴.9), on the three-bump instance of `exp_chaos_learning.py` at the same leak σ₀ = 0.15σ_crit.

1. Design table: for the σ-modification (ϑ⁰ = 0) and for mixture priors placed at the exact representation and misplaced from it
   (centres shifted, amplitudes scaled, widths scaled), the stationary three-atom measure μ*_ν (Newton from the exact
   representation), its fit error, κ_R at its atoms and over the spheres of radius ϱ′ = 0.1 (hypothesis (H) and the window's
   margin κ = σ₀ − κ_R), the Voronoi cell margin (the 'assignment locally constant' hypothesis), the weight sensitivities ‖S_k‖
   and the predicted stationary floors at parameter level (Proposition D‴.5) and at function level (the law E‖f̂_m − f̂_M‖² ≈
   (1/m − 1/M) tr(FC̃Fᵀ)/N) for m = 64 against M = 2048.
2. Coupled runs with the matching prior (m = 16, 64, 256 against M = 2048, warm start = the jittered mixture around the exact
   representation, 300 slow units = 2.1 relaxation times of the maximal margin κ = σ₀): window maxima of D_m and of the
   function-level distance, their m-laws, and the per-seed predictions of both laws from the realised cluster weights.
3. The function-level law against the σ-modification's measured distances of `exp_chaos_learning.py` (read from its raw data when
   present).

Output: results/chaos/prior_design.md and prior_design_raw.npz (CLW_WORKERS, PD_SEEDS, PD_S_END, PD_M_REF to change the pool).
"""
import os
import sys
import time
try:
    sys.stdout.reconfigure(encoding='utf-8')
except Exception:
    pass
import numpy as np

sys.path.insert(0, os.path.abspath(os.path.join(os.path.dirname(__file__), '..')))
from src.core import langevin as L
from src.core import chaos_learning as CL
from src.core import prior_design as PD

OUT = os.path.join(os.path.dirname(__file__), '..', 'results', 'chaos')
NET_KW = dict(a_max=4.0, c_max=3.0, s_min=0.3, s_max=2.0)
G = np.array([1.0, 0.25, 0.25])
BUMPS = [(1.0, -1.5, 0.5), (-0.7, 0.0, 0.4), (0.8, 1.5, 0.5)]
PER = 2 * np.pi
N_Q = 256
SIGMA_CRIT = 0.047162567584665846                                       # Proposition K on this instance (exp_chaos_learning.py, asserted in the tests)
SIGMA0 = 0.15 * SIGMA_CRIT
M_REF = int(os.environ.get('PD_M_REF', 2048))
MS = (16, 64, 256)
S_END, DT_S, REC = float(os.environ.get('PD_S_END', 300.0)), 0.02, 50
WINDOWS = tuple((a * S_END / 300.0, b * S_END / 300.0) for a, b in ((0.0, 37.5), (37.5, 75.0), (75.0, 150.0), (150.0, 300.0)))
RHO_PRIME = 0.1
JITTER = 0.02
N_SEEDS = int(os.environ.get('PD_SEEDS', 3))
N_WORKERS = int(os.environ.get('CLW_WORKERS', 3))
W_BAR = np.ones(3) / 3


def f_vec(X):
    return sum(A * np.exp(-(X - C) ** 2 / (2 * S ** 2)) for A, C, S in BUMPS)


def x_ref(t):
    return np.array([2.0 * np.sin(t)])


def make_net():
    return L.SaturatedLiftedNetwork(1, **NET_KW)


def exact_representation(net):
    return net.unconstrained(np.array([[3 * A] for A, C, S in BUMPS]), np.array([[C] for A, C, S in BUMPS]), np.array([S for A, C, S in BUMPS]))


def prior_from(net, a_scale=1.0, c_shift=0.0, s_scale=1.0):
    return net.unconstrained(np.array([[3 * A * a_scale] for A, C, S in BUMPS]), np.array([[C + c_shift] for A, C, S in BUMPS]),
                             np.array([S * s_scale for A, C, S in BUMPS]))


CASES = [("σ-modification, ϑ⁰ = 0", dict(single=True)),
         ("mixture prior at the exact representation", dict()),
         ("centres shifted by +0.15", dict(c_shift=0.15)), ("centres shifted by +0.3", dict(c_shift=0.3)),
         ("centres shifted by +0.45", dict(c_shift=0.45)), ("centres shifted by +0.6", dict(c_shift=0.6)),
         ("amplitudes ×0.5", dict(a_scale=0.5)), ("amplitudes ×0.7", dict(a_scale=0.7)), ("amplitudes ×1.2", dict(a_scale=1.2)),
         ("widths ×0.7", dict(s_scale=0.7)), ("widths ×1.5", dict(s_scale=1.5)), ("widths ×2", dict(s_scale=2.0))]


def make_loop(net, case):
    if case.get('single'):
        return PD.MixturePriorLoop(net, f_vec, x_ref, PER, G, SIGMA0, np.zeros((1, 3)), n_quad=N_Q)
    return PD.MixturePriorLoop(net, f_vec, x_ref, PER, G, SIGMA0, prior_from(net, **case), n_quad=N_Q)


def design_row(name, case):
    net = make_net()
    loop = make_loop(net, case)
    exact = exact_representation(net)
    atoms, res = PD.weighted_stationary_atoms_prior(loop, W_BAR, exact)
    r = loop.residual(atoms)
    k_at = loop.kappa_R(r, atoms)
    k_nb = loop.kappa_R_neighbourhood(r, atoms, RHO_PRIME, n_dirs=200, radii=(1.0, 0.5))
    S = PD.weight_sensitivity_prior(loop, W_BAR, atoms)
    F = PD.function_sensitivity(loop, W_BAR, atoms, S)
    a, c, s = net.physical(atoms)
    return dict(name=name, case=case, atoms=atoms, res=res, fit=loop.fit_error(atoms), a=a[:, 0], c=c[:, 0], s=s, k_at=k_at, k_nb=k_nb,
                margin=SIGMA0 - k_nb, cell=float(loop.cell_margin(atoms).min()) if not case.get('single') else float('inf'),
                S_norm=[float(np.linalg.norm(S[k] / np.sqrt(G)[:, None])) for k in range(3)], S=S, F=F,
                D64=CL.predicted_stationary_D(S, W_BAR, 64, M_REF, G), f64=PD.predicted_stationary_function_D(F, W_BAR, 64, M_REF))


# ---------------------------------------------------------------------------- coupled runs with the matching prior
def coupled_run(seed):
    net = make_net()
    exact = exact_representation(net)
    loop = make_loop(net, dict())
    rng = np.random.default_rng(seed)
    Th_all = CL.mixture_start(exact, M_REF, rng, JITTER, G)
    rec = loop.coupled_run(Th_all, MS, S_END, DT_S, rec_every=REC, rho_nbhd=RHO_PRIME, n_dirs=24, rng=rng, nb_rows_max=256, r_fixed=loop.residual(exact))
    labM, wM = CL.cluster_weights(rec['final'][M_REF], exact, G)
    out = dict(seed=seed, s=rec['s'], fit=rec['fit'], drift_rms=rec['drift_rms'], kR_ref_nbhd=rec['kR_ref_nbhd'], kR_ref_nbhd_fixed=rec['kR_ref_nbhd_fixed'],
               resid_dev_L1=rec['resid_dev_L1'], w_ref=wM)
    for m in MS:
        lab, wm = CL.cluster_weights(rec['final'][m], exact, G)
        out[f'D{m}'] = rec['D'][m]; out[f'h{m}'] = rec['hnorm_mf'][m]; out[f'devfinal{m}'] = rec['dev_final'][m]; out[f'w{m}'] = wm
    return out


def window_stats(s, D, windows):
    return [float(D[(s > a) & (s <= b)].max()) for a, b in windows] + [float(D[(s > windows[-1][0]) & (s <= windows[-1][1])].mean())]


def slope_se(vals_by_m):
    ms = sorted(vals_by_m); n = len(vals_by_m[ms[0]])
    sl = [np.polyfit(np.log(ms), np.log([vals_by_m[m][i] for m in ms]), 1)[0] for i in range(n)]
    return float(np.mean(sl)), (float(np.std(sl, ddof=1) / np.sqrt(n)) if n > 1 else float('nan'))


def mean_se(v):
    v = np.asarray(v, float)
    return float(v.mean()), (float(v.std(ddof=1) / np.sqrt(len(v))) if len(v) > 1 else float('nan'))


def fmt(x, se=None, p=3):
    return f"{x:.{p}e}" if se is None or not np.isfinite(se) else f"{x:.{p}e} ± {se:.1e}"


def main():
    import multiprocessing as mp
    os.makedirs(OUT, exist_ok=True)
    t0 = time.time()
    rows = [design_row(n, c) for n, c in CASES]
    with mp.Pool(N_WORKERS) as pool:
        runs = pool.map(coupled_run, range(N_SEEDS))
    net = make_net()
    exact = exact_representation(net)
    mix = make_loop(net, dict())
    row_m = rows[1]; row_s = rows[0]
    lines = ["# Proposition D‴.9: the leak toward a measure-valued prior, and the design of the window (`exp_prior_design.py`)", "",
             f"The three-bump instance of `exp_chaos_learning.py` (n = 1, a_max = {NET_KW['a_max']}, c_max = {NET_KW['c_max']}, s ∈ [{NET_KW['s_min']}, {NET_KW['s_max']}], G = diag{tuple(float(g) for g in G)}, "
             f"(A, C, S) = {BUMPS}, x_m = 2 sin t, ρ on {N_Q} times) at σ₀ = 0.15σ_crit = {SIGMA0:.5f}, with the nearest-atom leak −σ₀(ϑ − ϑ⁰_{{j(ϑ)}}) toward a prior of three atoms "
             f"placed at the exact representation (3A_k, C_k, S_k) and misplaced from it; the σ-modification (one atom at 0) for comparison. ϱ′ = {RHO_PRIME:g}; the floors are "
             f"predicted for m = 64 against M = {M_REF}.", "",
             "## 1. Design table: the stationary three-atom measure under each prior", "",
             "| prior | fit error of μ*_ν | atoms (a, c, s) | κ_R at the atoms (max) | κ_R over N_ϱ′ | margin κ = σ₀ − κ_R(N_ϱ′) | cell margin (min gap between the two nearest prior atoms; > 2ϱ′ needed) | ‖S_k‖ (whitened) | predicted E D_∞ (m = 64) | predicted E‖f̂₆₄ − f̂_M‖² |",
             "|---|---|---|---|---|---|---|---|---|---|"]
    for r in rows:
        lines.append(f"| {r['name']} | {r['fit']:.4f} | " + ", ".join(f"({r['a'][k]:.3f}, {r['c'][k]:.3f}, {r['s'][k]:.3f})" for k in range(3))
                     + f" | {r['k_at'].max():+.5f} | {r['k_nb']:+.5f} | {r['margin']:+.5f} | {r['cell']:.2f} | " + ", ".join(f"{x:.2f}" for x in r['S_norm'])
                     + f" | {r['D64']:.3e} | {r['f64']:.3e} |")
    best = max(rows, key=lambda r: r['margin'])
    closed = [r['name'] for r in rows if r['margin'] <= 0]
    lines += ["", f"Reading of the table. The matching prior makes the exact representation stationary with zero residual (fit error {row_m['fit']:.1e}), hence κ_R = 0 and the "
              f"maximal margin κ = σ₀ = {row_m['margin']:.5f}, {row_m['margin'] / row_s['margin']:.1f} times the σ-modification's {row_s['margin']:.5f} (relaxation time 1/κ = {1 / row_m['margin']:.0f} against "
              f"{1 / row_s['margin']:.0f} slow units); the σ-modification's bias (fit error {row_s['fit']:.3f}: amplitudes {', '.join(f'{x:.2f}' for x in row_s['a'])} against 3A_k = {', '.join(f'{3 * A:.1f}' for A, C, S in BUMPS)}, "
              f"widths {', '.join(f'{x:.2f}' for x in row_s['s'])} against {', '.join(f'{S:.1f}' for A, C, S in BUMPS)}) is removed. The floors move the other way: the weight sensitivities ‖S_k‖ are "
              f"{', '.join(f'{x:.2f}' for x in row_m['S_norm'])} against {', '.join(f'{x:.2f}' for x in row_s['S_norm'])}, the predicted parameter-level floor E D_∞(m = 64) is {row_m['D64']:.3e} against {row_s['D64']:.3e} "
              f"({row_m['D64'] / row_s['D64']:.2f}×) and the function-level floor {row_m['f64']:.3e} against {row_s['f64']:.3e} ({row_m['f64'] / row_s['f64']:.2f}×): at a stationary point under a leak the fitted "
              f"configuration does not stay on the zero-residual manifold when the weights change (the leak pulls the amplitudes back), and the response of both the atoms and the fitted function to "
              f"the weights grows with the amplitudes, which the σ-modification had biased down — bias against variance. Misplacing the prior brings the residual curvature back: "
              + ("the window closes (margin ≤ 0) for " + "; ".join(closed) if closed else "no misplacement in the table closes the window")
              + f"; the largest margin in the table is {best['margin']:.5f} ({best['name']})."]
    # ---- coupled runs with the matching prior
    s_grid = runs[0]['s']
    kR_fx = np.mean([r['kR_ref_nbhd_fixed'] for r in runs], axis=0); kR_own = np.mean([r['kR_ref_nbhd'] for r in runs], axis=0)
    dr = np.mean([r['drift_rms'] for r in runs], axis=0); fit = np.mean([r['fit'] for r in runs], axis=0)
    lines += ["", f"## 2. Coupled runs with the matching prior (m = {', '.join(str(m) for m in MS)} against M = {M_REF}; warm start = the mixture of Gaussians of width {JITTER:g} around the exact representation; {S_END:g} slow units = {S_END * row_m['margin']:.1f} relaxation times; {N_SEEDS} seeds)", "",
              f"Hypothesis along the run (κ_R over the spheres of radius ϱ′ around 256 reference particles, with the stationary residual r* = 0 and with the reference's own residual): "
              f"max_s κ_R(r*) = {kR_fx.max():.5f}, max_s κ_R(r_ref) = {kR_own.max():.5f} (σ₀ = {SIGMA0:.5f}); the reference's rms drift {dr[0]:.1e} → {dr[-1]:.1e}, fit error {fit[0]:.4f} → {fit[-1]:.4f}.", "",
              "| m | " + " | ".join(f"max D_m on ({a:g}, {b:g}]" for a, b in WINDOWS) + f" | mean D_m on ({WINDOWS[-1][0]:g}, {WINDOWS[-1][1]:g}] | mean ‖f̂_Θ − f̂_ref‖ on the last window | predicted E D_∞ | predicted E‖f̂_m − f̂_M‖² |",
              "|---|" + "---|" * (len(WINDOWS) + 4)]
    S_m, F_m = row_m['S'], row_m['F']
    W = {m: [window_stats(r['s'], r[f'D{m}'], WINDOWS) for r in runs] for m in MS}
    H = {m: [float(r[f'h{m}'][(r['s'] > WINDOWS[-1][0]) & (r['s'] <= WINDOWS[-1][1])].mean()) for r in runs] for m in MS}
    for m in MS:
        cells = [fmt(*mean_se([w[j] for w in W[m]])) for j in range(len(WINDOWS) + 1)]
        hm, hs = mean_se(H[m])
        lines.append(f"| {m} | " + " | ".join(cells) + f" | {fmt(hm, hs)} | {CL.predicted_stationary_D(S_m, W_BAR, m, M_REF, G):.3e} | {PD.predicted_stationary_function_D(F_m, W_BAR, m, M_REF):.3e} |")
    sl, se = slope_se({m: [w[len(WINDOWS) - 1] for w in W[m]] for m in MS}); slh, seh = slope_se(H)
    ratios = [np.mean([w[len(WINDOWS) - 1] for w in W[m]]) / np.mean([w[0] for w in W[m]]) for m in MS]
    ratios2 = [np.mean([w[len(WINDOWS) - 1] for w in W[m]]) / np.mean([w[len(WINDOWS) - 2] for w in W[m]]) for m in MS]
    lines += ["", f"Slope of the last-window maximum of D_m against m: {sl:.2f} ± {se:.2f} (−1 for the mean square); of the function-level distance: {slh:.2f} ± {seh:.2f} (−0.5). "
              f"Ratios of the last to the first window maxima: {', '.join(f'{r:.2f}' for r in ratios)}; last to the one before: {', '.join(f'{r:.2f}' for r in ratios2)}."]
    # per-seed laws from the realised weights
    agree_D, agree_f = [], []
    per_lines = []
    for m in MS:
        for r in runs:
            dw = r[f'w{m}'] - r['w_ref']
            pv = np.einsum('kij,j->ki', S_m, dw) / np.sqrt(G)[None, :]
            D_pred = float(np.sum(r[f'w{m}'] * np.sum(pv ** 2, axis=1)))
            f_pred = float(np.mean((F_m @ dw) ** 2))
            h_meas = float(r[f'h{m}'][-1]) ** 2
            if D_pred > 0 and f_pred > 0:
                agree_D.append(float(r[f'D{m}'][-1] / D_pred)); agree_f.append(h_meas / f_pred)
            per_lines.append(f"m = {m}, seed {r['seed']}: D {D_pred:.3e} → {r[f'D{m}'][-1]:.3e}; ‖f̂_Θ − f̂_ref‖² {f_pred:.3e} → {h_meas:.3e}")
    lines += ["", f"Per seed at s = {S_END:g}, predicted from the realised cluster weights → measured (parameter level Σ_k w^m_k‖S̃_k(w^m − w^M)‖², function level ‖F(w^m − w^M)‖²_{{L²(ρ)}}): "
              + "; ".join(per_lines) + f". Ratios measured/predicted: parameter level {', '.join(f'{x:.2f}' for x in agree_D)}; function level {', '.join(f'{x:.2f}' for x in agree_f)}."]
    # ---- the function-level law against the σ-modification's measured distances
    raw = os.path.join(OUT, 'learning_raw.npz')
    if os.path.exists(raw):
        z = np.load(raw, allow_pickle=True)
        warm = list(z['warm']); M0 = 2048
        lines += ["", f"## 3. The function-level law for the σ-modification against `exp_chaos_learning.py`'s warm runs (M = {M0}, last window)", "",
                  "| m | predicted RMS (1/m − 1/M)^{1/2}(tr FC̃Fᵀ/N)^{1/2} | measured mean ‖f̂_Θ − f̂_ref‖ on (450, 900] | ratio |", "|---|---|---|---|"]
        for m in MS:
            pred = np.sqrt(PD.predicted_stationary_function_D(row_s['F'], W_BAR, m, M0))
            meas = [float(r[f'h{m}'][(r['s'] > 450) & (r['s'] <= 900)].mean()) for r in warm]
            mu, se_ = mean_se(meas)
            lines.append(f"| {m} | {pred:.3e} | {fmt(mu, se_)} | {mu / pred:.2f} |")
        lines += ["", "The measured value is a mean of norms over the seeds (below the RMS by Jensen's inequality), and the prediction is the leading term in the weight fluctuation."]
    lines += ["", "Numbers are produced by `experiments/exp_prior_design.py`; nothing is edited by hand."]
    with open(os.path.join(OUT, 'prior_design.md'), 'w', encoding='utf-8') as f:
        f.write("\n".join(lines) + "\n")
    np.savez(os.path.join(OUT, 'prior_design_raw.npz'), rows=np.array(rows, dtype=object), runs=np.array(runs, dtype=object), allow_pickle=True)
    print("\n".join(lines))
    print(f"[{time.time() - t0:.0f}s]")


if __name__ == '__main__':
    main()
