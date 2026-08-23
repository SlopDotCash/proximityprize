/-
Copyright (c) 2026 ArkLib Contributors. All rights reserved.
Released under Apache 2.0 license as described in the file LICENSE.
Authors: ArkLib Contributors
-/
import Mathlib.Analysis.SpecialFunctions.Pow.Real
import Mathlib.Analysis.SpecialFunctions.Sqrt
import Mathlib.Data.Nat.Factorial.DoubleFactorial
import Mathlib.Tactic

/-!
# The moment-saddle value of the floor `M` — a NEW explicit-constant derivation (#444)

**Deriving the value of δ\* from the laws, and defending it.** The campaign's laws give the **moment
bridge** `M^{2r} ≤ p · E_r ≤ p · (2r−1)‼ · n^r` (Parseval + the char-`p` Wick bound), and the **saddle**
`min_r (p·(2r−1)‼·n^r)^{1/2r} = √(2n·log p)·(1+o(1))` (machine-confirmed `C → 1.0016` at prize scale). So
the floor's derived value is `M ≈ √(2n·log p)` — the constant the campaign measured.

This file lands the **explicit-constant** form (the defensible theorem, after shooting down the
non-defensible candidates — see `docs/kb/deltastar-444-derive-value-and-defend-2026-06-17.md`): using the
ELEMENTARY bound `(2r−1)‼ ≤ (2r)^r`, the moment bridge gives the closed value
  `M ≤ (p · (2r·n)^r)^{1/2r} = p^{1/2r} · √(2r·n)`,
and at the optimal integer depth `r = ⌈log p⌉` (so `p^{1/2r} ≤ √e`) this is `M ≤ √(2e·n·log p)` — an
EXPLICIT constant `√(2e) ≈ 2.33`. This is a genuinely new, defensible derivation: it pins the floor's value
to `O(√(n·log m))` with an explicit constant, **conditional on the char-`p` Wick bound at a SINGLE depth**
`r = ⌈log p⌉` — strictly weaker than the all-depth requirement, and the cleanest closed-form ceiling on the
floor. (The single-depth Wick input remains the open BGK residual; everything else here is proven.)

## What was shot down (the non-defensible candidates)
- `M = √(2n log p)` EXACTLY — refuted (only an upper bound; the Parseval lower bound is `√n ≠ √(2n log p)`).
- `M = 2√n` (Ramanujan) — refuted (machine `M/2√n = 1.34–2.43 > 1`, not Ramanujan).
- `M ≤ √(2n log p)` UNCONDITIONALLY — reduces (needs char-`p` Wick at all depths = the open prize).
The surviving, defended statement is the conditional explicit-constant bound below.

## D1-saddle UPGRADE: the sharper `√e` constant from AM–GM, and the exact `√2` asymptotic

The elementary `(2r−1)‼ ≤ (2r)^r` above is loose by a full factor `e^r` (Stirling:
`(2r−1)‼ ∼ √2·(2r/e)^r`). The cheapest rigorous tightening that is fully Lean-formalizable is **AM–GM**
on the `r` odd factors `1, 3, …, 2r−1` (arithmetic mean exactly `r`):
  `(2r−1)‼ = ∏_{i=1}^r (2i−1) ≤ r^r`     (geometric ≤ arithmetic mean).
This is *strictly* sharper than `(2r)^r` by the factor `2^r`. Feeding `(2r−1)‼·n^r ≤ (r·n)^r` into the
same saddle gives the closed value `M ≤ p^{1/2r}·√(r·n)`, and at the optimal depth `r = ⌈log p⌉`
(where `p^{1/2r} ≤ √e`) this is
  **`M ≤ √(e·r·n) = √(e·n·log p)`  — explicit constant `√e ≈ 1.6487`,**
a `√2`-factor improvement over the prior `√(2e) ≈ 2.3316`. Both `oddDoubleFactorial_le_pow`
(`(2r−1)‼ ≤ r^r`, proved by induction via Bernoulli `((m+2)/(m+1))^(m+1) ≥ 2`) and the saddle
composition `prize_floor_amgm_sqrt_e` are landed axiom-clean below.

**The exact asymptotic (`finding`, not Lean-landed — needs the upper Stirling bound Mathlib lacks):**
the genuine saddle of the Wick bound is, with the sharp Stirling `(2r−1)‼ ≤ √2·(2r/e)^r`,
`min_r (p·√2·(2rn/e)^r)^{1/2r}`. Writing `f(r) = (1/2r)·log p + ½·log(2rn/e) + (log 2)/(4r)`,
`f'(r) = −log p /(2r²) + 1/(2r) = 0 ⟹ r* = log p`, and at `r* = log p` the `p^{1/2r} = √e` factor
**cancels the `e^{-1/2}` from `(2r/e)`**, leaving exactly `√(2·r*·n)·(1+o(1)) = √(2·n·log p)·(1+o(1))`.
So `min_r (p·(2r−1)‼·n^r)^{1/2r} = √(2n·log p)·(1+o(1))` with the **optimal constant `√2 ≈ 1.4142`**
(machine-confirmed at prize scale `n=2^30, p≈n·2^128`: `r* = ⌈log p⌉ = 110`, `Mb*/√(n log p) = 1.4165`).
The AM–GM `√e` is the cheapest *proven* ceiling; the Stirling `√2` is the cheapest *attainable* one,
both at the SAME optimal depth `r* = ⌈log p⌉`.
-/

set_option autoImplicit false

namespace ArkLib.ProximityGap.MomentSaddleValue

open Real

/-- **The moment-saddle value (the defended theorem).** From the moment+elementary-Wick bound
`M^{2r} ≤ p · (2r·n)^r` (Parseval `M^{2r} ≤ p·E_r`, `E_r ≤ (2r−1)‼·n^r ≤ (2r)^r·n^r = (2rn)^r`), the floor
obeys the EXPLICIT closed value
  `M ≤ p^{1/2r} · √(2r·n)`.
Minimized at `r = ⌈log p⌉` (where `p^{1/2r} ≤ √e`) this is `M ≤ √(2e·n·log p)` — the floor pinned to
`O(√(n·log m))` with explicit constant `√(2e)`, conditional only on the single-depth char-`p` Wick input. -/
theorem moment_saddle_value {M p r2n : ℝ} {r : ℕ} (hr : 0 < r)
    (hM : 0 ≤ M) (hp : 0 ≤ p) (hr2n : 0 ≤ r2n)
    (hbound : M ^ (2 * r) ≤ p * r2n ^ r) :
    M ≤ p ^ (((2 * r : ℕ) : ℝ)⁻¹) * Real.sqrt r2n := by
  have hr2 : (2 * r : ℕ) ≠ 0 := by positivity
  have hMpow : (0 : ℝ) ≤ M ^ (2 * r) := by positivity
  -- M = (M^{2r})^{1/2r} ≤ (p·r2n^r)^{1/2r}
  have step1 : M ≤ (p * r2n ^ r) ^ (((2 * r : ℕ) : ℝ)⁻¹) := by
    calc M = (M ^ (2 * r)) ^ (((2 * r : ℕ) : ℝ)⁻¹) := (Real.pow_rpow_inv_natCast hM hr2).symm
      _ ≤ (p * r2n ^ r) ^ (((2 * r : ℕ) : ℝ)⁻¹) := Real.rpow_le_rpow hMpow hbound (by positivity)
  -- (r2n^r)^{1/2r} = r2n^{1/2} = √r2n
  have hsqrt : (r2n ^ r) ^ (((2 * r : ℕ) : ℝ)⁻¹) = Real.sqrt r2n := by
    rw [← Real.rpow_natCast r2n r, ← Real.rpow_mul hr2n, Real.sqrt_eq_rpow]
    congr 1
    push_cast
    rw [mul_inv_eq_iff_eq_mul₀ (by positivity)]
    ring
  -- (p·r2n^r)^{1/2r} = p^{1/2r} · √r2n
  have step2 : (p * r2n ^ r) ^ (((2 * r : ℕ) : ℝ)⁻¹) = p ^ (((2 * r : ℕ) : ℝ)⁻¹) * Real.sqrt r2n := by
    rw [Real.mul_rpow hp (by positivity), hsqrt]
  rw [step2] at step1
  exact step1

/-- **The elementary Wick reduction `m‼ ≤ (m+1)^{⌈m/2⌉}` feeding the saddle, abstract form.** The moment
bound `M^{2r} ≤ p·(2r−1)‼·n^r` reduces to the `moment_saddle_value` hypothesis `M^{2r} ≤ p·(2rn)^r` via the
elementary `(2r−1)‼ = 1·3⋯(2r−1) ≤ (2r)^r` (each of the `r` odd factors `≤ 2r`). We record the clean
product-bound shape: a product of `r` reals each `≤ B` is `≤ B^r`. -/
theorem prod_le_pow_of_le {r : ℕ} {B : ℝ} (hB : 0 ≤ B) (a : ℕ → ℝ)
    (ha : ∀ i ∈ Finset.range r, 0 ≤ a i) (hle : ∀ i ∈ Finset.range r, a i ≤ B) :
    ∏ i ∈ Finset.range r, a i ≤ B ^ r := by
  calc ∏ i ∈ Finset.range r, a i ≤ ∏ _i ∈ Finset.range r, B :=
        Finset.prod_le_prod ha hle
    _ = B ^ r := by rw [Finset.prod_const, Finset.card_range]

/-- **The MINIMAL residual: single-depth Wick ⟹ explicit prize floor.** Composing `moment_saddle_value`
with `p^{1/2r} ≤ √e` at depth `r ≥ log p` (`p ≤ exp r`): from the char-`p` energy bound at the SINGLE depth
`r = ⌈log p⌉`, `M^{2r} ≤ p·(2r·n)^r`, the floor is pinned `M ≤ √e · √(2r·n) = √(2e·r·n)`. This is the
WEAKEST sufficient input for the prize floor — implied by all-depth Wick (hence by the step-ratio
monotonicity and the Gaussian-tail decay law). So the campaign's many named residuals consolidate: the
prize floor needs only ONE energy bound at depth `≈ log p`, not the full sub-Gaussian decay. -/
theorem prize_floor_of_single_depth {M p n : ℝ} {r : ℕ} (hr : 0 < r)
    (hM : 0 ≤ M) (hp : 0 ≤ p) (hn : 0 ≤ n)
    (hWick : M ^ (2 * r) ≤ p * (2 * r * n) ^ r)
    (hdepth : p ≤ Real.exp r) :
    M ≤ Real.sqrt (Real.exp 1) * Real.sqrt (2 * r * n) := by
  have hsaddle := moment_saddle_value hr hM hp (by positivity : (0:ℝ) ≤ 2 * r * n) hWick
  refine le_trans hsaddle ?_
  apply mul_le_mul_of_nonneg_right _ (Real.sqrt_nonneg _)
  -- `p^{1/2r} ≤ √e`: from `p ≤ exp r` and `(exp r)^{1/2r} = exp(1/2) = √(exp 1)`.
  have hexp_pos : (0 : ℝ) < Real.exp (r : ℝ) := Real.exp_pos _
  have hrinv : (0 : ℝ) ≤ (((2 * r : ℕ) : ℝ))⁻¹ := by positivity
  calc p ^ (((2 * r : ℕ) : ℝ))⁻¹
      ≤ (Real.exp (r : ℝ)) ^ (((2 * r : ℕ) : ℝ))⁻¹ :=
        Real.rpow_le_rpow hp hdepth hrinv
    _ = Real.sqrt (Real.exp 1) := by
        rw [Real.rpow_def_of_pos (Real.exp_pos _), Real.log_exp, Real.sqrt_eq_rpow,
            Real.rpow_def_of_pos (Real.exp_pos 1), Real.log_exp]
        congr 1
        have hrne : (r : ℝ) ≠ 0 := by positivity
        push_cast
        field_simp

/-! ## D1-saddle: the sharper `√e` constant via AM–GM `(2r−1)‼ ≤ r^r` -/

/-- **Bernoulli sub-step** `((m+2)/(m+1))^(m+1) ≥ 2`, the engine of the AM–GM double-factorial bound.
From Mathlib's `one_add_mul_sub_le_pow` (`1 + n·(a−1) ≤ a^n`) at `a = (m+2)/(m+1)`, `n = m+1`:
`1 + (m+1)·(1/(m+1)) = 2 ≤ ((m+2)/(m+1))^(m+1)`. -/
theorem two_le_ratio_pow (m : ℕ) :
    (2 : ℝ) ≤ (((m:ℝ) + 2) / ((m:ℝ) + 1)) ^ (m + 1) := by
  have hpos : (0:ℝ) < (m:ℝ) + 1 := by positivity
  have hH : (-1 : ℝ) ≤ ((m:ℝ)+2)/((m:ℝ)+1) := by
    rw [le_div_iff₀ hpos]; nlinarith [hpos]
  have hb := one_add_mul_sub_le_pow (a := ((m:ℝ)+2)/((m:ℝ)+1)) hH (m + 1)
  push_cast at hb
  have he : (1:ℝ) + ((m:ℝ)+1) * (((m:ℝ)+2)/((m:ℝ)+1) - 1) = 2 := by
    rw [mul_sub, mul_div_cancel₀ _ (ne_of_gt hpos)]; ring
  rw [he] at hb
  exact hb

/-- **AM–GM double-factorial bound `(2r−1)‼ ≤ r^r`** (shifted form `(2k+1)‼ ≤ (k+1)^(k+1)`, so
`(2(k+1)−1)‼ = (2k+1)‼ ≤ (k+1)^(k+1)`). The product of the `r` odd numbers `1, 3, …, 2r−1` has
arithmetic mean `r`, so by AM ≥ GM its geometric mean is `≤ r` and the product is `≤ r^r`. Proved by
induction on the double-factorial recurrence `(2k+3)‼ = (2k+3)·(2k+1)‼`, with the step
`(2k+3)·(k+1)^(k+1) ≤ (k+2)^(k+2)` discharged via `two_le_ratio_pow` (`(k+2)^(k+1) ≥ 2(k+1)^(k+1)`).
This is `2^r`-sharper than the elementary `(2r−1)‼ ≤ (2r)^r`, halving the saddle constant. -/
theorem oddDoubleFactorial_le_pow (k : ℕ) :
    ((Nat.doubleFactorial (2 * k + 1) : ℝ)) ≤ ((k : ℝ) + 1) ^ (k + 1) := by
  induction k with
  | zero => simp [Nat.doubleFactorial]
  | succ m ih =>
    have hrec : Nat.doubleFactorial (2 * (m + 1) + 1)
        = (2 * (m + 1) + 1) * Nat.doubleFactorial (2 * m + 1) := by
      have h2 : 2 * (m + 1) + 1 = (2 * m + 1) + 2 := by ring
      rw [h2, Nat.doubleFactorial_add_two]
    have hcast : ((Nat.doubleFactorial (2 * (m + 1) + 1) : ℝ))
        = (2 * (m:ℝ) + 3) * (Nat.doubleFactorial (2 * m + 1) : ℝ) := by
      rw [hrec]; push_cast; ring
    rw [hcast]
    have hstep1 : (2 * (m:ℝ) + 3) * (Nat.doubleFactorial (2 * m + 1) : ℝ)
        ≤ (2 * (m:ℝ) + 3) * ((m:ℝ) + 1) ^ (m + 1) :=
      mul_le_mul_of_nonneg_left ih (by positivity)
    refine le_trans hstep1 ?_
    have hbern := two_le_ratio_pow m
    rw [div_pow] at hbern
    have hpow : (2:ℝ) * ((m:ℝ) + 1) ^ (m + 1) ≤ ((m:ℝ) + 2) ^ (m + 1) := by
      rw [le_div_iff₀ (by positivity)] at hbern; linarith [hbern]
    calc (2 * (m:ℝ) + 3) * ((m:ℝ) + 1) ^ (m + 1)
        ≤ (2 * (m:ℝ) + 4) * ((m:ℝ) + 1) ^ (m + 1) :=
          mul_le_mul_of_nonneg_right (by linarith) (by positivity)
      _ = ((m:ℝ) + 2) * (2 * ((m:ℝ) + 1) ^ (m + 1)) := by ring
      _ ≤ ((m:ℝ) + 2) * (((m:ℝ) + 2) ^ (m + 1)) :=
          mul_le_mul_of_nonneg_left hpow (by positivity)
      _ = ((↑(m+1) : ℝ) + 1) ^ (m + 1 + 1) := by push_cast; ring

/-- **The AM–GM moment-saddle value (the SHARPER defended theorem).** From the genuine char-`p` Wick
bound `M^{2(k+1)} ≤ p · ((2(k+1)−1)‼) · n^(k+1)` at depth `r = k+1 ≥ 1`, the AM–GM tightening
`(2r−1)‼ ≤ r^r` gives `M^{2r} ≤ p·(r·n)^r`, hence the EXPLICIT closed value
  `M ≤ p^{1/2r} · √(r·n)`.
This is the same saddle shape as `moment_saddle_value` but with `r2n = r·n` (not `2r·n`) — a `√2`
sharpening at every depth, sourced from a Lean-proved bound, not an elementary over-estimate. -/
theorem moment_saddle_value_amgm {M p n : ℝ} {k : ℕ}
    (hM : 0 ≤ M) (hp : 0 ≤ p) (hn : 0 ≤ n)
    (hWick : M ^ (2 * (k + 1)) ≤ p * (Nat.doubleFactorial (2 * (k + 1) - 1)) * n ^ (k + 1)) :
    M ≤ p ^ (((2 * (k + 1) : ℕ) : ℝ)⁻¹) * Real.sqrt (((k : ℝ) + 1) * n) := by
  -- Reduce the Wick input to the `moment_saddle_value` shape `M^{2r} ≤ p·(r·n)^r`, `r = k+1`.
  have hdf : (Nat.doubleFactorial (2 * (k + 1) - 1) : ℝ) ≤ ((k:ℝ) + 1) ^ (k + 1) := by
    have h2 : 2 * (k + 1) - 1 = 2 * k + 1 := by omega
    rw [h2]; exact oddDoubleFactorial_le_pow k
  have hrn : M ^ (2 * (k + 1)) ≤ p * (((k:ℝ) + 1) * n) ^ (k + 1) := by
    refine le_trans hWick ?_
    rw [mul_pow]
    calc p * (Nat.doubleFactorial (2 * (k + 1) - 1) : ℝ) * n ^ (k + 1)
        = p * ((Nat.doubleFactorial (2 * (k + 1) - 1) : ℝ) * n ^ (k + 1)) := by ring
      _ ≤ p * (((k:ℝ) + 1) ^ (k + 1) * n ^ (k + 1)) := by
          apply mul_le_mul_of_nonneg_left _ hp
          exact mul_le_mul_of_nonneg_right hdf (by positivity)
  exact moment_saddle_value (Nat.succ_pos k) hM hp (by positivity) hrn

/-- **The MINIMAL residual, SHARPENED: single-depth Wick ⟹ explicit `√e` prize floor.** Composing
`moment_saddle_value_amgm` with `p^{1/2r} ≤ √e` at depth `r = k+1 ≥ log p` (`p ≤ exp r`): from the
char-`p` energy bound at the SINGLE depth `r = ⌈log p⌉`, `M^{2r} ≤ p·(2r−1)‼·n^r`, the floor is pinned
  `M ≤ √e · √(r·n) = √(e·r·n)`  (i.e. `√(e·n·log p)`),
the **explicit constant `√e ≈ 1.6487`** — a `√2`-factor improvement over `prize_floor_of_single_depth`'s
`√(2e·r·n)`. The single-depth Wick input is the unchanged open BGK residual; everything else is proven. -/
theorem prize_floor_amgm_sqrt_e {M p n : ℝ} {k : ℕ}
    (hM : 0 ≤ M) (hp : 0 ≤ p) (hn : 0 ≤ n)
    (hWick : M ^ (2 * (k + 1)) ≤ p * (Nat.doubleFactorial (2 * (k + 1) - 1)) * n ^ (k + 1))
    (hdepth : p ≤ Real.exp (k + 1)) :
    M ≤ Real.sqrt (Real.exp 1) * Real.sqrt (((k : ℝ) + 1) * n) := by
  have hsaddle := moment_saddle_value_amgm hM hp hn hWick
  refine le_trans hsaddle ?_
  apply mul_le_mul_of_nonneg_right _ (Real.sqrt_nonneg _)
  -- `p^{1/2r} ≤ √e` from `p ≤ exp r` and `(exp r)^{1/2r} = √e`.
  have hrinv : (0 : ℝ) ≤ (((2 * (k + 1) : ℕ) : ℝ))⁻¹ := by positivity
  calc p ^ (((2 * (k + 1) : ℕ) : ℝ))⁻¹
      ≤ (Real.exp ((k : ℝ) + 1)) ^ (((2 * (k + 1) : ℕ) : ℝ))⁻¹ :=
        Real.rpow_le_rpow hp hdepth hrinv
    _ = Real.sqrt (Real.exp 1) := by
        rw [Real.rpow_def_of_pos (Real.exp_pos _), Real.log_exp, Real.sqrt_eq_rpow,
            Real.rpow_def_of_pos (Real.exp_pos 1), Real.log_exp]
        congr 1
        have hkne : ((k:ℝ) + 1) ≠ 0 := by positivity
        push_cast
        field_simp

end ArkLib.ProximityGap.MomentSaddleValue

/-! ## Axiom audit -/
#print axioms ArkLib.ProximityGap.MomentSaddleValue.moment_saddle_value
#print axioms ArkLib.ProximityGap.MomentSaddleValue.prod_le_pow_of_le
#print axioms ArkLib.ProximityGap.MomentSaddleValue.prize_floor_of_single_depth
#print axioms ArkLib.ProximityGap.MomentSaddleValue.two_le_ratio_pow
#print axioms ArkLib.ProximityGap.MomentSaddleValue.oddDoubleFactorial_le_pow
#print axioms ArkLib.ProximityGap.MomentSaddleValue.moment_saddle_value_amgm
#print axioms ArkLib.ProximityGap.MomentSaddleValue.prize_floor_amgm_sqrt_e
