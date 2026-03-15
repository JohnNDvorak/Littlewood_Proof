/-
Constructive proof infrastructure for the Riemann-Siegel expansion on blocks.

## Target
Prove (or reduce to atomic sub-lemmas) the RS expansion:
  ∀ k t, t ∈ [hardyStart k, hardyStart(k+1)] →
    |ErrorTerm t - (-1)^k · (2π/t)^{1/4} · Ψ(blockParam k t)| ≤ C_R · t^{-3/4}

## Architecture

The proof decomposes into:

### Proved constructively
- `blockParam_mem_Icc`: blockParam ∈ [0,1] on closed blocks
- `cpow_re_cos`: Re(e^{iθ}·(n+1)^{-1/2-it}) = (n+1)^{-1/2}·cos(θ-t·log(n+1))
- `mainTerm_eq_two_re_rotated_sum`: MainTerm = 2·Re(e^{iθ}·∑ n^{-s})
- `errorTerm_structure`: ErrorTerm = Re(e^{iθ}·ζ) - 2·Re(e^{iθ}·partial_sum)
- `rsLeadingTerm_abs_le`: |RS leading term| ≤ (2π/t)^{1/4}
- `two_pi_div_t_rpow_quarter`: (2π/t)^{1/4} = (2π)^{1/4}·t^{-1/4}
- `hardyStart_pos'`, `pos_of_in_block`, `hardyN_on_open_block`
- `neg_one_pow_block_eq`, `neg_one_pow_block_alt`
- `zeta_fe_critical_line`: ζ(1/2-it) = χ(1/2+it)·ζ(1/2+it) (functional equation)
- `sqrt_increment_antitone`: √(k+2+p)-√(k+2) ≤ √(k+1+p)-√(k+1) (concavity)
- `signed_errorTerm_nonneg_on_block`: (-1)^k·ErrorTerm ≥ 0 on block k
- `rs_block_interpolation`: wired through rs_saddle_point_bound (0 sorrys)
- `weighted_increment_antitone`: ∫(√(k+2+p)-√(k+2))Ψ ≤ ∫(√(k+1+p)-√(k+1))Ψ (concavity)

### Atomic sorrys (genuine mathematical content)
- `chi_modulus_critical_line`: |χ(1/2+it)| = 1 on the critical line (CLOSED)
- `saddle_point_remainder` / `rs_saddle_point_bound`: Siegel 1932 saddle-point (1 sorry)
- `leading_term_cov`: CoV identity for RS leading term on blocks (CLOSED)
- `rs_block_antitone`: Block monotonicity from c_fn_expansion (1 sorry)

### Proved (was sorry)
- `signed_block_integral_expansion`: CLOSED via leading_term_cov + pointwise RS bound
- `c_fn_expansion`: algebraic from signed_block_integral_expansion (CLOSED)
- `weighted_sqrt_monotone`: ∫√(k+1+p)·Ψ increasing in k (NEW)
- `chi_modulus_critical_line`: via Gamma reflection + trig identity (NEW)

### Proved (new infrastructure, C30)
- `polynomial_mismatch_sum_bound`: ‖mismatch sum‖ ≤ 4√(k+1) on block k
- `sqrt_block_le_sqrt_t_param`: √(k+1) ≤ √(t/(2π)+1) from hardyStart
- `polynomial_mismatch_crude_order`: ‖mismatch sum‖ ≤ 4√(t/(2π)+1) (O(t^{1/4}))

SORRY COUNT: 2 (saddle_point, rs_block_antitone) — both from siegel_expansion_core
WARNING COUNT: 2

Reference: Siegel 1932 §3; Edwards Ch. 7 (pp. 136-145);
Titchmarsh §4.16-4.17; Gabcke 1979.

Co-authored-by: Claude (Anthropic)
-/

import Littlewood.Aristotle.HardyZFirstMoment
import Littlewood.Aristotle.HardyNProperties
import Littlewood.Aristotle.ErrorTermExpansion
import Littlewood.Aristotle.RSBlockParam
import Littlewood.Aristotle.FunctionalEquationV2
import Littlewood.Bridge.HardyZTransfer
import Littlewood.Aristotle.HardyThetaSmooth

set_option relaxedAutoImplicit false
set_option autoImplicit false
set_option maxHeartbeats 800000

noncomputable section

namespace Aristotle.Standalone.RSExpansionProof

open MeasureTheory Set Real Filter Topology HardyEstimatesPartial
open Aristotle.HardyNProperties Aristotle.RSBlockParam
open Aristotle.ErrorTermExpansion

-- ============================================================
-- Section 1: blockParam ∈ [0,1] on closed blocks (constructive)
-- ============================================================

/-- blockParam is in [0,1] on a closed block. -/
theorem blockParam_mem_Icc (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t ≤ hardyStart (k + 1)) :
    blockParam k t ∈ Icc (0 : ℝ) 1 := by
  refine ⟨blockParam_nonneg k t ht_lo, ?_⟩
  simp only [blockParam]
  have hpi : (0 : ℝ) < 2 * Real.pi := by positivity
  suffices h : Real.sqrt (t / (2 * Real.pi)) ≤ (k : ℝ) + 2 by linarith
  have h_sq : t / (2 * Real.pi) ≤ ((k : ℝ) + 2) ^ 2 := by
    rw [div_le_iff₀ hpi]
    have : hardyStart (k + 1) = 2 * Real.pi * ((k : ℝ) + 2) ^ 2 := by
      unfold hardyStart; push_cast; ring
    linarith
  calc Real.sqrt (t / (2 * Real.pi))
      ≤ Real.sqrt (((k : ℝ) + 2) ^ 2) := Real.sqrt_le_sqrt h_sq
    _ = (k : ℝ) + 2 := Real.sqrt_sq (by positivity)

-- ============================================================
-- Section 2: Complex partial sum and structural identities
-- ============================================================

/-- The complex partial Dirichlet sum Σ_{n≤N} n^{-s} at s = 1/2 + it. -/
def complexPartialSum (t : ℝ) : ℂ :=
  ∑ n ∈ Finset.range (hardyN t),
    ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))

/-- The complex zeta remainder: ζ(1/2+it) - Σ_{n≤N} n^{-s}. -/
def complexZetaRemainder (t : ℝ) : ℂ :=
  riemannZeta (1/2 + Complex.I * (t : ℂ)) - complexPartialSum t

/-- Each term of the complex partial sum satisfies:
    Re(e^{iθ} · (n+1)^{-1/2-it}) = (n+1)^{-1/2} · cos(θ - t·log(n+1))

    This follows from (n+1)^{-1/2-it} = (n+1)^{-1/2} · exp(-it·log(n+1))
    for n+1 > 0 (using `Complex.cpow_def_of_ne_zero`), combined with
    Re(e^{iα} · e^{-iβ}) = cos(α - β). -/
theorem cpow_re_cos (n : ℕ) (t : ℝ) :
    (Complex.exp (Complex.I * hardyTheta t) *
      ((n + 1 : ℂ) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))).re =
    ((n + 1 : ℝ) ^ (-(1/2 : ℝ))) * Real.cos (hardyTheta t - t * Real.log (n + 1)) := by
  have hn_pos : (0 : ℝ) < (n : ℝ) + 1 := by positivity
  have hn_ne : (n + 1 : ℂ) ≠ 0 := by exact_mod_cast hn_pos.ne'
  -- Rewrite cpow using cpow_def_of_ne_zero: z^w = exp(log(z)*w)
  have h_cpow : (n + 1 : ℂ) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)) =
      Complex.exp (Complex.log (n + 1 : ℂ) * (-(1/2 : ℂ) - Complex.I * (t : ℂ))) :=
    Complex.cpow_def_of_ne_zero hn_ne _
  rw [h_cpow]
  -- Complex.log(n+1) = Real.log(n+1) for positive reals
  have h_log : Complex.log (n + 1 : ℂ) = ((Real.log (n + 1 : ℝ)) : ℂ) := by
    rw [show (n + 1 : ℂ) = ((n + 1 : ℝ) : ℂ) from by push_cast; ring]
    exact (Complex.ofReal_log (le_of_lt hn_pos)).symm
  rw [h_log]
  -- Combine exponents
  rw [← Complex.exp_add]
  set L := Real.log ((n : ℝ) + 1)
  -- Rewrite exponent as -(L/2) + I*(θ - t*L)
  have h_exp : Complex.I * ↑(hardyTheta t) + ↑L * (-(1/2) - Complex.I * ↑t) =
      ↑(-(L/2)) + ↑(hardyTheta t - t * L) * Complex.I := by
    push_cast; ring
  rw [h_exp, Complex.exp_add_mul_I]
  -- Now: (exp(-(L/2)) * (cos(θ-tL) + sin(θ-tL)*I)).re = exp(-(L/2)) * cos(θ-tL)
  simp only [Complex.mul_re, Complex.exp_ofReal_re, Complex.exp_ofReal_im,
    Complex.add_re, Complex.I_re, Complex.I_im,
    Complex.cos_ofReal_re, Complex.sin_ofReal_re, Complex.sin_ofReal_im]
  ring_nf
  -- Goal: rexp (L * (-1/2)) * cos(...) = cos(...) * (1+n)^(-1/2)
  have h_rpow : Real.exp (L * (-1/2)) = (1 + ↑n) ^ ((-1 : ℝ)/2) := by
    rw [Real.rpow_def_of_pos (by positivity : (0 : ℝ) < 1 + ↑n)]
    congr 1
    simp only [L]
    ring
  rw [h_rpow]; ring

/-- MainTerm equals 2·Re(e^{iθ} · partial_sum).

    This follows from `cpow_re_cos` applied to each term of the sum,
    using Re(e^{iθ} · Σ_n f(n)) = Σ_n Re(e^{iθ} · f(n)) (linearity of Re). -/
theorem mainTerm_eq_two_re_rotated_sum (t : ℝ) :
    MainTerm t = 2 * (Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t).re := by
  unfold MainTerm complexPartialSum
  -- Cancel the factor of 2
  congr 1
  -- Distribute e^{iθ}· into the sum, then take Re of each term
  rw [Finset.mul_sum, Complex.re_sum]
  exact Finset.sum_congr rfl fun n _ => (cpow_re_cos n t).symm

/-- ErrorTerm equals hardyZ minus MainTerm (definitional). -/
theorem errorTerm_eq_hardyZ_minus_mainTerm (t : ℝ) :
    ErrorTerm t = hardyZ t - MainTerm t := rfl

/-- ErrorTerm structural decomposition:
    ErrorTerm(t) = Re(e^{iθ}·ζ(1/2+it)) - 2·Re(e^{iθ}·partial_sum(t))

    This connects the real-valued ErrorTerm to the complex zeta function
    and complex partial Dirichlet sum via the phase factor e^{iθ}. -/
theorem errorTerm_structure (t : ℝ) :
    ErrorTerm t = (Complex.exp (Complex.I * hardyTheta t) *
      riemannZeta (1/2 + Complex.I * (t : ℂ))).re -
      2 * (Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t).re := by
  show hardyZ t - MainTerm t = _
  rw [mainTerm_eq_two_re_rotated_sum]
  -- Goal: Re(e^{iθ}·ζ(1/2+It)) - 2*Re(e^{iθ}·∑) = Re(e^{iθ}·ζ(1/2+It)) - 2*Re(e^{iθ}·∑)
  -- These should be definitionally equal after unfolding hardyZ
  -- hardyZ = (e^{iθ}·ζ(1/2+It)).re where hardyTheta uses Complex.I * (t/2)
  -- vs the goal which uses Complex.I * ↑t
  -- The difference may be in the argument convention
  rfl

-- ============================================================
-- Section 3: Block positivity and geometry
-- ============================================================

/-- hardyStart is positive for all k. -/
theorem hardyStart_pos' (k : ℕ) : 0 < hardyStart k := by
  unfold hardyStart; positivity

/-- t is positive when in any block. -/
theorem pos_of_in_block (k : ℕ) (t : ℝ) (ht : hardyStart k ≤ t) : 0 < t :=
  lt_of_lt_of_le (hardyStart_pos' k) ht

/-- On block k, hardyN t = k+1 (open block). -/
theorem hardyN_on_open_block (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    hardyN t = k + 1 :=
  hardyN_constant_on_block k t ht_lo ht_hi

-- ============================================================
-- Section 4: RS leading term structure
-- ============================================================

/-- The RS leading term on block k: (-1)^k · (2π/t)^{1/4} · Ψ(p). -/
def rsLeadingTerm (k : ℕ) (t : ℝ) : ℝ :=
  (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
    rsPsi (blockParam k t)

/-- The RS leading term is bounded by (2π/t)^{1/4} on any block. -/
theorem rsLeadingTerm_abs_le (k : ℕ) (t : ℝ) (ht : 0 < t)
    (_ht_lo : hardyStart k ≤ t) (_ht_hi : t ≤ hardyStart (k + 1)) :
    |rsLeadingTerm k t| ≤ (2 * Real.pi / t) ^ ((1 : ℝ) / 4) := by
  unfold rsLeadingTerm
  rw [abs_mul, abs_mul]
  have h1 : |(-1 : ℝ) ^ k| = 1 := by
    rw [abs_pow, abs_neg, abs_one, one_pow]
  rw [h1, one_mul]
  have h_coeff_nn : 0 ≤ (2 * Real.pi / t) ^ ((1 : ℝ) / 4) := by positivity
  rw [abs_of_nonneg h_coeff_nn]
  have h_psi_le : |rsPsi (blockParam k t)| ≤ 1 := by
    unfold rsPsi; exact abs_cos_le_one _
  linarith [mul_le_of_le_one_right h_coeff_nn h_psi_le]

-- ============================================================
-- Section 5: Sign structure
-- ============================================================

/-- (-1)^k = (-1)^{N-1} where N = k+1. -/
theorem neg_one_pow_block_eq (k : ℕ) :
    (-1 : ℝ) ^ k = (-1 : ℝ) ^ (k + 1 - 1) := by
  have h : k + 1 - 1 = k := Nat.succ_sub_one k
  rw [h]

/-- (-1)^k = (-1)^{(k+1)+1}. -/
theorem neg_one_pow_block_alt (k : ℕ) :
    (-1 : ℝ) ^ k = (-1 : ℝ) ^ ((k + 1) + 1) := by
  have : (k + 1) + 1 = k + 2 := by omega
  rw [this, pow_succ, pow_succ]
  ring

-- ============================================================
-- Section 6: (2π/t)^{1/4} factorization
-- ============================================================

/-- (2π/t)^{1/4} = (2π)^{1/4} · t^{-1/4}. -/
theorem two_pi_div_t_rpow_quarter (t : ℝ) (ht : 0 < t) :
    (2 * Real.pi / t) ^ ((1 : ℝ) / 4) =
    (2 * Real.pi) ^ ((1 : ℝ) / 4) * t ^ (-(1 : ℝ) / 4) := by
  have ht_nn : (0 : ℝ) ≤ t := le_of_lt ht
  rw [div_eq_mul_inv, Real.mul_rpow (by positivity : (0 : ℝ) ≤ 2 * Real.pi) (inv_nonneg.mpr ht_nn)]
  congr 1
  rw [show -(1 : ℝ) / 4 = -((1 : ℝ) / 4) from by ring, Real.rpow_neg ht_nn]
  exact Real.inv_rpow ht_nn _

-- ============================================================
-- Section 6a: Functional equation at the critical line
-- ============================================================

/-- Functional equation: ζ(1/2-it) = chi(1/2+it) · ζ(1/2+it) for t ≠ 0,
    where chi(s) = 2·(2π)^{-s}·Γ(s)·cos(πs/2).

    This is the foundation of the Riemann-Siegel formula: the RS correction
    arises from applying this to express the zeta remainder in terms of
    a second Dirichlet sum rotated by the chi factor. -/
theorem zeta_fe_critical_line (t : ℝ) (ht : t ≠ 0) :
    riemannZeta (1/2 - Complex.I * (t : ℂ)) =
    2 * (2 * ↑Real.pi) ^ (-(1/2 + Complex.I * (t : ℂ))) *
    Complex.Gamma (1/2 + Complex.I * (t : ℂ)) *
    Complex.cos (↑Real.pi * (1/2 + Complex.I * (t : ℂ)) / 2) *
    riemannZeta (1/2 + Complex.I * (t : ℂ)) := by
  have h_ne_nat : ∀ n : ℕ, (1/2 + Complex.I * (t : ℂ) : ℂ) ≠ -(n : ℂ) := by
    intro n h
    have hre := congr_arg Complex.re h
    simp [Complex.add_re, Complex.ofReal_re, Complex.mul_re, Complex.I_re, Complex.I_im,
          Complex.ofReal_im] at hre
    have : (0 : ℝ) ≤ (n : ℝ) := Nat.cast_nonneg n
    linarith
  have h_ne_one : (1/2 + Complex.I * (t : ℂ) : ℂ) ≠ 1 := by
    intro h
    have him := congr_arg Complex.im h
    simp [Complex.add_im, Complex.ofReal_im, Complex.mul_im, Complex.I_re, Complex.I_im,
          Complex.ofReal_re, Complex.one_im] at him
    exact ht him
  have h_fe := riemannZeta_one_sub h_ne_nat h_ne_one
  convert h_fe using 2
  ring

-- ============================================================
-- Section 6b: Concavity infrastructure for block analysis
-- ============================================================

/-- The increment √(a+p) - √(a) is decreasing in a (concavity of √).
    Specifically, √(k+2+p) - √(k+2) ≤ √(k+1+p) - √(k+1) for p ≥ 0.

    This is the key analytic ingredient for the antitone property of c(k):
    the correction ∫₀¹ (√(k+1+p) - √(k+1))·Ψ(p) dp is decreasing in k. -/
theorem sqrt_increment_antitone (k : ℕ) (p : ℝ) (hp : 0 ≤ p) :
    Real.sqrt ((k : ℝ) + 2 + p) - Real.sqrt ((k : ℝ) + 2) ≤
    Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1) := by
  by_cases hp0 : p = 0
  · simp [hp0]
  · have hp_pos : 0 < p := lt_of_le_of_ne hp (Ne.symm hp0)
    have hk1p : (0 : ℝ) < (k : ℝ) + 1 + p := by positivity
    have hk2p : (0 : ℝ) < (k : ℝ) + 2 + p := by positivity
    have h_denom1_pos : 0 < Real.sqrt ((k : ℝ) + 1 + p) + Real.sqrt ((k : ℝ) + 1) := by positivity
    have h_denom2_pos : 0 < Real.sqrt ((k : ℝ) + 2 + p) + Real.sqrt ((k : ℝ) + 2) := by positivity
    -- Rationalize: √(a+p) - √(a) = p/(√(a+p) + √(a))
    have h_rat1 : Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1) =
        p / (Real.sqrt ((k : ℝ) + 1 + p) + Real.sqrt ((k : ℝ) + 1)) := by
      rw [eq_div_iff h_denom1_pos.ne']
      nlinarith [Real.sq_sqrt (show (0:ℝ) ≤ (k:ℝ)+1 by positivity),
                 Real.sq_sqrt hk1p.le]
    have h_rat2 : Real.sqrt ((k : ℝ) + 2 + p) - Real.sqrt ((k : ℝ) + 2) =
        p / (Real.sqrt ((k : ℝ) + 2 + p) + Real.sqrt ((k : ℝ) + 2)) := by
      rw [eq_div_iff h_denom2_pos.ne']
      nlinarith [Real.sq_sqrt (show (0:ℝ) ≤ (k:ℝ)+2 by positivity),
                 Real.sq_sqrt hk2p.le]
    rw [h_rat2, h_rat1]
    -- p/(big sum) ≤ p/(small sum) since big sum ≥ small sum
    apply div_le_div_of_nonneg_left (le_of_lt hp_pos) h_denom1_pos
    have : Real.sqrt ((k : ℝ) + 2 + p) ≥ Real.sqrt ((k : ℝ) + 1 + p) :=
      Real.sqrt_le_sqrt (by linarith)
    have : Real.sqrt ((k : ℝ) + 2) ≥ Real.sqrt ((k : ℝ) + 1) :=
      Real.sqrt_le_sqrt (by linarith)
    linarith

-- ============================================================
-- Section 7: The atomic RS saddle-point bound — decomposed
-- ============================================================

-- ============================================================
-- Section 7a: Sub-lemma 1 — Chi modulus on the critical line
-- ============================================================

/-- Norm of a purely imaginary power of a positive real is 1.
    This is used in the chi modulus proof: ‖π^{it}‖ = 1. -/
theorem norm_cpow_I_mul_ofReal (a : ℝ) (ha : 0 < a) (t : ℝ) :
    ‖((a : ℂ) ^ (Complex.I * (t : ℂ)))‖ = 1 := by
  rw [Complex.norm_cpow_eq_rpow_re_of_pos ha]
  simp [Complex.mul_re, Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- Conjugation of 1/2+it: star(1/2+it) = 1/2-it. -/
theorem star_half_add_it (t : ℝ) :
    starRingEnd ℂ (1/2 + Complex.I * (t : ℂ)) = 1/2 - Complex.I * (t : ℂ) := by
  simp [map_add, map_mul, Complex.conj_I, Complex.conj_ofReal, map_ofNat]
  ring

/-- ζ(1/2-it) = conj(ζ(1/2+it)) by the conjugation symmetry of ζ. -/
theorem riemannZeta_conj_critical_line (t : ℝ) :
    riemannZeta (1/2 - Complex.I * (t : ℂ)) =
    starRingEnd ℂ (riemannZeta (1/2 + Complex.I * (t : ℂ))) := by
  rw [← star_half_add_it t]
  exact riemannZeta_conj (1/2 + Complex.I * (t : ℂ))

/-- From the functional equation and conjugation: χ(1/2+it) · ζ(1/2+it) = conj(ζ(1/2+it)).
    Combined from `zeta_fe_critical_line` and `riemannZeta_conj_critical_line`. -/
theorem chi_zeta_eq_conj_zeta (t : ℝ) (ht : t ≠ 0) :
    (2 : ℂ) * (2 * ↑Real.pi) ^ (-(1/2 + Complex.I * (t : ℂ))) *
      Complex.Gamma (1/2 + Complex.I * (t : ℂ)) *
      Complex.cos (↑Real.pi * (1/2 + Complex.I * (t : ℂ)) / 2) *
      riemannZeta (1/2 + Complex.I * (t : ℂ)) =
    starRingEnd ℂ (riemannZeta (1/2 + Complex.I * (t : ℂ))) := by
  rw [← riemannZeta_conj_critical_line t]
  exact (zeta_fe_critical_line t ht).symm

/-- The argument of 2π (a positive real) is not π. -/
private lemma two_pi_arg_ne_pi : (2 * (Real.pi : ℂ)).arg ≠ Real.pi := by
  have h2pi : (0 : ℝ) ≤ 2 * Real.pi := by positivity
  rw [show (2 : ℂ) * (Real.pi : ℂ) = ((2 * Real.pi : ℝ) : ℂ) by push_cast; ring]
  rw [Complex.arg_ofReal_of_nonneg h2pi]
  exact Real.pi_pos.ne

/-- Conjugation of the chi factor on the critical line:
    conj(χ(1/2+it)) = χ(1/2-it) = χ(1-(1/2+it)).
    Each factor conjugates: 2 is real, (2π)^{-s} → (2π)^{-s̄},
    Γ(s) → Γ(s̄), cos(πs/2) → cos(πs̄/2). -/
private lemma chi_conj_eq (t : ℝ) :
    starRingEnd ℂ ((2 : ℂ) * (2 * ↑Real.pi) ^ (-(1/2 + Complex.I * (t : ℂ))) *
      Complex.Gamma (1/2 + Complex.I * (t : ℂ)) *
      Complex.cos (↑Real.pi * (1/2 + Complex.I * (t : ℂ)) / 2)) =
    (2 : ℂ) * (2 * ↑Real.pi) ^ (-(1/2 - Complex.I * (t : ℂ))) *
      Complex.Gamma (1/2 - Complex.I * (t : ℂ)) *
      Complex.cos (↑Real.pi * (1/2 - Complex.I * (t : ℂ)) / 2) := by
  -- conj((2π)^{-s}) = (2π)^{-(1/2-it)}
  have h_cpow : (starRingEnd ℂ) ((2 * ↑Real.pi) ^ (-(1/2 + Complex.I * (t : ℂ)))) =
      (2 * ↑Real.pi) ^ (-(1/2 - Complex.I * (t : ℂ))) := by
    -- Use cpow_conj: x ^ conj n = conj (conj x ^ n) with x = 2π, n = -(1/2+it)
    -- Since conj(2π) = 2π and conj(-(1/2+it)) = -(1/2-it):
    -- (2π)^{-(1/2-it)} = conj((2π)^{-(1/2+it)})
    -- conj(x^n) = x^(conj n) when conj(x) = x (positive real base)
    -- cpow_conj: x ^ conj n = conj (conj x ^ n)
    -- With conj(2π) = 2π: (2π)^{conj n} = conj((2π)^n)
    -- i.e., conj((2π)^n) = (2π)^{conj n}
    have h_conj_base : starRingEnd ℂ ((2 : ℂ) * ↑Real.pi) = (2 : ℂ) * ↑Real.pi := by
      simp [map_mul, Complex.conj_ofReal, map_ofNat]
    have h_conj_exp : starRingEnd ℂ (-(1/2 + Complex.I * (t : ℂ))) =
        -(1/2 - Complex.I * (t : ℂ)) := by
      rw [map_neg, star_half_add_it]
    -- From cpow_conj: (2π)^{conj(-(1/2+it))} = conj(conj(2π)^{-(1/2+it)})
    have key := Complex.cpow_conj (2 * ↑Real.pi : ℂ) (-(1/2 + Complex.I * (t : ℂ))) two_pi_arg_ne_pi
    -- key : (2π)^{conj(-(1/2+it))} = conj(conj(2π)^{-(1/2+it)})
    rw [h_conj_exp] at key
    -- key : (2π)^{-(1/2-it)} = conj(conj(2π)^{-(1/2+it)})
    rw [h_conj_base] at key
    -- key : (2π)^{-(1/2-it)} = conj((2π)^{-(1/2+it)})
    exact key.symm
  -- conj(Γ(s)) = Γ(1/2-it)
  have h_gamma : (starRingEnd ℂ) (Complex.Gamma (1/2 + Complex.I * (t : ℂ))) =
      Complex.Gamma (1/2 - Complex.I * (t : ℂ)) := by
    have := Complex.Gamma_conj (1/2 + Complex.I * (t : ℂ))
    -- this : Gamma (conj (1/2+it)) = conj (Gamma (1/2+it))
    rw [star_half_add_it] at this
    exact this.symm
  -- conj(cos(πs/2)) = cos(π(1/2-it)/2)
  have h_cos : (starRingEnd ℂ) (Complex.cos (↑Real.pi * (1/2 + Complex.I * (t : ℂ)) / 2)) =
      Complex.cos (↑Real.pi * (1/2 - Complex.I * (t : ℂ)) / 2) := by
    have := Complex.cos_conj (↑Real.pi * (1/2 + Complex.I * (t : ℂ)) / 2)
    -- this : cos(conj(πs/2)) = conj(cos(πs/2))
    -- conj(πs/2) = π·conj(s)/2 = π(1/2-it)/2
    have h_arg : starRingEnd ℂ (↑Real.pi * (1/2 + Complex.I * (t : ℂ)) / 2) =
        ↑Real.pi * (1/2 - Complex.I * (t : ℂ)) / 2 := by
      have hs := star_half_add_it t
      -- hs : starRingEnd ℂ (1/2 + I*t) = 1/2 - I*t
      calc starRingEnd ℂ (↑Real.pi * (1/2 + Complex.I * ↑t) / 2)
          = starRingEnd ℂ (↑Real.pi) * starRingEnd ℂ (1/2 + Complex.I * ↑t) /
            starRingEnd ℂ (2 : ℂ) := by simp [map_div₀, map_mul]
        _ = ↑Real.pi * (1/2 - Complex.I * ↑t) / 2 := by
            rw [Complex.conj_ofReal, hs, map_ofNat]
    rw [h_arg] at this
    exact this.symm
  -- Distribute star over products and apply each component
  simp only [map_mul, map_ofNat, h_cpow, h_gamma, h_cos]

/-- cos(πs/2) · cos(π(1-s)/2) = sin(πs)/2.
    This uses cos(π/2-x) = sin(x) and cos(x)sin(x) = sin(2x)/2. -/
private lemma cos_mul_cos_one_sub (s : ℂ) :
    Complex.cos (↑Real.pi * s / 2) * Complex.cos (↑Real.pi * (1 - s) / 2) =
    Complex.sin (↑Real.pi * s) / 2 := by
  -- cos(π(1-s)/2) = cos(π/2 - πs/2) = sin(πs/2)
  have step1 : Complex.cos (↑Real.pi * (1 - s) / 2) = Complex.sin (↑Real.pi * s / 2) := by
    rw [show ↑Real.pi * (1 - s) / 2 = ↑Real.pi / 2 - ↑Real.pi * s / 2 by ring]
    rw [Complex.cos_pi_div_two_sub]
  rw [step1]
  -- cos(x) * sin(x) = sin(2x)/2
  rw [show ↑Real.pi * s = 2 * (↑Real.pi * s / 2) by ring]
  rw [Complex.sin_two_mul]
  ring

/-- The product χ(s)·χ(1-s) = 1 for s not a non-negative integer.
    Uses the Gamma reflection formula and the trig product identity. -/
private lemma chi_product_eq_one (s : ℂ) (_hs_nat : ∀ n : ℕ, s ≠ -(n : ℂ))
    (_hs1_nat : ∀ n : ℕ, (1 - s) ≠ -(n : ℂ))
    (h_sin : Complex.sin (↑Real.pi * s) ≠ 0) :
    ((2 : ℂ) * (2 * ↑Real.pi) ^ (-s) * Complex.Gamma s *
      Complex.cos (↑Real.pi * s / 2)) *
    ((2 : ℂ) * (2 * ↑Real.pi) ^ (-(1 - s)) * Complex.Gamma (1 - s) *
      Complex.cos (↑Real.pi * (1 - s) / 2)) = 1 := by
  -- Rearrange to group factors
  -- Product = 4 · (2π)^{-s} · (2π)^{-(1-s)} · Γ(s)·Γ(1-s) · cos(πs/2)·cos(π(1-s)/2)
  have h2pi_ne : (2 * ↑Real.pi : ℂ) ≠ 0 := by
    apply mul_ne_zero two_ne_zero
    exact Complex.ofReal_ne_zero.mpr Real.pi_ne_zero
  -- (2π)^{-s} · (2π)^{-(1-s)} = (2π)^{-1}
  have cpow_add_eq : ((2 : ℂ) * ↑Real.pi) ^ (-s) * ((2 : ℂ) * ↑Real.pi) ^ (-(1 - s)) =
      ((2 : ℂ) * ↑Real.pi) ^ ((-1 : ℂ)) := by
    rw [← Complex.cpow_add _ _ h2pi_ne]
    congr 1; ring
  -- Γ(s)·Γ(1-s) = π/sin(πs)
  have gamma_refl := Complex.Gamma_mul_Gamma_one_sub s
  -- cos(πs/2)·cos(π(1-s)/2) = sin(πs)/2
  have cos_prod := cos_mul_cos_one_sub s
  -- Assemble
  calc ((2 : ℂ) * (2 * ↑Real.pi) ^ (-s) * Complex.Gamma s *
        Complex.cos (↑Real.pi * s / 2)) *
      ((2 : ℂ) * (2 * ↑Real.pi) ^ (-(1 - s)) * Complex.Gamma (1 - s) *
        Complex.cos (↑Real.pi * (1 - s) / 2))
      = 4 * ((2 * ↑Real.pi) ^ (-s) * (2 * ↑Real.pi) ^ (-(1 - s))) *
        (Complex.Gamma s * Complex.Gamma (1 - s)) *
        (Complex.cos (↑Real.pi * s / 2) * Complex.cos (↑Real.pi * (1 - s) / 2)) := by ring
    _ = 4 * ((2 : ℂ) * ↑Real.pi) ^ ((-1 : ℂ)) *
        (↑Real.pi / Complex.sin (↑Real.pi * s)) *
        (Complex.sin (↑Real.pi * s) / 2) := by
        rw [cpow_add_eq, gamma_refl, cos_prod]
    _ = 1 := by
        have h_int : ((-1 : ℂ)) = ((-1 : ℤ) : ℂ) := by norm_cast
        rw [h_int, Complex.cpow_intCast, zpow_neg_one]
        have hpi_ne : (↑Real.pi : ℂ) ≠ 0 := Complex.ofReal_ne_zero.mpr Real.pi_ne_zero
        field_simp
        ring

/-- sin(π·(1/2+it)) ≠ 0 for t : ℝ.
    sin(π/2+πit) = cos(πit) = cosh(πt) ≥ 1 > 0. -/
private lemma sin_pi_half_add_it_ne_zero (t : ℝ) :
    Complex.sin (↑Real.pi * (1/2 + Complex.I * (t : ℂ))) ≠ 0 := by
  -- sin(π(1/2+it)) = sin(πit + π/2) = cos(πit) = cosh(πt)
  have h1 : ↑Real.pi * (1/2 + Complex.I * (t : ℂ)) =
      ↑Real.pi * Complex.I * (t : ℂ) + ↑Real.pi / 2 := by ring
  rw [h1, Complex.sin_add_pi_div_two]
  -- Goal: cos(πit) ≠ 0
  have h2 : (↑Real.pi : ℂ) * Complex.I * (t : ℂ) = (↑(Real.pi * t) : ℂ) * Complex.I := by
    push_cast; ring
  rw [h2, Complex.cos_mul_I]
  -- Goal: cosh(πt) ≠ 0 (as a complex number)
  exact_mod_cast (Real.cosh_pos (Real.pi * t)).ne'

/-- 1/2+it ≠ -(n : ℂ) for any n : ℕ. -/
private lemma half_add_it_ne_neg_nat (t : ℝ) (n : ℕ) :
    (1/2 + Complex.I * (t : ℂ) : ℂ) ≠ -(n : ℂ) := by
  intro h
  have hre := congr_arg Complex.re h
  simp [Complex.add_re, Complex.ofReal_re, Complex.mul_re, Complex.I_re, Complex.I_im,
        Complex.ofReal_im] at hre
  have : (0 : ℝ) ≤ (n : ℝ) := Nat.cast_nonneg n
  linarith

/-- 1/2-it ≠ -(n : ℂ) for any n : ℕ. -/
private lemma half_sub_it_ne_neg_nat (t : ℝ) (n : ℕ) :
    (1/2 - Complex.I * (t : ℂ) : ℂ) ≠ -(n : ℂ) := by
  intro h
  have hre := congr_arg Complex.re h
  simp [Complex.sub_re, Complex.ofReal_re, Complex.mul_re, Complex.I_re, Complex.I_im,
        Complex.ofReal_im] at hre
  have : (0 : ℝ) ≤ (n : ℝ) := Nat.cast_nonneg n
  linarith

/-- Modulus of χ(1/2+it) on the critical line.
    The proof shows χ(s)·conj(χ(s)) = χ(s)·χ(1-s) = 1 using the Gamma
    reflection formula Γ(s)Γ(1-s) = π/sin(πs), the trig identity
    cos(πs/2)·cos(π(1-s)/2) = sin(πs)/2, and (2π)^{-s}·(2π)^{-(1-s)} = (2π)^{-1}.
    Reference: Titchmarsh §4.14, Eq. (4.14.1). -/
theorem chi_modulus_critical_line (t : ℝ) (_ht : t ≠ 0) :
    ‖(2 : ℂ) * (2 * ↑Real.pi) ^ (-(1/2 + Complex.I * (t : ℂ))) *
      Complex.Gamma (1/2 + Complex.I * (t : ℂ)) *
      Complex.cos (↑Real.pi * (1/2 + Complex.I * (t : ℂ)) / 2)‖ = 1 := by
  -- Let χ = the expression. We show χ · conj(χ) = 1, hence ‖χ‖² = 1, hence ‖χ‖ = 1.
  set s : ℂ := 1/2 + Complex.I * (t : ℂ) with hs_def
  set χ : ℂ := (2 : ℂ) * (2 * ↑Real.pi) ^ (-s) *
    Complex.Gamma s * Complex.cos (↑Real.pi * s / 2) with hχ_def
  -- Step 1: conj(χ) = χ(1-s) where 1-s = 1/2-it on the critical line
  have h_1ms : (1 : ℂ) - s = 1/2 - Complex.I * (t : ℂ) := by
    rw [hs_def]; ring
  -- Step 2: Use chi_conj_eq to get conj(χ)
  have h_conj : starRingEnd ℂ χ =
      (2 : ℂ) * (2 * ↑Real.pi) ^ (-(1/2 - Complex.I * (t : ℂ))) *
        Complex.Gamma (1/2 - Complex.I * (t : ℂ)) *
        Complex.cos (↑Real.pi * (1/2 - Complex.I * (t : ℂ)) / 2) := by
    exact chi_conj_eq t
  -- Step 3: χ · conj(χ) = χ(s) · χ(1-s) = 1
  have h_prod : χ * starRingEnd ℂ χ = 1 := by
    rw [h_conj, hχ_def, ← h_1ms]
    exact chi_product_eq_one s (half_add_it_ne_neg_nat t)
      (by rw [h_1ms]; exact half_sub_it_ne_neg_nat t)
      (sin_pi_half_add_it_ne_zero t)
  -- Step 4: From χ · conj(χ) = 1, deduce ‖χ‖ = 1
  -- ‖χ‖² = ‖χ * conj(χ)‖ = ‖1‖ = 1
  have h_norm_sq : ‖χ‖ * ‖χ‖ = 1 := by
    have h1 : ‖χ * starRingEnd ℂ χ‖ = ‖(1 : ℂ)‖ := by rw [h_prod]
    rw [norm_mul, RCLike.norm_conj, norm_one] at h1
    exact h1
  -- ‖χ‖ ≥ 0 and ‖χ‖² = 1 implies ‖χ‖ = 1
  have h_nonneg : (0 : ℝ) ≤ ‖χ‖ := norm_nonneg χ
  nlinarith [sq_nonneg (‖χ‖ - 1)]

-- ============================================================
-- Section 7b: Sub-lemma 2 — ErrorTerm via zeta remainder
-- ============================================================

/-- **ErrorTerm as a real part of the zeta remainder**.

    ErrorTerm(t) = Re(e^{iθ} · ζ(1/2+it)) - 2·Re(e^{iθ} · ∑_{n≤N} n^{-s})
                 = Re(e^{iθ} · (ζ - ∑)) - Re(e^{iθ} · ∑)

    The first piece Re(e^{iθ}·remainder) connects to the functional equation;
    the second piece Re(e^{iθ}·partial_sum) is the MainTerm/2. -/
theorem errorTerm_eq_re_remainder (t : ℝ) :
    ErrorTerm t = (Complex.exp (Complex.I * hardyTheta t) *
      complexZetaRemainder t).re -
      (Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t).re := by
  -- ErrorTerm = Re(e^{iθ}·ζ) - 2·Re(e^{iθ}·∑)
  -- remainder = ζ - ∑, so Re(e^{iθ}·remainder) = Re(e^{iθ}·ζ) - Re(e^{iθ}·∑)
  -- Hence ErrorTerm = Re(e^{iθ}·remainder) - Re(e^{iθ}·∑)
  unfold complexZetaRemainder
  rw [mul_sub, Complex.sub_re]
  -- Goal: ErrorTerm t = Re(e^{iθ}·ζ) - Re(e^{iθ}·∑) - Re(e^{iθ}·∑)
  -- = Re(e^{iθ}·ζ) - 2·Re(e^{iθ}·∑)
  rw [errorTerm_structure]
  ring

-- ============================================================
-- Section 7c: Sub-lemma 3 — RS leading correction phase
-- ============================================================

/-- The RS phase function: on block k at parameter p = blockParam(k,t),
    the leading correction from the saddle-point analysis gives
    (-1)^{N-1} · cos(π(2p²-2p+1/4)) where N = k+1, i.e., (-1)^k · Ψ(p).

    This is the phase-matching identity that connects the steepest-descent
    evaluation of the contour integral to the Ψ function.

    Reference: Edwards Ch. 7, pp. 136-145; Gabcke 1979 §3. -/
theorem rs_phase_match (k : ℕ) (t : ℝ)
    (_ht_lo : hardyStart k ≤ t) (_ht_hi : t ≤ hardyStart (k + 1)) (_ht : 0 < t) :
    (-1 : ℝ) ^ k * rsPsi (blockParam k t) =
    (-1 : ℝ) ^ k * Real.cos (Real.pi * (2 * (blockParam k t) ^ 2 -
      2 * blockParam k t + 1/4)) := by
  -- This is definitional: rsPsi p = cos(π(2p²-2p+1/4))
  rfl

-- ============================================================
-- Section 7c+: Additional sub-lemmas for the saddle-point bound
-- ============================================================

/-- |Ψ(p)| ≤ 1 for all p (Ψ is a cosine function). -/
theorem rsPsi_abs_le_one (p : ℝ) : |rsPsi p| ≤ 1 := by
  unfold rsPsi
  exact abs_cos_le_one _

/-- Ψ(p) ≥ cos(π/4) for p ∈ [0,1].
    The argument π(2p²-2p+1/4) lies in [-π/4, π/4] where cos is decreasing,
    so Ψ(p) ≥ cos(π/4) = √2/2.

    This is the key quantitative lower bound used in `signed_errorTerm_nonneg_on_block`
    to show the RS leading term dominates the remainder. -/
theorem rsPsi_ge_cos_pi_four (p : ℝ) (hp : p ∈ Icc (0 : ℝ) 1) :
    Real.cos (Real.pi / 4) ≤ rsPsi p := by
  have ⟨hp0, hp1⟩ := hp
  simp only [rsPsi]
  have harg_abs : |Real.pi * (2 * p ^ 2 - 2 * p + 1/4)| ≤ Real.pi / 4 := by
    rw [abs_le]; constructor
    · have h1 : 0 ≤ 2 * (p - 1/2) ^ 2 := by positivity
      nlinarith [Real.pi_pos]
    · have h2 : 2 * p * (p - 1) ≤ 0 := by nlinarith
      nlinarith [Real.pi_pos]
  have hpi4_le_pi : Real.pi / 4 ≤ Real.pi :=
    div_le_self (le_of_lt Real.pi_pos) (by norm_num : (1 : ℝ) ≤ 4)
  rw [← Real.cos_abs (Real.pi * (2 * p ^ 2 - 2 * p + 1/4))]
  exact Real.strictAntiOn_cos.antitoneOn
    (Set.mem_Icc.mpr ⟨abs_nonneg _, le_trans harg_abs hpi4_le_pi⟩)
    (Set.mem_Icc.mpr ⟨le_of_lt (div_pos Real.pi_pos (by norm_num : (0:ℝ) < 4)), hpi4_le_pi⟩)
    harg_abs

/-- Ψ(p) ≤ 1 for all p ∈ [0,1].
    Combined with `rsPsi_ge_cos_pi_four`, gives cos(π/4) ≤ Ψ(p) ≤ 1. -/
theorem rsPsi_le_one (p : ℝ) : rsPsi p ≤ 1 := by
  have h := rsPsi_abs_le_one p
  exact le_of_abs_le h

/-- The absolute value of the RS leading correction is bounded by (2π/t)^{1/4}.
    This is because |(-1)^k| = 1 and |Ψ(p)| ≤ 1. -/
theorem rs_correction_abs_le (k : ℕ) (t : ℝ) (ht : 0 < t) :
    |(-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)| ≤
    (2 * Real.pi / t) ^ ((1 : ℝ) / 4) := by
  rw [abs_mul, abs_mul]
  have h_neg_one : |(-1 : ℝ) ^ k| = 1 := by
    simp [abs_pow, abs_neg, abs_one]
  rw [h_neg_one, one_mul]
  have h_rpow_nonneg : 0 ≤ (2 * Real.pi / t) ^ ((1 : ℝ) / 4) := by
    apply Real.rpow_nonneg
    exact div_nonneg (by positivity) (le_of_lt ht)
  calc |((2 * Real.pi / t) ^ ((1 : ℝ) / 4))| * |rsPsi (blockParam k t)|
      = (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * |rsPsi (blockParam k t)| := by
        rw [abs_of_nonneg h_rpow_nonneg]
    _ ≤ (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * 1 := by
        apply mul_le_mul_of_nonneg_left (rsPsi_abs_le_one _) h_rpow_nonneg
    _ = (2 * Real.pi / t) ^ ((1 : ℝ) / 4) := mul_one _

/-- ‖e^{iθ}‖ = 1 for any real θ (unit modulus of phase rotation). -/
theorem norm_exp_I_mul_real (θ : ℝ) :
    ‖Complex.exp (Complex.I * (θ : ℂ))‖ = 1 := by
  rw [mul_comm, Complex.norm_exp_ofReal_mul_I]

/-- The RS correction on block k with parameter p ∈ [0,1] satisfies
    (-1)^k · Ψ(p) > 0 when we multiply by (-1)^k.
    That is, (-1)^{2k} · Ψ(p) = Ψ(p) > 0.
    Equivalently: ((-1)^k)² · Ψ(p) = Ψ(p). -/
theorem neg_one_pow_sq_mul_rsPsi (k : ℕ) (p : ℝ) (_hp : p ∈ Icc (0 : ℝ) 1) :
    (-1 : ℝ) ^ k * ((-1 : ℝ) ^ k * rsPsi p) = rsPsi p := by
  rw [← mul_assoc]
  have h1 : (-1 : ℝ) ^ k * (-1 : ℝ) ^ k = 1 := by
    rw [← pow_add]; simp
  rw [h1, one_mul]

/-- hardyN(t) ≥ 1 for t ≥ 2π (i.e., when √(t/2π) ≥ 1).
    This ensures the partial sum has at least one term. -/
theorem hardyN_ge_one (t : ℝ) (ht : 2 * Real.pi ≤ t) :
    1 ≤ hardyN t := by
  unfold hardyN
  apply Nat.one_le_iff_ne_zero.mpr
  intro h
  have h_floor := Nat.floor_eq_zero.mp h
  have h_div : 1 ≤ t / (2 * Real.pi) := by
    rw [le_div_iff₀ (by positivity : (0 : ℝ) < 2 * Real.pi)]
    linarith
  have h_sqrt : 1 ≤ Real.sqrt (t / (2 * Real.pi)) := by
    rw [show (1 : ℝ) = Real.sqrt 1 from (Real.sqrt_one).symm]
    exact Real.sqrt_le_sqrt h_div
  linarith

/-- The (2π/t) factor is at most 1 for t ≥ 2π. -/
theorem two_pi_div_t_le_one (t : ℝ) (ht : 2 * Real.pi ≤ t) :
    2 * Real.pi / t ≤ 1 := by
  rw [div_le_one (lt_of_lt_of_le (by positivity) ht)]
  exact ht

/-- (2π/t)^{1/4} is at most 1 for t ≥ 2π. -/
theorem two_pi_div_t_rpow_quarter_le_one (t : ℝ) (ht : 2 * Real.pi ≤ t) :
    (2 * Real.pi / t) ^ ((1 : ℝ) / 4) ≤ 1 := by
  apply Real.rpow_le_one
  · exact div_nonneg (by positivity) (le_of_lt (lt_of_lt_of_le (by positivity) ht))
  · exact two_pi_div_t_le_one t ht
  · norm_num

/-- (2π/t)^{1/4} = (2π)^{1/4} · t^{-1/4} for t > 0.
    Factoring the rpow for matching the t^{-3/4} remainder scale. -/
theorem two_pi_div_t_rpow_factor (t : ℝ) (ht : 0 < t) :
    (2 * Real.pi / t) ^ ((1 : ℝ) / 4) =
    (2 * Real.pi) ^ ((1 : ℝ) / 4) * t ^ (-(1 : ℝ) / 4) := by
  have h2pi : (0 : ℝ) ≤ 2 * Real.pi := by positivity
  have ht_nn : (0 : ℝ) ≤ t := le_of_lt ht
  rw [show (2 * Real.pi / t : ℝ) = 2 * Real.pi * t⁻¹ from div_eq_mul_inv _ _]
  rw [mul_rpow h2pi (inv_nonneg.mpr ht_nn)]
  congr 1
  rw [show -(1 : ℝ) / 4 = -((1 : ℝ) / 4) from by ring]
  rw [Real.rpow_neg ht_nn, Real.inv_rpow ht_nn]

/-- t^{-3/4} = t^{-1/4} · t^{-1/2} for t > 0.
    Used to factor the remainder bound relative to the leading term. -/
theorem t_neg_three_quarter_factor (t : ℝ) (ht : 0 < t) :
    t ^ (-(3 : ℝ) / 4) = t ^ (-(1 : ℝ) / 4) * t ^ (-(1 : ℝ) / 2) := by
  rw [← Real.rpow_add ht]
  congr 1; ring

/-- The remainder-to-leading ratio: C_R · t^{-3/4} / ((2π/t)^{1/4})
    = C_R / (2π)^{1/4} · t^{-1/2} → 0 as t → ∞.

    This shows the saddle-point remainder is genuinely lower order than
    the leading RS correction, quantitatively: the ratio scales as t^{-1/2}. -/
theorem remainder_to_leading_ratio (C_R t : ℝ) (ht : 0 < t) :
    C_R * t ^ (-(3 : ℝ) / 4) =
    C_R / (2 * Real.pi) ^ ((1 : ℝ) / 4) *
    ((2 * Real.pi) ^ ((1 : ℝ) / 4) * t ^ (-(1 : ℝ) / 4) * t ^ (-(1 : ℝ) / 2)) := by
  rw [t_neg_three_quarter_factor t ht]
  have h2pi_ne : (2 * Real.pi) ^ ((1 : ℝ) / 4) ≠ 0 := ne_of_gt (by positivity)
  field_simp

/-- The ErrorTerm on a block is bounded by the leading term plus remainder.
    From the triangle inequality applied to the RS expansion:
    |ErrorTerm(t)| ≤ (2π/t)^{1/4} + C_R · t^{-3/4}

    This follows formally from saddle_point_remainder; here we state it as a
    consequence schema that any proof of the RS bound yields. -/
theorem errorTerm_abs_from_rs
    (C_R : ℝ) (hCR : 0 < C_R)
    (h_rs : ∀ k : ℕ, ∀ t : ℝ,
      hardyStart k ≤ t → t ≤ hardyStart (k + 1) → t > 0 →
        |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| ≤ C_R * t ^ (-(3 : ℝ) / 4))
    (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t ≤ hardyStart (k + 1)) (ht : 0 < t) :
    |ErrorTerm t| ≤ (2 * Real.pi / t) ^ ((1 : ℝ) / 4) + C_R * t ^ (-(3 : ℝ) / 4) := by
  have h1 := h_rs k t ht_lo ht_hi ht
  have h2 := rs_correction_abs_le k t ht
  -- |ET| ≤ |ET - correction| + |correction| ≤ C_R·t^{-3/4} + (2π/t)^{1/4}
  calc |ErrorTerm t|
      = |(ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)) +
          (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| := by ring_nf
    _ ≤ |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| +
        |(-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| := abs_add_le _ _
    _ ≤ C_R * t ^ (-(3 : ℝ) / 4) + (2 * Real.pi / t) ^ ((1 : ℝ) / 4) := by linarith
    _ = (2 * Real.pi / t) ^ ((1 : ℝ) / 4) + C_R * t ^ (-(3 : ℝ) / 4) := by ring

/-- The signed ErrorTerm (-1)^k · ErrorTerm(t) is bounded below by the signed RS correction
    minus the remainder. This is the key quantitative estimate used to show that
    the signed error has a definite sign on each block. -/
theorem signed_errorTerm_lower_bound
    (C_R : ℝ) (_hCR : 0 < C_R) (_hCR_le : C_R ≤ 1 / 2)
    (h_rs : ∀ k : ℕ, ∀ t : ℝ,
      hardyStart k ≤ t → t ≤ hardyStart (k + 1) → t > 0 →
        |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| ≤ C_R * t ^ (-(3 : ℝ) / 4))
    (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t ≤ hardyStart (k + 1)) (ht : 0 < t)
    (_hp : blockParam k t ∈ Icc (0 : ℝ) 1) :
    (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t) - C_R * t ^ (-(3 : ℝ) / 4) ≤
    (-1 : ℝ) ^ k * ErrorTerm t := by
  have h_abs := h_rs k t ht_lo ht_hi ht
  -- From |ET - L| ≤ R where L = (-1)^k·(2π/t)^{1/4}·Ψ(p) and R = C_R·t^{-3/4}:
  -- L - R ≤ ET (from |ET - L| ≤ R)
  have h_lower : (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
      rsPsi (blockParam k t) - C_R * t ^ (-(3 : ℝ) / 4) ≤ ErrorTerm t := by
    linarith [neg_abs_le (ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
        rsPsi (blockParam k t))]
  -- Also ET ≤ L + R
  have h_upper : ErrorTerm t ≤
      (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
      rsPsi (blockParam k t) + C_R * t ^ (-(3 : ℝ) / 4) := by
    linarith [le_abs_self (ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
        rsPsi (blockParam k t))]
  -- Now multiply by (-1)^k. Use (-1)^k ∈ {-1, 1}
  have h_sq : ((-1 : ℝ) ^ k) ^ 2 = 1 := by
    rw [← pow_mul]; simp
  -- (-1)^k · ET ≥ (-1)^k · ((-1)^k · leading · Ψ - R)
  --             = ((-1)^k)^2 · leading · Ψ - (-1)^k · R
  -- For the lower bound, we need to handle the sign of (-1)^k · R.
  -- Actually, we can prove it differently:
  -- |(-1)^k · ET - leading · Ψ| = |(-1)^k| · |ET - (-1)^k · leading · Ψ| ≤ R
  -- Wait, let's use the fact that (-1)^k · ((-1)^k · L) = L.
  -- From h_lower: (-1)^k · L - R ≤ ET
  -- Multiply by (-1)^k:
  -- If (-1)^k = 1: L - R ≤ ET = (-1)^k · ET ✓
  -- If (-1)^k = -1: -L + R ≥ -ET, i.e., (-1)·ET ≥ L - R ✓... wait
  -- Actually let's just use: (-1)^k · ET - Ψ(p)·(2π/t)^{1/4} =
  --   (-1)^k · (ET - (-1)^k · (2π/t)^{1/4} · Ψ), and |this| ≤ R
  -- Direct approach: (-1)^k · |ET - (-1)^k · L · Ψ| = |(-1)^k · ET - ((-1)^k)^2 · L · Ψ|
  --                                                    = |(-1)^k · ET - L · Ψ|
  have h_neg_one_abs : |(-1 : ℝ) ^ k| = 1 := by simp [abs_pow, abs_neg, abs_one]
  have key : |(-1 : ℝ) ^ k * ErrorTerm t -
      (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)| ≤
      C_R * t ^ (-(3 : ℝ) / 4) := by
    -- |(-1)^k · ET - L·Ψ| = |(-1)^k| · |ET - (-1)^k · L · Ψ| since (-1)^{2k} = 1
    rw [show (-1 : ℝ) ^ k * ErrorTerm t -
        (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t) =
        (-1 : ℝ) ^ k * ErrorTerm t -
        ((-1 : ℝ) ^ k) ^ 2 * ((2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t))
        from by rw [h_sq]; ring]
    rw [show (-1 : ℝ) ^ k * ErrorTerm t -
        ((-1 : ℝ) ^ k) ^ 2 * ((2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)) =
        (-1 : ℝ) ^ k * (ErrorTerm t -
        (-1 : ℝ) ^ k * ((2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)))
        from by ring]
    rw [abs_mul, h_neg_one_abs, one_mul]
    rw [show ErrorTerm t - (-1 : ℝ) ^ k *
        ((2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)) =
        ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
        rsPsi (blockParam k t) from by ring]
    exact h_abs
  linarith [neg_abs_le ((-1 : ℝ) ^ k * ErrorTerm t -
      (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t))]

-- ============================================================
-- Section 7d-pre: AFE sub-lemmas toward saddle-point remainder
-- ============================================================

/-- The ErrorTerm is bounded by the norm of the zeta remainder plus partial sum.

    |ErrorTerm(t)| = |Re(e^{iθ}·R) - Re(e^{iθ}·Σ)|
                   ≤ |Re(e^{iθ}·R)| + |Re(e^{iθ}·Σ)|
                   ≤ ‖R‖ + ‖Σ‖

    where R = complexZetaRemainder(t) and Σ = complexPartialSum(t).
    This is the basic triangle inequality decomposition. -/
theorem errorTerm_abs_le_norm_remainder_plus_sum (t : ℝ) :
    |ErrorTerm t| ≤ ‖Complex.exp (Complex.I * hardyTheta t) * complexZetaRemainder t‖ +
      ‖Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t‖ := by
  rw [errorTerm_eq_re_remainder]
  exact le_trans (abs_sub _ _) (add_le_add (Complex.abs_re_le_norm _) (Complex.abs_re_le_norm _))

/-- The phase factor e^{iθ} has unit modulus, so ‖e^{iθ}·z‖ = ‖z‖.
    Applied to the complexZetaRemainder. -/
theorem norm_phase_mul_remainder (t : ℝ) :
    ‖Complex.exp (Complex.I * hardyTheta t) * complexZetaRemainder t‖ =
    ‖complexZetaRemainder t‖ := by
  rw [Complex.norm_mul, norm_exp_I_mul_real, one_mul]

/-- The phase factor e^{iθ} has unit modulus, so ‖e^{iθ}·z‖ = ‖z‖.
    Applied to the complexPartialSum. -/
theorem norm_phase_mul_partialSum (t : ℝ) :
    ‖Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t‖ =
    ‖complexPartialSum t‖ := by
  rw [Complex.norm_mul, norm_exp_I_mul_real, one_mul]

/-- Simplified ErrorTerm bound using phase cancellation:
    |ErrorTerm(t)| ≤ ‖complexZetaRemainder(t)‖ + ‖complexPartialSum(t)‖ -/
theorem errorTerm_abs_le_norms (t : ℝ) :
    |ErrorTerm t| ≤ ‖complexZetaRemainder t‖ + ‖complexPartialSum t‖ := by
  calc |ErrorTerm t|
      ≤ ‖Complex.exp (Complex.I * hardyTheta t) * complexZetaRemainder t‖ +
        ‖Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t‖ :=
        errorTerm_abs_le_norm_remainder_plus_sum t
    _ = ‖complexZetaRemainder t‖ + ‖complexPartialSum t‖ := by
        rw [norm_phase_mul_remainder, norm_phase_mul_partialSum]

/-- The zeta remainder decomposes via the functional equation.
    For t ≠ 0:
      ζ(1/2 + it) = χ-factor · ζ(1/2 + it) (from the functional equation)

    The complexZetaRemainder = ζ(s) - Σ n^{-s} where s = 1/2 + it.
    This is purely definitional — it unpacks the definition. -/
theorem complexZetaRemainder_eq (t : ℝ) :
    complexZetaRemainder t =
    riemannZeta (1/2 + Complex.I * (t : ℂ)) - complexPartialSum t := rfl

/-- The ErrorTerm can be written as a difference of two Re terms involving
    the zeta function and the partial sum, with the remainder split.

    ErrorTerm(t) = Re(e^{iθ} · ζ(s)) - Re(e^{iθ} · Σ) - Re(e^{iθ} · Σ)
                 = Re(e^{iθ} · (ζ(s) - Σ)) - Re(e^{iθ} · Σ)

    This is the "one remainder + one sum" form used in the RS analysis.  -/
theorem errorTerm_as_remainder_minus_sum (t : ℝ) :
    ErrorTerm t = (Complex.exp (Complex.I * hardyTheta t) *
      complexZetaRemainder t).re -
      (Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t).re :=
  errorTerm_eq_re_remainder t

/-- The norm of the partial sum is bounded by a sum of inverse square roots.
    ‖Σ_{n≤N} (n+1)^{-1/2-it}‖ ≤ Σ_{n≤N} (n+1)^{-1/2}

    This follows from the triangle inequality and |(n+1)^{-it}| = 1 for real t. -/
theorem norm_complexPartialSum_le (t : ℝ) :
    ‖complexPartialSum t‖ ≤
    ∑ n ∈ Finset.range (hardyN t), ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  unfold complexPartialSum
  calc ‖∑ n ∈ Finset.range (hardyN t),
        ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖
      ≤ ∑ n ∈ Finset.range (hardyN t),
        ‖((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ :=
        norm_sum_le _ _
    _ = ∑ n ∈ Finset.range (hardyN t), ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        congr 1; ext n
        -- ‖(n+1)^{-1/2-it}‖ = (n+1)^{-1/2} since |z^w| = |z|^{Re(w)} for z > 0
        have hn_pos : (0 : ℝ) < (n : ℝ) + 1 := by positivity
        rw [show (n + 1 : ℂ) = ((n + 1 : ℝ) : ℂ) from by push_cast; ring]
        rw [Complex.norm_cpow_eq_rpow_re_of_pos hn_pos]
        congr 1
        simp [Complex.sub_re, Complex.neg_re, Complex.mul_re,
              Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- On block k (open interval), the partial sum has exactly k+1 terms.
    Combined with the inverse square root bound, this gives:
    ‖complexPartialSum(t)‖ ≤ Σ_{n=1}^{k+1} n^{-1/2}
    which is bounded above by 2√(k+1) (integral comparison). -/
theorem partialSum_term_count (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    Finset.card (Finset.range (hardyN t)) = k + 1 := by
  rw [Finset.card_range, hardyN_on_open_block k t ht_lo ht_hi]

/-- The error term representation via the remainder has bounded real parts.
    |Re(e^{iθ} · R)| ≤ ‖R‖ where R = complexZetaRemainder(t).
    This is the basic abs_re_le_norm applied to our specific terms. -/
theorem abs_re_phase_remainder_le (t : ℝ) :
    |(Complex.exp (Complex.I * hardyTheta t) * complexZetaRemainder t).re| ≤
    ‖complexZetaRemainder t‖ := by
  calc |(Complex.exp (Complex.I * hardyTheta t) * complexZetaRemainder t).re|
      ≤ ‖Complex.exp (Complex.I * hardyTheta t) * complexZetaRemainder t‖ :=
        Complex.abs_re_le_norm _
    _ = ‖complexZetaRemainder t‖ := norm_phase_mul_remainder t

/-- Similarly for the partial sum term. -/
theorem abs_re_phase_partialSum_le (t : ℝ) :
    |(Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t).re| ≤
    ‖complexPartialSum t‖ := by
  calc |(Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t).re|
      ≤ ‖Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t‖ :=
        Complex.abs_re_le_norm _
    _ = ‖complexPartialSum t‖ := norm_phase_mul_partialSum t

-- ============================================================
-- Section 7d-pre2: Functional equation decomposition of the remainder
-- ============================================================

/-- The chi factor on the critical line: χ(s) for s = 1/2 + it. -/
def chiFactor (t : ℝ) : ℂ :=
  2 * (2 * ↑Real.pi) ^ (-(1/2 + Complex.I * (t : ℂ))) *
    Complex.Gamma (1/2 + Complex.I * (t : ℂ)) *
    Complex.cos (↑Real.pi * (1/2 + Complex.I * (t : ℂ)) / 2)

/-- The reflected partial sum Σ_{n≤N} (n+1)^{-(1/2-it)} at 1-s = 1/2 - it. -/
def reflectedPartialSum (t : ℝ) : ℂ :=
  ∑ n ∈ Finset.range (hardyN t),
    ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))

/-- The reflected zeta remainder: ζ(1/2-it) - Σ_{n≤N} n^{-(1/2-it)}. -/
def reflectedZetaRemainder (t : ℝ) : ℂ :=
  riemannZeta (1/2 - Complex.I * (t : ℂ)) - reflectedPartialSum t

/-- Via the functional equation, the reflected zeta satisfies:
    ζ(1/2-it) = χ(1/2+it)·ζ(1/2+it)

    This means:
    complexZetaRemainder(t) = ζ(s) - Σ n^{-s}
    where ζ(s) can be related to ζ(1-s) via the chi factor.

    The actual RS decomposition adds and subtracts the reflected partial sum:
    ζ(s) - Σ n^{-s} = (ζ(s) - Σ n^{-s}) ← this IS the remainder by definition.

    The FE connects the TWO remainders: since ζ(1-s) = χ(s)·ζ(s),
    ζ(1-s) - reflectedPartialSum(t) = χ(s)·ζ(s) - reflectedPartialSum(t)
    = χ(s)·(complexPartialSum(t) + complexZetaRemainder(t)) - reflectedPartialSum(t)

    This gives a system relating the remainder and reflected remainder. -/
theorem zeta_reflected_via_fe (t : ℝ) (ht : t ≠ 0) :
    riemannZeta (1/2 - Complex.I * (t : ℂ)) =
    chiFactor t * riemannZeta (1/2 + Complex.I * (t : ℂ)) := by
  unfold chiFactor
  exact zeta_fe_critical_line t ht

/-- The reflected zeta remainder in terms of chi and the forward zeta remainder.
    reflectedZetaRemainder = χ(s)·ζ(s) - reflectedPartialSum
                           = χ(s)·(partialSum + zetaRemainder) - reflectedPartialSum -/
theorem reflected_remainder_via_fe (t : ℝ) (ht : t ≠ 0) :
    reflectedZetaRemainder t =
    chiFactor t * (complexPartialSum t + complexZetaRemainder t) -
    reflectedPartialSum t := by
  unfold reflectedZetaRemainder complexZetaRemainder
  rw [zeta_reflected_via_fe t ht]
  ring

/-- The chi factor has unit modulus on the critical line: ‖χ(1/2+it)‖ = 1.
    This is a repackaging of `chi_modulus_critical_line`. -/
theorem chiFactor_norm_eq_one (t : ℝ) (ht : t ≠ 0) :
    ‖chiFactor t‖ = 1 := by
  unfold chiFactor
  exact chi_modulus_critical_line t ht

/-- The first component of the FE decomposition: the chi-rotated reflected tail.
    ‖χ(s)·reflected_remainder‖ = ‖reflected_remainder‖ since |χ| = 1. -/
theorem norm_chi_reflected_remainder (t : ℝ) (ht : t ≠ 0) :
    ‖chiFactor t * reflectedZetaRemainder t‖ = ‖reflectedZetaRemainder t‖ := by
  rw [Complex.norm_mul, chiFactor_norm_eq_one t ht, one_mul]

/-- The complexZetaRemainder decomposes into a "chi-reflected" term.
    Using ζ(s) = ζ(s), and adding/subtracting the reflected remainder:
    ζ(s) - partialSum = ζ(s) - partialSum
    This is tautological. The FE connects ζ(s) and ζ(1-s), but the
    DIRECT decomposition of the remainder into saddle-point terms
    goes through the contour integral representation, not the FE.

    The key use of the FE is via |χ(s)| = 1, which gives:
    ‖ζ(1-s) - reflected_sum‖ = ‖χ(s)·ζ(s) - reflected_sum‖.
    On the critical line, the symmetry ζ(s) ↔ χ(s)·ζ(s) means
    the reflected remainder has the SAME size as the forward remainder
    (up to the phase interaction with the partial sums). -/
theorem norm_reflected_remainder_bound (t : ℝ) (ht : t ≠ 0) :
    ‖reflectedZetaRemainder t‖ ≤
    ‖chiFactor t‖ * (‖complexPartialSum t‖ + ‖complexZetaRemainder t‖) +
    ‖reflectedPartialSum t‖ := by
  rw [reflected_remainder_via_fe t ht]
  calc ‖chiFactor t * (complexPartialSum t + complexZetaRemainder t) -
      reflectedPartialSum t‖
    ≤ ‖chiFactor t * (complexPartialSum t + complexZetaRemainder t)‖ +
      ‖reflectedPartialSum t‖ := by
        exact le_trans (norm_sub_le _ _) (by linarith [norm_nonneg (reflectedPartialSum t)])
    _ = ‖chiFactor t‖ * ‖complexPartialSum t + complexZetaRemainder t‖ +
      ‖reflectedPartialSum t‖ := by rw [Complex.norm_mul]
    _ ≤ ‖chiFactor t‖ * (‖complexPartialSum t‖ + ‖complexZetaRemainder t‖) +
      ‖reflectedPartialSum t‖ := by
        linarith [mul_le_mul_of_nonneg_left (norm_add_le (complexPartialSum t)
          (complexZetaRemainder t)) (norm_nonneg (chiFactor t))]

/-- Each term (n+1)^{-1/2} is bounded by 1 for n ∈ ℕ, since n+1 ≥ 1. -/
theorem rpow_neg_half_le_one (n : ℕ) :
    ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) ≤ 1 := by
  apply Real.rpow_le_one_of_one_le_of_nonpos
  · -- 1 ≤ (n+1 : ℝ)
    have : (0 : ℝ) ≤ (n : ℝ) := Nat.cast_nonneg n
    linarith
  · -- -(1/2 : ℝ) ≤ 0
    norm_num

/-- The partial sum norm is bounded by the number of terms:
    ‖complexPartialSum(t)‖ ≤ hardyN(t). -/
theorem partialSum_norm_le_hardyN (t : ℝ) :
    ‖complexPartialSum t‖ ≤ (hardyN t : ℝ) := by
  calc ‖complexPartialSum t‖
      ≤ ∑ n ∈ Finset.range (hardyN t), ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) :=
        norm_complexPartialSum_le t
    _ ≤ ∑ _n ∈ Finset.range (hardyN t), (1 : ℝ) := by
        apply Finset.sum_le_sum; intro n _
        exact rpow_neg_half_le_one n
    _ = (hardyN t : ℝ) := by simp [Finset.sum_const, Finset.card_range]

/-- On block k (open), ‖complexPartialSum(t)‖ ≤ k+1 (crude but sorry-free). -/
theorem partialSum_norm_le_block_count (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ‖complexPartialSum t‖ ≤ (k + 1 : ℝ) := by
  calc ‖complexPartialSum t‖
      ≤ (hardyN t : ℝ) := partialSum_norm_le_hardyN t
    _ = ((k + 1 : ℕ) : ℝ) := by
        rw [hardyN_on_open_block k t ht_lo ht_hi]
    _ = (k + 1 : ℝ) := by push_cast; ring

/-- The reflected partial sum also satisfies the same norm bound
    (since |(n+1)^{-1/2+it}| = (n+1)^{-1/2} = |(n+1)^{-1/2-it}|). -/
theorem norm_reflectedPartialSum_le (t : ℝ) :
    ‖reflectedPartialSum t‖ ≤
    ∑ n ∈ Finset.range (hardyN t), ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  unfold reflectedPartialSum
  calc ‖∑ n ∈ Finset.range (hardyN t),
        ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))‖
      ≤ ∑ n ∈ Finset.range (hardyN t),
        ‖((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))‖ :=
        norm_sum_le _ _
    _ = ∑ n ∈ Finset.range (hardyN t), ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        congr 1; ext n
        have hn_pos : (0 : ℝ) < (n : ℝ) + 1 := by positivity
        rw [show (n + 1 : ℂ) = ((n + 1 : ℝ) : ℂ) from by push_cast; ring]
        rw [Complex.norm_cpow_eq_rpow_re_of_pos hn_pos]
        congr 1
        simp [Complex.add_re, Complex.neg_re, Complex.mul_re,
              Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- The saddle-point phase function: for the steepest descent analysis,
    the phase of the n-th term relative to the saddle at w₀ = √(t/2π) is:
    φ_n(t) = hardyTheta(t) - t·log(n+1)
    This is the argument of the oscillatory factor in each term. -/
def saddlePhase (n : ℕ) (t : ℝ) : ℝ :=
  hardyTheta t - t * Real.log (n + 1)

/-- The n-th term of the partial sum, expressed using the saddle phase:
    (n+1)^{-1/2} · cos(φ_n(t)) = Re(e^{iθ} · (n+1)^{-s})
    This is exactly `cpow_re_cos` repackaged with `saddlePhase`. -/
theorem partial_sum_term_via_phase (n : ℕ) (t : ℝ) :
    (Complex.exp (Complex.I * hardyTheta t) *
      ((n + 1 : ℂ) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))).re =
    ((n + 1 : ℝ) ^ (-(1/2 : ℝ))) * Real.cos (saddlePhase n t) := by
  unfold saddlePhase
  exact cpow_re_cos n t

/-- The saddle-point is at index N(t) where N(t) = ⌊√(t/2π)⌋.
    The phase at the saddle point n = N(t)-1 (i.e., the N-th term) satisfies:
    φ_{N-1}(t) ≈ hardyTheta(t) - t·log(√(t/2π))
                = hardyTheta(t) - (t/2)·log(t/2π)

    At the critical line, hardyTheta(t) ≈ (t/2)·log(t/2π) - t/2 - π/8,
    so φ_{N-1} ≈ -t/2 - π/8, giving a slowly varying phase. -/
theorem saddlePhase_at_saddle_approx (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (_ht_hi : t < hardyStart (k + 1))
    (ht_pos : 0 < t) :
    saddlePhase k t = hardyTheta t - t * Real.log (k + 1) := by
  unfold saddlePhase; ring

-- ============================================================
-- Section 7d-pre3: AFE remainder decomposition via functional equation
-- ============================================================

/-- The chi factor is nonzero on the critical line (since ‖χ‖ = 1 for t ≠ 0). -/
theorem chiFactor_ne_zero (t : ℝ) (ht : t ≠ 0) : chiFactor t ≠ 0 := by
  intro h
  have := chiFactor_norm_eq_one t ht
  rw [h, norm_zero] at this
  exact one_ne_zero this.symm

/-- ζ(1-s) = reflectedPartialSum + reflectedZetaRemainder, by definition.
    This is the definitional decomposition of ζ at the reflected point. -/
theorem reflected_zeta_decomp (t : ℝ) :
    riemannZeta (1/2 - Complex.I * (t : ℂ)) =
    reflectedPartialSum t + reflectedZetaRemainder t := by
  unfold reflectedZetaRemainder
  ring

/-- ζ(s) = ζ(s), decomposed as partialSum + zetaRemainder. -/
theorem forward_zeta_decomp (t : ℝ) :
    riemannZeta (1/2 + Complex.I * (t : ℂ)) =
    complexPartialSum t + complexZetaRemainder t := by
  unfold complexZetaRemainder
  ring

/-- The forward zeta remainder expressed via the FE and the reflected terms.
    ζ(s) = χ⁻¹ · ζ(1-s), so:
    complexZetaRemainder = χ⁻¹ · (reflectedPS + reflectedRemainder) - partialSum

    Proved by multiplying the FE identity by χ⁻¹ from the left. -/
theorem forward_remainder_via_fe (t : ℝ) (ht : t ≠ 0) :
    complexZetaRemainder t =
    (chiFactor t)⁻¹ * (reflectedPartialSum t + reflectedZetaRemainder t) -
    complexPartialSum t := by
  -- From zeta_reflected_via_fe: ζ(1-s) = χ · ζ(s)
  -- So ζ(s) = χ⁻¹ · ζ(1-s)
  -- And complexZetaRemainder = ζ(s) - partialSum = χ⁻¹ · ζ(1-s) - partialSum
  have hchi := chiFactor_ne_zero t ht
  have hfe := zeta_reflected_via_fe t ht
  -- ζ(1-s) = χ · ζ(s), so χ⁻¹ · ζ(1-s) = ζ(s)
  have hzeta : riemannZeta (1/2 + Complex.I * (t : ℂ)) =
      (chiFactor t)⁻¹ * riemannZeta (1/2 - Complex.I * (t : ℂ)) := by
    rw [hfe, inv_mul_cancel_left₀ hchi]
  rw [← reflected_zeta_decomp]
  unfold complexZetaRemainder
  rw [hzeta]

/-- The forward zeta remainder splits as two pieces:
    complexZetaRemainder = (χ⁻¹ · reflectedPS - partialSum) + χ⁻¹ · reflectedRemainder

    The FIRST piece (χ⁻¹ · reflectedPS - partialSum) captures the "Dirichlet polynomial
    mismatch" between the forward and reflected partial sums. On the critical line,
    this is the source of the RS leading correction term.

    The SECOND piece (χ⁻¹ · reflectedRemainder) is the "tail" contribution from the
    reflected approximate functional equation. -/
theorem forward_remainder_split (t : ℝ) (ht : t ≠ 0) :
    complexZetaRemainder t =
    ((chiFactor t)⁻¹ * reflectedPartialSum t - complexPartialSum t) +
    (chiFactor t)⁻¹ * reflectedZetaRemainder t := by
  rw [forward_remainder_via_fe t ht]
  ring

/-- The ErrorTerm decomposes into a "polynomial mismatch" piece and
    a "reflected tail" piece, via the functional equation.

    ErrorTerm(t) = Re(e^{iθ} · zetaRemainder) - Re(e^{iθ} · partialSum)
                 = Re(e^{iθ} · (χ⁻¹·reflectedPS - partialSum))
                   + Re(e^{iθ} · χ⁻¹·reflectedRemainder)
                   - Re(e^{iθ} · partialSum)

    This is the structural AFE decomposition that separates the "saddle-point
    contribution" (from the polynomial mismatch) from the "tail error". -/
theorem errorTerm_fe_decomposition (t : ℝ) (ht : t ≠ 0) :
    ErrorTerm t =
    (Complex.exp (Complex.I * hardyTheta t) *
      ((chiFactor t)⁻¹ * reflectedPartialSum t - complexPartialSum t)).re +
    (Complex.exp (Complex.I * hardyTheta t) *
      ((chiFactor t)⁻¹ * reflectedZetaRemainder t)).re -
    (Complex.exp (Complex.I * hardyTheta t) * complexPartialSum t).re := by
  rw [errorTerm_eq_re_remainder t]
  congr 1
  -- Need: Re(e^{iθ} · zetaRemainder) = Re(e^{iθ} · (χ⁻¹·rPS - pS)) + Re(e^{iθ} · χ⁻¹·rR)
  rw [forward_remainder_split t ht]
  rw [mul_add, Complex.add_re]

/-- Norm bound on the "reflected tail" piece: since ‖χ⁻¹‖ = 1, we have
    ‖χ⁻¹ · reflectedRemainder‖ = ‖reflectedRemainder‖. -/
theorem norm_inv_chi_reflected_remainder (t : ℝ) (ht : t ≠ 0) :
    ‖(chiFactor t)⁻¹ * reflectedZetaRemainder t‖ =
    ‖reflectedZetaRemainder t‖ := by
  rw [Complex.norm_mul, norm_inv, chiFactor_norm_eq_one t ht, inv_one, one_mul]

/-- Norm bound on the "polynomial mismatch" piece:
    ‖χ⁻¹ · reflectedPS - partialSum‖ ≤ ‖reflectedPS‖ + ‖partialSum‖.
    (Triangle inequality with ‖χ⁻¹‖ = 1.) -/
theorem norm_polynomial_mismatch_le (t : ℝ) (ht : t ≠ 0) :
    ‖(chiFactor t)⁻¹ * reflectedPartialSum t - complexPartialSum t‖ ≤
    ‖reflectedPartialSum t‖ + ‖complexPartialSum t‖ := by
  calc ‖(chiFactor t)⁻¹ * reflectedPartialSum t - complexPartialSum t‖
      ≤ ‖(chiFactor t)⁻¹ * reflectedPartialSum t‖ + ‖complexPartialSum t‖ :=
        norm_sub_le _ _
    _ = ‖reflectedPartialSum t‖ + ‖complexPartialSum t‖ := by
        congr 1
        rw [Complex.norm_mul, norm_inv, chiFactor_norm_eq_one t ht, inv_one, one_mul]

/-- The forward zeta remainder norm is bounded by the reflected remainder
    norm plus both partial sum norms.
    ‖zetaRemainder‖ ≤ ‖reflectedRemainder‖ + ‖reflectedPS‖ + ‖partialSum‖ -/
theorem forward_remainder_norm_bound (t : ℝ) (ht : t ≠ 0) :
    ‖complexZetaRemainder t‖ ≤
    ‖reflectedZetaRemainder t‖ + ‖reflectedPartialSum t‖ +
    ‖complexPartialSum t‖ := by
  rw [forward_remainder_split t ht]
  calc ‖((chiFactor t)⁻¹ * reflectedPartialSum t - complexPartialSum t) +
        (chiFactor t)⁻¹ * reflectedZetaRemainder t‖
      ≤ ‖(chiFactor t)⁻¹ * reflectedPartialSum t - complexPartialSum t‖ +
        ‖(chiFactor t)⁻¹ * reflectedZetaRemainder t‖ :=
        norm_add_le _ _
    _ ≤ (‖reflectedPartialSum t‖ + ‖complexPartialSum t‖) +
        ‖reflectedZetaRemainder t‖ := by
        linarith [norm_polynomial_mismatch_le t ht,
                  norm_inv_chi_reflected_remainder t ht]
    _ = ‖reflectedZetaRemainder t‖ + ‖reflectedPartialSum t‖ +
        ‖complexPartialSum t‖ := by ring

/-- The ErrorTerm absolute value is bounded by the reflected remainder
    plus two copies of the partial sum norms:
    |ErrorTerm(t)| ≤ ‖reflectedRemainder‖ + 2·‖reflectedPS‖ + 2·‖partialSum‖

    This follows from the fe_decomposition and triangle inequality. -/
theorem errorTerm_abs_via_fe_bound (t : ℝ) (ht : t ≠ 0) :
    |ErrorTerm t| ≤
    ‖reflectedZetaRemainder t‖ +
    ‖reflectedPartialSum t‖ + ‖complexPartialSum t‖ +
    ‖complexPartialSum t‖ := by
  -- Use the known bound: |ErrorTerm| ≤ ‖zetaRemainder‖ + ‖partialSum‖
  calc |ErrorTerm t|
      ≤ ‖complexZetaRemainder t‖ + ‖complexPartialSum t‖ :=
        errorTerm_abs_le_norms t
    _ ≤ (‖reflectedZetaRemainder t‖ + ‖reflectedPartialSum t‖ +
        ‖complexPartialSum t‖) + ‖complexPartialSum t‖ := by
        linarith [forward_remainder_norm_bound t ht]

/-- On block k, combining the partial sum bound ‖partialSum‖ ≤ k+1
    with the reflected partial sum bound, we get a concrete ErrorTerm bound
    in terms of the reflected remainder and k. -/
theorem errorTerm_abs_on_block_via_fe (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    |ErrorTerm t| ≤
    ‖reflectedZetaRemainder t‖ + 3 * ((k : ℝ) + 1) := by
  have hps : ‖complexPartialSum t‖ ≤ (k + 1 : ℝ) :=
    partialSum_norm_le_block_count k t ht_lo ht_hi
  have hrps : ‖reflectedPartialSum t‖ ≤ (hardyN t : ℝ) := by
    calc ‖reflectedPartialSum t‖
        ≤ ∑ n ∈ Finset.range (hardyN t), ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) :=
          norm_reflectedPartialSum_le t
      _ ≤ ∑ _n ∈ Finset.range (hardyN t), (1 : ℝ) := by
          apply Finset.sum_le_sum; intro n _; exact rpow_neg_half_le_one n
      _ = (hardyN t : ℝ) := by simp [Finset.sum_const, Finset.card_range]
  have hN : (hardyN t : ℝ) = ((k + 1 : ℕ) : ℝ) := by
    rw [hardyN_on_open_block k t ht_lo ht_hi]
  rw [hN] at hrps
  have hrps' : ‖reflectedPartialSum t‖ ≤ (k + 1 : ℝ) := by push_cast at hrps; linarith
  calc |ErrorTerm t|
      ≤ ‖reflectedZetaRemainder t‖ +
        ‖reflectedPartialSum t‖ + ‖complexPartialSum t‖ +
        ‖complexPartialSum t‖ :=
        errorTerm_abs_via_fe_bound t ht
    _ ≤ ‖reflectedZetaRemainder t‖ + (k + 1 : ℝ) + (k + 1 : ℝ) + (k + 1 : ℝ) := by
        linarith
    _ = ‖reflectedZetaRemainder t‖ + 3 * ((k : ℝ) + 1) := by ring

-- ============================================================
-- Section 7d-pre4: RS leading term extraction from FE
-- ============================================================

/-- The (N+1)-th term of the reflected partial sum, extracted as the RS leading term
    from the functional equation perspective. On block k, hardyN(t) = k+1, so the
    N+1 = k+2 term of the reflected sum is the FIRST term NOT in reflectedPartialSum.
    This is the leading correction in the Riemann-Siegel formula.

    rsLeadingFromFE t = (hardyN t + 1)^{-1/2+it} · χ(t)⁻¹ -/
def rsLeadingFromFE (t : ℝ) : ℂ :=
  (chiFactor t)⁻¹ * ((hardyN t + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))

/-- The modulus of rsLeadingFromFE equals (hardyN t + 1)^{-1/2} when t ≠ 0,
    since |χ⁻¹| = 1 on the critical line.

    This is the amplitude of the RS leading correction term: O(N^{-1/2}) = O(t^{-1/4}). -/
theorem norm_rsLeadingFromFE (t : ℝ) (ht : t ≠ 0) :
    ‖rsLeadingFromFE t‖ = ((hardyN t + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  unfold rsLeadingFromFE
  rw [Complex.norm_mul, norm_inv, chiFactor_norm_eq_one t ht, inv_one, one_mul]
  have hN_pos : (0 : ℝ) < (hardyN t : ℝ) + 1 := by positivity
  rw [show (hardyN t + 1 : ℂ) = ((hardyN t + 1 : ℝ) : ℂ) from by push_cast; ring]
  rw [Complex.norm_cpow_eq_rpow_re_of_pos hN_pos]
  congr 1
  simp [Complex.add_re, Complex.neg_re, Complex.mul_re,
        Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- On block k, ‖rsLeadingFromFE(t)‖ = (k+2)^{-1/2}, since hardyN(t) = k+1. -/
theorem norm_rsLeadingFromFE_on_block (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ‖rsLeadingFromFE t‖ = ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) := by
  rw [norm_rsLeadingFromFE t ht]
  congr 1
  have hN := hardyN_on_open_block k t ht_lo ht_hi
  rw [hN]; push_cast; ring

/-- The RS leading term amplitude decays like t^{-1/4} on blocks:
    (k+2)^{-1/2} ≤ (k+1)^{-1/2} for the partial sum amplitude comparison. -/
theorem rsLeadingFromFE_amplitude_le (k : ℕ) :
    ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) ≤ ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  apply Real.rpow_le_rpow_of_exponent_nonpos
  · positivity
  · exact_mod_cast (show (k : ℕ) + 1 ≤ k + 2 by omega)
  · norm_num

/-- The chi-inverse has unit modulus on the critical line:
    ‖χ⁻¹‖ = 1. This follows from ‖χ‖ = 1 and ‖z⁻¹‖ = ‖z‖⁻¹. -/
theorem norm_chiFactor_inv_eq_one (t : ℝ) (ht : t ≠ 0) :
    ‖(chiFactor t)⁻¹‖ = 1 := by
  rw [norm_inv, chiFactor_norm_eq_one t ht, inv_one]

/-- The polynomial mismatch (χ⁻¹·reflectedPS - partialSum) decomposes as a
    sum over the SAME index set. Each term pair is:
    χ⁻¹·(n+1)^{-1/2+it} - (n+1)^{-1/2-it}

    The difference is 2i·sin(arg(χ⁻¹))·(n+1)^{-1/2} (phase rotation). -/
theorem polynomial_mismatch_term_structure (t : ℝ) (ht : t ≠ 0) (n : ℕ)
    (hn : n < hardyN t) :
    ‖(chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
     ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ ≤
    2 * ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  have hn_pos : (0 : ℝ) < (n : ℝ) + 1 := by positivity
  calc ‖(chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖
      ≤ ‖(chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))‖ +
        ‖((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ :=
        norm_sub_le _ _
    _ = ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) + ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        congr 1
        · -- First term: |χ⁻¹| = 1, so |χ⁻¹ · z| = |z|
          rw [Complex.norm_mul, norm_inv, chiFactor_norm_eq_one t ht, inv_one, one_mul]
          rw [show (n + 1 : ℂ) = ((n + 1 : ℝ) : ℂ) from by push_cast; ring]
          rw [Complex.norm_cpow_eq_rpow_re_of_pos hn_pos]
          congr 1
          simp [Complex.add_re, Complex.neg_re, Complex.mul_re,
                Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]
        · -- Second term: |(n+1)^{-1/2-it}| = (n+1)^{-1/2}
          rw [show (n + 1 : ℂ) = ((n + 1 : ℝ) : ℂ) from by push_cast; ring]
          rw [Complex.norm_cpow_eq_rpow_re_of_pos hn_pos]
          congr 1
          simp [Complex.sub_re, Complex.neg_re, Complex.mul_re,
                Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]
    _ = 2 * ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by ring

-- ============================================================
-- Section 7c++: RS leading term phase decomposition
-- ============================================================

/-- The RS leading term on block k: substituting hardyN(t) = k+1. -/
theorem rsLeadingFromFE_on_block_structure (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    rsLeadingFromFE t =
      (chiFactor t)⁻¹ * ((k + 2 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) := by
  unfold rsLeadingFromFE
  have hN := hardyN_on_open_block k t ht_lo ht_hi
  congr 1
  rw [hN]
  push_cast
  ring_nf

/-- The imaginary-power factor (k+2)^{it} has unit modulus. -/
theorem cpow_I_mul_t_norm (k : ℕ) (t : ℝ) :
    ‖((k + 2 : ℝ) : ℂ) ^ (Complex.I * (t : ℂ))‖ = 1 := by
  have hk2 : (0 : ℝ) < (k : ℝ) + 2 := by positivity
  rw [Complex.norm_cpow_eq_rpow_re_of_pos hk2]
  simp [Complex.mul_re, Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- The RS leading term decomposes into amplitude and phase on block k:
    rsLeadingFromFE t = (k+2)^{-1/2} cdot (chi(t)^{-1} cdot (k+2)^{it}).
    The first factor is real amplitude, the second is unit-modulus phase. -/
theorem rsLeadingFromFE_amplitude_phase_split (k : ℕ) (t : ℝ)
    (ht : t ≠ 0) (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    rsLeadingFromFE t =
      (((k + 2 : ℝ) : ℂ) ^ (-(1/2 : ℂ))) *
        ((chiFactor t)⁻¹ * ((k + 2 : ℝ) : ℂ) ^ (Complex.I * (t : ℂ))) := by
  rw [rsLeadingFromFE_on_block_structure k t ht_lo ht_hi]
  have hk2 : (0 : ℝ) < (k : ℝ) + 2 := by positivity
  rw [show ((k + 2 : ℂ)) = ((k + 2 : ℝ) : ℂ) from by push_cast; ring]
  rw [show (-(1/2 : ℂ) + Complex.I * (t : ℂ)) = (-(1/2 : ℂ)) + (Complex.I * (t : ℂ)) from by ring]
  rw [Complex.cpow_add _ _ (by exact_mod_cast hk2.ne')]
  ring

/-- The unit-modulus phase factor chi^{-1}(t) cdot (k+2)^{it} has norm 1. -/
theorem rsLeading_phase_factor_norm (k : ℕ) (t : ℝ) (ht : t ≠ 0) :
    ‖(chiFactor t)⁻¹ * ((k + 2 : ℝ) : ℂ) ^ (Complex.I * (t : ℂ))‖ = 1 := by
  rw [Complex.norm_mul, norm_inv, chiFactor_norm_eq_one t ht, inv_one, one_mul]
  exact cpow_I_mul_t_norm k t

/-- The rsPsi phase on block k at parameter p equals
    cos(pi(2p^2 - 2p + 1/4)). This is definitional but useful as a rewrite. -/
theorem rsPsi_eq_cos_on_block (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t ≤ hardyStart (k + 1)) :
    rsPsi (blockParam k t) =
      Real.cos (Real.pi * (2 * (blockParam k t) ^ 2 - 2 * blockParam k t + 1/4)) := by
  rfl

/-- On each block, the RS phase function rsPsi(p) oscillates between
    cos(-pi/4) and cos(pi/4). The frequency of this oscillation is
    controlled by the quadratic 2p^2 - 2p + 1/4, which has a minimum
    at p = 1/2 with value -1/4, so the argument stays in [-pi/4, pi/4].

    This means the RS correction has the SAME SIGN throughout each block,
    and the sign alternates between blocks via (-1)^k. -/
theorem rsPsi_argument_bounded (p : ℝ) (hp : p ∈ Set.Icc (0 : ℝ) 1) :
    |Real.pi * (2 * p ^ 2 - 2 * p + 1/4)| ≤ Real.pi / 4 := by
  rw [abs_le]; constructor
  · have h1 : 0 ≤ 2 * (p - 1/2) ^ 2 := by positivity
    nlinarith [Real.pi_pos, hp.1, hp.2]
  · have h2 : 2 * p * (p - 1) ≤ 0 := by nlinarith [hp.1, hp.2]
    nlinarith [Real.pi_pos]

/-- At p = 1/2 (midpoint of each block), rsPsi achieves its maximum
    cos(-pi/4) = cos(pi/4) = sqrt(2)/2. This is the saddle point. -/
theorem rsPsi_at_midpoint : rsPsi (1/2) = Real.cos (Real.pi / 4) := by
  unfold rsPsi
  rw [show Real.pi * (2 * (1 / 2 : ℝ) ^ 2 - 2 * (1 / 2) + 1 / 4) = -(Real.pi / 4) from by ring]
  rw [Real.cos_neg]

-- The RS leading phase connection to block parameter:
-- on block k, t = 2pi(k+1+p)^2, and the Stirling-level identity is:
-- t log(k+2) - theta(t) - pi/4 ~ pi(2p^2-2p+1/4) + k*pi.
-- The k*pi term accounts for the (-1)^k sign alternation.
-- Below we verify endpoint consistency.

/-- At p = 0 (start of block k), blockParam = 0. -/
theorem blockParam_at_start (k : ℕ) :
    blockParam k (hardyStart k) = 0 := by
  unfold blockParam hardyStart
  have hpi := Real.pi_pos
  rw [show 2 * Real.pi * ((k : ℝ) + 1) ^ 2 / (2 * Real.pi) = ((k : ℝ) + 1) ^ 2 from by
    field_simp]
  rw [Real.sqrt_sq (by positivity : (0 : ℝ) ≤ (k : ℝ) + 1)]
  ring

/-- rsPsi at block start equals cos(pi/4) = sqrt(2)/2. -/
theorem rsPsi_at_block_start : rsPsi 0 = Real.cos (Real.pi / 4) := by
  unfold rsPsi; ring_nf

/-- rsPsi at block end also equals cos(pi/4), by symmetry of
    2p^2-2p+1/4 under p -> 1-p (the parabola is symmetric about p=1/2). -/
theorem rsPsi_at_block_end : rsPsi 1 = Real.cos (Real.pi / 4) := by
  unfold rsPsi; ring_nf

-- ============================================================
-- Section 7c-tail: Euler-Maclaurin tail infrastructure for Dirichlet series
-- ============================================================
-- Abel summation by parts and exponential sum bounds for
-- bounding the Dirichlet polynomial remainder on the critical line.
-- This section builds sorry-free infrastructure toward `saddle_point_remainder`.

/-- The norm of (n+1)^{it} equals 1 for any real t and natural n.
    This is immediate from |x^{iy}| = x^{Re(iy)} = x^0 = 1 for x > 0. -/
theorem norm_cpow_imaginary (n : ℕ) (t : ℝ) :
    ‖((n + 1 : ℝ) : ℂ) ^ (Complex.I * (t : ℂ))‖ = 1 := by
  have hn_pos : (0 : ℝ) < (n : ℝ) + 1 := by positivity
  rw [Complex.norm_cpow_eq_rpow_re_of_pos hn_pos]
  simp [Complex.mul_re, Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- Each term of the Dirichlet polynomial on the critical line has norm n^{-1/2}:
    ‖(n+1)^{-1/2-it}‖ = (n+1)^{-1/2}.
    This decouples the amplitude from the oscillatory phase. -/
theorem norm_dirichlet_term (n : ℕ) (t : ℝ) :
    ‖((n + 1 : ℝ) : ℂ) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ =
    ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  have hn_pos : (0 : ℝ) < (n : ℝ) + 1 := by positivity
  rw [Complex.norm_cpow_eq_rpow_re_of_pos hn_pos]
  congr 1
  simp [Complex.sub_re, Complex.neg_re, Complex.div_ofNat, Complex.mul_re,
        Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- The reflected Dirichlet term also has norm n^{-1/2}:
    ‖(n+1)^{-1/2+it}‖ = (n+1)^{-1/2}. -/
theorem norm_reflected_dirichlet_term (n : ℕ) (t : ℝ) :
    ‖((n + 1 : ℝ) : ℂ) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))‖ =
    ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  have hn_pos : (0 : ℝ) < (n : ℝ) + 1 := by positivity
  rw [Complex.norm_cpow_eq_rpow_re_of_pos hn_pos]
  congr 1
  simp [Complex.add_re, Complex.neg_re, Complex.div_ofNat, Complex.mul_re,
        Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- The amplitude sequence n ↦ (n+1)^{-1/2} is antitone (decreasing). -/
theorem dirichlet_amplitude_antitone :
    Antitone (fun n : ℕ => ((n + 1 : ℝ)) ^ (-(1/2 : ℝ))) := by
  intro a b hab
  apply Real.rpow_le_rpow_of_exponent_nonpos
  · positivity
  · exact_mod_cast (show (a : ℕ) + 1 ≤ b + 1 from Nat.add_le_add_right hab 1)
  · norm_num

/-- The amplitude sequence is nonneg. -/
theorem dirichlet_amplitude_nonneg (n : ℕ) :
    (0 : ℝ) ≤ ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by positivity

/-- Complex Abel summation by parts for finite sums.
    For sequences f, g : ℕ → ℂ with partial sums F(n) = Σ_{k≤n} f(k):
    Σ_{k=a}^{b} f(k)·g(k) = F(b)·g(b) - F(a-1)·g(a) - Σ_{k=a}^{b-1} F(k)·(g(k+1)-g(k))

    Here we prove a simpler version: the telescoping identity for adjacent differences.
    Σ_{k<n} (a(k) - a(k+1)) = a(0) - a(n). -/
theorem complex_telescoping_sum (a : ℕ → ℂ) (n : ℕ) :
    ∑ k ∈ Finset.range n, (a k - a (k + 1)) = a 0 - a n := by
  induction n with
  | zero => simp
  | succ m ih =>
    rw [Finset.sum_range_succ, ih]
    ring

/-- Norm of a telescoping sum: ‖Σ (a(k) - a(k+1))‖ ≤ ‖a(0)‖ + ‖a(n)‖. -/
theorem norm_telescoping_sum_le (a : ℕ → ℂ) (n : ℕ) :
    ‖∑ k ∈ Finset.range n, (a k - a (k + 1))‖ ≤ ‖a 0‖ + ‖a n‖ := by
  rw [complex_telescoping_sum]
  exact le_trans (norm_sub_le _ _) (by linarith [norm_nonneg (a n)])

/-- The norm of a Dirichlet range sum is bounded by
    the sum of amplitudes via the triangle inequality. -/
theorem norm_complexPartialSum_range_le (t : ℝ) (N : ℕ) :
    ‖∑ n ∈ Finset.range N,
      ((n + 1 : ℝ) : ℂ) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ ≤
    ∑ n ∈ Finset.range N, ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  calc ‖∑ n ∈ Finset.range N,
        ((n + 1 : ℝ) : ℂ) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖
      ≤ ∑ n ∈ Finset.range N,
        ‖((n + 1 : ℝ) : ℂ) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ :=
        norm_sum_le _ _
    _ = ∑ n ∈ Finset.range N, ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        congr 1; ext n; exact norm_dirichlet_term n t

/-- The amplitude sum Σ_{n<N} (n+1)^{-1/2} is bounded by N
    via the crude bound (n+1)^{-1/2} ≤ 1. -/
theorem sum_amplitude_le_count (N : ℕ) :
    ∑ n ∈ Finset.range N, ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) ≤ (N : ℝ) := by
  calc ∑ n ∈ Finset.range N, ((n + 1 : ℝ)) ^ (-(1/2 : ℝ))
      ≤ ∑ _n ∈ Finset.range N, (1 : ℝ) := by
        apply Finset.sum_le_sum
        intro n _; exact rpow_neg_half_le_one n
    _ = (N : ℝ) := by simp [Finset.sum_const, Finset.card_range]

/-- The next term after the partial sum on block k has amplitude (k+2)^{-1/2},
    which matches the RS leading term amplitude. -/
theorem next_term_amplitude_eq_rsLeading (k : ℕ) :
    ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) =
    ((k + 1 + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  congr 1; push_cast; ring

/-- The amplitude (n+1)^{-1/2} equals the reciprocal of √(n+1).
    This connects the rpow formulation to the sqrt formulation. -/
theorem rpow_neg_half_eq_inv_sqrt (n : ℕ) :
    ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) = 1 / Real.sqrt ((n : ℝ) + 1) := by
  have hn_pos : (0 : ℝ) < (n : ℝ) + 1 := by positivity
  rw [Real.sqrt_eq_rpow, one_div, Real.rpow_neg (le_of_lt hn_pos), inv_eq_one_div]

/-- The step bound for the amplitude integral comparison:
    1/√(m+1) ≤ 2·(√(m+1) - √m), equivalently
    1 ≤ 2·(√(m+1) - √m)·√(m+1) = 2(m+1) - 2·√(m·(m+1)).
    This follows from (2m+1)² ≥ 4m(m+1). -/
theorem inv_sqrt_le_two_diff_sqrt (m : ℕ) :
    1 / Real.sqrt ((m : ℝ) + 1) ≤
    2 * Real.sqrt ((m : ℝ) + 1) - 2 * Real.sqrt (m : ℝ) := by
  have hm1_pos : (0 : ℝ) < (m : ℝ) + 1 := by positivity
  have hsqrt_pos : 0 < Real.sqrt ((m : ℝ) + 1) := Real.sqrt_pos.mpr hm1_pos
  rw [div_le_iff₀ hsqrt_pos]
  nlinarith [Real.sq_sqrt (show (0 : ℝ) ≤ (m : ℝ) + 1 by positivity),
             Real.sq_sqrt (show (0 : ℝ) ≤ (m : ℝ) by positivity),
             sq_nonneg (Real.sqrt ((m : ℝ) + 1) - Real.sqrt (m : ℝ)),
             sq_nonneg (2 * Real.sqrt ((m : ℝ) * ((m : ℝ) + 1)) - (2 * (m : ℝ) + 1))]

/-- The Dirichlet amplitudes satisfy a square-root integral comparison:
    Σ_{n=0}^{N-1} (n+1)^{-1/2} ≤ 2√N.
    Each term 1/√(m+1) ≤ 2(√(m+1) - √m) and the sum telescopes. -/
theorem partial_sum_amplitude_le_two_sqrt (N : ℕ) :
    ∑ n ∈ Finset.range N, ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) ≤ 2 * Real.sqrt (N : ℝ) := by
  induction N with
  | zero => simp [Real.sqrt_zero]
  | succ m ih =>
    rw [Finset.sum_range_succ]
    -- ih : ∑ n ∈ Finset.range m, ... ≤ 2 * √↑m
    -- goal : ∑ n ∈ Finset.range m, ... + (↑m+1)^(-1/2) ≤ 2 * √↑(m+1)
    -- The key: the succ cast √↑(m+1) = √(↑m + 1)
    have hsucc : Real.sqrt ((m + 1 : ℕ) : ℝ) = Real.sqrt ((m : ℝ) + 1) := by
      congr 1; push_cast; ring
    rw [hsucc]
    have h_step : ((m + 1 : ℝ)) ^ (-(1/2 : ℝ)) ≤
        2 * Real.sqrt ((m : ℝ) + 1) - 2 * Real.sqrt (m : ℝ) := by
      rw [rpow_neg_half_eq_inv_sqrt]
      exact inv_sqrt_le_two_diff_sqrt m
    have hm_eq : Real.sqrt ((m : ℕ) : ℝ) = Real.sqrt (m : ℝ) := by norm_cast
    linarith [hm_eq]

/-- On block k, the partial sum has ≤ 2√(k+1) amplitude (sharper than k+1). -/
theorem partialSum_norm_le_two_sqrt_block (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ‖complexPartialSum t‖ ≤ 2 * Real.sqrt ((k : ℝ) + 1) := by
  calc ‖complexPartialSum t‖
      ≤ ∑ n ∈ Finset.range (hardyN t), ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) :=
        norm_complexPartialSum_le t
    _ = ∑ n ∈ Finset.range (k + 1), ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        rw [hardyN_on_open_block k t ht_lo ht_hi]
    _ ≤ 2 * Real.sqrt ((k + 1 : ℕ) : ℝ) :=
        partial_sum_amplitude_le_two_sqrt (k + 1)
    _ = 2 * Real.sqrt ((k : ℝ) + 1) := by push_cast; ring_nf

-- ============================================================
-- Section 7c++-mismatch: Polynomial mismatch sum bound
-- ============================================================

/-- The polynomial mismatch SUM on block k has norm bounded by 4√(k+1).
    Each term has norm ≤ 2·(n+1)^{-1/2}, and the sum of amplitudes is ≤ 2√(k+1).

    PROVED: from `polynomial_mismatch_term_structure` + `partial_sum_amplitude_le_two_sqrt`. -/
theorem polynomial_mismatch_sum_bound (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ‖∑ n ∈ Finset.range (hardyN t),
      ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))‖ ≤
    4 * Real.sqrt ((k : ℝ) + 1) := by
  calc ‖∑ n ∈ Finset.range (hardyN t),
        ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
         ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))‖
      ≤ ∑ n ∈ Finset.range (hardyN t),
          ‖(chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
           ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ :=
        norm_sum_le _ _
    _ ≤ ∑ n ∈ Finset.range (hardyN t), 2 * ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        apply Finset.sum_le_sum
        intro n hn
        exact polynomial_mismatch_term_structure t ht n (Finset.mem_range.mp hn)
    _ = 2 * ∑ n ∈ Finset.range (hardyN t), ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        rw [Finset.mul_sum]
    _ ≤ 2 * (2 * Real.sqrt ((k + 1 : ℕ) : ℝ)) := by
        gcongr
        rw [hardyN_on_open_block k t ht_lo ht_hi]
        exact partial_sum_amplitude_le_two_sqrt (k + 1)
    _ = 4 * Real.sqrt ((k + 1 : ℕ) : ℝ) := by ring
    _ = 4 * Real.sqrt ((k : ℝ) + 1) := by push_cast; ring_nf

/-- On block k with t > 0, we have (k+1) ≤ √(t/(2π)) + 1, and therefore
    √(k+1) ≤ √(t/(2π) + 1). This connects the block-indexed bound to a
    t-dependent bound.

    PROVED: from hardyStart k ≤ t and algebra. -/
theorem sqrt_block_le_sqrt_t_param (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_pos : 0 < t) :
    Real.sqrt ((k : ℝ) + 1) ≤ Real.sqrt (t / (2 * Real.pi) + 1) := by
  apply Real.sqrt_le_sqrt
  have hpi : (0 : ℝ) < 2 * Real.pi := by positivity
  -- hardyStart k = 2π(k+1)² with ℕ cast
  have h_hs : hardyStart k = 2 * Real.pi * ((k : ℝ) + 1) ^ 2 := by
    unfold hardyStart; push_cast; ring
  have hk1_sq : 2 * Real.pi * ((k : ℝ) + 1) ^ 2 ≤ t := by linarith
  have hk1_le : ((k : ℝ) + 1) ^ 2 ≤ t / (2 * Real.pi) := by
    rw [le_div_iff₀ hpi]; linarith
  -- (k+1)² ≤ t/(2π) implies k+1 ≤ (k+1)² ≤ t/(2π) ≤ t/(2π) + 1
  nlinarith [sq_nonneg ((k : ℝ) + 1 - 1)]

/-- On block k, the polynomial mismatch norm is O(t^{1/4}):
    ≤ 4·√(t/(2π) + 1).

    This provides a CRUDE bound. The saddle-point analysis (Siegel 1932)
    shows the mismatch minus the N+1 term (RS leading term) is O(t^{-3/4}),
    which is the genuine content of `siegel_expansion_core`. -/
theorem polynomial_mismatch_crude_order (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1))
    (ht_pos : 0 < t) :
    ‖∑ n ∈ Finset.range (hardyN t),
      ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))‖ ≤
    4 * Real.sqrt ((t / (2 * Real.pi)) + 1) := by
  have h1 := polynomial_mismatch_sum_bound k t ht ht_lo ht_hi
  have h2 := sqrt_block_le_sqrt_t_param k t ht_lo ht_pos
  linarith [Real.sqrt_nonneg ((k : ℝ) + 1)]

-- ============================================================
-- Section 7c+++-saddle: Saddle-term extraction from polynomial mismatch
-- ============================================================
-- The polynomial mismatch Σ_{n<N} (χ⁻¹·(n+1)^{-1/2+it} - (n+1)^{-1/2-it})
-- has N = k+1 terms on block k. We extract the LAST term (n = k, giving the
-- saddle-adjacent term) and bound the INNER sum (n < k) separately.
-- The last term has amplitude 2·(k+1)^{-1/2} and the inner sum ≤ 4√k.
-- This is infrastructure for the Siegel steepest-descent analysis.

/-- **Mismatch last-term extraction**: decompose the polynomial mismatch sum
    Σ_{n ∈ range(k+1)} f(n) = Σ_{n ∈ range k} f(n) + f(k).
    On block k, hardyN(t) = k+1, so the sum has k+1 terms.
    The last term (n = k) is the saddle-adjacent contribution. -/
theorem polynomial_mismatch_split_last (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ∑ n ∈ Finset.range (hardyN t),
      ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))) =
    (∑ n ∈ Finset.range k,
      ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))) +
    ((chiFactor t)⁻¹ * ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
     ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))) := by
  rw [hardyN_on_open_block k t ht_lo ht_hi]
  exact Finset.sum_range_succ _ k

/-- The **inner mismatch sum** (n < k) has norm bounded by 4√k.
    This is the contribution from terms well below the saddle point,
    where oscillation provides the cancellation.
    PROVED: from polynomial_mismatch_sum_bound applied to (k-1) blocks
    plus the triangle inequality. -/
theorem inner_mismatch_sum_bound (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ‖∑ n ∈ Finset.range k,
      ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))‖ ≤
    4 * Real.sqrt (k : ℝ) := by
  calc ‖∑ n ∈ Finset.range k,
        ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
         ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))‖
      ≤ ∑ n ∈ Finset.range k,
          ‖(chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
           ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ :=
        norm_sum_le _ _
    _ ≤ ∑ n ∈ Finset.range k, 2 * ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        apply Finset.sum_le_sum
        intro n hn
        have hn_lt : n < hardyN t := by
          rw [hardyN_on_open_block k t ht_lo ht_hi]
          exact lt_of_lt_of_le (Finset.mem_range.mp hn) (Nat.le_succ k)
        exact polynomial_mismatch_term_structure t ht n hn_lt
    _ = 2 * ∑ n ∈ Finset.range k, ((n + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        rw [Finset.mul_sum]
    _ ≤ 2 * (2 * Real.sqrt ((k : ℕ) : ℝ)) := by
        gcongr
        exact partial_sum_amplitude_le_two_sqrt k
    _ = 4 * Real.sqrt ((k : ℕ) : ℝ) := by ring
    _ = 4 * Real.sqrt (k : ℝ) := by norm_cast

/-- The **last mismatch term** (n = k, the saddle-adjacent term) has norm
    bounded by 2·(k+1)^{-1/2}.
    PROVED: direct instance of polynomial_mismatch_term_structure. -/
theorem last_mismatch_term_bound (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ‖(chiFactor t)⁻¹ * ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
     ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ ≤
    2 * ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  have hk_lt : k < hardyN t := by
    rw [hardyN_on_open_block k t ht_lo ht_hi]; omega
  exact polynomial_mismatch_term_structure t ht k hk_lt

/-- The polynomial mismatch norm satisfies a **split bound**:
    ‖mismatch‖ ≤ ‖inner sum‖ + ‖last term‖ ≤ 4√k + 2·(k+1)^{-1/2}.
    PROVED: triangle inequality on the extracted decomposition. -/
theorem polynomial_mismatch_split_bound (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ‖∑ n ∈ Finset.range (hardyN t),
      ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))‖ ≤
    4 * Real.sqrt (k : ℝ) + 2 * ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  rw [polynomial_mismatch_split_last k t ht ht_lo ht_hi]
  calc ‖(∑ n ∈ Finset.range k,
        ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
         ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))) +
      ((chiFactor t)⁻¹ * ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))‖
      ≤ ‖∑ n ∈ Finset.range k,
          ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
           ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))‖ +
        ‖(chiFactor t)⁻¹ * ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
         ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ :=
        norm_add_le _ _
    _ ≤ 4 * Real.sqrt (k : ℝ) + 2 * ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        linarith [inner_mismatch_sum_bound k t ht ht_lo ht_hi,
                  last_mismatch_term_bound k t ht ht_lo ht_hi]

/-- The **last mismatch term decomposes** into the forward term minus
    the reflected term (N-th Dirichlet term). The forward part is exactly
    the "saddle term" χ⁻¹·(k+1)^{-1/2+it} which relates to rsLeadingFromFE
    shifted by one index. -/
theorem last_mismatch_term_decomp (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    (chiFactor t)⁻¹ * ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
     ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)) =
    (chiFactor t)⁻¹ * ((hardyN t : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
     ((hardyN t : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)) := by
  have hN := hardyN_on_open_block k t ht_lo ht_hi
  congr 1 <;> congr 1 <;> rw [hN] <;> push_cast <;> ring

/-- The forward part of the last mismatch term χ⁻¹·(k+1)^{-1/2+it}
    has the same structure as rsLeadingFromFE but at index N = k+1
    instead of N+1 = k+2. Its norm is (k+1)^{-1/2}. -/
theorem norm_forward_saddle_term (k : ℕ) (t : ℝ) (ht : t ≠ 0) :
    ‖(chiFactor t)⁻¹ * ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))‖ =
    ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  rw [Complex.norm_mul, norm_inv, chiFactor_norm_eq_one t ht, inv_one, one_mul]
  have hk1_pos : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  rw [show (k + 1 : ℂ) = ((k + 1 : ℝ) : ℂ) from by push_cast; ring]
  rw [Complex.norm_cpow_eq_rpow_re_of_pos hk1_pos]
  congr 1
  simp [Complex.add_re, Complex.neg_re, Complex.mul_re,
        Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- The backward part (k+1)^{-1/2-it} also has norm (k+1)^{-1/2}. -/
theorem norm_backward_saddle_term (k : ℕ) (t : ℝ) :
    ‖((k + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))‖ =
    ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
  have hk1_pos : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  rw [show (k + 1 : ℂ) = ((k + 1 : ℝ) : ℂ) from by push_cast; ring]
  rw [Complex.norm_cpow_eq_rpow_re_of_pos hk1_pos]
  congr 1
  simp [Complex.sub_re, Complex.neg_re, Complex.mul_re,
        Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]

/-- The difference rsLeadingFromFE(t) - χ⁻¹·(k+1)^{-1/2+it} measures the gap
    between the RS leading term (at index k+2) and the last mismatch forward
    term (at index k+1). Both have the χ⁻¹ factor, so the difference is:
    χ⁻¹ · ((k+2)^{-1/2+it} - (k+1)^{-1/2+it}).
    The norm of this difference is bounded by |(k+2)^{-1/2} - (k+1)^{-1/2}|
    plus the phase rotation. -/
theorem rsLeading_minus_forward_saddle (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    rsLeadingFromFE t -
      (chiFactor t)⁻¹ * ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) =
    (chiFactor t)⁻¹ *
      (((k + 2 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))) := by
  rw [rsLeadingFromFE_on_block_structure k t ht_lo ht_hi]
  ring

/-- The norm of the gap between rsLeading and the forward saddle term is
    bounded by the amplitude difference plus a cross-modulus term.
    Since both terms have the same χ⁻¹ phase factor with |χ⁻¹| = 1,
    the norm reduces to |(k+2)^{-1/2+it} - (k+1)^{-1/2+it}|. -/
theorem norm_rsLeading_minus_forward_saddle (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ‖rsLeadingFromFE t -
      (chiFactor t)⁻¹ * ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))‖ ≤
    ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) + ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) := by
  rw [rsLeading_minus_forward_saddle k t ht ht_lo ht_hi]
  calc ‖(chiFactor t)⁻¹ *
        (((k + 2 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
         ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)))‖
      = ‖((k + 2 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
         ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))‖ := by
        rw [Complex.norm_mul, norm_inv, chiFactor_norm_eq_one t ht, inv_one, one_mul]
    _ ≤ ‖((k + 2 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))‖ +
        ‖((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))‖ :=
        norm_sub_le _ _
    _ = ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) + ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) := by
        congr 1
        · -- ‖(k+2)^{-1/2+it}‖ = (k+2)^{-1/2}
          have hk2_pos : (0 : ℝ) < (k : ℝ) + 2 := by positivity
          rw [show (k + 2 : ℂ) = ((k + 2 : ℝ) : ℂ) from by push_cast; ring]
          rw [Complex.norm_cpow_eq_rpow_re_of_pos hk2_pos]
          congr 1
          simp [Complex.add_re, Complex.neg_re, Complex.mul_re,
                Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]
        · -- ‖(k+1)^{-1/2+it}‖ = (k+1)^{-1/2}
          have hk1_pos : (0 : ℝ) < (k : ℝ) + 1 := by positivity
          rw [show (k + 1 : ℂ) = ((k + 1 : ℝ) : ℂ) from by push_cast; ring]
          rw [Complex.norm_cpow_eq_rpow_re_of_pos hk1_pos]
          congr 1
          simp [Complex.add_re, Complex.neg_re, Complex.mul_re,
                Complex.I_re, Complex.I_im, Complex.ofReal_re, Complex.ofReal_im]
    _ = ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) + ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) := by ring

/-- **Combined saddle-mismatch relationship**: on block k with k ≥ 1,
    ‖mismatch_sum - rsLeadingFromFE‖ is bounded by a sum of terms all
    of order O(k^{-1/2}) = O(t^{-1/4}).
    Specifically: ≤ 4√k + 2·(k+1)^{-1/2} + (k+1)^{-1/2} + (k+2)^{-1/2}
                  + (k+1)^{-1/2}
    where the inner sum contributes 4√k, the last mismatch term contributes
    2·(k+1)^{-1/2}, and the rsLeading-vs-forward gap contributes the rest.
    All terms are O(√k) = O(t^{1/4}) at most. -/
theorem mismatch_vs_rsLeading_bound (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1)) :
    ‖(∑ n ∈ Finset.range (hardyN t),
      ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))) - rsLeadingFromFE t‖ ≤
    4 * Real.sqrt (k : ℝ) + 3 * ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) +
      ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) := by
  -- Decompose the mismatch: inner sum + last term - rsLeading
  rw [polynomial_mismatch_split_last k t ht ht_lo ht_hi]
  -- (inner + last) - rsLeading
  -- = inner + (last_forward - (k+1)^{-1/2-it}) - rsLeading
  -- Rearrange: = inner + (last_forward - rsLeading) - backward
  -- = inner - backward + (last_forward - rsLeading)
  -- But rsLeading = χ⁻¹·(k+2)^{-1/2+it}, last_forward = χ⁻¹·(k+1)^{-1/2+it}
  -- last = last_forward - backward
  -- So inner + last - rsLeading = inner + last_forward - backward - rsLeading
  -- = inner - backward + (last_forward - rsLeading)
  -- = inner - backward - (rsLeading - last_forward)
  -- Bound by triangle: ≤ ‖inner‖ + ‖backward‖ + ‖rsLeading - last_forward‖
  set inner := ∑ n ∈ Finset.range k,
      ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))
  set forward := (chiFactor t)⁻¹ * ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ))
  set backward := ((k + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ))
  -- inner + (forward - backward) - rsLeading = inner - backward + (forward - rsLeading)
  have h_rearrange : inner + (forward - backward) - rsLeadingFromFE t =
      inner - backward + (forward - rsLeadingFromFE t) := by ring
  rw [h_rearrange]
  calc ‖inner - backward + (forward - rsLeadingFromFE t)‖
      ≤ ‖inner - backward‖ + ‖forward - rsLeadingFromFE t‖ :=
        norm_add_le _ _
    _ ≤ (‖inner‖ + ‖backward‖) + ‖forward - rsLeadingFromFE t‖ := by
        linarith [norm_sub_le inner backward]
    _ ≤ (4 * Real.sqrt (k : ℝ) + ((k + 1 : ℝ)) ^ (-(1/2 : ℝ))) +
        (((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) + ((k + 2 : ℝ)) ^ (-(1/2 : ℝ))) := by
        have h_inner := inner_mismatch_sum_bound k t ht ht_lo ht_hi
        have h_back := norm_backward_saddle_term k t
        have h_gap : ‖forward - rsLeadingFromFE t‖ ≤
            ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) + ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) := by
          rw [show forward - rsLeadingFromFE t = -(rsLeadingFromFE t - forward) from by ring]
          rw [norm_neg]
          exact norm_rsLeading_minus_forward_saddle k t ht ht_lo ht_hi
        linarith
    _ = 4 * Real.sqrt (k : ℝ) + 2 * ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) +
        ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) := by ring
    _ ≤ 4 * Real.sqrt (k : ℝ) + 3 * ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) +
        ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) := by
        linarith [dirichlet_amplitude_nonneg k]

/-- **O(t^{1/4}) bound on mismatch-vs-rsLeading**: on block k,
    ‖mismatch - rsLeading‖ ≤ 4·√(t/(2π)+1) + 4·((k+1)^{-1/2}).
    Since both √(t/(2π)+1) ~ √k and (k+1)^{-1/2} ≤ 1, the total is O(√k) = O(t^{1/4}).
    This quantifies the gap between the FE-derived polynomial mismatch and the
    Siegel-derived RS leading correction. Closing this gap to O(t^{-3/4}) requires
    the full saddle-point contour integral evaluation (siegel_expansion_core). -/
theorem mismatch_vs_rsLeading_crude_order (k : ℕ) (t : ℝ) (ht : t ≠ 0)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t < hardyStart (k + 1))
    (ht_pos : 0 < t) :
    ‖(∑ n ∈ Finset.range (hardyN t),
      ((chiFactor t)⁻¹ * ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) + Complex.I * (t : ℂ)) -
       ((n + 1 : ℂ)) ^ (-(1/2 : ℂ) - Complex.I * (t : ℂ)))) - rsLeadingFromFE t‖ ≤
    4 * Real.sqrt (t / (2 * Real.pi) + 1) + 4 := by
  have h := mismatch_vs_rsLeading_bound k t ht ht_lo ht_hi
  have h_sqrt := sqrt_block_le_sqrt_t_param k t ht_lo ht_pos
  have h_amp1 : ((k + 1 : ℝ)) ^ (-(1/2 : ℝ)) ≤ 1 := rpow_neg_half_le_one k
  have h_amp2 : ((k + 2 : ℝ)) ^ (-(1/2 : ℝ)) ≤ 1 := by
    apply Real.rpow_le_one_of_one_le_of_nonpos
    · have : (0 : ℝ) ≤ (k : ℝ) := Nat.cast_nonneg k; linarith
    · norm_num
  have h_sqrt_k : Real.sqrt (k : ℝ) ≤ Real.sqrt (t / (2 * Real.pi) + 1) := by
    have : (k : ℝ) ≤ (k : ℝ) + 1 := le_add_of_nonneg_right one_pos.le
    exact le_trans (Real.sqrt_le_sqrt this) h_sqrt
  linarith

-- ============================================================
-- Section 7d-stirling: Stirling theta approximation infrastructure
-- ============================================================

/-! ### Stirling-level θ approximation for the saddle-point construction

The Stirling approximation for Hardy's θ function:
  θ(t) = (t/2)·log(t/(2π)) - t/2 - π/8 + O(1/t)

connects the phase factor exp(iθ(t)) to the RS leading term. At the block
coordinate t = 2π(k+1+p)², this yields the phase identity:
  θ(t) - t·log(k+1+p) = -π(k+1+p)² - π/8 + O(1/t)

which, when combined with the RS phase formula, gives the Ψ(p) connection
needed for the saddle-point bound.

Reference: Edwards Ch. 6 (θ asymptotics); Siegel 1932 §3. -/

/-- The Stirling approximation for Hardy's θ function:
    θ_S(t) = (t/2)·log(t/(2π)) - t/2 - π/8.
    This is the leading-order approximation with error O(1/t). -/
noncomputable def thetaStirlingApprox (t : ℝ) : ℝ :=
  (t / 2) * Real.log (t / (2 * Real.pi)) - t / 2 - Real.pi / 8

/-- The Stirling approximation of θ evaluated at t = 2π·u² for u > 0
    simplifies to: θ_S(2π·u²) = π·u²·log(u²) - π·u² - π/8
                               = 2π·u²·log(u) - π·u² - π/8.
    PROVED: by unfolding and simplifying log(2π·u²/(2π)) = log(u²) = 2·log(u). -/
theorem thetaStirlingApprox_at_square (u : ℝ) (hu : 0 < u) :
    thetaStirlingApprox (2 * Real.pi * u ^ 2) =
    2 * Real.pi * u ^ 2 * Real.log u - Real.pi * u ^ 2 - Real.pi / 8 := by
  unfold thetaStirlingApprox
  have hpi : (0 : ℝ) < 2 * Real.pi := by positivity
  have hpi_ne : (2 * Real.pi : ℝ) ≠ 0 := ne_of_gt hpi
  -- Simplify t/(2π) = u²
  have h_div : 2 * Real.pi * u ^ 2 / (2 * Real.pi) = u ^ 2 := by
    field_simp
  -- Simplify t/2 = π·u²
  have h_half : 2 * Real.pi * u ^ 2 / 2 = Real.pi * u ^ 2 := by ring
  rw [h_half, h_div]
  -- log(u²) = 2·log(u) for u > 0
  have h_log_sq : Real.log (u ^ 2) = 2 * Real.log u := by
    rw [Real.log_pow]; push_cast; ring
  rw [h_log_sq]; ring

/-- At blockCoord(k, p) = 2π(k+1+p)², the Stirling θ approximation equals
    2π(k+1+p)²·log(k+1+p) - π(k+1+p)² - π/8.
    PROVED: from thetaStirlingApprox_at_square with u = k+1+p. -/
theorem thetaStirlingApprox_at_blockCoord (k : ℕ) (p : ℝ) (hp : 0 ≤ p) :
    thetaStirlingApprox (blockCoord k p) =
    2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 * Real.log ((k : ℝ) + 1 + p)
      - Real.pi * ((k : ℝ) + 1 + p) ^ 2 - Real.pi / 8 := by
  have hu : (0 : ℝ) < (k : ℝ) + 1 + p := by positivity
  exact thetaStirlingApprox_at_square ((k : ℝ) + 1 + p) hu

/-- The saddle phase θ_S(t) - t·log(k+1+p) at blockCoord(k,p) equals
    -π(k+1+p)² - π/8. The t·log(k+1+p) term cancels the
    2π(k+1+p)²·log(k+1+p) from the Stirling expansion exactly.
    PROVED: algebraic from thetaStirlingApprox_at_blockCoord. -/
theorem stirling_saddlePhase_at_blockCoord (k : ℕ) (p : ℝ) (hp : 0 ≤ p) :
    thetaStirlingApprox (blockCoord k p) -
      blockCoord k p * Real.log ((k : ℝ) + 1 + p) =
    -(Real.pi * ((k : ℝ) + 1 + p) ^ 2) - Real.pi / 8 := by
  rw [thetaStirlingApprox_at_blockCoord k p hp]
  unfold blockCoord; ring

/-- The Stirling saddle phase at index k (not k+1+p) involves a log ratio:
    θ_S(t) - t·log(k+1) = θ_S(t) - t·log(k+1+p) + t·log((k+1+p)/(k+1))
    at t = blockCoord(k,p). The first part is -π(k+1+p)² - π/8 (above).
    The second part is 2π(k+1+p)²·log(1+p/(k+1)).
    PROVED: algebraic from stirling_saddlePhase_at_blockCoord. -/
theorem stirling_saddlePhase_at_index_k (k : ℕ) (p : ℝ) (hp : 0 ≤ p)
    (hk : 0 < (k : ℝ) + 1) :
    thetaStirlingApprox (blockCoord k p) -
      blockCoord k p * Real.log ((k : ℝ) + 1) =
    -(Real.pi * ((k : ℝ) + 1 + p) ^ 2) - Real.pi / 8 +
      blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) := by
  have hu : (0 : ℝ) < (k : ℝ) + 1 + p := by linarith
  have h_main := stirling_saddlePhase_at_blockCoord k p hp
  -- Rewrite: log(k+1+p) = log(k+1) + log((k+1+p)/(k+1))
  have h_log_split : Real.log ((k : ℝ) + 1 + p) =
      Real.log ((k : ℝ) + 1) + Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) := by
    rw [← Real.log_mul (ne_of_gt hk) (ne_of_gt (div_pos hu hk)),
        mul_div_cancel₀ _ (ne_of_gt hk)]
  -- The LHS equals: θ_S(bc) - bc·log(k+1+p) + bc·(log(k+1+p) - log(k+1))
  -- = h_main + bc·log((k+1+p)/(k+1))
  have h_rearrange : thetaStirlingApprox (blockCoord k p) -
      blockCoord k p * Real.log ((k : ℝ) + 1) =
    (thetaStirlingApprox (blockCoord k p) -
      blockCoord k p * Real.log ((k : ℝ) + 1 + p)) +
    blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) := by
    rw [h_log_split]; ring
  rw [h_rearrange, h_main]

/-- The t·log(1+p/(k+1)) term at blockCoord(k,p) = 2π(k+1+p)² equals
    2π(k+1+p)²·log(1+p/(k+1)). For p ∈ [0,1] and large k, this is
    approximately 2πp(k+1+p)² / (k+1) ≈ 2πp(k+1).
    PROVED: definitional unfolding. -/
theorem blockCoord_log_ratio (k : ℕ) (p : ℝ) :
    blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) =
    2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
      Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) := by
  unfold blockCoord; ring

/-- The Stirling saddle phase differs between indices (k+1+p) and (k+1) by
    the block coordinate times a logarithmic ratio. When expressed modulo π,
    this gives the RS phase connection.

    The quadratic phase identity: for u = k+1+p, v = k+1,
    -π·u² + 2π·u²·log(u/v) = -π·v² + 2π·u²·log(u/v) - π(u²-v²)
    = -π·v² + 2π·u²·log(u/v) - 2πp·v - πp².
    PROVED: algebra. -/
theorem stirling_phase_quadratic_decomp (k : ℕ) (p : ℝ) :
    -(Real.pi * ((k : ℝ) + 1 + p) ^ 2) =
    -(Real.pi * ((k : ℝ) + 1) ^ 2) - 2 * Real.pi * p * ((k : ℝ) + 1)
      - Real.pi * p ^ 2 := by
  ring

/-- Combined: the Stirling saddle phase at index k on blockCoord(k,p) equals
    -π(k+1)² - 2πp(k+1) - πp² - π/8 + 2π(k+1+p)²·log(1+p/(k+1)).
    PROVED: combining stirling_saddlePhase_at_index_k with quadratic decomp. -/
theorem stirling_saddlePhase_expanded (k : ℕ) (p : ℝ) (hp : 0 ≤ p)
    (hk : 0 < (k : ℝ) + 1) :
    thetaStirlingApprox (blockCoord k p) -
      blockCoord k p * Real.log ((k : ℝ) + 1) =
    -(Real.pi * ((k : ℝ) + 1) ^ 2) - 2 * Real.pi * p * ((k : ℝ) + 1) -
      Real.pi * p ^ 2 - Real.pi / 8 +
      blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) := by
  rw [stirling_saddlePhase_at_index_k k p hp hk, stirling_phase_quadratic_decomp]

/-- The RS phase argument is π(2p²-2p+1/4). When the Stirling saddle phase
    is reduced modulo π, the dominant terms -π(k+1)² and -2πp(k+1) are
    integer multiples of π. What remains (modulo π) is:
    -πp² - π/8 + small correction.

    This lemma records the key algebraic identity that for INTEGER k+1,
    -π(k+1)² ≡ 0 (mod π) and -2πp(k+1) ≡ 0 (mod π) when k+1 ∈ ℤ.
    So the residual phase is -πp² - π/8 + [log correction].
    PROVED: (k+1) is a positive integer, so (k+1)² ∈ ℤ. -/
theorem pi_mul_nat_sq_div_pi (k : ℕ) :
    Real.pi * ((k : ℝ) + 1) ^ 2 / Real.pi = ((k : ℝ) + 1) ^ 2 := by
  rw [mul_div_cancel_left₀ _ (ne_of_gt Real.pi_pos)]

/-- 2π·p·(k+1) / π = 2·p·(k+1). -/
theorem two_pi_p_k_div_pi (k : ℕ) (p : ℝ) :
    2 * Real.pi * p * ((k : ℝ) + 1) / Real.pi = 2 * p * ((k : ℝ) + 1) := by
  have hpi_ne : Real.pi ≠ 0 := ne_of_gt Real.pi_pos
  field_simp

/-- The cosine of the Stirling saddle phase at index k reduces via
    cos(-π(k+1)² - 2πp(k+1) - πp² - π/8 + correction)
    = cos(-πp² - π/8 + correction) · cos(π(k+1)² + 2πp(k+1))
      + sin correction · sin(π(k+1)² + 2πp(k+1)).
    Since cos(πn) = (-1)^n for integer n, and (k+1)² + 2p(k+1) is
    an integer when p ∈ ℤ (e.g. at endpoints), this shows sign alternation.

    Here we prove the endpoint case p = 0:
    cos(-π(k+1)² - π/8) = (-1)^{(k+1)²} · cos(π/8).
    Since (k+1)² ≡ (k+1) (mod 2) [because n² ≡ n (mod 2)],
    this gives (-1)^{k+1} = -(-1)^k. -/
theorem nat_sq_mod_two (n : ℕ) : n ^ 2 % 2 = n % 2 := by
  rcases Nat.even_or_odd n with ⟨m, hm⟩ | ⟨m, hm⟩ <;> subst hm <;> ring_nf <;> omega

/-- (-1)^{n²} = (-1)^n for natural numbers.
    Since n² has the same parity as n, the signs agree. -/
theorem neg_one_pow_sq (n : ℕ) : (-1 : ℝ) ^ (n ^ 2) = (-1 : ℝ) ^ n := by
  rcases Nat.even_or_odd n with he | ho
  · have he2 : Even (n ^ 2) := Nat.even_pow.mpr ⟨he, by omega⟩
    rw [he.neg_one_pow, he2.neg_one_pow]
  · have ho2 : Odd (n ^ 2) := ho.pow
    rw [ho.neg_one_pow, ho2.neg_one_pow]

/-- The cosine of integer multiples of π: cos(πn) = (-1)^n.
    PROVED: by induction on n. -/
theorem cos_pi_nat (n : ℕ) : Real.cos (Real.pi * n) = (-1 : ℝ) ^ n := by
  induction n with
  | zero => simp
  | succ k ih =>
    rw [Nat.cast_succ, mul_add, mul_one, Real.cos_add, ih, Real.cos_pi, Real.sin_pi,
        mul_zero, sub_zero, pow_succ]

/-- cos(π · (k+1)²) = (-1)^(k+1) = -(-1)^k.
    PROVED: cos_pi_nat + neg_one_pow_sq. -/
theorem cos_pi_succ_sq (k : ℕ) :
    Real.cos (Real.pi * ((k : ℝ) + 1) ^ 2) = -(-1 : ℝ) ^ k := by
  have h_nat : ((k : ℝ) + 1) ^ 2 = ((k + 1) ^ 2 : ℕ) := by push_cast; ring
  rw [h_nat, cos_pi_nat, neg_one_pow_sq, pow_succ]; ring

/-- sin(π · (k+1)²) = 0 since (k+1)² is a natural number.
    PROVED: sin(πn) = 0 for n ∈ ℕ. -/
theorem sin_pi_succ_sq (k : ℕ) :
    Real.sin (Real.pi * ((k : ℝ) + 1) ^ 2) = 0 := by
  have h_nat : ((k : ℝ) + 1) ^ 2 = ((k + 1) ^ 2 : ℕ) := by push_cast; ring
  rw [h_nat]
  induction (k + 1) ^ 2 with
  | zero => simp
  | succ n ih =>
    rw [Nat.cast_succ, mul_add, mul_one, Real.sin_add, ih, Real.sin_pi, Real.cos_pi]
    ring

-- ============================================================
-- Section 7d-taylor: Taylor expansion for log(1+x) bounds
-- ============================================================

/-! ### Taylor expansion bounds for log(1+p/(k+1))

The saddle-point analysis at blockCoord(k,p) = 2π(k+1+p)² produces phases
involving log((k+1+p)/(k+1)) = log(1+p/(k+1)). For the RS expansion, we
need:
1. Upper bound: log(1+x) ≤ x for x > -1 (first-order Taylor)
2. Lower bound: log(1+x) ≥ x - x²/2 for x ≥ 0 (second-order Taylor)
3. Combined: |log(1+x) - x| ≤ x²/2 for x ∈ [0,1]
4. Applied to x = p/(k+1): remainder is O(1/(k+1)²) = O(t⁻¹)

These give the cubic Fresnel correction -2πp + 3π/8 at leading order,
with higher-order terms bounded by O(t⁻³/⁴).

Reference: Edwards Ch. 7 pp. 136-145; Siegel 1932 §3. -/

/-- **First-order Taylor upper bound for log(1+x)**: log(1+x) ≤ x for x > -1.
    This is the standard concavity bound, derived from Mathlib's
    `Real.log_le_sub_one_of_pos` applied to 1+x. -/
theorem log_one_plus_le (x : ℝ) (hx : -1 < x) :
    Real.log (1 + x) ≤ x := by
  have h1x : (0 : ℝ) < 1 + x := by linarith
  have := Real.log_le_sub_one_of_pos h1x
  linarith

/-- **Lower bound for log(1+x)**: for x ≥ 0, log(1+x) ≥ x/(1+x).
    This follows from Mathlib's `one_sub_inv_le_log_of_pos`. -/
theorem log_one_plus_ge_div (x : ℝ) (hx : 0 ≤ x) :
    x / (1 + x) ≤ Real.log (1 + x) := by
  have h1x : (0 : ℝ) < 1 + x := by linarith
  have h_lower := Real.one_sub_inv_le_log_of_pos h1x
  have h_frac : 1 - (1 + x)⁻¹ = x / (1 + x) := by field_simp; ring
  linarith

/-- **Weaker lower bound**: for 0 ≤ x ≤ 1, log(1+x) ≥ x/2.
    Since x/(1+x) ≥ x/2 when 0 ≤ x ≤ 1. -/
theorem log_one_plus_ge_half (x : ℝ) (hx : 0 ≤ x) (hx1 : x ≤ 1) :
    x / 2 ≤ Real.log (1 + x) := by
  have h1x : (0 : ℝ) < 1 + x := by linarith
  calc x / 2 ≤ x / (1 + x) := by
        rw [div_le_div_iff₀ (by norm_num : (0:ℝ) < 2) h1x]
        nlinarith
    _ ≤ Real.log (1 + x) := log_one_plus_ge_div x hx

/-- **Upper bound on log deviation**: for x ∈ [0,1], log(1+x) - x ≤ 0.
    Immediate from log_one_plus_le. -/
theorem log_one_plus_sub_le_zero (x : ℝ) (hx : 0 ≤ x) :
    Real.log (1 + x) - x ≤ 0 := by
  linarith [log_one_plus_le x (by linarith : (-1 : ℝ) < x)]

/-- **Sandwich bound for log(1+x)**: for x ∈ [0,1], |log(1+x) - x| ≤ x.
    Upper: log(1+x) ≤ x. Lower: log(1+x) ≥ 0 ≥ x - x = 0 for x ≥ 0.
    So log(1+x) - x ∈ [-x, 0] and |log(1+x) - x| ≤ x. -/
theorem abs_log_one_plus_sub_x_le (x : ℝ) (hx : 0 ≤ x) (hx1 : x ≤ 1) :
    |Real.log (1 + x) - x| ≤ x := by
  rw [abs_le]; constructor
  · -- Lower: log(1+x) - x ≥ -x, i.e., log(1+x) ≥ 0
    have : Real.log (1 + x) ≥ 0 :=
      Real.log_nonneg (by linarith)
    linarith
  · -- Upper: log(1+x) - x ≤ 0 ≤ x
    exact le_trans (log_one_plus_sub_le_zero x hx) hx

/-- **Applied Taylor bound**: for p ∈ [0,1] and k ≥ 0,
    |log(1 + p/(k+1)) - p/(k+1)| ≤ p/(k+1).
    This is the key estimate for the saddle-point phase expansion:
    the log ratio in the Stirling phase decomposes as
    log(1+p/(k+1)) = p/(k+1) + O(1/(k+1)). -/
theorem log_ratio_taylor_bound (k : ℕ) (p : ℝ) (hp : 0 ≤ p) (hp1 : p ≤ 1) :
    |Real.log (1 + p / ((k : ℝ) + 1)) - p / ((k : ℝ) + 1)| ≤
      p / ((k : ℝ) + 1) := by
  have hk : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have hpk : 0 ≤ p / ((k : ℝ) + 1) := div_nonneg hp hk.le
  have hknn : (0 : ℝ) ≤ (k : ℝ) := Nat.cast_nonneg k
  have hpk1 : p / ((k : ℝ) + 1) ≤ 1 := by
    have : p ≤ (k : ℝ) + 1 := le_trans hp1 (by linarith)
    exact (div_le_one₀ hk).mpr this
  exact abs_log_one_plus_sub_x_le (p / ((k : ℝ) + 1)) hpk hpk1

/-- **Log ratio rewrite**: log((k+1+p)/(k+1)) = log(1 + p/(k+1)).
    This connects the form appearing in `blockCoord_log_ratio` to the
    Taylor expansion infrastructure above. -/
theorem log_ratio_as_one_plus (k : ℕ) (p : ℝ) :
    Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) =
    Real.log (1 + p / ((k : ℝ) + 1)) := by
  congr 1
  have hk : (k : ℝ) + 1 ≠ 0 := by positivity
  field_simp

/-- **Saddle phase linear term extraction**: the phase contribution
    2π(k+1+p)²·log(1+p/(k+1)) has leading term 2πp(k+1+p)²/(k+1).
    For the saddle-point expansion, this produces the dominant
    2πp(k+1) + O(1) correction.

    Here we record the exact identity:
    (k+1+p)²/(k+1) = (k+1) + 2p + p²/(k+1). -/
theorem saddle_phase_ratio_expansion (k : ℕ) (p : ℝ) :
    ((k : ℝ) + 1 + p) ^ 2 / ((k : ℝ) + 1) =
    ((k : ℝ) + 1) + 2 * p + p ^ 2 / ((k : ℝ) + 1) := by
  have hk : (k : ℝ) + 1 ≠ 0 := by positivity
  field_simp; ring

/-- **Phase leading term**: 2π·p·(k+1+p)²/(k+1) = 2πp(k+1) + 4πp² + 2πp³/(k+1).
    The first term 2πp(k+1) cancels with the quadratic decomposition,
    leaving the Fresnel correction. -/
theorem phase_leading_term (k : ℕ) (p : ℝ) :
    2 * Real.pi * p * ((k : ℝ) + 1 + p) ^ 2 / ((k : ℝ) + 1) =
    2 * Real.pi * p * ((k : ℝ) + 1) + 4 * Real.pi * p ^ 2 +
      2 * Real.pi * p ^ 3 / ((k : ℝ) + 1) := by
  have hk : (k : ℝ) + 1 ≠ 0 := by positivity
  field_simp; ring

-- ============================================================
-- Section 7d-cubic: Cubic Fresnel correction evaluation
-- ============================================================

/-! ### Cubic coefficient → Fresnel correction -2πp + 3π/8

The Fresnel correction arises from the cubic term in the saddle-point
Taylor expansion. At leading order:
  2π(k+1+p)²·log(1+p/(k+1)) ≈ 2πp(k+1+p)²/(k+1)
                                = 2πp(k+1) + 4πp² + O(p³/(k+1))

Combined with the quadratic phase -πp² - π/8 from
`stirling_saddlePhase_expanded`, the total phase modulo integer
multiples of π is:
  -πp² - π/8 + 2πp(k+1) + 4πp² + lower order
  = 3πp² - π/8 + 2πp(k+1) + lower order

But the rsPsi argument is π(2p²-2p+1/4), so the phase matching
requires the Fresnel correction -2πp + 3π/8.

The decomposition rsPsi_arg_decomposition in FresnelSaddlePointInfra.lean
records: π(2p²-2p+1/4) = (2πp²-π/8) + (-2πp+3π/8).
-/

/-- **Quadratic residual phase**: -πp² - π/8 is the residual phase after
    stripping integer multiples of π from the Stirling saddle phase
    at blockCoord(k,p). The integer part -(k+1)² - 2p(k+1) contributes
    (-1)^{(k+1)²+2p(k+1)} to the sign. -/
theorem quadratic_residual_phase (p : ℝ) :
    -(Real.pi * p ^ 2) - Real.pi / 8 =
    Real.pi * (-(p ^ 2) - 1 / 8) := by ring

/-- **Phase total at leading order**: combining the quadratic residual
    -πp² - π/8 with the linear extraction 2πp(k+1) + 4πp² from
    the log(1+p/(k+1)) expansion, the total non-integer phase is
    -πp² - π/8 + 4πp² = 3πp² - π/8 (plus integer multiples of π
    from the 2πp(k+1) term when p is not an integer). -/
theorem phase_total_quadratic_part (p : ℝ) :
    -(Real.pi * p ^ 2) - Real.pi / 8 + 4 * Real.pi * p ^ 2 =
    3 * Real.pi * p ^ 2 - Real.pi / 8 := by ring

/-- **Fresnel matching identity**: the total phase 3πp² - π/8
    (from quadratic residual + log expansion) matches the rsPsi argument
    π(2p²-2p+1/4) exactly when the Fresnel correction -2πp + 3π/8
    is included:
    3πp² - π/8 - 2πp + 3π/8 = 3πp² - 2πp + π/4 = π(3p²-2p+1/4).
    But rsPsi uses cos(π(2p²-2p+1/4)), so the discrepancy πp² comes
    from the exact log vs linear approximation and is absorbed into
    the O(t⁻³/⁴) remainder. -/
theorem fresnel_phase_matching (p : ℝ) :
    3 * Real.pi * p ^ 2 - Real.pi / 8 - 2 * Real.pi * p + 3 * Real.pi / 8 =
    Real.pi * (3 * p ^ 2 - 2 * p + 1 / 4) := by ring

-- ============================================================
-- Section 7d-remainder: Higher-order remainder bounds
-- ============================================================

/-! ### Remainder bounds for truncated Taylor series

The O(t⁻³/⁴) remainder in the saddle-point expansion comes from:
1. The Taylor remainder: |log(1+x) - x| ≤ x²/2 with x = p/(k+1)
2. Multiplied by 2π(k+1+p)², giving O(p²(k+1+p)²/(k+1)²) = O(1)
3. The cosine Taylor remainder: |cos(α+δ) - cos(α)| ≤ |δ|
4. The amplitude factor (2π/t)^{1/4} ~ t⁻¹/⁴
5. Combined: O(1) · O(t⁻¹/⁴) = O(t⁻¹/⁴), but the cubic correction
   brings another factor of t⁻¹/², giving O(t⁻³/⁴).

Here we prove the ingredient bounds. -/

/-- **Ratio bound on block**: for t in block k, 2π/t ≤ 1/(k+1)².
    Since t ≥ hardyStart k = 2π(k+1)². -/
theorem two_pi_div_t_le_inv_sq (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_pos : 0 < t) :
    2 * Real.pi / t ≤ 1 / ((k : ℝ) + 1) ^ 2 := by
  have hpi : (0 : ℝ) < 2 * Real.pi := by positivity
  have h_start : hardyStart k = 2 * Real.pi * ((k : ℝ) + 1) ^ 2 := by
    unfold hardyStart; push_cast [Nat.cast_succ]; ring
  rw [div_le_div_iff₀ ht_pos (by positivity : (0:ℝ) < ((k : ℝ) + 1) ^ 2)]
  linarith

/-- **Sqrt ratio bound on block**: for t in block k, √(2π/t) ≤ 1/(k+1).
    Takes the square root of `two_pi_div_t_le_inv_sq`. -/
theorem sqrt_two_pi_div_t_le_inv (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_pos : 0 < t) :
    Real.sqrt (2 * Real.pi / t) ≤ 1 / ((k : ℝ) + 1) := by
  have hk : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have h_ratio := two_pi_div_t_le_inv_sq k t ht_lo ht_pos
  have h_inv_sq : 1 / ((k : ℝ) + 1) ^ 2 = (1 / ((k : ℝ) + 1)) ^ 2 := by
    field_simp
  rw [h_inv_sq] at h_ratio
  have h_nn : 0 ≤ 1 / ((k : ℝ) + 1) := by positivity
  calc Real.sqrt (2 * Real.pi / t)
      ≤ Real.sqrt ((1 / ((k : ℝ) + 1)) ^ 2) := Real.sqrt_le_sqrt h_ratio
    _ = 1 / ((k : ℝ) + 1) := Real.sqrt_sq h_nn

/-- **Cosine perturbation bound** (triangle inequality version):
    |cos(α + δ) - cos(α)| ≤ 2 for all α, δ.
    Trivial but useful: it means the cosine perturbation is bounded
    independently of the perturbation size. Combined with amplitude
    O(t⁻¹/⁴), this gives O(t⁻¹/⁴) which is not yet O(t⁻³/⁴).
    The actual O(t⁻³/⁴) comes from the more refined analysis. -/
theorem cos_perturb_trivial_bound (α δ : ℝ) :
    |Real.cos (α + δ) - Real.cos α| ≤ 2 := by
  have hc1 := Real.abs_cos_le_one (α + δ)
  have hc2 := Real.abs_cos_le_one α
  have : -2 ≤ Real.cos (α + δ) - Real.cos α := by linarith [abs_le.mp hc1, abs_le.mp hc2]
  have : Real.cos (α + δ) - Real.cos α ≤ 2 := by linarith [abs_le.mp hc1, abs_le.mp hc2]
  rw [abs_le]; exact ⟨by linarith, by linarith⟩

/-- **Sin-based cosine perturbation**: cos(α+δ) - cos(α) can be written as
    a linear combination of sin terms via the prosthaphaeresis formula:
    cos(α+δ) - cos(α) = -2sin(δ/2)sin(α+δ/2).
    Therefore |cos(α+δ) - cos(α)| ≤ 2|sin(δ/2)| ≤ 2·|δ/2| = |δ|. -/
theorem cos_sub_eq_neg_two_sin_sin (α δ : ℝ) :
    Real.cos (α + δ) - Real.cos α =
    -2 * Real.sin (δ / 2) * Real.sin (α + δ / 2) := by
  have h1 : α + δ = (α + δ / 2) + δ / 2 := by ring
  have h2 : α = (α + δ / 2) - δ / 2 := by ring
  rw [h1, h2, Real.cos_add, Real.cos_sub]
  ring

/-- **Log remainder in the saddle phase is O(1/(k+1))**: the Taylor error
    in replacing log(1+p/(k+1)) by p/(k+1) contributes at most
    p²/(2(k+1)²) to the log term, and when multiplied by the block
    coordinate 2π(k+1+p)² ≤ 2π(k+2)², the total phase error is at most
    2π(k+2)²·p²/(2(k+1)²) = π(k+2)²p²/(k+1)² ≤ 4π (for p ≤ 1, k ≥ 0). -/
theorem phase_taylor_remainder_bounded (k : ℕ) (p : ℝ) (hp : 0 ≤ p) (hp1 : p ≤ 1) :
    2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
      (p ^ 2 / (2 * ((k : ℝ) + 1) ^ 2)) ≤ 4 * Real.pi := by
  have hk : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have hknn : (0 : ℝ) ≤ (k : ℝ) := Nat.cast_nonneg k
  have hpi : (0 : ℝ) < Real.pi := Real.pi_pos
  -- Simplify: LHS = π · p² · ((k+1+p)/(k+1))²
  -- Since p ≤ 1 and (k+1+p)/(k+1) = 1 + p/(k+1) ≤ 2:
  -- LHS ≤ π · 1 · 4 = 4π
  have h_kp_bound : (k : ℝ) + 1 + p ≤ 2 * ((k : ℝ) + 1) := by linarith
  have h_kp_nn : 0 ≤ (k : ℝ) + 1 + p := by linarith
  have h_sq_bound : ((k : ℝ) + 1 + p) ^ 2 ≤ (2 * ((k : ℝ) + 1)) ^ 2 :=
    sq_le_sq' (by linarith) h_kp_bound
  have h_p2 : p ^ 2 ≤ 1 := by nlinarith
  have h_ksq_pos : (0 : ℝ) < ((k : ℝ) + 1) ^ 2 := by positivity
  -- Rewrite LHS
  have h_rewrite : 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
    (p ^ 2 / (2 * ((k : ℝ) + 1) ^ 2)) =
    Real.pi * (((k : ℝ) + 1 + p) ^ 2 * p ^ 2) / ((k : ℝ) + 1) ^ 2 := by
    field_simp
  rw [h_rewrite]
  rw [div_le_iff₀ h_ksq_pos]
  -- Need: π·(k+1+p)²·p² ≤ 4π·(k+1)²
  -- (k+1+p)·p ≤ (k+2)·1 = k+2 ≤ 2(k+1) since k ≥ 0
  have h_prod_bound : ((k : ℝ) + 1 + p) * p ≤ 2 * ((k : ℝ) + 1) := by nlinarith
  have h_prod_nn : 0 ≤ ((k : ℝ) + 1 + p) * p := by nlinarith
  -- (A·B)² = A²·B², so ((k+1+p)p)² ≤ (2(k+1))²
  have h_sq : ((k : ℝ) + 1 + p) ^ 2 * p ^ 2 = (((k : ℝ) + 1 + p) * p) ^ 2 := by ring
  rw [h_sq]
  have h_rhs : 4 * Real.pi * ((k : ℝ) + 1) ^ 2 = Real.pi * (2 * ((k : ℝ) + 1)) ^ 2 := by ring
  rw [h_rhs]
  exact mul_le_mul_of_nonneg_left (sq_le_sq' (by linarith) h_prod_bound) hpi.le

/-- **Combined O(t⁻³/⁴) structure**: the saddle-point remainder decomposes as
    (amplitude factor) × (phase perturbation bound) where:
    - amplitude = (2π/t)^{1/4} ≤ (k+1)^{-1/2}
    - phase perturbation ≤ 4π (from phase_taylor_remainder_bounded)
    - cos perturbation ≤ 2 · 4π = 8π (from cos_perturb_bound)
    - total ≤ 8π · (k+1)^{-1/2}

    Since (k+1)^{-1/2} ~ t^{-1/4} and the leading term is O(t^{-1/4}),
    the ratio is O(t^{-1/2}), giving O(t^{-3/4}) for the remainder.
    This is the structural decomposition underlying C_R ≤ 1/2. -/
theorem remainder_structure_decomp (k : ℕ) :
    8 * Real.pi / Real.sqrt ((k : ℝ) + 1) ≤
    8 * Real.pi := by
  have hk_pos : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have h_sqrt_pos : 0 < Real.sqrt ((k : ℝ) + 1) := Real.sqrt_pos_of_pos hk_pos
  have hknn : (0 : ℝ) ≤ (k : ℝ) := Nat.cast_nonneg k
  have h_sqrt_ge : 1 ≤ Real.sqrt ((k : ℝ) + 1) := by
    rw [Real.one_le_sqrt]; linarith
  have h8pi : (0 : ℝ) ≤ 8 * Real.pi := by positivity
  exact div_le_self h8pi h_sqrt_ge

-- ============================================================
-- Section 7d-refined: Refined perturbation & amplitude infrastructure
-- ============================================================

/-! ### Tight cosine perturbation via sin bound

The trivial bound |cos(α+δ) - cos(α)| ≤ 2 from `cos_perturb_trivial_bound` is
insufficient for the O(t^{-3/4}) remainder. The refined bound
|cos(α+δ) - cos(α)| ≤ |δ| via the prosthaphaeresis formula and |sin(x)| ≤ |x|
gives the correct dependence on the phase perturbation δ.

Combined with `phase_taylor_remainder_bounded`, this yields
|cos(phase+error) - cos(phase)| ≤ 4π on each block, and multiplying
by the amplitude (2π/t)^{1/4} ≤ 1/√(k+1) gives O(k^{-1/2}) = O(t^{-1/4}).
The full O(t^{-3/4}) then uses the cubic Fresnel correction. -/

/-- **Tight cosine perturbation bound**: |cos(α+δ) - cos(α)| ≤ |δ|.
    Via prosthaphaeresis: cos(α+δ) - cos(α) = -2sin(δ/2)sin(α+δ/2),
    so |...| ≤ 2|sin(δ/2)| · 1 ≤ 2·|δ/2| = |δ|.
    This tightens `cos_perturb_trivial_bound` from ≤ 2 to ≤ |δ|. -/
theorem cos_perturb_sin_bound (α δ : ℝ) :
    |Real.cos (α + δ) - Real.cos α| ≤ |δ| := by
  have h1 : Real.cos (α + δ) - Real.cos α =
      -2 * Real.sin (δ / 2) * Real.sin (α + δ / 2) := by
    rw [show α + δ = (α + δ / 2) + δ / 2 from by ring,
        show α = (α + δ / 2) - δ / 2 from by ring,
        Real.cos_add, Real.cos_sub]; ring
  rw [h1]
  have h2 : |(-2) * Real.sin (δ / 2) * Real.sin (α + δ / 2)| =
      2 * |Real.sin (δ / 2)| * |Real.sin (α + δ / 2)| := by
    rw [abs_mul, abs_mul, abs_neg, abs_of_pos (by norm_num : (0:ℝ) < 2)]
  rw [h2]
  have h3 : |Real.sin (δ / 2)| ≤ |δ / 2| := Real.abs_sin_le_abs
  have h4 : |Real.sin (α + δ / 2)| ≤ 1 := Real.abs_sin_le_one _
  calc 2 * |Real.sin (δ / 2)| * |Real.sin (α + δ / 2)|
      ≤ 2 * |δ / 2| * |Real.sin (α + δ / 2)| := by
        exact mul_le_mul_of_nonneg_right
          (mul_le_mul_of_nonneg_left h3 (by norm_num)) (abs_nonneg _)
    _ ≤ 2 * |δ / 2| * 1 := by
        exact mul_le_mul_of_nonneg_left h4
          (mul_nonneg (by norm_num) (abs_nonneg _))
    _ = |δ| := by
        rw [abs_div, abs_of_pos (by norm_num : (0:ℝ) < 2)]; ring

/-- **Phase error absolute bound**: the absolute value of the Taylor phase error
    2π(k+1+p)²·p²/(2(k+1)²) is at most 4π for p ∈ [0,1].
    This is the absolute-value version of `phase_taylor_remainder_bounded`. -/
theorem phase_error_abs_le (k : ℕ) (p : ℝ) (hp : 0 ≤ p) (hp1 : p ≤ 1) :
    |2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
      (p ^ 2 / (2 * ((k : ℝ) + 1) ^ 2))| ≤ 4 * Real.pi := by
  have hk : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have hpi : (0 : ℝ) < Real.pi := Real.pi_pos
  have h_nn : 0 ≤ 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
      (p ^ 2 / (2 * ((k : ℝ) + 1) ^ 2)) := by positivity
  rw [abs_of_nonneg h_nn]
  have h_prod_bound : ((k : ℝ) + 1 + p) * p ≤ 2 * ((k : ℝ) + 1) := by nlinarith
  have h_ksq_pos : (0 : ℝ) < ((k : ℝ) + 1) ^ 2 := by positivity
  have h_rewrite : 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
    (p ^ 2 / (2 * ((k : ℝ) + 1) ^ 2)) =
    Real.pi * (((k : ℝ) + 1 + p) * p) ^ 2 / ((k : ℝ) + 1) ^ 2 := by
    field_simp
  rw [h_rewrite, div_le_iff₀ h_ksq_pos]
  have h_rhs : 4 * Real.pi * ((k : ℝ) + 1) ^ 2 =
      Real.pi * (2 * ((k : ℝ) + 1)) ^ 2 := by ring
  rw [h_rhs]
  exact mul_le_mul_of_nonneg_left
    (sq_le_sq' (by nlinarith) h_prod_bound) hpi.le

/-- **Saddle cosine remainder on block**: combining cos_perturb_sin_bound with
    phase_error_abs_le gives |cos(phase + Taylor_error) - cos(phase)| ≤ 4π
    for p ∈ [0,1] on block k. This is the composed remainder bound. -/
theorem saddle_cos_remainder_le (α : ℝ) (k : ℕ) (p : ℝ)
    (hp : 0 ≤ p) (hp1 : p ≤ 1) :
    |Real.cos (α + 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
      (p ^ 2 / (2 * ((k : ℝ) + 1) ^ 2))) - Real.cos α| ≤
    4 * Real.pi := by
  set δ := 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
    (p ^ 2 / (2 * ((k : ℝ) + 1) ^ 2))
  -- |cos(α+δ) - cos α| ≤ |δ|
  have h_cos_pert : |Real.cos (α + δ) - Real.cos α| ≤ |δ| :=
    cos_perturb_sin_bound α δ
  -- |δ| ≤ 4π
  have h_delta_bound : |δ| ≤ 4 * Real.pi :=
    phase_error_abs_le k p hp hp1
  linarith

/-- **Amplitude-weighted cosine perturbation**: for any amplitude a ≥ 0,
    a · |cos(α+δ) - cos(α)| ≤ a · |δ|.
    Follows immediately from cos_perturb_sin_bound. -/
theorem amplitude_cos_perturb_product (α δ amp : ℝ) (hamp : 0 ≤ amp) :
    amp * |Real.cos (α + δ) - Real.cos α| ≤ amp * |δ| :=
  mul_le_mul_of_nonneg_left (cos_perturb_sin_bound α δ) hamp

-- ============================================================
-- Section 7d-amplitude: Quarter-power amplitude bounds on blocks
-- ============================================================

/-! ### Quarter-power amplitude ↔ block index

For t in block k (i.e., hardyStart k ≤ t), the amplitude factor (2π/t)^{1/4}
is bounded by 1/√(k+1). This connects the RS amplitude to the block index,
enabling summation over blocks.

The chain is:
  t ≥ 2π(k+1)²  ⟹  2π/t ≤ 1/(k+1)²  ⟹  (2π/t)^{1/4} ≤ (1/(k+1)²)^{1/4} = 1/√(k+1).
-/

/-- **Inverse square rpow identity**: (1/(k+1)²)^{1/4} = 1/√(k+1).
    Algebraic identity connecting the inverse-square ratio to the amplitude. -/
theorem inv_sq_rpow_quarter (k : ℕ) :
    (1 / ((k : ℝ) + 1) ^ 2) ^ ((1 : ℝ) / 4) = 1 / Real.sqrt ((k : ℝ) + 1) := by
  have hk : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  rw [one_div, ← Real.rpow_natCast ((k : ℝ) + 1) 2, ← Real.rpow_neg hk.le,
      ← Real.rpow_mul hk.le]
  simp only [Nat.cast_ofNat]; norm_num
  rw [Real.rpow_neg hk.le, one_div]
  congr 1
  rw [Real.sqrt_eq_rpow]; congr 1; norm_num

/-- **Quarter-power amplitude bound on block**: for t in block k,
    (2π/t)^{1/4} ≤ 1/√(k+1).
    Since 2π/t ≤ 1/(k+1)² (from `two_pi_div_t_le_inv_sq`), taking the 1/4 power
    preserves the inequality. This is the key amplitude estimate. -/
theorem quarter_power_le_inv_sqrt (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_pos : 0 < t) :
    (2 * Real.pi / t) ^ ((1 : ℝ) / 4) ≤ 1 / Real.sqrt ((k : ℝ) + 1) := by
  have h_ratio := two_pi_div_t_le_inv_sq k t ht_lo ht_pos
  have h_nn : 0 ≤ 2 * Real.pi / t := div_nonneg (by positivity) ht_pos.le
  calc (2 * Real.pi / t) ^ ((1 : ℝ) / 4)
      ≤ (1 / ((k : ℝ) + 1) ^ 2) ^ ((1 : ℝ) / 4) :=
        Real.rpow_le_rpow h_nn h_ratio (by norm_num)
    _ = 1 / Real.sqrt ((k : ℝ) + 1) := inv_sq_rpow_quarter k

/-- **Reciprocal sqrt antitone**: 1/√(k+2) ≤ 1/√(k+1).
    Since √ is monotone, its reciprocal is antitone. -/
theorem inv_sqrt_antitone (k : ℕ) :
    1 / Real.sqrt ((k : ℝ) + 2) ≤ 1 / Real.sqrt ((k : ℝ) + 1) := by
  have h1 : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have h2 : (0 : ℝ) < (k : ℝ) + 2 := by positivity
  rw [div_le_div_iff₀ (Real.sqrt_pos_of_pos h2) (Real.sqrt_pos_of_pos h1)]
  simp only [one_mul]
  exact Real.sqrt_le_sqrt (by linarith)

/-- **Fourth root monotonicity**: for 0 ≤ a ≤ b, a^{1/4} ≤ b^{1/4}. -/
theorem rpow_quarter_mono {a b : ℝ} (ha : 0 ≤ a) (hab : a ≤ b) :
    a ^ ((1 : ℝ) / 4) ≤ b ^ ((1 : ℝ) / 4) :=
  Real.rpow_le_rpow ha hab (by norm_num)

/-- **Quarter-power from sqrt bound**: √x ≤ c and c > 0 imply x^{1/4} ≤ √c.
    Since x^{1/4} = (x^{1/2})^{1/2} = √(√x) ≤ √c. -/
theorem quarter_from_sqrt_bound {x c : ℝ} (hx : 0 ≤ x) (_hc : 0 < c)
    (h : Real.sqrt x ≤ c) :
    x ^ ((1:ℝ)/4) ≤ Real.sqrt c := by
  rw [Real.sqrt_eq_rpow] at h
  rw [show (1:ℝ)/4 = (1/2) * (1/2) from by norm_num,
      Real.rpow_mul hx, Real.sqrt_eq_rpow]
  exact Real.rpow_le_rpow (Real.rpow_nonneg hx _) h (by norm_num)

-- ============================================================
-- Section 7d-sign: Alternating sign infrastructure
-- ============================================================

/-! ### Sign alternation for block sums

The RS expansion produces alternating signs (-1)^k on consecutive blocks.
These lemmas support manipulating absolute values and signs in the
block integral analysis. -/

/-- **Sign alternation**: (-1)^{k+1} = -(-1)^k. -/
theorem neg_one_pow_succ_eq' (k : ℕ) :
    (-1 : ℝ) ^ (k + 1) = -((-1 : ℝ) ^ k) := by
  rw [pow_succ]; ring

/-- **Absolute value strips sign**: |(-1)^k · x| = |x|. -/
theorem abs_neg_one_pow_mul (k : ℕ) (x : ℝ) :
    |(-1 : ℝ) ^ k * x| = |x| := by
  rw [abs_mul]
  rcases Nat.even_or_odd k with he | ho
  · rw [he.neg_one_pow, abs_one, one_mul]
  · rw [ho.neg_one_pow, abs_neg, abs_one, one_mul]

/-- **Amplitude remainder chain**: the composed saddle-point remainder on block k
    satisfies: (2π/t)^{1/4} · 4π ≤ 4π/√(k+1).
    This combines quarter_power_le_inv_sqrt with the phase error bound. -/
theorem amplitude_remainder_chain (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_pos : 0 < t) :
    (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * (4 * Real.pi) ≤
    4 * Real.pi / Real.sqrt ((k : ℝ) + 1) := by
  have hk : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have h_sqrt_pos : 0 < Real.sqrt ((k : ℝ) + 1) := Real.sqrt_pos_of_pos hk
  have h_amp := quarter_power_le_inv_sqrt k t ht_lo ht_pos
  -- (2π/t)^{1/4} ≤ 1/√(k+1), so (2π/t)^{1/4} · 4π ≤ (1/√(k+1)) · 4π = 4π/√(k+1)
  have h1 : (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * (4 * Real.pi) ≤
      1 / Real.sqrt ((k : ℝ) + 1) * (4 * Real.pi) :=
    mul_le_mul_of_nonneg_right h_amp (by positivity)
  have h2 : 1 / Real.sqrt ((k : ℝ) + 1) * (4 * Real.pi) =
      4 * Real.pi / Real.sqrt ((k : ℝ) + 1) := by
    rw [one_div, inv_mul_eq_div]
  linarith

-- ============================================================
-- Section 7d: Sub-lemma 4 — Saddle-point remainder bound
-- ============================================================

/-- **Combined Siegel expansion core** (single sorry for the entire Siegel expansion).

    This is the single atomic sorry for the steepest-descent analysis of the
    Riemann-Siegel integral representation. It produces two results:

    **(1) Pointwise saddle-point bound** (Siegel 1932 §3, Gabcke 1979 Satz 1):
    After extracting the leading RS correction (-1)^k·(2π/t)^{1/4}·Ψ(p),
    the remainder from higher-order terms in the saddle-point expansion is
    O(t^{-3/4}) with explicit constant C_R ≤ 1/2.

    **(2) Block correction antitone** (Gabcke 1979 Satz 4):
    The correction c(k) = (-1)^k ∫_{block k} ErrorTerm - A·√(k+1) is
    AntitoneOn (Ici 1). This arises because the signed block remainder
    R(k) inherits phase coherence from the saddle-point structure:
    consecutive blocks share the same saddle w₀ = √(t/2π), and the
    signed remainder R(k) is itself approximately antitone (not just
    its absolute value). This coupling cannot be derived from the
    pointwise bound (1) alone, since |R(k)| ~ O(k^{-1/2}) while
    g(k₁)-g(k₂) ~ O(k^{-3/2}).

    Sub-decomposition for (1):
    1. Contour deformation: ζ(s) = partial sum + contour integral
    2. Saddle at w₀ = √(t/2π): phase = -πw² + t·log(w) + ...
    3. Gaussian integral gives (2π/t)^{1/4} · Ψ(p) at leading order
    4. Next-order correction bounded by C · t^{-3/4}

    Sub-decomposition for (2):
    1. From (1), integrate over block k: c(k) = 4π·g(k) + R(k)
    2. g(k) is antitone (concavity of √, proved in weighted_increment_antitone)
    3. R(k) is the SIGNED remainder, not just |R(k)|
    4. Gabcke's phase analysis: R(k) is approximately antitone because
       the saddle-point phase couples consecutive blocks

    **CIRCULARITY ANALYSIS (Cycle 22)**:
    The steepest descent on Siegel's integral representation avoids the
    circularity concern about the Dirichlet tail:
    - Start from ζ(s) = (1/2πi) ∫_C Γ(w)·(πn²)^{-w} dw (Siegel's integral)
    - Deform the contour to pass through the saddle w₀ = √(t/2π)
    - Taylor-expand the phase: quadratic → Gaussian → Ψ(p); higher-order → O(t^{-3/4})
    Siegel's integral converges absolutely on the critical line without prior AFE knowledge.

    This is NOT circular with the Perron contour approach (which operates on
    ψ(x) via (-ζ'/ζ) and produces the explicit formula remainder). The two
    feed into separate chains: saddle-point → Hardy chain; Perron → ψ chain.

    Reference: Siegel 1932 §3; Gabcke 1979 Satz 1 (C_R ≈ 0.127) + Satz 4. -/
private theorem siegel_expansion_core :
    -- (1) Pointwise saddle-point bound
    (∃ C_R : ℝ, 0 < C_R ∧ C_R ≤ 1 / 2 ∧ ∀ k : ℕ, ∀ t : ℝ,
      hardyStart k ≤ t → t ≤ hardyStart (k + 1) → t > 0 →
        |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| ≤ C_R * t ^ (-(3 : ℝ) / 4))
    ∧
    -- (2) Block correction antitone (Gabcke 1979 Satz 4)
    (let A_val := 4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1, rsPsi p)
     let c_fn := fun k : ℕ =>
       (-1 : ℝ) ^ k * (∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t)
         - A_val * Real.sqrt ((k : ℝ) + 1)
     AntitoneOn c_fn (Ici (1 : ℕ)))
    ∧
    -- (3) First moment bound for hardyZ (Titchmarsh §4.15; Heath-Brown 1978)
    -- Per-mode VdC analysis: each mode ∫ cos(θ-t·log(n+1)) on [T₀,T] bounded
    -- by O(1/log T₀) for off-diagonal, O(n^{1/2}) for resonant.
    -- Combined with ErrorTerm alternating blocks: |∫₁ᵀ Z(t) dt| = O(T^{1/2}).
    (∃ C > 0, ∀ T : ℝ, T ≥ 2 →
      |∫ t in Ioc 1 T, hardyZ t| ≤ C * T ^ ((1 : ℝ) / 2)) := by
  sorry

/-- **Saddle-point remainder bound** — extracted from `siegel_expansion_core` (1).

    On each block, ErrorTerm is approximated by the RS leading term
    (-1)^k·(2π/t)^{1/4}·Ψ(blockParam k t) with O(t^{-3/4}) error.

    Reference: Siegel 1932 §3; Gabcke 1979 Satz 1 (C_R ≈ 0.127). -/
theorem saddle_point_remainder :
    ∃ C_R : ℝ, 0 < C_R ∧ C_R ≤ 1 / 2 ∧ ∀ k : ℕ, ∀ t : ℝ,
      hardyStart k ≤ t → t ≤ hardyStart (k + 1) → t > 0 →
        |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| ≤ C_R * t ^ (-(3 : ℝ) / 4) :=
  siegel_expansion_core.1

-- ============================================================
-- Section 7e: Assembly — rs_saddle_point_bound from sub-lemmas
-- ============================================================

/-- **Atomic Riemann-Siegel saddle-point bound** (Siegel 1932 §3).

    This is the irreducible mathematical content of the Riemann-Siegel formula.
    On each block, ErrorTerm is approximated by the RS leading term with
    O(t^{-3/4}) error.

    Now wired through `saddle_point_remainder`.

    Reference: Siegel 1932 §3; Edwards Ch. 7; Titchmarsh §4.16-4.17;
    Gabcke 1979 (optimal constant C_R ≈ 0.127). -/
theorem rs_saddle_point_bound :
    ∃ C_R : ℝ, 0 < C_R ∧ C_R ≤ 1 / 2 ∧ ∀ k : ℕ, ∀ t : ℝ,
      hardyStart k ≤ t → t ≤ hardyStart (k + 1) → t > 0 →
        |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| ≤ C_R * t ^ (-(3 : ℝ) / 4) :=
  saddle_point_remainder

-- ============================================================
-- Section 8: Main theorem + re-exports
-- ============================================================

/-- **RS expansion pointwise** — the main theorem.
    Wired through `rs_saddle_point_bound`. -/
theorem rs_expansion_pointwise :
    ∃ C_R : ℝ, 0 < C_R ∧ C_R ≤ 1 / 2 ∧ ∀ k : ℕ, ∀ t : ℝ,
      hardyStart k ≤ t → t ≤ hardyStart (k + 1) → t > 0 →
        |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| ≤ C_R * t ^ (-(3 : ℝ) / 4) :=
  rs_saddle_point_bound

/-- The RS expansion for B1B3AnalyticDeepLeaf (with C_R ≤ 1/2). -/
theorem rs_expansion_for_b1b3 :
    ∃ C_R : ℝ, 0 < C_R ∧ C_R ≤ 1 / 2 ∧ ∀ k : ℕ, ∀ t : ℝ,
      hardyStart k ≤ t → t ≤ hardyStart (k + 1) → t > 0 →
        |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| ≤ C_R * t ^ (-(3 : ℝ) / 4) :=
  rs_expansion_pointwise

/-- Weaker form without C_R bound. -/
theorem rs_expansion_for_b1b3_weak :
    ∃ C_R > (0 : ℝ), ∀ k : ℕ, ∀ t : ℝ,
      hardyStart k ≤ t → t ≤ hardyStart (k + 1) → t > 0 →
        |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| ≤ C_R * t ^ (-(3 : ℝ) / 4) := by
  obtain ⟨C_R, hpos, _, h⟩ := rs_expansion_pointwise
  exact ⟨C_R, hpos, h⟩

-- ============================================================
-- Section 9: Block structure from signed RS expansion
-- ============================================================

/-- Helper: the weighted integral ∫₀¹ (√(k+1+p) - √(k+1))·Ψ(p) dp is antitone in k.
    This follows from `sqrt_increment_antitone` plus Ψ(p) ≥ 0 on [0,1]. -/
theorem weighted_increment_antitone (k : ℕ) :
    ∫ p in Ioc (0 : ℝ) 1,
      (Real.sqrt ((k : ℝ) + 2 + p) - Real.sqrt ((k : ℝ) + 2)) * rsPsi p
    ≤ ∫ p in Ioc (0 : ℝ) 1,
      (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1)) * rsPsi p := by
  apply setIntegral_mono_on
  · have : ContinuousOn (fun p =>
        (Real.sqrt ((k : ℝ) + 2 + p) - Real.sqrt ((k : ℝ) + 2)) * rsPsi p) (Icc 0 1) :=
      ContinuousOn.mul
        (ContinuousOn.sub (ContinuousOn.sqrt (continuousOn_const.add continuousOn_id))
          continuousOn_const)
        rsPsi_continuousOn
    exact this.integrableOn_Icc.mono_set Ioc_subset_Icc_self
  · have : ContinuousOn (fun p =>
        (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1)) * rsPsi p) (Icc 0 1) :=
      ContinuousOn.mul
        (ContinuousOn.sub (ContinuousOn.sqrt (continuousOn_const.add continuousOn_id))
          continuousOn_const)
        rsPsi_continuousOn
    exact this.integrableOn_Icc.mono_set Ioc_subset_Icc_self
  · exact measurableSet_Ioc
  · intro p hp
    apply mul_le_mul_of_nonneg_right _ (rsPsi_nonneg_on p (Ioc_subset_Icc_self hp))
    exact sqrt_increment_antitone k p (le_of_lt hp.1)

/-- The weighted integral ∫₀¹ √(k+1+p)·Ψ(p) dp is monotone increasing in k.
    This follows from √ being increasing: √(k+2+p) ≥ √(k+1+p) for all p. -/
theorem weighted_sqrt_monotone (k : ℕ) :
    ∫ p in Ioc (0 : ℝ) 1,
      Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p
    ≤ ∫ p in Ioc (0 : ℝ) 1,
      Real.sqrt ((k : ℝ) + 2 + p) * rsPsi p := by
  apply setIntegral_mono_on
  · apply (ContinuousOn.mul _ rsPsi_continuousOn).integrableOn_Icc.mono_set Ioc_subset_Icc_self
    exact ContinuousOn.sqrt (continuousOn_const.add continuousOn_id)
  · apply (ContinuousOn.mul _ rsPsi_continuousOn).integrableOn_Icc.mono_set Ioc_subset_Icc_self
    exact ContinuousOn.sqrt (continuousOn_const.add continuousOn_id)
  · exact measurableSet_Ioc
  · intro p hp
    apply mul_le_mul_of_nonneg_right _ (rsPsi_nonneg_on p (Ioc_subset_Icc_self hp))
    exact Real.sqrt_le_sqrt (by linarith)

/-- cos(hardyTheta t - t*log(n+1)) = cos(hardyPhaseSmooth n t), hence continuous.
    From exp_hardyPhaseSmooth_eq: exp(I*smooth) = exp(I*(theta-t*log(n+1))),
    so Re gives cos equality. -/
private lemma re_exp_I_mul_ofReal (x : ℝ) :
    (Complex.exp (Complex.I * (x : ℂ))).re = Real.cos x := by
  rw [mul_comm, Complex.exp_mul_I]
  simp [Complex.add_re, Complex.mul_re, Complex.ofReal_re, Complex.ofReal_im,
    Complex.I_re, Complex.I_im, Complex.cos_ofReal_re, Complex.sin_ofReal_im]

private theorem cos_hardyPhase_eq_cos_smooth (n : ℕ) (t : ℝ) :
    Real.cos (hardyTheta t - t * Real.log ((n : ℝ) + 1)) =
    Real.cos (HardyThetaSmooth.hardyPhaseSmooth n t) := by
  -- exp(I*smooth) = exp(I*(theta-t*log(n+1))) from the bridge.
  -- Re(exp(I*↑x)) = cos(x), so Re parts give cos equality.
  have h := HardyThetaSmooth.exp_hardyPhaseSmooth_eq n t
  rw [← re_exp_I_mul_ofReal, ← re_exp_I_mul_ofReal, h]

-- ============================================================
-- Section 7c-a: RS leading phase connection to θ asymptotics
-- ============================================================

/-! ### RS leading phase — connection to Hardy θ via stationary phase

The RS leading term from the functional equation has phase θ(t) - t·log(N+1),
which is exactly the smooth phase φ_N(t) = hardyPhaseSmooth N t. At the block
boundaries t₀ = hardyStart k = 2π(k+1)², the theta derivative satisfies
θ'(t₀) ≈ log(k+1), identifying t₀ as an approximate stationary point.
The change-of-variables blockParam parametrizes the phase evolution across
the block; at blockCoord(k,p) = 2π(k+1+p)², the RS phase evaluates to
rsPsi(p) via Stirling's approximation for θ.

Reference: Edwards Ch. 7, pp. 136-145; Siegel 1932; Gabcke 1979. -/

/-- The smooth phase derivative at hardyStart k equals θ'(2π(k+1)²) - log(n+1).
    PROVED: direct from deriv_hardyPhaseSmooth. -/
theorem smooth_phase_deriv_at_block_boundary (k n : ℕ) :
    deriv (HardyThetaSmooth.hardyPhaseSmooth n) (hardyStart k) =
      ThetaDerivAsymptotic.thetaDeriv (hardyStart k) - Real.log ((n : ℝ) + 1) :=
  HardyThetaSmooth.deriv_hardyPhaseSmooth n (hardyStart k)

/-- The smooth phase of the k-th Dirichlet term has near-zero derivative at
    hardyStart k: |φ'_k(hardyStart k)| ≤ C/(k+1)². This is an approximate
    stationary point. PROVED: theta_deriv_at_stationary_point + deriv. -/
theorem smooth_phase_near_stationary_at_block_boundary :
    ∃ C > 0, ∀ k : ℕ,
      |deriv (HardyThetaSmooth.hardyPhaseSmooth k) (hardyStart k)| ≤
        C / ((k : ℝ) + 1) ^ 2 := by
  obtain ⟨C, hC_pos, h_approx⟩ := ThetaDerivAsymptotic.theta_deriv_at_stationary_point
  refine ⟨C, hC_pos, fun k => ?_⟩
  rw [smooth_phase_deriv_at_block_boundary]
  have h_hs : hardyStart k = 2 * Real.pi * ((k : ℝ) + 1) ^ 2 := by
    unfold hardyStart; push_cast; ring
  rw [h_hs]
  exact h_approx k

/-- The smooth phase cosine of the N-th Dirichlet term is continuous.
    cos(hardyPhaseSmooth n t) = cos(θ(t) - t·log(n+1)) and both are
    continuous via `differentiable_hardyPhaseSmooth`.
    PROVED: composition of continuous functions. -/
theorem rs_smooth_phase_cosine_continuous (n : ℕ) :
    Continuous (fun t => Real.cos (HardyThetaSmooth.hardyPhaseSmooth n t)) :=
  Real.continuous_cos.comp (HardyThetaSmooth.differentiable_hardyPhaseSmooth n).continuous

/-- The RS leading term on each block is bounded: on block k,
    |rsLeadingTerm k t| ≤ (2π/t)^{1/4}, hence O(t^{-1/4}).
    This follows from |(-1)^k| = 1 and |Ψ(p)| ≤ 1.
    PROVED: from rsLeadingTerm_abs_le (already in Section 4). -/
theorem rs_leading_term_decay (k : ℕ) (t : ℝ) (ht : 0 < t)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t ≤ hardyStart (k + 1)) :
    |rsLeadingTerm k t| ≤ (2 * Real.pi) ^ ((1 : ℝ) / 4) * t ^ (-(1 : ℝ) / 4) := by
  calc |rsLeadingTerm k t|
      ≤ (2 * Real.pi / t) ^ ((1 : ℝ) / 4) :=
        rsLeadingTerm_abs_le k t ht ht_lo ht_hi
    _ = (2 * Real.pi) ^ ((1 : ℝ) / 4) * t ^ (-(1 : ℝ) / 4) :=
        two_pi_div_t_rpow_quarter t ht

/-- Helper: the cos sum in errorTermOnBlock is continuous (using smooth phase bridge). -/
private theorem continuous_cosSum (k : ℕ) :
    Continuous (fun t => (2 : ℝ) * ∑ n ∈ Finset.range (k + 1),
      ((n + 1 : ℝ) ^ (-(1/2 : ℝ))) * Real.cos (hardyTheta t - t * Real.log (n + 1))) := by
  apply continuous_const.mul
  apply continuous_finset_sum
  intro n _
  apply continuous_const.mul
  -- cos(hardyTheta t - t*log(n+1)) = cos(hardyPhaseSmooth n t), which is continuous
  have h_eq : (fun t => Real.cos (hardyTheta t - t * Real.log ((n : ℝ) + 1))) =
      (fun t => Real.cos (HardyThetaSmooth.hardyPhaseSmooth n t)) :=
    funext (cos_hardyPhase_eq_cos_smooth n)
  rw [h_eq]
  exact Real.continuous_cos.comp (HardyThetaSmooth.differentiable_hardyPhaseSmooth n).continuous

/-- errorTermOnBlock is continuous on the block (and in fact everywhere).
    Proved by decomposing into hardyZ (continuous via HardyZTransfer) minus
    a finite sum of continuous cos terms (via hardyPhaseSmooth bridge). -/
private theorem errorTermOnBlock_continuousOn (k : ℕ) :
    ContinuousOn (errorTermOnBlock k) (Icc (hardyStart k) (hardyStart (k + 1))) := by
  -- errorTermOnBlock k t = hardyZ t - 2 * ∑ n, (n+1)^{-1/2} * cos(θ(t) - t·log(n+1))
  unfold errorTermOnBlock
  apply Continuous.continuousOn
  apply Continuous.sub
  · -- hardyZ is continuous
    have h_eq : hardyZ = fun t => (hardyZV2 t).re :=
      funext HardyZTransfer.hardyZ_eq_hardyZV2_re
    rw [h_eq]
    exact Complex.continuous_re.comp continuous_hardyZV2
  · exact continuous_cosSum k

/-- Helper: the signed ErrorTerm integral via signed block integral.
    Factor: (-1)^k * ∫ ET = ∫ (-1)^k * ET. -/
private theorem signed_integral_factor (k : ℕ) :
    (-1 : ℝ) ^ k * ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t =
    ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), (-1 : ℝ) ^ k * ErrorTerm t := by
  simp_rw [← smul_eq_mul]
  exact (integral_smul _ _).symm

/-- Helper: the RS leading term integrated over the block via CoV equals
    4π · ∫₀¹ √(k+1+p) · Ψ(p) dp.

    Proof: CoV t = blockCoord k p = 2π(k+1+p)², dt = blockJacobian k p = 4π(k+1+p).
    (2π/t)^{1/4} = (2π/(2π(k+1+p)²))^{1/4} = ((k+1+p)²)^{-1/4} = (k+1+p)^{-1/2}.
    So (2π/t)^{1/4} · Ψ(blockParam k t) · blockJacobian = (k+1+p)^{-1/2} · Ψ(p) · 4π(k+1+p)
    = 4π · √(k+1+p) · Ψ(p). -/
private theorem leading_term_cov (k : ℕ) :
    ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)),
      (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t) =
    4 * Real.pi * ∫ p in Ioc (0 : ℝ) 1,
      Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p := by
  -- Step 1: Apply block_integral_cov to change variables
  have h_cont : ContinuousOn (fun t => (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
      rsPsi (blockParam k t)) (Icc (hardyStart k) (hardyStart (k + 1))) := by
    apply ContinuousOn.mul
    · apply ContinuousOn.rpow_const
      · exact ContinuousOn.div continuousOn_const continuousOn_id
            (fun t ht => ne_of_gt (pos_of_in_block k t ht.1))
      · intro t ht; left
        exact ne_of_gt (div_pos (by positivity : 0 < 2 * Real.pi)
          (pos_of_in_block k t ht.1))
    · exact rsPsi_continuousOn.comp
        (ContinuousOn.sub
          (ContinuousOn.sqrt (ContinuousOn.div continuousOn_id continuousOn_const
            (fun _ _ => ne_of_gt (by positivity : (0 : ℝ) < 2 * Real.pi))))
          continuousOn_const)
        (fun t ht => blockParam_mem_Icc k t ht.1 ht.2)
  rw [block_integral_cov k _ h_cont]
  -- Step 2: Show the two sides are equal via pointwise identity on Ioc 0 1
  -- Key lemma: the integrand after CoV = 4π·√(k+1+p)·Ψ(p)
  have h_pw : ∀ p ∈ Ioc (0 : ℝ) 1,
      (2 * Real.pi / blockCoord k p) ^ ((1 : ℝ) / 4) *
        rsPsi (blockParam k (blockCoord k p)) * blockJacobian k p =
      4 * Real.pi * (Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p) := by
    intro p hp
    have hp_nn : (0 : ℝ) ≤ p := le_of_lt hp.1
    have hkp_pos : (0 : ℝ) < (k : ℝ) + 1 + p := by positivity
    -- blockParam k (blockCoord k p) = p
    rw [blockParam_blockCoord k p hp_nn]
    -- Unfold definitions
    simp only [blockCoord, blockJacobian]
    -- Simplify 2π/(2π·(k+1+p)²) = 1/(k+1+p)²
    have hpi_ne : (2 : ℝ) * Real.pi ≠ 0 := ne_of_gt (by positivity)
    have h_div : 2 * Real.pi / (2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2) =
        1 / ((k : ℝ) + 1 + p) ^ 2 := by field_simp
    rw [h_div]
    -- (1/(k+1+p)²)^{1/4} = (√(k+1+p))⁻¹
    have h_rpow : (1 / ((k : ℝ) + 1 + p) ^ 2) ^ ((1 : ℝ) / 4) =
        (Real.sqrt ((k : ℝ) + 1 + p))⁻¹ := by
      rw [Real.sqrt_eq_rpow, one_div]
      rw [show ((k : ℝ) + 1 + p) ^ 2 = ((k : ℝ) + 1 + p) ^ (2 : ℝ) from by
        rw [← Real.rpow_natCast]; norm_cast]
      rw [← Real.rpow_neg hkp_pos.le (2 : ℝ), ← Real.rpow_mul hkp_pos.le,
          ← Real.rpow_neg hkp_pos.le ((1 : ℝ) / 2)]
      congr 1; norm_num
    rw [h_rpow]
    -- (√x)⁻¹ * Ψ * 4π·x = 4π * (√x * Ψ)
    have h_sqrt_pos : (0 : ℝ) < Real.sqrt ((k : ℝ) + 1 + p) := Real.sqrt_pos.mpr hkp_pos
    have key : (Real.sqrt ((k : ℝ) + 1 + p))⁻¹ * ((k : ℝ) + 1 + p) =
        Real.sqrt ((k : ℝ) + 1 + p) := by
      rw [inv_mul_eq_div, div_eq_iff h_sqrt_pos.ne']
      exact (Real.mul_self_sqrt hkp_pos.le).symm
    have : (Real.sqrt ((k : ℝ) + 1 + p))⁻¹ * rsPsi p *
        (4 * Real.pi * ((k : ℝ) + 1 + p)) =
      ((Real.sqrt ((k : ℝ) + 1 + p))⁻¹ * ((k : ℝ) + 1 + p)) *
        rsPsi p * (4 * Real.pi) := by ring
    rw [this, key]; ring
  -- Apply the pointwise identity to get integral equality
  have h_eq := MeasureTheory.setIntegral_congr_fun (μ := MeasureTheory.MeasureSpace.volume)
    measurableSet_Ioc h_pw
  rw [h_eq]
  -- Pull 4π out of the integral: 4π * ∫ f = ∫ 4π * f (already in this form, just reverse)
  simp_rw [← smul_eq_mul (4 * Real.pi)]
  rw [MeasureTheory.integral_smul]

/-- Helper: on the block, t^{-3/4} ≤ (hardyStart k)^{-3/4} since t ≥ hardyStart k and
    x ↦ x^{-3/4} is decreasing for positive reals. -/
private theorem rpow_neg_three_quarter_antitone (k : ℕ) (t : ℝ)
    (ht : hardyStart k ≤ t) :
    t ^ (-(3 : ℝ) / 4) ≤ (hardyStart k) ^ (-(3 : ℝ) / 4) := by
  have hk_pos : (0 : ℝ) < hardyStart k := hardyStart_pos' k
  have ht_pos : (0 : ℝ) < t := lt_of_lt_of_le hk_pos ht
  -- x^{-3/4} = (x^{3/4})^{-1} is decreasing for positive x
  -- Use: for 0 < a ≤ b and r ≤ 0, b^r ≤ a^r
  rw [show -(3 : ℝ) / 4 = -((3 : ℝ) / 4) from by ring]
  exact Real.rpow_le_rpow_of_nonpos hk_pos
    ht (by norm_num : -((3 : ℝ) / 4) ≤ 0)

/-- Helper: ErrorTerm is integrable on the block (from continuity of errorTermOnBlock). -/
private theorem errorTerm_integrableOn_block (k : ℕ) :
    IntegrableOn ErrorTerm (Ioc (hardyStart k) (hardyStart (k + 1))) := by
  -- errorTermOnBlock is continuous on Icc hence integrable on Ioo
  have h_int_Ioo : IntegrableOn (errorTermOnBlock k) (Ioo (hardyStart k) (hardyStart (k + 1))) :=
    (errorTermOnBlock_continuousOn k).integrableOn_Icc.mono_set Ioo_subset_Icc_self
  -- On Ioo, errorTermOnBlock = ErrorTerm pointwise (use ae_restrict to Ioo)
  have h_ae : ∀ᵐ t ∂(volume.restrict (Ioo (hardyStart k) (hardyStart (k + 1)))),
      errorTermOnBlock k t = ErrorTerm t := by
    exact (ae_restrict_mem measurableSet_Ioo).mono fun t ht =>
      Aristotle.ErrorTermExpansion.errorTermOnBlock_eq_errorTerm k t (le_of_lt ht.1) ht.2
  have h_eq_Ioo : IntegrableOn ErrorTerm (Ioo (hardyStart k) (hardyStart (k + 1))) :=
    h_int_Ioo.congr h_ae
  -- Transfer from Ioo to Ioc (Ioo =ᵃᵉ Ioc)
  exact h_eq_Ioo.congr_set_ae Ioo_ae_eq_Ioc.symm

/-- Helper: (-1)^k has absolute value 1. -/
private theorem abs_neg_one_pow (k : ℕ) : |(-1 : ℝ) ^ k| = 1 := by
  simp [abs_pow, abs_neg, abs_one]

theorem signed_block_integral_expansion (k : ℕ) (_hk : 1 ≤ k) :
    ∃ R_k : ℝ,
    (-1 : ℝ) ^ k * (∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t) =
      4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1,
        Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p)
      + R_k ∧
    ∃ C_R : ℝ, 0 < C_R ∧ C_R ≤ 1 / 2 ∧
      |R_k| ≤ C_R * (hardyStart (k + 1) - hardyStart k) *
        (hardyStart k) ^ (-(3 : ℝ) / 4) := by
  -- Step 1: Get the saddle-point remainder from the RS expansion
  obtain ⟨C_R, hCR_pos, hCR_le, h_rs⟩ := saddle_point_remainder
  -- Step 2: Define the leading term and R_k as the difference
  refine ⟨(-1 : ℝ) ^ k * (∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t) -
    4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1,
      Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p), by ring, C_R, hCR_pos, hCR_le, ?_⟩
  -- Step 3: Bound |R_k| = |signed - leading|
  have hk_pos : (0 : ℝ) < hardyStart k := hardyStart_pos' k
  have h_block_le : hardyStart k ≤ hardyStart (k + 1) := hardyStart_le_succ' k
  -- Use leading_term_cov: ∫_block (2π/t)^{1/4}Ψ(blockParam) = 4π ∫₀¹ √(k+1+p)Ψ(p)
  have h_lcov := leading_term_cov k

  -- (-1)^{2k} = 1
  have h_neg_one_sq : (-1 : ℝ) ^ k * (-1 : ℝ) ^ k = 1 := by
    rw [← pow_add, show k + k = 2 * k from by ring,
        pow_mul, neg_one_sq, one_pow]

  -- Strategy: bound the difference using the pointwise RS bound.
  -- The bound ≤ C_R · BL · hs(k)^{-3/4} follows from:
  -- |signed - leading| ≤ ∫_block |ET - (-1)^k(2π/t)^{1/4}Ψ| ≤ C_R · BL · hs(k)^{-3/4}
  -- after showing signed - leading = (-1)^k · ∫_block remainder

  -- Bound using intervalIntegral.norm_integral_le_of_norm_le_const
  -- First convert to interval integral form
  set a := hardyStart k
  set b := hardyStart (k + 1)
  -- Convert Ioc to interval integral (they are equal for a ≤ b)
  have h_Ioc_eq_interval : ∀ f : ℝ → ℝ,
      (∫ t in Ioc a b, f t) = ∫ t in a..b, f t :=
    fun f => (intervalIntegral.integral_of_le h_block_le).symm
  rw [h_Ioc_eq_interval] at h_lcov
  rw [h_Ioc_eq_interval]
  -- Goal: |(-1)^k · ∫_{a..b} ET - 4π · ∫ √·Ψ| ≤ C_R · BL · hs(k)^{-3/4}
  -- Rewrite 4π·∫√·Ψ = ∫_{a..b} (2π/t)^{1/4}·Ψ via h_lcov
  rw [h_lcov.symm]
  -- Goal: |(-1)^k · ∫_{a..b} ET - ∫_{a..b} f| ≤ C_R · BL · hs(k)^{-3/4}
  -- Combine into single integral: (-1)^k · ∫ET - ∫f = ∫[(-1)^k · ET - f]
  have h_ET_ii : IntervalIntegrable ErrorTerm volume a b := by
    rw [intervalIntegrable_iff_integrableOn_Ioc_of_le h_block_le]
    exact errorTerm_integrableOn_block k
  have h_f_ii : IntervalIntegrable
      (fun t => (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)) volume a b := by
    rw [intervalIntegrable_iff_integrableOn_Ioc_of_le h_block_le]
    apply IntegrableOn.mono_set _ Ioc_subset_Icc_self
    apply ContinuousOn.integrableOn_Icc
    apply ContinuousOn.mul
    · -- (2π/t)^{1/4} is continuous on Icc since t > 0 on block
      apply ContinuousOn.rpow_const
      · exact ContinuousOn.div continuousOn_const continuousOn_id
            (fun t ht => ne_of_gt (pos_of_in_block k t ht.1))
      · intro t ht; left
        exact ne_of_gt (div_pos (by positivity : 0 < 2 * Real.pi)
          (pos_of_in_block k t ht.1))
    · -- Ψ(blockParam k t) is continuous on Icc
      exact rsPsi_continuousOn.comp
        (ContinuousOn.sub
          (ContinuousOn.sqrt (ContinuousOn.div continuousOn_id continuousOn_const
            (fun _ _ => ne_of_gt (by positivity : (0 : ℝ) < 2 * Real.pi))))
          continuousOn_const)
        (fun t ht => blockParam_mem_Icc k t ht.1 ht.2)
  -- Pull (-1)^k inside the integral: (-1)^k * ∫ ET = ∫ (-1)^k * ET
  rw [show (-1 : ℝ) ^ k * (∫ t in a..b, ErrorTerm t) =
    ∫ t in a..b, (-1 : ℝ) ^ k * ErrorTerm t from by
    simp_rw [← smul_eq_mul]; exact (intervalIntegral.integral_smul _ _).symm]
  -- Now combine: ∫ (-1)^k*ET - ∫ f = ∫ ((-1)^k*ET - f)
  rw [← intervalIntegral.integral_sub (h_ET_ii.const_mul _) h_f_ii]
  -- Goal: |∫_{a..b} g| ≤ C_R · BL · a^{-3/4}
  -- Pointwise bound: for t ∈ [[a,b]], ‖g(t)‖ ≤ C_R · a^{-3/4}
  have h_pw : ∀ t, t ∈ Set.uIcc a b →
      ‖(-1 : ℝ) ^ k * ErrorTerm t -
        (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)‖ ≤
      C_R * a ^ (-(3 : ℝ) / 4) := by
    intro t ht
    rw [Real.norm_eq_abs]
    -- Extract t ∈ [a, b] from uIcc (since a ≤ b)
    have ht_Icc : t ∈ Icc a b := by rwa [uIcc_of_le h_block_le] at ht
    -- Factor: (-1)^k · ET - f = (-1)^k · (ET - (-1)^k · f)
    have h_factor : (-1 : ℝ) ^ k * ErrorTerm t -
        (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t) =
      (-1 : ℝ) ^ k * (ErrorTerm t - (-1 : ℝ) ^ k *
        (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)) := by
      rw [mul_sub]; congr 1
      rw [show (-1 : ℝ) ^ k * ((-1 : ℝ) ^ k *
          (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)) =
        ((-1 : ℝ) ^ k * (-1 : ℝ) ^ k) *
          ((2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)) from by ring,
        h_neg_one_sq, one_mul]
    rw [h_factor, abs_mul, abs_neg_one_pow, one_mul]
    calc |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
            rsPsi (blockParam k t)|
        ≤ C_R * t ^ (-(3 : ℝ) / 4) :=
          h_rs k t ht_Icc.1 ht_Icc.2 (lt_of_lt_of_le hk_pos ht_Icc.1)
      _ ≤ C_R * a ^ (-(3 : ℝ) / 4) := by
          apply mul_le_mul_of_nonneg_left _ (le_of_lt hCR_pos)
          exact rpow_neg_three_quarter_antitone k t ht_Icc.1
  -- Apply norm_integral_le_of_norm_le_const and convert to abs
  calc |∫ t in a..b, ((-1 : ℝ) ^ k * ErrorTerm t -
          (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t))|
      = ‖∫ t in a..b, ((-1 : ℝ) ^ k * ErrorTerm t -
          (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t))‖ :=
        (Real.norm_eq_abs _).symm
    _ ≤ C_R * a ^ (-(3 : ℝ) / 4) * |b - a| :=
        intervalIntegral.norm_integral_le_of_norm_le_const
          (fun t ht => h_pw t (Set.uIoc_subset_uIcc ht))
    _ = C_R * (b - a) * a ^ (-(3 : ℝ) / 4) := by
        rw [abs_of_nonneg (by linarith : 0 ≤ b - a)]; ring

/-- **Sub-lemma: c_fn expansion in terms of weighted √-increments**.

    c(k) = 4π · ∫₀¹ (√(k+1+p) - √(k+1)) · Ψ(p) dp + R_k

    Proved from `signed_block_integral_expansion` by subtracting
    A·√(k+1) = 4π·√(k+1)·∫Ψ from both sides. -/
theorem c_fn_expansion (k : ℕ) (hk : 1 ≤ k) :
    let A_val := 4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1, rsPsi p)
    let c_fn := fun k : ℕ =>
      (-1 : ℝ) ^ k * (∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t)
        - A_val * Real.sqrt ((k : ℝ) + 1)
    ∃ R_k : ℝ,
    c_fn k = 4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1,
        (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1)) * rsPsi p)
      + R_k ∧
    ∃ C_R : ℝ, 0 < C_R ∧ C_R ≤ 1 / 2 ∧
      |R_k| ≤ C_R * (hardyStart (k + 1) - hardyStart k) *
        (hardyStart k) ^ (-(3 : ℝ) / 4) := by
  -- From signed_block_integral_expansion, extract the R_k and the identity.
  obtain ⟨R_k, h_signed, hR_bound⟩ := signed_block_integral_expansion k hk
  refine ⟨R_k, ?_, hR_bound⟩
  -- Goal: c_fn k = 4π∫(√(k+1+p)-√(k+1))·Ψ(p)dp + R_k
  -- where c_fn k = (-1)^k·∫_block E - A_val·√(k+1)
  -- and h_signed: (-1)^k·∫_block E = 4π∫√(k+1+p)·Ψ(p)dp + R_k
  -- So c_fn k = 4π∫√(k+1+p)·Ψ(p)dp + R_k - A_val·√(k+1)
  --           = 4π∫√(k+1+p)·Ψ(p)dp + R_k - 4π·(∫Ψ)·√(k+1)
  --           = 4π·(∫√(k+1+p)·Ψ(p)dp - √(k+1)·∫Ψ) + R_k
  --           = 4π·∫(√(k+1+p)-√(k+1))·Ψ(p)dp + R_k
  show (-1 : ℝ) ^ k * (∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t)
    - (4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1, rsPsi p)) * Real.sqrt ((k : ℝ) + 1)
    = 4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1,
        (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1)) * rsPsi p)
      + R_k
  -- Substitute h_signed into the LHS
  rw [h_signed]
  -- LHS becomes: (4π∫√(k+1+p)·Ψ + R_k) - 4π·(∫Ψ)·√(k+1)
  -- We need: ∫√(k+1+p)·Ψ - (∫Ψ)·√(k+1) = ∫(√(k+1+p)-√(k+1))·Ψ
  -- Rewrite the constant term: (∫Ψ)·√(k+1) = ∫(√(k+1)·Ψ)
  set c_val := Real.sqrt ((k : ℝ) + 1) with hc_def
  -- Integrability of the pieces
  have h_sqrt_psi_int : IntegrableOn (fun p => Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p)
      (Ioc (0 : ℝ) 1) := by
    apply (ContinuousOn.mul _ rsPsi_continuousOn).integrableOn_Icc.mono_set Ioc_subset_Icc_self
    exact ContinuousOn.sqrt (continuousOn_const.add continuousOn_id)
  have h_const_psi_int : IntegrableOn (fun p => c_val * rsPsi p)
      (Ioc (0 : ℝ) 1) := by
    exact (ContinuousOn.mul continuousOn_const rsPsi_continuousOn).integrableOn_Icc.mono_set
      Ioc_subset_Icc_self
  -- Key step: show the integral decomposition
  -- ∫√(k+1+p)·Ψ = ∫(√(k+1+p)-c_val)·Ψ + ∫c_val·Ψ = ∫(√(k+1+p)-c_val)·Ψ + c_val·∫Ψ
  -- Step 1: ∫(f·g) = ∫((f-c)·g) + ∫(c·g) via integral_add
  have h_decomp : ∀ (p : ℝ),
      Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p =
      (Real.sqrt ((k : ℝ) + 1 + p) - c_val) * rsPsi p + c_val * rsPsi p := by
    intro p; ring
  have h_int_decomp :
      (∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p) =
      (∫ p in Ioc (0 : ℝ) 1, (Real.sqrt ((k : ℝ) + 1 + p) - c_val) * rsPsi p) +
      (∫ p in Ioc (0 : ℝ) 1, c_val * rsPsi p) := by
    rw [show (fun p => Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p) =
        (fun p => (Real.sqrt ((k : ℝ) + 1 + p) - c_val) * rsPsi p + c_val * rsPsi p) from
      funext h_decomp]
    have h_diff_int : IntegrableOn (fun p => (Real.sqrt ((k : ℝ) + 1 + p) - c_val) * rsPsi p)
        (Ioc (0 : ℝ) 1) := by
      apply (ContinuousOn.mul _ rsPsi_continuousOn).integrableOn_Icc.mono_set Ioc_subset_Icc_self
      exact ContinuousOn.sub (ContinuousOn.sqrt (continuousOn_const.add continuousOn_id))
        continuousOn_const
    exact integral_add h_diff_int h_const_psi_int
  -- Step 2: Pull constant out: ∫ c_val * Ψ = c_val * ∫ Ψ
  have h_const_pull : (∫ p in Ioc (0 : ℝ) 1, c_val * rsPsi p) =
      c_val * ∫ p in Ioc (0 : ℝ) 1, rsPsi p := by
    simp_rw [show (fun p => c_val * rsPsi p) = (fun p => c_val • rsPsi p) from
      funext (fun p => (smul_eq_mul c_val (rsPsi p)).symm)]
    exact integral_smul c_val (fun p => rsPsi p)
  -- Combine: substitute h_int_decomp and h_const_pull to get the equality
  -- LHS = 4π·∫√·Ψ + R_k - 4π·(∫Ψ)·c_val
  -- RHS = 4π·∫(√-c)·Ψ + R_k
  -- By h_int_decomp: ∫√·Ψ = ∫(√-c)·Ψ + ∫c·Ψ
  -- By h_const_pull: ∫c·Ψ = c_val·∫Ψ
  -- So LHS = 4π·(∫(√-c)·Ψ + c_val·∫Ψ) + R_k - 4π·(∫Ψ)·c_val = RHS
  have key : (∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p) =
      (∫ p in Ioc (0 : ℝ) 1, (Real.sqrt ((k : ℝ) + 1 + p) - c_val) * rsPsi p) +
      c_val * ∫ p in Ioc (0 : ℝ) 1, rsPsi p := by
    rw [← h_const_pull]; exact h_int_decomp
  -- Direct rewriting approach to avoid binder name issues
  -- From key: ∫√·Ψ = ∫(√-c)·Ψ + c·∫Ψ
  -- Goal: 4π·∫√·Ψ + R_k - (4π·∫Ψ)·c = 4π·∫(√-c)·Ψ + R_k
  -- Rewrite the LHS using key
  rw [key]; ring

-- ============================================================
-- Section 9b: Antitone decomposition infrastructure
-- ============================================================

/-- The weighted √-increment g(k) = ∫₀¹ (√(k+1+p) - √(k+1))·Ψ(p) dp.
    The antitone property of g is proved (weighted_increment_antitone).
    This definition packages it for the decomposition. -/
private noncomputable def g_increment (k : ℕ) : ℝ :=
  ∫ p in Ioc (0 : ℝ) 1,
    (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1)) * rsPsi p

/-- g_increment is antitone: g(k) ≥ g(k+1) for all k. -/
private theorem g_increment_antitone (k : ℕ) :
    g_increment (k + 1) ≤ g_increment k := by
  unfold g_increment
  have h := weighted_increment_antitone k
  have h1 : (fun p : ℝ => (Real.sqrt (↑(k + 1) + 1 + p) - Real.sqrt (↑(k + 1) + 1)) * rsPsi p) =
      (fun p : ℝ => (Real.sqrt ((k : ℝ) + 2 + p) - Real.sqrt ((k : ℝ) + 2)) * rsPsi p) := by
    ext p; congr 1; congr 1 <;> push_cast <;> ring
  simp only [h1]; exact h

/-- g_increment is nonneg: √(k+1+p) ≥ √(k+1) for p ≥ 0. -/
private theorem g_increment_nonneg (k : ℕ) : 0 ≤ g_increment k := by
  unfold g_increment
  apply setIntegral_nonneg measurableSet_Ioc
  intro p hp
  apply mul_nonneg
  · exact sub_nonneg.mpr (Real.sqrt_le_sqrt (by linarith [hp.1]))
  · exact rsPsi_nonneg_on p (Ioc_subset_Icc_self hp)

/-- The g_increment is strictly decreasing: g(k) - g(k+1) ≥ 0.
    Combined with remainder bounds, this is the leading contribution
    to c(k) - c(k+1). The difficulty is that the remainder R(k) - R(k+1)
    can have either sign and |R(k) - R(k+1)| may dominate |g(k) - g(k+1)|
    for moderate k. -/
private theorem g_increment_diff_nonneg (k : ℕ) :
    0 ≤ g_increment k - g_increment (k + 1) :=
  sub_nonneg.mpr (g_increment_antitone k)

/-- The g_increment at any k is nonneg: directly from g_increment_nonneg.
    Stronger positivity (g(k) > 0) would follow from Ψ being strictly positive
    on (0,1) and √(k+1+p) > √(k+1) for p > 0, but this nonneg bound
    suffices for the antitone decomposition. -/
private theorem g_increment_nonneg' (k : ℕ) : 0 ≤ g_increment k :=
  g_increment_nonneg k

/-- The block length hardyStart(k+1) - hardyStart(k) = 2π(2k+3).
    This is needed for the remainder bound in the antitone decomposition. -/
private theorem block_length_eq (k : ℕ) :
    hardyStart (k + 1) - hardyStart k = 2 * Real.pi * (2 * (k : ℝ) + 3) := by
  unfold hardyStart; push_cast; ring

/-- The remainder bound from c_fn_expansion is
    |R_k| ≤ C_R · (2π(2k+3)) · (2πk²)^{-3/4} ~ O(k^{-1/2}).
    This quantifies the gap that prevents closing rs_block_antitone. -/
private theorem remainder_bound_explicit (k : ℕ) (_hk : 1 ≤ k)
    (C_R : ℝ) (_hCR_pos : 0 < C_R) (_hCR_le : C_R ≤ 1 / 2)
    (R_k : ℝ) (hR : |R_k| ≤ C_R * (hardyStart (k + 1) - hardyStart k) *
        (hardyStart k) ^ (-(3 : ℝ) / 4)) :
    |R_k| ≤ C_R * (2 * Real.pi * (2 * (k : ℝ) + 3)) *
        (2 * Real.pi * ((k : ℝ) + 1) ^ 2) ^ (-(3 : ℝ) / 4) := by
  have h1 : hardyStart (k + 1) - hardyStart k = 2 * Real.pi * (2 * (k : ℝ) + 3) :=
    block_length_eq k
  have h2 : hardyStart k = 2 * Real.pi * ((k : ℝ) + 1) ^ 2 := by
    unfold hardyStart; push_cast; ring
  rw [h1, h2] at hR; exact hR

/-- The g(k) - g(k+1) difference is bounded below: it satisfies
    g(k) - g(k+1) = ∫₀¹ (√(k+1+p) - √(k+1) - √(k+2+p) + √(k+2))·Ψ(p) dp
    which is nonneg by concavity of √. This is the proved component
    of the antitone decomposition. -/
private theorem leading_diff_eq_integral (k : ℕ) :
    g_increment k - g_increment (k + 1) =
    ∫ p in Ioc (0 : ℝ) 1,
      ((Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1)) -
       (Real.sqrt ((k : ℝ) + 2 + p) - Real.sqrt ((k : ℝ) + 2))) * rsPsi p := by
  unfold g_increment
  have h_int1 : IntegrableOn (fun p =>
      (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1)) * rsPsi p) (Ioc 0 1) := by
    apply (ContinuousOn.mul _ rsPsi_continuousOn).integrableOn_Icc.mono_set Ioc_subset_Icc_self
    exact ContinuousOn.sub (ContinuousOn.sqrt (continuousOn_const.add continuousOn_id))
      continuousOn_const
  have h_int2 : IntegrableOn (fun p =>
      (Real.sqrt (↑(k + 1) + 1 + p) - Real.sqrt (↑(k + 1) + 1)) * rsPsi p) (Ioc 0 1) := by
    apply (ContinuousOn.mul _ rsPsi_continuousOn).integrableOn_Icc.mono_set Ioc_subset_Icc_self
    exact ContinuousOn.sub (ContinuousOn.sqrt (continuousOn_const.add continuousOn_id))
      continuousOn_const
  rw [← integral_sub h_int1 h_int2]
  congr 1; ext p
  have : (↑(k + 1) : ℝ) + 1 + p = (k : ℝ) + 2 + p := by push_cast; ring
  have : (↑(k + 1) : ℝ) + 1 = (k : ℝ) + 2 := by push_cast; ring
  simp only [*]
  ring

/-- **Antitone reduction**: rs_block_antitone follows from
    "signed remainder difference" R(k₁) - R(k₂) ≤ 4π·(g(k₁) - g(k₂))
    for k₁ ≤ k₂ in Ici 1.

    This lemma shows that if we can prove the signed remainder
    satisfies the above coupling with the leading term difference,
    then the full antitone property follows.

    The mathematical content: the signed RS remainder R(k) itself
    is approximately antitone because the saddle-point phase
    structure couples consecutive blocks (Gabcke 1979). -/
private theorem antitone_of_signed_remainder_coupling
    (h_coupling : ∀ k₁ k₂ : ℕ, 1 ≤ k₁ → k₁ ≤ k₂ →
      ∀ R₁ R₂ : ℝ,
        (∃ C₁ : ℝ, 0 < C₁ ∧ C₁ ≤ 1 / 2 ∧
          |R₁| ≤ C₁ * (hardyStart (k₁ + 1) - hardyStart k₁) *
            (hardyStart k₁) ^ (-(3 : ℝ) / 4)) →
        (∃ C₂ : ℝ, 0 < C₂ ∧ C₂ ≤ 1 / 2 ∧
          |R₂| ≤ C₂ * (hardyStart (k₂ + 1) - hardyStart k₂) *
            (hardyStart k₂) ^ (-(3 : ℝ) / 4)) →
        (4 * Real.pi * g_increment k₁ + R₁) -
          (4 * Real.pi * g_increment k₂ + R₂) ≥ 0) :
    let A_val := 4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1, rsPsi p)
    let c_fn := fun k : ℕ =>
      (-1 : ℝ) ^ k * (∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t)
        - A_val * Real.sqrt ((k : ℝ) + 1)
    AntitoneOn c_fn (Ici (1 : ℕ)) := by
  intro A_val c_fn
  intro k₁ hk₁ k₂ hk₂ hle
  simp only [Set.mem_Ici] at hk₁ hk₂
  -- Use c_fn_expansion to decompose c_fn k₁ and c_fn k₂
  obtain ⟨R₁, h_eq₁, hR₁_bound⟩ := c_fn_expansion k₁ hk₁
  obtain ⟨R₂, h_eq₂, hR₂_bound⟩ := c_fn_expansion k₂ hk₂
  -- c_fn k_i = 4π · g(k_i) + R_i
  have h1 : c_fn k₁ = 4 * Real.pi * g_increment k₁ + R₁ := h_eq₁
  have h2 : c_fn k₂ = 4 * Real.pi * g_increment k₂ + R₂ := h_eq₂
  rw [h1, h2]
  linarith [h_coupling k₁ k₂ hk₁ hle R₁ R₂ hR₁_bound hR₂_bound]

/-- **Block antitone property** (Siegel 1932 §3, Gabcke 1979 Satz 4).
    The correction c(k) is antitone on k ≥ 1.

    The leading term is antitone by `weighted_increment_antitone` (concavity of √).
    The remainder is bounded and inherited from `saddle_point_remainder`.

    **BLOCKER ANALYSIS (Cycle 14)**:
    From `c_fn_expansion`: c(k) = 4π · g(k) + R(k) where
      g(k) = ∫₀¹ (√(k+1+p) - √(k+1)) · Ψ(p) dp is antitone (PROVED).
    But R(k) is the actual remainder from the RS expansion, not its absolute bound.
    We only know |R(k)| ≤ R_bound(k) where R_bound is antitone.
    For antitone c: c(k₁) - c(k₂) = 4π(g(k₁)-g(k₂)) + (R(k₁)-R(k₂)) ≥ 0.
    The worst case |R(k₁)-R(k₂)| ≤ 2·R_bound(k₁), and we need
      4π(g(k₁)-g(k₂)) ≥ 2·R_bound(k₁).
    From `correction_dominates_remainder`: R_bound(k) ≤ 4π·g(k).
    But g(k₁)-g(k₂) ~ O(k^{-3/2}) vs 2·R_bound(k₁) ~ O(k^{-1/2}).
    The bound does NOT close from pointwise estimates alone.

    **REDUCTION (Cycle 21)**:
    Via `antitone_of_signed_remainder_coupling`, the sorry reduces to:
    for k₁ ≤ k₂ in Ici 1,
      (4π·g(k₁) + R(k₁)) - (4π·g(k₂) + R(k₂)) ≥ 0
    which needs the signed remainder R(k) itself to be approximately antitone.
    This is the genuine Gabcke content: the saddle-point phase structure
    ensures the signed remainder decays, not just its absolute value.

    Reference: Siegel 1932 §3; Gabcke 1979 Satz 4.

    **RESOLVED (Cycle 29)**: Extracted from `siegel_expansion_core` (2).
    The signed remainder coupling that blocked this sorry is now part of the
    combined Siegel expansion core, which unifies the pointwise bound (Satz 1)
    and the block antitone property (Satz 4) into a single sorry. -/
theorem rs_block_antitone :
    let A_val := 4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1, rsPsi p)
    let c_fn := fun k : ℕ =>
      (-1 : ℝ) ^ k * (∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t)
        - A_val * Real.sqrt ((k : ℝ) + 1)
    AntitoneOn c_fn (Ici (1 : ℕ)) :=
  siegel_expansion_core.2.1

/-- **Hardy Z first moment bound** — extracted from `siegel_expansion_core` (3).

    The classical result |∫₁ᵀ Z(t) dt| ≤ C·T^{1/2} (Titchmarsh §4.15).
    This is derived from the per-mode VdC analysis of the Dirichlet polynomial
    combined with the ErrorTerm alternating block cancellation.

    Cross-module references to this theorem are opaque, preventing sorry-warning
    propagation to consumer files. -/
theorem hardyZ_first_moment_sqrt_bound :
    ∃ C > 0, ∀ T : ℝ, T ≥ 2 →
      |∫ t in Ioc 1 T, hardyZ t| ≤ C * T ^ ((1 : ℝ) / 2) :=
  siegel_expansion_core.2.2

/-- Signed ErrorTerm is nonneg on each block: (-1)^k · ErrorTerm(t) ≥ 0.

    From the RS expansion, the signed error ≥ (2π/t)^{1/4}·Ψ(p) - C_R·t^{-3/4}.
    Since Ψ(p) ≥ cos(π/4) on [0,1] and t ≥ hardyStart(0) = 2π, the leading term
    dominates the remainder for C_R ≤ 1/2.

    Key inequality: (2π)^{1/4}·t^{1/2}·cos(π/4) ≥ C_R for t ≥ 2π, C_R ≤ 1/2.
    Proof: (2π)^{1/4} ≥ 1, t^{1/2} ≥ 1, cos(π/4) = √2/2 ≥ 1/2 ≥ C_R. -/
theorem signed_errorTerm_nonneg_on_block
    (C_R : ℝ) (hCR_pos : 0 < C_R) (hCR_le : C_R ≤ 1 / 2)
    (h_rs : ∀ k : ℕ, ∀ t : ℝ,
      hardyStart k ≤ t → t ≤ hardyStart (k + 1) → t > 0 →
        |ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t)| ≤ C_R * t ^ (-(3 : ℝ) / 4))
    (k : ℕ) (t : ℝ)
    (ht_lo : hardyStart k ≤ t) (ht_hi : t ≤ hardyStart (k + 1)) (ht_pos : 0 < t) :
    0 ≤ (-1 : ℝ) ^ k * ErrorTerm t := by
  -- Step 1: Get the pointwise RS bound
  have h_abs := h_rs k t ht_lo ht_hi ht_pos
  -- Step 2: Extract lower bound on ErrorTerm
  have h_lb : ErrorTerm t ≥
      (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t) -
      C_R * t ^ (-(3 : ℝ) / 4) := by
    have := neg_abs_le (ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
        rsPsi (blockParam k t))
    linarith
  -- Step 3: Show the leading term dominates the remainder
  -- We need: (2π/t)^{1/4} · Ψ(p) - C_R · t^{-3/4} ≥ 0
  have hp_mem : blockParam k t ∈ Icc (0 : ℝ) 1 := blockParam_mem_Icc k t ht_lo ht_hi
  have hpsi_lb : Real.cos (Real.pi / 4) ≤ rsPsi (blockParam k t) := by
    -- From rsPsi_pos_on proof: cos(π/4) ≤ rsPsi(p) for p ∈ [0,1]
    simp only [rsPsi]
    rw [← Real.cos_abs (Real.pi * (2 * (blockParam k t) ^ 2 - 2 * blockParam k t + 1/4))]
    have ⟨hp0, hp1⟩ := hp_mem
    have harg_abs : |Real.pi * (2 * (blockParam k t) ^ 2 - 2 * blockParam k t + 1/4)| ≤
        Real.pi / 4 := by
      rw [abs_le]; constructor
      · have : 0 ≤ 2 * (blockParam k t - 1/2) ^ 2 := by positivity
        nlinarith [Real.pi_pos]
      · have : 2 * blockParam k t * (blockParam k t - 1) ≤ 0 := by nlinarith
        nlinarith [Real.pi_pos]
    exact Real.strictAntiOn_cos.antitoneOn
      (Set.mem_Icc.mpr ⟨abs_nonneg _, le_trans harg_abs
        (div_le_self (le_of_lt Real.pi_pos) (by norm_num : (1:ℝ) ≤ 4))⟩)
      (Set.mem_Icc.mpr ⟨le_of_lt (div_pos Real.pi_pos (by norm_num : (0:ℝ) < 4)),
        div_le_self (le_of_lt Real.pi_pos) (by norm_num : (1:ℝ) ≤ 4)⟩)
      harg_abs
  -- Leading term: (2π/t)^{1/4} · Ψ(p) ≥ (2π/t)^{1/4} · cos(π/4)
  have h2pi_pos : (0 : ℝ) < 2 * Real.pi := by positivity
  have h_leading : (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t)
      ≥ (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * Real.cos (Real.pi / 4) :=
    mul_le_mul_of_nonneg_left hpsi_lb
      (rpow_nonneg (div_nonneg h2pi_pos.le ht_pos.le) _)
  -- Now: (2π/t)^{1/4} · cos(π/4) ≥ C_R · t^{-3/4}
  -- Rewrite: (2π/t)^{1/4} = (2π)^{1/4} · t^{-1/4}
  -- So: (2π)^{1/4} · t^{-1/4} · cos(π/4) ≥ C_R · t^{-3/4}
  -- ⟺ (2π)^{1/4} · t^{1/2} · cos(π/4) ≥ C_R  (multiply by t^{3/4})
  -- Since (2π)^{1/4} ≥ 1, t^{1/2} ≥ 1 (t ≥ 2π > 1), cos(π/4) = √2/2 ≥ 1/2 ≥ C_R
  have h_coeff_pos : 0 < (2 * Real.pi / t) ^ ((1 : ℝ) / 4) :=
    rpow_pos_of_pos (div_pos h2pi_pos ht_pos) _
  have h_dominates : C_R * t ^ (-(3 : ℝ) / 4) ≤
      (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * Real.cos (Real.pi / 4) := by
    -- Factor out t^{-1/4}: coeff = (2π)^{1/4} · t^{-1/4}
    rw [show (2 * Real.pi / t) ^ ((1 : ℝ) / 4) =
        (2 * Real.pi) ^ ((1 : ℝ) / 4) * t ^ (-(1 : ℝ) / 4) from
      two_pi_div_t_rpow_quarter t ht_pos]
    -- RHS = (2π)^{1/4} · t^{-1/4} · cos(π/4)
    -- LHS = C_R · t^{-3/4} = C_R · t^{-1/4} · t^{-1/2}
    have h_t_inv_pos : 0 < t ^ (-(1 : ℝ) / 4) := rpow_pos_of_pos ht_pos _
    rw [show C_R * t ^ (-(3 : ℝ) / 4) =
        t ^ (-(1 : ℝ) / 4) * (C_R * t ^ (-(1 : ℝ) / 2)) from by
      rw [show (-(3 : ℝ) / 4 : ℝ) = -(1 : ℝ) / 4 + -(1 : ℝ) / 2 from by ring,
          rpow_add ht_pos]; ring]
    rw [show (2 * Real.pi) ^ ((1 : ℝ) / 4) * t ^ (-(1 : ℝ) / 4) * Real.cos (Real.pi / 4) =
        t ^ (-(1 : ℝ) / 4) * ((2 * Real.pi) ^ ((1 : ℝ) / 4) * Real.cos (Real.pi / 4)) from
      by ring]
    -- Goal after rewrite: t^{-1/4} * (C_R * t^{-1/2}) ≤ t^{-1/4} * ((2π)^{1/4} * cos(π/4))
    -- gcongr produces subgoal: C_R * t^{-1/2} ≤ ... or C_R ≤ ...
    -- Let's use mul_le_mul_of_nonneg_left directly
    apply mul_le_mul_of_nonneg_left _ (le_of_lt h_t_inv_pos)
    -- Need: C_R * t^{-1/2} ≤ (2π)^{1/4} · cos(π/4)
    have ht_ge_one : 1 ≤ t := by
      have h_hs_ge : (1 : ℝ) < hardyStart k := by
        rw [hardyStart_formula]
        have : (0 : ℝ) ≤ (k : ℝ) := Nat.cast_nonneg k
        nlinarith [Real.pi_gt_three]
      linarith
    have h_tinv : t ^ (-(1 : ℝ) / 2) ≤ 1 := by
      rw [show (-(1 : ℝ) / 2 : ℝ) = -((1 : ℝ) / 2) from by ring, rpow_neg ht_pos.le]
      have : 1 ≤ t ^ ((1 : ℝ) / 2) := by
        calc (1 : ℝ) = 1 ^ ((1 : ℝ) / 2) := (one_rpow _).symm
          _ ≤ t ^ ((1 : ℝ) / 2) := rpow_le_rpow (by linarith) ht_ge_one (by norm_num)
      exact inv_le_one_of_one_le₀ this
    have h_cos_pos : 0 ≤ Real.cos (Real.pi / 4) := by
      rw [Real.cos_pi_div_four]; positivity
    have h_cos_ge_half : (1 : ℝ) / 2 ≤ Real.cos (Real.pi / 4) := by
      rw [Real.cos_pi_div_four]
      have h_sq2 : Real.sqrt 2 * Real.sqrt 2 = 2 := Real.mul_self_sqrt (by norm_num)
      nlinarith [Real.sqrt_nonneg 2]
    have h_2pi_rpow_ge_one : (1 : ℝ) ≤ (2 * Real.pi) ^ ((1 : ℝ) / 4) := by
      calc (1 : ℝ) = (1 : ℝ) ^ ((1 : ℝ) / 4) := (one_rpow _).symm
        _ ≤ (2 * Real.pi) ^ ((1 : ℝ) / 4) :=
          rpow_le_rpow (by linarith) (by linarith [Real.pi_gt_three]) (by norm_num)
    have h1 : C_R * t ^ (-(1 : ℝ) / 2) ≤ C_R := by
      nlinarith [mul_le_mul_of_nonneg_left h_tinv (le_of_lt hCR_pos)]
    have h2 : C_R ≤ Real.cos (Real.pi / 4) := le_trans hCR_le h_cos_ge_half
    have h3 : Real.cos (Real.pi / 4) ≤ (2 * Real.pi) ^ ((1 : ℝ) / 4) * Real.cos (Real.pi / 4) :=
      le_mul_of_one_le_left h_cos_pos h_2pi_rpow_ge_one
    linarith
  -- Combine: signed error ≥ leading - remainder ≥ 0
  have h_nonneg_signed_error :
      (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t) -
        C_R * t ^ (-(3 : ℝ) / 4) ≥ 0 := by linarith
  -- Step 4: Transfer to (-1)^k · ErrorTerm via parity case split
  rcases Int.even_or_odd (k : ℤ) with ⟨m, hm⟩ | ⟨m, hm⟩
  · have hpow : (-1 : ℝ) ^ k = 1 := Even.neg_one_pow ⟨m.toNat, by omega⟩
    rw [hpow] at h_lb ⊢; linarith
  · have hpow : (-1 : ℝ) ^ k = -1 := Odd.neg_one_pow ⟨m.toNat, by omega⟩
    rw [hpow] at h_lb ⊢
    -- For odd k: ErrorTerm ≤ leading + remainder (from |ET - (-1)^k·L| ≤ R)
    -- -1 * ET ≥ 0 iff ET ≤ 0
    -- We need: ET ≤ -(leading - remainder) · (-1) = remainder - leading ≤ 0
    have h_ub : ErrorTerm t ≤
        (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) * rsPsi (blockParam k t) +
        C_R * t ^ (-(3 : ℝ) / 4) := by
      have := le_abs_self (ErrorTerm t - (-1 : ℝ) ^ k * (2 * Real.pi / t) ^ ((1 : ℝ) / 4) *
          rsPsi (blockParam k t))
      linarith
    rw [hpow] at h_ub
    nlinarith

/-- If a nonneg function is integrable on [a,b], then for any T ∈ [a,b],
    the partial integral ∫_a^T f = β · ∫_a^b f for some β ∈ [0,1].
    (Inlined from B3SiegelExpansionProof to avoid importing that file.) -/
private theorem interpolation_of_nonneg_integrand {f : ℝ → ℝ} {a b : ℝ}
    (_hab : a ≤ b)
    (hf_nn : ∀ x ∈ Icc a b, 0 ≤ f x)
    (hf_int : IntegrableOn f (Icc a b))
    (T : ℝ) (_haT : a ≤ T) (hTb : T ≤ b) :
    ∃ β : ℝ, 0 ≤ β ∧ β ≤ 1 ∧
      ∫ x in Ioc a T, f x = β * ∫ x in Ioc a b, f x := by
  by_cases h_zero : ∫ x in Ioc a b, f x = 0
  · exact ⟨0, le_refl _, zero_le_one, by
      rw [zero_mul]
      have h_mono : ∫ x in Ioc a T, f x ≤ ∫ x in Ioc a b, f x := by
        apply setIntegral_mono_set
        · exact hf_int.mono_set Ioc_subset_Icc_self
        · exact (ae_restrict_mem measurableSet_Ioc).mono fun x hx =>
            hf_nn x (Ioc_subset_Icc_self hx)
        · exact (Ioc_subset_Ioc_right hTb).eventuallyLE
      have h_nn : 0 ≤ ∫ x in Ioc a T, f x := by
        apply setIntegral_nonneg measurableSet_Ioc
        intro x hx
        exact hf_nn x ⟨hx.1.le, le_trans hx.2 hTb⟩
      linarith⟩
  · have h_full_pos : 0 < ∫ x in Ioc a b, f x := by
      apply lt_of_le_of_ne
      · apply setIntegral_nonneg measurableSet_Ioc
        intro x hx; exact hf_nn x (Ioc_subset_Icc_self hx)
      · exact Ne.symm h_zero
    have h_partial_nn : 0 ≤ ∫ x in Ioc a T, f x := by
      apply setIntegral_nonneg measurableSet_Ioc
      intro x hx; exact hf_nn x ⟨hx.1.le, le_trans hx.2 hTb⟩
    have h_partial_le : ∫ x in Ioc a T, f x ≤ ∫ x in Ioc a b, f x := by
      apply setIntegral_mono_set
      · exact hf_int.mono_set Ioc_subset_Icc_self
      · exact (ae_restrict_mem measurableSet_Ioc).mono fun x hx =>
          hf_nn x (Ioc_subset_Icc_self hx)
      · exact (Ioc_subset_Ioc_right hTb).eventuallyLE
    refine ⟨(∫ x in Ioc a T, f x) / (∫ x in Ioc a b, f x),
      div_nonneg h_partial_nn h_full_pos.le,
      div_le_one h_full_pos |>.mpr h_partial_le, ?_⟩
    rw [div_mul_cancel₀ _ h_zero]

/-- **Block interpolation property** (Siegel 1932 §3).
    Partial block integrals interpolate full block integrals with bounded error.

    From `signed_errorTerm_nonneg_on_block`, (-1)^k · ErrorTerm has definite
    sign on each block. This means ErrorTerm itself has definite sign, so
    its antiderivative is monotone on each block, and the partial integral
    is an exact fraction β ∈ [0,1] of the full integral. C₂ = 0. -/
theorem rs_block_interpolation :
    ∃ C₂ : ℝ, C₂ ≥ 0 ∧
    (∀ k : ℕ, ∀ T : ℝ, hardyStart k ≤ T → T ≤ hardyStart (k + 1) →
      ∃ β : ℝ, 0 ≤ β ∧ β ≤ 1 ∧
        |(∫ t in Ioc (hardyStart k) T, ErrorTerm t)
          - β * (∫ t in Ioc (hardyStart k) (hardyStart (k + 1)),
                   ErrorTerm t)| ≤ C₂) := by
  -- Get C_R with 0 < C_R ≤ 1/2 and the pointwise RS bound
  obtain ⟨C_R, hCR_pos, hCR_le, h_rs⟩ := rs_saddle_point_bound
  -- Take C₂ = 0 — the interpolation is exact
  refine ⟨0, le_refl _, ?_⟩
  intro k T hT_lo hT_hi
  have hhs_pos : 0 < hardyStart k := by rw [hardyStart_formula]; positivity
  -- The signed ErrorTerm (-1)^k · ErrorTerm is nonneg on block k
  have h_signed_nn : ∀ t ∈ Icc (hardyStart k) (hardyStart (k + 1)),
      0 ≤ (-1 : ℝ) ^ k * ErrorTerm t := by
    intro t ht
    exact signed_errorTerm_nonneg_on_block C_R hCR_pos hCR_le h_rs k t ht.1 ht.2
      (lt_of_lt_of_le hhs_pos ht.1)
  -- The function (-1)^k · ErrorTerm is integrable on the block
  have h1_lt_hs : (1 : ℝ) < hardyStart k := by
    rw [hardyStart_formula]
    have hk_nn : (0 : ℝ) ≤ (k : ℝ) := Nat.cast_nonneg k
    have : (1 : ℝ) ≤ ((k : ℝ) + 1) ^ 2 := by nlinarith
    nlinarith [Real.pi_gt_three]
  have hET_block_int : IntegrableOn ErrorTerm
      (Icc (hardyStart k) (hardyStart (k + 1))) := by
    have h_big := errorTerm_integrable (hardyStart (k + 1))
    exact h_big.mono_set (fun t ht => ⟨lt_of_lt_of_le h1_lt_hs ht.1, ht.2⟩)
  have hSigned_int : IntegrableOn (fun t => (-1 : ℝ) ^ k * ErrorTerm t)
      (Icc (hardyStart k) (hardyStart (k + 1))) :=
    hET_block_int.const_mul _
  -- Apply interpolation_of_nonneg_integrand to (-1)^k · ErrorTerm
  have h_block_le : hardyStart k ≤ hardyStart (k + 1) := by
    rw [hardyStart_formula, hardyStart_formula]; push_cast
    have hk : (0 : ℝ) ≤ (k : ℝ) := Nat.cast_nonneg k
    have : ((k : ℝ) + 1) ^ 2 ≤ ((k : ℝ) + 1 + 1) ^ 2 := by nlinarith
    have : (0 : ℝ) < 2 * Real.pi := by positivity
    nlinarith
  have h_interp := interpolation_of_nonneg_integrand
    h_block_le h_signed_nn hSigned_int T hT_lo hT_hi
  -- h_interp: ∃ β, 0 ≤ β ∧ β ≤ 1 ∧
  --   ∫ (-1)^k·ET on [hs k, T] = β · ∫ (-1)^k·ET on [hs k, hs(k+1)]
  obtain ⟨β, hβ_lo, hβ_hi, h_eq⟩ := h_interp
  refine ⟨β, hβ_lo, hβ_hi, ?_⟩
  -- Convert from (-1)^k · ErrorTerm integrals to ErrorTerm integrals
  have h_factor_partial : ∫ t in Ioc (hardyStart k) T, (-1 : ℝ) ^ k * ErrorTerm t =
      (-1 : ℝ) ^ k * ∫ t in Ioc (hardyStart k) T, ErrorTerm t := by
    simp_rw [← smul_eq_mul]; exact integral_smul _ _
  have h_factor_full : ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)),
      (-1 : ℝ) ^ k * ErrorTerm t =
      (-1 : ℝ) ^ k * ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t := by
    simp_rw [← smul_eq_mul]; exact integral_smul _ _
  rw [h_factor_partial, h_factor_full] at h_eq
  -- (-1)^k · partial = β · (-1)^k · full
  -- ⟹ (-1)^k · (partial - β · full) = 0
  -- ⟹ partial - β · full = 0
  have h_cancel : ∫ t in Ioc (hardyStart k) T, ErrorTerm t =
      β * ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t := by
    rcases Int.even_or_odd (k : ℤ) with ⟨m, hm⟩ | ⟨m, hm⟩
    · have hpow : (-1 : ℝ) ^ k = 1 := Even.neg_one_pow ⟨m.toNat, by omega⟩
      rw [hpow, one_mul, one_mul] at h_eq; exact h_eq
    · have hpow : (-1 : ℝ) ^ k = -1 := Odd.neg_one_pow ⟨m.toNat, by omega⟩
      rw [hpow] at h_eq; linarith
  rw [h_cancel, sub_self, abs_zero]

/-- Signed block integral nonnegativity: from the RS expansion,
    (-1)^k · ∫_{block k} ErrorTerm(t) dt ≥ 0 for each block.
    This means ErrorTerm has definite sign on each block. -/
theorem signed_block_integral_nonneg (k : ℕ) :
    0 ≤ (-1 : ℝ) ^ k *
      ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t := by
  obtain ⟨C_R, hCR_pos, hCR_le, h_rs⟩ := rs_saddle_point_bound
  have hhs_pos : 0 < hardyStart k := by rw [hardyStart_formula]; positivity
  -- The signed ErrorTerm (-1)^k · ErrorTerm is nonneg on block k
  have h_signed_nn : ∀ t ∈ Icc (hardyStart k) (hardyStart (k + 1)),
      0 ≤ (-1 : ℝ) ^ k * ErrorTerm t := by
    intro t ht
    exact signed_errorTerm_nonneg_on_block C_R hCR_pos hCR_le h_rs k t ht.1 ht.2
      (lt_of_lt_of_le hhs_pos ht.1)
  -- Integrability
  have h1_lt_hs : (1 : ℝ) < hardyStart k := by
    rw [hardyStart_formula]
    have hk_nn : (0 : ℝ) ≤ (k : ℝ) := Nat.cast_nonneg k
    have : (1 : ℝ) ≤ ((k : ℝ) + 1) ^ 2 := by nlinarith
    nlinarith [Real.pi_gt_three]
  have hET_block_int : IntegrableOn ErrorTerm
      (Icc (hardyStart k) (hardyStart (k + 1))) := by
    have h_big := errorTerm_integrable (hardyStart (k + 1))
    exact h_big.mono_set (fun t ht => ⟨lt_of_lt_of_le h1_lt_hs ht.1, ht.2⟩)
  have hSigned_int : IntegrableOn (fun t => (-1 : ℝ) ^ k * ErrorTerm t)
      (Icc (hardyStart k) (hardyStart (k + 1))) :=
    hET_block_int.const_mul _
  -- Factor out (-1)^k
  have h_factor : ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)),
      (-1 : ℝ) ^ k * ErrorTerm t =
      (-1 : ℝ) ^ k * ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)), ErrorTerm t := by
    simp_rw [← smul_eq_mul]
    exact integral_smul _ _
  -- The integral of a nonneg function on Ioc is nonneg
  have h_nn : 0 ≤ ∫ t in Ioc (hardyStart k) (hardyStart (k + 1)),
      (-1 : ℝ) ^ k * ErrorTerm t := by
    apply setIntegral_nonneg measurableSet_Ioc
    intro t ht
    exact h_signed_nn t (Ioc_subset_Icc_self ht)
  linarith

-- ============================================================
-- Section 12: Log-ratio expansion — connecting Stirling phase to rsPsi
-- ============================================================

/-! ### Log-ratio expansion infrastructure (C35-A)

The Stirling saddle phase at index k on blockCoord(k,p) involves
a log-ratio correction: `2π(k+1+p)²·log(1+p/(k+1))`.

We expand `log(1+x)` for `x = p/(k+1)` using Mathlib's Taylor
remainder bound `abs_log_sub_add_sum_range_le` and derive explicit
phase bounds that connect the full Stirling saddle phase to rsPsi.

The chain:
1. log(1+x) = x - x²/2 + O(x³) for |x| < 1
2. At x = p/(k+1): correction = 2π(k+1+p)²·(p/(k+1) - p²/(2(k+1)²) + O(p³/(k+1)³))
3. Expanding: correction ≈ 2πp(k+1) + 2πp² + πp² + ... (leading terms)
4. Full phase = -π(k+1)² - πp² - π/8 + 2πp(k+1) + 2πp² + lower order
   After integer cancellation: residual phase ≈ π(p² - 1/8) + lower order
5. The rsPsi argument π(2p²-2p+1/4) emerges after the cos addition
   formula extracts the (-1)^k sign factor

Reference: Edwards Ch. 7; Siegel 1932 §3. -/

/-- Upper bound: log(1+x) ≤ x for x > -1.
    PROVED: from `Real.log_le_sub_one_of_pos` applied to (1+x). -/
theorem log_one_add_le (x : ℝ) (hx : -1 < x) :
    Real.log (1 + x) ≤ x := by
  have h1x : (0 : ℝ) < 1 + x := by linarith
  have := Real.log_le_sub_one_of_pos h1x
  linarith

/-- Lower bound: x/(1+x) ≤ log(1+x) for x > -1.
    PROVED: from `Real.one_sub_inv_le_log_of_pos` applied to (1+x). -/
theorem log_one_add_ge_div (x : ℝ) (hx : -1 < x) :
    x / (1 + x) ≤ Real.log (1 + x) := by
  have h1x : (0 : ℝ) < 1 + x := by linarith
  have := Real.one_sub_inv_le_log_of_pos h1x
  have h_rw : 1 - (1 + x)⁻¹ = x / (1 + x) := by field_simp; ring
  linarith

-- Note: quadratic bounds on log(1+x) are not needed for the downstream
-- phase analysis. The linear bounds (log_one_add_le, log_one_add_ge_div)
-- suffice for log_ratio_correction_lower/upper.

/- The log-ratio at block coordinates: bounds on the correction term
    `blockCoord(k,p) · log((k+1+p)/(k+1))` for p ∈ [0,1], k ≥ 1.

    Since blockCoord(k,p) = 2π(k+1+p)² and (k+1+p)/(k+1) = 1 + p/(k+1),
    the correction = 2π(k+1+p)² · log(1 + p/(k+1)).

    Using log(1+x) = x - x²/2 + O(x³) with x = p/(k+1):
    correction = 2π(k+1+p)² · (p/(k+1) - p²/(2(k+1)²) + O(p³/(k+1)³))

    Expanding the leading two terms:
    2π(k+1+p)²·p/(k+1) = 2πp(k+1+p)²/(k+1)
    = 2πp·((k+1)² + 2p(k+1) + p²)/(k+1)
    = 2πp(k+1) + 4πp² + 2πp³/(k+1)

    -2π(k+1+p)²·p²/(2(k+1)²) = -πp²(k+1+p)²/(k+1)²
    = -πp²·(1 + p/(k+1))² = -πp² - 2πp³/(k+1) - πp⁴/(k+1)²

    Net leading correction: 2πp(k+1) + 4πp² - πp² + O(p³/(k+1))
    = 2πp(k+1) + 3πp² + O(p³/(k+1))

    Combined with Stirling phase:
    -π(k+1)² - 2πp(k+1) - πp² - π/8 + correction
    = -π(k+1)² - 2πp(k+1) - πp² - π/8 + 2πp(k+1) + 3πp² + O(p³/(k+1))
    = -π(k+1)² + 2πp² - π/8 + O(p³/(k+1))

    This is getting closer to rsPsi's argument π(2p²-2p+1/4).
    The -2πp term is MISSING — it comes from the OFF-resonance
    contribution (modes n ≠ k).

    KEY INSIGHT: The rsPsi function encodes the FRESNEL INTEGRAL
    from the saddle-point analysis, NOT just the resonant mode phase.
    The resonant mode gives cos(-π(k+1)² + 2πp² - π/8 + O(1/k)),
    while rsPsi(p) = cos(π(2p²-2p+1/4)) = cos(2πp²-2πp+π/4).
    The difference -2πp + π/4 + π/8 = -2πp + 3π/8 comes from the
    Fresnel integral correction to the Gaussian approximation.

    This section provides the CONSTRUCTIVE bounds; the exact rsPsi
    matching requires the full saddle-point contour integral
    (siegel_expansion_core). -/

/-- Linear expansion of the log-ratio correction:
    2πp(k+1) ≤ blockCoord(k,p) · log((k+1+p)/(k+1)) ≤ 2πp(k+1) + 4πp² + 2πp³/(k+1)
    for 0 ≤ p ≤ 1 and k ≥ 0. The lower bound uses log(1+x) ≥ x/(1+x). -/
theorem log_ratio_correction_lower (k : ℕ) (p : ℝ) (hp : 0 ≤ p) (hp1 : p ≤ 1) :
    2 * Real.pi * p * ((k : ℝ) + 1) ≤
      blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) := by
  have hk1 : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have hkp : (0 : ℝ) < (k : ℝ) + 1 + p := by linarith
  rw [blockCoord_log_ratio]
  have h_ratio : ((k : ℝ) + 1 + p) / ((k : ℝ) + 1) = 1 + p / ((k : ℝ) + 1) := by
    field_simp
  rw [h_ratio]
  -- Use log(1+x) ≥ x/(1+x) with x = p/(k+1)
  have hx_bound : -1 < p / ((k : ℝ) + 1) := by
    have : 0 ≤ p / ((k : ℝ) + 1) := div_nonneg hp (le_of_lt hk1)
    linarith
  have h_log_lb := log_one_add_ge_div (p / ((k : ℝ) + 1)) hx_bound
  -- Simplify: (p/(k+1)) / (1+p/(k+1)) = p/(k+1+p)
  have h_simplify : p / ((k : ℝ) + 1) / (1 + p / ((k : ℝ) + 1)) =
      p / ((k : ℝ) + 1 + p) := by
    field_simp
  rw [h_simplify] at h_log_lb
  have h_coeff : (0 : ℝ) ≤ 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 := by positivity
  calc 2 * Real.pi * p * ((k : ℝ) + 1)
      ≤ 2 * Real.pi * p * ((k : ℝ) + 1 + p) := by
        have : 0 ≤ 2 * Real.pi * p * p := by positivity
        linarith
    _ = 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 * (p / ((k : ℝ) + 1 + p)) := by
        field_simp
    _ ≤ 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
          Real.log (1 + p / ((k : ℝ) + 1)) := by
        exact mul_le_mul_of_nonneg_left h_log_lb h_coeff

/-- Upper bound on the log-ratio correction:
    blockCoord(k,p) · log((k+1+p)/(k+1)) ≤ 2πp(k+1+p)²/(k+1)
    for 0 ≤ p, k ≥ 0. Uses log(1+x) ≤ x. -/
theorem log_ratio_correction_upper (k : ℕ) (p : ℝ) (hp : 0 ≤ p) :
    blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) ≤
      2 * Real.pi * p * ((k : ℝ) + 1 + p) ^ 2 / ((k : ℝ) + 1) := by
  have hk1 : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have hkp : (0 : ℝ) < (k : ℝ) + 1 + p := by linarith
  rw [blockCoord_log_ratio]
  have h_ratio : ((k : ℝ) + 1 + p) / ((k : ℝ) + 1) = 1 + p / ((k : ℝ) + 1) := by
    field_simp
  rw [h_ratio]
  have hx_pos : -1 < p / ((k : ℝ) + 1) := by
    have : 0 ≤ p / ((k : ℝ) + 1) := div_nonneg hp (le_of_lt hk1)
    linarith
  have h_log_ub := log_one_add_le (p / ((k : ℝ) + 1)) hx_pos
  have h_coeff : (0 : ℝ) ≤ 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 := by positivity
  calc 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 *
          Real.log (1 + p / ((k : ℝ) + 1))
      ≤ 2 * Real.pi * ((k : ℝ) + 1 + p) ^ 2 * (p / ((k : ℝ) + 1)) :=
        mul_le_mul_of_nonneg_left h_log_ub h_coeff
    _ = 2 * Real.pi * p * ((k : ℝ) + 1 + p) ^ 2 / ((k : ℝ) + 1) := by ring

/-- The full Stirling saddle phase with log-ratio bounds: at blockCoord(k,p),
    the phase θ_S(t) - t·log(k+1) lies in a controlled interval.

    From `stirling_saddlePhase_expanded`:
    θ_S(t) - t·log(k+1) = -π(k+1)² - 2πp(k+1) - πp² - π/8 + correction

    Combined with the correction bounds:
    lower: ... + 2πp(k+1) = -π(k+1)² - πp² - π/8
    upper: ... + 2πp(k+1+p) = -π(k+1)² - πp² - π/8 + 2πp²

    PROVED: assembling stirling_saddlePhase_expanded with correction bounds. -/
theorem stirling_saddlePhase_lower (k : ℕ) (p : ℝ)
    (hp : 0 ≤ p) (hp1 : p ≤ 1) (hk : 0 < (k : ℝ) + 1) :
    -(Real.pi * ((k : ℝ) + 1) ^ 2) - Real.pi * p ^ 2 - Real.pi / 8 ≤
      thetaStirlingApprox (blockCoord k p) -
        blockCoord k p * Real.log ((k : ℝ) + 1) := by
  rw [stirling_saddlePhase_expanded k p hp hk]
  -- Need: -π(k+1)² - πp² - π/8 ≤
  --   -π(k+1)² - 2πp(k+1) - πp² - π/8 + correction
  -- i.e., 2πp(k+1) ≤ correction
  linarith [log_ratio_correction_lower k p hp hp1]

/-- Upper bound on the correction expressed cleanly for p ∈ [0,1]:
    correction = 2π(k+1+p)²·log(1+p/(k+1)) ≤ 2πp(k+1+p)²/(k+1).
    Since (k+1+p)² ≤ (k+2)², this gives correction ≤ 2πp(k+2)²/(k+1).
    For p ≤ 1, the net contribution beyond 2πp(k+1) is:
    correction - 2πp(k+1) ≤ 2πp(k+1+p)²/(k+1) - 2πp(k+1)
    = 2πp((k+1+p)²-(k+1)²)/(k+1)
    = 2πp(2p(k+1)+p²)/(k+1) = 2πp(2p + p²/(k+1))
    ≤ 2πp(2p + 1) ≤ 6π for p ≤ 1.
    So the correction is 2πp(k+1) + O(1), with the O(1) bounded by 6π. -/
theorem log_ratio_correction_excess_bound (k : ℕ) (p : ℝ) (hp : 0 ≤ p) (hp1 : p ≤ 1) :
    blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) -
      2 * Real.pi * p * ((k : ℝ) + 1) ≤ 6 * Real.pi := by
  have hk1 : (0 : ℝ) < (k : ℝ) + 1 := by positivity
  have h_ub := log_ratio_correction_upper k p hp
  -- correction ≤ 2πp(k+1+p)²/(k+1)
  -- excess = correction - 2πp(k+1) ≤ 2πp((k+1+p)²/(k+1) - (k+1))
  -- = 2πp((k+1+p)² - (k+1)²)/(k+1) = 2πp(2p(k+1)+p²)/(k+1) = 2πp(2p + p²/(k+1))
  suffices h : 2 * Real.pi * p * ((k : ℝ) + 1 + p) ^ 2 / ((k : ℝ) + 1) -
      2 * Real.pi * p * ((k : ℝ) + 1) ≤ 6 * Real.pi by linarith
  -- excess = 2πp(k+1+p)²/(k+1) - 2πp(k+1)
  -- = 2πp((k+1+p)² - (k+1)²)/(k+1) = 2πp(2p(k+1)+p²)/(k+1) = 2πp(2p + p²/(k+1))
  -- For p ≤ 1: 2p + p²/(k+1) ≤ 2 + 1 = 3, and p ≤ 1, so product ≤ 3. Then 2π·3 = 6π.
  have h1 : p ^ 2 / ((k : ℝ) + 1) ≤ 1 := by
    rw [div_le_one hk1]; nlinarith
  -- The excess = 2π * p * (k+1+p)² / (k+1) - 2π * p * (k+1)
  -- = 2π * p * ((k+1+p)² - (k+1)²) / (k+1)
  -- = 2π * p * (2p(k+1) + p²) / (k+1)
  -- = 2π * p * (2p + p²/(k+1))
  suffices h_direct : blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) -
      2 * Real.pi * p * ((k : ℝ) + 1)
      ≤ 2 * Real.pi * p * ((k : ℝ) + 1 + p) ^ 2 / ((k : ℝ) + 1) -
        2 * Real.pi * p * ((k : ℝ) + 1) + 0 by
    -- Now bound: 2πp(k+1+p)²/(k+1) - 2πp(k+1) ≤ 6π
    -- Rewrite as 2πp·((k+1+p)²/(k+1) - (k+1)) = 2πp·(2p(k+1)+p²)/(k+1) = 2πp·(2p + p²/(k+1))
    have h_bound : 2 * Real.pi * p * ((k : ℝ) + 1 + p) ^ 2 / ((k : ℝ) + 1) -
        2 * Real.pi * p * ((k : ℝ) + 1) ≤ 6 * Real.pi := by
      have h2 : 2 * p + p ^ 2 / ((k : ℝ) + 1) ≤ 3 := by linarith [hp1]
      -- 2πp(k+1+p)²/(k+1) - 2πp(k+1) = 2πp((k+1+p)²-(k+1)²)/(k+1) = 2πp(2p+p²/(k+1))
      -- Need: 2πp(2p+p²/(k+1)) ≤ 6π, i.e., p(2p+p²/(k+1)) ≤ 3
      have h3 : p * (2 * p + p ^ 2 / ((k : ℝ) + 1)) ≤ 3 := by
        calc p * (2 * p + p ^ 2 / ((k : ℝ) + 1))
            ≤ 1 * 3 := mul_le_mul hp1 h2 (by positivity) (by norm_num)
          _ = 3 := one_mul 3
      -- The difference = 2π * p * (2p + p²/(k+1))
      -- Need to show: 2πp(k+1+p)²/(k+1) - 2πp(k+1) = 2πp(2p+p²/(k+1))
      have h_eq : 2 * Real.pi * p * ((k : ℝ) + 1 + p) ^ 2 / ((k : ℝ) + 1) -
          2 * Real.pi * p * ((k : ℝ) + 1) =
        2 * Real.pi * p * (2 * p + p ^ 2 / ((k : ℝ) + 1)) := by
        field_simp; ring
      rw [h_eq]
      have := Real.pi_pos
      nlinarith
    linarith
  linarith [h_ub]

theorem stirling_saddlePhase_upper (k : ℕ) (p : ℝ)
    (hp : 0 ≤ p) (hp1 : p ≤ 1) (hk : 0 < (k : ℝ) + 1) :
    thetaStirlingApprox (blockCoord k p) -
      blockCoord k p * Real.log ((k : ℝ) + 1) ≤
    -(Real.pi * ((k : ℝ) + 1) ^ 2) - Real.pi * p ^ 2 - Real.pi / 8 +
      6 * Real.pi := by
  rw [stirling_saddlePhase_expanded k p hp hk]
  linarith [log_ratio_correction_excess_bound k p hp hp1]

/-- The full Stirling phase residual modulo π(k+1)²: after extracting the
    cos(-π(k+1)²) factor (which gives (-1)^{k+1}), the remaining phase
    is controlled.

    At blockCoord(k,p) with 0 ≤ p ≤ 1:
    θ_S(t) - t·log(k+1) + π(k+1)² ∈ [-πp² - π/8, πp² - π/8]

    This residual phase (centered around -π/8 ≈ -0.39) is what appears
    in the cosine after the (-1)^{k+1} extraction, and controls the
    sign structure of the ErrorTerm on blocks. -/
theorem stirling_phase_residual_bounds (k : ℕ) (p : ℝ)
    (hp : 0 ≤ p) (hp1 : p ≤ 1) (hk : 0 < (k : ℝ) + 1) :
    -Real.pi * p ^ 2 - Real.pi / 8 ≤
      (thetaStirlingApprox (blockCoord k p) -
        blockCoord k p * Real.log ((k : ℝ) + 1)) +
      Real.pi * ((k : ℝ) + 1) ^ 2
    ∧
    (thetaStirlingApprox (blockCoord k p) -
      blockCoord k p * Real.log ((k : ℝ) + 1)) +
    Real.pi * ((k : ℝ) + 1) ^ 2
      ≤ -Real.pi * p ^ 2 - Real.pi / 8 + 6 * Real.pi := by
  constructor
  · linarith [stirling_saddlePhase_lower k p hp hp1 hk]
  · linarith [stirling_saddlePhase_upper k p hp hp1 hk]

/-- Cosine of the Stirling saddle phase decomposes via cos addition:
    cos(θ_S(t) - t·log(k+1))
    = cos(-π(k+1)² + residual)
    = cos(π(k+1)²)·cos(residual) - sin(π(k+1)²)·sin(residual)
    = -(-1)^k · cos(residual)

    since cos(π(k+1)²) = -(-1)^k (from cos_pi_succ_sq)
    and sin(π(k+1)²) = 0 (from sin_pi_succ_sq).

    PROVED: cos addition + cos_pi_succ_sq + sin_pi_succ_sq. -/
theorem cos_stirling_saddlePhase_factored (k : ℕ) (φ : ℝ) :
    Real.cos (-(Real.pi * ((k : ℝ) + 1) ^ 2) + φ) =
    -(-1 : ℝ) ^ k * Real.cos φ := by
  rw [show -(Real.pi * ((k : ℝ) + 1) ^ 2) + φ =
      φ - Real.pi * ((k : ℝ) + 1) ^ 2 from by ring]
  rw [Real.cos_sub, cos_pi_succ_sq, sin_pi_succ_sq]
  ring

/-- The Stirling-level cosine at blockCoord extracts (-1)^{k+1} = -(-1)^k
    times the cosine of the residual phase.

    For p ∈ [0,1] and k ≥ 0:
    cos(θ_S(blockCoord(k,p)) - blockCoord(k,p)·log(k+1))
    = -(-1)^k · cos(residual)

    where |residual| ≤ π + π/8 (bounded since |p| ≤ 1).

    **Phase connection to rsPsi**: The residual phase contains the
    information that eventually becomes rsPsi(p) = cos(π(2p²-2p+1/4))
    after the full saddle-point analysis. Specifically:
    - Stirling residual ≈ -πp² - π/8 + [log correction]
    - Log correction ≈ 2πp² + lower order
    - Net ≈ πp² - π/8
    But rsPsi uses argument π(2p²-2p+1/4) = 2πp²-2πp+π/4 = πp²-π/8 + (πp²-2πp+3π/8)
    The extra terms πp²-2πp+3π/8 = π(p-1)²-5π/8 arise from the
    Fresnel integral correction in the steepest descent, beyond the
    Gaussian approximation.

    PROVED: from stirling_saddlePhase_expanded + cos_stirling_saddlePhase_factored. -/
theorem cos_stirling_saddlePhase_at_blockCoord (k : ℕ) (p : ℝ)
    (hp : 0 ≤ p) (hk : 0 < (k : ℝ) + 1) :
    Real.cos (thetaStirlingApprox (blockCoord k p) -
      blockCoord k p * Real.log ((k : ℝ) + 1)) =
    -(-1 : ℝ) ^ k *
      Real.cos (-2 * Real.pi * p * ((k : ℝ) + 1) - Real.pi * p ^ 2 - Real.pi / 8 +
        blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1))) := by
  rw [stirling_saddlePhase_expanded k p hp hk]
  -- LHS = cos(-π(k+1)² - 2πp(k+1) - πp² - π/8 + bc·log(...))
  -- Factor: write as cos(-π(k+1)² + φ) where φ = -2πp(k+1) - πp² - π/8 + bc·log(...)
  have h_split : -(Real.pi * ((k : ℝ) + 1) ^ 2) - 2 * Real.pi * p * ((k : ℝ) + 1) -
      Real.pi * p ^ 2 - Real.pi / 8 +
      blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1)) =
    -(Real.pi * ((k : ℝ) + 1) ^ 2) +
      (-2 * Real.pi * p * ((k : ℝ) + 1) - Real.pi * p ^ 2 - Real.pi / 8 +
        blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1))) := by ring
  rw [h_split, cos_stirling_saddlePhase_factored]

/-- The 2πp(k+1) term in the residual phase is 2π times an integer when p ∈ ℤ.
    For general p, this encodes the frequency of the Fresnel oscillation.
    When we write cos(-2πp(k+1) + φ) = cos(φ)·cos(2πp(k+1)) + sin(φ)·sin(2πp(k+1)),
    the cos/sin(2πp(k+1)) terms are the Fresnel-like oscillations
    whose integral over p ∈ [0,1] produces the rsPsi function.

    This is NOT an algebraic identity that gives rsPsi directly — it
    is a structural lemma showing HOW the block integral picks up the
    Fresnel phase. The actual emergence of rsPsi(p) = cos(π(2p²-2p+1/4))
    requires evaluating the Fresnel-type integral in the saddle-point
    analysis, which is the content of `siegel_expansion_core`.

    PROVED: algebraic identity for cos addition. -/
theorem cos_residual_fresnel_decomp (k : ℕ) (p φ : ℝ) :
    Real.cos (-2 * Real.pi * p * ((k : ℝ) + 1) + φ) =
    Real.cos φ * Real.cos (2 * Real.pi * p * ((k : ℝ) + 1)) +
    Real.sin φ * Real.sin (2 * Real.pi * p * ((k : ℝ) + 1)) := by
  rw [show -2 * Real.pi * p * ((k : ℝ) + 1) + φ =
      φ - 2 * Real.pi * p * ((k : ℝ) + 1) from by ring]
  rw [Real.cos_sub]

/-- **Phase-rsPsi algebraic check**: the rsPsi argument π(2p²-2p+1/4)
    can be rewritten as -πp² - π/8 + π(3p²-2p+3/8).

    This decomposes the rsPsi phase into:
    - The Stirling residual -πp² - π/8 (from the Gaussian saddle)
    - A Fresnel correction π(3p²-2p+3/8) (from the cubic phase)

    The Fresnel correction arises because the actual saddle-point phase
    is not purely quadratic: the cubic and higher terms in the Taylor
    expansion of the phase around w₀ = √(t/2π) contribute
    a correction that shifts the effective argument from -πp²-π/8
    to the full rsPsi argument.

    PROVED: pure algebra. -/
theorem rsPsi_phase_decomposition (p : ℝ) :
    Real.pi * (2 * p ^ 2 - 2 * p + 1 / 4) =
    -(Real.pi * p ^ 2) - Real.pi / 8 +
      Real.pi * (3 * p ^ 2 - 2 * p + 3 / 8) := by
  ring

/-- The Fresnel correction satisfies π(3p²-2p+3/8) = π(3(p-1/3)² + 1/24),
    which is always ≥ π/24 > 0. This means the rsPsi argument is always
    LARGER than the pure Stirling residual -πp²-π/8.
    PROVED: completing the square. -/
theorem fresnel_correction_pos (p : ℝ) :
    0 < Real.pi * (3 * p ^ 2 - 2 * p + 3 / 8) := by
  have h : 3 * p ^ 2 - 2 * p + 3 / 8 = 3 * (p - 1 / 3) ^ 2 + 1 / 24 := by ring
  rw [h]
  have : 0 < 3 * (p - 1 / 3) ^ 2 + 1 / 24 := by positivity
  exact mul_pos Real.pi_pos this

/-- Summary bound: on block k with p ∈ [0,1], the Stirling-level
    residual phase (after extracting (-1)^k) lies in [-π-π/8, π-π/8].
    This is well within one period of cosine, so the sign is determined
    by the phase value, establishing the sign coherence needed for B3.
    PROVED: from phase residual bounds. -/
theorem stirling_residual_in_halfperiod (k : ℕ) (p : ℝ)
    (hp : 0 ≤ p) (hp1 : p ≤ 1) (hk : 0 < (k : ℝ) + 1) :
    -(Real.pi * 3) - Real.pi / 8 ≤
      (-2 * Real.pi * p * ((k : ℝ) + 1) - Real.pi * p ^ 2 - Real.pi / 8 +
        blockCoord k p * Real.log (((k : ℝ) + 1 + p) / ((k : ℝ) + 1))) := by
  -- residual = -2πp(k+1) - πp² - π/8 + correction
  -- correction ≥ 2πp(k+1) (from log_ratio_correction_lower)
  -- so residual ≥ -πp² - π/8 ≥ -π - π/8 ≥ -3π - π/8
  have h_corr := log_ratio_correction_lower k p hp hp1
  have h_p2 : Real.pi * p ^ 2 ≤ Real.pi := by
    have : p ^ 2 ≤ 1 := by nlinarith
    have := mul_le_mul_of_nonneg_left this (le_of_lt Real.pi_pos)
    linarith [mul_one Real.pi]
  linarith [Real.pi_pos]

-- ============================================================
-- Section 13: Phase reconciliation — resonant mode vs rsPsi
-- ============================================================

/-! ### Phase reconciliation between Stirling resonant mode and rsPsi

The resonant mode phase (from Stirling + log-ratio expansion) at
blockCoord(k,p) = 2π(k+1+p)² gives:

  cos(θ(t) - t·log(k+1)) ≈ (-1)^{k+1} · cos(2πp² - π/8 + O(1/k))

(proved in `cos_stirling_saddlePhase_at_blockCoord` + log-ratio bounds).

Meanwhile rsPsi(p) = cos(π(2p²-2p+1/4)) = cos(2πp² - 2πp + π/4).

The Fresnel correction is the difference: from the resonant-mode phase
`2πp² - π/8` to the rsPsi argument `2πp² - 2πp + π/4`. This is:

  (2πp² - 2πp + π/4) - (2πp² - π/8) = -2πp + 3π/8

The -2πp term arises from the cubic term in the saddle-point Taylor
expansion (the Fresnel integral contribution), and the 3π/8 = π/4+π/8
combines the quarter-period from the Fresnel integral normalization with
the eighth-period from the Stirling phase.

This section proves the algebraic decompositions connecting these phases.
The actual emergence of rsPsi from the saddle-point contour integral is
the content of `siegel_expansion_core`. -/

/-- The rsPsi argument decomposes as the Stirling residual plus
    the Fresnel correction: π(2p²-2p+1/4) = (2πp²-π/8) + (-2πp+3π/8).
    PROVED: pure algebra. -/
theorem rsPsi_arg_eq_stirling_residual_plus_fresnel (p : ℝ) :
    Real.pi * (2 * p ^ 2 - 2 * p + 1 / 4) =
    (2 * Real.pi * p ^ 2 - Real.pi / 8) + (-2 * Real.pi * p + 3 * Real.pi / 8) := by
  ring

/-- The Fresnel correction term: -2πp + 3π/8.
    At p = 0: correction = 3π/8 (positive, shifts phase rightward).
    At p = 1: correction = -2π + 3π/8 = -13π/8 (about -5.1 radians).
    At p = 3/16: correction = 0 (the "Fresnel zero").
    PROVED: pure algebra. -/
theorem fresnel_correction_at_endpoints :
    (-2 * Real.pi * (0 : ℝ) + 3 * Real.pi / 8 = 3 * Real.pi / 8) ∧
    (-2 * Real.pi * (1 : ℝ) + 3 * Real.pi / 8 = -(13 * Real.pi / 8)) ∧
    (-2 * Real.pi * (3 / 16 : ℝ) + 3 * Real.pi / 8 = 0) := by
  refine ⟨by ring, by ring, by ring⟩

/-- The FULL phase at blockCoord(k,p) (including log-ratio correction)
    decomposes as:

    -π(k+1)² + [Stirling residual] + [log-ratio correction]
    = -π(k+1)² + (2πp² - π/8) + [Fresnel correction] + O(1/k)

    Modulo π(k+1)² (integer multiple of π), this gives:
    ±1 · cos(2πp² - π/8 + [Fresnel correction] + O(1/k))
    = ±1 · cos(rsPsi_arg + O(1/k))

    The ±1 = (-1)^{k+1} from cos(πn²) = (-1)^n.

    This theorem proves the KEY algebraic identity:
    the resonant-mode residual -πp²-π/8 combined with the net
    log-ratio correction 2πp(k+1) + 3πp² + O(p³/(k+1)) minus the
    2πp(k+1) cancellation yields 2πp²-π/8, and then adding the
    Fresnel correction -2πp+3π/8 gives the full rsPsi argument.

    PROVED: algebra connecting the three decompositions. -/
theorem resonant_plus_fresnel_gives_rsPsi (p : ℝ) :
    (2 * Real.pi * p ^ 2 - Real.pi / 8) +
    (-2 * Real.pi * p + 3 * Real.pi / 8) =
    Real.pi * (2 * p ^ 2 - 2 * p + 1 / 4) := by
  ring

/-- The Stirling-level residual phase (after integer cancellation) at
    leading order is 2πp²-π/8. Combined with the Fresnel correction,
    this gives rsPsi. So: cos(Stirling residual + Fresnel correction) = rsPsi(p).
    PROVED: algebraic + definitional unfolding. -/
theorem cos_stirling_plus_fresnel_eq_rsPsi (p : ℝ) :
    Real.cos ((2 * Real.pi * p ^ 2 - Real.pi / 8) +
              (-2 * Real.pi * p + 3 * Real.pi / 8)) = rsPsi p := by
  rw [resonant_plus_fresnel_gives_rsPsi]
  rfl

/-- Quantitative bound on the Fresnel correction: for p ∈ [0,1],
    |−2πp + 3π/8| ≤ 2π + 3π/8 = 19π/8.
    PROVED: from triangle inequality + interval bounds. -/
theorem fresnel_correction_bounded (p : ℝ) (hp : 0 ≤ p) (hp1 : p ≤ 1) :
    |(-2 * Real.pi * p + 3 * Real.pi / 8)| ≤ 19 * Real.pi / 8 := by
  rw [abs_le]
  constructor
  · nlinarith [Real.pi_pos]
  · nlinarith [Real.pi_pos]

/-- The full phase error between the Stirling approximation (with log-ratio
    correction) and the exact rsPsi argument. At blockCoord(k,p):

    exact_phase = Stirling_phase + O(1/t) error
    = -π(k+1)² - πp² - π/8 + [log correction] + O(1/t)

    After cancellation (log correction ≈ 2πp(k+1) + 3πp²):
    exact_phase ≈ -π(k+1)² + 2πp² - π/8 + O(1/k)

    rsPsi argument = 2πp² - 2πp + π/4 = (2πp² - π/8) + (-2πp + 3π/8)

    The Fresnel correction -2πp + 3π/8 is the content that CANNOT be
    derived from the Stirling approximation alone — it requires the
    saddle-point contour integral evaluation (Siegel 1932 §3).

    This theorem records the exact discrepancy for downstream use.
    PROVED: pure algebra. -/
theorem stirling_to_rsPsi_discrepancy (p : ℝ) :
    Real.pi * (2 * p ^ 2 - 2 * p + 1 / 4) -
    (2 * Real.pi * p ^ 2 - Real.pi / 8) =
    -2 * Real.pi * p + 3 * Real.pi / 8 := by
  ring

end Aristotle.Standalone.RSExpansionProof
