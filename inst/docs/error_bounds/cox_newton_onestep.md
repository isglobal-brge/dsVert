# Error bound for Cox one-step Newton from β=0

> **Archived historical design record.** The derivation below analyzes a
> retired one-step estimator. It is not release evidence: every Cox public
> frontdoor is quarantined and fails before any DSI call. References to
> shipping or PASS_PRACTICAL record an obsolete proposal only.

## Theorem

Let β* ∈ ℝ^p be the Cox partial-likelihood MLE for a fixed (X, t, δ) design
with standardized covariates (sd=1, mean=0). Let β_1 be the one-step
Newton iterate starting from β=0:

    β_1 = I(0)^{-1} · U(0)

where U(β) = ∂ℓ(β)/∂β is the score and I(β) = −∂²ℓ(β)/∂β∂β^T is the
observed information. Then

    ‖β_1 − β*‖₂  ≤  C(X,t,δ) · ‖β*‖₂²  +  O(‖β*‖₂³)

where the constant C depends on the design's third-order moments (skewness
tensor of the risk-set weighted covariate distribution) and the condition
number of I(β*).

## Derivation

Expand the score U around β* via Taylor series:

    U(0) = U(β*) + ∂U(β*)·(0 − β*)                                  (1)
                + (1/2) ∂²U(β*)·(0 − β*, 0 − β*)
                + (1/6) ∂³U(β*)·(0 − β*, 0 − β*, 0 − β*)
                + O(‖β*‖⁴)

At β*, U(β*) = 0 (first-order optimality).  ∂U = −I (observed Fisher),
so ∂U(β*) = −I(β*). Let T_{jkl} = ∂³ℓ/∂β_j∂β_k∂β_l denote the third-
derivative tensor (skewness of the score). Substituting:

    U(0) = I(β*) · β*  −  (1/2) T(β*, β*)  +  O(‖β*‖³)              (2)

Similarly expand I(0). For Cox,

    I(β) = Σ_i δ_i [ ω̄_i(X⊗X; β) − ω̄_i(X; β) ω̄_i(X; β)^T ]

where ω̄_i(f; β) = Σ_{k∈R_i} f(X_k) e^{X_k^T β} / Σ_{k∈R_i} e^{X_k^T β}
is the risk-set weighted average with hazard weights μ_k = e^{X_k^T β}.
Since ∂_β μ_k/μ_k = X_k, we have ∂_β ω̄_i(f; β) = cov_i(X, f; β) where
cov_i is the risk-set covariance under weights μ. Hence

    I(0) = I(β*) [ 1 + O(‖β*‖) ]                                    (3)

(Specifically, I(0) − I(β*) = ∫_0^{β*} ∂_β I(β) dβ, with
∂_β I scaling as ‖X‖² × first-moment shifts, each O(‖β‖).)

Combining (2) and (3):

    β_1 = I(0)^{-1} · U(0)
        = I(β*)^{-1} [1 − O(‖β*‖) + O(‖β*‖²)] · [I(β*) β* − (1/2) T(β*,β*) + O(‖β*‖³)]
        = β*  +  O(‖β*‖) · β*  −  (1/2) I(β*)^{-1} T(β*,β*)  +  O(‖β*‖³)
        = β*  +  O(‖β*‖²)                                           (4)

(The O(‖β*‖)·β* term IS O(‖β*‖²), and the skewness term is exactly
O(‖β*‖²) with constant (1/2) |I(β*)^{-1} T|_op.)

Therefore

    ‖β_1 − β*‖ = C(X,t,δ) · ‖β*‖² + O(‖β*‖³)                       (5)

where

    C(X,t,δ)  =  max{ ‖∂_β log I(β)‖_op ,  (1/2) ‖I(β*)^{-1} T‖_op }

is a design-dependent constant in [0.5, 5] for typical biomedical
cohorts with moderate covariate correlation.

## Consequence for the ⟨1e−3 acceptance bar

To guarantee ‖β_1 − β*‖ < 10^{-3} with one-step Newton, one requires

    ‖β*‖_std  <  √(10^{-3} / C)

For the typical biomedical C ≈ 1–2:

    ‖β*‖_std_max  <  √(5×10^{-4})  ≈  0.022–0.032

In ORIGINAL (un-standardized) covariate scale with sd(X_j) ≈ σ_j,

    |β*_j,orig|  <  0.022 / σ_j

For NCCTG lung (σ_{ph.ecog} ≈ 0.8, observed β_orig ≈ 0.67, i.e. β_std ≈ 0.54):
the 1-step Newton error is bounded by 1 × 0.54² = 0.29 in std-scale, or
0.36 in original scale. Observed: 0.053 (loose bound, OK).

For Pima-synth (σ_ped ≈ 0.47, β_std ≈ 0.16): bound 1 × 0.16² = 0.026
std-scale ≈ 0.055 original. Observed 0.12. The empirical constant is
C ≈ 2.2 for this design (higher third-order skewness from Pima-ped's
uniform distribution).

For strong-signal synth (β_std ≈ 0.86): bound 0.74. Observed 0.16.
Loose bound, shrinkage kicks in.

## Implications for shipping Cox-Newton one-step

**The plan's <1e-3 strict target is UNREACHABLE with one-step Newton
on realistic biomedical signals.** The O(‖β*‖²) bound forces
‖β*‖_std < 0.03 for <1e-3 accuracy. Biomedical effect sizes routinely
have ‖β‖_std ∈ [0.05, 0.5].

Two acceptance paths are honestly available:

1. **Path B (iterative Newton)**: compute I(β_k) at each β_k via Beaver
   on session μ, G shares and iterate. Quadratic convergence:
   ‖β_{k+1} − β*‖ ≤ C‖β_k − β*‖² → 3 iters from β_1 with β*_std=0.5
   gives error ≤ C × (C × 0.25)² × C × ... ≤ 10^{-9} (for C=1).
   Closes the target on all signal scales. Implementation cost:
   ~350 LOC + ~30 min Opal wall clock for p=5.

2. **Relaxed acceptance with explicit bound (paper honesty)**: accept
   PASS_PRACTICAL (abs<1e-2) and ship with (5) in the manuscript and
   disclosure table. Wide-HR claims within ±1% exp(1e-2)−1 ≈ 1%.
   Requires reviewer agreement on the non-strict bar.

The reviewer's P1 flag rejects path (2) without derivation; this
document provides the derivation. The decision on which path to ship
must be explicit and documented in the paper.

## References

- Greenland (1987), "Interpretation and choice of effect measures in
  epidemiologic analyses," *Am J Epidemiol* 125(5).
- Therneau & Grambsch (2000), *Modeling Survival Data*, Springer,
  §3.2 (asymptotic properties of partial-likelihood MLE and the
  Newton-Raphson iteration).
- Lin & Wei (1989), "The robust inference for the Cox proportional
  hazards model," *JASA* 84(408), for the skewness tensor T.
