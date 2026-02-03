/-
Copyright (c) 2025. All rights reserved.
Released under Apache 2.0 license as described in the file LICENSE.
Authors: Cameron Freer
-/
import SpherePacking.ModularForms.FG
import SpherePacking.ModularForms.JacobiTheta
import SpherePacking.ModularForms.QExpansion
import SpherePacking.ModularForms.summable_lems

/-!
# L₁₀ Definition and Serre Derivative Positivity

This file contains the definition of `L₁₀`, Serre derivative algebra, and the F-side analysis
including vanishing order and log-derivative limits. The main result is `serre_D_L₁₀_pos_imag_axis`.

## Main definitions and results

* `L₁₀` : The key function `L₁,₀ = (∂₁₀F)G - F(∂₁₀G)` for monotonicity analysis.
* `serre_D_L₁₀` : Formula for `∂₂₂ L₁,₀`.
* `serre_D_L₁₀_pos_imag_axis` : `∂₂₂ L₁,₀(it) > 0` for all `t > 0`.
* `F_vanishing_order` : `F / q² → 720²` as `im(z) → ∞`.
* `D_F_div_F_tendsto` : `(D F)/F → 2` as `im(z) → ∞`.
-/

open UpperHalfPlane hiding I
open Real Complex CongruenceSubgroup SlashAction SlashInvariantForm ContinuousMap

open scoped ModularForm MatrixGroups Manifold ArithmeticFunction.sigma

namespace MonotoneFG

/-! ## Helper lemmas -/

/-- Reindex σ₃ q-expansion from ℕ+ to ℕ using n ↦ m+1. -/
lemma sigma3_qexp_reindex_pnat_nat (z : ℍ) :
    ∑' n : ℕ+, ↑n * ↑(ArithmeticFunction.sigma 3 n) *
      cexp (2 * π * Complex.I * (n - 1) * z) =
    ∑' m : ℕ, ↑(m + 1) * ↑(ArithmeticFunction.sigma 3 (m + 1)) *
      cexp (2 * π * Complex.I * m * z) := by
  simpa [tsum_pnat_eq_tsum_succ3] using
    (tsum_pnat_eq_tsum_succ3 (f := fun n : ℕ => (n : ℂ) * (↑(ArithmeticFunction.sigma 3 n) : ℂ) *
      cexp (2 * π * Complex.I * ((n : ℂ) - 1) * z)))

/-- If f/g → c ≠ 0, then eventually f ≠ 0. -/
lemma eventually_ne_zero_of_tendsto_div {f g : ℍ → ℂ} {c : ℂ} (hc : c ≠ 0)
    (h : Filter.Tendsto (fun z => f z / g z) atImInfty (nhds c)) :
    ∀ᶠ z : ℍ in atImInfty, f z ≠ 0 := by
  filter_upwards [h.eventually_ne hc] with z hz hf
  exact hz (by simp [hf])

/-!
## Section 1: Definition and Properties of L₁,₀

The key object in proving monotonicity is:
  `L₁,₀ = (∂₁₀F)G - F(∂₁₀G)`

By the quotient rule for derivatives:
  `d/dt (F(it)/G(it)) = (-2π) * L₁,₀(it) / G(it)²`

So proving L₁,₀(it) > 0 implies Q is decreasing.
-/

/--
The function `L₁,₀ = (∂₁₀F)G - F(∂₁₀G)`.
Blueprint: Proposition 8.12.
-/
noncomputable def L₁₀ (z : ℍ) : ℂ :=
  serre_D 10 F z * G z - F z * serre_D 10 G z

/--
Alternative form: `L₁,₀ = F'G - FG'` where `'` denotes the normalized derivative.
This follows from the fact that ∂₀ = D (the E₂ term cancels in the difference).
-/
theorem L₁₀_eq_FD_G_sub_F_DG (z : ℍ) :
    L₁₀ z = D F z * G z - F z * D G z := by
  simp only [L₁₀, serre_D]
  ring

/-!
## Section 2: Serre Derivative of L₁,₀

We need to compute `∂₂₂ L₁,₀` and show it's positive on the imaginary axis.
-/

/--
The Serre derivative `∂₂₂ L₁,₀`.
Blueprint: Using the product rule (Theorem 6.53) twice.
The cross terms `(∂₁₀F)(∂₁₀G)` cancel in the subtraction.
-/
theorem serre_D_L₁₀ (z : ℍ) :
    serre_D 22 L₁₀ z = serre_D 12 (serre_D 10 F) z * G z
      - F z * serre_D 12 (serre_D 10 G) z := by
  have hDF := serre_D_differentiable F_holo (k := 10)
  have hDG := serre_D_differentiable G_holo (k := 10)
  rw [show L₁₀ = serre_D 10 F * G - F * serre_D 10 G from rfl]
  have hsub := serre_D_sub (22 : ℤ) _ _ (hDF.mul G_holo) (F_holo.mul hDG)
  simp only [Int.cast_ofNat] at hsub
  rw [hsub, Pi.sub_apply]
  have h1 : serre_D 22 (serre_D 10 F * G) z =
      serre_D 12 (serre_D 10 F) z * G z + serre_D 10 F z * serre_D 10 G z := by
    conv_lhs => rw [show (22 : ℂ) = 12 + 10 by norm_num]
    simpa [Pi.mul_apply, Pi.add_apply] using congrFun (serre_D_mul 12 10 _ G hDF G_holo) z
  have h2 : serre_D 22 (F * serre_D 10 G) z =
      serre_D 10 F z * serre_D 10 G z + F z * serre_D 12 (serre_D 10 G) z := by
    conv_lhs => rw [show (22 : ℂ) = 10 + 12 by norm_num]
    simpa [Pi.mul_apply, Pi.add_apply] using congrFun (serre_D_mul 10 12 F _ F_holo hDG) z
  rw [h1, h2]
  ring

/--
`∂₂₂ L₁,₀ = Δ(7200(-E₂')G + 640H₂F)` on the upper half-plane.
Blueprint: Follows from differential equations (65) and (66).
-/
theorem serre_D_L₁₀_eq (z : ℍ) :
    serre_D 22 L₁₀ z = Δ z * (7200 * (-(D E₂ z)) * G z + 640 * H₂ z * F z) := by
  have hF_z := congrFun MLDE_F z
  have hG_z := congrFun MLDE_G z
  simp only [Pi.add_apply, Pi.mul_apply, Pi.sub_apply, negDE₂, Pi.neg_apply, Δ_fun_eq_Δ,
    Pi.ofNat_apply, Pi.inv_apply] at hF_z hG_z
  rw [serre_D_L₁₀, hF_z, hG_z]
  ring

/-!
### negDE₂ imaginary axis properties

We prove that `negDE₂ = -(D E₂)` is real and positive on the imaginary axis.
From `ramanujan_E₂`: `D E₂ = 12⁻¹ * (E₂² - E₄)`, so `negDE₂ = 12⁻¹ * (E₄ - E₂²)`.
The positivity `E₄(it) > E₂(it)²` follows from the q-expansion coefficients being positive.
-/

/-- Extract the imaginary part condition at a point from `ResToImagAxis.Real`. -/
private lemma im_eq_zero_of_real {F : ℍ → ℂ} (hF : ResToImagAxis.Real F)
    {t : ℝ} (ht : 0 < t) (z : ℍ) (hz : z = ⟨Complex.I * t, by simp [ht]⟩) :
    (F z).im = 0 := by
  subst hz
  simpa [Function.resToImagAxis, ResToImagAxis, ht] using hF t ht

/-- Extract the positivity condition at a point from `ResToImagAxis.Pos`. -/
private lemma re_pos_of_pos {F : ℍ → ℂ} (hF : ResToImagAxis.Pos F)
    {t : ℝ} (ht : 0 < t) (z : ℍ) (hz : z = ⟨Complex.I * t, by simp [ht]⟩) :
    0 < (F z).re := by
  subst hz
  simpa [Function.resToImagAxis, ResToImagAxis, ht] using hF.2 t ht

/--
`∂₂₂ L₁,₀(it) > 0` for all `t > 0`.
Blueprint: Corollary 8.9 - both terms in the expression are positive.
- `-D E₂(it) > 0` (negDE₂_imag_axis_pos)
- `Δ(it) > 0` (Delta_imag_axis_pos)
- `G(it) > 0` and `H₂(it) > 0` and `F(it) > 0`
-/
theorem serre_D_L₁₀_pos_imag_axis : ResToImagAxis.Pos (serre_D 22 L₁₀) := by
  refine ⟨?_, fun t ht => ?_⟩
  -- Part 1: Real on imaginary axis
  · intro t ht
    simp only [Function.resToImagAxis, ResToImagAxis, ht, ↓reduceDIte]
    set z : ℍ := ⟨Complex.I * t, by simp [ht]⟩
    rw [serre_D_L₁₀_eq z]
    change (Δ z * (7200 * negDE₂ z * G z + 640 * H₂ z * F z)).im = 0
    simp only [Complex.mul_im, Complex.add_im,
      (by norm_num : (7200 : ℂ).im = 0), (by norm_num : (640 : ℂ).im = 0),
      im_eq_zero_of_real Delta_imag_axis_pos.1 ht z rfl,
      im_eq_zero_of_real G_imag_axis_real ht z rfl,
      im_eq_zero_of_real H₂_imag_axis_pos.1 ht z rfl,
      im_eq_zero_of_real F_imag_axis_real ht z rfl,
      im_eq_zero_of_real negDE₂_imag_axis_real ht z rfl]
    ring
  -- Part 2: Positive on imaginary axis
  · simp only [Function.resToImagAxis, ResToImagAxis, ht, ↓reduceDIte]
    set z : ℍ := ⟨Complex.I * t, by simp [ht]⟩
    rw [serre_D_L₁₀_eq z]
    change 0 < (Δ z * (7200 * negDE₂ z * G z + 640 * H₂ z * F z)).re
    have hΔ_pos := re_pos_of_pos Delta_imag_axis_pos ht z rfl
    have hΔ_real := im_eq_zero_of_real Delta_imag_axis_pos.1 ht z rfl
    have hnegDE₂_pos := re_pos_of_pos negDE₂_imag_axis_pos ht z rfl
    have hnegDE₂_real := im_eq_zero_of_real negDE₂_imag_axis_pos.1 ht z rfl
    have hG_pos := re_pos_of_pos G_imag_axis_pos ht z rfl
    have hG_real := im_eq_zero_of_real G_imag_axis_real ht z rfl
    have hH₂_pos := re_pos_of_pos H₂_imag_axis_pos ht z rfl
    have hH₂_real := im_eq_zero_of_real H₂_imag_axis_pos.1 ht z rfl
    have hF_pos := re_pos_of_pos F_imag_axis_pos ht z rfl
    have hF_real := im_eq_zero_of_real F_imag_axis_real ht z rfl
    have hsum_pos : (7200 * negDE₂ z * G z + 640 * H₂ z * F z).re > 0 := by
      simp only [Complex.add_re, Complex.mul_re, hnegDE₂_real, hG_real, hH₂_real, hF_real,
        mul_zero, sub_zero]
      positivity
    have hsum_real : (7200 * negDE₂ z * G z + 640 * H₂ z * F z).im = 0 := by
      simp only [Complex.add_im, Complex.mul_im, hnegDE₂_real, hG_real, hH₂_real, hF_real]
      ring
    rw [Complex.mul_re, hΔ_real, hsum_real, mul_zero, sub_zero]
    exact mul_pos hΔ_pos hsum_pos

/-!
## Section 3: Large-t Positivity of L₁,₀

Using Lemma 8.11 (vanishing orders), we show L₁,₀(it) > 0 for large t.
-/

/-- Summability of (m+1)^k * exp(-2πm) via comparison with shifted sum. -/
lemma summable_pow_shift (k : ℕ) : Summable fun m : ℕ => (m + 1 : ℝ) ^ k * rexp (-2 * π * m) := by
  have h := Real.summable_pow_mul_exp_neg_nat_mul k (by positivity : 0 < 2 * π)
  have h_eq : ∀ m : ℕ, (m + 1 : ℝ) ^ k * rexp (-2 * π * m) =
      rexp (2 * π) * ((m + 1) ^ k * rexp (-2 * π * (m + 1))) := fun m => by
    have : rexp (-2 * π * m) = rexp (2 * π) * rexp (-2 * π * (m + 1)) := by
      rw [← Real.exp_add]
      ring_nf
    rw [this]
    ring
  simp_rw [h_eq]
  apply Summable.mul_left
  convert h.comp_injective Nat.succ_injective using 1
  ext m
  simp [Function.comp_apply, Nat.succ_eq_add_one]

/-- Derivative bounds for q-expansion coefficients.
Given `‖a n‖ ≤ n^k`, produces bounds `‖a n * 2πin * exp(2πin z)‖ ≤ 2π * n^(k+1) * exp(-2πn * y_min)`
on compact K ⊆ {z : 0 < z.im}. This is a key hypothesis for `D_qexp_tsum_pnat`. -/
lemma qexp_deriv_bound_of_coeff_bound {a : ℕ+ → ℂ} {k : ℕ} (ha : ∀ n : ℕ+, ‖a n‖ ≤ (n : ℝ)^k) :
    ∀ K : Set ℂ, K ⊆ {w : ℂ | 0 < w.im} → IsCompact K →
      ∃ u : ℕ+ → ℝ, Summable u ∧ ∀ (n : ℕ+) (z : K),
        ‖a n * (2 * π * I * ↑n) * cexp (2 * π * I * ↑n * z.1)‖ ≤ u n := by
  intro K hK_sub hK_compact
  by_cases hK_nonempty : K.Nonempty
  · obtain ⟨k_min, hk_min_mem, hk_min_le⟩ := hK_compact.exists_isMinOn hK_nonempty
      Complex.continuous_im.continuousOn
    have hy_min_pos : 0 < k_min.im := hK_sub hk_min_mem
    have hpos : 0 < 2 * π * k_min.im := by nlinarith [pi_pos]
    have h := Real.summable_pow_mul_exp_neg_nat_mul (k + 1) hpos
    have hconv : Summable (fun n : ℕ+ =>
        2 * π * ((n : ℕ) : ℝ)^(k + 1) * rexp (-(2 * π * k_min.im) * (n : ℕ))) := by
      have : Summable (fun n : ℕ+ =>
          ((n : ℕ) : ℝ)^(k + 1) * rexp (-(2 * π * k_min.im) * (n : ℕ))) := h.subtype _
      convert this.mul_left (2 * π) using 1
      ext n; ring
    use fun n => 2 * π * (n : ℝ)^(k + 1) * rexp (-2 * π * ↑n * k_min.im)
    constructor
    · apply hconv.of_nonneg_of_le
      · intro n; positivity
      · intro n
        have h1 : -2 * π * ↑↑n * k_min.im = -(2 * π * k_min.im) * ↑↑n := by ring
        simp only [h1]; exact le_refl _
    · intro n ⟨z, hz_mem⟩
      have hz_im : k_min.im ≤ z.im := hk_min_le hz_mem
      have hn_pos : (0 : ℝ) < n := by exact_mod_cast n.pos
      have h_norm_2pin : ‖(2 : ℂ) * π * I * ↑↑n‖ = 2 * π * n := by
        rw [norm_mul, norm_mul, norm_mul, Complex.norm_ofNat, Complex.norm_real,
            Complex.norm_I, mul_one, Complex.norm_natCast, Real.norm_of_nonneg pi_pos.le]
      calc ‖a n * (2 * π * I * ↑↑n) * cexp (2 * π * I * ↑↑n * z)‖
          = ‖a n‖ * ‖(2 * π * I * ↑↑n)‖ * ‖cexp (2 * π * I * ↑↑n * z)‖ := by
            rw [norm_mul, norm_mul]
        _ ≤ (n : ℝ)^k * (2 * π * n) * rexp (-2 * π * n * z.im) := by
            rw [h_norm_2pin]
            have hexp : ‖cexp (2 * π * I * ↑↑n * z)‖ ≤ rexp (-2 * π * n * z.im) := by
              rw [Complex.norm_exp]
              have : (2 * π * I * ↑↑n * z).re = -2 * π * n * z.im := by
                simp only [Complex.mul_re, Complex.mul_im, Complex.ofReal_re, Complex.ofReal_im,
                  Complex.I_re, Complex.I_im, Complex.natCast_re, Complex.natCast_im,
                  mul_zero, mul_one, zero_add, add_zero, sub_zero]; ring
              rw [this]
            gcongr; exact ha n
        _ ≤ (n : ℝ)^k * (2 * π * n) * rexp (-2 * π * n * k_min.im) := by
            apply mul_le_mul_of_nonneg_left _ (by positivity)
            apply Real.exp_le_exp_of_le
            apply mul_le_mul_of_nonpos_left hz_im
            nlinarith [pi_pos, hn_pos]
        _ = 2 * π * (n : ℝ)^(k + 1) * rexp (-2 * π * n * k_min.im) := by ring
  · use fun _ => 0
    constructor
    · exact summable_zero
    · intro n ⟨z, hz_mem⟩
      exfalso; exact hK_nonempty ⟨z, hz_mem⟩

/-- (E₂E₄ - E₆) / q → 720 as im(z) → ∞.
This is used in both F_vanishing_order and D_F_div_F_tendsto. -/
lemma E₂E₄_sub_E₆_div_q_tendsto :
    Filter.Tendsto (fun z : ℍ => (E₂ z * E₄ z - E₆ z) / cexp (2 * π * I * z))
      atImInfty (nhds (720 : ℂ)) := by
  have h_rw : ∀ z : ℍ, E₂ z * E₄ z - E₆ z =
      720 * ∑' n : ℕ+, ↑n * ↑(ArithmeticFunction.sigma 3 n) *
        cexp (2 * π * Complex.I * n * z) := E₂_mul_E₄_sub_E₆
  have h_eq : ∀ z : ℍ,
      (E₂ z * E₄ z - E₆ z) / cexp (2 * π * Complex.I * z) =
      720 * (∑' n : ℕ+, ↑n * ↑(ArithmeticFunction.sigma 3 n) *
        cexp (2 * π * Complex.I * (n - 1) * z)) := by
    intro z
    rw [h_rw z, mul_div_assoc, ← tsum_div_const]
    congr 1; apply tsum_congr; intro n
    rw [mul_div_assoc, ← Complex.exp_sub]; congr 2; ring
  simp_rw [h_eq, sigma3_qexp_reindex_pnat_nat]
  set a : ℕ → ℂ := fun m => ↑(m + 1) * ↑(ArithmeticFunction.sigma 3 (m + 1)) with ha
  have ha0 : a 0 = 1 := by simp [ha, ArithmeticFunction.sigma_one]
  have h_tendsto : Filter.Tendsto
      (fun z : ℍ => ∑' m : ℕ, a m * cexp (2 * π * Complex.I * z * m))
      atImInfty (nhds (a 0)) := by
    apply QExp.tendsto_nat a
    have hbound : ∀ m : ℕ, ‖a m‖ ≤ ((m + 1 : ℕ) : ℝ) ^ 5 := by
      intro m
      simp only [ha, norm_mul, Complex.norm_natCast]
      have h1 : (ArithmeticFunction.sigma 3 (m + 1) : ℝ) ≤ ((m + 1 : ℕ) : ℝ) ^ 4 := by
        exact_mod_cast (sigma_bound 3 (m + 1))
      calc (↑(m + 1) : ℝ) * (ArithmeticFunction.sigma 3 (m + 1) : ℝ)
          ≤ (↑(m + 1) : ℝ) * (↑(m + 1) : ℝ) ^ 4 :=
            mul_le_mul_of_nonneg_left h1 (Nat.cast_nonneg _)
        _ = (↑(m + 1) : ℝ) ^ 5 := by ring
    apply Summable.of_nonneg_of_le
    · intro m; positivity
    · intro m
      calc ‖a m‖ * rexp (-2 * π * m)
          ≤ ((m + 1 : ℕ) : ℝ) ^ 5 * rexp (-2 * π * m) :=
            mul_le_mul_of_nonneg_right (hbound m) (Real.exp_nonneg _)
        _ = (m + 1 : ℝ) ^ 5 * rexp (-2 * π * m) := by simp
    · exact summable_pow_shift 5
  have h_eq2 : ∀ z : ℍ,
      ∑' m : ℕ, ↑(m + 1) * ↑(ArithmeticFunction.sigma 3 (m + 1)) *
        cexp (2 * π * Complex.I * m * z) =
      ∑' m : ℕ, a m * cexp (2 * π * Complex.I * z * m) := by
    intro z; apply tsum_congr; intro m; simp only [ha]; ring_nf
  simp_rw [h_eq2, ha0] at h_tendsto ⊢
  convert h_tendsto.const_mul (720 : ℂ) using 2; ring

/--
Helper lemma: `Θ₂(z) / exp(πiz/4) → 2` as `im(z) → ∞`.
This follows from `Θ₂ = exp(πiz/4) * jacobiTheta₂(z/2, z)` and `jacobiTheta₂(z/2, z) → 2`.
-/
theorem Θ₂_div_exp_tendsto :
    Filter.Tendsto (fun z : ℍ => Θ₂ z / cexp (π * Complex.I * z / 4))
      atImInfty (nhds (2 : ℂ)) := by
  convert jacobiTheta₂_half_mul_apply_tendsto_atImInfty using 1
  ext z
  rw [Θ₂_as_jacobiTheta₂]
  field_simp [Complex.exp_ne_zero]

/--
Helper lemma: `H₂(z) / exp(πiz) → 16` as `im(z) → ∞`.
Since `H₂ = Θ₂⁴` and `Θ₂ / exp(πiz/4) → 2`, we get `H₂ / exp(πiz) → 2⁴ = 16`.
-/
theorem H₂_div_exp_tendsto :
    Filter.Tendsto (fun z : ℍ => H₂ z / cexp (π * Complex.I * z))
      atImInfty (nhds (16 : ℂ)) := by
  have h_eq : ∀ z : ℍ, H₂ z / cexp (π * I * z) = (Θ₂ z / cexp (π * I * z / 4)) ^ 4 := fun z => by
    simp only [H₂, div_pow, ← Complex.exp_nat_mul]; congr 2; ring
  simp_rw [h_eq]; convert Θ₂_div_exp_tendsto.pow 4; norm_num

/--
The vanishing order of F at infinity is 2.
Blueprint: From q-expansion F = 720² * q² * (1 + O(q)), so F / q² → 720² as im(z) → ∞.
Here q = exp(2πiz), so q² = exp(4πiz) = exp(2πi * 2 * z).
-/
theorem F_vanishing_order :
    Filter.Tendsto (fun z : ℍ => F z / cexp (2 * π * Complex.I * 2 * z))
      atImInfty (nhds (720 ^ 2 : ℂ)) := by
  -- F = (E₂E₄ - E₆)² and we want to show F / q² → 720² where q = exp(2πiz)
  -- F = (E₂E₄ - E₆)², so F/q² = ((E₂E₄ - E₆)/q)² → 720²
  have h_exp_eq : ∀ z : ℍ, cexp (2 * π * I * 2 * z) = cexp (2 * π * I * z) ^ 2 := by
    intro z; rw [← Complex.exp_nat_mul]; congr 1; ring
  have h_F_eq : ∀ z : ℍ, F z / cexp (2 * π * I * 2 * z) =
      ((E₂ z * E₄ z - E₆ z) / cexp (2 * π * I * z)) ^ 2 := by
    intro z
    simp only [F, h_exp_eq, sq, div_mul_div_comm, Pi.mul_apply, Pi.sub_apply,
      ModularForm.toFun_eq_coe]
  simp_rw [h_F_eq]
  exact E₂E₄_sub_E₆_div_q_tendsto.pow 2

/-- D(E₂E₄ - E₆) equals 720 times the q-expansion with n²·σ₃(n) coefficients.

This is key for the log-derivative limit: `(D F)/F → 2` as `z → i∞`,
since F has vanishing order 2 (F ~ c·q²).

TODO: The proof requires:
1. From E₂_mul_E₄_sub_E₆: E₂E₄ - E₆ = 720 * ∑' n·σ₃(n)·qⁿ
2. Apply D linearity: D(720 * ∑') = 720 * D(∑')
3. Apply D_qexp_tsum_pnat with a(n) = n·σ₃(n):
   - D(∑' a(n)·qⁿ) = ∑' n·a(n)·qⁿ = ∑' n²·σ₃(n)·qⁿ

Technical requirements for D_qexp_tsum_pnat:
- Summability: n·σ₃(n) ≤ n⁵ (since σ₃(n) ≤ n⁴ by sigma_bound)
  so ‖n·σ₃(n)·qⁿ‖ ≤ n⁵ * exp(-2πn·y) is summable via a33 with k=5
- Derivative bound: ‖n·σ₃(n)·n·qⁿ‖ ≤ n⁶ * exp(-2πn·y_min) on compact K ⊂ ℍ
  is summable via Real.summable_pow_mul_exp_neg_nat_mul

Note: This depends on E₂_mul_E₄_sub_E₆ from Derivative.lean (which uses D_E₄_eq_tsum).
-/
theorem D_diff_qexp (z : ℍ) :
    D (fun w => E₂ w * E₄ w - E₆ w) z =
      720 * ∑' n : ℕ+, (↑↑n : ℂ) ^ 2 * ↑((ArithmeticFunction.sigma 3) ↑n) *
        cexp (2 * ↑Real.pi * Complex.I * ↑n * z) := by
  -- Step 1: Rewrite using E₂_mul_E₄_sub_E₆
  have h_eq : ∀ w : ℍ, E₂ w * E₄ w - E₆ w =
      720 * ∑' (n : ℕ+), ↑n * ↑(σ 3 n) * cexp (2 * π * I * ↑n * w) := E₂_mul_E₄_sub_E₆
  -- Step 2: Define coefficient function a(n) = n * σ₃(n)
  let a : ℕ+ → ℂ := fun n => ↑n * ↑(σ 3 n)
  -- Helper: ‖a n‖ ≤ n⁵ (used in both hsum and hsum_deriv)
  have norm_a_le : ∀ n : ℕ+, ‖a n‖ ≤ (n : ℝ)^5 := fun n => by
    simp only [a, Complex.norm_mul, Complex.norm_natCast]
    calc (n : ℝ) * ↑(σ 3 ↑n) ≤ (n : ℝ) * (n : ℝ)^4 := by
           gcongr; exact_mod_cast sigma_bound 3 n
       _ = (n : ℝ)^5 := by ring
  -- Step 3: Summability of a(n) * q^n using sigma_qexp_summable_generic
  have hsum : Summable (fun n : ℕ+ => a n * cexp (2 * π * I * ↑n * ↑z)) := by
    simpa [pow_one] using sigma_qexp_summable_generic 1 3 z
  -- Step 4: Derivative bounds using the extracted helper
  have hsum_deriv := qexp_deriv_bound_of_coeff_bound norm_a_le
  -- Step 5: Apply D_qexp_tsum_pnat with b(n) = 720 * a(n) = 720 * n * σ₃(n)
  -- This avoids needing D_const_mul and MDifferentiable for the tsum
  let b : ℕ+ → ℂ := fun n => 720 * (↑n * ↑(σ 3 n))
  have h_eq' : ∀ w : ℍ, E₂ w * E₄ w - E₆ w = ∑' (n : ℕ+), b n * cexp (2 * π * I * ↑n * w) :=
    fun w => by rw [h_eq]; simp only [b, ← tsum_mul_left]; congr 1; funext n; ring
  have hsum' : Summable (fun n : ℕ+ => b n * cexp (2 * π * I * ↑n * ↑z)) := by
    convert hsum.mul_left 720 using 1; funext n; simp only [b]; ring
  have hsum_deriv' : ∀ K : Set ℂ, K ⊆ {w : ℂ | 0 < w.im} → IsCompact K →
      ∃ u : ℕ+ → ℝ, Summable u ∧ ∀ (n : ℕ+) (k : K), ‖b n * (2 * π * I * ↑n) *
        cexp (2 * π * I * ↑n * k.1)‖ ≤ u n := by
    intro K hK_sub hK_compact
    obtain ⟨u, hu_sum, hu_bound⟩ := hsum_deriv K hK_sub hK_compact
    refine ⟨fun n => 720 * u n, hu_sum.mul_left 720, fun n k => ?_⟩
    calc ‖b n * (2 * π * I * ↑n) * cexp (2 * π * I * ↑n * k.1)‖
        = 720 * ‖a n * (2 * π * I * ↑n) * cexp (2 * π * I * ↑n * k.1)‖ := by
          simp only [b, a, norm_mul, Complex.norm_ofNat]; ring
      _ ≤ 720 * u n := mul_le_mul_of_nonneg_left (hu_bound n k) (by norm_num)
  have hD := D_qexp_tsum_pnat b z hsum' hsum_deriv'
  calc D (fun w => E₂ w * E₄ w - E₆ w) z
      = D (fun w => ∑' (n : ℕ+), b n * cexp (2 * π * I * ↑n * w)) z := by
        congr 1; ext w; exact h_eq' w
    _ = ∑' (n : ℕ+), (n : ℂ) * b n * cexp (2 * π * I * ↑n * z) := hD
    _ = 720 * ∑' (n : ℕ+), (n : ℂ) ^ 2 * ↑(σ 3 n) * cexp (2 * π * I * ↑n * z) := by
        simp only [b, ← tsum_mul_left, sq]; congr 1; funext n; ring

-- Helper: D(E₂E₄ - E₆) / q → 720 (same pattern as f/q → 720)
-- This follows from D acting as q·d/dq on q-expansions, so D(n·σ₃(n)·qⁿ) = n²·σ₃(n)·qⁿ
-- and the leading coefficient 1²·σ₃(1) = 1 gives the limit 720·1 = 720
theorem D_diff_div_q_tendsto :
    Filter.Tendsto (fun z : ℍ => D (fun w => E₂ w * E₄ w - E₆ w) z /
      cexp (2 * π * Complex.I * z))
      atImInfty (nhds (720 : ℂ)) := by
  -- Use D_diff_qexp and the QExp.tendsto_nat pattern
  -- D(f) = 720 * ∑ n² * σ₃(n) * q^n
  -- D(f)/q = 720 * ∑ n² * σ₃(n) * q^(n-1)
  -- Leading term (n=1): 1² * σ₃(1) = 1, so limit is 720 * 1 = 720
  have h_rw : ∀ z : ℍ, D (fun w => E₂ w * E₄ w - E₆ w) z =
      720 * ∑' n : ℕ+, (↑↑n : ℂ) ^ 2 * ↑((ArithmeticFunction.sigma 3) ↑n) *
        cexp (2 * ↑Real.pi * Complex.I * ↑n * z) := D_diff_qexp
  simp_rw [h_rw]
  -- Divide by q and reindex
  have h_eq : ∀ z : ℍ,
      (720 * ∑' n : ℕ+, (↑↑n : ℂ) ^ 2 * ↑((ArithmeticFunction.sigma 3) ↑n) *
        cexp (2 * ↑Real.pi * Complex.I * ↑n * z)) / cexp (2 * π * I * z) =
      720 * (∑' n : ℕ+, (↑↑n : ℂ) ^ 2 * ↑((ArithmeticFunction.sigma 3) ↑n) *
        cexp (2 * π * I * (↑n - 1) * z)) := by
    intro z
    rw [mul_div_assoc, ← tsum_div_const]
    congr 1; apply tsum_congr; intro n
    rw [mul_div_assoc, ← Complex.exp_sub]
    congr 2; ring
  simp_rw [h_eq]
  -- Reindex ℕ+ to ℕ via n ↦ m+1
  have h_reindex : ∀ z : ℍ,
      ∑' n : ℕ+, (↑↑n : ℂ) ^ 2 * ↑((ArithmeticFunction.sigma 3) ↑n) *
        cexp (2 * π * I * (↑n - 1) * z) =
      ∑' m : ℕ, (↑(m + 1) : ℂ) ^ 2 * ↑((ArithmeticFunction.sigma 3) (m + 1)) *
        cexp (2 * π * I * m * z) := by
    intro z
    rw [← Equiv.tsum_eq (Equiv.pnatEquivNat)]
    apply tsum_congr; intro m
    simp only [Equiv.pnatEquivNat_apply, PNat.natPred_add_one]
    congr 2
    simp only [← PNat.natPred_add_one m, Nat.cast_add, Nat.cast_one, add_sub_cancel_right]
  simp_rw [h_reindex]
  -- Apply QExp.tendsto_nat with coefficient function a(m) = (m+1)² * σ₃(m+1)
  set a : ℕ → ℂ := fun m => (↑(m + 1) : ℂ) ^ 2 * ↑((ArithmeticFunction.sigma 3) (m + 1)) with ha_def
  have ha0 : a 0 = 1 := by simp [ha_def, ArithmeticFunction.sigma_one]
  have h_tendsto : Filter.Tendsto
      (fun z : ℍ => ∑' m : ℕ, a m * cexp (2 * π * I * z * m))
      atImInfty (nhds (a 0)) := by
    apply QExp.tendsto_nat a
    -- Summability: ‖a m‖ ≤ (m+1)^6, and (m+1)^6 * exp(-2πm) is summable
    have hbound : ∀ m : ℕ, ‖a m‖ ≤ ((m + 1 : ℕ) : ℝ) ^ 6 := by
      intro m
      simp only [ha_def, norm_mul, Complex.norm_natCast, Complex.norm_pow]
      have h1 : (ArithmeticFunction.sigma 3 (m + 1) : ℝ) ≤ ((m + 1 : ℕ) : ℝ) ^ 4 := by
        exact_mod_cast (sigma_bound 3 (m + 1))
      calc (↑(m + 1) : ℝ) ^ 2 * (ArithmeticFunction.sigma 3 (m + 1) : ℝ)
          ≤ (↑(m + 1) : ℝ) ^ 2 * (↑(m + 1) : ℝ) ^ 4 :=
            mul_le_mul_of_nonneg_left h1 (pow_nonneg (Nat.cast_nonneg _) _)
        _ = (↑(m + 1) : ℝ) ^ 6 := by ring
    apply Summable.of_nonneg_of_le
    · intro m; positivity
    · intro m
      calc ‖a m‖ * rexp (-2 * π * m)
          ≤ ((m + 1 : ℕ) : ℝ) ^ 6 * rexp (-2 * π * m) :=
            mul_le_mul_of_nonneg_right (hbound m) (Real.exp_nonneg _)
        _ = (m + 1 : ℝ) ^ 6 * rexp (-2 * π * m) := by simp
    · exact summable_pow_shift 6
  have h_eq2 : ∀ z : ℍ,
      ∑' m : ℕ, (↑(m + 1) : ℂ) ^ 2 * ↑((ArithmeticFunction.sigma 3) (m + 1)) *
        cexp (2 * π * I * m * z) =
      ∑' m : ℕ, a m * cexp (2 * π * I * z * m) := by
    intro z; apply tsum_congr; intro m; simp only [ha_def]; ring_nf
  simp_rw [h_eq2, ha0] at h_tendsto ⊢
  convert h_tendsto.const_mul (720 : ℂ) using 2; ring

theorem D_F_div_F_tendsto :
    Filter.Tendsto (fun z : ℍ => D F z / F z) atImInfty (nhds (2 : ℂ)) := by
  -- F = (E₂E₄ - E₆)² = f² where f = E₂E₄ - E₆
  -- D(f²) = 2f·Df (chain rule), so DF/F = 2·Df/f
  -- f/q → 720 (from F_vanishing_order proof), and f has vanishing order 1
  -- Df/f → 1 (the vanishing order), so DF/F → 2

  -- Step 1: Define f and show F = f²
  set f : ℍ → ℂ := fun z => E₂ z * E₄.toFun z - E₆.toFun z with hf_def
  have hF_eq : ∀ z, F z = (f z) ^ 2 := fun z => by
    simp only [F, hf_def, sq, Pi.mul_apply, Pi.sub_apply, ModularForm.toFun_eq_coe]
  -- Step 2: f is holomorphic
  have hf_holo : MDifferentiable 𝓘(ℂ) 𝓘(ℂ) f := by
    apply MDifferentiable.sub
    · exact MDifferentiable.mul E₂_holo' E₄.holo'
    · exact E₆.holo'
  -- Step 3: D(F) = 2·f·D(f) by chain rule
  have hDF_eq : ∀ z, D F z = 2 * f z * D f z := fun z => by
    have hF_eq' : F = f ^ 2 := funext fun w => by simp [F, hf_def, sq]
    rw [hF_eq']
    exact congr_fun (D_sq f hf_holo) z
  -- Step 4: Therefore D(F)/F = 2·D(f)/f
  have hDF_div_eq : ∀ z, F z ≠ 0 → D F z / F z = 2 * (D f z / f z) := fun z hFz => by
    have hfz : f z ≠ 0 := fun h => hFz (by simp [hF_eq, h])
    rw [hDF_eq z, hF_eq z, sq]; field_simp [hfz]
  -- Step 5: f/q → 720 (use extracted helper after showing f z = E₂ z * E₄ z - E₆ z)
  have hf_div_q : Filter.Tendsto (fun z : ℍ => f z / cexp (2 * π * Complex.I * z))
      atImInfty (nhds (720 : ℂ)) :=
    E₂E₄_sub_E₆_div_q_tendsto.congr fun z => by simp only [hf_def, ModularForm.toFun_eq_coe]
  -- Step 6: D(f)/q → 720 (by D_diff_div_q_tendsto)
  have hDf_div_q : Filter.Tendsto (fun z : ℍ => D f z / cexp (2 * π * Complex.I * z))
      atImInfty (nhds (720 : ℂ)) := D_diff_div_q_tendsto
  -- Step 7: D(f)/f → 1 by dividing limits (720/720 = 1)
  have h_720_ne : (720 : ℂ) ≠ 0 := by norm_num
  have hDf_div_f : Filter.Tendsto (fun z : ℍ => D f z / f z) atImInfty (nhds 1) := by
    have h_eq : ∀ z : ℍ, D f z / f z = (D f z / cexp (2 * π * Complex.I * z)) /
        (f z / cexp (2 * π * Complex.I * z)) := fun z => by field_simp [Complex.exp_ne_zero]
    simp_rw [h_eq, show (1 : ℂ) = 720 / 720 from by norm_num]
    exact hDf_div_q.div hf_div_q h_720_ne
  -- Step 8: D(F)/F → 2·1 = 2
  have h_F_ne := eventually_ne_zero_of_tendsto_div (by norm_num : (720^2 : ℂ) ≠ 0) F_vanishing_order
  simpa using (hDf_div_f.const_mul (2 : ℂ)).congr' (by
    filter_upwards [h_F_ne] with z hFz; exact (hDF_div_eq z hFz).symm)

end MonotoneFG
