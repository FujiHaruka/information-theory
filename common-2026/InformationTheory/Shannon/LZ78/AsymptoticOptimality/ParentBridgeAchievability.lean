import InformationTheory.Meta.EntryPoint
import InformationTheory.Shannon.LZ78.Basic
import InformationTheory.Shannon.LZ78.GreedyParsing
import InformationTheory.Shannon.LZ78.GreedyLongestPrefix
import InformationTheory.Shannon.LZ78.PhraseCounting
import InformationTheory.Shannon.LZ78.ZivAchievabilityComposition
import InformationTheory.Shannon.SMB.AlgoetCover.Liminf
import Mathlib.Data.Nat.Log
import Mathlib.Data.List.Basic
import Mathlib.Data.List.Range
import Mathlib.Analysis.SpecialFunctions.Log.Base
import Mathlib.Topology.Order.LiminfLimsup
import Mathlib.Topology.Algebra.GroupWithZero
import InformationTheory.Shannon.LZ78.AsymptoticOptimality.EncodingLength
import InformationTheory.Shannon.LZ78.AsymptoticOptimality.ParentBridgeConverse

/-! # LZ78 parent-bridge: Ziv achievability + asymptotic-optimality headline (part 3/3) -/

namespace InformationTheory.Shannon

open scoped Topology

set_option linter.unusedSectionVars false

/-! ## §3. Parent-theorem bridge (continued) -/

section ParentBridge

variable {α : Type*} [Fintype α] [DecidableEq α] [Nonempty α]
  [MeasurableSpace α] [MeasurableSingletonClass α]
variable {Ω : Type*} [MeasurableSpace Ω]

open MeasureTheory ProbabilityTheory
open scoped ENNReal

/-- Elementary log bound `log t ≤ 2 · √t` for `t > 0`, used to control the
`c · log(Ntot / c)` boundary term of the achievability composition. -/
private theorem log_le_two_sqrt (t : ℝ) (ht : 0 < t) :
    Real.log t ≤ 2 * Real.sqrt t := by
  have hlog : Real.log (Real.sqrt t) = Real.log t / 2 := Real.log_sqrt ht.le
  nlinarith [Real.log_le_sub_one_of_pos (Real.sqrt_pos.mpr ht), Real.sqrt_nonneg t]

/-- The `c · log(Ntot / c)` boundary term of the achievability composition,
controlled by `2 · n · √(c' / n)`, where `c ≤ c'` and `Ntot ≤ n`. The `c = 0`
boundary degenerates to `0 ≤ …`; otherwise `c · log(Ntot/c) ≤ c · log(n/c) =
2 · √(c · n) ≤ 2 · √(c' · n) = 2 · n · √(c'/n)` via `log_le_two_sqrt`. -/
private theorem clog_div_le_two_mul_sqrt
    (c Ntot cp n : ℝ) (hc : 0 ≤ c) (hcCp : c ≤ cp) (hcn : c ≤ n) (hNn : Ntot ≤ n)
    (hN0 : 0 ≤ Ntot) (hn : 0 < n) :
    c * Real.log (Ntot / c) ≤ 2 * n * Real.sqrt (cp / n) := by
  rcases eq_or_lt_of_le hc with hc0 | hcpos
  · rw [← hc0]; simp; positivity
  · have hCp_pos : 0 < cp := lt_of_lt_of_le hcpos hcCp
    have hstep1 : c * Real.log (Ntot / c) ≤ c * Real.log (n / c) := by
      rcases eq_or_lt_of_le hN0 with hN00 | hNpos
      · rw [← hN00]; simp
        have h1c : (1 : ℝ) ≤ n / c := by rw [le_div_iff₀ hcpos]; nlinarith
        have := Real.log_nonneg h1c
        positivity
      · apply mul_le_mul_of_nonneg_left _ hc
        apply Real.log_le_log (by positivity)
        exact div_le_div_of_nonneg_right hNn hcpos.le
    have hncpos : 0 < n / c := by positivity
    have hlogbd : Real.log (n / c) ≤ 2 * Real.sqrt (n / c) := log_le_two_sqrt _ hncpos
    have hstep2 : c * Real.log (n / c) ≤ c * (2 * Real.sqrt (n / c)) :=
      mul_le_mul_of_nonneg_left hlogbd hc
    have hcn_eq : c * Real.sqrt (n / c) = Real.sqrt (c * n) := by
      rw [Real.sqrt_mul hcpos.le n, Real.sqrt_div' n hcpos.le, mul_div_assoc']
      rw [div_eq_iff (Real.sqrt_pos.mpr hcpos).ne']
      nlinarith [Real.mul_self_sqrt hcpos.le, Real.sqrt_nonneg n, Real.sqrt_nonneg c]
    have hsqrt_eq : c * (2 * Real.sqrt (n / c)) = 2 * Real.sqrt (c * n) := by
      rw [show c * (2 * Real.sqrt (n / c)) = 2 * (c * Real.sqrt (n / c)) by ring, hcn_eq]
    rw [hsqrt_eq] at hstep2
    have hn_eq : n * Real.sqrt (cp / n) = Real.sqrt (n * cp) := by
      rw [Real.sqrt_mul hn.le cp, Real.sqrt_div' cp hn.le, mul_div_assoc']
      rw [div_eq_iff (Real.sqrt_pos.mpr hn).ne']
      nlinarith [Real.mul_self_sqrt hn.le, Real.sqrt_nonneg cp, Real.sqrt_nonneg n]
    have hrhs_eq : 2 * n * Real.sqrt (cp / n) = 2 * Real.sqrt (n * cp) := by
      rw [show 2 * n * Real.sqrt (cp / n) = 2 * (n * Real.sqrt (cp / n)) by ring, hn_eq]
    rw [hrhs_eq]
    have hmono : Real.sqrt (c * n) ≤ Real.sqrt (n * cp) :=
      Real.sqrt_le_sqrt (by nlinarith)
    calc c * Real.log (Ntot / c) ≤ 2 * Real.sqrt (c * n) := le_trans hstep1 hstep2
      _ ≤ 2 * Real.sqrt (n * cp) := by linarith [hmono]

/-- Reconcile term: with `cp = c + b`, `b ≤ K`, `1 ≤ c`, `cp ≤ n`, the genuine
distinct-phrase product `cp · log cp` is bounded by the composition product
`c · log c` plus the `o(n)` reconcile slack `K + K · log n`. Uses
`log(1 + b/c) ≤ b/c`. -/
private theorem cp_log_cp_le_reconcile
    (c cp b n K : ℝ) (hc : 1 ≤ c) (hcp : cp = c + b) (hb : 0 ≤ b) (hbK : b ≤ K)
    (hcpn : cp ≤ n) (hcppos : 1 ≤ cp) :
    cp * Real.log cp ≤ c * Real.log c + (K + K * Real.log n) := by
  have hcpos : 0 < c := lt_of_lt_of_le one_pos hc
  have hcppos' : 0 < cp := lt_of_lt_of_le one_pos hcppos
  have e1 : cp * Real.log cp = c * Real.log cp + b * Real.log cp := by rw [hcp]; ring
  have e2 : c * Real.log cp = c * Real.log c + c * Real.log (cp / c) := by
    rw [Real.log_div hcppos'.ne' hcpos.ne']; ring
  have hbound1 : c * Real.log (cp / c) ≤ b := by
    have hcpc : cp / c = 1 + b / c := by rw [hcp]; field_simp
    rw [hcpc]
    have hlog : Real.log (1 + b / c) ≤ b / c := by
      have := Real.log_le_sub_one_of_pos (show (0 : ℝ) < 1 + b / c by positivity)
      linarith [this]
    calc c * Real.log (1 + b / c) ≤ c * (b / c) :=
          mul_le_mul_of_nonneg_left hlog hcpos.le
      _ = b := by field_simp
  have hbound2 : b * Real.log cp ≤ K * Real.log n := by
    have hlogcp_nn : 0 ≤ Real.log cp := Real.log_nonneg hcppos
    have hlogcp_le : Real.log cp ≤ Real.log n := Real.log_le_log hcppos' hcpn
    have hKnn : 0 ≤ K := le_trans hb hbK
    calc b * Real.log cp ≤ K * Real.log cp :=
          mul_le_mul_of_nonneg_right hbK hlogcp_nn
      _ ≤ K * Real.log n := mul_le_mul_of_nonneg_left hlogcp_le hKnn
  rw [e1, e2]; linarith

theorem cp_log_cp_le_reconcile_cases (cR cp bR n K : ℝ)
    (hcR_nn : 0 ≤ cR) (hcount : cp = cR + bR) (hbR_nn : 0 ≤ bR) (hbA : bR ≤ K)
    (hcp_le_n : cp ≤ n) (hlogn_nn : 0 ≤ Real.log n) (hK_nn : 0 ≤ K)
    (hcp_zero : cp < 1 → cp = 0) (hcR_zero : cR < 1 → cR = 0) :
    cp * Real.log cp ≤ cR * Real.log cR + (K + K * Real.log n) := by
  have hcR_le_cp : cR ≤ cp := by rw [hcount]; linarith
  rcases lt_or_ge cp 1 with hlt | hge
  · -- `cp < 1` ⇒ `cp = 0` ⇒ `cR = 0` too.
    have hcp0 : cp = 0 := hcp_zero hlt
    have hcR0 : cR = 0 := le_antisymm (by linarith [hcR_le_cp, hcp0]) hcR_nn
    rw [hcp0, hcR0]
    simp only [Real.log_zero, mul_zero, zero_add]
    positivity
  · -- `cp ≥ 1`. Two cases on `cR`.
    rcases lt_or_ge cR 1 with hcRlt | hcRge
    · -- `cR < 1` ⇒ `cR = 0` ⇒ `cp = bR ≤ K`, so `cp log cp` is small.
      have hcR0 : cR = 0 := hcR_zero hcRlt
      have hcp_eq_b : cp = bR := by rw [hcount, hcR0]; ring
      have hcp_le_k1 : cp ≤ K := by rw [hcp_eq_b]; exact hbA
      have hlogcp_le : Real.log cp ≤ Real.log n :=
        Real.log_le_log (by linarith) hcp_le_n
      have hlogcp_nn : 0 ≤ Real.log cp := Real.log_nonneg hge
      rw [hcR0]; simp only [Real.log_zero, mul_zero, zero_add]
      calc cp * Real.log cp ≤ K * Real.log n :=
            mul_le_mul hcp_le_k1 hlogcp_le hlogcp_nn hK_nn
        _ ≤ K + K * Real.log n := by linarith
    · -- `1 ≤ cR` and `1 ≤ cp`: the generic reconcile lemma.
      exact cp_log_cp_le_reconcile cR cp bR n K hcRge hcount hbR_nn hbA hcp_le_n hge

theorem ziv_cp_div_tendsto_zero (cp : ℕ → ℝ) (hcp_nn : ∀ n, 0 ≤ cp n)
    (hBigO : cp =O[Filter.atTop] (fun n : ℕ => (n : ℝ) / Real.log (n : ℝ))) :
    Filter.Tendsto (fun n => cp n / (n : ℝ)) Filter.atTop (𝓝 0) := by
  obtain ⟨C, hCb⟩ := hBigO.bound
  have hub : Filter.Tendsto (fun n : ℕ => C * (Real.log (n : ℝ))⁻¹)
      Filter.atTop (𝓝 0) := by
    have h1 : Filter.Tendsto (fun n : ℕ => Real.log (n : ℝ))
        Filter.atTop Filter.atTop :=
      Real.tendsto_log_atTop.comp tendsto_natCast_atTop_atTop
    simpa using (tendsto_inv_atTop_zero.comp h1).const_mul C
  refine squeeze_zero_norm' ?_ hub
  filter_upwards [hCb, Filter.eventually_gt_atTop 1] with n hn hn1
  have hnpos : (0 : ℝ) < (n : ℝ) := by positivity
  have hlogpos : (0 : ℝ) < Real.log (n : ℝ) :=
    Real.log_pos (by exact_mod_cast hn1)
  rw [Real.norm_eq_abs, abs_of_nonneg (div_nonneg (hcp_nn n) hnpos.le)]
  rw [Real.norm_eq_abs, abs_of_nonneg (hcp_nn n)] at hn
  have hng : ‖(n : ℝ) / Real.log (n : ℝ)‖ = (n : ℝ) / Real.log (n : ℝ) := by
    rw [Real.norm_eq_abs, abs_of_nonneg (le_of_lt (div_pos hnpos hlogpos))]
  rw [hng] at hn
  calc cp n / (n : ℝ) ≤ (C * ((n : ℝ) / Real.log (n : ℝ))) / (n : ℝ) :=
        div_le_div_of_nonneg_right hn hnpos.le
    _ = C * (Real.log (n : ℝ))⁻¹ := by
        rw [mul_div_assoc, div_div, mul_comm (Real.log (n : ℝ)) (n : ℝ), ← div_div,
          div_self hnpos.ne', one_div]

theorem ziv_error_seq_tendsto_zero (cp : ℕ → ℝ) (k : ℕ) (La L : ℝ)
    (hcp_div : Filter.Tendsto (fun n => cp n / (n : ℝ)) Filter.atTop (𝓝 0)) :
    Filter.Tendsto
      (fun n : ℕ =>
        (2 * (n : ℝ) * Real.sqrt (cp n / (n : ℝ)) + cp n + cp n * ((k : ℝ) * La)
          + ((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)
          + (cp n * Real.log 2 + cp n * (L + 2))) / (Real.log 2 * (n : ℝ)))
      Filter.atTop (𝓝 0) := by
  have hsqrt : Filter.Tendsto (fun n : ℕ => Real.sqrt (cp n / (n : ℝ)))
      Filter.atTop (𝓝 0) := by
    have h := (Real.continuous_sqrt.tendsto 0).comp hcp_div
    simp only [Function.comp_def, Real.sqrt_zero] at h
    exact h
  have hinv : Filter.Tendsto (fun n : ℕ => (1 : ℝ) / (n : ℝ))
      Filter.atTop (𝓝 0) := tendsto_one_div_atTop_nhds_zero_nat
  have hlogn : Filter.Tendsto (fun n : ℕ => Real.log (n : ℝ) / (n : ℝ))
      Filter.atTop (𝓝 0) := by
    have hR : Filter.Tendsto (fun x : ℝ => Real.log x ^ 1 / (1 * x + 0))
        Filter.atTop (𝓝 0) := Real.tendsto_pow_log_div_mul_add_atTop 1 0 1 (by norm_num)
    simpa using hR.comp tendsto_natCast_atTop_atTop
  set g : ℕ → ℝ := fun n =>
    (2 / Real.log 2) * Real.sqrt (cp n / (n : ℝ))
    + (1 / Real.log 2) * (cp n / (n : ℝ))
    + ((k : ℝ) * La / Real.log 2) * (cp n / (n : ℝ))
    + (((k : ℝ) + 1) / Real.log 2) * ((1 : ℝ) / (n : ℝ))
    + (((k : ℝ) + 1) / Real.log 2) * (Real.log (n : ℝ) / (n : ℝ))
    + (cp n / (n : ℝ))
    + ((L + 2) / Real.log 2) * (cp n / (n : ℝ)) with hg
  have hg_tend : Filter.Tendsto g Filter.atTop (𝓝 0) := by
    have t1 := hsqrt.const_mul (2 / Real.log 2)
    have t2 := hcp_div.const_mul (1 / Real.log 2)
    have t3 := hcp_div.const_mul ((k : ℝ) * La / Real.log 2)
    have t4 := hinv.const_mul (((k : ℝ) + 1) / Real.log 2)
    have t5 := hlogn.const_mul (((k : ℝ) + 1) / Real.log 2)
    have t6 := hcp_div
    have t7 := hcp_div.const_mul ((L + 2) / Real.log 2)
    simpa [hg] using ((((((t1.add t2).add t3).add t4).add t5).add t6).add t7)
  refine hg_tend.congr' ?_
  filter_upwards [Filter.eventually_gt_atTop 0] with n hn
  have hnpos : (0 : ℝ) < (n : ℝ) := by exact_mod_cast hn
  rw [hg]
  field_simp
  ring

/-- **Lemma 1 (core)**: for each fixed `k`, the a.s.-eventual limsup of the
greedy bit-rate is at most the `k`-th conditional tail entropy in bits.

This is the per-`k` Ziv bound: combining the achievability composition
`ziv_achievability_composition` (the `c·log c ≤ negLogQk + o(n)` brick) with
the AEP `negLogQk_div_tendsto_condEntropyTail` and the deterministic
overhead-vanishing `c = O(n/log n)`, the per-symbol greedy rate is dominated
by `negLogQk/(log 2 · n) → H_k/log 2`. -/
theorem ziv_aseventual_le_condEntropyTail_bits
    (μ : Measure Ω) [IsProbabilityMeasure μ] (p : ErgodicProcess μ α) (k : ℕ) :
    ∀ᵐ ω ∂μ,
      Filter.limsup
        (fun n => (lz78GreedyEncodingLength n
            (p.toStationaryProcess.blockRV n ω) : ℝ) / (n : ℝ))
        Filter.atTop
      ≤ conditionalEntropyTail μ p.toStationaryProcess k / Real.log 2 := by
  classical
  set q := p.toStationaryProcess with hq
  set H : ℝ := conditionalEntropyTail μ q k with hH
  set La : ℝ := Real.log (Fintype.card α) with hLa
  set L : ℝ := (Nat.log 2 (Fintype.card α) : ℝ) with hL
  have hℓ2 : (0 : ℝ) < Real.log 2 := Real.log_pos (by norm_num)
  have hLa_nn : (0 : ℝ) ≤ La := Real.log_nonneg (by
    have : (1 : ℝ) ≤ (Fintype.card α : ℝ) := by exact_mod_cast Fintype.card_pos
    linarith)
  have hL_nn : (0 : ℝ) ≤ L := by rw [hL]; positivity
  filter_upwards [negLogQk_div_tendsto_condEntropyTail μ p k,
      (MeasureTheory.ae_all_iff.2 (fun n => ziv_achievability_composition μ q k n))]
    with ω h_aep h_comp
  -- Abbreviations: the genuine distinct phrase count `cp n`, the LZ78 bit-rate
  -- `T n`, and the deterministic error sequence `E n`.
  set cp : ℕ → ℝ :=
    fun n => ((lz78PhraseStrings (List.ofFn (q.blockRV n ω))).length : ℝ) with hcp
  set T : ℕ → ℝ :=
    fun n => (lz78GreedyEncodingLength n (q.blockRV n ω) : ℝ) / (n : ℝ) with hT
  set E : ℕ → ℝ := fun n =>
    (2 * (n : ℝ) * Real.sqrt (cp n / (n : ℝ)) + cp n + cp n * ((k : ℝ) * La)
      + ((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)
      + (cp n * Real.log 2 + cp n * (L + 2))) / (Real.log 2 * (n : ℝ)) with hE
  set U : ℕ → ℝ :=
    fun n => (negLogQk μ q k n ω / (n : ℝ)) / Real.log 2 + E n with hU
  -- `cp n ≥ 0` and `cp n / n → 0`.
  have hcp_nn : ∀ n, 0 ≤ cp n := fun n => by simp only [hcp]; positivity
  have hcp_div : Filter.Tendsto (fun n => cp n / (n : ℝ)) Filter.atTop (𝓝 0) :=
    ziv_cp_div_tendsto_zero cp hcp_nn
      (lz78PhraseStrings_count_isBigO (fun n => List.ofFn (q.blockRV n ω))
        (fun n => List.length_ofFn))
  -- `E n → 0` (every summand divided by `log 2 · n` vanishes via `cp/n → 0`).
  have hE_tend : Filter.Tendsto E Filter.atTop (𝓝 0) := by
    rw [hE]; exact ziv_error_seq_tendsto_zero cp k La L hcp_div
  -- `U n → H / log 2`.
  have hU_tend : Filter.Tendsto U Filter.atTop (𝓝 (H / Real.log 2)) := by
    have ha : Filter.Tendsto (fun n => negLogQk μ q k n ω / (n : ℝ) / Real.log 2)
        Filter.atTop (𝓝 (H / Real.log 2)) := h_aep.div_const (Real.log 2)
    have := ha.add hE_tend
    simpa [hU] using this
  -- Per-`n` bound: `T n ≤ U n` eventually.
  have hTU : ∀ᶠ n in Filter.atTop, T n ≤ U n := by
    filter_upwards [Filter.eventually_ge_atTop 1] with n hn1
    obtain ⟨c, bAbsorbed, Ntot, hcount, hbA, hNtot, hbound⟩ := h_comp n
    have hn : 0 < n := hn1
    have hnR : (0 : ℝ) < (n : ℝ) := by exact_mod_cast hn
    have hden_pos : (0 : ℝ) < Real.log 2 * (n : ℝ) := by positivity
    -- Real-cast abbreviations.
    set cR : ℝ := (c : ℝ) with hcR
    set bR : ℝ := (bAbsorbed : ℝ) with hbR
    set NtR : ℝ := (Ntot : ℝ) with hNtR
    have hcR_nn : (0 : ℝ) ≤ cR := by positivity
    have hbR_nn : (0 : ℝ) ≤ bR := by positivity
    have hNtR_nn : (0 : ℝ) ≤ NtR := by positivity
    -- `cp n = cR + bR`, so `cR ≤ cp n` and `cp n ≤ n`.
    have hcount' : cp n = cR + bR := by
      simp only [hcp, hcR, hbR]; rw [← Nat.cast_add, hcount]
    have hbA' : bR ≤ (k : ℝ) + 1 := by rw [hbR]; exact_mod_cast hbA
    have hNtot' : NtR ≤ (n : ℝ) := by rw [hNtR]; exact_mod_cast hNtot
    have hcp_le_n : cp n ≤ (n : ℝ) := by
      have := lz78GreedyPhraseCount_ofFn_le n (q.blockRV n ω)
      simp only [hcp]; exact_mod_cast this
    have hcR_le_cp : cR ≤ cp n := by rw [hcount']; linarith
    have hcR_le_n : cR ≤ (n : ℝ) := le_trans hcR_le_cp hcp_le_n
    -- Composition bound with `log((card α)^k) = k · log(card α)`.
    have hlogpow : Real.log (((Fintype.card α) ^ k : ℕ) : ℝ) = (k : ℝ) * La := by
      rw [hLa, Nat.cast_pow, Real.log_pow]
    have hcomp : cR * Real.log cR ≤ negLogQk μ q k n ω
        + (cR * Real.log (NtR / cR) + cR + cR * ((k : ℝ) * La)) := by
      have := hbound
      rw [hlogpow] at this
      simpa [hcR, hNtR] using this
    -- Boundary term bound: `cR · log(Ntot/cR) ≤ 2 n √(cp n / n)`.
    have hbdry : cR * Real.log (NtR / cR) ≤ 2 * (n : ℝ) * Real.sqrt (cp n / (n : ℝ)) :=
      clog_div_le_two_mul_sqrt cR NtR (cp n) (n : ℝ) hcR_nn hcR_le_cp hcR_le_n
        hNtot' hNtR_nn hnR
    -- `cp n · log(cp n) ≤ cR · log cR + reconcile`, handling the `cp n < 1` boundary.
    -- nat-ness of the phrase counts: a value `< 1` collapses to `0`.
    have hcp_zero : cp n < 1 → cp n = 0 := by
      intro hlt
      rcases Nat.eq_zero_or_pos (lz78PhraseStrings (List.ofFn (q.blockRV n ω))).length
        with h0 | hpos
      · simp only [hcp, h0]; simp
      · exfalso; simp only [hcp] at hlt
        have : (1 : ℝ) ≤ ((lz78PhraseStrings (List.ofFn (q.blockRV n ω))).length : ℝ) := by
          exact_mod_cast hpos
        linarith
    have hcR_zero : cR < 1 → cR = 0 := by
      intro hcRlt
      rcases Nat.eq_zero_or_pos c with h0 | hpos
      · rw [hcR, h0]; simp
      · exfalso
        have : (1 : ℝ) ≤ (c : ℝ) := by exact_mod_cast hpos
        rw [hcR] at hcRlt; linarith
    -- `cp n · log(cp n) ≤ cR · log cR + reconcile`, handling the `cp n < 1` boundary.
    have hrec : cp n * Real.log (cp n)
        ≤ cR * Real.log cR + (((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)) :=
      cp_log_cp_le_reconcile_cases cR (cp n) bR (n : ℝ) ((k : ℝ) + 1) hcR_nn hcount'
        hbR_nn hbA' hcp_le_n (Real.log_nonneg (by exact_mod_cast hn1)) (by positivity)
        hcp_zero hcR_zero
    -- Step A: `T n ≤ cp n · log(cp n)/(log 2 · n) + StepA-overhead/(log 2 · n)`.
    have hstepA := lz78_bitrate_le_clogc_plus_overhead n hn (q.blockRV n ω)
    -- Assemble. Clear the common `log 2 · n` denominator and chain the bounds.
    simp only [hU, hE]
    -- The Step-A RHS, rewritten via `cp`.
    have hstepA' : T n ≤ cp n * Real.log (cp n) / (Real.log 2 * (n : ℝ))
        + (cp n * Real.log 2 + cp n * (L + 2)) / (Real.log 2 * (n : ℝ)) := by
      simp only [hT, hcp, hL]; exact hstepA
    -- Bound `cp n · log(cp n) ≤ negLogQk + boundary + reconcile + alphabet`.
    have hclog : cp n * Real.log (cp n)
        ≤ negLogQk μ q k n ω
          + (2 * (n : ℝ) * Real.sqrt (cp n / (n : ℝ)) + cp n + cp n * ((k : ℝ) * La)
            + ((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)) := by
      have hcR_le_cp' : cR ≤ cp n := hcR_le_cp
      -- `cR·log(Ntot/cR) + cR + cR·k·La ≤ boundary + cp n + cp n·k·La`.
      have h1 : cR * Real.log (NtR / cR) + cR + cR * ((k : ℝ) * La)
          ≤ 2 * (n : ℝ) * Real.sqrt (cp n / (n : ℝ)) + cp n + cp n * ((k : ℝ) * La) := by
        have hmono_kLa : cR * ((k : ℝ) * La) ≤ cp n * ((k : ℝ) * La) :=
          mul_le_mul_of_nonneg_right hcR_le_cp' (by positivity)
        linarith [hbdry]
      calc cp n * Real.log (cp n)
          ≤ cR * Real.log cR + (((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)) := hrec
        _ ≤ (negLogQk μ q k n ω
              + (cR * Real.log (NtR / cR) + cR + cR * ((k : ℝ) * La)))
            + (((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)) := by linarith [hcomp]
        _ ≤ negLogQk μ q k n ω
              + (2 * (n : ℝ) * Real.sqrt (cp n / (n : ℝ)) + cp n + cp n * ((k : ℝ) * La)
                + ((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)) := by linarith [h1]
    -- Divide `hclog` by the positive denominator and combine with Step A.
    have hdiv : cp n * Real.log (cp n) / (Real.log 2 * (n : ℝ))
        ≤ (negLogQk μ q k n ω
            + (2 * (n : ℝ) * Real.sqrt (cp n / (n : ℝ)) + cp n + cp n * ((k : ℝ) * La)
              + ((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)))
          / (Real.log 2 * (n : ℝ)) :=
      div_le_div_of_nonneg_right hclog hden_pos.le
    -- Final: combine `hstepA'` + `hdiv`, splitting the RHS fraction.
    have hgoal : (negLogQk μ q k n ω / (n : ℝ)) / Real.log 2
        + (2 * (n : ℝ) * Real.sqrt (cp n / (n : ℝ)) + cp n + cp n * ((k : ℝ) * La)
            + ((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)
            + (cp n * Real.log 2 + cp n * (L + 2))) / (Real.log 2 * (n : ℝ))
        = (negLogQk μ q k n ω
            + (2 * (n : ℝ) * Real.sqrt (cp n / (n : ℝ)) + cp n + cp n * ((k : ℝ) * La)
              + ((k : ℝ) + 1) + ((k : ℝ) + 1) * Real.log (n : ℝ)))
          / (Real.log 2 * (n : ℝ))
          + (cp n * Real.log 2 + cp n * (L + 2)) / (Real.log 2 * (n : ℝ)) := by
      rw [div_div]
      have : negLogQk μ q k n ω / ((n : ℝ) * Real.log 2)
          = negLogQk μ q k n ω / (Real.log 2 * (n : ℝ)) := by rw [mul_comm]
      rw [this, ← add_div]
      ring
    rw [hgoal]
    linarith [hstepA', hdiv]
  -- Conclude via `limsup_le_limsup`.
  have hcobdd : Filter.IsCoboundedUnder (· ≤ ·) Filter.atTop T :=
    Filter.isCoboundedUnder_le_of_le Filter.atTop
      (fun n => lz78_encoding_length_per_symbol_nonneg n (q.blockRV n ω))
  have hbdd : Filter.IsBoundedUnder (· ≤ ·) Filter.atTop U :=
    hU_tend.isBoundedUnder_le
  have hlim_le : Filter.limsup T Filter.atTop ≤ Filter.limsup U Filter.atTop :=
    Filter.limsup_le_limsup hTU hcobdd hbdd
  rw [hU_tend.limsup_eq] at hlim_le
  exact hlim_le

/-- **Lemma 2 (diagonalization = inf over `k`)**: the a.s.-eventual limsup of
the greedy bit-rate is at most the bit entropy rate.

From Lemma 1 (`ziv_aseventual_le_condEntropyTail_bits`) for all `k`
(countable intersection) plus the limit `conditionalEntropyTail → entropyRate`
(`entropyRate_eq_lim_condEntropy`), rescaled by `/Real.log 2`. The LHS is a
`k`-independent constant, so `le_of_tendsto` closes it. -/
theorem ziv_aseventual_le_entropyRate₂
    (μ : Measure Ω) [IsProbabilityMeasure μ] (p : ErgodicProcess μ α) :
    ∀ᵐ ω ∂μ,
      Filter.limsup
        (fun n => (lz78GreedyEncodingLength n
            (p.toStationaryProcess.blockRV n ω) : ℝ) / (n : ℝ))
        Filter.atTop
      ≤ entropyRate₂ μ p.toStationaryProcess := by
  filter_upwards
    [(MeasureTheory.ae_all_iff.2
        (fun k => ziv_aseventual_le_condEntropyTail_bits μ p k))] with ω hω
  -- `hω : ∀ k, limsup (lz/n) ≤ conditionalEntropyTail μ p k / log 2`.
  have h_tend : Filter.Tendsto
      (fun k => conditionalEntropyTail μ p.toStationaryProcess k / Real.log 2)
      Filter.atTop (𝓝 (entropyRate₂ μ p.toStationaryProcess)) := by
    have h := (entropyRate_eq_lim_condEntropy μ p.toStationaryProcess).div_const
      (Real.log 2)
    simpa only [entropyRate₂] using h
  exact ge_of_tendsto h_tend (Filter.Eventually.of_forall hω)

/-- **a.s.-eventual Ziv comparison**: the limsup of the greedy bit-rate is at
most the limsup of `blockLogAvg₂`.

The achievability crux (Cover–Thomas Lemma 13.5.5): combining the Ziv product
bound `c·log c ≤ 8·log(|α|+1)·n` with the length-grouping overhead control
`c = O(n/log n)` and the `-log Pₙ = n·blockLogAvg` identity, the greedy
bit-rate is asymptotically dominated by `blockLogAvg₂`. Stated as an
`a.s.-eventual` limsup comparison (the per-block form is FALSE, counterexample
`a^16`).

The body is `sorry`-free (filter_upwards on `ziv_aseventual_le_entropyRate₂`
+ `shannon_mcmillan_breiman₂`, `rw [h_smb.limsup_eq]`, `exact h_ziv`); `#print
axioms` = `[propext, Classical.choice, Quot.sound]` (sorryAx-free). The
Ziv→AEP connection is supplied by the genuine composition
`ziv_achievability_composition` (`c·log c ≤ negLogQk + o(n)`, sorryAx-free)
plus the AEP `negLogQk_div_tendsto_condEntropyTail`, assembled in
`ziv_aseventual_le_condEntropyTail_bits`.

@audit:ok (non-circular, non-bundled (signature is `(μ, p)` +
`[IsProbabilityMeasure μ]` regularity only), non-degenerate (genuine limsup
inequality), sufficiency TRUE-as-framed (Cover–Thomas 13.5.5; per-block form
correctly avoided; degenerate `entropyRate = 0` boundary stays alive)). -/
theorem ziv_aseventual_le_blockLogAvg₂
    (μ : Measure Ω) [IsProbabilityMeasure μ] (p : ErgodicProcess μ α) :
    ∀ᵐ ω ∂μ,
      Filter.limsup
        (fun n => (lz78GreedyEncodingLength n
            (p.toStationaryProcess.blockRV n ω) : ℝ) / (n : ℝ))
        Filter.atTop
      ≤ Filter.limsup
          (fun n => blockLogAvg₂ μ p.toStationaryProcess n ω) Filter.atTop := by
  filter_upwards [ziv_aseventual_le_entropyRate₂ μ p, shannon_mcmillan_breiman₂ μ p]
    with ω h_ziv h_smb
  rw [h_smb.limsup_eq]
  exact h_ziv

/-- **Ziv-inequality achievability upper bound for the genuine greedy
parser (Cover–Thomas Lemma 13.5.5 / Theorem 13.5.3 upper-bound half),
a.s. form**.

For a stationary ergodic source `p` the per-symbol length of the genuine
longest-prefix-match greedy LZ78 parse is, almost surely, asymptotically at
most the bit entropy rate:

```
limsup_n (1/n) · lz78GreedyEncodingLength(X^n) ≤ entropyRate₂ μ p   a.s.
```

This is the achievability (upper-bound) half of LZ78 asymptotic
optimality, i.e. the a.s.-eventual Ziv inequality
`limsup (c·log₂ c / n) ≤ H₂` combined with the SMB upper bound.

Units: the encoding length is a base-2 code length (`bitLength` uses
`Nat.log 2`), so the per-symbol rate `lz/n` is in **bits** and the correct
RHS is the **bit** entropy rate `entropyRate₂ = entropyRate / Real.log 2`,
the unit-correction documented in `ZivEntropyBridge.lean` ("Base-2 (bit)
layer") and `McMillanKraftBridge.lean`.

`lz78GreedyEncodingLength` charges `c · bitLength c |α|` against the
genuine distinct phrase count `c = (lz78PhraseStrings (List.ofFn x)).length`,
so this is a **genuine proposition** carrying real Ziv content.

**Composition lemma.** The body of this theorem is `sorry`-free: it is
assembled from the two genuine halves of the achievability sandwich,

* `shannon_mcmillan_breiman₂` (SMB in bits, **sorryAx-free**) — gives
  `Tendsto blockLogAvg₂ → entropyRate₂` a.s., hence
  `limsup blockLogAvg₂ = entropyRate₂` (`Filter.Tendsto.limsup_eq`);
* `ziv_aseventual_le_blockLogAvg₂` (the a.s.-eventual Ziv comparison) —
  gives `limsup (lz/n) ≤ limsup blockLogAvg₂` a.s.

`ziv_aseventual_le_blockLogAvg₂` is itself sorryAx-free: the Ziv→AEP
connection — variable-depth tree-node AEP linking the combinatorial
`c · log c` to the probabilistic `-log Pₙ` — is supplied by the genuine
composition
`ziv_achievability_composition` (`c · log c ≤ negLogQk + o(n)`) plus the AEP
`negLogQk_div_tendsto_condEntropyTail`, assembled per-`k` in
`ziv_aseventual_le_condEntropyTail_bits` and diagonalized in
`ziv_aseventual_le_entropyRate₂`. The combinatorial core
(`c · log c ≤ K · n`, `c = O(n / log n)`) and the SMB AEP
(`shannon_mcmillan_breiman`) are all sorryAx-free; the whole achievability
chain depends only on `[propext, Classical.choice, Quot.sound]`.

This statement is TRUE-as-framed against the bit target `entropyRate₂` (it is
false on a uniform i.i.d. source when stated against the nat-unit
`entropyRate`; the bit RHS is the correct unit). On a
uniform i.i.d. source on A symbols the LZ78-optimal bit-rate limit is
`log₂ A = entropyRate / Real.log 2 = entropyRate₂` exactly, so
`limsup ≤ entropyRate₂` holds with equality in the limit (A=2: `1 ≤ 1`); on
the degenerate `entropyRate = 0` boundary it reads `limsup ≤ 0` with
`entropyRate₂ = 0`, again genuine. Signature takes only source data, no
load-bearing hypothesis.

The body is sorry-free (filter_upwards on `shannon_mcmillan_breiman₂` +
`ziv_aseventual_le_blockLogAvg₂`, `exact h_ziv.trans h_smb.limsup_eq.le`);
`#print axioms` = `[propext, Classical.choice, Quot.sound]` (sorryAx-free).
The bit RHS `entropyRate₂ = entropyRate / Real.log 2` is the correct unit (the
nat-unit bound is false for A ≥ 2; the bit bound holds at equality, A=2:
`1 ≤ 1`, A=3: `log₂ 3 ≤ log₂ 3`).

@audit:ok (non-circular, non-bundled (signature is `(μ, p)` +
`[IsProbabilityMeasure μ]` regularity only), non-degenerate, sufficiency
TRUE-as-framed; degenerate `entropyRate = 0` boundary reads `limsup ≤ 0` and
stays alive). -/
theorem lz78Greedy_achievability_ae
    (μ : Measure Ω) [IsProbabilityMeasure μ]
    (p : ErgodicProcess μ α) :
    ∀ᵐ ω ∂μ,
      Filter.limsup
        (fun n =>
          (lz78GreedyEncodingLength n
              (p.toStationaryProcess.blockRV n ω) : ℝ)
            / (n : ℝ))
        Filter.atTop
      ≤ entropyRate₂ μ p.toStationaryProcess := by
  filter_upwards [shannon_mcmillan_breiman₂ μ p, ziv_aseventual_le_blockLogAvg₂ μ p]
    with ω h_smb h_ziv
  exact h_ziv.trans h_smb.limsup_eq.le

/-- **LZ78 asymptotic optimality with the genuine greedy parsing
implementation (Cover–Thomas Theorem 13.5.3)**.

For a stationary ergodic source `p : ErgodicProcess μ α` on a finite
alphabet `α`, the per-symbol output length of the genuine
longest-prefix-match greedy LZ78 parse converges almost surely to the
**bit** entropy rate:

```
lim_{n → ∞} (1/n) · lz78GreedyEncodingLength(X^n) = entropyRate₂ μ p   a.s.
```

Units: the encoding length is a base-2 code length
(`lz78GreedyEncodingLength = c · bitLength c |α|`, `bitLength` uses
`Nat.log 2`), so the per-symbol rate is in **bits** and the convergence
target is the **bit** entropy rate `entropyRate₂ = entropyRate / Real.log 2`
(not the nat-unit `entropyRate`). This is the unit-correction documented in
`ZivEntropyBridge.lean` ("Base-2 (bit) layer — unit correction for the LZ78
headline"). On a uniform i.i.d. source on A symbols the bit-rate limit is
`log₂ A = entropyRate₂` exactly (e.g. A=2: `rate → 1`), which is what the
two TRUE-as-framed halves squeeze to.

This is the LZ78 optimality headline. The two halves of the sandwich —
the converse lower bound and the Ziv achievability upper bound — are
supplied internally by `lz78Greedy_converse_ae` and
`lz78Greedy_achievability_ae`, both now stated against the bit target
`entropyRate₂`. The a.s. convergence is assembled via the generic
combinator `lz78_asymptotic_optimality` instantiated at `L = entropyRate₂`
(the genuine `tendsto_of_le_liminf_of_limsup_le` squeeze).

`lz78GreedyEncodingLength` charges `c · bitLength c |α|` against the
genuine distinct phrase count of the longest-prefix-match parse, so the
per-symbol rate is data-dependent and
**deterministically bounded above by an `n`- and `ω`-uniform constant**
`(1 + 8·log(|α|+1)/log 2) + (log₂|α| + 2)` (via `lz78_rate_le_const`,
combining the Ziv product bound `c·log c ≤ 8·log(|α|+1)·n` with `c ≤ n` and the
`ℕ`–`Real` `log` bridge). The upper-boundedness hypothesis is therefore **no
longer a parameter**: it is supplied internally — even the `a.e.` envelope is
unnecessary since the bound holds for every `ω` and every `n`.

Units: the convergence target is the bit entropy rate
`entropyRate₂ = entropyRate / Real.log 2`, not the nat-unit `entropyRate`.
Against the nat-unit target the achievability half — and hence this headline —
would be FALSE on a uniform i.i.d. source (the bit-rate `lz/n` converges to the
bit entropy rate). With the
bit target the headline is a **TRUE-as-framed proposition**: on a uniform
i.i.d. source on A symbols the bit-rate limit is `log₂ A = entropyRate₂`
exactly (A=2: `entropyRate₂ = log₂ 2 = 1`, so the two halves squeeze
`rate → 1`, the genuine LZ78-optimal bit rate); on the degenerate
`entropyRate = 0` boundary the target is `entropyRate₂ = 0` and the squeeze
reads `rate → 0`, again genuine. Both halves
(`lz78Greedy_converse_ae` / `lz78Greedy_achievability_ae`) are stated
against `entropyRate₂`, and the base combinator `lz78_asymptotic_optimality`
is instantiated at `L = entropyRate₂`.

**Proof done (Standard B): fully `sorryAx`-free** (`#print axioms` =
`[propext, Classical.choice, Quot.sound]`). The headline takes only the source
data (`μ`, `p`) — no `h_bdd_above` precondition. Both `IsBoundedUnder`
witnesses (`(·≤·)` above and `(·≥·)` below) are constructed deterministically
inside the body from `lz78_rate_le_const` /
`lz78_encoding_length_per_symbol_nonneg` (both unit-agnostic: they bound
the bit-rate `lz/n` itself, so they are unaffected by the choice of `L`), so
the squeeze `tendsto_of_le_liminf_of_limsup_le` is applied with all of its
regularity inputs genuine. Both halves are genuine: the achievability half
(`lz78Greedy_achievability_ae`) and the converse half
(`lz78Greedy_converse_ae`, whose sole combinatorial brick
`lz78_block_kraft_poly` / `lz78_phrase_count_fiber_card_le` is closed via
the LZ78 dictionary parent-extension invariant). LZ78 asymptotic optimality is
fully proven.

@audit:ok (FINAL completion audit 2026-06-21, commit `bd28e0e`, independent
subagent not involved in implementation). Four honesty checks PASS: non-circular,
non-bundled (signature is `(μ, p)` + `[IsProbabilityMeasure μ]` only; both
`IsBoundedUnder` witnesses + both sandwich halves are constructed internally),
non-degenerate, sufficiency TRUE-as-framed (bit `entropyRate₂` target, genuine
`tendsto_of_le_liminf_of_limsup_le` squeeze via `lz78_asymptotic_optimality`).
`#print axioms = [propext, Classical.choice, Quot.sound]` (sorryAx-free,
machine-confirmed; both files compile with 0 sorry warnings). -/
@[entry_point]
theorem lz78_asymptotic_optimality_with_greedy
    (μ : Measure Ω) [IsProbabilityMeasure μ]
    (p : ErgodicProcess μ α) :
    ∀ᵐ ω ∂μ,
      Filter.Tendsto
        (fun n =>
          (lz78GreedyEncodingLength n (p.toStationaryProcess.blockRV n ω) : ℝ)
            / (n : ℝ))
        Filter.atTop
        (𝓝 (entropyRate₂ μ p.toStationaryProcess)) := by
  have h_bdd_above : ∀ᵐ ω ∂μ,
      Filter.IsBoundedUnder (· ≤ ·) Filter.atTop
        (fun n =>
          (lz78GreedyEncodingLength n
              (p.toStationaryProcess.blockRV n ω) : ℝ)
            / (n : ℝ)) := by
    refine Filter.Eventually.of_forall (fun ω => ?_)
    exact Filter.isBoundedUnder_of
      ⟨(1 + 8 * Real.log (Fintype.card α + 1) / Real.log 2)
          + ((Nat.log 2 (Fintype.card α) : ℝ) + 2),
        fun n => lz78_rate_le_const n _⟩
  have h_bdd_below : ∀ᵐ ω ∂μ,
      Filter.IsBoundedUnder (· ≥ ·) Filter.atTop
        (fun n =>
          (lz78GreedyEncodingLength n
              (p.toStationaryProcess.blockRV n ω) : ℝ)
            / (n : ℝ)) := by
    refine Filter.Eventually.of_forall (fun ω => ?_)
    exact Filter.isBoundedUnder_of
      ⟨0, fun n => lz78_encoding_length_per_symbol_nonneg n _⟩
  exact lz78_asymptotic_optimality μ p (@lz78GreedyEncodingLength α _ _)
    (entropyRate₂ μ p.toStationaryProcess)
    (lz78Greedy_converse_ae μ p)
    (lz78Greedy_achievability_ae μ p)
    h_bdd_above h_bdd_below


end ParentBridge

end InformationTheory.Shannon
