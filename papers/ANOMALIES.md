# Methods anomalies (promoted findings)

Cross-paper ledger of measurement anomalies that turned out to be citable methods findings, not
bugs. Each entry states the observation, the mechanism, the fix, and who it affects.

---

## A1 — Covariance-matched nulls are unusable in massive-activation families without robustification

**Date:** 2026-07-01 · **Found in:** Direction-2 chunk-1 B1/B3 (`d2_decision_coupling`), cross-model
panel OLMo-3 / Qwen2.5-7B / Llama-3.1-8B (instruct).

**Observation.** The covariance-matched rank-matched null (draw random directions from `N(0, Σ̂)`
of residual activations, project onto the rank-`r` subspace) — the honest null used throughout
Papers 5–7 and D1 — **saturates** on Qwen2.5 and Llama-3.1: R2 null q95 = 0.92 (Qwen) / 0.36
(Llama), R3 pairwise-null q95 = 0.995 (Qwen) / 0.90 (Llama), versus 0.26 on OLMo-3. At a saturated
null every direction "projects like a typical direction," so the test has no discriminating power —
exactly the degeneracy d1 documented for eff-dim-385, here from a different cause.

**Mechanism.** Qwen2.5 and Llama-3.1 carry **massive-activation outlier dimensions** (Qwen dim 458
= **59%** of residual variance; Llama dim 788 = **32%**; OLMo-3's top dim = 1.4%). `Σ̂` is dominated
by these dims, so covariance-matched random directions nearly all align with them and project ~1
onto any subspace with a component there. The same dims dominate raw mean-diff directions, collapsing
distinct constructs (Qwen ethics≈moral mean-diff `|cos|` = 0.90). This is the known
**massive-activations / attention-sink** phenomenon (e.g. Sun et al. 2024, *Massive Activations in
Large Language Models*; Xiao et al. 2023, *Efficient Streaming LMs with Attention Sinks* — verify
exact refs before citing in a paper). OLMo-3's well-conditioned activations are why every OLMo-based
result in Papers 1–7 / D1 was clean.

**Fix (pre-registered, `d2_decision_coupling/PREREGISTRATION.md` Amendment 1).** Recompute
directions + the null in a **per-dimension-standardized** space (z-score by σ from a format/position-
matched `act_sample` with sink tokens excluded); primary. Robustness variant: **project out
dimensions individually > 5% of variance** (criterion-based). Legitimacy proof: the clean instrument
(OLMo) must give the **same verdict** raw→standardized. Behavioral results (ablation, judgment
accuracy) do not use the null and are untouched; only geometric cells need the re-audit.

**Affects.** Any direction-geometry projection-fraction / cosine-null computed on Qwen or Llama
family activations, including **Paper 6's cross-model geometric cells** (back-audit pre-registered)
and Direction-2 R2/R3/R5/R8 for Qwen/Llama. Does **not** affect OLMo-based numbers.

**Why it's a contribution.** "Covariance-matched nulls silently degenerate in massive-activation
families" is a portable caution for anyone building moral/refusal/concept subspaces and testing them
against activation-space nulls on Llama/Qwen — the field's default panel. It belongs in the methods
section, not a footnote.

**Paper 6 back-audit (2026-07-01, zero-GPU — rider d, CLEAN, no revision needed).** Paper 6's
Qwen/Llama geometric cells do **not** use the vulnerable null: `exp2_framework_geometry` uses a
**permutation test** (observed statistics ~0.01, unsaturated), and the refusal-morality geometry is
a **raw projection fraction** with no covariance-matched null — and those fractions are low and
un-inflated (`moral_subspace_projection_fraction`: OLMo 0.104, Qwen 0.127, Llama 0.071; mean|cos|
0.04–0.07). Paper 6 also built its MFT subspace on the **base** model, whose foundation directions
did not collapse onto the outlier dim. So the degeneracy is confined to the **covariance-matched
projection null applied to D2's instruct-model `V_moral`**; no Paper 6 number changes. Llama's
behavioral results were never at risk (they don't use the null). Paper 6 saved no `act_sample` for
Qwen/Llama, but since no covariance null was used there, no standardized re-audit is required (so no
`MISSING_ARTIFACTS` rider is filed).

**Post-standardization eff-dim (participation ratio).** The degeneracy's magnitude: raw PR = OLMo
43, **Qwen 1.0, Llama 1.5** (one dim carries essentially all variance for Qwen/Llama); after
per-dim z-scoring, PR = OLMo 94, **Qwen 39, Llama 89**. Standardization lifts Qwen/Llama from a
rank-1 effective space to a genuinely multi-dimensional one — the quantitative before/after of the
fix. (Measured; higher than a ~10–15 first estimate — the standardized space is richer than
expected, but the raw PR≈1 → the collapse was near-total.)

**Qwen is elevated in TWO cells — discriminator is the in-format ladder + the projection-out read.**
Qwen's refusal geometry sits high in both the chat R3 cell (|cos| 0.32, still dissociation, but
above OLMo's 0.10) and the raw R5 cell. On R5, the two robustifications **disagree**: standardization
gives refusal 0.20 > controls 0.10 (strong-form FALSE), while top-k projection-out gives refusal
0.21 < controls 0.45–0.55 (strong-form TRUE) — and the same disagreement appears for Llama. So R5 is
not resolvable by robustification alone; the **chat-format in-format ladder** (whose decision-site
space carries no >5%-variance dim, so it is outlier-free by construction) is the discriminator. This
is a worked example of the entry's thesis: when standardization and projection-out disagree, the
subspace is genuinely degenerate and needs a format/position change, not a null patch.

---

## A2 — The decision-site is a low-dimensional control-token bottleneck (band-below-null ⇒ position-invalid)

**Date:** 2026-07-01 · **Found in:** the D2 in-format ladder (`informat_ladder.py`), OLMo-3-Instruct.

**Observation.** The chat **`final_pre_assistant`** position (the assistant-header token — the
decision site where the refusal gate and judgment-decision direction are defined) has a
**participation ratio of 14.7** — a ~15-effective-dimensional channel — while content positions
(`mean_content`) are full-rank-healthy. There the positive-control moral band **[0.40, 0.47] sits
BELOW the covariance null (0.557)**: held-one-out moral directions project onto their own span *less*
than random directions do, so the projection-fraction instrument has **no discriminating power**.
It is **not** an outlier dim (top dim 0.2%) and **not** standardization-fixable (null stays 0.52).
Three independent estimates converge on ~15 dims: `√(3/14.7) = 0.45` ↔ null_q95 0.557 ↔ the R3
pairwise-|cos| null 0.41–0.51.

**The general tell (portable).** **Band-below-null ⇒ position-invalid instrument.** The A1
positive-control band is not just a yardstick for "moral-adjacent"; it is a **validity check on the
measurement position**. Any projection-fraction result at a position where the positive control
falls below the covariance null is uninterpretable, whatever the direction-of-interest does.

**Reframe (a finding, not a failure).** The decision site being a narrow control channel is the
*mechanism*. Stacked with A3 (refusal in a ≤q10-variance channel) and A5 (refusal does not
crystallize from a pretraining precursor, cos 0.155): the refusal gate is a fresh post-training
construction in a narrow control channel at a template-token bottleneck that moral content does not
reach (band-below-null there, healthy at content positions). Content-vs-decision geometric
orthogonality is therefore **architecturally guaranteed**, and any comprehension→decision coupling
must be carried by the **attention heads writing into the bottleneck** — a concrete anatomical
target for the causal (C1) follow-up. R3 (a decision-direction cosine, immune to the projection
null) reads *stronger* under this lens: in a ~15-slot channel, judgment and refusal occupy different
slots at |cos| below even the low-dim random level → active separation.

**Fix + guard.** `participation_ratio` is a required type-block field; positions with PR < 30 are
flagged position-invalid at extraction (`d2_decision_coupling/PREREGISTRATION.md` Amendment 2). The
D1 reasoning-extension band rung (GPT-OSS P2 vs a raw-pooled band) inherits the same cross-position
hazard and is being PR-audited + scoping-noted.
