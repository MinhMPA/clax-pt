"""Parameter containers for clax.

CosmoParams: cosmological parameters, JAX-traced (for autodiff).
PrecisionParams: numerical precision settings, static (not traced).
BackgroundResult: output of the background module.

All result types are frozen dataclasses registered as JAX pytrees.

References:
    CLASS source: include/background.h (struct background)
    CLASS source: include/precisions.h
"""

from __future__ import annotations

from dataclasses import dataclass, field, fields
from typing import Optional

import jax
import jax.numpy as jnp

from clax.constants import T_cmb_default


# ---------------------------------------------------------------------------
# CosmoParams: traced by JAX for autodiff
# ---------------------------------------------------------------------------

@jax.tree_util.register_pytree_node_class
@dataclass(frozen=True)
class CosmoParams:
    """Cosmological parameters. All float fields are JAX-traceable.

    These are the parameters that gradients are computed with respect to.
    The integer field N_ncdm is static (controls array shapes).

    Units follow CLASS conventions:
        - omega_b, omega_cdm: physical density parameters Omega_x h^2
        - h: dimensionless Hubble parameter H0/(100 km/s/Mpc)
        - T_cmb: CMB temperature in Kelvin
        - m_ncdm: neutrino mass sum in eV (single species degenerate approx)
        - k_pivot: pivot scale in Mpc^-1
    """

    # Hubble
    h: float = 0.6736

    # Densities
    omega_b: float = 0.02237      # Omega_b h^2
    omega_cdm: float = 0.1200     # Omega_cdm h^2

    # CMB
    T_cmb: float = T_cmb_default  # Kelvin

    # Neutrinos
    N_ur: float = 2.0328          # ultra-relativistic species (effective)
    N_ncdm: int = 1               # number of massive species (STATIC, not traced)
    m_ncdm: float = 0.06          # total mass in eV (single species)
    T_ncdm_over_T_cmb: float = 0.71611  # (4/11)^(1/3)
    deg_ncdm: float = 1.0         # degeneracy factor

    # Primordial
    ln10A_s: float = 3.0445224377  # matches A_s=2.1e-9 exactly
    n_s: float = 0.9649
    alpha_s: float = 0.0          # running of spectral index
    r_t: float = 0.0              # tensor-to-scalar ratio
    n_t: float = 0.0              # tensor spectral index
    k_pivot: float = 0.05         # Mpc^-1

    # Reionization
    tau_reio: float = 0.0544

    # Dark energy (CPL: w(a) = w0 + wa*(1-a))
    w0: float = -1.0
    wa: float = 0.0
    cs2_fld: float = 1.0          # DE sound speed squared

    # Curvature (v1: must be 0)
    Omega_k: float = 0.0

    # Helium
    Y_He: float = 0.2454006

    # --- PyTree registration ---
    def tree_flatten(self):
        # All float fields are children (traced); N_ncdm is aux (static)
        children = []
        child_names = []
        for f in fields(self):
            if f.name == "N_ncdm":
                continue
            children.append(getattr(self, f.name))
            child_names.append(f.name)
        aux_data = {"N_ncdm": self.N_ncdm, "child_names": tuple(child_names)}
        return children, aux_data

    @classmethod
    def tree_unflatten(cls, aux_data, children):
        child_names = aux_data["child_names"]
        kwargs = dict(zip(child_names, children))
        kwargs["N_ncdm"] = aux_data["N_ncdm"]
        return cls(**kwargs)

    def replace(self, **kwargs) -> CosmoParams:
        """Return a new CosmoParams with specified fields replaced."""
        current = {f.name: getattr(self, f.name) for f in fields(self)}
        current.update(kwargs)
        return CosmoParams(**current)


# ---------------------------------------------------------------------------
# PrecisionParams: NOT traced by JAX (static, controls array shapes)
# ---------------------------------------------------------------------------

@dataclass(frozen=True)
class PrecisionParams:
    """Numerical precision parameters. These are NOT JAX-traced.

    They control grid sizes, tolerances, and solver settings. Changing them
    changes the shapes of arrays, so they must be compile-time constants
    for JIT.
    """

    # Background
    bg_n_points: int = 800          # number of log(a) grid points
    bg_a_ini_default: float = 1e-7  # initial scale factor (needs to be early enough for high-k perturbation ICs)
    bg_tol: float = 1e-10           # ODE tolerance

    # NCDM (massive neutrino) quadrature
    ncdm_q_size: int = 5            # perturbation hierarchy q-bins (CLASS default: 5)
    ncdm_bg_q_size: int = 30        # background integration q-points (CLASS default: 11)
    ncdm_q_max: float = 15.0        # max comoving momentum q
    ncdm_bg_n_points: int = 512     # points for pre-tabulation grid
    ncdm_fluid_approximation: str = "class"  # mb, hu, class, none (CLASS default: class)
    ncdm_fluid_trigger_tau_over_tau_k: float = 31.0  # CLASS default late-time switch

    # Thermodynamics
    # 5e4 is a practical floor, not a tunable knob: the thermo table's first
    # knot (z=th_z_max) must map to a conformal time earlier than perturbation
    # start tau_ini (~0.1-0.5 Mpc), because CubicSpline.evaluate clips to the
    # table boundary. Below the first knot, kappa_dot would freeze at its
    # boundary value instead of scaling as a^-2. Measured: th_z_max=5e3 puts
    # the first knot at tau=80.7 Mpc (> tau_ini) and gives P(k=0.01)=4.77e15
    # (wrong); th_z_max=5e4 gives P(k=0.01)=7.94e4, matching th_z_max=5e5 to
    # 2e-6 while running ~6x faster than 5e3 (60s vs 366s at k=0.01).
    th_z_max: float = 5e4           # max redshift for recombination
    th_n_points: int = 20000        # number of z grid points
    th_tol: float = 1e-5            # ODE tolerance
    # Reverse-mode AD rule for the fused background+thermodynamics solve
    # (clax.thermodynamics.solve_background_and_thermo), issue #30:
    #   "stable" — jax.custom_vjp whose backward pass computes the params
    #              cotangent via a batched forward-mode basis (jacfwd over
    #              the CosmoParams leaves). Fixes the ~2% h-gradient error
    #              from catastrophic cancellation in the recombination-era
    #              native backward pass. Forward-mode (jax.jvp) through the
    #              fused solve is BLOCKED in this mode (custom_vjp caveat).
    #   "native" — plain background_solve + thermodynamics_solve calls;
    #              required for jax.jvp/jacfwd through the fused solve.
    # Mirrors the ode_adjoint precedent below (static string flag).
    th_grad_mode: str = "stable"    # or "native"

    # Perturbations
    pt_k_min: float = 1e-5          # Mpc^-1
    pt_k_max_cl: float = 5.0        # Mpc^-1 (for C_l computation)
    pt_k_max_pk: float = 50.0       # Mpc^-1 (for P(k) output)
    pt_k_per_decade: int = 30
    pt_k_grid_type: str = "log"     # "log" | "chebyshev" (Lobatto nodes in log10 k; issue #31)
    pt_l_max_g: int = 17            # photon Boltzmann hierarchy
    pt_l_max_pol_g: int = 17        # photon polarization hierarchy
    pt_l_max_ur: int = 17           # massless neutrino hierarchy
    pt_l_max_ncdm: int = 17         # massive neutrino hierarchy
    pt_tau_n_points: int = 5000
    pt_ode_rtol: float = 1e-5
    pt_ode_atol: float = 1e-10

    # Transfer
    tr_l_max_scalars: int = 2500
    tr_l_max_tensors: int = 500
    tr_l_limber_switch: int = 100
    tr_limber_transition_width: float = 20.0

    # Harmonic
    hr_k_per_decade: int = 40
    hr_n_k_fine: int = 5000          # fine k-grid for source interpolation
    hr_l_max: int = 2500             # max multipole for C_l computation
    hr_l_limber: int = 0             # use Limber approx for l >= this (0=disabled)

    # Lensing
    le_l_max: int = 2500

    # ODE solver settings
    ode_max_steps: int = 65536
    ode_adjoint: str = "recursive_checkpoint"  # or "direct"
    # Perturbation ODE solver.
    #   "kvaerno5" — 5th-order ESDIRK (diffrax default, robust, Newton iteration)
    #   "rodas5"   — 5th-order Rosenbrock (no Newton, LU only; ~1.3x faster on
    #                CPU, potentially 3-5x on GPU; batched automatically for
    #                table solves)
    pt_ode_solver: str = "kvaerno5"

    # Memory management
    # >0 exact chunk size, 0 backend-aware auto-batching, <0 force full vmap.
    pt_k_chunk_size: int = 0

    @staticmethod
    def fast_cl():
        """Fast preset for C_l iteration.

        k_max=0.15 limits to where hierarchy (l_max=25) is well-converged.
        """
        return PrecisionParams(
            pt_k_max_cl=0.15,        # k*tau_visibility < l_max → hierarchy valid
            pt_k_per_decade=15,
            pt_tau_n_points=2000,
            pt_l_max_g=25,           # larger hierarchy for better convergence
            pt_l_max_pol_g=25,
            pt_l_max_ur=25,
            pt_ode_rtol=1e-4,
            pt_ode_atol=1e-8,
            ode_max_steps=65536,
        )

    @staticmethod
    def medium_cl():
        """Medium precision preset for C_l computation.

        l_max=50 reduces hierarchy truncation artifacts at high multipoles.
        k_max=0.3 extends to smaller scales. More expensive than fast_cl.
        """
        return PrecisionParams(
            pt_k_max_cl=0.3,         # extend to smaller scales
            pt_k_per_decade=20,
            pt_tau_n_points=3000,
            pt_l_max_g=50,           # reduce truncation artifacts
            pt_l_max_pol_g=50,
            pt_l_max_ur=50,
            # Oct 2026: tolerance rung carried over from the planck_cl sweep
            # (docs/precision_sweep_2026-10-10.md), not measured on this
            # preset's 20 k/decade, k_max 0.3 grid. At l_max 50, 60 k/decade,
            # k_max 1.0 (config E6, Kvaerno5) rtol 1e-4 / atol 1e-6 differs
            # from 1e-6 / 1e-11 by 0.094% at l=2 and 0.003% at l>=30; this
            # preset's old 1e-5 / 1e-10 and the new rung agree to < 0.01% for
            # l>=30 at the 12/10/17 hierarchy (sweep configs F vs G6).
            pt_ode_rtol=1e-4,
            pt_ode_atol=1e-6,
            # 4096 was sufficient with Kvaerno5 at rtol 1e-4 / atol 1e-8
            # (sweep config G4, hierarchy 12/10/17); 8192 carried over from
            # planck_cl, not measured on this grid (Kvaerno5 here by default).
            ode_max_steps=8192,
        )

    @staticmethod
    def science_cl():
        """Science-quality preset targeting <1% C_l accuracy at l=20-150.

        k_max=0.35, l_max=50. 200 k/decade resolves the oscillatory T_l(k)
        transfer function (Bessel period ~2.3e-4 Mpc^-1 vs k-spacing ~1.2e-4).
        ~900 k-modes total. Achieves sub-percent EE at l=12-100 and TT at
        l=20-150 (except l=100 at ~2%). ~10 min on V100 GPU.
        """
        return PrecisionParams(
            pt_k_max_cl=0.35,        # covers l~2500 via k*chi_star
            pt_k_per_decade=200,     # resolves T_l(k) Bessel oscillations
            pt_tau_n_points=4000,
            pt_l_max_g=50,           # converged hierarchy
            pt_l_max_pol_g=50,
            pt_l_max_ur=50,
            # Oct 2026: tolerance rung carried over from the planck_cl sweep
            # (docs/precision_sweep_2026-10-10.md), not measured on this
            # preset's 200 k/decade, k_max 0.35 grid. At l_max 50, 60 k/decade,
            # k_max 1.0 (config E6, Kvaerno5) rtol 1e-4 / atol 1e-6 differs
            # from the old 1e-6 / 1e-11 by 0.094% at l=2 and 0.003% at l>=30
            # (config E, rtol 1e-4 / atol 1e-8, is the one identical to 0.005%).
            pt_ode_rtol=1e-4,
            pt_ode_atol=1e-6,
            # 4096 was sufficient with Kvaerno5 at rtol 1e-4 / atol 1e-8
            # (sweep config G4, hierarchy 12/10/17); 8192 carried over from
            # planck_cl, not measured on this grid (Kvaerno5 here by default).
            ode_max_steps=8192,
        )

    @staticmethod
    def planck_cl():
        """Science preset, measured as shipped (rodas5; job 24668, before #53;
        V100, compute_cls_all_fast at n_k_fine 20000) against CLASS with a
        massless neutrino and RECFAST: TT within 0.086% (l <= 30), 0.233%
        (l <= 500), 0.262% (l <= 1000); EE within 0.60% (l = 2-4), 0.46%
        (l = 5-500), 0.98% (l = 5-1000); TE/sqrt(TT EE) within 0.37% (0.33%
        in job 24668, 0.37% in job 24639). The 0.98% EE number to l = 1000 is
        a single multipole at l ~ 526 and is bounded by the sparse-l-grid
        interpolation of the C_l stage, not by this preset: sparse_l_grid
        steps by 20 to l = 500 and by 50 from 550, and splining CLASS's own
        spectra on that grid gives EE 1.13% at l = 526 and TT 0.16% at l = 527
        from the grid alone (CHANGELOG, Oct 12, 2026, follow-ups). Stages on
        a V100, cached: thermodynamics ~63 s, perturbations ~30 s massless
        (~47 s with the preset's 5 neutrino q-bins, which
        scripts/benchmark_speed.py keeps at m_ncdm = 0), harmonic ~13 s;
        ~124 s end to end. After the #53 recombination rewrite (job 27000,
        Oct 20, 2026): TT 0.086 / 0.238 / 0.271%, EE 0.596 / 0.455 / 0.981%,
        TE/sqrt(TT EE) 0.327%, within 0.01 pp of the above; stages
        thermodynamics 59.6 s, perturbations 27.8 s, harmonic 13.5 s,
        101.5 s end to end.

        Retuned Oct 2026 (docs/precision_sweep_2026-10-10.md). The previous
        values (Kvaerno5, l_max 50, rtol 1e-6, atol 1e-11, max_steps 131072)
        cost 4606 s per perturbation solve on a V100 and give the same spectra
        to 0.1%: the solve is step-count-bound and the tolerance ladder is
        converged at rtol 1e-4 / atol 1e-6 for every hierarchy size, so the
        retune costs nothing at l <= 2000. l_max 17 for all species keeps the
        photon-truncation effect in the reionization EE bump below 0.05%
        (12/10/17 gives 0.18%). hr_n_k_fine 20000 together with the fast
        path's 30-point-per-unit-x Bessel table removes the former -1% TT
        offset at l < 50 and the +20% EE error at l=2. Above l ~ 1000 the
        C_l stage is percent-level (TT rms 1.7-2% at l = 1000-2000, EE 3-8%,
        common to the exact-j_l and table paths: perturbation k sampling /
        source interpolation); 120 k/decade halves that at ~1.4x the cost.
        300 k-modes.
        th_n_points: 100000 is kept for the science preset; 20000 (as in
        planck_fast) changes C_l by <= 0.02% to l=500, <= 0.05% to l=1000 and
        ~0.13% above, and cuts thermodynamics from ~59 s to ~13 s on a V100.
        Both numbers predate the Saha -> ODE recombination staging (#48, Oct
        2026): 100000 was chosen for the former explicit Heun stepping and is
        not re-tuned for the staging, where x_e at 20000 points is within
        1.1e-4 of 100000 over z 200-8000 (largest at z = 200), both 2.0e-4 from
        CLASS (the HeIII-era offset near z ~ 5900); the C_l effect of 20000 on
        the staged recombination is unmeasured.
        Sweep history (Kvaerno5 candidate, configs P1/P1m, V100 cached):
        perturbations 105 s (massless), 189 s (one 0.06 eV neutrino, 5
        q-bins), harmonic 13 s; TT within 0.26% and EE within 0.31%
        (l = 30-500) of CLASS massless RECFAST up to l = 1000. rodas5 (default
        since Oct 12, 2026) matches that candidate to 0.08% at l=2 and
        <= 0.03% elsewhere at 29.5 s vs 110.6 s of perturbations;
        thermodynamics (~60 s at th_n_points 100000) then dominates.
        GPU memory: with n_k_fine 20000 and n_tau 5000 every (n_k, n_tau)
        working array of the fast C_l path is 1e8 doubles (800 MB) and the
        stage materialises several of them, so budget of order 10 GB or more;
        validated only on a 32 GB V100.
        """
        return PrecisionParams(
            pt_k_max_cl=1.0,         # covers l~2500 with margin
            # 30 / 60 / 120 per decade give identical C_l only to l <= 300
            # (sweep G6k30 / G6k120); at 60 the C_l stage is at TT rms 1.7-2%
            # over l = 1000-2000; 120 halves the l > 1000 error at ~1.4x the
            # perturbation cost.
            pt_k_per_decade=60,
            pt_tau_n_points=5000,    # 10000 and 20000 identical; 2000 costs 0.6% low-l EE
            th_n_points=100000,      # 20000: <=0.05% to l=1000, 46 s cheaper; not re-tuned for #48
            pt_l_max_g=17,
            pt_l_max_pol_g=17,
            pt_l_max_ur=17,
            pt_ode_rtol=1e-4,
            pt_ode_atol=1e-6,
            # 4096 was sufficient with Kvaerno5 at rtol 1e-4 / atol 1e-8 (sweep
            # config G4, hierarchy 12/10/17); rodas5's step count differs, and
            # the validation of this preset passed at 8192 (job 24668).
            ode_max_steps=8192,
            hr_n_k_fine=20000,       # 5000 is percent-level above l~500
            # Oct 12, 2026: rodas5 with cubic Hermite dense output (rosenbrock.py)
            # matches kvaerno5 to 0.08% at l=2 and <= 0.03% elsewhere at 3.7x
            # less perturbation time (29.5 s vs 110.6 s on a V100).
            pt_ode_solver="rodas5",
        )

    @staticmethod
    def planck_fast():
        """planck_cl's perturbation and C_l-stage settings with a cheaper
        thermodynamics grid and a shorter l range.

        Same perturbation stage as planck_cl (k_max 1.0, 60 k/decade, 5000
        tau points, l_max 17/17/17, rtol 1e-4 / atol 1e-6, max_steps 8192,
        rodas5 with the cubic Hermite dense output) and the same fast-path
        C_l settings (hr_n_k_fine 20000, 30-point-per-unit-x Bessel table),
        with two changes:
        - th_n_points 20000 (planck_cl: 100000): thermodynamics ~13 s instead
          of ~59-63 s on a V100; C_l differ by <= 0.02% to l=500, <= 0.05%
          to l=1000 and ~0.13% above (precision-sweep candidate runs, Oct 12,
          2026, before #53; not re-tuned for the Saha -> ODE recombination
          staging, see planck_cl).
        - hr_l_max 1500 (planck_cl: 2500): the table C_l stage scales as
          n_l x n_k_fine x n_tau, so the shorter l range roughly halves the
          harmonic work. planck_cl's stage is ~13 s at l_max 2500 with
          n_k_fine 20000 on a V100; planck_fast's is not separately
          benchmarked (scripts/benchmark_speed.py has no planck_fast entry).

        Accuracy to l=1000 is planck_cl's up to the th_n_points differences
        above; this preset is not separately validated against CLASS
        (tests/test_preset_accuracy.py covers planck_cl and fit_cl). It is
        the --fast preset of the matched-species perturbation comparisons in
        tests/test_perturbations.py.
        GPU memory: with n_k_fine 20000 and n_tau 5000 every (n_k, n_tau)
        working array of the fast C_l path is 1e8 doubles (800 MB) and the
        stage materialises several of them, so budget of order 10 GB or more;
        validated only on a 32 GB V100.
        """
        return PrecisionParams(
            pt_k_max_cl=1.0,         # same as planck_cl
            pt_k_per_decade=60,      # same as planck_cl
            pt_tau_n_points=5000,    # same as planck_cl
            th_n_points=20000,       # 5x fewer than planck_cl (100000)
            pt_l_max_g=17,           # same as planck_cl (Oct 2026 retune)
            pt_l_max_pol_g=17,
            pt_l_max_ur=17,
            pt_ode_rtol=1e-4,        # same as planck_cl
            pt_ode_atol=1e-6,        # same as planck_cl
            ode_max_steps=8192,      # same as planck_cl
            hr_n_k_fine=20000,       # same as planck_cl
            hr_l_max=1500,           # halves the n_l x n_k_fine x n_tau table work vs 2500
            pt_ode_solver="rodas5",  # same as planck_cl (Oct 12, 2026)
        )

    @staticmethod
    def fit_cl():
        """Fast preset for fitting / HMC, targeting <2% C_l accuracy at l<600
        with a massless neutrino (see the ncdm_q_size caveat below).

        Reduces resolution everywhere for speed (planck_cl values in
        parentheses):
        - 20 k/decade (60) -> ~100 k-modes (300)
        - l_max 17/17/17 hierarchy (17; the same since the Oct 2026 retune,
          which moved planck_cl from 50 and fit_cl from 25)
        - 2000 tau points (5000)
        - 3000 thermodynamics points (100000)
        - ncdm_q_size 0: no massive-neutrino hierarchy, the 0.06 eV species
          is followed as massless (~3x faster perturbations). Measured cost
          (job 27008, Oct 20, 2026): against CLASS with the default 0.06 eV
          neutrino, TT is 14.6-15.4% off at l <= 30 at every LCDM grid point
          (EE 3-4%, TE/sqrt(TT EE) 17-19%), against 0.46% / 1.25% with
          m_ncdm = 0. Until that treatment is changed this is a
          massless-neutrino preset; tests/test_preset_accuracy.py records the
          grid numbers as a strict expected failure.
        - ode_max_steps 8192 (8192; was 1024)
        - rtol 1e-4 / atol 1e-6 (the same; Oct 2026): the converged rung of
          the tolerance ladder. The old 1e-3 / 1e-4 was never validated at
          low l and leaves 1.8% TT at l=2 even with the Hermite dense output.
        - fast all-l table Bessel (hr_n_k_fine 5000, hr_l_max 1500; planck_cl
          20000, 2500): precomputed j_l(x) and j_l'(x) tables with the
          T0+T1+T2 transfer contributions, one JIT instead of one per sparse
          l (83 of them at l_max 1500)

        V100 timings, cached, rodas5 at rtol 1e-4 / atol 1e-6, from two
        scripts that time the harmonic stage differently (quote the script
        with the number): diags/diag_preset_solver_choice.py (job 24652,
        config E; C_l to l_max 1500 with n_k_fine 5000): BG 0.7 s, TH 2.4 s,
        PT 9.8 s, HR 3.8 s, 16.8 s end to end (kvaerno5: 61.0 s);
        scripts/benchmark_speed.py (job 24668, hr_l_max 1500, n_k_fine 5000):
        BG 0.6 s, TH 2.1 s, PT 8.4 s, HR 7.6 s, 18.6 s end to end (job 24621:
        HR 7.2 s). Accuracy vs CLASS (massless RECFAST; job 24668, before
        #53): TT 0.46% at l<=30, 0.69% at l<=500; EE 1.25% at l=5-500; after
        #53 (job 27000): 0.46% / 0.46% / 1.19%, 16.9 s end to end. The
        perturbation k-grid limits l > 500 (TT -6.4% at l=1000).
        """
        return PrecisionParams(
            pt_k_max_cl=1.0,         # keep full k range for l coverage
            pt_k_per_decade=20,      # sparse perturbation k-grid (interp compensates)
            pt_tau_n_points=2000,    # sufficient for source resolution
            th_n_points=3000,        # RECFAST with fewer steps (was 5000)
            pt_l_max_g=17,           # CLASS default hierarchy (59 vs 83 state vars at l_max=25)
            pt_l_max_pol_g=17,
            pt_l_max_ur=17,
            ncdm_q_size=0,           # disable ncdm hierarchy (massless approx, ~3x faster)
            pt_ode_rtol=1e-4,        # Oct 2026: converged rung of the tolerance ladder (was 1e-3)
            pt_ode_atol=1e-6,        # (was 1e-4)
            # was 1024; 4096 was sufficient with Kvaerno5 at rtol 1e-4 / atol
            # 1e-8 (sweep config G4); rodas5's step count differs, and the
            # validation passed at 8192 (job 24668).
            ode_max_steps=8192,
            hr_n_k_fine=5000,        # fine k-grid for accurate Bessel integrals
            hr_l_max=1500,           # reduced max multipole
            # rodas5 with cubic Hermite dense output (Oct 12, 2026). With the
            # earlier linear dense output the late ISW was wrong (TT -46% at
            # l=2 at these tolerances); now rodas5 matches kvaerno5 to 0.08%
            # at l=2 and 0.03% elsewhere at 9.8 s vs 54.7 s of perturbations.
            # rtol 1e-3 / atol 1e-4 would save another 5.6 s but leaves 1.8%
            # at l=2 and 1.3% at l=3.
            pt_ode_solver="rodas5",
        )
