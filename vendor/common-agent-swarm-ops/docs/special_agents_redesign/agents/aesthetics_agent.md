**Comprehensive Functional Specification: Aesthetics Agent — Computational "Artiste Sense" Critic & Alignment Service for the VA-Agent-Swarm**

**Document Version:** 1.0 (Final – Complete & Exhaustive)
**Date:** May 29, 2026
**Authors:** Grok (xAI) + Collaborative Iteration with User Nicholas (nicholas_hui)
**Target Audience:** Senior AI Engineering / Coding Agents (for immediate implementation)
**Purpose:** This is the **definitive, production-grade specification** for building the **Aesthetics Agent** — a stateful, multimodal evaluation-and-alignment service that operationalizes a simulated **"artiste sense"** (artistic/aesthetic intuition) for the entire VA-Agent-Swarm. It is the deep rethink of [`aesthetics_agents.md`](./aesthetics_agents.md): where that document is a *survey of methods*, this is a *buildable agent contract*. It reframes "teach AI artistic sense" from a single image scorer into a **shared aesthetic nervous system** — a critic that every generative agent consults, a reward signal that every fine-tuning loop trusts, and a personalization engine that carries a director's, brand's, or artist's taste across the whole pipeline.

---

### 1. Executive Summary

The **Aesthetics Agent** is the swarm's computational embodiment of "artiste sense." It does not *replace* human taste — it **amplifies, encodes, and propagates** it at superhuman speed across 114 agents.

It serves three distinct, composable functions:

1. **The Critic (Perceive).** A multimodal, multi-head evaluator that scores any visual artifact — single frame, image, or full video clip — against a decomposed aesthetic rubric (composition, color harmony, lighting, depth, emotional resonance, technical quality, style fidelity, novelty). This is the swarm's shared "eye."
2. **The Aligner (Refine).** A preference-and-reward service that turns the Critic's judgments into actionable feedback and training signal — driving self-refinement loops, preference optimization (DPO/RLHF/RLAIF), and prompt steering for `PromptEngineerAgent`, `CinematographerAgent`, `ColoristAgent`, and peers.
3. **The Taste-Keeper (Personalize).** A profile store that captures *whose* aesthetic governs a project — a director's lookbook, a brand's guidelines, an artist's portfolio, an audience cohort's preferences — and conditions all scoring and alignment on that profile.

**Why this is a "deep rethink" and not a wrapper:**

| The naive guide says... | The Aesthetics Agent does... |
|---|---|
| "Train an aesthetic scorer (e.g., NIMA, LAION)." | Treats a single scalar score as *insufficient and dangerous*. Decomposes aesthetics into auditable sub-attributes + a temporal track for video, with calibrated uncertainty. |
| "Use the critic as a reward to fine-tune the generator." | Wraps every reward use in **anti-reward-hacking** guardrails (reward variance monitoring, ensemble disagreement, OOD detection, KL anchoring). |
| "Personalize on one artist's ratings." | Makes taste a **first-class, versioned, consent-governed profile** that flows through the swarm's handoff contract and critique bus. |
| Operates on still images. | Is **video-native first**: temporal coherence, motion aesthetics, cut rhythm, and per-shot-vs-sequence scoring. |
| Aesthetic sense = beauty prediction. | Aesthetic sense = beauty **+ intent fidelity + emotional target + brand/style fit + novelty**, gated so high scores never come from generic "pretty slop." |

The result is a single agent that other agents *cannot do their job without*: it is referenced by `agents.md` entries #6, #10, #14, #15, #16, #39, #46, #49 and others as "aesthetic regressor / CLIP-based aesthetic scoring," and this document is its authoritative definition.

---

### 2. Background: From "Artiste Sense" to Computational Aesthetics

The source document [`aesthetics_agents.md`](./aesthetics_agents.md) defines **"artiste sense"** as the intuitive, perceptual, and expressive sensitivity artists develop — an "eye" for composition, color harmony, rhythm, proportion, light/shadow, depth, and emotional resonance; a structural (3D) way of seeing; a psychological drive to express; and a grounded, iterative creative practice.

Its central thesis, which this spec adopts wholesale:

> AI cannot possess *genuine* lived artistic sense (no consciousness, no emotion), but it can develop a **sophisticated simulated version** through (a) data-driven evaluators trained on human aesthetic judgments, (b) preference-alignment feedback loops, and (c) computational-creativity extensions. The strongest results come from **human–AI symbiosis**, not autonomous AI artists.

This specification accepts that framing as ground truth and answers the only question the survey left open: **what is the precise, implementable agent contract that delivers it inside a 114-agent video production system?**

---

### 3. The Deep Rethink — Five Reframings

The act of "deeply rethinking" the guide produced five architectural commitments. Each is a deliberate departure from the naive "train a scorer" recipe.

**3.1 Aesthetics is a vector, not a scalar.**
A single 1–10 score is unaccountable and trivially reward-hacked. The Critic emits a **decomposed AestheticVector** — independent heads for composition, color, light, depth, subject treatment, technical quality, emotional resonance, style fidelity, and novelty — each with a calibrated confidence. The scalar is a *gated aggregation*, never the source of truth.

**3.2 Aesthetics is temporal.**
This is a video swarm. A montage of individually beautiful frames can be aesthetically incoherent. The Critic scores both **per-frame** and **per-sequence**: motion smoothness, temporal color/exposure stability, cut rhythm vs. genre prior, and "does the clip read as one authored gesture."

**3.3 Aesthetics is whose.**
Following the LAION-Aesthetics audit critique that a "one-size-fits-all" beauty model encodes a narrow, unexamined taste ([arXiv:2601.09896](https://arxiv.org/html/2601.09896v1)), the agent refuses to pretend there is one universal beauty. Every score is conditioned on an explicit **AestheticProfile** (director / brand / artist / audience cohort / "neutral baseline"). Personalization is the default, not an add-on. Recent work shows LLM-interview-elicited personalized aesthetic models can exceed generic ones at predicting an individual's judgments ([arXiv:2605.14761](https://arxiv.org/html/2605.14761v1)).

**3.4 Aesthetics must not be hackable.**
The moment the Critic becomes a reward, generators learn to exploit it (high-frequency texture spam, saturation blowouts, "AI-glossy" sheen). The Aligner therefore ships with first-class **anti-reward-hacking** machinery — ensemble disagreement, reward-variance monitoring (large/diverse reward models retain high variance and resist collapse, per [arXiv:2509.08826](https://arxiv.org/html/2509.08826v1)), KL anchoring to a reference model, OOD artifact detectors, and inference-time mitigation ([arXiv:2510.01549](https://arxiv.org/abs/2510.01549)). Rich, rationale-bearing preferences are favored over opaque scalars ([arXiv:2503.11720](https://arxiv.org/html/2503.11720)).

**3.5 Aesthetics is gated by intent.**
Beauty divorced from the brief is noise. The aggregate quality is multiplied by **intent fidelity** (does it match the shot intent / prompt / brand?) and **emotional-target match** (does it land the intended valence/arousal?). A gorgeous image that ignores the director's intent scores low. This mirrors the value-gated selection in the [General Creative Agent](./general_creative_agent_functional_specification.md) (SSOR).

---

### 4. Formal Aesthetic Model

Let an artifact \( x \) (image or video clip) be evaluated under an aesthetic profile \( p \), an intent/brief \( b \), and an emotional target \( e \).

The Critic produces a **decomposed aesthetic vector**:

\[
\mathbf{A}(x \mid p) = \bigl[\, a_1, a_2, \dots, a_k \,\bigr], \quad a_i \in [0,1], \; \text{with confidence } \sigma_i
\]

over \( k \) sub-attributes (the **Aesthetic Dimensions**, §6). The **gated aesthetic quality** is:

\[
\operatorname{AQ}(x \mid p,b,e) \;=\; \underbrace{G\!\left(\mathbf{A}(x\mid p), \mathbf{w}_p\right)}_{\text{profiled aggregate}} \;\cdot\; \underbrace{I(x,b)}_{\text{intent fidelity}} \;\cdot\; \underbrace{E(x,e)}_{\text{emotion match}} \;\cdot\; \underbrace{\big(1 - H(x)\big)}_{\text{anti-hack penalty}}
\]

Where:
- \( G(\cdot, \mathbf{w}_p) \): profile-weighted aggregation of the attribute vector (weights \( \mathbf{w}_p \) come from the active `AestheticProfile`; a brand may weight color/brand-fit heavily, a horror DoP may weight light/contrast).
- \( I(x,b) \in [0,1] \): intent fidelity (e.g., CLIP-T / VLM grounding of artifact against shot-intent text or reference; target ≥ 0.32 per `DirectorAgent` rubric in `agents.md`).
- \( E(x,e) \in [0,1] \): emotional-target match (valence/arousal regression vs. target, shared with `ComposerAgent` emotional-arc validator).
- \( H(x) \in [0,1] \): hack/artifact likelihood (OOD score, ensemble disagreement, artifact detector) — high \( H \) collapses the score regardless of surface prettiness.

For video, AQ is computed per-frame **and** at sequence level, then combined:

\[
\operatorname{AQ}_{\text{clip}} = \alpha \cdot \operatorname{mean}_t \operatorname{AQ}(x_t) \;+\; \beta \cdot \operatorname{AQ}_{\text{temporal}}(x_{1:T}) \;-\; \gamma \cdot \operatorname{Var}_t\!\big[\text{exposure, color, identity}\big]
\]

penalizing temporal instability (flicker, color drift, identity break — overlaps with `AIQAConsistencyAgent` #49).

**Hard principles (encoded in code):**
- **No naked scalar.** Any consumer requesting only `AQ` also receives \( \mathbf{A} \), \( H \), and the top failing dimension.
- **Uncertainty travels.** Every score ships with confidence; low-confidence scores must escalate to HiTL or a second model, never silently pass.
- **Profile-or-refuse.** If no profile is supplied, the agent uses an explicitly labeled `neutral_baseline_v{n}` profile and flags that the result is taste-agnostic.

---

### 5. Architecture

The Aesthetics Agent is a three-subsystem service sharing one profile store and one model registry.

```
                         ┌───────────────────────────────────────────────┐
                         │              AESTHETICS AGENT                   │
                         │                                                 │
  Artifact (img/video) ─▶│  ┌──────────────┐   ┌──────────────┐           │
  + Profile + Intent     │  │  THE CRITIC  │   │ THE ALIGNER  │           │
  + Emotion target       │  │  (Perceive)  │──▶│  (Refine)    │──┐        │
                         │  │ multi-head   │   │ reward +     │  │        │
                         │  │ evaluator    │   │ preference + │  │        │
                         │  └──────┬───────┘   │ critique gen │  │        │
                         │         │           └──────────────┘  │        │
                         │         ▼                              ▼        │
                         │  ┌──────────────┐          ┌────────────────┐  │
                         │  │ ANTI-HACK    │          │ THE TASTE-KEEPER│  │
                         │  │ guardrails   │◀────────▶│ (Personalize)   │  │
                         │  │ (ensemble,   │          │ AestheticProfile│  │
                         │  │ OOD, KL)     │          │ store (versioned)│ │
                         │  └──────────────┘          └────────────────┘  │
                         └───────────────────────────────────────────────┘
                                   │                          │
                          AestheticVerdict (JSON)     Profile updates
                                   ▼                          ▼
                          CRITIQUE BUS  ──────▶  consuming agents (#6,#10,#15,#39,#46,#49…)
```

**5.1 The Critic (Perceive).** Ensemble of complementary backbones:
- A fast **regression head** on a vision backbone (SigLIP / CLIP-ViT) — Aesthetic-Predictor-V2.5-style MLP for cheap first-pass screening at scale.
- A **VLM critic** (Grok-4.x vision, Gemini 2.5 Pro, GPT-4o-vision) producing fine-grained, attribute-level natural-language critique + scores — the "explainable eye."
- Specialized detectors: artifact/hand/face-distortion detectors, ΔE color drift, exposure histogram/zone analysis, rule-of-thirds & leading-lines geometry, FID/FVD against style reference, temporal smoothness (optical flow), VBench-style video metrics.

**5.2 The Aligner (Refine).** Converts verdicts into action:
- **Self-refine feedback**: a prioritized, machine-readable critique ("scene 3 underexposed in zone IV; subject collides with right edge; color drifts +6 ΔE across cut").
- **Reward signal**: scalar/vector reward for RLHF / RLAIF / DPO / ReFL-style diffusion fine-tuning, always emitted with variance + ensemble-agreement metadata.
- **Preference pairs**: for DPO-style training, with rationale (rich preferences) not just A≻B.
- **Prompt-steer hints**: concrete prompt deltas handed to `PromptEngineerAgent` (#46) to reach target in ≤3 iterations.

**5.3 The Taste-Keeper (Personalize).** Versioned, consent-governed `AestheticProfile` store (see §10), elicited via portfolio ingestion, pairwise preference collection, and LLM-interview elicitation ([arXiv:2605.14761](https://arxiv.org/html/2605.14761v1)).

**5.4 Anti-Hack Guardrails.** Cross-cutting safety layer wrapping every reward emission (see §11).

---

### 6. Aesthetic Dimensions (the Decomposed Rubric)

The Critic emits a score + confidence for each dimension. Profiles re-weight them; they are *never* collapsed before being logged.

| # | Dimension | What it measures | Primary signal |
|---|-----------|------------------|----------------|
| D1 | **Composition** | Balance, rule-of-thirds, leading lines, negative space, framing, staging clarity | Geometry detector + VLM |
| D2 | **Color Harmony** | Palette coherence, contrast, temperature consistency, mood vector | Color histogram, ΔE, palette extraction |
| D3 | **Light & Shadow** | Exposure zones, key/fill ratio, direction, dynamic range, mood | Histogram/zone analysis, VLM |
| D4 | **Depth & Form** | 3D readability, layering, focal depth, structural "seeing" (per artiste-sense) | Depth estimation + VLM |
| D5 | **Subject Treatment** | Subject prominence, gaze, gesture, silhouette readability | Saliency + pose/landmark |
| D6 | **Technical Quality** | Sharpness, noise, banding, artifacts, resolution adequacy | Detectors + IQA model |
| D7 | **Emotional Resonance** | Evoked valence/arousal vs. target | Affect regressor (shared w/ ComposerAgent) |
| D8 | **Style Fidelity** | Adherence to style bible / lookbook / brand | CLIP/embedding distance to reference set |
| D9 | **Novelty / Distinctiveness** | Originality vs. "generic AI slop"; inverted-U (not maximal) | Embedding rarity vs. corpus |
| D10 | **Temporal Aesthetics** *(video)* | Motion smoothness, cut rhythm, temporal stability, "one authored gesture" | Optical flow, VBench-style, beat-sync |

**Novelty note (D9):** Following the SSOR inverted-U principle from the GCA spec, novelty is rewarded in a *moderate* band — too low = cliché/derivative; too high = incoherent. This is what prevents the agent from rewarding bland, statistically-average "pretty" output.

---

### 7. Functional Requirements

**7.1 Input (JSON).**
```json
{
  "artifact_ref": "asset_id_or_uri",
  "media_type": "image | video_clip | frame_sequence",
  "profile_id": "director_lynchian_v3 | brand_acme_v2 | neutral_baseline_v4",
  "intent": { "shot_intent_text": "...", "reference_refs": ["..."], "genre_prior": "noir" },
  "emotional_target": { "valence": -0.4, "arousal": 0.7 },
  "mode": "screen | score | align | compare | refine",
  "constraints": { "aspect_ratio": "2.39:1", "color_space": "ACEScct", "deliverable": "HDR" },
  "budget": { "max_latency_ms": 800, "tier": "fast | deep" }
}
```

**7.2 Output — `AestheticVerdict` (JSON + Markdown).**
```json
{
  "artifact_ref": "asset_id_v2",
  "profile_id": "director_lynchian_v3",
  "aesthetic_vector": { "composition": 0.81, "color_harmony": 0.74, "light": 0.62,
                        "depth": 0.70, "subject": 0.88, "technical": 0.91,
                        "emotion": 0.66, "style_fidelity": 0.79, "novelty": 0.55,
                        "temporal": 0.83 },
  "confidence": { "composition": 0.9, "light": 0.6, "...": "..." },
  "intent_fidelity": 0.79,
  "emotion_match": 0.71,
  "hack_likelihood": 0.04,
  "aesthetic_quality": 0.73,
  "top_failing_dimensions": ["light", "novelty"],
  "actionable_critique": [
    "Underexposed in zone IV; lift key +1/3 stop on subject left.",
    "Palette is conventional for genre; consider one strategic outlier hue."
  ],
  "prompt_steer_hints": ["add 'low-key chiaroscuro, single practical source'"],
  "uncertainty_flag": false,
  "escalate_to_hitl": false,
  "provenance": { "models": ["aesV2.5","grok-vision-4.x"], "ensemble_agreement": 0.86 }
}
```

**7.3 Modes.**
- `screen` — fast scalar gate for high-volume candidate culling (regression head only).
- `score` — full decomposed vector + verdict.
- `align` — emit reward/preference signal for a training/refinement loop.
- `compare` — pairwise/listwise ranking of N candidates (for "choose the best take").
- `refine` — generate → score → critique → suggest, iterated (mimics the artist's iterative loop).

**7.4 Statefulness.** Per-project memory of accepted/rejected artifacts ratchets the profile and feeds Reflexion-style episodic memory (consistent with swarm principle "Continuous Self-Improvement").

**7.5 Non-functional.** Fast-tier screening ≤ 800 ms/artifact; deep-tier ≤ 8 s; horizontal GPU autoscale; deterministic given fixed profile + model versions (reproducibility for audits).

---

### 8. Integration with the VA-Agent-Swarm

This agent is **cross-cutting infrastructure**, registered alongside the Research Agent, GCA, and Optimization Agent in [`SYSTEM_REFERENCE.md`](./SYSTEM_REFERENCE.md) §4.

**8.1 Consumers (who calls it and why).**

| Agent (from `agents.md`) | Use of Aesthetics Agent |
|---|---|
| #6 CinematographerAgent (DoP) | Replaces ad-hoc "CLIP-based aesthetic scoring" — composition/light/color self-refine rubric |
| #10 ColoristAgent | ΔE drift, mood-vector match, palette coherence scoring |
| #14 StoryboardAgent / #15 ConceptArtistAgent / #16 ProductionDesignAgent | Style-bible adherence + composition scoring |
| #39 FoodStylistAgent / #40 TravelCineAgent / #45 RealEstatePhotoAgent | The shared "aesthetic regressor" these specs reference |
| #46 PromptEngineerAgent | `refine` mode + `prompt_steer_hints` to hit target in ≤3 iterations |
| #49 AIQAConsistencyAgent | Temporal stability / artifact (`hack_likelihood`) cross-check |
| #1 DirectorAgent / #56 JudgeAgent | Tie-break and blind-preference adjudication on candidate takes |
| Delivery & Marketing (#27, #28, #31) | Thumbnail/hook aesthetic scoring for predicted engagement |

**8.2 Critique Bus.** Verdicts are published on the swarm's structured critique bus (`SYSTEM_REFERENCE.md` §7.1) with `critique_type: "aesthetic_feedback"`, `severity`, `rubric_score`, and `artifact_ref`, so any agent can react asynchronously.

**8.3 Handoff Contract.** The `AestheticVerdict` is attached to the artifact's `qc_status` field in the **Shared Artifact Handoff Contract** (`SYSTEM_REFERENCE.md` §7), making aesthetic state travel with provenance through every phase.

**8.4 Relationship to neighbors.**
- **vs. GCA (creativity):** GCA *generates* novel-yet-useful candidates; Aesthetics Agent *judges and refines* them. GCA's novelty score (D9) is supplied by this agent. They form a generate↔evaluate loop.
- **vs. AIQAConsistencyAgent (#49):** AIQA catches *errors* (drift, broken hands, identity breaks); Aesthetics Agent judges *taste*. `hack_likelihood` is the shared boundary — co-trained, deduplicated.
- **vs. Psychological Recommendation / AudienceSim:** those predict *audience* preference; Aesthetics Agent encodes *authorial/brand* taste. A profile can be an audience-cohort profile, bridging the two.

---

### 9. The Three Operating Loops

**9.1 Critic Loop (evaluate).** `artifact → ensemble score → decompose → gate by intent/emotion → anti-hack check → AestheticVerdict`.

**9.2 Alignment Loop (teach the generator).** Mirrors the source guide's pipeline, hardened:
1. Generate N candidates (base model).
2. `compare` mode ranks them; `score` mode decomposes.
3. Human raters spot-check a sampled subset (symbiosis, not full autonomy).
4. Build **rich preference pairs** (with rationale) → DPO / RLHF / RLAIF / ReFL update.
5. Monitor reward variance & ensemble agreement; if variance collapses → suspect hacking, freeze, escalate.
6. Repeat; generator internalizes the taste and "instinctively" picks stronger outputs.

**9.3 Personalization Loop (capture whose taste).**
1. Ingest portfolio / lookbook / brand guide → seed embedding profile.
2. Collect pairwise preferences and/or run **LLM-interview elicitation** to surface latent criteria.
3. Fit profile weights \( \mathbf{w}_p \); validate against held-out judgments.
4. Version, sign, and store; expose `profile_id` to the swarm.

---

### 10. Personalization: the `AestheticProfile`

A first-class, versioned, consent-governed object.

```json
{
  "profile_id": "director_lynchian_v3",
  "owner": "consenting_entity_id",
  "consent": { "scope": "project_x", "expires": "2027-01-01", "c2pa_signed": true },
  "weights": { "light": 0.22, "color_harmony": 0.18, "novelty": 0.15, "...": "..." },
  "exemplars": ["asset_uri_1", "..."],
  "anti_exemplars": ["asset_uri_9", "..."],
  "elicited_criteria": ["prefers low-key contrast", "avoids saturated reds", "..."],
  "embedding_centroid": "vec://...",
  "version": 3,
  "lineage": ["v1","v2","v3"]
}
```

Profile types: **Director**, **Brand**, **Artist**, **Audience-Cohort** (links to [Psychological Recommendation](./psychological_recommendation_agent_functional_specification.md)), **Genre-prior**, **Neutral-baseline**. Profiles are composable (e.g., `brand_acme ⊕ genre_noir`) with documented precedence.

**Governance:** Personalizing on a named human's taste/portfolio requires consent recorded in the profile and cleared by `ComplianceAgent` (#37) — same rigor as voice/likeness cloning.

---

### 11. Reward Hacking, Failure Modes & Defenses

The single greatest risk: when the Critic becomes a reward, generators learn to *fool the eye*, not *please it*.

| Failure mode | Symptom | Defense |
|---|---|---|
| **Texture/detail spam** | High score, busy high-frequency noise | Artifact detector; frequency-domain sanity check; human spot-check |
| **Saturation/contrast blowout** | "AI-glossy" oversaturated look | ΔE & gamut bounds; per-dimension caps; brand profile constraints |
| **Mode collapse** | All outputs converge to one "safe" look | Reward-variance monitoring; large/diverse reward ensembles retain variance ([arXiv:2509.08826](https://arxiv.org/html/2509.08826v1)) |
| **Off-distribution exploitation** | Score high on inputs unlike training data | OOD detector → force `escalate_to_hitl`, never auto-pass |
| **Intent drift** | Beautiful but ignores brief | Intent-fidelity gate \( I(x,b) \) multiplies AQ |
| **Opaque-scalar overfit** | Generator games one number | Rich, rationale-bearing preferences ([arXiv:2503.11720](https://arxiv.org/html/2503.11720)); decomposed vector never collapsed |
| **Taste monoculture / bias** | One narrow aesthetic encoded as "universal" | Mandatory explicit profiles; bias audit per LAION critique ([arXiv:2601.09896](https://arxiv.org/html/2601.09896v1)) |

**Core mechanisms:** (1) **Ensemble disagreement** — regression head, VLM critic, and detectors must agree; high disagreement raises \( H(x) \) and triggers HiTL. (2) **KL anchoring** to a reference generator during alignment to prevent runaway exploitation. (3) **Inference-time mitigation** for alignment without full fine-tuning ([arXiv:2510.01549](https://arxiv.org/abs/2510.01549)). (4) **Held-out human eval** as the non-negotiable ground truth — the agent's correlation with human raters is itself continuously monitored and is a release gate.

---

### 12. Technical Architecture & Implementation Guidelines

- **Core classes:** `AestheticCritic`, `AttributeHead[]`, `EnsembleScorer`, `IntentGate`, `EmotionGate`, `AntiHackGuard`, `Aligner`, `PreferenceBuilder`, `TasteKeeper`, `AestheticProfile`, `AestheticsAgent` (facade).
- **Models:** SigLIP/CLIP-ViT backbone + MLP regression head (fast tier, Aesthetic-Predictor-V2.5 lineage); VLM critic via swarm LLM providers (Grok-4.x vision / Gemini 2.5 Pro / GPT-4o); detector zoo (artifact, ΔE, depth, flow, FID/FVD, VBench-style).
- **Frameworks:** PyTorch + `diffusers` (for ReFL/DPO hooks); LangGraph node for orchestration; FastAPI service; Redis Streams for critique-bus publication.
- **Stores:** vector DB (Chroma/Pinecone) for exemplars & embeddings; profile DB (versioned, signed); episodic memory for refine-loop learning.
- **Provenance:** every verdict logs model versions, ensemble agreement, profile version → C2PA-aligned audit trail.
- **Deliverables:** repo skeleton, `AestheticVerdict` schema, profile schema, example notebooks (image scoring, video scoring, DPO alignment loop, profile elicitation), integration adapters for #6/#10/#46/#49.

---

### 13. Evaluation & Success Criteria

| Criterion | Target |
|---|---|
| Correlation with human aesthetic ratings (held-out) | Spearman ρ ≥ 0.75 on benchmark; ≥ 0.85 on personalized profile |
| Personalized > generic | Profiled model beats `neutral_baseline` at predicting owner's pairwise choices (per [arXiv:2605.14761](https://arxiv.org/html/2605.14761v1)) |
| Blind preference (downstream) | Outputs aligned via this agent win ≥ 55% blind pairwise vs. unaligned (Arena-style) |
| Reward-hacking resistance | Reward variance maintained; mode-collapse rate below threshold over a fine-tuning run |
| Anti-hack recall | ≥ 95% of human-flagged "fooled-the-eye" cases caught by `hack_likelihood` |
| Latency | Fast tier ≤ 800 ms; deep tier ≤ 8 s |
| Calibration | Confidence well-calibrated (ECE below threshold); low-confidence reliably escalates |
| Traceability | 100% of verdicts carry decomposed vector + provenance |

---

### 14. Limitations & Future Directions

- **No genuine lived aesthetic.** The agent's "sense" is statistical and derivative; it has no spontaneity or personal impulse. It is an *amplifier* of human taste — best used in symbiosis, with HiTL on novel or low-confidence judgments.
- **Taste is contested.** Even with explicit profiles, the corpus and rater pool carry bias; the agent surfaces *whose* taste it encodes rather than claiming universality.
- **Reward hacking is an arms race.** Defenses reduce, not eliminate, exploitation; held-out human eval remains the ground truth and release gate.
- **Future:** larger multimodal critics; brain-activity / biosignal proxies for emotional resonance; embodied/3D structural "seeing"; tighter artist co-training loops; cross-modal aesthetics (image↔music↔motion) shared with `ComposerAgent` and `ChoreographyAgent`.

---

### 15. References (Curated, 2024–2026)

Foundational & survey (from [`aesthetics_agents.md`](./aesthetics_agents.md)):
- NIMA — Neural Image Assessment (CNN aesthetic-distribution prediction).
- LAION-Aesthetics / CLIP+MLP improved aesthetic predictor; Aesthetic Predictor V2.5 (SigLIP-based).
- Multi-task / unified aesthetic models (UniQA, HumanAesExpert lineage); VBench (video aesthetic/quality benchmark).
- Aesthetic post-training of diffusion models; RLHF for diffusion (DDPO, ReFL, DPOK, RewardDance).

Current grounding (web-verified May 2026; *content rephrased for licensing compliance*):
- Personalized aesthetics via LLM interviews + semantic features — [arXiv:2605.14761](https://arxiv.org/html/2605.14761v1).
- Audit/ethnography of the LAION-Aesthetics predictor ("whose taste") — [arXiv:2601.09896](https://arxiv.org/html/2601.09896v1).
- Reward Scaling in Visual Generation (large RMs resist reward hacking via retained variance) — [arXiv:2509.08826](https://arxiv.org/html/2509.08826v1).
- Mitigating reward hacking in inference-time alignment of T2I diffusion — [arXiv:2510.01549](https://arxiv.org/abs/2510.01549).
- Rich Preference Optimization for diffusion fine-tuning (rationale-bearing preferences) — [arXiv:2503.11720](https://arxiv.org/html/2503.11720).
- Rethinking DPO in diffusion models — [arXiv:2505.18736](https://arxiv.org/abs/2505.18736).
- Alignment & safety of diffusion via RL + reward modeling — [arXiv:2505.17352](https://arxiv.org/abs/2505.17352).

Intra-system references:
- [`aesthetics_agents.md`](./aesthetics_agents.md) — source survey of artiste sense.
- [`general_creative_agent_functional_specification.md`](./general_creative_agent_functional_specification.md) — SSOR creativity (generate side of the loop; novelty inverted-U).
- [`agents.md`](./agents.md) — consuming agents (#6, #10, #14–16, #39, #46, #49).
- [`SYSTEM_REFERENCE.md`](./SYSTEM_REFERENCE.md) — critique bus (§7.1), handoff contract (§7), cross-cutting registration (§4).
- [`psychological_recommendation_agent_functional_specification.md`](./psychological_recommendation_agent_functional_specification.md) — audience-cohort profiles.

---

**This specification is complete, self-contained, and ready for immediate coding.** It transforms the "artiste sense" survey into a buildable, swarm-integrated agent: a decomposed multimodal Critic, a hack-resistant Aligner, and a consent-governed Taste-Keeper — the shared aesthetic nervous system of the VA-Agent-Swarm.

Implement exactly as written. The resulting Aesthetics Agent will give all 114 agents a single, trustworthy, personalizable "eye."

**End of Specification**
*Save as `aesthetics_agent_functional_specification.md`.*
