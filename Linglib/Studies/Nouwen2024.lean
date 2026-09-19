import Linglib.Pragmatics.RSA.Basic
import Linglib.Fragments.English.Adjectives

/-!
# Nouwen (2024): The Semantics and Probabilistic Pragmatics of Deadjectival Intensifiers

This file formalizes Nouwen's probabilistic account of deadjectival intensifiers such as
*horribly warm* and *pleasantly warm*. The adverb contributes a second positive form: its
adjectival base measures the proposition that the subject has the degree it actually has, so
over the cells of the question under discussion raised by the adjective both the adjective
and the adverb are measure functions on the same states. Each positive form is interpreted as
in Lassiter and Goodman's threshold model, with a costly positive form competing against a
free silent message, and the listener's posterior over states is the state marginal of the
joint posterior over states and thresholds (`update`).

Because a speaker sees a state only through the thresholds the state meets, the posterior is
the prior reweighted by a quantity that grows with the set of thresholds met
(`update_mul_le_mul`, strictly in `update_mul_lt_mul`). For a single positive form this is the
upward shift along the measure function (`positiveForm_mul_le_mul`). The conjunctive model
resolves the two thresholds in tandem (`simultaneous`) and is ordered only by the two measures
jointly; Nouwen's final proposal backgrounds the adverb, updating first with the adverb's
positive form and then interpreting the adjective against that posterior (`sequential`), so
that the last update is ordered by the adjective's measure alone. The Goldilocks effect of
evaluation, negative evaluation growing and positive evaluation shrinking with excess, fixes
the direction of the shift (`sequential_mul_le_mul_of_negative`,
`sequential_mul_le_mul_of_positive`), with the valence read off the English fragment
(`horribly_mul_le_mul`, `pleasantly_mul_le_mul`). A measure function that does not distinguish
the states leaves the prior unchanged (`update_eq_self`). This is the intuition Nouwen offers
for the generalisation he credits to Zwicky, that positive modal adjectives such as *usual* do
not form intensifiers: if *usual* conveyed the prior, the intensified adjective would be
indistinguishable from the bare one (`sequential_eq_positiveForm`). Nouwen notes that the
intuition faces complications.

## Implementation notes

States are an arbitrary finite type standing for the cells of the question under discussion,
and a measure function is any map from states to a linear order, so the adverb's measure of
the proposition a cell expresses is a function on states like the adjective's. The three
models are instances of one update over a family of extensions indexed by a latent parameter:
a threshold, or a pair of thresholds for the conjunctive model. The threshold prior is a
parameter; the paper sums over thresholds unweighted. The cost `c` of the paper's utility
`ln π - c` enters the speaker as the factor `exp (-α * c)`.

## TODO

The simulations behind the paper's figures are not stated. In particular the residual mass
that the conjunctive model leaves on the cold extreme for *horribly warm*, the reason the
paper rejects it, is a quantitative fact about a discretized normal prior and a quadratic
measure, and so is the comparison between the intensified and the bare posterior. The
paper's discussion of why a predicative *normal* is informative while the adverb is not
is not formalized.

## References

* [R. Nouwen, *The Semantics and Probabilistic Pragmatics of Deadjectival Intensifiers*
  (2024)][nouwen-2024]
* [D. Lassiter and N. D. Goodman, *Adjectival Vagueness in a Bayesian Model of Interpretation*
  (2017)][lassiter-goodman-2017]
* [A. M. Zwicky, *Usually and Unusually* (1970)][zwicky-1970]
-/

open MeasureTheory ProbabilityTheory RSA
open scoped ENNReal

namespace Nouwen2024

/-- The messages of the threshold model are the positive form and saying nothing. -/
inductive Message
  | positive | silent
  deriving DecidableEq, Repr, Fintype

instance : MeasurableSpace Message := ⊤
instance : DiscreteMeasurableSpace Message := ⟨fun _ ↦ trivial⟩
instance : Nonempty Message := ⟨.silent⟩

/-- The cost factor of a message at rationality `α` is `exp (-α * c)` for the positive form of
cost `c` and one for the free silent message. -/
noncomputable def costFactor (α c : ℝ) : Message → ℝ≥0∞
  | .positive => ENNReal.ofReal (Real.exp (-α * c))
  | .silent => 1

theorem costFactor_ne_zero (α c : ℝ) : ∀ u, costFactor α c u ≠ 0
  | .positive => (ENNReal.ofReal_pos.mpr (Real.exp_pos _)).ne'
  | .silent => one_ne_zero

theorem costFactor_ne_top (α c : ℝ) : ∀ u, costFactor α c u ≠ ∞
  | .positive => ENNReal.ofReal_ne_top
  | .silent => ENNReal.one_ne_top

variable {S Λ : Type*} [Fintype S] [MeasurableSpace S] [DiscreteMeasurableSpace S]
  [Fintype Λ] [MeasurableSpace Λ] [DiscreteMeasurableSpace Λ]

/-! ### The update with a positive form -/

/-- The meaning of a message under a latent parameter is the parameter's extension for the
positive form and every state for silence. -/
def sem (E : Λ → Set S) (l : Λ) : Message → Set S
  | .positive => E l
  | .silent => Set.univ

/-- The literal listener at a latent parameter conditions the prior on the truth of the
message. -/
noncomputable def L0 (P : Measure S) (E : Λ → Set S) (l : Λ) : Kernel Message S :=
  literalListener P fun u ↦ (sem E l u).indicator 1

/-- The speaker at a state and a latent parameter soft-maximizes the literal listener's log
probability of the state minus the cost of the message. -/
noncomputable def S1 (P : Measure S) (E : Λ → Set S) (α c : ℝ) : Kernel (S × Λ) Message :=
  familySpeaker (L0 P E) α (costFactor α c)

instance (P : Measure S) (E : Λ → Set S) (α c : ℝ) : IsFiniteKernel (S1 P E α c) :=
  inferInstanceAs (IsFiniteKernel (familySpeaker _ _ _))

variable (P : Measure S) [IsFiniteMeasure P] (ν : Measure Λ) (E : Λ → Set S) (α c : ℝ)

/-- The speaker produces a message at a state and a latent parameter exactly when it is true
there and the state has positive prior. -/
theorem S1_apply_singleton_ne_zero_iff (hα : 0 < α) (s : S) (l : Λ) (u : Message) :
    S1 P E α c (s, l) {u} ≠ 0 ↔ s ∈ sem E l u ∧ P {s} ≠ 0 :=
  speaker_literalListener_indicator_apply_singleton_ne_zero_iff hα (costFactor_ne_zero α c)
    (costFactor_ne_top α c) P (sem E l) u s

/-- The positive form is assertable when some state of positive prior lies in the extension of
some latent parameter of positive prior. -/
def Assertable : Prop := ∃ s l, P {s} ≠ 0 ∧ ν {l} ≠ 0 ∧ s ∈ E l

/-- The production weight of a state is the prior-averaged probability that the speaker
produces the positive form there. -/
noncomputable def production (s : S) : ℝ :=
  ∑ l, ν.real {l} * (S1 P E α c (s, l)).real {.positive}

variable {P ν E α}

/-- The speaker treats alike two states of positive prior in the extension of a latent
parameter. -/
theorem S1_congr (hα : 0 < α) {s t : S} {l : Λ} (hs : P {s} ≠ 0) (ht : P {t} ≠ 0)
    (hsl : s ∈ E l) (htl : t ∈ E l) : S1 P E α c (t, l) = S1 P E α c (s, l) :=
  speaker_literalListener_indicator_congr hα _ P (sem E l) hs ht fun u ↦ by
    cases u <;> simp [sem, hsl, htl]

/-- At each latent parameter the speaker is no less likely to produce the positive form at a
state that lies in its extension whenever another state does. -/
theorem S1_real_positive_le (hα : 0 < α) {s t : S} (hs : P {s} ≠ 0) (ht : P {t} ≠ 0) {l : Λ}
    (h : s ∈ E l → t ∈ E l) :
    (S1 P E α c (s, l)).real {.positive} ≤ (S1 P E α c (t, l)).real {.positive} := by
  by_cases hl : s ∈ E l
  · rw [S1_congr c hα hs ht hl (h hl)]
  · rw [measureReal_def, not_not.mp (mt (S1_apply_singleton_ne_zero_iff P E α c hα s l
      .positive).mp fun h' ↦ hl h'.1), ENNReal.toReal_zero]
    exact measureReal_nonneg

/-- A state that lies in no more extensions than another has no greater production weight. -/
theorem production_le_production (hα : 0 < α) {s t : S} (hs : P {s} ≠ 0) (ht : P {t} ≠ 0)
    (h : ∀ l, s ∈ E l → t ∈ E l) : production P ν E α c s ≤ production P ν E α c t :=
  Finset.sum_le_sum fun l _ ↦
    mul_le_mul_of_nonneg_left (S1_real_positive_le c hα hs ht (h l)) measureReal_nonneg

/-- The production weight is strictly greater when a latent parameter of positive prior
separates the two states. -/
theorem production_lt_production [IsFiniteMeasure ν] (hα : 0 < α) {s t : S} (hs : P {s} ≠ 0)
    (ht : P {t} ≠ 0) (h : ∀ l, s ∈ E l → t ∈ E l) {l₀ : Λ} (hl₀ : ν {l₀} ≠ 0) (hs₀ : s ∉ E l₀)
    (ht₀ : t ∈ E l₀) : production P ν E α c s < production P ν E α c t := by
  refine Finset.sum_lt_sum (fun l _ ↦ mul_le_mul_of_nonneg_left
    (S1_real_positive_le c hα hs ht (h l)) measureReal_nonneg) ⟨l₀, Finset.mem_univ _, ?_⟩
  rw [measureReal_def (μ := S1 P E α c (s, l₀)), not_not.mp (mt
    (S1_apply_singleton_ne_zero_iff P E α c hα s l₀ .positive).mp fun h' ↦ hs₀ h'.1),
    ENNReal.toReal_zero, mul_zero]
  exact mul_pos (ENNReal.toReal_pos hl₀ (measure_ne_top _ _))
    (ENNReal.toReal_pos ((S1_apply_singleton_ne_zero_iff P E α c hα t l₀ .positive).mpr ⟨ht₀, ht⟩)
      (measure_ne_top _ _))

/-- An assertable positive form has a positive marginal under the speaker. -/
theorem Assertable.comp_S1_ne_zero (h : Assertable P ν E) (hα : 0 < α) :
    (S1 P E α c ∘ₘ P.prod ν) {.positive} ≠ 0 := by
  obtain ⟨s, l, hs, hl, hsl⟩ := h
  exact comp_familySpeaker_ne_zero (w := s) (l := l)
    (by rw [← Set.singleton_prod_singleton, Measure.prod_prod]; exact mul_ne_zero hs hl)
    ((S1_apply_singleton_ne_zero_iff P E α c hα s l .positive).mpr ⟨hsl, hs⟩)

variable (P ν E α) [IsFiniteMeasure ν] [Nonempty S] [Nonempty Λ]

/-- The pragmatic listener inverts the speaker against the product of the state prior and the
prior over latent parameters. -/
noncomputable def L1 : Kernel Message (S × Λ) :=
  familyListener (L0 P E) α (costFactor α c) (P.prod ν)

instance : IsMarkovKernel (L1 P ν E α c) :=
  inferInstanceAs (IsMarkovKernel ((familySpeaker (L0 P E) α (costFactor α c))†(P.prod ν)))

/-- The update of a prior with the positive form is the state marginal of the pragmatic
listener's posterior. -/
noncomputable def update : Measure S := (L1 P ν E α c .positive).fst

instance : IsProbabilityMeasure (update P ν E α c) := by
  unfold update; infer_instance

variable {P ν E α}

/-- The posterior of a state is its prior times its production weight, normalized. -/
theorem update_real_singleton (hα : 0 < α) (hE : Assertable P ν E) (s : S) :
    (update P ν E α c).real {s}
      = P.real {s} * production P ν E α c s / (S1 P E α c ∘ₘ P.prod ν).real {.positive} :=
  familyListener_fst_real_singleton (L0 P E) α (costFactor α c) P ν (hE.comp_S1_ne_zero c hα) s

/-- The update keeps exactly the states of positive prior that lie in the extension of some
latent parameter of positive prior. -/
theorem update_apply_singleton_ne_zero_iff (hα : 0 < α) (hE : Assertable P ν E) (s : S) :
    update P ν E α c {s} ≠ 0 ↔ P {s} ≠ 0 ∧ ∃ l, ν {l} ≠ 0 ∧ s ∈ E l := by
  rw [update, L1, familyListener_fst_apply_singleton_ne_zero_iff _ _ _ (hE.comp_S1_ne_zero c hα)]
  have hs := S1_apply_singleton_ne_zero_iff P E α c hα s
  simp only [S1, familySpeaker_apply] at hs
  simp_rw [← Set.singleton_prod_singleton, Measure.prod_prod, mul_ne_zero_iff, hs, sem]
  exact ⟨fun ⟨l, ⟨h, hl⟩, hsl, _⟩ ↦ ⟨h, l, hl, hsl⟩, fun ⟨h, l, hl, hsl⟩ ↦ ⟨l, ⟨h, hl⟩, hsl, h⟩⟩

/-- A further positive form is assertable against the updated prior when some state of positive
prior lies in an extension of positive prior for each of the two forms. -/
theorem assertable_update {Λ' : Type*} [MeasurableSpace Λ'] {ν' : Measure Λ'}
    {E' : Λ' → Set S} (hα : 0 < α) {s : S} {l : Λ} {l' : Λ'} (hs : P {s} ≠ 0) (hl : ν {l} ≠ 0)
    (hsl : s ∈ E l) (hl' : ν' {l'} ≠ 0) (hsl' : s ∈ E' l') :
    Assertable (update P ν E α c) ν' E' :=
  ⟨s, l', (update_apply_singleton_ne_zero_iff c hα ⟨s, l, hs, hl, hsl⟩ s).mpr ⟨hs, l, hl, hsl⟩,
    hl', hsl'⟩

/-- The update shifts mass toward states that lie in more extensions, in that the ratio of posterior
to prior is monotone in the set of latent parameters whose extension contains the state. -/
theorem update_mul_le_mul (hα : 0 < α) (hE : Assertable P ν E) {s t : S}
    (h : ∀ l, s ∈ E l → t ∈ E l) :
    (update P ν E α c).real {s} * P.real {t} ≤ (update P ν E α c).real {t} * P.real {s} := by
  rw [update_real_singleton c hα hE, update_real_singleton c hα hE]
  rcases eq_or_ne (P {s}) 0 with hs | hs
  · simp [measureReal_def, hs]
  rcases eq_or_ne (P {t}) 0 with ht | ht
  · simp [measureReal_def, ht]
  set Z := (S1 P E α c ∘ₘ P.prod ν).real {Message.positive}
  calc P.real {s} * production P ν E α c s / Z * P.real {t}
      = P.real {s} * P.real {t} / Z * production P ν E α c s := by ring
    _ ≤ P.real {s} * P.real {t} / Z * production P ν E α c t :=
        mul_le_mul_of_nonneg_left (production_le_production c hα hs ht h)
          (div_nonneg (mul_nonneg measureReal_nonneg measureReal_nonneg) measureReal_nonneg)
    _ = P.real {t} * production P ν E α c t / Z * P.real {s} := by ring

/-- The shift is strict between two states of positive prior separated by a latent parameter
of positive prior. -/
theorem update_mul_lt_mul (hα : 0 < α) {s t : S} (hs : P {s} ≠ 0) (ht : P {t} ≠ 0)
    (h : ∀ l, s ∈ E l → t ∈ E l) {l₀ : Λ} (hl₀ : ν {l₀} ≠ 0) (hs₀ : s ∉ E l₀) (ht₀ : t ∈ E l₀) :
    (update P ν E α c).real {s} * P.real {t} < (update P ν E α c).real {t} * P.real {s} := by
  have hE : Assertable P ν E := ⟨t, l₀, ht, hl₀, ht₀⟩
  rw [update_real_singleton c hα hE, update_real_singleton c hα hE]
  set Z := (S1 P E α c ∘ₘ P.prod ν).real {Message.positive}
  have hpos : 0 < P.real {s} * P.real {t} / Z :=
    div_pos (mul_pos (ENNReal.toReal_pos hs (measure_ne_top _ _))
        (ENNReal.toReal_pos ht (measure_ne_top _ _)))
      (ENNReal.toReal_pos (hE.comp_S1_ne_zero c hα) (measure_ne_top _ _))
  calc P.real {s} * production P ν E α c s / Z * P.real {t}
      = P.real {s} * P.real {t} / Z * production P ν E α c s := by ring
    _ < P.real {s} * P.real {t} / Z * production P ν E α c t :=
        mul_lt_mul_of_pos_left (production_lt_production c hα hs ht h hl₀ hs₀ ht₀) hpos
    _ = P.real {t} * production P ν E α c t / Z * P.real {s} := by ring

/-- A positive form whose extensions do not distinguish the states leaves a probability prior
unchanged. -/
theorem update_eq_self [IsProbabilityMeasure P] (hα : 0 < α) (hE : Assertable P ν E)
    (h : ∀ l s t, s ∈ E l → t ∈ E l) : update P ν E α c = P := by
  refine Measure.ext_of_singleton fun s ↦ ?_
  have key : ∀ t, (update P ν E α c).real {s} * P.real {t}
      = (update P ν E α c).real {t} * P.real {s} := fun t ↦
    le_antisymm (update_mul_le_mul c hα hE fun l ↦ h l s t)
      (update_mul_le_mul c hα hE fun l ↦ h l t s)
  have hsum := Finset.sum_congr (s₁ := Finset.univ) rfl fun t _ ↦ key t
  rw [← Finset.mul_sum, ← Finset.sum_mul, sum_measureReal_singleton,
    sum_measureReal_singleton, Finset.coe_univ, probReal_univ, probReal_univ, mul_one,
    one_mul] at hsum
  exact (ENNReal.toReal_eq_toReal_iff' (measure_ne_top _ _) (measure_ne_top _ _)).mp hsum

/-- The update depends on the prior only as a measure. -/
private theorem update_congr {Q : Measure S} [IsFiniteMeasure Q] (h : Q = P) :
    update Q ν E α c = update P ν E α c := by
  subst h; rfl

/-! ### Positive forms of measure functions -/

section Models

variable {D D' X : Type*} [LinearOrder D] [Fintype D] [MeasurableSpace D]
  [DiscreteMeasurableSpace D] [Nonempty D] [LinearOrder D'] [Fintype D'] [MeasurableSpace D']
  [DiscreteMeasurableSpace D'] [Nonempty D'] [Preorder X]

/-- The extension of a positive form at a threshold holds the states whose measure meets the
threshold. -/
def atLeast (m : S → D) (θ : D) : Set S := {s | θ ≤ m s}

/-- The interpretation of a bare positive form updates the prior with the extensions of the
adjective's measure function. -/
noncomputable abbrev positiveForm (P : Measure S) [IsFiniteMeasure P] (νA : Measure D)
    [IsFiniteMeasure νA] (mA : S → D) (α c : ℝ) : Measure S :=
  update P νA (atLeast mA) α c

/-- The conjunctive model of an intensified adjective resolves the thresholds of the adjective
and the adverb in tandem, as one update over pairs of thresholds. -/
noncomputable abbrev simultaneous (P : Measure S) [IsFiniteMeasure P] (νA : Measure D)
    [IsFiniteMeasure νA] (νD : Measure D') [IsFiniteMeasure νD] (mA : S → D) (mD : S → D')
    (α c : ℝ) : Measure S :=
  update P (νA.prod νD) (fun θ ↦ atLeast mA θ.1 ∩ atLeast mD θ.2) α c

/-- The backgrounded model of an intensified adjective first updates the prior with the
adverb's positive form at cost `c'` and then interprets the adjective's positive form
against that posterior. -/
noncomputable abbrev sequential (P : Measure S) [IsFiniteMeasure P] (νA : Measure D)
    [IsFiniteMeasure νA] (νD : Measure D') [IsFiniteMeasure νD] (mA : S → D) (mD : S → D')
    (α c c' : ℝ) : Measure S :=
  positiveForm (positiveForm P νD mD α c') νA mA α c

variable {νA : Measure D} [IsFiniteMeasure νA] {νD : Measure D'} [IsFiniteMeasure νD]
  {mA : S → D} {mD : S → D'} (c' : ℝ)

/-- A positive form shifts mass toward the states of higher measure. -/
theorem positiveForm_mul_le_mul (hα : 0 < α) (hE : Assertable P νA (atLeast mA)) {s t : S}
    (h : mA s ≤ mA t) :
    (positiveForm P νA mA α c).real {s} * P.real {t}
      ≤ (positiveForm P νA mA α c).real {t} * P.real {s} :=
  update_mul_le_mul c hα hE fun _ hθ ↦ le_trans hθ h

/-- The shift is strict between two states of positive prior when the higher measure is a
threshold of positive prior. -/
theorem positiveForm_mul_lt_mul (hα : 0 < α) {s t : S} (hs : P {s} ≠ 0) (ht : P {t} ≠ 0)
    (h : mA s < mA t) (hν : νA {mA t} ≠ 0) :
    (positiveForm P νA mA α c).real {s} * P.real {t}
      < (positiveForm P νA mA α c).real {t} * P.real {s} :=
  update_mul_lt_mul c hα hs ht (fun _ hθ ↦ le_trans hθ h.le) hν (not_le.mpr h) le_rfl

/-- The conjunctive model is ordered by the two measures jointly, in that mass shifts toward a state
only when it is at least as high on the adjective's scale and on the adverb's. -/
theorem simultaneous_mul_le_mul (hα : 0 < α)
    (hE : Assertable P (νA.prod νD) fun θ ↦ atLeast mA θ.1 ∩ atLeast mD θ.2) {s t : S}
    (hA : mA s ≤ mA t) (hD : mD s ≤ mD t) :
    (simultaneous P νA νD mA mD α c).real {s} * P.real {t}
      ≤ (simultaneous P νA νD mA mD α c).real {t} * P.real {s} :=
  update_mul_le_mul c hα hE fun _ hθ ↦ ⟨le_trans hθ.1 hA, le_trans hθ.2 hD⟩

/-- Relative to the original prior the backgrounded model is also ordered by the two measures
jointly; relative to the backgrounded posterior its last update is ordered by the adjective's
measure alone, by `positiveForm_mul_le_mul`. -/
theorem sequential_mul_le_mul (hα : 0 < α) (hD : Assertable P νD (atLeast mD))
    (hA : Assertable (positiveForm P νD mD α c') νA (atLeast mA)) {s t : S}
    (hmA : mA s ≤ mA t) (hmD : mD s ≤ mD t) :
    (sequential P νA νD mA mD α c c').real {s} * P.real {t}
      ≤ (sequential P νA νD mA mD α c c').real {t} * P.real {s} := by
  have h₁ := positiveForm_mul_le_mul c hα hA hmA
  have h₂ := positiveForm_mul_le_mul c' hα hD hmD
  set Q := positiveForm P νD mD α c'
  set ρ := sequential P νA νD mA mD α c c'
  rcases (measureReal_nonneg (μ := Q) (s := {t})).eq_or_lt with hQt | hQt
  · rw [← hQt, zero_mul] at h₂
    rcases mul_eq_zero.mp (le_antisymm h₂ (mul_nonneg measureReal_nonneg measureReal_nonneg))
      with hQs | hPt
    · rw [show ρ.real {s} = 0 by rw [update_real_singleton c hα hA, hQs, zero_mul, zero_div],
        zero_mul]
      exact mul_nonneg measureReal_nonneg measureReal_nonneg
    · rw [hPt, mul_zero]
      exact mul_nonneg measureReal_nonneg measureReal_nonneg
  · refine le_of_mul_le_mul_right ?_ hQt
    calc ρ.real {s} * P.real {t} * Q.real {t}
        = ρ.real {s} * Q.real {t} * P.real {t} := by ring
      _ ≤ ρ.real {t} * Q.real {s} * P.real {t} :=
          mul_le_mul_of_nonneg_right h₁ measureReal_nonneg
      _ = ρ.real {t} * (Q.real {s} * P.real {t}) := by ring
      _ ≤ ρ.real {t} * (Q.real {t} * P.real {s}) :=
          mul_le_mul_of_nonneg_left h₂ measureReal_nonneg
      _ = ρ.real {t} * P.real {s} * Q.real {t} := by ring

/-! ### The Goldilocks effect and vacuous intensifiers -/

/-- The Goldilocks effect of evaluation constrains the measure function of an evaluative base
over a scale of excess: a negative evaluation grows with excess and a positive evaluation
shrinks with it. -/
def Goldilocks (a : Degree.GradableAdjective) (excess : S → X) (m : S → D') : Prop :=
  match a.evaluativeValence with
  | some .negative => ∀ s t, excess s ≤ excess t → m s ≤ m t
  | some .positive => ∀ s t, excess s ≤ excess t → m t ≤ m s
  | _ => True

variable {a : Degree.GradableAdjective} {excess : S → X}

/-- An intensifier with a negatively evaluative base shifts mass toward the states that are
higher on the adjective's scale and more excessive, which is intensification to a high
degree. -/
theorem sequential_mul_le_mul_of_negative (ha : a.evaluativeValence = some .negative)
    (hm : Goldilocks a excess mD) (hα : 0 < α) (hD : Assertable P νD (atLeast mD))
    (hA : Assertable (positiveForm P νD mD α c') νA (atLeast mA)) {s t : S}
    (hmA : mA s ≤ mA t) (hx : excess s ≤ excess t) :
    (sequential P νA νD mA mD α c c').real {s} * P.real {t}
      ≤ (sequential P νA νD mA mD α c c').real {t} * P.real {s} := by
  rw [Goldilocks, ha] at hm
  exact sequential_mul_le_mul c c' hα hD hA hmA (hm s t hx)

/-- An intensifier with a positively evaluative base shifts mass toward the states that are
higher on the adjective's scale and less excessive, which is intensification to a moderate
degree. -/
theorem sequential_mul_le_mul_of_positive (ha : a.evaluativeValence = some .positive)
    (hm : Goldilocks a excess mD) (hα : 0 < α) (hD : Assertable P νD (atLeast mD))
    (hA : Assertable (positiveForm P νD mD α c') νA (atLeast mA)) {s t : S}
    (hmA : mA s ≤ mA t) (hx : excess t ≤ excess s) :
    (sequential P νA νD mA mD α c c').real {s} * P.real {t}
      ≤ (sequential P νA νD mA mD α c c').real {t} * P.real {s} := by
  rw [Goldilocks, ha] at hm
  exact sequential_mul_le_mul c c' hα hD hA hmA (hm t s hx)

/-- The English fragment records *horrible* as negatively evaluative, so *horribly* intensifies
to a high degree. -/
theorem horribly_mul_le_mul (hm : Goldilocks English.Adjectives.horrible excess mD)
    (hα : 0 < α) (hD : Assertable P νD (atLeast mD))
    (hA : Assertable (positiveForm P νD mD α c') νA (atLeast mA)) {s t : S}
    (hmA : mA s ≤ mA t) (hx : excess s ≤ excess t) :
    (sequential P νA νD mA mD α c c').real {s} * P.real {t}
      ≤ (sequential P νA νD mA mD α c c').real {t} * P.real {s} :=
  sequential_mul_le_mul_of_negative c c' rfl hm hα hD hA hmA hx

/-- The English fragment records *pleasant* as positively evaluative, so *pleasantly*
intensifies to a moderate degree. -/
theorem pleasantly_mul_le_mul (hm : Goldilocks English.Adjectives.pleasant excess mD)
    (hα : 0 < α) (hD : Assertable P νD (atLeast mD))
    (hA : Assertable (positiveForm P νD mD α c') νA (atLeast mA)) {s t : S}
    (hmA : mA s ≤ mA t) (hx : excess t ≤ excess s) :
    (sequential P νA νD mA mD α c c').real {s} * P.real {t}
      ≤ (sequential P νA νD mA mD α c c').real {t} * P.real {s} :=
  sequential_mul_le_mul_of_positive c c' rfl hm hα hD hA hmA hx

/-- An adverb whose measure function does not distinguish the states, as that of *usual* would
not if it conveyed the prior, is a vacuous intensifier: the intensified adjective is
interpreted as the bare adjective. -/
theorem sequential_eq_positiveForm [IsProbabilityMeasure P] (hα : 0 < α)
    (hD : Assertable P νD (atLeast mD)) (h : ∀ s t, mD s = mD t) :
    sequential P νA νD mA mD α c c' = positiveForm P νA mA α c :=
  update_congr c (update_eq_self c' hα hD fun θ s t (hs : θ ≤ mD s) ↦ (h s t ▸ hs : θ ≤ mD t))

end Models

end Nouwen2024
