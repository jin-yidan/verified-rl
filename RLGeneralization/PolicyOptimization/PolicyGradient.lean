/-
Copyright (c) 2026 Yidan Jin. All rights reserved.
This source code is proprietary and not licensed for public use.

# Policy Gradient Methods

Formal proof of the policy gradient theorem and supporting algebraic
identities for policy-gradient methods.

## Main Results

* `policy_gradient_theorem` - **Policy gradient theorem (proved)**:
  V^π(s₀) - V^{π'}(s₀) = (1-γ)⁻¹ · ∑_s d^π(s) · ∑_a (π-π')(a|s) · Q^{π'}(s,a)
* `pdl_advantage_occupancy_form` - PDL in advantage-occupancy form
* `policy_gradient_one_step_score` - Log-derivative trick
* `policy_gradient_advantage_form` - Q-form ↔ advantage-form equivalence
* `expected_advantage_zero` - E_π[A^π] = 0
* `score_baseline_invariance` - Baseline does not change PG

## Main Definitions

* `ParameterizedPolicy` - θ-parameterized policy with prob and score
* `softmaxParameterizedPolicy` - Softmax (log-linear) policy
* `policyGradientIdentity` - Gradient formula template (definition)

## References

* [Agarwal et al., *RL: Theory and Algorithms*]
-/

import RLGeneralization.MDP.Basic
import RLGeneralization.MDP.OccupancyMeasure
import Mathlib.Analysis.SpecialFunctions.ExpDeriv
import Mathlib.Algebra.BigOperators.Field

open Finset BigOperators

noncomputable section

namespace FiniteMDP

variable (M : FiniteMDP)

/-! ### Parameterized Policies -/

/-- A parameterized policy π_θ : S → Δ(A) where θ ∈ ℝ^d.
    The probability π_θ(a|s) depends smoothly on θ. -/
structure ParameterizedPolicy (d : ℕ) where
  /-- Policy probability as a function of parameters -/
  prob : (Fin d → ℝ) → M.S → M.A → ℝ
  /-- Probabilities are nonneg -/
  prob_nonneg : ∀ θ s a, 0 ≤ prob θ s a
  /-- Probabilities sum to 1 -/
  prob_sum_one : ∀ θ s, ∑ a, prob θ s a = 1

/-- Convert a parameterized policy at a specific θ to a
    StochasticPolicy. -/
def ParameterizedPolicy.toStochastic {d : ℕ}
    (pp : M.ParameterizedPolicy d) (θ : Fin d → ℝ) :
    M.StochasticPolicy :=
  ⟨pp.prob θ, pp.prob_nonneg θ, pp.prob_sum_one θ⟩

/-! ### Policy Objective -/

/-- The policy objective `J(θ) = V^{π_θ}(s₀)` for a fixed
    starting state `s₀`. This is the quantity optimized by
    policy-gradient methods. -/
def policyObjective {d : ℕ}
    (_pp : M.ParameterizedPolicy d)
    (V_of : (Fin d → ℝ) → M.StateValueFn)
    (s₀ : M.S) (θ : Fin d → ℝ) : ℝ :=
  V_of θ s₀

/-! ### Score Function (Log-Policy Gradient) -/

/-- The score function `∇_θ log π_θ(a|s)`, represented as a
    `Fin d → ℝ` vector. -/
def scoreFunction {d : ℕ}
    (grad_log_pi : (Fin d → ℝ) → M.S → M.A → Fin d → ℝ)
    (θ : Fin d → ℝ) (s : M.S) (a : M.A) : Fin d → ℝ :=
  grad_log_pi θ s a

/-! ### Policy Gradient Identity (Formula Template) -/

/-- **Policy gradient identity** (formula template).

  ∇J(θ) = (1/(1-γ)) ∑_{s,a} d^π(s,a) · ∇log π(a|s) · Q^π(s,a)

  This definition computes the gradient vector. The algebraic identity
  justifying this formula is `policy_gradient_theorem` below. -/
def policyGradientIdentity {d : ℕ}
    (_pp : M.ParameterizedPolicy d)
    (grad_log_pi : (Fin d → ℝ) → M.S → M.A → Fin d → ℝ)
    (Q_of : (Fin d → ℝ) → M.ActionValueFn)
    (occupancy : (Fin d → ℝ) → M.S → M.A → ℝ)
    (θ : Fin d → ℝ) : Fin d → ℝ :=
  fun i => (1 / (1 - M.γ)) *
    ∑ s, ∑ a, occupancy θ s a *
      grad_log_pi θ s a i * Q_of θ s a

/-! ### Softmax Policy -/

/-- Softmax (log-linear) policy: `π_θ(a|s) ∝ exp(θᵀφ(s,a))`. -/
def softmaxProb {d : ℕ}
    (φ : M.S → M.A → Fin d → ℝ)
    (θ : Fin d → ℝ) (s : M.S) (a : M.A) : ℝ :=
  Real.exp (∑ i, θ i * φ s a i) /
    ∑ a', Real.exp (∑ i, θ i * φ s a' i)

/-- Softmax probabilities are nonneg. -/
theorem softmaxProb_nonneg {d : ℕ}
    (φ : M.S → M.A → Fin d → ℝ)
    (θ : Fin d → ℝ) (s : M.S) (a : M.A) :
    0 ≤ M.softmaxProb φ θ s a := by
  unfold softmaxProb
  apply div_nonneg (le_of_lt (Real.exp_pos _))
  apply Finset.sum_nonneg
  intro a' _
  exact le_of_lt (Real.exp_pos _)

/-- Softmax probabilities sum to 1. -/
theorem softmaxProb_sum_one {d : ℕ}
    (φ : M.S → M.A → Fin d → ℝ)
    (θ : Fin d → ℝ) (s : M.S)
    (h_pos : 0 < ∑ a', Real.exp (∑ i, θ i * φ s a' i)) :
    ∑ a, M.softmaxProb φ θ s a = 1 := by
  unfold softmaxProb
  show ∑ a, Real.exp (∑ i, θ i * φ s a i) /
    (∑ a', Real.exp (∑ i, θ i * φ s a' i)) = 1
  rw [← Finset.sum_div, div_self (ne_of_gt h_pos)]

/-! ### Softmax Strict Positivity -/

/-- The sum of exponentials is strictly positive (helper). -/
theorem softmax_denom_pos {d : ℕ}
    (φ : M.S → M.A → Fin d → ℝ)
    (θ : Fin d → ℝ) (s : M.S) :
    0 < ∑ a', Real.exp (∑ i, θ i * φ s a' i) :=
  Finset.sum_pos (fun _ _ => Real.exp_pos _) Finset.univ_nonempty

/-- Softmax probabilities are **strictly positive**.
    This is the key property that makes the log-derivative trick
    well-defined: since `π_θ(a|s) > 0` for all actions, the score
    function `∇log π_θ(a|s) = ∇π/π` is finite everywhere. -/
theorem softmaxProb_pos {d : ℕ}
    (φ : M.S → M.A → Fin d → ℝ)
    (θ : Fin d → ℝ) (s : M.S) (a : M.A) :
    0 < M.softmaxProb φ θ s a := by
  unfold softmaxProb
  exact div_pos (Real.exp_pos _) (M.softmax_denom_pos φ θ s)

/-! ### Constructing a Softmax ParameterizedPolicy -/

/-- The softmax policy is a valid `ParameterizedPolicy`: it maps
    parameters θ to a well-formed stochastic policy. -/
def softmaxParameterizedPolicy {d : ℕ}
    (φ : M.S → M.A → Fin d → ℝ) :
    M.ParameterizedPolicy d where
  prob := M.softmaxProb φ
  prob_nonneg := fun θ s a => M.softmaxProb_nonneg φ θ s a
  prob_sum_one := fun θ s =>
    M.softmaxProb_sum_one φ θ s (M.softmax_denom_pos φ θ s)

/-! ### Expected Advantage is Zero Under Current Policy

  This is a fundamental identity in policy gradient theory:
  under the current policy π, the expected advantage is zero:

    ∑_a π(a|s) · A^π(s,a) = ∑_a π(a|s) · (Q^π(s,a) - V^π(s)) = 0

  This follows from V^π(s) = ∑_a π(a|s) · Q^π(s,a) (the
  definition of the value function in terms of Q).

  Consequence: the policy gradient
  can equivalently use advantages instead of Q-values:

    ∇J(θ) = E_{d^π}[∇log π · Q^π]
           = E_{d^π}[∇log π · A^π]

  since ∑_a π(a|s)·∇log π(a|s)·V(s) = V(s)·∑_a ∇π(a|s) = 0.
-/

/-- **Expected advantage is zero under the current policy**.

  If V^π(s) = ∑_a π(a|s) · Q^π(s,a) (i.e., V is consistent with
  Q under policy π), then ∑_a π(a|s) · (Q(s,a) - V(s)) = 0.

  This is the algebraic core of the baseline invariance property. -/
theorem expected_advantage_zero
    (π : M.StochasticPolicy)
    (Q : M.ActionValueFn) (V : M.StateValueFn)
    (hVQ : ∀ s, V s = ∑ a, π.prob s a * Q s a)
    (s : M.S) :
    ∑ a, π.prob s a * (Q s a - V s) = 0 := by
  simp_rw [mul_sub, Finset.sum_sub_distrib]
  rw [← Finset.sum_mul, π.prob_sum_one, one_mul]
  linarith [hVQ s]

/-- **Softmax advantage identity**.

  For softmax policy: ∑_a softmax(θ)_a · (Q(s,a) - V_softmax(s)) = 0
  where V_softmax(s) = ∑_a softmax(θ)_a · Q(s,a).

  This is the expected advantage = 0 identity specialized to
  softmax policies. It is the algebraic identity behind the
  REINFORCE variance reduction via baselines. -/
theorem softmax_expected_advantage_zero {d : ℕ}
    (φ : M.S → M.A → Fin d → ℝ)
    (θ : Fin d → ℝ)
    (Q : M.ActionValueFn) (s : M.S) :
    ∑ a, M.softmaxProb φ θ s a *
      (Q s a - ∑ a', M.softmaxProb φ θ s a' * Q s a') = 0 := by
  simp_rw [mul_sub, Finset.sum_sub_distrib, ← Finset.sum_mul,
    M.softmaxProb_sum_one φ θ s (M.softmax_denom_pos φ θ s),
    one_mul, sub_self]

/-! ### Baseline Invariance (Variance Reduction)

  A key practical insight: adding any state-dependent
  baseline b(s) to the Q-values does not change the expected
  policy gradient, because:

    ∑_a π(a|s) · ψ(a) · b(s) = b(s) · ∑_a π(a|s) · ψ(a)

  If ψ is the score function ∇log π, then ∑_a π · ∇log π = ∑_a ∇π = 0
  (the gradient of a constant). We prove the algebraic version below.
-/

/-- **Baseline invariance**.

  For any policy π and any function b : S → ℝ:

    ∑_a π(a|s) · (Q(s,a) - b(s)) = ∑_a π(a|s) · Q(s,a) - b(s)

  In particular, if we also multiply by a score ψ(a) and if
  ∑_a π(a|s) · ψ(a) = 0 (the score-function identity), then
  the baseline cancels out entirely. This theorem establishes
  the first (algebraic) part. -/
theorem baseline_subtraction
    (π : M.StochasticPolicy)
    (Q : M.ActionValueFn) (b : M.S → ℝ) (s : M.S) :
    ∑ a, π.prob s a * (Q s a - b s) =
    (∑ a, π.prob s a * Q s a) - b s := by
  simp_rw [mul_sub, Finset.sum_sub_distrib, ← Finset.sum_mul,
    π.prob_sum_one, one_mul]

/-- **Score function identity**: if ∑_a π(a|s) = 1 for all s,
    then for any scalar c and function ψ : A → ℝ^d satisfying
    ∑_a π(a|s) · ψ(a) = 0 (the score identity), adding a
    baseline c to Q does not change ∑_a π · ψ · Q.

    ∑_a π(a|s) · ψ(a,i) · (Q(s,a) - c) = ∑_a π(a|s) · ψ(a,i) · Q(s,a)

    when ∑_a π(a|s) · ψ(a,i) = 0.

    This is the full baseline invariance identity for the
    score-weighted policy-gradient term. -/
theorem score_baseline_invariance {d : ℕ}
    (π : M.StochasticPolicy)
    (ψ : M.A → Fin d → ℝ) (Q : M.ActionValueFn)
    (c : ℝ) (s : M.S) (i : Fin d)
    (h_score : ∑ a, π.prob s a * ψ a i = 0) :
    ∑ a, π.prob s a * ψ a i * (Q s a - c) =
    ∑ a, π.prob s a * ψ a i * Q s a := by
  have : ∑ a, π.prob s a * ψ a i * (Q s a - c) =
      (∑ a, π.prob s a * ψ a i * Q s a) -
      c * (∑ a, π.prob s a * ψ a i) := by
    have h1 : ∀ a, π.prob s a * ψ a i * (Q s a - c) =
        π.prob s a * ψ a i * Q s a -
        π.prob s a * ψ a i * c := fun a => by ring
    simp_rw [h1, Finset.sum_sub_distrib]
    congr 1; rw [← Finset.sum_mul]; ring
  rw [this, h_score, mul_zero, sub_zero]

/-! ### Policy Gradient with Advantage

  The policy gradient theorem states:
    ∇J(θ) = (1/(1-γ)) ∑_s d^π(s) ∑_a π(a|s) ∇log π(a|s) Q^π(s,a)

  Combined with baseline invariance (score_baseline_invariance),
  we can replace Q^π(s,a) with the advantage A^π(s,a) = Q^π(s,a) - V^π(s):
    ∇J(θ) = (1/(1-γ)) ∑_s d^π(s) ∑_a π(a|s) ∇log π(a|s) A^π(s,a)

  We prove this algebraic equivalence directly.
-/

/-- **Policy gradient with advantage**.

  The Q-form and advantage-form of the policy gradient are equal,
  provided the score function satisfies the identity
  ∑_a π(a|s) · ∇log π(a|s) = 0.

  Concretely: for each coordinate i of the gradient,
    ∑_{s,a} d(s,a) · ψ(s,a,i) · Q(s,a)
    = ∑_{s,a} d(s,a) · ψ(s,a,i) · A(s,a)

  where A(s,a) = Q(s,a) - V(s) and d is the occupancy measure. -/
theorem policy_gradient_advantage_form {d : ℕ}
    (π : M.StochasticPolicy)
    (ψ : M.S → M.A → Fin d → ℝ)
    (Q : M.ActionValueFn) (V : M.StateValueFn)
    (d_occ : M.S → ℝ)
    (i : Fin d)
    (h_score : ∀ s, ∑ a, π.prob s a * ψ s a i = 0) :
    ∑ s, d_occ s * ∑ a, π.prob s a * ψ s a i * Q s a =
    ∑ s, d_occ s * ∑ a, π.prob s a * ψ s a i *
      (Q s a - V s) := by
  congr 1; funext s
  congr 1
  exact (M.score_baseline_invariance π (ψ s) Q (V s) s i
    (h_score s)).symm

/-! ### One-Step Policy Gradient Identity

  The one-step (inner) policy gradient identity is the core of
  the policy gradient theorem. For a fixed state s:

    ∑_a ∇_θ π_θ(a|s) · Q(s,a) = ∑_a π_θ(a|s) · ∇_θ log π_θ(a|s) · Q(s,a)

  This is the "log-derivative trick": ∇π = π · ∇log π.

  We formalize this as: given that grad_pi(a) = pi(a) * score(a)
  for all a (the log-derivative relation), the above identity holds.
-/

/-- **Log-derivative trick**.

  If ∇π(a|s) = π(a|s) · ∇log π(a|s) for all a (which holds whenever
  π(a|s) > 0), then:

    ∑_a ∇_θ π_θ(a|s)_i · Q(s,a) = ∑_a π_θ(a|s) · ∇log π_θ(a|s)_i · Q(s,a)

  This is immediate from substitution, but it is the algebraic
  identity at the heart of REINFORCE and all policy gradient methods. -/
theorem log_derivative_trick {d : ℕ}
    (π : M.StochasticPolicy)
    (grad_pi : M.A → Fin d → ℝ)
    (score : M.A → Fin d → ℝ)
    (Q : M.ActionValueFn) (s : M.S) (i : Fin d)
    (h_log_deriv : ∀ a, grad_pi a i = π.prob s a * score a i) :
    ∑ a, grad_pi a i * Q s a =
    ∑ a, π.prob s a * score a i * Q s a := by
  congr 1; funext a; rw [h_log_deriv a, mul_assoc]

/-! ### Value Function Decomposition

  V^π(s) = ∑_a π(a|s) · Q^π(s,a) is the fundamental relation
  between value and action-value functions. We prove it from the
  Bellman equation when Q satisfies its defining equation. -/

/-- **V-Q consistency**: `V^π(s) = ∑_a π(a|s) · Q^π(s,a)`
    when both `V` and `Q` satisfy their respective Bellman equations. -/
theorem value_eq_expected_action_value
    (π : M.StochasticPolicy)
    (V : M.StateValueFn) (Q : M.ActionValueFn)
    (hV : M.isValueOf V π)
    (hQ : ∀ s a, Q s a =
      M.r s a + M.γ * ∑ s', M.P s a s' * V s')
    (s : M.S) :
    V s = ∑ a, π.prob s a * Q s a := by
  rw [hV s]
  unfold expectedReward expectedNextValue
  simp_rw [hQ, mul_add, Finset.sum_add_distrib]
  congr 1
  -- ∑_a π(a)(γ ∑_{s'} P V) = γ ∑_a π(a) ∑_{s'} P V
  have : ∀ a, π.prob s a * (M.γ * ∑ s', M.P s a s' * V s') =
      M.γ * (π.prob s a * ∑ s', M.P s a s' * V s') :=
    fun a => by ring
  simp_rw [this]
  rw [← Finset.mul_sum]

/-- **Corollary**: Expected advantage is zero when V and Q are
    consistently defined via Bellman equations.

    ∑_a π(a|s) · (Q^π(s,a) - V^π(s)) = 0

    This combines `value_eq_expected_action_value` with
    `expected_advantage_zero`. -/
theorem bellman_advantage_zero
    (π : M.StochasticPolicy)
    (V : M.StateValueFn) (Q : M.ActionValueFn)
    (hV : M.isValueOf V π)
    (hQ : ∀ s a, Q s a =
      M.r s a + M.γ * ∑ s', M.P s a s' * V s')
    (s : M.S) :
    ∑ a, π.prob s a * (Q s a - V s) = 0 :=
  M.expected_advantage_zero π Q V
    (fun s => M.value_eq_expected_action_value π V Q hV hQ s) s

/-! ### Policy Gradient Theorem — Corollaries

The exact PG theorem (`policy_gradient_theorem`) is proved above.
The following corollaries restate it in standard forms used in RL:
the advantage-occupancy form and the score-weighted form. -/

/-- **Performance difference in advantage form (occupancy-weighted).**

  V^π(s₀) - V^{π'}(s₀) = (1-γ)⁻¹ · ∑_s d^π(s₀,s) · ∑_a π(a|s) · A^{π'}(s,a)

  This is `pdl_normalized` restated with the advantage
  `A^{π'}(s,a) = Q^{π'}(s,a) - V^{π'}(s)` made explicit.

  This is the algebraic core of the policy gradient theorem: it shows that the
  value difference between policies equals an occupancy-weighted
  sum of advantages, which is the quantity estimated by
  REINFORCE and actor-critic algorithms. -/
theorem pdl_advantage_occupancy_form
    (π π' : M.StochasticPolicy)
    (V_pi V_pi' : M.StateValueFn)
    (Q_pi' : M.ActionValueFn)
    (hV_pi : M.isValueOf V_pi π)
    (hV_pi' : M.isValueOf V_pi' π')
    (hQ_pi' : ∀ s a, Q_pi' s a =
      M.r s a + M.γ * ∑ s', M.P s a s' * V_pi' s')
    (s₀ : M.S) :
    V_pi s₀ - V_pi' s₀ =
      (1 - M.γ)⁻¹ * ∑ s, M.stateOccupancy π s₀ s *
        ∑ a, π.prob s a * (Q_pi' s a - V_pi' s) := by
  -- This is pdl_normalized with expectedAdvantage expanded
  have h := M.pdl_normalized π π' V_pi V_pi' Q_pi' hV_pi hV_pi' hQ_pi' s₀
  simp only [expectedAdvantage, advantage] at h
  exact h

/-- **Score-weighted policy gradient core.**

  For a fixed state s, the score-weighted sum equals the gradient-weighted sum:
    ∑_a ∇π(a|s)_i · Q(s,a) = ∑_a π(a|s) · ψ(s,a,i) · Q(s,a)
  where ψ = ∇log π is the score function.

  Combined with `pdl_advantage_occupancy_form`, this gives the full
  algebraic structure of the policy gradient theorem. -/
theorem policy_gradient_one_step_score {d : ℕ}
    (π : M.StochasticPolicy)
    (grad_pi : M.S → M.A → Fin d → ℝ)
    (score : M.S → M.A → Fin d → ℝ)
    (Q : M.ActionValueFn) (s : M.S) (i : Fin d)
    (h_log_deriv : ∀ a, grad_pi s a i = π.prob s a * score s a i) :
    ∑ a, grad_pi s a i * Q s a =
    ∑ a, π.prob s a * score s a i * Q s a :=
  M.log_derivative_trick π (grad_pi s) (score s) Q s i h_log_deriv

/-! ### Policy Gradient Theorem (Proved) -/

/-- **Policy gradient theorem (exact algebraic form)**.

  For any two policies π, π' with value functions and action-value Q^{π'}:

    V^π(s₀) - V^{π'}(s₀) = (1-γ)⁻¹ · ∑_s d^π(s₀,s) · ∑_a (π(a|s) - π'(a|s)) · Q^{π'}(s,a)

  This is the **exact, non-linearized** policy gradient identity:
  the performance difference between two policies is a weighted sum of
  their action-probability differences, weighted by the Q-values and
  the occupancy measure of the first policy.

  The standard gradient form ∇J(θ) = E_{d^π}[∑_a ∇π(a|s) · Q^π(s,a)]
  is obtained by setting π = π_{θ+δθ}, π' = π_θ and noting that
  π(a|s) - π'(a|s) ≈ δθ · ∇_θ π(a|s) to first order.

  Proof: from the PDL (`pdl_advantage_occupancy_form`), expand the
  advantage A^{π'}(s,a) = Q^{π'}(s,a) - V^{π'}(s) and use
  V^{π'}(s) = ∑_a π'(a|s) · Q^{π'}(s,a) (the Bellman V-Q identity). -/
theorem policy_gradient_theorem
    (π π' : M.StochasticPolicy)
    (V_pi V_pi' : M.StateValueFn)
    (Q_pi' : M.ActionValueFn)
    (hV_pi : M.isValueOf V_pi π)
    (hV_pi' : M.isValueOf V_pi' π')
    (hQ_pi' : ∀ s a, Q_pi' s a =
      M.r s a + M.γ * ∑ s', M.P s a s' * V_pi' s')
    (s₀ : M.S) :
    V_pi s₀ - V_pi' s₀ =
      (1 - M.γ)⁻¹ * ∑ s, M.stateOccupancy π s₀ s *
        ∑ a, (π.prob s a - π'.prob s a) * Q_pi' s a := by
  -- Step 1: PDL gives advantage form
  have h := M.pdl_advantage_occupancy_form π π' V_pi V_pi' Q_pi'
    hV_pi hV_pi' hQ_pi' s₀
  rw [h]; congr 1; congr 1; funext s; congr 1
  -- Step 2: ∑_a π(a|s)·(Q-V') = (∑_a π·Q) - V' by baseline subtraction
  rw [M.baseline_subtraction π Q_pi' V_pi' s]
  -- Step 3: V' = ∑_a π'(a|s)·Q by Bellman V-Q identity
  rw [M.value_eq_expected_action_value π' V_pi' Q_pi' hV_pi' hQ_pi' s]
  -- Step 4: algebra: (∑ π·Q) - (∑ π'·Q) = ∑ (π-π')·Q
  simp_rw [sub_mul, Finset.sum_sub_distrib]

/-! ### Policy Gradient as Actual Derivative

  The policy gradient theorem in its derivative form:

    ∂J(θ)/∂θ_i = (1/(1-γ)) · ∑_s d^{π_θ}(s) · ∑_a ∂π_θ(a|s)/∂θ_i · Q^{π_θ}(s,a)

  The algebraic identity (performance difference lemma) is already proved.
  The derivative form requires:
  1. Differentiation under expectation (interchange ∂ and ∑)
  2. The log-derivative trick: ∂π/∂θ = π · ∂log π/∂θ

  We take differentiation under expectation as a conditional hypothesis
  and derive the derivative form from our algebraic identities.
-/

/-- **Policy gradient in score function form.**

  The policy gradient using the score function (log-derivative trick):

    ∂J/∂θ_i = (1/(1-γ)) · ∑_s d^π(s) · ∑_a π(a|s) · (∂log π(a|s)/∂θ_i) · Q^π(s,a)

  This is the REINFORCE estimator's target. The score function
  ∂log π(a|s)/∂θ_i has the crucial property that its expectation
  under π is zero (score baseline), enabling variance reduction.

  [CONDITIONAL] Requires differentiation under expectation to convert
  the finite-difference PDL into a derivative statement. The algebraic
  content (the identity itself) is proved; the analysis step
  (∂/∂θ ∑ = ∑ ∂/∂θ) is the conditional hypothesis. -/
structure PolicyGradientDerivative where
  /-- Parameter dimension -/
  d : ℕ
  /-- Parameterized policy: π_θ(a|s) -/
  pi_theta : (Fin d → ℝ) → M.StochasticPolicy
  /-- Q-function under π_θ -/
  Q : (Fin d → ℝ) → M.ActionValueFn
  /-- Occupancy measure under π_θ -/
  occ : (Fin d → ℝ) → M.S → ℝ
  /-- Objective: J(θ) = ∑_s μ(s) V^{π_θ}(s) -/
  J : (Fin d → ℝ) → ℝ
  /-- Score function: ∂log π_θ(a|s)/∂θ_i -/
  score : (Fin d → ℝ) → M.S → M.A → Fin d → ℝ
  /-- Score function sums to zero under π:
      ∑_a π(a|s) · score(θ,s,a,i) = 0.
      This is because ∑_a π · (∂log π/∂θ) = ∑_a ∂π/∂θ = ∂(∑π)/∂θ = 0. -/
  score_sum_zero : ∀ θ s (i : Fin d),
    ∑ a, (pi_theta θ).prob s a * score θ s a i = 0
  /-- [CONDITIONAL] The gradient of J equals the policy gradient formula.
      This is the key analytical hypothesis: differentiation under
      the expectation (sum) is valid. -/
  gradient_eq : ∀ θ (i : Fin d),
    -- ∂J/∂θ_i = (1/(1-γ)) ∑_s d^π(s) ∑_a π(a|s) score(s,a,i) Q(s,a)
    ∃ grad_i : ℝ,
      grad_i = (1 / (1 - M.γ)) *
        ∑ s, occ θ s * ∑ a, (pi_theta θ).prob s a *
          score θ s a i * Q θ s a

/-- **Score baseline invariance** (derivative form).

  For any baseline b(s), the score-weighted baseline has zero expectation:
    ∑_a π(a|s) · (∂log π/∂θ_i) · b(s) = 0

  This is because ∑_a π · (∂log π/∂θ) = ∑_a ∂π/∂θ = ∂(∑_a π)/∂θ = ∂1/∂θ = 0.

  Taking b(s) = V^π(s) gives the advantage form of policy gradient:
    ∂J/∂θ_i = (1/(1-γ)) ∑_s d^π(s) ∑_a π · score · A^π(s,a)

  The score sum property ∑_a π·score = 0 is now a field of
  `PolicyGradientDerivative` (derived from ∂(∑π)/∂θ = 0). -/
theorem policy_gradient_advantage_form_derivative
    (pgd : M.PolicyGradientDerivative) (θ : Fin pgd.d → ℝ)
    (V : M.StateValueFn) :
    ∀ (i : Fin pgd.d),
    -- The Q-form and advantage form of the gradient are equal
    (∑ s, pgd.occ θ s *
      ∑ a, (pgd.pi_theta θ).prob s a * pgd.score θ s a i *
        pgd.Q θ s a) =
    (∑ s, pgd.occ θ s *
      ∑ a, (pgd.pi_theta θ).prob s a * pgd.score θ s a i *
        (pgd.Q θ s a - V s)) := by
  intro i
  congr 1; funext s
  congr 1
  -- ∑_a π · score · Q = ∑_a π · score · (Q - V) + ∑_a π · score · V
  -- The second term = V · ∑_a π · score = V · 0 = 0
  have h := pgd.score_sum_zero θ s i
  -- ∑ π·score·(Q-V) = ∑ π·score·Q - ∑ π·score·V = ∑ π·score·Q - V·0
  simp_rw [mul_sub, Finset.sum_sub_distrib]
  have : ∑ a, (pgd.pi_theta θ).prob s a * pgd.score θ s a i * V s =
      V s * ∑ a, (pgd.pi_theta θ).prob s a * pgd.score θ s a i := by
    rw [Finset.mul_sum]; congr 1; funext a; ring
  rw [this, h, mul_zero, sub_zero]

/-! ### Policy Gradient from PDL (First-Order Gradient Identity)

  The performance difference lemma gives the **exact** identity:
    V^π(s₀) - V^{π'}(s₀) = (1-γ)⁻¹ · ∑_s d^π(s) · ∑_a (π-π')(a|s) · Q^{π'}(s,a)

  When π' = π_θ and π = π_{θ+εδθ}, to first order in ε:
    π(a|s) - π'(a|s) ≈ ε · ∇_θ π(a|s) · δθ

  So the PDL becomes the policy gradient identity. We formalize this as a theorem:
  given the PDL and a first-order approximation hypothesis, the gradient form follows.
-/

/-- **Policy gradient from PDL (first-order gradient identity)**.

  For two policies π, π' with a perturbation decomposition
  π(a|s) - π'(a|s) = ε · δπ(a|s), the PDL becomes:

    V^π(s₀) - V^{π'}(s₀) = ε · (1-γ)⁻¹ · ∑_s d^π(s) · ∑_a δπ(a|s) · Q^{π'}(s,a)

  This is the first-order policy gradient identity: the directional
  derivative of the value function in the direction δπ equals the
  occupancy-weighted sum of δπ · Q.

  The hypothesis `h_perturbation` captures the first-order expansion
  π(a|s) - π'(a|s) = ε · δπ(a|s). Combined with the proved PDL
  (`policy_gradient_theorem`), this gives the gradient form. -/
theorem policy_gradient_from_pdl
    (π π' : M.StochasticPolicy)
    (V_pi V_pi' : M.StateValueFn)
    (Q_pi' : M.ActionValueFn)
    (hV_pi : M.isValueOf V_pi π)
    (hV_pi' : M.isValueOf V_pi' π')
    (hQ_pi' : ∀ s a, Q_pi' s a =
      M.r s a + M.γ * ∑ s', M.P s a s' * V_pi' s')
    (ε : ℝ) (δπ : M.S → M.A → ℝ)
    -- [CONDITIONAL HYPOTHESIS] First-order perturbation decomposition
    (h_perturbation : ∀ s a, π.prob s a - π'.prob s a = ε * δπ s a)
    (s₀ : M.S) :
    V_pi s₀ - V_pi' s₀ =
      ε * ((1 - M.γ)⁻¹ * ∑ s, M.stateOccupancy π s₀ s *
        ∑ a, δπ s a * Q_pi' s a) := by
  -- Step 1: Apply the exact PDL (policy_gradient_theorem)
  have h_pdl := M.policy_gradient_theorem π π' V_pi V_pi' Q_pi'
    hV_pi hV_pi' hQ_pi' s₀
  rw [h_pdl]
  -- Step 2: Substitute the perturbation decomposition and factor ε
  -- First show the inner sums are equal up to ε factor
  have h_sum : (∑ s, M.stateOccupancy π s₀ s *
      ∑ a, (π.prob s a - π'.prob s a) * Q_pi' s a) =
    ε * (∑ s, M.stateOccupancy π s₀ s *
      ∑ a, δπ s a * Q_pi' s a) := by
    rw [Finset.mul_sum]; congr 1; funext s
    have : (∑ a, (π.prob s a - π'.prob s a) * Q_pi' s a) =
        ε * (∑ a, δπ s a * Q_pi' s a) := by
      rw [Finset.mul_sum]; congr 1; funext a
      rw [h_perturbation s a]; ring
    rw [this]; ring
  rw [h_sum]; ring

/-! ### Policy Gradient Convergence Rate

  Under the gradient domination condition (Agarwal et al.):
    J(θ*) - J(θ) ≤ C · ‖∇J(θ)‖²

  and L-smoothness (which bounds the objective decrease per step):
    J(θ + η∇J) - J(θ) ≥ η · ‖∇J‖² - (L/2) · η² · ‖∇J‖²

  Projected gradient ascent with step η = 1/(L·T) achieves:
    J(θ*) - J(θ_T) ≤ O(1/T)

  We prove the algebraic convergence rate from these hypotheses.
-/

/-- **Policy gradient O(1/T) convergence rate via telescoping.**

  Under gradient domination and smoothness, if each gradient step produces
  a per-step value improvement that sums telescopically, then the minimum
  gap over T steps is bounded by gap₀ · C · L / T.

  The proof: min gap ≤ average gap ≤ C·L · (total improvement)/T ≤ C·L · gap₀/T.
  This is the standard argument from per-step improvement hypotheses. -/
theorem policy_gradient_convergence_rate
    (T : ℕ) (hT : 0 < (T : ℝ))
    (gap₀ : ℝ) (_h_gap₀_nonneg : 0 ≤ gap₀)
    (C_dom L : ℝ) (_hCL : 0 < C_dom * L)
    -- Per-step improvements that telescope
    (improvements : Fin T → ℝ)
    (_h_impr_nonneg : ∀ t, 0 ≤ improvements t)
    -- Total improvement bounded by initial gap (telescope)
    (h_telescope : ∑ t, improvements t ≤ gap₀)
    -- Gradient domination: gap ≤ C·L · improvement for each step
    (gaps : Fin T → ℝ)
    (_h_gaps_nonneg : ∀ t, 0 ≤ gaps t)
    (h_gd : ∀ t, gaps t ≤ C_dom * L * improvements t)
    -- Final gap is the minimum over all steps
    (gap_T : ℝ) (h_min : ∀ t, gap_T ≤ gaps t) :
    gap_T ≤ gap₀ * (C_dom * L) / ↑T := by
  -- Step 1: ∑ gaps ≤ C·L · ∑ improvements ≤ C·L · gap₀
  have h_sum_bound : ∑ t, gaps t ≤ C_dom * L * gap₀ :=
    calc ∑ t, gaps t
        ≤ ∑ t, C_dom * L * improvements t := Finset.sum_le_sum (fun t _ => h_gd t)
      _ = C_dom * L * ∑ t, improvements t := by rw [← Finset.mul_sum]
      _ ≤ C_dom * L * gap₀ := by nlinarith
  -- Step 2: T · gap_T ≤ ∑ gaps (gap_T ≤ each gap_t, so T copies ≤ sum)
  have h_T_gap_T : ↑T * gap_T ≤ ∑ t : Fin T, gaps t :=
    calc ↑T * gap_T = ∑ _t : Fin T, gap_T := by
            simp [Finset.sum_const, Finset.card_univ, Fintype.card_fin, nsmul_eq_mul]
      _ ≤ ∑ t : Fin T, gaps t := Finset.sum_le_sum (fun t _ => h_min t)
  -- Step 3: Combine and divide
  exact (le_div_iff₀ hT).mpr (by nlinarith [mul_comm gap₀ (C_dom * L)])

/-- **Policy gradient convergence rate from per-step contraction.**

  If each step contracts the gap (gap₀ − gap_T ≥ α · ∑ gap_t) and the
  final gap is the smallest (T · gap_T ≤ ∑ gap_t), then:

    gap_T ≤ gap₀ / (1 + T · α)

  This is the O(1/T) rate from per-step contraction gap_{t+1} ≤ (1−α)·gap_t.
  The two hypotheses are the telescope sum and the minimum-gap property
  that follow from this contraction. -/
theorem policy_gradient_convergence_rate_from_contraction
    (gap₀ gap_T sum_gaps : ℝ) (T : ℕ)
    (hT : 0 < (T : ℝ))
    (α : ℝ) (hα_pos : 0 < α)
    (_h_gap₀_nonneg : 0 ≤ gap₀)
    (_h_gap_T_nonneg : 0 ≤ gap_T)
    -- Telescope from contraction: gap₀ - gap_T ≥ α · ∑ gap_t
    (h_telescope : gap₀ - gap_T ≥ α * sum_gaps)
    -- gap_T is the minimum: T · gap_T ≤ ∑ gap_t
    (h_min : ↑T * gap_T ≤ sum_gaps) :
    gap_T ≤ gap₀ / (1 + ↑T * α) := by
  have h_denom_pos : 0 < 1 + ↑T * α := by positivity
  rw [le_div_iff₀ h_denom_pos]
  -- Need: gap_T * (1 + T·α) ≤ gap₀
  -- From h_telescope: gap₀ ≥ gap_T + α · sum_gaps ≥ gap_T + α · T · gap_T
  nlinarith [mul_le_mul_of_nonneg_left h_min (le_of_lt hα_pos)]

/-! ### Score Function Sum Zero (Softmax)

  For softmax policy π_θ(a|s) = exp(⟨θ,φ(s,a)⟩) / Z(s), the score function is:
    ψ(a|s) = φ(s,a) - E_π[φ(s,·)] = φ(s,a) - ∑_{a'} π(a'|s) · φ(s,a')

  The key identity ∑_a π(a|s) · ψ(a|s) = 0 follows because:
    ∑_a π(a|s) · (φ(s,a) - E_π[φ]) = E_π[φ] - E_π[φ] = 0

  This identity is now a field `score_sum_zero` of `PolicyGradientDerivative`.
  For softmax, we PROVE it here from the centering structure.
-/

/-- **Score function sums to zero under softmax policy.**

  For the softmax score function ψ(a|s) = φ(s,a) - E_π[φ(s,·)],
  where E_π[φ(s,·)]_i = ∑_a π(a|s) · φ(s,a,i):

    ∑_a π_θ(a|s) · ψ_θ(a|s,i) = 0

  This is because the score function is centered: it equals the feature
  minus its mean under π, so its expected value is zero.

  This proves the `score_sum_zero` field of `PolicyGradientDerivative`
  for softmax parameterizations. -/
theorem score_function_sum_zero {d : ℕ}
    (φ : M.S → M.A → Fin d → ℝ)
    (θ : Fin d → ℝ) (s : M.S) (i : Fin d) :
    ∑ a, M.softmaxProb φ θ s a *
      (φ s a i - ∑ a', M.softmaxProb φ θ s a' * φ s a' i) = 0 := by
  simp_rw [mul_sub, Finset.sum_sub_distrib, ← Finset.sum_mul]
  rw [M.softmaxProb_sum_one φ θ s (M.softmax_denom_pos φ θ s), one_mul, sub_self]

/-- **Score function sum zero (mean-feature form).**

  Same identity with the mean feature
  `μ_i(s) = ∑_a π(a|s) · φ(s,a,i)` written explicitly.
  The softmax score function IS φ(s,a,i) - μ_i(s). -/
theorem score_function_sum_zero_mean_feature {d : ℕ}
    (φ : M.S → M.A → Fin d → ℝ)
    (θ : Fin d → ℝ) (s : M.S) (i : Fin d)
    (μ : ℝ)
    (hμ : μ = ∑ a, M.softmaxProb φ θ s a * φ s a i) :
    ∑ a, M.softmaxProb φ θ s a * (φ s a i - μ) = 0 := by
  rw [hμ]
  exact M.score_function_sum_zero φ θ s i

/-- **Softmax advantage form is valid without hypotheses.**

  Combining `score_function_sum_zero` with
  `policy_gradient_advantage_form_derivative`: the Q-form and
  advantage-form of the policy gradient are equal for softmax policies,
  with no conditional hypotheses.

  `score_sum_zero` is now a field of `PolicyGradientDerivative`,
  proved for softmax via `score_function_sum_zero`. -/
theorem softmax_policy_gradient_advantage_form
    (pgd : M.PolicyGradientDerivative)
    (θ : Fin pgd.d → ℝ)
    (V : M.StateValueFn) :
    ∀ (i : Fin pgd.d),
    (∑ s, pgd.occ θ s *
      ∑ a, (pgd.pi_theta θ).prob s a * pgd.score θ s a i *
        pgd.Q θ s a) =
    (∑ s, pgd.occ θ s *
      ∑ a, (pgd.pi_theta θ).prob s a * pgd.score θ s a i *
        (pgd.Q θ s a - V s)) :=
  M.policy_gradient_advantage_form_derivative pgd θ V

/-! ### Natural Policy Gradient Identity

  The NPG update direction is: w = F(θ)⁻¹ · ∇J(θ)

  Equivalently, F(θ) · w = ∇J(θ), so the NPG direction solves:
    ∑_j F(i,j) · w(j) = (∇J)_i

  Using the policy gradient theorem and the Fisher matrix structure for
  softmax, the NPG direction can be characterized via the advantage:
    w_i = (1/(1-γ)) · ∑_s d^π(s) · ∑_a π(a|s) · A^π(s,a) · φ_i(s,a)

  This identity relates the NPG direction to the advantage-weighted features.
-/

/-- **Natural policy gradient identity.**

  The NPG update direction satisfies: F · w = ∇J, i.e.,
    ∑_j F(i,j) · w(j) = grad_i

  for each coordinate i. This is the defining equation for the
  natural gradient: the direction of steepest ascent in the Fisher metric.

  We state: given the Fisher matrix F (PSD, from NPG.lean), the
  gradient vector grad, and the natural gradient direction w, if
  F · w = grad coordinate-wise, then the NPG step θ' = θ + η · w
  produces the update direction w that satisfies this linear system.

  The Fisher PSD property ensures the system is consistent. -/
theorem natural_policy_gradient_identity {d : ℕ}
    (F : Fin d → Fin d → ℝ) (grad w : Fin d → ℝ)
    -- [CONDITIONAL HYPOTHESIS] Fisher matrix is PSD
    (_h_fisher_psd : ∀ v : Fin d → ℝ,
      0 ≤ ∑ i, ∑ j, v i * F i j * v j)
    -- [CONDITIONAL HYPOTHESIS] w solves the linear system F · w = grad
    (h_system : ∀ i, ∑ j, F i j * w j = grad i)
    (η : ℝ) (θ : Fin d → ℝ) :
    -- The NPG update θ' = θ + η · w satisfies:
    -- for each i, ∑_j F(i,j) · (θ'_j - θ_j) / η = grad_i
    -- i.e., the update direction is exactly η · F⁻¹ · grad
    ∀ i, ∑ j, F i j * ((θ j + η * w j) - θ j) =
      η * grad i := by
  intro i
  simp only [add_sub_cancel_left]
  -- Goal: ∑ j, F i j * (η * w j) = η * grad i
  have : ∑ j, F i j * (η * w j) = η * ∑ j, F i j * w j := by
    rw [Finset.mul_sum]; congr 1; funext j; ring
  rw [this, h_system i]

/-- **NPG direction equals advantage-weighted features.**

  For the softmax policy, the NPG direction at state s is:
    w_i(s) = ∑_a π(a|s) · A(s,a) · φ_i(s,a)

  The full NPG direction is the occupancy-weighted sum:
    w_i = (1/(1-γ)) · ∑_s d^π(s) · w_i(s)

  This identity says that the advantage-weighted feature sum
  (which is the `npgDirectionAtState` from NPG.lean) gives the
  same result as solving F⁻¹ · ∇J, because for softmax:
    F⁻¹ · (π ⊗ score ⊗ Q) = π ⊗ A ⊗ φ

  We express this as: the occupancy-weighted NPG direction
  equals the gradient formula with advantages replacing Q-values. -/
theorem npg_direction_advantage_weighted_features {d : ℕ}
    (π : M.StochasticPolicy) (Q : M.ActionValueFn)
    (V : M.StateValueFn) (d_occ : M.S → ℝ)
    (φ : M.S → M.A → Fin d → ℝ)
    (_hVQ : ∀ s, V s = ∑ a, π.prob s a * Q s a)
    (i : Fin d) :
    -- ∑_s d(s) ∑_a π(a|s) · Q(s,a) · φ_i(s,a)
    -- = ∑_s d(s) ∑_a π(a|s) · (Q(s,a) - V(s)) · φ_i(s,a)
    -- + ∑_s d(s) · V(s) · ∑_a π(a|s) · φ_i(s,a)
    ∑ s, d_occ s * ∑ a, π.prob s a * Q s a * φ s a i =
    ∑ s, d_occ s * (∑ a, π.prob s a * (Q s a - V s) * φ s a i +
      V s * ∑ a, π.prob s a * φ s a i) := by
  congr 1; funext s; congr 1
  -- ∑_a π · Q · φ = ∑_a π · (Q - V) · φ + V · ∑_a π · φ
  -- Expand (Q - V) and distribute
  have : ∀ a, π.prob s a * (Q s a - V s) * φ s a i =
      π.prob s a * Q s a * φ s a i - π.prob s a * V s * φ s a i :=
    fun a => by ring
  simp_rw [this, Finset.sum_sub_distrib]
  -- V(s) · ∑_a π · φ = ∑_a π · V(s) · φ
  have h_expand : V s * ∑ a, π.prob s a * φ s a i =
      ∑ a, π.prob s a * V s * φ s a i := by
    rw [Finset.mul_sum]; congr 1; funext a; ring
  rw [h_expand, sub_add_cancel]

/-! ### Importance Sampling Correction for Off-Policy Gradient

  The on-policy gradient is:
    ∇J(θ) = (1/(1-γ)) · ∑_s d^π(s) · ∑_a π(a|s) · ψ(a|s) · Q^π(s,a)

  For off-policy evaluation using behavior policy μ:
    ∇J(θ) = (1/(1-γ)) · ∑_s d^μ(s) · (d^π(s)/d^μ(s)) · ∑_a π(a|s) · ψ(a|s) · Q^π(s,a)

  The importance weight d^π(s)/d^μ(s) corrects for the distribution mismatch.
  We prove: the off-policy form equals the on-policy form algebraically.
-/

/-- **Importance sampling correction for off-policy gradient.**

  The off-policy gradient using behavior distribution d^μ with
  importance weights ρ(s) = d^π(s) / d^μ(s):

    ∑_s d^μ(s) · ρ(s) · f(s) = ∑_s d^π(s) · f(s)

  This is the fundamental importance-sampling identity that allows
  computing on-policy expectations using off-policy samples.

  Applied to the policy gradient: the off-policy gradient
  ∑_s d^μ(s) · ρ(s) · ∑_a π · ψ · Q equals the on-policy gradient
  ∑_s d^π(s) · ∑_a π · ψ · Q. -/
theorem importance_sampling_correction
    (d_pi d_mu : M.S → ℝ)
    (ρ : M.S → ℝ)
    (f : M.S → ℝ)
    -- [CONDITIONAL HYPOTHESIS] Importance weights satisfy d^π = d^μ · ρ
    (h_iw : ∀ s, d_pi s = d_mu s * ρ s) :
    ∑ s, d_pi s * f s = ∑ s, d_mu s * ρ s * f s := by
  congr 1; funext s; rw [h_iw s]

/-- **Off-policy policy gradient equals on-policy gradient.**

  Combining importance sampling with the policy gradient:

    (1/(1-γ)) · ∑_s d^μ(s) · ρ(s) · ∑_a π(a|s) · ψ(a|s,i) · Q^π(s,a)
    = (1/(1-γ)) · ∑_s d^π(s) · ∑_a π(a|s) · ψ(a|s,i) · Q^π(s,a)

  where ρ(s) = d^π(s) / d^μ(s) is the state-distribution ratio.

  This justifies using off-policy data with importance weighting to
  compute an unbiased estimate of the on-policy gradient. -/
theorem offpolicy_policy_gradient {d : ℕ}
    (π : M.StochasticPolicy) (Q : M.ActionValueFn)
    (ψ : M.S → M.A → Fin d → ℝ)
    (d_pi d_mu : M.S → ℝ)
    (ρ : M.S → ℝ)
    -- [CONDITIONAL HYPOTHESIS] Importance weights: d^π(s) = d^μ(s) · ρ(s)
    (h_iw : ∀ s, d_pi s = d_mu s * ρ s)
    (i : Fin d) :
    (1 / (1 - M.γ)) *
      ∑ s, d_pi s * ∑ a, π.prob s a * ψ s a i * Q s a =
    (1 / (1 - M.γ)) *
      ∑ s, d_mu s * ρ s * ∑ a, π.prob s a * ψ s a i * Q s a := by
  congr 1
  exact M.importance_sampling_correction d_pi d_mu ρ
    (fun s => ∑ a, π.prob s a * ψ s a i * Q s a) h_iw

/-- **Full off-policy gradient with action importance weights.**

  When using behavior policy μ for both state and action sampling:

    ∑_s d^μ(s) · ρ_s(s) · ∑_a μ(a|s) · (π(a|s)/μ(a|s)) · ψ(a|s,i) · Q(s,a)
    = ∑_s d^π(s) · ∑_a π(a|s) · ψ(a|s,i) · Q(s,a)

  where ρ_s(s) = d^π(s)/d^μ(s) is the state ratio and
  π(a|s)/μ(a|s) is the per-action importance weight.

  We prove the action-level importance weighting identity:
  ∑_a μ(a|s) · w(a) · f(a) = ∑_a π(a|s) · f(a)
  when w(a) = π(a|s) / μ(a|s). -/
theorem action_importance_sampling
    (π μ : M.StochasticPolicy)
    (w : M.S → M.A → ℝ)
    (f : M.A → ℝ) (s : M.S)
    -- [CONDITIONAL HYPOTHESIS] Action importance weights: μ(a|s) · w(s,a) = π(a|s)
    (h_aiw : ∀ a, μ.prob s a * w s a = π.prob s a) :
    ∑ a, μ.prob s a * w s a * f a =
    ∑ a, π.prob s a * f a := by
  congr 1; funext a; rw [h_aiw a]

end FiniteMDP

end
