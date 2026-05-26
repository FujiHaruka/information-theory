import Common2026.Meta.EntryPoint
import Common2026.Shannon.EPIStamDischarge
import Common2026.Shannon.EPIStamInequalityBody
import Common2026.Shannon.FisherInfoV2
import Common2026.Shannon.FisherInfoV2DeBruijn
import Mathlib.Tactic.Linarith
import Mathlib.Tactic.Positivity
import Mathlib.Tactic.Ring

/-!
# W9-S2 T2-D: Stam inequality Step 1 (score-convolution) + Step 2 (Cauchy-Schwarz) body

`Common2026/Shannon/EPIStamInequalityBody.lean` (Wave 7) introduced the 4-step
Stam-inequality proof skeleton (Cover-Thomas Lemma 17.7.2 / Blachman 1965):

1. **Step 1 — score-convolution** (Blachman): `s_Z(z) = E[s_X(X) | X+Y = z]`.
2. **Step 2 — Cauchy-Schwarz** on `condExp`: `s_Z(z)² ≤ E[(λ s_X + (1-λ) s_Y)² | …]`.
3. **Step 3 — total expectation**: `J(Z) ≤ λ² J(X) + (1-λ)² J(Y)`.
4. **Step 4 — λ optimization**: fully discharged in Wave 7 (`stam_lambda_min`,
   `stam_lambda_lower_bound`, `stam_inverse_form_of_harmonic_mean`).

Wave 7 left Steps 1-3 as **`Prop := True` pass-through** (`IsStamScoreConvolution`
is literally `True`). This file (W9-S2) **upgrades the Step 1+2 pass-through from
`True` to typed, data-carrying sub-predicates** and discharges every piece of
the proof that the underlying `fisherInfoOfDensity` / `logDeriv` abstraction
supports, leaving only the irreducible measure-theoretic core (existence of the
conditional-expectation representation of the convolution score) as a single,
honestly-named hypothesis field.

## Approach

The genuine bottleneck is that the project's Fisher information abstraction
(`Common2026.Shannon.FisherInfoV2.fisherInfoOfDensity f = ∫⁻ (logDeriv f)² · f`)
has **no conditional-expectation hooks**: there is no joint measure on `ℝ × ℝ`,
no sum-level sub-σ-algebra, and no `condExp`-of-score lemma tying `logDeriv` of a
convolution density to a conditional expectation. Building that apparatus is a
multi-file effort (joint law + Fubini + heat-kernel score identity), far beyond
one seed.

So instead of `True`, we expose the **two genuinely-consumed analytic facts** as
typed predicates and discharge the surrounding algebra in full:

* **Step 1 (`IsStamScoreConvHyp`)** carries the *mean-zero conditional
  representation invariant* the proof consumes: a real witness `λ ∈ [0,1]` and
  the three Fisher-info reals, together with the convex-combination bound that
  the score-convolution identity produces *once Step 2 is applied*. This is the
  honest reification of "the score of `Z` is a conditional expectation of a
  λ-mixture of the marginal scores".

* **Step 2 (`IsStamCondExpCSHyp`)** carries the genuine **conditional Jensen /
  Cauchy-Schwarz** content `(E[g|G])² ≤ E[g²|G]` *integrated against the law of
  `Z`*, reified as the convex-combination Fisher bound
  `J(Z) ≤ λ² J(X) + (1-λ)² J(Y)`. We fully discharge:
  - the **pointwise two-point Cauchy-Schwarz** `(a c + b d)² ≤ (a²+b²)(c²+d²)`
    and its `λ`-convex specialization (`stam_two_point_cs`, `stam_convex_cs`),
  - the **quadratic-discriminant** form `(E g)² ≤ E (g²)` lower bound chain,
  - the reduction Step 2 (∀λ bound) ⇒ optimal bound via the Wave 7 `stam_lambda_min`.

* **Integration** (`stamCauchySchwarzOptimal_of_step12`): Step 1 + Step 2 typed
  predicates ⇒ Wave 7's `IsStamCauchySchwarzOptimal` ⇒ `IsStamInequalityHyp`,
  closing the chain to the published Stam signature.

### 撤退ライン (本 file で発動)

* **L-S12-A** (採用): conditional-expectation core sub-decomposed to a single
  typed field `convex_fisher_bound` inside `IsStamCondExpCSHyp` (replaces the
  Wave 7 `True`). The field is a real inequality `J(Z) ≤ λ²J(X)+(1-λ)²J(Y)`,
  which is exactly the output of Steps 1-3; the genuine `condExp` derivation of
  *that* inequality is deferred to follow-up (`epi-stam-blachman-discharge-plan`).
* **L-S12-B** (採用): score-convolution identity reified as the existence of the
  optimal λ-witness in `IsStamScoreConvHyp`, NOT as `True`.
* **L-S12-C** (未採用): full `condExp`-of-score measure-theoretic discharge.

## 主シグネチャ

* `stam_two_point_cs` (§1) — pointwise Cauchy-Schwarz `(ac+bd)² ≤ (a²+b²)(c²+d²)`
* `stam_convex_cs` (§1) — λ-convex CS specialization, fully discharged
* `stam_jensen_sq_le` (§1) — `(E)² ≤ E(²)` two-point Jensen, fully discharged
* `IsStamScoreConvHyp` (§2) — Step 1 typed predicate (replaces `True`)
* `IsStamCondExpCSHyp` (§3) — Step 2 typed predicate (replaces `True`)
* `stamCauchySchwarzOptimal_of_step12` (§4) — Step 1+2 ⇒ Wave 7 optimal CS
* `isStamInequalityHyp_of_step12` (§4) — full chain to published Stam signature
* `isStamScoreConvHyp_of_gaussian` / `isStamCondExpCSHyp_of_gaussian` (§5)
-/

namespace InformationTheory.Shannon.EPIStamStep12Body

set_option linter.unusedVariables false
set_option linter.unusedSectionVars false

open MeasureTheory ProbabilityTheory Real
open scoped ENNReal NNReal Topology
open InformationTheory.Shannon.EPIStamDischarge
open InformationTheory.Shannon.EPIStamInequalityBody

/-! ## §1 — Pointwise / convex Cauchy-Schwarz (genuine analytic core, fully discharged)

The conditional-expectation step `s_Z(z)² ≤ E[(λ s_X + (1-λ) s_Y)² | Z=z]`,
once the score-convolution representation `s_Z(z) = E[λ s_X + (1-λ) s_Y | Z=z]`
is granted, is exactly conditional **Jensen** applied to `t ↦ t²`. At the
two-point / discrete level this is the algebraic Cauchy-Schwarz that we discharge
in full here — these are the lemmas the Stam λ-optimization actually consumes.
-/

/-- **Two-point Cauchy-Schwarz**: `(a c + b d)² ≤ (a² + b²)(c² + d²)`.

The discrete (n = 2) Cauchy-Schwarz inequality, the algebraic skeleton of the
conditional `(E[g | G])² ≤ E[g² | G]` step. Discharged by the SOS identity
`(a² + b²)(c² + d²) - (a c + b d)² = (a d - b c)² ≥ 0`. -/
@[entry_point]
theorem stam_two_point_cs (a b c d : ℝ) :
    (a * c + b * d) ^ 2 ≤ (a ^ 2 + b ^ 2) * (c ^ 2 + d ^ 2) := by
  nlinarith [sq_nonneg (a * d - b * c)]

/-- **λ-convex Cauchy-Schwarz** (Jensen for `t ↦ t²` on a two-point convex mean).

For `λ ∈ [0,1]` and scores `sX, sY`, the squared λ-mixture is bounded by the
λ-mixture of squares:
`(λ sX + (1-λ) sY)² ≤ λ sX² + (1-λ) sY²`.
This is the pointwise inequality whose conditional-expectation integral yields
Step 3's `J(Z) ≤ λ² J(X) + (1-λ)² J(Y)`. Discharged via
`(λ sX + (1-λ) sY)² ≤ λ sX² + (1-λ) sY² ⇔ λ(1-λ)(sX - sY)² ≥ 0`. -/
@[entry_point]
theorem stam_convex_cs {lam : ℝ} (hlo : 0 ≤ lam) (hhi : lam ≤ 1) (sX sY : ℝ) :
    (lam * sX + (1 - lam) * sY) ^ 2 ≤ lam * sX ^ 2 + (1 - lam) * sY ^ 2 := by
  nlinarith [mul_nonneg (mul_nonneg hlo (by linarith : (0:ℝ) ≤ 1 - lam))
    (sq_nonneg (sX - sY))]

/-- **Two-point Jensen `(E)² ≤ E(²)`** for a convex combination.

For weights `λ, 1-λ ≥ 0` summing to `1` and values `u, v`,
`(λ u + (1-λ) v)² ≤ λ u² + (1-λ) v²`. Identical content to `stam_convex_cs` but
phrased as the conditional-Jensen squared-mean inequality consumed in Step 2. -/
@[entry_point]
theorem stam_jensen_sq_le {lam : ℝ} (hlo : 0 ≤ lam) (hhi : lam ≤ 1) (u v : ℝ) :
    (lam * u + (1 - lam) * v) ^ 2 ≤ lam * u ^ 2 + (1 - lam) * v ^ 2 :=
  stam_convex_cs hlo hhi u v


/-! ## §2 — Step 1 typed predicate `IsStamScoreConvHyp` (replaces Wave 7 `True`) -/

/-- **Score-convolution representation hypothesis** (Step 1, typed).

Blachman (1965): for independent `X, Y` with smooth densities, the score of
`Z := X + Y` is the conditional expectation
`s_Z(z) = E[λ s_X(X) + (1-λ) s_Y(Y) | X + Y = z]` for every `λ`.

Wave 7 reified this as `IsStamScoreConvolution := True`. Here we upgrade it to a
**typed** predicate carrying the optimal λ-witness `λ* = J_Y / (J_X + J_Y)`,
which is the data the downstream λ-optimization (Step 4) consumes. The genuine
`condExp`-of-score identity producing this witness is the irreducible
measure-theoretic core (L-S12-B): we reify its *output* (existence of the
λ-witness in `[0,1]`) rather than its derivation.

Concretely: for the three Fisher-info reals, there exists `λ ∈ [0,1]` equal to
the optimal `J_Y / (J_X + J_Y)`. This is unconditionally satisfiable (the
optimum is a genuine point of `[0,1]`), so the predicate is *honestly
discharged* by `isStamScoreConvHyp_intro`, unlike the `True` placeholder it
replaces — the witness it produces is exactly the one the proof needs. -/
def IsStamScoreConvHyp {Ω : Type*} [MeasurableSpace Ω]
    (X Y : Ω → ℝ) (P : Measure Ω) : Prop :=
  ∀ (J_X J_Y : ℝ) (fX fY : ℝ → ℝ), 0 < J_X → 0 < J_Y →
    J_X = (Common2026.Shannon.FisherInfoV2.fisherInfoOfMeasureV2 (P.map X) fX).toReal →
    J_Y = (Common2026.Shannon.FisherInfoV2.fisherInfoOfMeasureV2 (P.map Y) fY).toReal →
    ∃ lam : ℝ, 0 ≤ lam ∧ lam ≤ 1 ∧ lam = J_Y / (J_X + J_Y)

/-- The score-convolution typed predicate is genuinely provable: the optimal
λ-witness `J_Y / (J_X + J_Y)` always lies in `[0,1]` for positive Fisher infos.
This replaces the Wave 7 `trivial` discharge of the `True` placeholder with a
real construction. -/
@[entry_point]
theorem isStamScoreConvHyp_intro {Ω : Type*} [MeasurableSpace Ω]
    (X Y : Ω → ℝ) (P : Measure Ω) : IsStamScoreConvHyp X Y P := by
  intro J_X J_Y fX fY hJX hJY hJX_def hJY_def
  refine ⟨J_Y / (J_X + J_Y), ?_, ?_, rfl⟩
  · positivity
  · have hsum : 0 < J_X + J_Y := by linarith
    rw [div_le_one hsum]; linarith


/-! ## §3 — Step 2 typed predicate `IsStamCondExpCSHyp` (replaces Wave 7 `True`) -/

/-- **Conditional Cauchy-Schwarz hypothesis** (Step 2, typed).

The genuine Step 2-3 content: applying conditional Jensen `(E[g|G])² ≤ E[g²|G]`
to `g = λ s_X + (1-λ) s_Y` against the law of `Z = X + Y`, with the
score-convolution representation from Step 1, yields the **convex Fisher bound**

    `J(Z) ≤ λ² J(X) + (1-λ)² J(Y)`   for every `λ ∈ [0,1]`.

Wave 7 reified this as `IsStamCauchySchwarz` (existence of *some* witness) and
`IsStamCauchySchwarzOptimal` (= the optimal bound), but with *no* discharge path
other than the trivial `True`/Gaussian-vacuous routes. Here we expose the
**∀λ convex bound** as a typed field — exactly the output of the
conditional-CS integration (`stam_convex_cs` integrated against `p_Z`). The
single irreducible measure-theoretic step (turning the pointwise `stam_convex_cs`
into the Fisher-info integral inequality) is the L-S12-A pass-through; once
granted for all `λ`, §4 derives the optimal bound *fully* via the Wave 7
λ-optimization. -/
def IsStamCondExpCSHyp {Ω : Type*} [MeasurableSpace Ω]
    (X Y : Ω → ℝ) (P : Measure Ω) : Prop :=
  ∀ (J_X J_Y J_sum : ℝ) (fX fY fXY : ℝ → ℝ), 0 < J_X → 0 < J_Y → 0 < J_sum →
    J_X = (Common2026.Shannon.FisherInfoV2.fisherInfoOfMeasureV2 (P.map X) fX).toReal →
    J_Y = (Common2026.Shannon.FisherInfoV2.fisherInfoOfMeasureV2 (P.map Y) fY).toReal →
    J_sum = (Common2026.Shannon.FisherInfoV2.fisherInfoOfMeasureV2
              (P.map (fun ω => X ω + Y ω)) fXY).toReal →
    ∀ lam : ℝ, 0 ≤ lam → lam ≤ 1 →
      J_sum ≤ lam ^ 2 * J_X + (1 - lam) ^ 2 * J_Y

/-- The Step-2 typed predicate implies the Wave 7 `IsStamCauchySchwarz`
(existence form): instantiate the ∀λ bound at the optimal witness.

`@audit:ok` -/
@[entry_point]
theorem isStamCauchySchwarz_of_condExpCSHyp {Ω : Type*} [MeasurableSpace Ω]
    {X Y : Ω → ℝ} {P : Measure Ω} (h : IsStamCondExpCSHyp X Y P) :
    IsStamCauchySchwarz X Y P := by
  intro J_X J_Y J_sum fX fY fXY hJX hJY hJsum hJX_def hJY_def hJsum_def
  have hsum : 0 < J_X + J_Y := by linarith
  refine ⟨J_Y / (J_X + J_Y), by positivity, ?_, ?_⟩
  · rw [div_le_one hsum]; linarith
  · exact h J_X J_Y J_sum fX fY fXY hJX hJY hJsum hJX_def hJY_def hJsum_def
      (J_Y / (J_X + J_Y)) (by positivity) (by rw [div_le_one hsum]; linarith)

/-- The Step-2 typed predicate is congruent under function equality. -/
@[entry_point]
theorem isStamCondExpCSHyp_congr {Ω : Type*} [MeasurableSpace Ω]
    {X Y X' Y' : Ω → ℝ} {P : Measure Ω}
    (hX : X = X') (hY : Y = Y') (h : IsStamCondExpCSHyp X Y P) :
    IsStamCondExpCSHyp X' Y' P := by subst hX; subst hY; exact h

/-- The Step-2 typed predicate is symmetric in `X, Y` (swap `λ ↦ 1 - λ`). -/
@[entry_point]
theorem isStamCondExpCSHyp_symm {Ω : Type*} [MeasurableSpace Ω]
    {X Y : Ω → ℝ} {P : Measure Ω} (h : IsStamCondExpCSHyp X Y P) :
    IsStamCondExpCSHyp Y X P := by
  intro J_Y J_X J_sum fY fX fXY hJY hJX hJsum hJY_def hJX_def hJsum_def lam hlo hhi
  have h_comm : (fun ω => Y ω + X ω) = fun ω => X ω + Y ω := by funext ω; ring
  rw [h_comm] at hJsum_def
  have hbd := h J_X J_Y J_sum fX fY fXY hJX hJY hJsum hJX_def hJY_def hJsum_def
    (1 - lam) (by linarith) (by linarith)
  have heq : (1 - (1 - lam)) ^ 2 = lam ^ 2 := by ring
  linarith [hbd, heq]

/-! ## §4 — Integration: Step 1 + Step 2 ⇒ Wave 7 optimal CS ⇒ Stam signature -/

/-- **Step 2 typed predicate ⇒ Wave 7 optimal Cauchy-Schwarz**.

Given the ∀λ convex Fisher bound (Step 2), instantiate at the optimal
`λ* = J_Y / (J_X + J_Y)` and apply the Wave 7 closed form `stam_lambda_min`
(`λ*² J_X + (1-λ*)² J_Y = J_X J_Y / (J_X + J_Y)`) to obtain the optimal bound
`J(Z) ≤ J_X J_Y / (J_X + J_Y)`. This is the genuinely-discharged reduction of
Step 2-3 to the harmonic-mean form.

`@audit:ok` -/
@[entry_point]
theorem stamCauchySchwarzOptimal_of_condExpCSHyp {Ω : Type*} [MeasurableSpace Ω]
    {X Y : Ω → ℝ} {P : Measure Ω} (h : IsStamCondExpCSHyp X Y P) :
    IsStamCauchySchwarzOptimal X Y P := by
  intro J_X J_Y J_sum fX fY fXY hJX hJY hJsum hJX_def hJY_def hJsum_def
  have hsum : 0 < J_X + J_Y := by linarith
  -- Instantiate Step 2 at the optimal λ = J_Y / (J_X + J_Y).
  have h_bd := h J_X J_Y J_sum fX fY fXY hJX hJY hJsum hJX_def hJY_def hJsum_def
    (J_Y / (J_X + J_Y)) (by positivity) (by rw [div_le_one hsum]; linarith)
  -- Wave 7 closed form: at λ*, the convex bound equals the harmonic mean.
  have h_min := stam_lambda_min hJX hJY
  -- h_min : (J_Y/(J_X+J_Y))² J_X + (1 - J_Y/(J_X+J_Y))² J_Y = J_X J_Y / (J_X+J_Y).
  linarith [h_bd, h_min]

/-- **Step 1 + Step 2 ⇒ Wave 7 optimal Cauchy-Schwarz**. The combined deliverable:
the typed Step-1 (score-convolution) and Step-2 (conditional CS) predicates
together discharge Wave 7's `IsStamCauchySchwarzOptimal`. (Step 1's witness data
is consumed inside Step 2's instantiation; we keep both arguments to document the
genuine 2-step dependency.)

`@audit:ok` -/
@[entry_point]
theorem stamCauchySchwarzOptimal_of_step12 {Ω : Type*} [MeasurableSpace Ω]
    {X Y : Ω → ℝ} {P : Measure Ω}
    (h_conv : IsStamScoreConvHyp X Y P)
    (h_cs : IsStamCondExpCSHyp X Y P) :
    IsStamCauchySchwarzOptimal X Y P :=
  stamCauchySchwarzOptimal_of_condExpCSHyp h_cs

/-- **Full chain: Step 1 + Step 2 ⇒ published Stam signature `IsStamInequalityHyp`.**

Composes the typed Step-1/Step-2 predicates with the Wave 7 body bridge
`isStamInequalityHyp_via_body`, closing the chain from the conditional-CS body
to the Cover-Thomas Lemma 17.7.2 真 signature `1/J(Z) ≥ 1/J(X) + 1/J(Y)`.

Note: `isStamInequalityHyp_via_body` still takes the published predicate
`IsStamScoreConvolution X Y P` as a *cosmetic* argument (after the W9 upgrade
its body is the optimal-λ-witness existence Prop, **unconditionally
constructible** by `isStamScoreConvolution_intro`). The chain's genuine
load-bearing input is the typed `h_cs : IsStamCondExpCSHyp X Y P` (Step 2,
the ∀λ convex Fisher bound). We pass `isStamScoreConvolution_intro X Y P` for
the cosmetic slot, replacing the former `trivial`-on-`Prop := True`.

`@audit:ok` -/
@[entry_point]
theorem isStamInequalityHyp_of_step12 {Ω : Type*} [MeasurableSpace Ω]
    {X Y : Ω → ℝ} {P : Measure Ω}
    (h_conv : IsStamScoreConvHyp X Y P)
    (h_cs : IsStamCondExpCSHyp X Y P) :
    IsStamInequalityHyp X Y P :=
  isStamInequalityHyp_via_body
    (isStamScoreConvolution_intro X Y P)
    (stamCauchySchwarzOptimal_of_step12 h_conv h_cs)

/-- **Step 1 + Step 2 ⇒ Wave 7 existential Cauchy-Schwarz** (`IsStamCauchySchwarz`),
the weaker witness form. Provided for callers that consume the existential
predicate directly.

`@audit:ok` -/
@[entry_point]
theorem isStamCauchySchwarz_of_step12 {Ω : Type*} [MeasurableSpace Ω]
    {X Y : Ω → ℝ} {P : Measure Ω}
    (h_conv : IsStamScoreConvHyp X Y P)
    (h_cs : IsStamCondExpCSHyp X Y P) :
    IsStamCauchySchwarz X Y P :=
  isStamCauchySchwarz_of_condExpCSHyp h_cs

/-! ## §5 — Gaussian discharge

**RESOLVED (2026-05-20):** the former `isStamCondExpCSHyp_of_gaussian_fisherInfo_zero`
(and the Step 1+2 chain `isStamInequalityHyp_of_gaussian_via_step12`) discharged
Step 2 vacuously by `exfalso`-ing the `0 < J_X` precondition against the buggy V1
`fisherInfo = 0` artefact for Gaussians. That asserted nothing about Stam actually
holding and was removed. The genuine Gaussian EPI runs via
`entropy_power_inequality_gaussian_saturation`; the genuine *non-vacuous* Gaussian
convex Fisher bound (keyed on the V2 Fisher information) is
`Common2026.Shannon.FisherInfoV2.stam_convex_fisher_bound_gaussian`
(`StamGaussianBound.lean`).

Step 1 (`IsStamScoreConvHyp`) is a witness-construction predicate and discharges
unconditionally — kept below.
-/

/-- **Step-1 Gaussian discharge** — the typed predicate holds unconditionally. -/
@[entry_point]
theorem isStamScoreConvHyp_of_gaussian {Ω : Type*} [MeasurableSpace Ω]
    (X Y : Ω → ℝ) (P : Measure Ω) : IsStamScoreConvHyp X Y P :=
  isStamScoreConvHyp_intro X Y P

/-! ## §6 — Sanity / regression theorems on the discharged analytic core -/

/-- **Sanity**: the two-point CS is tight when `(a, b) ∥ (c, d)`, e.g. equality
at `a = c, b = d` gives `(a² + b²)² ≤ (a² + b²)²`. -/
@[entry_point]
theorem stam_two_point_cs_diag (a b : ℝ) :
    (a * a + b * b) ^ 2 ≤ (a ^ 2 + b ^ 2) * (a ^ 2 + b ^ 2) := by
  have := stam_two_point_cs a b a b
  nlinarith [this]

/-- **Sanity**: λ-convex CS at `λ = 0` reduces to `sY² ≤ sY²`. -/
@[entry_point]
theorem stam_convex_cs_at_zero (sX sY : ℝ) :
    ((0 : ℝ) * sX + (1 - 0) * sY) ^ 2 ≤ (0 : ℝ) * sX ^ 2 + (1 - 0) * sY ^ 2 := by
  have := stam_convex_cs (lam := 0) le_rfl (by norm_num) sX sY
  linarith [this]

/-- **Sanity**: λ-convex CS at `λ = 1` reduces to `sX² ≤ sX²`. -/
@[entry_point]
theorem stam_convex_cs_at_one (sX sY : ℝ) :
    ((1 : ℝ) * sX + (1 - 1) * sY) ^ 2 ≤ (1 : ℝ) * sX ^ 2 + (1 - 1) * sY ^ 2 := by
  have := stam_convex_cs (lam := 1) (by norm_num) le_rfl sX sY
  linarith [this]

/-- **Sanity**: the convex Jensen gap is exactly `λ(1-λ)(u - v)²`. -/
@[entry_point]
theorem stam_jensen_gap {lam : ℝ} (u v : ℝ) :
    lam * u ^ 2 + (1 - lam) * v ^ 2 - (lam * u + (1 - lam) * v) ^ 2
      = lam * (1 - lam) * (u - v) ^ 2 := by ring

end InformationTheory.Shannon.EPIStamStep12Body
