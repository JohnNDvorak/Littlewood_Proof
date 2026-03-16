/-
Infrastructure for Gabcke phase coupling (Satz 4): sub-lemmas toward closing
the GabckePhaseCouplingHyp sorry.

## Mathematical content

The signed block correction is:
  c(k) = (-1)^k · ∫_{block k} ErrorTerm(t) dt - A · √(k+1)

Gabcke's Satz 4 asserts AntitoneOn c (Ici 1). The proof strategy:
1. Express each block integral via the saddle-point expansion (uses SiegelSaddleExpansionHyp)
2. Show the leading term is 4π·A·√(k+1) with a remainder that is O(1/√k)
3. Use concavity of √ to show the A·√(k+1) terms decrease faster than remainders

This file provides sorry-free algebraic infrastructure and key lemmas.

SORRY COUNT: 0

Co-authored-by: Claude (Anthropic)
-/

import Littlewood.Aristotle.ErrorTermExpansion
import Littlewood.Aristotle.RSBlockParam
import Littlewood.Aristotle.HardyZFirstMoment
import Littlewood.Aristotle.Standalone.FresnelSaddlePointInfra
import Littlewood.Aristotle.Standalone.SteepestDescentContour

set_option relaxedAutoImplicit false
set_option autoImplicit false
set_option maxHeartbeats 800000

noncomputable section

namespace Aristotle.Standalone.GabckePhaseCouplingInfra

open MeasureTheory Set Real Filter Topology HardyEstimatesPartial
open Aristotle.RSBlockParam Aristotle.ErrorTermExpansion
open Aristotle.Standalone.FresnelSaddlePointInfra
open Aristotle.Standalone.SteepestDescentContour

/-! ## Part 1: Sign structure of (-1)^k across consecutive blocks -/

/-- (-1)^(k+1) = -(-1)^k. The sign alternates. -/
theorem neg_one_pow_succ (k : ℕ) :
    (-1 : ℝ) ^ (k + 1) = -((-1 : ℝ) ^ k) := by
  rw [pow_succ]; ring

/-- (-1)^k * (-1)^k = 1. The sign squared is always 1. -/
theorem neg_one_pow_sq (k : ℕ) :
    (-1 : ℝ) ^ k * (-1 : ℝ) ^ k = 1 := by
  rw [← pow_add, show k + k = 2 * k from by ring]
  simp [pow_mul]

/-- |(-1)^k| = 1 for all k. -/
theorem abs_neg_one_pow (k : ℕ) :
    |(-1 : ℝ) ^ k| = 1 := by
  rw [abs_pow, abs_neg, abs_one, one_pow]

/-! ## Part 2: Consecutive block correction difference

The key identity for antitonicity is:
  c(k) - c(k+1) = (-1)^k · [I_k + I_{k+1}] - A · [√(k+1) - √(k+2)]

where I_k = ∫_{block k} ErrorTerm(t) dt and we used (-1)^{k+1} = -(-1)^k.

Since √ is concave, √(k+1) - √(k+2) < 0, so -A·[√(k+1) - √(k+2)] > 0.
The question is whether this positive contribution dominates.
-/

/-- The signed block correction difference decomposes as:
    c(k) - c(k+1)
    = (-1)^k · [I_k + I_{k+1}]
      - A · (√(k+1) - √(k+2))

    where I_k = ∫_{block k} ErrorTerm(t) dt. -/
theorem correction_diff_decomposition (A : ℝ)
    (I : ℕ → ℝ) -- I k = ∫ block k ErrorTerm dt
    (c : ℕ → ℝ)
    (hc : ∀ k, c k = (-1 : ℝ) ^ k * I k - A * Real.sqrt ((k : ℝ) + 1)) :
    ∀ k, c k - c (k + 1) =
      (-1 : ℝ) ^ k * (I k + I (k + 1)) -
      A * (Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2)) := by
  intro k
  rw [hc k, hc (k + 1)]
  rw [neg_one_pow_succ k]
  push_cast
  ring

/-! ## Part 3: √ concavity gives the positive contribution

From RSBlockParam.sqrt_decrement_antitone:
  √(k+2) - √(k+1) ≤ √(k+1) - √k

We need: √(k+1) - √(k+2) < 0, so -A·(√(k+1) - √(k+2)) > 0 when A > 0.
-/

/-- √(k+2) > √(k+1) for all k. -/
theorem sqrt_succ_lt (k : ℕ) :
    Real.sqrt ((k : ℝ) + 1) < Real.sqrt ((k : ℝ) + 2) := by
  apply Real.sqrt_lt_sqrt (by positivity) (by linarith)

/-- √(k+1) - √(k+2) < 0 for all k. -/
theorem sqrt_diff_neg (k : ℕ) :
    Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2) < 0 := by
  linarith [sqrt_succ_lt k]

/-- For A > 0: -A · (√(k+1) - √(k+2)) > 0.
    This is the positive "concavity bonus" in each correction difference. -/
theorem concavity_bonus_pos (A : ℝ) (hA : 0 < A) (k : ℕ) :
    0 < -(A * (Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2))) := by
  have h := sqrt_diff_neg k
  nlinarith

/-- The concavity bonus is antitone: larger k gives smaller bonus.
    -A·(√(k+1) - √(k+2)) ≥ -A·(√(k+2) - √(k+3))  for k ≥ 1, A > 0. -/
theorem concavity_bonus_antitone (A : ℝ) (hA : 0 < A) (k : ℕ) (hk : 1 ≤ k) :
    -(A * (Real.sqrt ((k : ℝ) + 2) - Real.sqrt ((k : ℝ) + 3)))
    ≤ -(A * (Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2))) := by
  -- Equivalently: A*(√(k+2)-√(k+3)) ≥ A*(√(k+1)-√(k+2)) reversed
  -- Actually: we need √(k+2)-√(k+1) ≤ √(k+3)-√(k+2) to FAIL.
  -- Rather: the bonus is -A*(√(k+1)-√(k+2)) = A*(√(k+2)-√(k+1))
  -- We need A*(√(k+2)-√(k+1)) ≥ A*(√(k+3)-√(k+2)), i.e., concavity of √.
  have h_decr := sqrt_decrement_antitone (k + 1) (by omega)
  -- h_decr : √(k+3) - √(k+2) ≤ √(k+2) - √(k+1)
  -- Rewrite the casts
  have h1 : Real.sqrt ((↑(k + 1) : ℝ) + 2) = Real.sqrt ((k : ℝ) + 3) := by
    congr 1; push_cast; ring
  have h2 : Real.sqrt ((↑(k + 1) : ℝ) + 1) = Real.sqrt ((k : ℝ) + 2) := by
    congr 1; push_cast; ring
  have h3 : Real.sqrt (↑(k + 1) : ℝ) = Real.sqrt ((k : ℝ) + 1) := by
    congr 1; push_cast; ring
  rw [h1, h2, h3] at h_decr
  nlinarith

/-! ## Part 4: blockCorrectionA positivity

The constant A = 4π · ∫₀¹ Ψ(p) dp is positive since Ψ > 0 on [0,1].
-/

/-- blockCorrectionA = 4π · ∫₀¹ rsPsi(p) dp is positive.
    Follows from rsPsi_integral_pos. -/
theorem blockCorrectionA_pos :
    0 < 4 * Real.pi * (∫ p in Ioc (0 : ℝ) 1, rsPsi p) := by
  have h1 : 0 < Real.pi := Real.pi_pos
  have h2 : 0 < ∫ p in Ioc (0 : ℝ) 1, rsPsi p := rsPsi_integral_pos
  positivity

/-! ## Part 5: Weighted rsPsi integral bounds

The saddle-point expansion gives (via CoV):
  (-1)^k · ∫_{block k} ErrorTerm(t) dt
  ≈ (2π/t)^{1/4} · 4π · ∫₀¹ √(k+1+p) · Ψ(p) dp

The √(k+1+p) factor is bounded between √(k+1) and √(k+2).
-/

/-- Upper bound: √(k+1+p) ≤ √(k+2) for p ∈ [0,1]. -/
theorem sqrt_block_upper (k : ℕ) (p : ℝ) (_hp0 : 0 ≤ p) (hp1 : p ≤ 1) :
    Real.sqrt ((k : ℝ) + 1 + p) ≤ Real.sqrt ((k : ℝ) + 2) := by
  apply Real.sqrt_le_sqrt; linarith

/-- Lower bound: √(k+1) ≤ √(k+1+p) for p ≥ 0. -/
theorem sqrt_block_lower (k : ℕ) (p : ℝ) (hp0 : 0 ≤ p) :
    Real.sqrt ((k : ℝ) + 1) ≤ Real.sqrt ((k : ℝ) + 1 + p) := by
  apply Real.sqrt_le_sqrt; linarith

/-- The weighted integral ∫₀¹ √(k+1+p) · Ψ(p) dp is at most
    √(k+2) · ∫₀¹ Ψ(p) dp. -/
theorem rsPsi_weighted_integral_upper (k : ℕ) :
    (∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p)
    ≤ Real.sqrt ((k : ℝ) + 2) * (∫ p in Ioc (0 : ℝ) 1, rsPsi p) := by
  rw [mul_comm]
  have h_mono : ∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p
      ≤ ∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 2) * rsPsi p := by
    apply integral_mono_ae
    · have hcont : ContinuousOn (fun p => Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p) (Icc 0 1) := by
        apply ContinuousOn.mul
        · apply ContinuousOn.sqrt
          exact continuousOn_const.add continuousOn_id
        · exact rsPsi_continuousOn
      exact hcont.integrableOn_Icc.mono_set Ioc_subset_Icc_self
    · exact rsPsi_integrableOn.const_mul _
    · apply (ae_restrict_mem measurableSet_Ioc).mono
      intro p hp
      have hpsi_nn : 0 ≤ rsPsi p := rsPsi_nonneg_on p (Ioc_subset_Icc_self hp)
      exact mul_le_mul_of_nonneg_right
        (sqrt_block_upper k p hp.1.le hp.2) hpsi_nn
  have h_eq : ∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 2) * rsPsi p
      = Real.sqrt ((k : ℝ) + 2) * (∫ p in Ioc (0 : ℝ) 1, rsPsi p) := by
    have := integral_smul (𝕜 := ℝ) (Real.sqrt ((k : ℝ) + 2))
      (fun p => rsPsi p) (μ := volume.restrict (Ioc 0 1))
    simp only [smul_eq_mul] at this
    exact this
  linarith

/-- The difference of consecutive weighted integrals satisfies:
    ∫ √(k+1+p)·Ψ dp - ∫ √(k+2+p)·Ψ dp
    ≥ (√(k+1) - √(k+2)) · ∫ Ψ dp

    This uses the lower/upper bounds on √(k+1+p). -/
theorem weighted_integral_diff_lower (k : ℕ) :
    (Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2)) *
      (∫ p in Ioc (0 : ℝ) 1, rsPsi p)
    ≤ (∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p)
      - (∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 2 + p) * rsPsi p) := by
  -- Lower bound on first integral: ≥ √(k+1) · ∫Ψ
  have h_lo := rsPsi_weighted_integral_lower k
  -- Upper bound on second integral: ≤ √(k+3) · ∫Ψ
  -- Actually we need: ∫√(k+2+p)Ψ ≤ √(k+3)·∫Ψ which follows from rsPsi_weighted_integral_upper
  -- But the difference ≥ √(k+1)·∫Ψ - √(k+3)·∫Ψ = (√(k+1)-√(k+3))·∫Ψ which is too loose.
  -- Better: use pointwise √(k+1+p) - √(k+2+p) ≥ √(k+1) - √(k+2) (since √(a+p)-√(b+p) is
  -- increasing in p when a < b -- NO, it's decreasing).
  -- Actually √(a+p) - √(b+p) for a < b is negative and increasing (less negative) as p grows.
  -- That doesn't help directly. Let's just use the integral form.
  -- We have: first ≥ √(k+1)·∫Ψ and second ≤ √(k+3)·∫Ψ, so
  -- difference ≥ √(k+1)·∫Ψ - √(k+3)·∫Ψ. But we claimed ≥ (√(k+1)-√(k+2))·∫Ψ.
  -- Since √(k+2) ≤ √(k+3), this is √(k+1)-√(k+2) ≥ √(k+1)-√(k+3). True!
  -- More precisely: second ≤ √(k+2+1)·∫Ψ = √(k+3)·∫Ψ. But we want ≤ √(k+2)·∫Ψ is WRONG
  -- since √(k+2+p) ≥ √(k+2) for p ≥ 0.
  -- OK so the bound with √(k+3) is what we get.
  -- But (√(k+1) - √(k+3)) ≤ (√(k+1) - √(k+2)) since √(k+3) ≥ √(k+2). YES.
  -- So: diff ≥ (√(k+1) - √(k+3))·∫Ψ, and we need ≥ (√(k+1)-√(k+2))·∫Ψ.
  -- Since √(k+1)-√(k+3) ≤ √(k+1)-√(k+2), and ∫Ψ > 0, this would require
  -- (√(k+1)-√(k+3))·∫Ψ ≥ (√(k+1)-√(k+2))·∫Ψ, i.e., √(k+1)-√(k+3) ≥ √(k+1)-√(k+2),
  -- i.e., -√(k+3) ≥ -√(k+2), i.e., √(k+2) ≥ √(k+3). FALSE.
  -- So this approach doesn't work as stated. The correct pointwise bound needs more care.
  -- Let me use the integral subtraction directly.
  have h_int_pos : 0 < ∫ p in Ioc (0 : ℝ) 1, rsPsi p := rsPsi_integral_pos
  -- Direct approach: ∫ (√(k+1+p) - √(k+2+p)) · Ψ(p) dp
  -- and √(k+1+p) - √(k+2+p) is a negative function of p.
  -- We bound it below pointwise: √(k+1+p) - √(k+2+p) ≥ √(k+1+1) - √(k+2+1) = √(k+2) - √(k+3)
  -- Wait, that's the WRONG direction. √(k+1+p) - √(k+2+p) is negative and gets LESS negative
  -- as p grows (concavity). So the minimum is at p = 0: √(k+1) - √(k+2).
  -- So √(k+1+p) - √(k+2+p) ≥ √(k+1) - √(k+2) for all p ∈ [0,1]. YES!
  -- Because: d/dp [√(a+p) - √(b+p)] = 1/(2√(a+p)) - 1/(2√(b+p)) > 0 when a < b (since √(a+p) < √(b+p)).
  -- So the function is increasing in p, minimum at p = 0.
  -- Great, so: ∫ [√(k+1+p) - √(k+2+p)] · Ψ dp ≥ (√(k+1)-√(k+2)) · ∫ Ψ dp.
  -- This is: first - second ≥ (√(k+1)-√(k+2)) · ∫ Ψ dp.
  -- Rewrite as an integral inequality.
  have h_diff_lower : ∀ p, p ∈ Ioc (0 : ℝ) 1 →
      (Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2)) * rsPsi p
      ≤ (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 2 + p)) * rsPsi p := by
    intro p hp
    have hpsi_nn : 0 ≤ rsPsi p := rsPsi_nonneg_on p (Ioc_subset_Icc_self hp)
    apply mul_le_mul_of_nonneg_right _ hpsi_nn
    -- Need: √(k+1) - √(k+2) ≤ √(k+1+p) - √(k+2+p) for p ≥ 0
    -- Equivalently: √(k+1+p) - √(k+1) ≥ √(k+2+p) - √(k+2)
    -- This follows from concavity of √: the increment √(a+p) - √(a) is smaller for larger a.
    -- Specifically: √ is concave, so for a < b and p > 0:
    --   √(a+p) - √(a) ≥ √(b+p) - √(b)
    -- We use: √ is concave on [0,∞), i.e., √((1-t)x + ty) ≥ (1-t)√x + t√y.
    -- Direct approach: sufficient to show f(p) = (√(k+1+p) - √(k+2+p)) - (√(k+1) - √(k+2)) ≥ 0
    -- f(0) = 0 and f'(p) = 1/(2√(k+1+p)) - 1/(2√(k+2+p)) ≥ 0.
    -- Alternatively: rearrange as √(k+2) - √(k+1) ≥ √(k+2+p) - √(k+1+p)
    -- i.e., the increment of √ over an interval of length 1 starting at (k+1) is at least as large
    -- as the increment over the same-length interval starting at (k+1+p).
    -- This is: √ concave ⟹ √(b) - √(a) ≥ √(b+p) - √(a+p) for b > a, p > 0.
    -- Let's prove this via nlinarith + sqrt properties.
    suffices h : Real.sqrt ((k : ℝ) + 2 + p) - Real.sqrt ((k : ℝ) + 2)
        ≤ Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1) by linarith
    -- Use: for 0 ≤ a ≤ b and 0 ≤ p:
    --   √(a+p) - √a ≥ √(b+p) - √b
    -- Proof: (√(a+p)-√a)(√(a+p)+√a) = p = (√(b+p)-√b)(√(b+p)+√b)
    -- and √(a+p)+√a ≤ √(b+p)+√b, so √(a+p)-√a ≥ √(b+p)-√b.
    have ha : (0 : ℝ) ≤ (k : ℝ) + 1 := by positivity
    have hb : (0 : ℝ) ≤ (k : ℝ) + 2 := by positivity
    have hab : (k : ℝ) + 1 ≤ (k : ℝ) + 2 := by linarith
    have hp_nn : 0 ≤ p := le_of_lt hp.1
    -- √(a+p) + √a ≤ √(b+p) + √b
    have h_sum_le : Real.sqrt ((k : ℝ) + 1 + p) + Real.sqrt ((k : ℝ) + 1)
        ≤ Real.sqrt ((k : ℝ) + 2 + p) + Real.sqrt ((k : ℝ) + 2) := by
      have h1 : Real.sqrt ((k : ℝ) + 1 + p) ≤ Real.sqrt ((k : ℝ) + 2 + p) :=
        Real.sqrt_le_sqrt (by linarith)
      have h2 : Real.sqrt ((k : ℝ) + 1) ≤ Real.sqrt ((k : ℝ) + 2) :=
        Real.sqrt_le_sqrt (by linarith)
      linarith
    -- Both sums are positive
    have h_sum_a_pos : 0 < Real.sqrt ((k : ℝ) + 1 + p) + Real.sqrt ((k : ℝ) + 1) := by
      positivity
    have h_sum_b_pos : 0 < Real.sqrt ((k : ℝ) + 2 + p) + Real.sqrt ((k : ℝ) + 2) := by
      positivity
    -- Conjugate multiplication: (√x - √y)(√x + √y) = x - y
    have h_conj_a : (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1)) *
        (Real.sqrt ((k : ℝ) + 1 + p) + Real.sqrt ((k : ℝ) + 1)) = p := by
      have := Real.mul_self_sqrt (show (0:ℝ) ≤ (k:ℝ) + 1 + p by linarith)
      have := Real.mul_self_sqrt (show (0:ℝ) ≤ (k:ℝ) + 1 by positivity)
      nlinarith [sq_abs (Real.sqrt ((k : ℝ) + 1 + p)), sq_abs (Real.sqrt ((k : ℝ) + 1))]
    have h_conj_b : (Real.sqrt ((k : ℝ) + 2 + p) - Real.sqrt ((k : ℝ) + 2)) *
        (Real.sqrt ((k : ℝ) + 2 + p) + Real.sqrt ((k : ℝ) + 2)) = p := by
      have := Real.mul_self_sqrt (show (0:ℝ) ≤ (k:ℝ) + 2 + p by linarith)
      have := Real.mul_self_sqrt (show (0:ℝ) ≤ (k:ℝ) + 2 by positivity)
      nlinarith [sq_abs (Real.sqrt ((k : ℝ) + 2 + p)), sq_abs (Real.sqrt ((k : ℝ) + 2))]
    -- From conjugate: diff_a = p / sum_a, diff_b = p / sum_b
    -- Since sum_a ≤ sum_b, diff_a ≥ diff_b
    by_cases hp_zero : p = 0
    · subst hp_zero; simp
    · have hp_pos : 0 < p := lt_of_le_of_ne hp_nn (Ne.symm hp_zero)
      rw [show Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 1)
          = p / (Real.sqrt ((k : ℝ) + 1 + p) + Real.sqrt ((k : ℝ) + 1)) from by
        rw [eq_div_iff h_sum_a_pos.ne.symm]; linarith [h_conj_a]]
      rw [show Real.sqrt ((k : ℝ) + 2 + p) - Real.sqrt ((k : ℝ) + 2)
          = p / (Real.sqrt ((k : ℝ) + 2 + p) + Real.sqrt ((k : ℝ) + 2)) from by
        rw [eq_div_iff h_sum_b_pos.ne.symm]; linarith [h_conj_b]]
      exact div_le_div_of_nonneg_left hp_pos.le h_sum_a_pos h_sum_le
  -- Now integrate
  have h_sub_int :
      (∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p)
      - (∫ p in Ioc (0 : ℝ) 1, Real.sqrt ((k : ℝ) + 2 + p) * rsPsi p)
      = ∫ p in Ioc (0 : ℝ) 1,
          (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 2 + p)) * rsPsi p := by
    rw [← integral_sub]
    · congr 1; ext p; ring
    · -- integrability of first
      have hcont1 : ContinuousOn (fun p => Real.sqrt ((k : ℝ) + 1 + p) * rsPsi p) (Icc 0 1) := by
        apply ContinuousOn.mul
        · apply ContinuousOn.sqrt; exact continuousOn_const.add continuousOn_id
        · exact rsPsi_continuousOn
      exact hcont1.integrableOn_Icc.mono_set Ioc_subset_Icc_self
    · -- integrability of second
      have hcont2 : ContinuousOn (fun p => Real.sqrt ((k : ℝ) + 2 + p) * rsPsi p) (Icc 0 1) := by
        apply ContinuousOn.mul
        · apply ContinuousOn.sqrt; exact continuousOn_const.add continuousOn_id
        · exact rsPsi_continuousOn
      exact hcont2.integrableOn_Icc.mono_set Ioc_subset_Icc_self
  rw [h_sub_int]
  -- Now use pointwise bound + integration
  have h_const_int :
      (Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2)) *
        (∫ p in Ioc (0 : ℝ) 1, rsPsi p)
      = ∫ p in Ioc (0 : ℝ) 1,
          (Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2)) * rsPsi p := by
    have := integral_smul (𝕜 := ℝ)
      (Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2))
      (fun p => rsPsi p) (μ := volume.restrict (Ioc 0 1))
    simp only [smul_eq_mul] at this
    exact this.symm
  rw [h_const_int]
  apply integral_mono_ae
  · exact rsPsi_integrableOn.const_mul _
  · have hcont : ContinuousOn
        (fun p => (Real.sqrt ((k : ℝ) + 1 + p) - Real.sqrt ((k : ℝ) + 2 + p)) * rsPsi p)
        (Icc 0 1) := by
      apply ContinuousOn.mul
      · apply ContinuousOn.sub
        · apply ContinuousOn.sqrt; exact continuousOn_const.add continuousOn_id
        · apply ContinuousOn.sqrt; exact continuousOn_const.add continuousOn_id
      · exact rsPsi_continuousOn
    exact hcont.integrableOn_Icc.mono_set Ioc_subset_Icc_self
  · exact (ae_restrict_mem measurableSet_Ioc).mono (fun p hp => h_diff_lower p hp)

/-! ## Part 6: Antitone criterion via sufficient block estimates

If we can show that for each k ≥ 1, the signed block integral sum
(-1)^k · (I_k + I_{k+1}) is nonneg and at least
A · (√(k+1) - √(k+2)), then c(k) - c(k+1) ≥ 0.
-/

/-- **Sufficient condition for antitonicity**: if for each k ≥ 1,
    (-1)^k · (I_k + I_{k+1}) ≥ A · (√(k+1) - √(k+2))
    then c is antitone on Ici 1. -/
theorem antitone_from_block_estimate
    (A : ℝ) (I : ℕ → ℝ) (c : ℕ → ℝ)
    (hc : ∀ k, c k = (-1 : ℝ) ^ k * I k - A * Real.sqrt ((k : ℝ) + 1))
    (h_est : ∀ k : ℕ, 1 ≤ k →
      A * (Real.sqrt ((k : ℝ) + 1) - Real.sqrt ((k : ℝ) + 2))
      ≤ (-1 : ℝ) ^ k * (I k + I (k + 1))) :
    AntitoneOn c (Ici (1 : ℕ)) := by
  -- First establish consecutive step: c(k) ≥ c(k+1) for k ≥ 1
  have h_step : ∀ k : ℕ, 1 ≤ k → c (k + 1) ≤ c k := by
    intro k hk
    have := correction_diff_decomposition A I c hc k
    linarith [h_est k hk]
  -- Then extend to arbitrary a ≤ b via telescoping
  intro a (ha : 1 ≤ a) b (_hb : 1 ≤ b) (hab : a ≤ b)
  -- Prove by induction on b - a
  have key : ∀ n : ℕ, 1 ≤ a → c (a + n) ≤ c a := by
    intro n
    induction n with
    | zero => intro _; simp
    | succ n ih =>
      intro ha'
      have h_an : 1 ≤ a + n := le_trans ha' (Nat.le_add_right a n)
      calc c (a + (n + 1)) = c ((a + n) + 1) := by ring_nf
        _ ≤ c (a + n) := h_step (a + n) h_an
        _ ≤ c a := ih ha'
  have h_eq : b = a + (b - a) := by omega
  rw [h_eq]; exact key (b - a) ha

/-! ## Part 7: Block integral sign structure from saddle expansion

Under the saddle-point expansion (SiegelSaddleExpansionHyp), the block integral
of ErrorTerm on block k is approximately:
  ∫_{block k} ErrorTerm(t) dt ≈ (-1)^k · 4π · ∫₀¹ (2π/t(k,p))^{1/4} · √(k+1+p) · Ψ(p) · 4π(k+1+p) dp

where we used CoV t = 2π(k+1+p)² and dt = 4π(k+1+p) dp.

The sign (-1)^k enters naturally from the expansion. So:
  (-1)^k · ∫_{block k} ErrorTerm = 4π · ∫₀¹ (2π/t(k,p))^{1/4} · Ψ(p) · 4π(k+1+p) dp
which is positive.
-/

/-- 2π / blockCoord k p = 1/(k+1+p)². -/
theorem two_pi_div_blockCoord (k : ℕ) (p : ℝ) (hp : 0 ≤ p) :
    2 * Real.pi / blockCoord k p = 1 / ((k : ℝ) + 1 + p) ^ 2 := by
  unfold blockCoord; field_simp

/-- On block k, 1/√(k+1+p) is positive when p ≥ 0. -/
theorem inv_sqrt_block_pos (k : ℕ) (p : ℝ) (hp : 0 ≤ p) :
    0 < 1 / Real.sqrt ((k : ℝ) + 1 + p) := by
  positivity

/-- The (2π/blockCoord k p)^{1/4} factor squared equals 1/(k+1+p).
    Key identity: ((1/x²)^{1/4})^2 = (1/x²)^{1/2} = 1/x for x > 0. -/
theorem quarter_power_sq_on_block (k : ℕ) (p : ℝ) (hp : 0 ≤ p) :
    ((2 * Real.pi / blockCoord k p) ^ ((1 : ℝ) / 4)) ^ 2 =
    1 / ((k : ℝ) + 1 + p) := by
  have hkp : 0 < (k : ℝ) + 1 + p := by positivity
  rw [two_pi_div_blockCoord k p hp]
  -- Rewrite LHS using rpow
  set x := ((k : ℝ) + 1 + p) with hx_def
  have hx_pos : 0 < x := hkp
  -- (1/x²)^{1/4} is nonneg
  have h_base_nn : (0 : ℝ) ≤ 1 / x ^ 2 := by positivity
  -- Use rpow_natCast to convert ^ 2 to rpow
  conv_lhs => rw [sq]
  -- ((1/x²)^{1/4}) * ((1/x²)^{1/4}) = (1/x²)^{1/4 + 1/4}
  rw [← Real.rpow_add (by positivity : 0 < 1 / x ^ 2)]
  -- 1/4 + 1/4 = 1/2
  have h_exp : (1 : ℝ) / 4 + 1 / 4 = 1 / 2 := by norm_num
  rw [h_exp, ← Real.sqrt_eq_rpow,
      Real.sqrt_div' _ (by positivity), Real.sqrt_one, Real.sqrt_sq hx_pos.le]

end Aristotle.Standalone.GabckePhaseCouplingInfra
