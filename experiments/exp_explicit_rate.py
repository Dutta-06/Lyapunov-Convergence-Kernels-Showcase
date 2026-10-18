"""
Lemma E.0 against the exact rate: how conservative is the explicit strict Lyapunov function?
===========================================================================================

Three tables (PARADIGM.md §6, Lemma E.0 and Remark E.1):

1. Remark E.1's instance (m = n = 1, ϑ* = (1.5, 0.3, 0.8), G = I, k_e = 3, x_m = 1.5 sin ωt): the exact Floquet rate
   of the linearised loop against the explicit bound, for ω = 1 … 64.  Both fall like ω⁻²; the bound explains why
   (Ψ_D ∝ ω dominates c₁).
2. The slow-adaptation limit: the m = 3, n = 2 ideal of the Theorem E tests with G = g·diag(2, 2, 1), g from 30 down to
   0.01.  The ratio exact/explicit saturates as g → 0 (the mean-field normalisation Ψ_G ∝ m^{−1/2} puts large networks
   in this regime) and grows in the fast regime.
3. The window length: the bound depends on the PE window T through α(T) and c₁(T); the table shows the optimum.

4. Lemma E.0′ in the slow regime (the same ideal at g = 0.01, k = 50 … 600): the peak factors of the regressor, the
   conditions of the lemma, its guaranteed rate against the exact Floquet rate and against the averaged rate λ_min(M̄)/k,
   the certificate sup V̇/V ≤ −γ, and the optimised rate of Lemma E.0 for comparison.

5. Corollary E.0′.2 (Theorem E in the slow regime) on Remark E.1's single-kernel instance (G = 0.3·I, k_e = 40): the
   explicit ball radius, nonlinear rate and overshoot from Lemma E.0′'s V against those from Lemma E.0's, and the exact
   linear rate; the envelope itself is checked on the implemented loop by `tests/test_excitation.py`.

Output: results/explicit_rate/table.md
"""
import os
import sys
try:
    sys.stdout.reconfigure(encoding='utf-8')
except Exception:
    pass
import numpy as np

sys.path.insert(0, os.path.abspath(os.path.join(os.path.dirname(__file__), '..')))
from src.core import excitation as X
from src.core import transport as T

OUT = os.path.join(os.path.dirname(__file__), '..', 'results', 'explicit_rate')
PER = 2 * np.pi


def remark_E1_table():
    rows = []
    k = 3.0
    P_star = np.array([[1.5, 0.3, 0.8]])
    for om in (1.0, 2.0, 4.0, 8.0, 16.0, 32.0, 64.0):
        reg = X.TheoremERegressor(P_star, np.ones(3), lambda t, o=om: np.array([1.5 * np.sin(o * t)]),
                                  lambda t, o=om: np.array([1.5 * o * np.cos(o * t)]))
        per = PER / om
        tg = np.linspace(0, per, 100)
        _, best, _ = X.explicit_rate(reg.Psi, reg.Psidot, k, [per / 2, per, 2 * per], tg, n_nodes=100)
        c_cf = X.strict_lyapunov_constants(k, best['alpha'], best['T'], best['Psi_M'], best['Psi_D'])
        c_op = X.optimise_eps(k, best['alpha'], best['T'], best['Psi_M'], best['Psi_D'], n_grid=300)
        fl = X.floquet_rate(reg.Psi, k, per, n_steps=2000)
        rows.append(dict(omega=om, T=best['T'], alpha=best['alpha'], Psi_M=best['Psi_M'], Psi_D=best['Psi_D'],
                         floquet=fl, closed_form=c_cf['rate'], optimised=c_op['rate'], ratio=fl / c_op['rate']))
    return rows


def slow_limit_table():
    rng = np.random.default_rng(12)
    m, n = 3, 2
    ctrl = T.TransportController(m, n, ke=6.0, g_a=30.0, g_c=30.0, g_s=15.0, a_max=8.0, c_max=4.0, s_min=0.3, s_max=3.0, eps=0.15)
    P_star = T.sample_lifted_ideal(m, n, ctrl, rng, min_sep=0.9)
    plant = T.LiftedRepresentablePlant(P_star, amplitude=2.5)
    per = 20 * np.pi
    rows = []
    for g in (30.0, 10.0, 3.0, 1.0, 0.3, 0.1, 0.03, 0.01):
        G_diag = np.concatenate([np.full(n, 2 * g), np.full(n, 2 * g), [g]])
        reg = X.TheoremERegressor(P_star, G_diag, plant.x_ref, plant.x_ref_dot)
        tg = np.linspace(0, per, 80)
        _, best, _ = X.explicit_rate(reg.Psi, reg.Psidot, ctrl.ke, [per], tg, n_nodes=800)       # 800 nodes: converged over the 20π window
        c_cf = X.strict_lyapunov_constants(ctrl.ke, best['alpha'], best['T'], best['Psi_M'], best['Psi_D'])
        c_op = X.optimise_eps(ctrl.ke, best['alpha'], best['T'], best['Psi_M'], best['Psi_D'], n_grid=300)
        fl = X.floquet_rate(reg.Psi, ctrl.ke, per, n_steps=4000)
        # the averaging prediction of Remark E.1 for slow adaptation: λ_min⟨Ψ_GᵀΨ_G⟩/k_e
        avg = X.gramian(reg.Psi, 0.0, per, n_nodes=400) / per
        lam_min = np.linalg.eigvalsh(avg)[0]
        pred = lam_min / ctrl.ke
        kappa = best['Psi_M'] ** 2 / lam_min                                      # condition number of ⟨Ψ_GᵀΨ_G⟩
        # slow-regime value of the closed-form bound: rate ≈ kα²/(3c₁²) with c₁ ≈ T(kΨ_M + Ψ_D) and α = Tλ_min,
        # so exact/explicit ≈ 3κ(1 + Ψ_D/(kΨ_M))² (Remark E.0a)
        sat = 3 * kappa * (1 + best['Psi_D'] / (ctrl.ke * best['Psi_M'])) ** 2
        rows.append(dict(g=g, Psi_M=best['Psi_M'], Psi_D=best['Psi_D'], alpha=best['alpha'], floquet=fl, explicit=c_op['rate'],
                         closed_form=c_cf['rate'], ratio=fl / c_op['rate'], ratio_cf=fl / c_cf['rate'], averaging=pred,
                         excitation=best['Psi_M'] ** 2 / ctrl.ke, kappa=kappa, sat=sat))
    return rows


def window_table():
    rng = np.random.default_rng(12)
    m, n = 3, 2
    ctrl = T.TransportController(m, n, ke=6.0, g_a=3.0, g_c=3.0, g_s=1.5, a_max=8.0, c_max=4.0, s_min=0.3, s_max=3.0, eps=0.15)
    P_star = T.sample_lifted_ideal(m, n, ctrl, rng, min_sep=0.9)
    plant = T.LiftedRepresentablePlant(P_star, amplitude=2.5)
    per = 20 * np.pi
    reg = X.TheoremERegressor(P_star, ctrl.G_diag, plant.x_ref, plant.x_ref_dot)
    tg = np.linspace(0, per, 80)
    rows = []
    for frac in (0.25, 0.5, 1.0, 2.0):
        Tw = frac * per
        alpha = X.pe_level(reg.Psi, Tw, tg, n_nodes=int(800 * max(1.0, 2 * frac)))     # nodes proportional to the window (converged; checked by pe_level)
        Psi_M, Psi_D = X.sup_norms(reg.Psi, reg.Psidot, tg)
        if alpha <= 0:
            rows.append(dict(T=Tw, alpha=alpha, rate=0.0)); continue
        c = X.optimise_eps(ctrl.ke, alpha, Tw, Psi_M, Psi_D, n_grid=300)
        rows.append(dict(T=Tw, alpha=alpha, rate=c['rate'], eps=c['eps']))
    return rows


def slow_regime_table():
    rng = np.random.default_rng(12)
    m, n = 3, 2
    ctrl = T.TransportController(m, n, ke=6.0, g_a=30.0, g_c=30.0, g_s=15.0, a_max=8.0, c_max=4.0, s_min=0.3, s_max=3.0, eps=0.15)
    P_star = T.sample_lifted_ideal(m, n, ctrl, rng, min_sep=0.9)
    plant = T.LiftedRepresentablePlant(P_star, amplitude=2.5)
    per = 20 * np.pi
    g = 0.01
    G_diag = np.concatenate([np.full(n, 2 * g), np.full(n, 2 * g), [g]])
    reg = X.TheoremERegressor(P_star, G_diag, plant.x_ref, plant.x_ref_dot)
    S = X.SlowRegimeLyapunov(reg.Psi, reg.Psidot, per, N=2048)
    head = dict(lam_min=S.lam_min, kappa=S.lam_max / S.lam_min, rho=S.rho, rho_D=S.rho_D, rho_DD=S.rho_DD, Psi_M=S.Psi_M, Psi_D=S.Psi_D,
                Psi_DD=S.Psi_DD, TPsiM2=per * S.Psi_M ** 2, N2=float(np.linalg.norm(S.N2, 2)), k0_02=S.threshold(0.2), k0_01=S.threshold(0.1))
    rows = []
    tg = np.linspace(0, per, 80)
    for k in (50.0, 100.0, 200.0, 300.0, 400.0, 600.0):
        fl = X.floquet_rate(reg.Psi, k, per)
        _, best, _ = X.explicit_rate(reg.Psi, reg.Psidot, k, [per], tg, n_nodes=800)
        e0 = X.optimise_eps(k, best['alpha'], best['T'], best['Psi_M'], best['Psi_D'], n_grid=300)
        for delta in (0.2, 0.1):
            c = S.constants(k, delta)
            sup, mg = S.certificate(k, delta, n_t=128) if c['ok'] else (float('nan'), float('nan'))
            rows.append(dict(k=k, delta=delta, c=c, floquet=fl, e0=e0['rate'], sup=sup, mg=mg, avg=S.lam_min / k))
    return head, rows


def corollary_table():
    rng = np.random.default_rng(7)
    m, n = 1, 1
    g, ke = 0.3, 40.0
    ctrl = T.TransportController(m, n, ke=ke, g_a=g, g_c=g, g_s=g, a_max=8.0, c_max=4.0, s_min=0.3, s_max=3.0, eps=0.15)
    P_star = np.array([[1.5, 0.3, 0.8]])
    plant = T.LiftedRepresentablePlant(P_star, amplitude=1.5, freqs=[1.0], phases=[0.0])
    per = 2 * np.pi
    p = 2 * n + 1
    reg = X.TheoremERegressor(P_star, ctrl.G_diag, plant.x_ref, plant.x_ref_dot)
    S = X.SlowRegimeLyapunov(reg.Psi, reg.Psidot, per, N=1024)
    r = float(min(ctrl.a_max - ctrl.eps - abs(P_star[0, 0]), ctrl.c_max - ctrl.eps - abs(P_star[0, 1]),
                  P_star[0, 2] - ctrl.s_min - ctrl.eps, ctrl.s_max - ctrl.eps - P_star[0, 2]))
    tg = np.linspace(0, per, 80)

    def field(z, t):
        e = z[:n]; P = P_star + z[n:].reshape(m, p); x = plant.x_ref(t) + e
        edot = plant.f(x, t) - ctrl.ke * e - T.f_hat(x, P); v, _ = ctrl.velocity(x, e, P)
        return np.concatenate([edot, v.reshape(-1)])
    L_J = X.jacobian_lipschitz_estimate(field, n + m * p, r, tg, rng, n_samples=150)
    _, best, _ = X.explicit_rate(reg.Psi, reg.Psidot, ke, [per], tg, n_nodes=160)
    e0 = X.optimise_eps(ke, best['alpha'], best['T'], best['Psi_M'], best['Psi_D'], n_grid=120)
    old = X.theorem_E_constants(ke, best['alpha'], best['T'], best['Psi_M'], best['Psi_D'], m, ctrl.G_diag, r, L_J, eps=e0['eps'])
    fl = X.floquet_rate(reg.Psi, ke, per)
    rows = []
    for delta in (0.2, 0.1):
        c = S.constants(ke, delta)
        rows.append(dict(delta=delta, ok=c['ok'], c=c, new=X.slow_regime_theorem_E_constants(S, ke, delta, m, ctrl.G_diag, r, L_J) if c['ok'] else None))
    return dict(S=S, ke=ke, r=r, L_J=L_J, old=old, fl=fl, rows=rows, thr02=S.threshold(0.2), thr01=S.threshold(0.1))


def main():
    os.makedirs(OUT, exist_ok=True)
    r1, r2, r3 = remark_E1_table(), slow_limit_table(), window_table()
    head4, r4 = slow_regime_table()
    c5 = corollary_table()
    L = ["# Lemma E.0: the explicit rate against the exact Floquet rate (`exp_explicit_rate.py`)", "",
         "The explicit rate lies below the exact rate in every row. The ordering is numerical: Ψ_M, Ψ_D are grid maxima "
         "(80–100 samples per period), α a converged quadrature (checked by refinement), ε a finite grid; the margins are at "
         "least 17×.", "",
         "## 1. Remark E.1's instance, x_m = 1.5 sin ωt (m = n = 1, G = I, k_e = 3)", "",
         "| ω | window T | α(T) | Ψ_M | Ψ_D | exact Floquet rate | explicit rate, closed-form ε | explicit rate, optimised ε | exact / explicit |",
         "|---|---|---|---|---|---|---|---|---|"]
    for r in r1:
        L.append(f"| {r['omega']:g} | {r['T']:.3g} | {r['alpha']:.3g} | {r['Psi_M']:.3g} | {r['Psi_D']:.3g} | {r['floquet']:.3e} | "
                 f"{r['closed_form']:.3e} | {r['optimised']:.3e} | {r['ratio']:.3g} |")
    om = np.array([r['omega'] for r in r1]); fl = np.array([r['floquet'] for r in r1]); ex = np.array([r['optimised'] for r in r1])
    sl_f = np.polyfit(np.log(om[2:]), np.log(fl[2:]), 1)[0]; sl_e = np.polyfit(np.log(om[2:]), np.log(ex[2:]), 1)[0]
    sl_last = np.log(ex[-1] / ex[-2]) / np.log(om[-1] / om[-2])
    L += ["", f"Log-log slopes over ω ≥ 4: exact {sl_f:.2f}, explicit {sl_e:.2f} (Remark E.1 reports the exact ω⁻² law); "
          f"explicit slope over the last octave (ω = {om[-2]:g} → {om[-1]:g}): {sl_last:.2f}.", "",
          "## 2. Slow-adaptation limit: the ideal of the Theorem E tests (m = 3, n = 2, k_e = 6), two-tone reference of period 20π, G = g·diag(2, 2, 1)", "",
          "| g | Ψ_M | Ψ_D | α(T = 20π) | Ψ_M²/k_e | κ_Ψ = Ψ_M²/λ_min⟨Ψ_GᵀΨ_G⟩ | exact Floquet rate | explicit rate, closed-form ε | explicit rate, optimised ε | exact / explicit (closed form) | exact / explicit (optimised) | 3κ_Ψ(1 + Ψ_D/(k_eΨ_M))² | averaging value λ_min⟨Ψ_GᵀΨ_G⟩/k_e |",
          "|---|---|---|---|---|---|---|---|---|---|---|---|---|"]
    for r in r2:
        L.append(f"| {r['g']:g} | {r['Psi_M']:.3g} | {r['Psi_D']:.3g} | {r['alpha']:.3g} | {r['excitation']:.3g} | {r['kappa']:.3g} | "
                 f"{r['floquet']:.3e} | {r['closed_form']:.3e} | {r['explicit']:.3e} | {r['ratio_cf']:.3g} | {r['ratio']:.3g} | {r['sat']:.3g} | {r['averaging']:.3e} |")
    L += ["", "As g → 0 (slow adaptation) the ratio exact/explicit decreases towards a constant of order 3κ_Ψ(1 + Ψ_D/(k_eΨ_M))², where "
          "κ_Ψ is the condition number of the averaged Gramian (Remark E.0a): the exact rate pays for ill-conditioning once, through "
          "λ_min, and the bound pays twice.  The formula is the leading-order value of the closed-form rate kα²/(3c₁²); the measured "
          "ratio is smaller because the Young step and the bound p_hi ≤ 3/4 have slack and because ε is optimised.  The ratio grows "
          "further with the excitation strength Ψ_M²/k_e (fast adaptation).  α is the PE level over one period (t-independent; "
          "800 Gauss–Legendre nodes, converged).", "",
          "## 3. The PE window (same ideal, G = diag(3, 3, 1.5))", "",
          "| T / period | α(T) | explicit rate | ε |", "|---|---|---|---|"]
    per = 20 * np.pi
    for r in r3:
        L.append(f"| {r['T'] / per:g} | {r['alpha']:.3g} | {r['rate']:.3e} | {r.get('eps', float('nan')):.3e} |")
    L += ["", "## 4. Lemma E.0′ in the slow regime (the ideal of table 2 at g = 0.01, T = 20π)", "",
          f"λ_min(M̄) = {head4['lam_min']:.3e}, κ(M̄) = {head4['kappa']:.2e}, Ψ_M = {head4['Psi_M']:.3f}, Ψ_D = {head4['Psi_D']:.3f}, Ψ_DD = {head4['Psi_DD']:.2f}, "
          f"TΨ_M² = {head4['TPsiM2']:.2f}; peak factors ρ = {head4['rho']:.1f}, ρ_D = {head4['rho_D']:.0f}, ρ_DD = {head4['rho_DD']:.3g}; ‖N₂‖ = {head4['N2']:.1e} "
          f"(the lemma: N₂ = 0); threshold k₀ of conditions (A)–(D): {head4['k0_02']:.0f} (δ = 0.2), {head4['k0_01']:.0f} (δ = 0.1).", "",
          "| k | δ | conditions (A) c₁c₂ ≤ δ/2, (B), (C), (D) | β | c_ζ | guaranteed rate γ/2 | exact Floquet rate | exact / guaranteed | averaged rate λ_min/k | exact / averaged | Lemma E.0 optimised rate | exact / E.0 | sup V̇/V on the grid, −γ | overshoot C |",
          "|---|---|---|---|---|---|---|---|---|---|---|---|---|---|"]
    for r in r4:
        c = r['c']; cd = c['conds']
        L.append(f"| {r['k']:g} | {r['delta']:g} | {c['c1c2']:.3f}: {'yes' if cd['A'] else 'no'}, {'yes' if cd['B'] else 'no'}, {'yes' if cd['C'] else 'no'}, {'yes' if cd['D'] else 'no'} | "
                 f"{c['beta']:.0f} | {c['c_z']:+.3f} | {c['rate']:.3e} | {r['floquet']:.3e} | {r['floquet'] / c['rate'] if c['ok'] else float('nan'):.3f} | {r['avg']:.3e} | "
                 f"{r['floquet'] / r['avg']:.4f} | {r['e0']:.3e} | {r['floquet'] / r['e0']:.3g} | {r['sup']:+.3e}, {r['mg']:+.3e} | {c['overshoot']:.1f} |")
    L += ["", "Reading: above the threshold the guaranteed rate of Lemma E.0′ is the averaged rate λ_min(M̄)/k up to the factor "
          "c_ζ/(1 + εp₁ + ε²p₂) ≈ 1 − δ, within a factor 1.3 of the exact rate, where Lemma E.0's optimised rate is five orders of "
          "magnitude below it; the certificate sup V̇/V ≤ −γ is verified on the grid wherever the conditions hold. Below the threshold "
          "the conditions fail through (A): the derivative peak factor ρ_DD of this regressor is large (the directions that are poorly "
          "excited on average are excited in short bursts).", "",
          "## 5. Corollary E.0′.2: Theorem E in the slow regime on the single-kernel instance (m = n = 1, ϑ* = (1.5, 0.3, 0.8), G = 0.3·I, x_m = 1.5 sin t, k_e = 40)", "",
          f"λ_min(M̄_G) = {c5['S'].lam_min:.3e}, κ(M̄_G) = {c5['S'].lam_max / c5['S'].lam_min:.1f}, peak factors ρ = {c5['S'].rho:.1f}, ρ_D = {c5['S'].rho_D:.1f}, ρ_DD = {c5['S'].rho_DD:.0f}; "
          f"threshold k₀ = {c5['thr02']:.1f} (δ = 0.2), {c5['thr01']:.1f} (δ = 0.1); r = min(ρ, δ) = {c5['r']:.3f}, L_J = {c5['L_J']:.2f} (estimated from samples); exact linear rate {c5['fl']:.3e}.", "",
          "| Lyapunov function | explicit ball radius r₀ (w-coordinates) | nonlinear rate λ | overshoot C | exact linear rate / λ |", "|---|---|---|---|---|",
          f"| Lemma E.0, optimised ε (Theorem E) | {c5['old']['r0_w']:.3e} | {c5['old']['rate_nonlinear']:.3e} | {c5['old']['C']:.2f} | {c5['fl'] / c5['old']['rate_nonlinear']:.1f} |"]
    for rr in c5['rows']:
        if rr['ok']:
            L.append(f"| Lemma E.0′, δ = {rr['delta']:g} (Corollary E.0′.2) | {rr['new']['r0_w']:.3e} | {rr['new']['rate_nonlinear']:.3e} | {rr['new']['C']:.2f} | {c5['fl'] / rr['new']['rate_nonlinear']:.1f} |")
        else:
            L.append(f"| Lemma E.0′, δ = {rr['delta']:g} | conditions fail: {rr['c']['conds']} | | | |")
    L += ["", "Reading: on this well-conditioned regressor (κ ≈ 7) Lemma E.0 is only an order of magnitude conservative, and the corollary trades the "
          "certified ball for the rate: its nonlinear rate is within a small factor of the exact linear rate (the factor 2 of the Lyapunov argument "
          "times 1/(1 − δ)), while its ball radius carries the anisotropy p_lo/p_hi ≈ 1/β of the quadratic form. On ill-conditioned regressors "
          "(table 4) both improve, the rate by the factor of Remark E.0a.", "",
          "Numbers are produced by `experiments/exp_explicit_rate.py`; nothing is edited by hand."]
    with open(os.path.join(OUT, 'table.md'), 'w', encoding='utf-8') as f:
        f.write("\n".join(L) + "\n")
    print("\n".join(L))


if __name__ == '__main__':
    main()
