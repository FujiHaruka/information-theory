import InformationTheory.Meta.EntryPoint
import InformationTheory.Shannon.LZ78.ZivEntropyBridge
import InformationTheory.Shannon.LZ78.PhraseCounting
import InformationTheory.Shannon.EntropyRate
import Mathlib.Algebra.BigOperators.Group.Finset.Basic

/-!
# Stationary-process telescoping layer (LZ78 `blockRV` factorization)

This file derives the genuine **algebraic telescoping** backbone of the LZ78
per-path parsing factorization `Pₙ{block ω} = ∏ⱼ condPhraseProb …`
(`IsLZ78PerPathParsingFactorization`, `LZ78ZivEntropyBridge.lean`).

`condPhraseProb μ p n ω j` is *defined* as the ratio of successive
parsing-prefix block probabilities
`prefixBlockProb ω (boundary (j+1)) / prefixBlockProb ω (boundary j)`. Over
the phrase positions `j ∈ range c` this product **telescopes** to
`prefixBlockProb ω (boundary c) / prefixBlockProb ω (boundary 0)`
(`Finset.prod_range_div`). Since `boundary 0 = 0` and the length-`0` block
has probability `1`, the denominator is `1`, leaving
`prefixBlockProb ω (boundary c)`.

The remaining content that connects this to `Pₙ{block ω}` is the
**parse-completeness** fact `boundary c = n` (the parse consumes all `n`
symbols) — together with the **positivity** of each ratio. These are the
genuinely process-dependent inputs of the factorization; the telescoping
algebra itself is unconditional and lives here.
-/

namespace InformationTheory.Shannon

open MeasureTheory ProbabilityTheory Filter Topology
open scoped ENNReal NNReal BigOperators

variable {α Ω : Type*}
variable [Fintype α] [DecidableEq α] [Nonempty α]
  [MeasurableSpace α] [MeasurableSingletonClass α]
variable [MeasurableSpace Ω]

omit [Fintype α] [Nonempty α] [MeasurableSingletonClass α] in
/-- `parsingBoundary μ p n ω 0 = 0`: the empty parsing prefix consumes no
symbols. -/
theorem parsingBoundary_zero
    (μ : Measure Ω) (p : StationaryProcess μ α) (n : ℕ) (ω : Ω) :
    parsingBoundary μ p n ω 0 = 0 := by
  simp [parsingBoundary]

omit [Fintype α] [DecidableEq α] [Nonempty α] [MeasurableSingletonClass α] in
/-- **`prefixBlockProb` of the empty prefix is `1`**: `Pₘ{block_m ω}` at
`m = 0` is the probability of the unique length-`0` block, which is `1`. -/
theorem prefixBlockProb_zero
    (μ : Measure Ω) [IsProbabilityMeasure μ] (p : StationaryProcess μ α) (ω : Ω) :
    prefixBlockProb μ p ω 0 = 1 := by
  unfold prefixBlockProb
  have _ : IsProbabilityMeasure (μ.map (p.blockRV 0)) :=
    Measure.isProbabilityMeasure_map (p.measurable_blockRV 0).aemeasurable
  have h_default : ∀ x : (Fin 0 → α), x = default := fun x ↦ by
    funext i; exact i.elim0
  have h_singleton_eq_univ :
      ({(p.blockRV 0 ω : Fin 0 → α)} : Set (Fin 0 → α)) = Set.univ := by
    ext x; simp [h_default x, h_default (p.blockRV 0 ω)]
  rw [h_singleton_eq_univ]
  simp [measureReal_def, measure_univ]

omit [Fintype α] [Nonempty α] [MeasurableSingletonClass α] in
/-- **Genuine telescoping**: the product of the per-phrase conditional
probabilities over `range c` telescopes to
`prefixBlockProb ω (boundary c)`, using `boundary 0 = 0` and
`prefixBlockProb ω 0 = 1`.

Proved by induction on `c` (a `ℝ` field telescoping, where the `prod_range_div`
group lemma does not apply): each step cancels the denominator ratio against
the previous prefix probability, which is nonzero by `hpos`. -/
@[entry_point]
theorem prod_condPhraseProb_telescope
    (μ : Measure Ω) [IsProbabilityMeasure μ] (p : StationaryProcess μ α)
    (n : ℕ) (ω : Ω) (c : ℕ)
    (hpos : ∀ j ≤ c, prefixBlockProb μ p ω (parsingBoundary μ p n ω j) ≠ 0) :
    ∏ j ∈ Finset.range c, condPhraseProb μ p n ω j
      = prefixBlockProb μ p ω (parsingBoundary μ p n ω c) := by
  induction c with
  | zero =>
      simp [parsingBoundary_zero, prefixBlockProb_zero]
  | succ k ih =>
      have hk : ∀ j ≤ k, prefixBlockProb μ p ω (parsingBoundary μ p n ω j) ≠ 0 :=
        fun j hj ↦ hpos j (Nat.le_succ_of_le hj)
      rw [Finset.prod_range_succ, ih hk]
      -- `prefix(b k) * (prefix(b (k+1)) / prefix(b k)) = prefix(b (k+1))`.
      unfold condPhraseProb
      rw [mul_div_cancel₀ _ (hpos k (Nat.le_succ k))]

/-! ## Reduction of the factorization to parse-completeness + positivity

The telescoping above reduces the `factor` field of
`IsLZ78PerPathParsingFactorization` to two genuinely process-dependent
facts about the LZ78 parse: positivity of the intermediate prefix block
probabilities, and **parse-completeness** `boundary c = n` (the parse
consumes all `n` symbols). The latter is the load-bearing residual: the
genuine longest-prefix greedy parse `lz78PhraseStrings` leaves an
*unfinished tail* (`lz78PhraseStrings_total_length_le` is `≤`, not `=`), so
`boundary c = n` is **not** unconditionally true for the present parse — it
is the Cover–Thomas "last partial phrase" content. -/

/-! ## Genuine Ziv-direction factorization (parse-completeness defect fix)

The `factor` field of `IsLZ78PerPathParsingFactorization`
(`LZ78ZivEntropyBridge.lean`) was originally stated as the **equality**
`Pₙ{block ω} = ∏ⱼ condPhraseProb …`. That equality is *genuinely false*
in general: the longest-prefix greedy parse `lz78PhraseStrings` leaves an
unfinished tail, so the phrase boundaries cover only
`boundary c ≤ n` symbols (`lz78PhraseStrings_total_length_le` is `≤`, not
`=`), and the telescoping product equals `prefixBlockProb ω (boundary c)`,
which exceeds `Pₙ = prefixBlockProb ω n` whenever the parse is incomplete.

The Ziv chain (Cover–Thomas Eq. 13.122–124) does **not** need that false
equality — it needs only the **inequality** `Pₙ{block ω} ≤ ∏ⱼ qⱼ`
(equivalently `-log Pₙ ≥ ∑ⱼ -log qⱼ`), which **is** unconditionally true:
`Pₙ = prefixBlockProb ω n ≤ prefixBlockProb ω (boundary c) = ∏ⱼ qⱼ` by
*prefix monotonicity* of the cylinder block probability (a shorter prefix
has larger mass). The two genuine ingredients below establish this, fixing
the defect: the factorization is recast from a false equality to the true
Ziv inequality. Positivity of the intermediate prefix block probabilities
(a.s. regularity of the observed cylinders) is the only side condition. -/

omit [Fintype α] [DecidableEq α] [Nonempty α] in
/-- **Prefix monotonicity of the block probability** (genuine, unconditional):
for `m₁ ≤ m₂`, the length-`m₂` cylinder is contained in the length-`m₁`
cylinder (matching more coordinates is a stronger constraint), so its mass
is smaller: `prefixBlockProb ω m₂ ≤ prefixBlockProb ω m₁`.

This is the load-bearing measure-theoretic fact that turns the (false)
factorization *equality* into the (true) Ziv *inequality*. -/
@[entry_point]
theorem prefixBlockProb_antitone
    (μ : Measure Ω) [IsProbabilityMeasure μ] (p : StationaryProcess μ α)
    (ω : Ω) {m₁ m₂ : ℕ} (h : m₁ ≤ m₂) :
    prefixBlockProb μ p ω m₂ ≤ prefixBlockProb μ p ω m₁ := by
  unfold prefixBlockProb
  rw [map_measureReal_apply (p.measurable_blockRV m₂) (measurableSet_singleton _),
      map_measureReal_apply (p.measurable_blockRV m₁) (measurableSet_singleton _)]
  apply measureReal_mono (h₂ := measure_ne_top μ _)
  intro ω' hω'
  simp only [Set.mem_preimage, Set.mem_singleton_iff] at hω' ⊢
  funext i
  have := congrFun hω' ⟨i.val, i.isLt.trans_le h⟩
  simpa [StationaryProcess.blockRV] using this

omit [Nonempty α] [MeasurableSingletonClass α] in
/-- **The complete-phrase boundary never exceeds `n`** (genuine): the total
length of the emitted phrase strings is at most the input length
(`lz78PhraseStrings_total_length_le`), so the parsing boundary at the full
phrase count is `≤ n`. This is the *unconditional* replacement for the
false `boundary c = n` parse-completeness claim. -/
@[entry_point]
theorem parsingBoundary_complete_le
    (μ : Measure Ω) (p : StationaryProcess μ α) (n : ℕ) (ω : Ω) :
    parsingBoundary μ p n ω (lz78PhraseStrings (List.ofFn (p.blockRV n ω))).length ≤ n := by
  unfold parsingBoundary
  rw [List.take_length, ← foldr_length_eq_map_sum]
  have h := lz78PhraseStrings_total_length_le (List.ofFn (p.blockRV n ω))
  rwa [List.length_ofFn] at h

omit [Nonempty α] in
/-- **Genuine Ziv-direction factorization inequality** (parse-completeness
defect fix): the block probability is bounded **above** by the product of
the per-phrase conditional probabilities over the parse,
`Pₙ{block ω} ≤ ∏ⱼ condPhraseProb …`. This is the *true* content the Ziv
chain needs (replacing the false equality `factor`): the telescoping gives
`∏ⱼ qⱼ = prefixBlockProb ω (boundary c)`
(`prod_condPhraseProb_telescope`, genuine), and prefix monotonicity
(`prefixBlockProb_antitone`, genuine) gives
`Pₙ = prefixBlockProb ω n ≤ prefixBlockProb ω (boundary c)` since
`boundary c ≤ n` (`parsingBoundary_complete_le`, genuine).

The only side condition is positivity of the intermediate prefix block
probabilities (a.s. regularity of the observed cylinders) — not the false
parse-completeness claim. -/
@[entry_point]
theorem blockProb_le_prod_condPhraseProb
    (μ : Measure Ω) [IsProbabilityMeasure μ] (p : StationaryProcess μ α)
    (n : ℕ) (ω : Ω)
    (hpos : ∀ j ≤ (lz78PhraseStrings (List.ofFn (p.blockRV n ω))).length,
      prefixBlockProb μ p ω (parsingBoundary μ p n ω j) ≠ 0) :
    (μ.map (p.blockRV n)).real {p.blockRV n ω}
      ≤ ∏ j ∈ Finset.range
            (lz78PhraseStrings (List.ofFn (p.blockRV n ω))).length,
          condPhraseProb μ p n ω j := by
  rw [prod_condPhraseProb_telescope μ p n ω _ hpos]
  -- `Pₙ = prefixBlockProb ω n ≤ prefixBlockProb ω (boundary c)` since `boundary c ≤ n`.
  have hb : parsingBoundary μ p n ω
      (lz78PhraseStrings (List.ofFn (p.blockRV n ω))).length ≤ n :=
    parsingBoundary_complete_le μ p n ω
  have := prefixBlockProb_antitone μ p ω hb
  -- `prefixBlockProb ω n` is definitionally `Pₙ{block ω}`.
  simpa [prefixBlockProb] using this

omit [Nonempty α] [MeasurableSingletonClass α] in
/-- **The parsing boundary never exceeds `n` at any phrase index** (genuine):
the cumulative length of the first `j` phrases is bounded by the total
phrase length, which is `≤ n`. (For `j ≥ c` the prefix is the whole phrase
list, so the boundary is constant `= boundary c ≤ n`.) -/
@[entry_point]
theorem parsingBoundary_le_n
    (μ : Measure Ω) (p : StationaryProcess μ α) (n : ℕ) (ω : Ω) (j : ℕ) :
    parsingBoundary μ p n ω j ≤ n := by
  refine le_trans ?_ (parsingBoundary_complete_le μ p n ω)
  unfold parsingBoundary
  -- `((take j L).map length).sum ≤ ((L).map length).sum`. Convert `take`/`map`
  -- and use `sum_take + sum_drop = sum` on the ℕ-valued length list.
  rw [List.take_length, List.map_take]
  set lens : List ℕ := (lz78PhraseStrings (List.ofFn (p.blockRV n ω))).map List.length
    with hlens
  have hsplit : (lens.take j).sum + (lens.drop j).sum = lens.sum :=
    List.sum_take_add_sum_drop lens j
  have hdrop : 0 ≤ (lens.drop j).sum := Nat.zero_le _
  omega

end InformationTheory.Shannon
