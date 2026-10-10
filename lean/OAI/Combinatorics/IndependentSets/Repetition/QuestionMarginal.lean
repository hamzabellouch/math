import Mathlib
import OAI.Combinatorics.IndependentSets.Repetition.TotalVariation
import OAI.Combinatorics.IndependentSets.Repetition.Pinsker

namespace OAI

namespace IndependentSetsGames.Foundations.Repetition

open scoped BigOperators
open Games Information

noncomputable section

variable {Q₁ Q₂ A₁ A₂ : Type*}
  [Fintype Q₁] [Fintype Q₂] [Fintype A₁] [Fintype A₂]
  [DecidableEq Q₁] [DecidableEq Q₂]
  {n : Nat}

def selectedTupleLikelihood (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) (questions : Fin n → Q₁ × Q₂) : ℝ :=
  if G.selectedWins strategy selected (Game.tupleQuestionEquiv n questions) then 1 else 0

omit [DecidableEq Q₁] [DecidableEq Q₂] in
theorem selectedTupleLikelihood_nonnegative (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) (questions : Fin n → Q₁ × Q₂) :
    0 ≤ selectedTupleLikelihood G strategy selected questions := by
  unfold selectedTupleLikelihood
  split <;> norm_num

omit [DecidableEq Q₁] [DecidableEq Q₂] in
theorem selectedTupleLikelihood_le_one (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) (questions : Fin n → Q₁ × Q₂) :
    selectedTupleLikelihood G strategy selected questions ≤ 1 := by
  unfold selectedTupleLikelihood
  split <;> norm_num

omit [DecidableEq Q₁] [DecidableEq Q₂] in
theorem selectedTupleLikelihood_mass (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) :
    (∑ questions, independentProduct (fun _ : Fin n => G.questions.weight) questions *
      selectedTupleLikelihood G strategy selected questions) =
        G.selectedSuccess strategy selected := by
  classical
  change _ = ((G.questions.iid n).transport (Game.tupleQuestionEquiv n)).probability
    (G.selectedWins strategy selected)
  rw [FiniteDistribution.probability_transport]
  simp only [FiniteDistribution.probability, FiniteDistribution.iid, independentProduct,
    selectedTupleLikelihood, mul_ite, mul_one, mul_zero]

def selectedQuestionMarginal (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) (positive : 0 < G.selectedSuccess strategy selected)
    (i : Fin n) : FiniteDistribution (Q₁ × Q₂) :=
  ((G.repetition n).questions.condition (G.selectedWins strategy selected) positive).pushforward
    (fun questions => (questions.1 i, questions.2 i))

theorem selectedQuestionMarginal_weight (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) (positive : 0 < G.selectedSuccess strategy selected)
    (i : Fin n) :
    (selectedQuestionMarginal G strategy selected positive i).weight =
      coordinateMarginal
        (posterior (independentProduct (fun _ : Fin n => G.questions.weight))
          (selectedTupleLikelihood G strategy selected) (G.selectedSuccess strategy selected)) i := by
  classical
  funext a
  simp only [selectedQuestionMarginal, FiniteDistribution.pushforward,
    FiniteDistribution.condition, coordinateMarginal]
  refine Fintype.sum_equiv (Game.tupleQuestionEquiv (Q₁ := Q₁) (Q₂ := Q₂) n).symm _ _ ?_
  intro questions
  cases he : G.selectedWins strategy selected questions <;>
    simp [Game.repetition_question_weight, Game.tupleQuestionEquiv,
      posterior, independentProduct, selectedTupleLikelihood, Game.selectedSuccess, he]

theorem selectedQuestionMarginal_totalVariation_sq_sum_le_log
    (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) (positive : 0 < G.selectedSuccess strategy selected) :
    (∑ i : Fin n,
      (selectedQuestionMarginal G strategy selected positive i).totalVariation G.questions ^ 2) ≤
        Real.log (1 / G.selectedSuccess strategy selected) := by
  classical
  change (∑ i : Fin n, Information.totalVariation
    (selectedQuestionMarginal G strategy selected positive i).weight G.questions.weight ^ 2) ≤ _
  simp_rw [selectedQuestionMarginal_weight]
  exact posterior_coordinate_totalVariation_sq_sum_le_log
    (fun _ : Fin n => G.questions.weight) (fun _ => gameLaw_isProbability G.questions)
    (selectedTupleLikelihood G strategy selected)
    (selectedTupleLikelihood_nonnegative G strategy selected)
    (selectedTupleLikelihood_le_one G strategy selected)
    positive (selectedTupleLikelihood_mass G strategy selected)

theorem unselectedQuestionMarginal_totalVariation_sq_sum_le_log
    (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) (positive : 0 < G.selectedSuccess strategy selected) :
    (∑ i : {i : Fin n // i ∉ selected},
      (selectedQuestionMarginal G strategy selected positive i.1).totalVariation G.questions ^ 2) ≤
        Real.log (1 / G.selectedSuccess strategy selected) := by
  classical
  let d : Fin n → ℝ := fun i =>
    (selectedQuestionMarginal G strategy selected positive i).totalVariation G.questions
  have hfull := selectedQuestionMarginal_totalVariation_sq_sum_le_log G strategy selected positive
  have hsplit := Fintype.sum_subtype_add_sum_subtype (fun i : Fin n => i ∈ selected)
    (fun i => d i ^ 2)
  have hinst : Subtype.fintype (fun i : Fin n => i ∈ selected) =
      Finset.Subtype.fintype selected := Subsingleton.elim _ _
  rw [hinst] at hsplit
  have hselected : 0 ≤ ∑ i : {i : Fin n // i ∈ selected}, d i.1 ^ 2 :=
    Finset.sum_nonneg (fun _ _ => sq_nonneg _)
  change (∑ i : {i : Fin n // i ∉ selected}, d i.1 ^ 2) ≤ _
  change (∑ i : Fin n, d i ^ 2) ≤ _ at hfull
  linarith

theorem unselectedQuestionMarginal_totalVariation_sum_le_sqrt
    (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) (positive : 0 < G.selectedSuccess strategy selected) :
    (∑ i : {i : Fin n // i ∉ selected},
      (selectedQuestionMarginal G strategy selected positive i.1).totalVariation G.questions) ≤
        Real.sqrt ((Fintype.card {i : Fin n // i ∉ selected} : ℝ) *
          Real.log (1 / G.selectedSuccess strategy selected)) := by
  classical
  let d : {i : Fin n // i ∉ selected} → ℝ := fun i =>
    (selectedQuestionMarginal G strategy selected positive i.1).totalVariation G.questions
  have hsq := unselectedQuestionMarginal_totalVariation_sq_sum_le_log G strategy selected positive
  have hcs := Finset.sum_mul_sq_le_sq_mul_sq
    (Finset.univ : Finset {i : Fin n // i ∉ selected}) d (fun _ => (1 : ℝ))
  simp only [mul_one, one_pow, Finset.sum_const, Finset.card_univ, nsmul_eq_mul, mul_one] at hcs
  have hln : 0 ≤ Real.log (1 / G.selectedSuccess strategy selected) :=
    (Finset.sum_nonneg (fun _ _ => sq_nonneg _)).trans hsq
  have hcard : 0 ≤ (Fintype.card {i : Fin n // i ∉ selected} : ℝ) := Nat.cast_nonneg _
  have hmul := mul_le_mul_of_nonneg_left hsq hcard
  have hsqrt := Real.sq_sqrt (mul_nonneg hcard hln)
  have hsqrtpos := Real.sqrt_nonneg
    ((Fintype.card {i : Fin n // i ∉ selected} : ℝ) *
      Real.log (1 / G.selectedSuccess strategy selected))
  change (∑ i, d i) ≤ _
  change (∑ i, d i ^ 2) ≤ _ at hsq
  change (Fintype.card {i : Fin n // i ∉ selected} : ℝ) * (∑ i, d i ^ 2) ≤ _ at hmul
  nlinarith

theorem unselectedQuestionMarginal_totalVariation_sum_le_sqrt_sub_card
    (G : Game Q₁ Q₂ A₁ A₂)
    (strategy : Strategy (Fin n → Q₁) (Fin n → Q₂) (Fin n → A₁) (Fin n → A₂))
    (selected : Finset (Fin n)) (positive : 0 < G.selectedSuccess strategy selected) :
    (∑ i : {i : Fin n // i ∉ selected},
      (selectedQuestionMarginal G strategy selected positive i.1).totalVariation G.questions) ≤
        Real.sqrt (((n - selected.card : Nat) : ℝ) *
          Real.log (1 / G.selectedSuccess strategy selected)) := by
  classical
  have hcard : Fintype.card {i : Fin n // i ∉ selected} = n - selected.card := by
    simp
  simpa only [hcard] using
    unselectedQuestionMarginal_totalVariation_sum_le_sqrt G strategy selected positive

end

end IndependentSetsGames.Foundations.Repetition

end OAI
