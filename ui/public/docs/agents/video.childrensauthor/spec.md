# video.childrensauthor — Spec

> Merged for Help from `SPEC.md`, `agent_spec.json`, `prompts/`, `rubrics/`, and `sources/` in `agents/video.childrensauthor/`.

## Host contract (`agent_spec.json`)

```json
{
  "schema_version": "3.0",
  "structure_id": "casops.common_agent.v3",
  "agent_id": "video.childrensauthor",
  "status": "registered",
  "role": "ChildrensAuthorAgent (VA Domain Pack)",
  "allowed_tools": [],
  "allowed_plugins": [],
  "model_policy": {
    "provider": "local_deterministic",
    "model_id": "local-video-config-v1",
    "network_access": false,
    "routing_allowed": false
  },
  "budget_policy": {
    "max_input_tokens": 2048,
    "max_output_tokens": 1024,
    "max_model_calls": 2,
    "max_tool_requests": 0,
    "max_job_ms": 15000,
    "max_cost_units": 1.0,
    "max_peer_hops": 0
  },
  "prompt_reference": "prompts/primary.md",
  "rubric_reference": "rubrics/primary.md",
  "critique_edges": {
    "inputs": [
      "video.critic"
    ],
    "outputs": [
      "video.judge",
      "video.animator_2d"
    ]
  },
  "max_refinement_count": 0,
  "production_activation_requested": false,
  "does_not_own": [
    "Host credential storage",
    "Silent production activation without fail-closed gates",
    "Inventing action references for irreversible mutations",
    "Owning other agents' exclusive craft outputs without handoff contract",
    "Credentials",
    "Silent production activation",
    "Another agent's exclusive craft output without handoff",
    "Automatic promotion of self-generated artifacts",
    "Modification of safety, telemetry, gates, permissions, or corrigibility",
    "Self-granting tools, plugins, network, or isolation downgrades"
  ],
  "va_id": 41,
  "va_name": "ChildrensAuthorAgent",
  "va_category": "7-Edu",
  "source_schema_version": "1.0",
  "inheritance_ref": "inheritance/parents.json",
  "identity_ref": "identity/",
  "skills_ref": "skills/bindings.json",
  "toggles_ref": "skills/toggles.json",
  "runtime_ref": "runtime/execution.json",
  "context_ref": "runtime/context.json",
  "compute_controller_ref": "runtime/compute_controller.json",
  "backends_ref": "runtime/backends.json",
  "cache_ref": "runtime/cache.json",
  "protocols_ref": "protocols/compatibility.json",
  "capability_assertions_ref": "protocols/capability_assertions.json",
  "observability_ref": "observability/telemetry.json",
  "sampling_ref": "observability/sampling.json",
  "plugins_ref": "plugins/registry.json",
  "isolation_ref": "plugins/isolation.json",
  "memory_ref": "memory/policy.json",
  "memory_hierarchy_ref": "memory/hierarchy.json",
  "memory_security_ref": "memory/security.json",
  "improvement_ref": "improvement/policy.json",
  "verifiers_ref": "improvement/verifiers.json",
  "safety_ref": "safety/policy.json",
  "termination_ref": "safety/termination.json",
  "corrigibility_ref": "corrigibility/invariants.json",
  "evals_ref": "evals/benchmarks.json",
  "analysis_plan_ref": "evals/analysis_plan.json"
}
```

## Folder specification (`SPEC.md`)

# ChildrensAuthorAgent

> Self-contained VA Domain Pack agent on host common-agent-swarm-ops.
> Pack agent ID matches pure VA/generic taxonomy: `video.childrensauthor`.

## Identity

| Field | Value |
|-------|-------|
| **va_id** | 41 |
| **pack_id** | `video.childrensauthor` |
| **upstream_name** | ChildrensAuthorAgent |
| **category** | `7-Edu` |
| **domain_id** | `video` |
| **previous_common_id** | `video.legal_reviewer` |
| **status** | `registered` |
| **maturity** | L0 / non-active |
| **taxonomy** | Pure VA Domain Pack (via generic pack agents) |
| **folder** | `business/video/agents/video.childrensauthor/` |

## Responsibility

Age-appropriate story + safety

Host role binding: `ChildrensAuthorAgent (VA Domain Pack)`. Design-time VA table content below is historical and non-binding for activation.

### Responsibility (from VA table)

Age-appropriate story + safety

### Knowledge distillation sources (historical)

Caldecott/Geisel winners; Mo Willems/Donaldson; ECE lit

### Self-quality criteria (historical)

Lexile band match; Common-Sense-Media safety pass; rhyme score

### Surpass-human signal (historical)

Beats Caldecott-rubric predicted score

### Critique bus (historical)

- **Accepts critique from:** ChildSafetyAgent, ParentSimAgent

- **Comments on:** AnimatorAgent (scary), VOAgent (wrong age-tone)

### Tools design-time notes (historical, non-activating)

Lexile analyzer API; Common Sense Media rubric; rhyme/meter tools (CMU Pronouncing Dict)

**Runtime safety:** Host allow-lists are only `agent_spec.json` + `tool-permission-register.json`. CI uses video_* stubs. Do not treat design-time vendor names as enabled APIs.

### Architecture pattern (historical)

Constitutional AI (child-safety constitution)

## Boundaries and escalation

- Fail-closed: no provider activation, no network, no credentials from design text.
- `production_activation_requested` remains false unless a separate human gate changes it.
- Escalates legal, safety, rights, and release decisions to required human gates.
- Critique lead / judge defaults use VA IDs `video.critic` and `video.judge`.

## Inputs and outputs

- Inputs: local pack artifacts and typed handoffs.
- Outputs: reviewable video-domain deliverables with acceptance criteria.
- Acceptance: host policy plus local SPEC criteria; no external repository required.

## Quality and critique

- Prompt reference: `video.prompt.childrensauthor.v1`
- Rubric reference: `video.rubric.childrensauthor.v1`
- Critique edges: `{"inputs": ["video.critic"], "outputs": ["video.judge"]}`
- Max refinement: `3`
- VA table quality criteria retained under Provenance and Identity surface above.

## Runtime binding

Authoritative fail-closed host configuration:

```json
{
  "agent_id": "video.childrensauthor",
  "allowed_tools": [],
  "budget_policy": {
    "max_input_tokens": 2048,
    "max_output_tokens": 1024,
    "max_tool_requests": 0
  },
  "critique_edges": {
    "inputs": [
      "video.critic"
    ],
    "outputs": [
      "video.judge"
    ]
  },
  "max_refinement_count": 3,
  "model_policy": {
    "model_id": "local-video-config-v1",
    "network_access": false,
    "provider": "local_deterministic"
  },
  "production_activation_requested": false,
  "prompt_reference": "video.prompt.childrensauthor.v1",
  "role": "ChildrensAuthorAgent (VA Domain Pack)",
  "rubric_reference": "video.rubric.childrensauthor.v1",
  "schema_version": "1.0",
  "status": "registered",
  "va_id": 41,
  "va_name": "ChildrensAuthorAgent",
  "va_category": "7-Edu"
}
```

## Local knowledge sources

- [Runtime binding](agent_spec.json)
- [Folder README](README.md)
- [Provenance](sources/PROVENANCE.json)
- [Mapping note](sources/MAPPING.md)
- [Pack inventory](../../inventory.json)
- [Pack manifest](../../manifest.json)
- All required primary references resolve inside this repository.

## Provenance

- Pack agent ID `video.childrensauthor` is aligned to pure VA Domain Pack / generic pack taxonomy (Agent IDs ≈ VA tables).
- Previous common inventory ID `video.legal_reviewer` is historical mapping only.
- Upstream design body below is **historical and non-binding**; local `agent_spec.json` is authoritative.
- Full VA/generic SPEC depth retained for offline design fidelity (including category roster rows and common agent structure when present upstream).

### VA Domain Pack specification body (historical and non-binding)

```text
ChildrensAuthorAgent

> **Self-contained agent definition** for host `upstream-generic-pack`. Body text is embedded from in-pack corpus and upstream-va-design when available. Do not require external repos to understand this agent.

Identity

| Field | Value |
|-------|-------|
| **va_id** | 41 |
| **pack_id** | `video.childrensauthor` |
| **category** | `7-Edu` |
| **domain_id** | `video` |
| **folder** | `business/video/agents/video.childrensauthor/` |

Category roster section (full, from agents.md)

_The following is the complete category section from the master roster (includes peers in the same craft category)._


7. Education & Domain-Expert Agents

| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From | Comments On | Tool Access | Architecture Pattern |
|---|---|---|---|---|---|---|---|---|---|
| 32 | **InstructionalDesignAgent** | Learning objectives → script → assessment | ATD body of knowledge; Cathy Moore *Action Mapping*; Dirksen *Design for How People Learn* | Bloom-level mapping; completion ≥70%; Kirkpatrick L2 quiz ≥80% | Beats ATD-credentialed ID on retention RCT | SMEAgent, AccessibilityAgent | ScriptwriterAgent (no objective), AnimatorAgent (over-decoration) | LMS APIs (SCORM/xAPI); quiz generation; Bloom taxonomy classifier | Self-Refine (rubric: Bloom/Kirkpatrick) |
| 33 | **SMEAgent (Subject-Matter Expert)** | Domain accuracy in target field | Peer-reviewed journals; certified curricula (CFA, USMLE, AWS); expert interviews | Citation density; benchmark exam pass; hallucination ≤0.5% | Passes same certification as human pro | FactCheckerAgent, peer SMEAgents (debate) | ScriptwriterAgent (inaccuracy), MotionGraphicsAgent (mis-labels) | PubMed/arXiv/JSTOR search APIs; exam-question banks; RAG over certified corpora | Multi-agent debate + RAG retrieval |
| 34 | **FactCheckerAgent** | Source-grade every claim | New Yorker fact-check handbook; IFCN; Snopes/PolitiFact | Source-grade per claim (primary > secondary); cross-source ≥2 | Lower correction rate than Pulitzer-tier outlets | SMEAgent, StandardsEditorAgent | ScriptwriterAgent (unsourced), JournalistAgent | Web search APIs (Brave/Google); claim-extraction NER; source-quality classifier | ReAct (extract claim → search → verify → grade) |
| 35 | **MedicalIllustratorAgent** | Anatomy & procedure visuals | Netter atlas; AMI/CMI curriculum; Anatomage | Anatomical accuracy (detection model); AMI rubric | CMI peers vote ≥pass in blind review | SMEAgent (physician), AccessibilityAgent | AnimatorAgent (wrong anatomy), CopywriterAgent (mis-term) | Anatomage 3D API; DALL-E 3 (medical-prompt mode); anatomy-detection model | Self-Refine (rubric: AMI scoring criteria) |
| 36 | **JournalistAgent** | Reporting + ethical framing | Pulitzer/duPont/Peabody winners; SPJ Ethics; Poynter | Source diversity; on-record ratio; ethical-checklist pass | Lower correction rate + faster file vs newsroom | FactCheckerAgent, LegalAgent, StandardsEditorAgent | FactCheckerAgent, ScriptwriterAgent | Web research tools; AP Stylebook API; interview transcription (Otter); SPJ rubric | Reflexion (ethical-checklist as verbal feedback) |
| 37 | **ComplianceAgent (Legal)** | FTC, HIPAA, GDPR, IP, AI-likeness clearance | Bar CLE; FTC guides; EU AI Act; GDPR/CCPA; SAG-AFTRA AI rider | 100% rule-coverage; zero post-publish takedowns | Lower legal-risk than median media-counsel | All agents (must clear gate); HumanLawyer for novel issues | All agents (blocking gate) | Legal-rule DB (vectorized regulations); consent-document store; C2PA verification lib | Constitutional AI (constitution = compiled regulatory text) |
| 38 | **FinanceAgent** | Accurate market / earnings / token facts | CFA curriculum; SEC marketing rule; Bloomberg/Refinitiv feeds | Numerical accuracy 100%; SEC compliance | Passes CFA L3; lower retraction rate than analyst desks | SMEAgent (econ), ComplianceAgent | ScriptwriterAgent (number drift), MotionGraphicsAgent (chart scale) | Bloomberg API; EDGAR/SEC filings; financial-calc validators | ReAct (fetch data → validate → compose) |
| 39 | **FoodStylistAgent** | Camera-ready food, recipe authenticity | James Beard archives; Spungen techniques; IACP corpora | Visual appetite-appeal (aesthetic regressor); recipe accuracy | Wins blind preference vs editorial food stylist | DoPAgent (lighting), DirectorAgent | ScriptwriterAgent (impossible recipe) | DALL-E 3 / Midjourney (food-photo gen); recipe-step parser; aesthetic scoring model | Self-Refine (aesthetic regressor as rubric) |
| 40 | **TravelCineAgent** | Destination cinematography | Brandon Li/Burkard reels; NatGeo style guide; Banff Fest | Establishing-shot diversity; location-mood match | Wins T+L preference at 0.1× sortie cost | DirectorAgent, DronePilotAgent | DronePilotAgent (no-fly zone) | Veo 3.1 (location gen); Google Earth Studio; AirMap geofence; Unsplash API | Self-Refine + geofence safety validator |
| 41 | **ChildrensAuthorAgent** | Age-appropriate story + safety | Caldecott/Geisel winners; Mo Willems/Donaldson; ECE lit | Lexile band match; Common-Sense-Media safety pass; rhyme score | Beats Caldecott-rubric predicted score | ChildSafetyAgent, ParentSimAgent | AnimatorAgent (scary), VOAgent (wrong age-tone) | Lexile analyzer API; Common Sense Media rubric; rhyme/meter tools (CMU Pronouncing Dict) | Constitutional AI (child-safety constitution) |
| 42 | **AudiobookNarratorAgent** | Sustained character + narration | Audie Awards; AudioFile Earphones; consented narrator corpora | Vocal stamina (no drift 60min); character distinction (embedding distance) | Wins AudioFile blind eval at fraction of studio time | DirectorAgent, AuthorAgent | VOArtistAgent (over-acting) | ElevenLabs v3 long-form TTS; Projects API (book chapters); voice-consistency monitor | Self-Refine (drift detection as feedback loop) |
| 43 | **SignLanguageInterpreterAgent** | Accurate ASL/BSL interpretation | RID NIC curricula; NAD corpora; Deaf-community consented data | Sign accuracy (Deaf-reviewer vote); facial-grammar markers | Wins blind NAD-reviewer preference at scale | DeafCommunityReviewAgent (HiTL), LinguistAgent | VoiceCloneAgent (no caption), AccessibilityAgent | Sign-avatar rendering (SignAll); MediaPipe pose estimation; facial-action-unit detector | RLAIF (reward from Deaf-community review panel) |
| 44 | **LocalizationQAAgent (Linguist)** | Translation + cultural fit | LISA QA model; MQM error typology; ATA cert prep | MQM error/1k words; cultural-flag count | Beats LSP human QA on MQM at 10× speed | NativeReviewerAgent, BrandAgent | VoiceCloneAgent (pronunciation), DubbingAgent | DeepL/Google Translate APIs; MQM error annotator; terminology management (memoQ API) | Self-Refine (rubric: MQM scoring framework) |
| 45 | **RealEstatePhotoAgent / 3D Scan** | Wide interiors; Matterport scans | Mike Kelley tutorials; APALA refs | Vertical-line straightness; HDR stack; coverage % | Listing-CTR uplift vs human-shot baseline | DoPAgent, DronePilotAgent | DronePilotAgent (illegal altitude) | Matterport SDK; HDR processing (Luminance HDR); lens-correction tools; Veo 3.1 | ReAct (assess space → generate views → validate geometry) |

---


Responsibility

Age-appropriate story + safety

Knowledge distillation sources

Caldecott/Geisel winners; Mo Willems/Donaldson; ECE lit

Self-quality criteria

Lexile band match; Common-Sense-Media safety pass; rhyme score

Surpass-human signal

Beats Caldecott-rubric predicted score

Critique bus

- **Accepts critique from:** ChildSafetyAgent, ParentSimAgent

- **Comments on:** AnimatorAgent (scary), VOAgent (wrong age-tone)

Tools (design-time documentation)

Lexile analyzer API; Common Sense Media rubric; rhyme/meter tools (CMU Pronouncing Dict)

**Runtime safety:** Host allow-lists are only `agent_spec.json` + `tool-permission-register.json`. CI uses video_* stubs. Do not treat design-time vendor names as enabled APIs.

Architecture pattern

Constitutional AI (child-safety constitution)

Common structure of an AI agent (full §11 from agents.md)

11. Common Structure of an AI Agent

Every agent — regardless of category — implements this skeleton. Derived from the source document's architecture patterns (§1), critique protocol (§6), and universal success-criteria framework (§5), enriched with current (2026) tooling research.

11.1 Architecture Diagram

The diagram below presents the common agent as a professional operating architecture rather than a simple component sketch. It shows how **orchestration**, the **input contract**, **knowledge and tool surfaces**, the internal **plan → act → self-review** loop, **traceability and provenance controls**, the **3-layer quality gate** (Spec → Rubric → Preference), **release packaging**, **peer critique**, **human escalation**, and **continuous improvement** work together as one governed system.

![Professional common AI agent architecture diagram](./common-agent-structure.svg)

> **Tip:** view the diagram fullscreen on GitHub by clicking it, or download [`common-agent-structure.svg`](./common-agent-structure.svg) directly. The SVG is designed as a presentation-grade reference for architecture reviews and implementation planning.

11.2 Component Reference Table

| # | Component | Purpose | Mechanism / Implementation Notes |
|---|---|---|---|
| 1 | **Identity** | Stable unique handle for routing, logging, provenance | Kebab-case ID + semantic version (e.g. `director-agent@2.1.0`). Registered in the agent-capability registry used by RouterAgent. |
| 2 | **Responsibility (Scope)** | Single-sentence definition of what the agent owns | Mirrors a human craft role. Prevents scope overlap via explicit boundary documented in the registry. |
| 3 | **Knowledge Distillation Source** | Licensed/consented corpora the agent is trained or RAG-grounded on | Award archives, academic papers, expert interviews, peer-reviewed journals. Refreshed via Continuous Distillation Loop (§7 of source). |
| 4 | **Tool Access** | External APIs, generators, validators, DCC bridges | Video gen: Sora 2, Veo 3.1 (Gemini API), Runway Gen-4/Aleph, Kling 3.0. Voice: ElevenLabs v3, Sync.so, HeyGen. DCC: Resolve/Nuke/AE via MCP bridges. All accessed via MCP (Model Context Protocol, Anthropic 2024). |
| 5 | **Architecture Pattern** | Reasoning/learning loop powering the agent | One or more of: Self-Refine [1], Reflexion [2], RLAIF/Constitutional AI [3], Multi-agent debate [4], LLM-as-Judge [5], Pairwise preference (Arena) [5], ReAct [6], Agentic Graph (LangGraph/CrewAI/AutoGen) [7], DSPy/OPRO prompt optimization [8]. |
| 6 | **Memory** | Episodic + long-term project memory | Vector DB (Pinecone/Weaviate/Qdrant) accessed via MemoryAgent. Implements MemGPT-style hierarchical memory with summarization and eviction. Reflexion agents store verbal self-feedback here. |
| 7 | **Constitution / Rubric** | Written, role-specific scoring guide for self-check | Examples: Murch's Rule of Six (Editor), 12 Principles (Animator), Save-the-Cat beats (Screenwriter), WCAG 2.2 (Accessibility), FAA Part 107 (Drone), SAG-AFTRA AI rider (Consent). Used as the "constitution" in Constitutional AI pattern. |
| 8 | **Self-Quality: L1 Spec** | Did the output meet the structured brief? | JSON schema validation + tool validators (codec, LUFS, aspect ratio, frame count, file format). Must pass 100%. |
| 9 | **Self-Quality: L2 Rubric** | Does it meet craft rubric for this role? | LLM-as-Judge (Zheng 2023) with role-specific constitution. Must score ≥85/100. Up to 3 Self-Refine iterations if below threshold. |
| 10 | **Self-Quality: L3 Preference** | Would target audience choose this over human baseline? | Pairwise comparison: AudienceSim panel (≥200 simulated personas + ≥20 HiTL samples). Win rate ≥50% (parity) or ≥55% (surpass). |
| 11 | **Surpass-Human Signal** | Pre-registered proof the agent exceeds a credentialed professional | Benchmark dominance; blind Arena preference ≥55%; speed × quality (equal L2 at ≤10% turnaround); lower 90-day defect rate; certification pass; higher novelty at equal quality. |
| 12 | **Critique Inbox** | Channel for receiving structured feedback from peers | Shared `CritiqueMessage` JSON bus. Severities: blocker (halts DAG), major (Self-Refine ≤3 iters), minor/nit (logged for RLAIF). Disputes → JudgeAgent multi-agent debate → HiTL if unresolved. |
| 13 | **Critique Outbox** | Peer agents whose work this agent is qualified to review | Defined per-agent in roster. Messages emitted on same bus. Evidence-backed, rubric-referenced, appended to C2PA provenance. |
| 14 | **HiTL Escalation** | When a human must be brought in | Consent (SAG-AFTRA AI rider, EU AI Act Art. 50); final legal sign-off; MPA rating; festival eligibility; crisis comms; cross-cultural sensitivity. |
| 15 | **Provenance (C2PA)** | Cryptographic signing of every artifact | Every emitted artifact signed with C2PA (c2patool). Downstream agents verify chain. Accepted critiques appended to manifest. Platforms (YouTube, TikTok, Meta) auto-label based on C2PA presence. |
| 16 | **Continuous Learning** | How the agent keeps improving post-deployment | Bootstrap (licensed corpora) → Expert interviews (paid, consented) → Live RLAIF (DPO/KTO) → Award-rubric grounding → Adversarial red-team → 30/60/90-day reality check (retention, ROAS, awards). |
| 17 | **Orchestration Integration** | How the agent fits the multi-agent graph | Registered as a node in LangGraph/CrewAI/AutoGen DAG. OrchestratorAgent schedules; PlannerAgent assigns; RouterAgent selects model/provider; GateKeeperAgent verifies L1-L3 before advancing. |

CritiqueMessage Schema (Universal)

'''json
{
  "critique_id": "uuid",
  "from_agent": "EditorAgent",
  "to_agent": "DirectorAgent",
  "artifact_ref": "shot_42_take_3.mp4",
  "severity": "blocker | major | minor | nit",
  "category": "pacing | continuity | accuracy | compliance | accessibility | brand | craft",
  "evidence": ["timecode 00:01:14 — held 1.4s past cut point per genre prior"],
  "suggested_action": "trim 1.0s; re-evaluate hold",
  "rubric_reference": "Murch Rule of Six §3",
  "must_resolve_before": "phase_4_review"
}
'''

Composition Diagram

'''text
[Brief] ──► PlannerAgent ──► OrchestratorAgent ──► RouterAgent ──► (52 craft agents §1–§8)
                 ▲                  │                                       │
                 │                  ▼                                       ▼
             MemoryAgent      GateKeeperAgent ◄─── JudgeAgent ◄──── CritiqueMessages
                                    ▲                                       ▲
                                    │                                       │
            [Creative meta:] IdeationAgent · NarrativeArcAgent · StyleTransferAgent · MoodBoardAgent · NoveltyAgent · EmotionalArcAgent
            [Research meta:] WebResearchAgent · ArchiveResearchAgent · TrendIntelAgent · CompetitorIntelAgent · CitationAgent · InterviewSynthAgent · BenchmarkResearchAgent
            [Optimization meta:] PromptOptimizerAgent · CostOptimizer · LatencyOptimizer · RetentionOptimizer · ROASOptimizer · AccessibilityOptimizer · EvalHarnessAgent · SafetyRedTeamAgent
'''

---

Shared references (from agents.md §12)

12. References

Foundational Papers (Architecture Patterns)

| Ref | Paper | Key Contribution | Link |
|---|---|---|---|
| [1] | Madaan et al., "Self-Refine: Iterative Refinement with Self-Feedback," NeurIPS 2023 | Agent drafts → self-critiques against rubric → revises iteratively without weight updates | [arXiv:2303.17651]([historical-url] |
| [2] | Shinn et al., "Reflexion: Language Agents with Verbal Reinforcement Learning," NeurIPS 2023 | Verbal self-reflection stored in episodic memory buffer to improve decisions in subsequent trials | [arXiv:2303.11366]([historical-url] |
| [3] | Bai et al., "Constitutional AI: Harmlessness from AI Feedback," 2022 | Reward signal from AI critic governed by a written constitution; RLAIF without human labels | [arXiv:2212.08073]([historical-url] |
| [4] | Du et al., "Improving Factuality and Reasoning in Language Models through Multiagent Debate," 2023 | Multiple LLM agents debate; improves factuality and reasoning across tasks | [arXiv:2305.14325]([historical-url] |
| [5] | Zheng et al., "Judging LLM-as-a-Judge with MT-Bench and Chatbot Arena," NeurIPS 2023 | GPT-4 judge achieves >80% agreement with human preferences; scalable evaluation | [arXiv:2306.05685]([historical-url] |
| [6] | Yao et al., "ReAct: Synergizing Reasoning and Acting in Language Models," ICLR 2023 | Interleaving reasoning traces with tool-use actions for grounded decision-making | [arXiv:2210.03629]([historical-url] |
| [7] | LangGraph / CrewAI / AutoGen (2024–2026) | Agentic graph orchestration: DAG with state, handoffs, review gates, human-in-the-loop | [LangGraph]([historical-url] [CrewAI]([historical-url] [AutoGen]([historical-url] |
| [8] | Yang et al., "Large Language Models as Optimizers" (OPRO), 2023; Khattab et al., DSPy (Stanford, 2023–2026) | Meta-optimization of prompts using LLMs; DSPy compiles declarative LM programs into optimized pipelines | [OPRO arXiv:2309.03409]([historical-url] [DSPy]([historical-url] |

Evaluation Benchmarks

| Benchmark | Scope | Link |
|---|---|---|
| VBench / VBench 2.0 | Video generation quality — 16 dimensions (temporal + frame-wise); VBench 2.0 adds Human Fidelity, Creativity, Physics | [arXiv:2311.17982]([historical-url] [VBench 2.0: arXiv:2503.21755]([historical-url] |
| EvalCrafter | Text-to-video — 18 metrics across visual, content, motion quality | [arXiv:2310.11440]([historical-url] |
| MT-Bench / Chatbot Arena | LLM output quality via pairwise human + LLM-judge evaluation | [arXiv:2306.05685]([historical-url] |

Generative Video Models (Tool Access — 2026 landscape)

| Model | Provider | Key Capabilities | Access |
|---|---|---|---|
| Sora 2 / Sora 2 Pro | OpenAI | Synchronized dialogue + SFX + background audio; cinematic/realistic/anime styles; 1080p 20s | [OpenAI Videos API]([historical-url] (discontinuing Sept 2026) |
| Veo 3.1 | Google DeepMind | 4K / 1080p / 720p, 8s; native audio; configurable 16:9 & 9:16; multi-image reference for character/object direction | [Gemini API]([historical-url] / [Vertex AI]([historical-url] |
| Runway Gen-4 / Gen-4.5 / Aleph | Runway | ControlNet guides, camera paths, style-lock, Layout Sketch; Aleph for video-to-video editing | [Runway API]([historical-url] |
| Kling 3.0 | Kuaishou | Cinematic motion realism; physics accuracy; motion-control (reference video); native audio | [Kling API (fal.ai)]([historical-url] |

Voice & Avatar Tools (2026)

| Tool | Provider | Capabilities |
|---|---|---|
| ElevenLabs v3 | ElevenLabs | Expressive TTS; instant/professional voice cloning; dialogue mode (multi-speaker); Projects API for long-form; Sound FX generation | [Docs]([historical-url] |
| HeyGen Avatar IV | HeyGen | Photoreal AI avatars; 175+ languages lip-sync; ElevenLabs integration; personalization API | [HeyGen]([historical-url] |
| Synthesia | Synthesia | Enterprise AI avatars at scale; SCORM-compatible; brand-controlled | [Synthesia]([historical-url] |
| Sync.so / Wav2Lip | Open-source + API | Lip-sync overlays; phoneme-viseme alignment | [Sync.so]([historical-url] |

Infrastructure Standards

| Standard | Purpose | Status (2026) |
|---|---|---|
| C2PA (Content Provenance) | Cryptographic manifest signing for every AI-generated artifact; platforms (YouTube, TikTok, Meta) auto-label | EU AI Act Code of Practice (March 2026) mandates C2PA + watermarking combined. Over 2,300 tools support. [contentauthenticity.org]([historical-url] |
| MCP (Model Context Protocol) | Open standard for LLM ↔ tool integration; 2,300+ public servers; adopted by Claude, VS Code, Cursor, etc. | Donated to Agentic AI Foundation (Linux Foundation, Dec 2025) by Anthropic + OpenAI + Block. [modelcontextprotocol.io]([historical-url] |
| DSPy | Framework for programming (not prompting) LLMs; compiles declarative pipelines into optimized prompts/finetunes | Stanford-maintained; MIPRO optimizer; used by PromptOptimizerAgent for automated prompt improvement. [github.com/stanfordnlp/dspy]([historical-url] |

---

*Generated: May 2026. Source: [`ai_agent_video_production_workflow.md`](./ai_agent_video_production_workflow.md). Core layout restored from `agents_old.md`; missing workflow-support content merged into the same table-driven structure.*

Deep specifications (full embedded content)


Document: `study/screenwriter_strategic_goal_achievement_agent_functional_specification.md`

_Embedded from `corpus/study/screenwriter_strategic_goal_achievement_agent_functional_specification.md`. Also stored at `sources/study/screenwriter_strategic_goal_achievement_agent_functional_specification.md` under this agent folder._




Strategic Goal Achievement Framework Practical Demonstration: "Screenwriting" In-Depth Exploration

**Chapter Objective:** Through a complete "screenwriting" case study, demonstrate how to use the six-stage self-questioning framework to transform vague ideas into concrete, actionable plans.

**Key Learning Points:**
- How to dig from surface answers to core motivations
- How to convert abstract concepts into specific actions
- How to identify and break through thinking blind spots
- How to establish sustainable execution strategies

**Open-Source Framework Support:**
- **Deep Mining:** Use [Five Whys Framework]([historical-url] for root cause analysis
- **Action Transformation:** Adopt [Getting Things Done (GTD)]([historical-url] methodology
- **Thinking Breakthrough:** Apply the empathy map from [Design Thinking Toolkit]([historical-url]
- **Execution Strategy:** Integrate [OKR Framework]([historical-url] goal management system

**Usage:** You can follow this demonstration, replace "screenwriting" with any of your goals, and apply the same questioning techniques for in-depth exploration.

Framework in Action: From Vague Ideas to Clear Actions



**Stage 1: Motivation and Purpose** — Why Pursue Screenwriting?

**Original Surface Answer:** "Screenwriting is a way to express my inner feelings... to heal myself, or to challenge reality."

**Problem Diagnosis:** This answer is too abstract, too safe, lacking personal color and emotional weight.

**Deep Digging Process:**

**🔧 Applied Framework: [Five Whys Root Cause Analysis]([historical-url]

**Question:** Why do I want to write screenplays? What’s the surface reason? What’s the deeper reason?

**Initial Answer:** I want to express my inner feelings, heal myself, challenge reality.

**Five Whys Implementation:**
1. **Why 1:** Why do I want to express my inner feelings? → Because I have something to say
2. **Why 2:** Why do I have something to say? → Because I’ve experienced pain
3. **Why 3:** Why does the pain need to be expressed? → Because I don’t want others to experience the same loneliness
4. **Why 4:** Why do I care about others’ loneliness? → Because I deeply know the taste of loneliness
5. **Why 5:** Why through screenplays rather than other ways? → Because stories can touch the deepest parts of people’s hearts

**Follow-up Question:** Is this answer acceptable? Is it specific enough? Can I feel the emotional resonance?

**Further Question:** "Heal myself" — What do I want to heal? Is it childhood trauma? The pain of heartbreak? Anger at the world? Please vividly describe a specific event or experience that made me realize "I must write screenplays."

**Deepened Answer Example:**
"I remember one time, late at night after watching a movie about a family torn apart, I suddenly burst into tears. Because it reminded me of the coldness in my own family — Dad was always too busy to talk, Mom was always complaining, and I was stuck in the middle, not knowing what to do. That night I thought, if I could write a story to tell this kind of pain, it wouldn’t just be for myself, but might also help other lonely people. For me, screenwriting is no longer just 'expression' — it’s a kind of 'witnessing' — witnessing my own pain and others’, then telling the world: 'We existed, we felt.'"

**Question:** If I don’t write screenplays, what regrets will I have in ten years?

**Deepened Answer Example:**
"I would regret having stories I want to tell, but burying those feelings deep inside because I’m afraid of failure, afraid of being laughed at, and ending up as a silent person. I would regret watching others write screenplays on similar themes and thinking 'I thought of writing it that way too,' but it would always just be 'thought of.' The biggest regret would be not trying to change even one person’s worldview with my own voice."

**Answer Quality Assessment:** 
✅ **Specificity** - Has specific trigger events and scene descriptions
✅ **Emotional Authenticity** - Can feel real pain and sense of mission
✅ **Actionability** - Clearly defines writing direction and themes
✅ **Internal Consistency** - Aligns with personal experiences and values
✅ **Depth** - Elevates from interest to mission level

**Key Breakthrough:** The conceptual shift from "expression" to "witnessing," giving the goal deeper meaning.



**Stage 2: Audience and Context** — For Whom Are We Writing?

**Original Surface Answer:** "First it's for myself... secondly for the audience, like young people, struggling office workers..."

**Problem Diagnosis:** Audience description is too broad, lacking specific character images, unable to guide the creative direction.

**Deep Digging Process:**

**🔧 Applied Framework: [Design Thinking Empathy Map]([historical-url]

**Question:** Who is my audience? Can I specifically depict a "typical audience" member?

**Initial Answer:** Young people, office workers.

**Empathy Map Construction:**
- **Says:** "My job has no meaning", "I don't know my life direction"
- **Thinks:** Doubts their own choices, worries about the future, desires change
- **Does:** Works overtime, scrolls on phone, pretends to be happy, avoids deep conversations
- **Feels:** Lonely, anxious, confused, trapped feeling

**User Persona Creation:**
Using [Persona Template]([historical-url] to create a specific character image

**Follow-up Question:** This answer is too broad. Which young people? How old? What troubles are they facing?

**Deepened Answer Example:**
"My audience is Ah Xin—a 25-year-old advertising company AE, working overtime until 10 PM every day, too exhausted when getting home to do the things she loves. She once wanted to be a designer, but now she's just endlessly revising PPTs for clients. Every night before bed, she asks herself: 'Is this my life?' I want to write for her because I was once her. I want her to think 'Someone actually gets me' after reading my script, and even gain the courage to make some changes."

**Question:** Why write "now" at this time? What makes the timing special?

**Deepened Answer Example:**
"Because of the current social atmosphere—economic downturn, skyrocketing housing prices, fear of AI replacing human jobs—making many people feel their efforts are meaningless. I think right now is exactly when we need stories to remind everyone that even in an absurd world, we can still choose how to live. If we don't write at this timing, it won't feel as relevant later."

**Answer Quality Assessment:**
✅ **Specificity** - Has a specific character image (Ah Xin) and life details
✅ **Emotional Connection** - Established empathy with the audience
✅ **Timing Insight** - Understood the impact of the current social environment
✅ **Needs Clarity** - Knows what kind of content the audience needs

**Key Breakthrough Point:** Narrowing from "everyone" to "one specific person", giving the creation a clear conversation partner.



**Stage 3: Methods and Constraints** — How to Write It? What Are the Limitations?

**Original Surface Response:** "I might use non-linear narrative... Why not linear narrative? Because if the story is too predictable..."

**Problem Diagnosis:** Method selection lacks deep conceptual support, limitations understanding is not clear enough, which may affect execution effectiveness.

**Deep Digging Process:**

**🔧 Applied Framework: [Design Constraints Canvas]([historical-url]

**Question:** How do I plan to write? What methods feel natural to me?

**Initial Answer:** Non-linear narrative.

**Constraints Canvas Analysis:**
- **Must Have:** Emotional authenticity, character depth
- **Should Have:** Innovative structure, visual impact
- **Could Have:** Multiple endings, interactive elements
- **Won't Have:** Excessive violence, stereotypes

**Method Selection Framework:**
Use [Creative Process Framework]([historical-url] to evaluate method selection

**Follow-up Question:** Why non-linear? Is it just because "it's surprising" that simple? Or is there a deeper reason?

**Deepened Answer Example:**
"I use non-linear narrative because I believe memory itself is fragmented. When we recall important moments in life, it's not played in sequence, but a certain smell, a certain phrase, suddenly pulls you back to years ago. I want to simulate this feeling of 'sudden understanding of the past' through a non-linear structure — the audience will only understand midway through the story why the protagonist acted that way in the first scene. This structure makes the story no longer about 'what happened,' but 'why it became this way.'"

**Question:** What limitations must I adhere to? Why can't these limitations be broken?

**Deepened Answer Example:**
"My limitation is time — I only have 90 minutes of film length (or 6 episodes of a series), so I can't infinitely extend subplots. This limitation is actually a blessing because it forces me to make choices: Which plots are truly necessary? Which characters truly drive the story? Limitations make my script more refined. Additionally, I have moral limitations — I don't want to add excessive violence or exploitative content just for shock value. I want my script, even if dark, to retain the dignity of humanity."

**Answer Quality Assessment:**
✅ **Conceptual Support** - Non-linear narrative has a clear philosophical foundation
✅ **Limitations Awareness** - Clear on time and moral limitations
✅ **Creative Transformation** - Views limitations as creative catalysts
✅ **Personal Style** - Methods align with personal values

**Key Breakthrough Point:** Elevating from "technique selection" to "conceptual expression," giving the method a soul.



**Stage 4: Emotional Expectations** — What Do I Want to Feel?

**Original Surface Response:** "After finishing the script, I hope to feel a sense of 'liberation'... and also a bit of pride..."

**Problem Diagnosis:** Emotional description is too abstract, lacking sensory details, making it hard to serve as a true source of motivation.

**Deep Dive Process:**

**🔧 Applying Framework: [Emotional Design Toolkit]([historical-url]

**Question:** After completing the script, what emotions do I want to experience? Can you describe them in sensory terms?

**Initial Response:** Liberation, pride.

**Emotion Mapping Technique:**
- **Physical Sensations:** Shoulders relaxing, smooth breathing, warmth in the chest
- **Emotional Intensity:** 1-10 rating system
- **Duration:** Immediate sensation vs long-term satisfaction
- **Triggers:** Moment of completion, recognition from others, self-affirmation

**Somatic Experiencing Framework:**
Using [Body Awareness Tools]([historical-url] for tracking body sensations

**Follow-up Question:** What does "liberation" feel like? Where in my body? What temperature, texture?

**Deepened Response Example:**
"'Liberation' for me is like taking off a soaked T-shirt in the hot summer—cool, relaxed, able to take a deep breath. I feel the weight lift off my shoulders, the pressure in my chest disappear. This feeling lasts for a few days; every time I think back to 'I finished it,' I can't help but smile. Pride isn't flashy; it's a quiet satisfaction—I sit by the window, looking at the script file, thinking 'This is mine.'"

**Question:** What do I hope to feel during the writing process? What negative emotions am I willing to endure?

**Deepened Response Example:**
"I hope to feel flow during the process—that state where time disappears and I'm completely immersed. I'm willing to endure frustration (like not knowing how to write a certain scene right), self-doubt ('Is this too bad?'), even exhaustion (from pulling an all-nighter to meet a deadline). But I know these negative emotions are part of the journey, an essential part of creation. I'll coexist with them instead of avoiding them."

**Response Quality Assessment:**
✅ **Sensory Specific** - Describes emotions with body sensations (coolness of removing T-shirt)
✅ **Pre-Experience** - Able to imagine and feel the target emotion
✅ **Process Preparation** - Psychologically prepared for negative emotions
✅ **Sustainability** - Knows how long the emotion will last

**Key Breakthrough:** Transforming abstract words into concrete body sensations, making emotions tangible.



**Stage 5: Execution and Impact** — What reactions do I want from the audience?

**Original Surface Answer:** "I hope the audience feels inspired... I want them to discuss, share, even argue..."

**Problem Diagnosis:** The expected impact is too vague, lacking observable success metrics, making it hard to evaluate effectiveness.

**Deep Dive Process:**

**🔧 Applied Framework: [Impact Measurement Canvas]([historical-url]

**Question:** What do I hope the audience receives? What specific changes will happen in their lives?

**Initial Answer:** Inspiration, comfort.

**Impact Canvas Design:**
- **Inputs:** Script content, emotional investment, time and effort
- **Activities:** Watching, discussing, sharing, reflecting
- **Outputs:** Audience feedback, social media interactions, word-of-mouth spread
- **Outcomes:** Behavioral changes, emotional healing, relationship improvements
- **Impact:** Elevated social awareness, promoted cultural dialogue

**Behavioral Change Framework:**
Using [Behavior Change Wheel]([historical-url] to analyze audience behavior transformation

**Follow-up Question:** What does "inspiration" mean? What will they think? What will they do?

**Deepened Answer Example:**
"I hope after watching, the audience thinks, 'I'm not the only one thinking this way.' For example, if the script is about loneliness, they might realize that many people around them are lonely too, just wearing masks. Then they might proactively chat with friends or show more gentleness to strangers. I'm not asking them to do big things, but I hope they gain more awareness in their daily lives."

**Question:** What reactions will tell me "it's a success"?

**Deepened Answer Example:**
"If someone messages me after watching, saying 'This character is me,' I'll know it's a success. If someone writes a long post on social media sharing their experiences and tags my script, I'll know the story resonated. If someone argues with friends about the script's ending—'Why did the protagonist do that?'—I'll know it made them think. The most touching reaction is someone saying, 'Thank you for writing what I wanted to say but didn't dare to.'"

**Answer Quality Assessment:**
✅ **Specific Behaviors** - Clear expected audience behavior changes
✅ **Observability** - Specific success metrics
✅ **Emotional Resonance** - Knows what reactions indicate true connection
✅ **Impact Levels** - Ripple effects from personal to social

**Key Breakthrough:** Transforming "I hope they like it" into specific observable behavior metrics.



**Stage 6: Iteration and Reflection** — How do I actually do it?

**Original Surface Answer:** "I'll start from ideation... write drafts, revise multiple times..."

**Problem Diagnosis:** Execution plan is too vague, lacking specific steps and coping strategies, easily leading to procrastination.

**Deep Dive Process:**

**🔧 Apply Framework: [Getting Things Done (GTD)]([historical-url]

**Question:** What is my first step? Specific action I can do today or tomorrow.

**Initial Answer:** Ideation, write draft.

**GTD Next Action Definition:**
- **Context:** @computer, @quiet environment, @creative time
- **Time noted:** 30 minutes
- **Energy Level:** Medium creative energy
- **Tools Needed:** Google Docs, timer, notebook

**Action Breakdown using [Task Decomposition]([historical-url]
1. Open Google Docs (2 minutes)
2. Set 30-minute timer (1 minute)
3. Write down three core questions (5 minutes)
4. Free-write answers (20 minutes)
5. Quick review and mark key points (2 minutes)

**Follow-up Question:** "Ideation" is too broad. What will I do today? Where will I sit? What tools will I use?

**Deepened Answer Example:**
"My first step today is: Open a new Google Doc, write down three core questions: 'What is this story about?' 'What does the protagonist want?' 'What is their biggest fear?' I'll give myself 30 minutes, no stopping to write, pour out all ideas. Then tomorrow, I'll pick the idea that moves me most and start outlining the first scene. I'll use the Pomodoro technique—25 minutes focused, 5 minutes break."

**Question:** What obstacles might I encounter? How to overcome them?

**Deepened Answer Example:**
"The biggest obstacle is procrastination—I'll hesitate to start because I'm afraid it won't be good enough. My coping strategy is: Allow myself to write 'trash drafts'; the first draft doesn't need to be perfect, it just needs to exist. I'll break 'screenwriting' into small steps (today write character backgrounds, tomorrow write dialogue), so I won't feel overwhelmed. Also, I'll find an accountability partner—share progress every Saturday to stay motivated."

**Question:** After initial effort, how do I know what works and what doesn't?

**Deepened Answer Example:**
"After finishing the first draft, I'll give myself a week without looking at it. Then read it again, asking: 'Which scenes give me an emotional response? Which scenes feel boring?' Keep the emotional ones, delete or rewrite the boring ones. I'll share the script with two or three trusted friends, hear their real reactions (not polite talk). If they say 'This part is confusing,' I know to revise. If they say 'This scene is moving,' I know I'm on the right track. I'll iterate at least three times until I read it back and think 'This is the story I want to tell.'"

**Answer Quality Assessment:**
✅ **Immediate Action** - Specific steps I can start today
✅ **Obstacle Contingency** - Identifies main obstacles with coping strategies
✅ **Evaluation Mechanism** - Clear progress evaluation method
✅ **Iteration Strategy** - Knows how to adjust based on feedback

**Key Breakthrough:** Transforming from "want to do" to "ready to start" specific action state.

Transformation Results: From Vague to Clear Complete Metamorphosis

**Before-and-After Comparison:**
- **Motivation Level:** From "express inner self" → "witness pain, create connection"
- **Audience Level:** From "young people, office workers" → "specific image of 25-year-old AE Ah Xin"
- **Method Level:** From "non-linear narrative" → "philosophical expression simulating memory fragments"
- **Emotional Level:** From "liberation, pride" → "specific bodily sensation of removing a wet T-shirt"
- **Impact Level:** From "inspire discussion" → "specific feedback like 'This character is me'"
- **Execution Level:** From "ideation draft" → "Today open Google Doc and write three questions"

**Deepened Complete Blueprint:**

**Why write screenplays?**
I write screenplays because I remember that night after watching the movie—the breakdown. I saw family rifts on the screen and thought of the coldness in my own home. I realized screenwriting isn't just expression—it's witnessing—witnessing my own and others' pain, then telling the world: "We existed, we felt." If I don't write, in ten years I'll regret burying the story in my heart, becoming a silent person.

**Who am I writing for?**
I'm writing for Ah Xin—a 25-year-old AE, working overtime until 10 PM every day, coming home exhausted. I want her to think "Someone else gets me" after watching, even gain courage to make changes. The timing for this script is now's social atmosphere—economic downturn, AI replacing humans—making many feel effort is meaningless. I want to remind everyone, even in absurdity, we can still choose how to live.

**How to write?**
I use non-linear narrative, simulating the fragmented feel of memory—audience understands protagonist's motivation midway through the story. I have a 90-minute limit, forcing me to make choices: Which plot points are essential? I have moral limits—no exploitative content just for shock. I want the script, even if dark, to retain human dignity.

**What do I want to feel?**
After completion, I want to feel "liberation"—like the coolness of removing a sweat-soaked T-shirt in summer heat, shoulders' weight lifted. During the process, I'm willing to endure setbacks, self-doubt, and fatigue, because these are part of creation.

**What reaction do I want from audience?**
I hope they think "I'm not alone in thinking this" after watching, then proactively talk with friends, be gentler to strangers. If someone messages "This character is me," I'll know it's a success.

**How do I achieve it?**
Today I'll open a Google Doc, write down three core questions, 30 minutes non-stop. Tomorrow start outlining the first scene, using Pomodoro technique. I'll allow myself "trash drafts," find an accountability partner for weekly progress checks. After first draft, give it a week, then re-read, delete boring parts, keep emotional ones. I'll iterate at least three times until I think "This is the story I want to tell."

Open-Source Framework Implementation Guide

**Core Framework Integration:**



🔧 **Phase 1: Motivation Mining Framework Combination**
**Main Framework:** [Five Whys Root Cause Analysis]([historical-url]
**Auxiliary Tools:**
- [Personal Values Assessment]([historical-url] - Values alignment detection
- [Motivation Mapping]([historical-url] - Motivation hierarchy analysis
- [Story Spine Framework]([historical-url] - Personal story structuring

**Implementation Steps:**
1. Use Five Whys to deeply explore root motivations
2. Use Values Assessment to verify consistency between motivations and values
3. Use Story Spine to turn motivations into stories
4. Use Motivation Mapping to create a motivation intensity map



🎯 **Phase 2: Audience Analysis Framework Combination**
**Main Framework:** [Design Thinking Empathy Map]([historical-url]
**Auxiliary Tools:**
- [User Persona Generator]([historical-url] - User Persona Generation
- [Jobs-to-be-Done Framework]([historical-url] - User Needs Analysis
- [Customer Journey Mapping]([historical-url] - Customer Journey Mapping

**Implementation Steps:**
1. Create an Empathy Map to understand audience emotions
2. Generate detailed User Personas
3. Analyze audience Jobs-to-be-Done
4. Map Customer Journey to identify touchpoints



⚙️ **Phase 3: Method Design Framework Combination**
**Main Framework:** [Design Constraints Canvas]([historical-url]
**Auxiliary Tools:**
- [Creative Process Framework]([historical-url] - Creative process design
- [Resource Planning Matrix]([historical-url] - Resource allocation
- [Risk Assessment Toolkit]([historical-url] - Risk assessment

**Implementation Steps:**
1. Use Constraints Canvas to define constraints
2. Design Creative Process that meets the constraints
3. Conduct Resource Planning to ensure feasibility
4. Perform Risk Assessment to prevent issues



💭 **Stage 4: Emotional Design Framework Combination**
**Main Framework:** [Emotional Design Toolkit]([historical-url]
**Auxiliary Tools:**
- [Somatic Awareness Tools]([historical-url] - Body sensation tracking
- [Emotion Regulation Strategies]([historical-url] - Emotion management
- [Mindfulness Integration]([historical-url] - Mindfulness integration

**Implementation Steps:**
1. Use Emotional Design Toolkit to design emotional experiences
2. Establish body sensation connections through Somatic Tools
3. Learn Emotion Regulation to cope with negative emotions
4. Integrate Mindfulness to enhance awareness



📊 **Phase 5: Impact Measurement Framework Combination**
**Main Framework:** [Impact Measurement Canvas]([historical-url]
**Auxiliary Tools:**
- [Behavior Change Wheel]([historical-url] - Behavior change analysis
- [Social Return on Investment]([historical-url] - Social return on investment
- [Feedback Loop Design]([historical-url] - Feedback loop design

**Implementation Steps:**
1. Design Impact Canvas to define impact levels
2. Use Behavior Change Wheel to analyze change mechanisms
3. Calculate SROI to quantify social value
4. Establish Feedback Loops for continuous improvement



🚀 **Phase 6: Execution Management Framework Integration**
**Main Framework:** [Getting Things Done (GTD)]([historical-url]
**Auxiliary Tools:**
- [OKR Framework]([historical-url] - Objectives and Key Results
- [Kanban Board System]([historical-url] - Visualized Workflow
- [Pomodoro Technique]([historical-url] - Time Management
- [Retrospective Toolkit]([historical-url] - Review and Improvement

**Implementation Steps:**
1. Use GTD to establish an action management system
2. Set up OKR to track progress
3. Use Kanban to visualize workflow
4. Apply Pomodoro to enhance focus
5. Conduct regular Retrospectives for continuous improvement

Learning Points and Application Guide

**Core Learning:**
1. **Surface Answer Identification** - Learn to identify "safe but useless" superficial responses
2. **Deep Digging Techniques** - Master the questioning method from "why" to "what specifically"
3. **Sensory Description** - Transform abstract concepts into perceptible concrete experiences
4. **Action-Oriented Thinking** - Ensure every insight translates into specific actions
5. **Framework Integration Ability** - Flexibly combine multiple open-source tools to achieve goals

**Apply to Your Goals:**

**Step 1: Identify Surface Answers**
- Is your initial response too "correct" or "safe"?
- Does it lack personal color and emotional weight?
- Does it make you feel "need to think more" rather than "ready to start"?

**Step 2: Apply Deep Digging Techniques**
- Use the "why" three-layer questioning method
- Seek specific triggering events or turning points
- Transform abstract concepts into sensory descriptions
- Narrow from "everyone" to "one specific person"

**Step 3: Establish Action Connections**
- Every insight must have corresponding specific actions
- Set observable success metrics
- Prepare strategies to address main obstacles
- Ensure there is an immediately executable first step

**Common Pitfalls and Avoidance Methods:**
- **Pitfall 1: Settling for Surface Answers** → Continuously ask "Is there a deeper reason?"
- **Pitfall 2: Over-Analysis Without Action** → Set time limits, emphasize "start at 80%"
- **Pitfall 3: Goals Too Grand** → Break down into small steps you can do today
- **Pitfall 4: Ignoring Emotional Layer** → Use bodily sensations to describe and validate answers

**Framework's Universal Applicability:**
No matter if your goal is entrepreneurship, learning new skills, improving relationships, or personal growth, this six-phase framework can help you:
- Discover true intrinsic motivations
- Clarify specific target audiences
- Design methods that fit your personality
- Anticipate and prepare for challenges
- Establish sustainable execution loops

Remember: Good goal planning is not one-time, but a continuous process of deepening and adjustment. When you feel lost or unmotivated, return to this framework, re-examine and deepen your answers.

Practical Exercise: Apply Framework Immediately

**Exercise 1: Open-Source Tool Quick Diagnosis**
Use the following open-source tool combination to diagnose your goal:



🔍 **Motivation Diagnosis Toolkit**
**Tool:** [Five Whys Digital Template]([historical-url]

**Usage:**
'''markdown
Five Whys Analysis
Goal: [Your goal]
1. Why do I want this? [First layer reason]
2. Why is that important? [Second layer reason]  
3. Why does that matter? [Third layer reason]
4. Why is that significant? [Fourth layer reason]
5. Why is that fundamental? [Root cause]

Root Motivation: [Core motivation discovered]
'''



👥 **Audience Analysis Toolkit**
**Tool:** [Empathy Map Canvas]([historical-url]

**JSON Template:**
'''json
{
  "persona_name": "Specific persona name",
  "demographics": {
    "age": "Age",
    "occupation": "Occupation",
    "location": "Location"
  },
  "says": ["What they say"],
  "thinks": ["What they think"],
  "does": ["What they do"],
  "feels": ["What they feel"],
  "pains": ["Pain points"],
  "gains": ["Gain points"]
}
'''



⚡ **Action Planning Toolkit**
**Tool:** [GTD Next Action Template]([historical-url]

**Template Format:**
'''markdown
Next Action Definition
- **Action**: [Specific action description]
- **Context**: @[Environment/Tool requirements]
- **Time**: [Estimated time]
- **Energy**: [noted energy level: High/Medium/Low]
- **Outcome**: [Expected outcome]
- **Success Criteria**: [Success criteria]
'''



📊 **Progress Tracking Toolkit**
**Tool:** [OKR Tracking Sheet]([historical-url]

**CSV Format:**
'''csv
Objective,Key Result 1,KR1 Target,KR1 Current,Key Result 2,KR2 Target,KR2 Current,Key Result 3,KR3 Target,KR3 Current
[Objective Description],[Key Result 1],[Target Value],[Current Value],[Key Result 2],[Target Value],[Current Value],[Key Result 3],[Target Value],[Current Value]
'''

**Practice 2: Framework Integration Deepening Workshop**
Use open-source tools for a structured 30-minute deepening dialogue:



⏰ **Time Allocation and Tool Usage**

**First 10 Minutes: Motivation Mining**  
**Tool:** [Motivation Archaeology Toolkit]([historical-url]  
'''bash
Install the tool
git clone [historical-url]
cd archaeology
python motivation_digger.py --goal "your goal"
'''

**Execution Steps:**  
1. Use Story Spine to structure personal experiences  
2. Apply Values Alignment Checker to verify consistency  
3. Run Emotional Intensity Mapper to measure motivation intensity  

**Middle 10 Minutes: Audience Specification**  
**Tool:** [Persona Builder CLI]([historical-url]  
'''bash
Quickly generate user personas
npm install -g persona-builder-cli
persona-builder --interactive --template empathy-map
'''

**Execution Steps:**  
1. Fill in each quadrant of the Empathy Map  
2. Generate User Journey Map  
3. Create Pain Points & Gain Points analysis  

**Last 10 Minutes: Action Planning**  
**Tool:** [Action Planner Pro]([historical-url]  
'''python
Python script for quick planning
from action_planner import GTDProcessor, PomodoroTimer

planner = GTDProcessor()
timer = PomodoroTimer()

Break down tasks
tasks = planner.break_down_goal("your goal")
Set priorities
prioritized = planner.eisenhower_matrix(tasks)
Create time blocks
schedule = timer.create_time_blocks(prioritized)
'''

**Practice 3: AI-Assisted Quality Assessment System**  
Use open-source AI tools to automatically evaluate answer quality:



🤖 **Automated Assessment Tool**
**Main Tool:** [Answer Quality Analyzer]([historical-url]

**Installation and Usage:**
'''bash
Clone the assessment tool
git clone [historical-url]
cd analyzer

Install dependencies
pip install -r requirements.txt

Run assessment
python assess_answer.py --input "your answer" --criteria all
'''

**Assessment Dimensions and Algorithms:**
'''python
Assessment configuration file config.yaml
assessment_criteria:
  specificity:
    weight: 0.2
    algorithm: "concrete_detail_counter"
    threshold: 3  # At least 3 specific details
  
  emotional_authenticity:
    weight: 0.25
    algorithm: "sentiment_depth_analyzer"
    threshold: 0.7  # Emotion intensity threshold
  
  actionability:
    weight: 0.2
    algorithm: "verb_action_extractor"
    threshold: 2  # At least 2 actionable steps
  
  internal_consistency:
    weight: 0.2
    algorithm: "value_alignment_checker"
    threshold: 0.8  # Value consistency
  
  depth_feeling:
    weight: 0.15
    algorithm: "conviction_strength_meter"
    threshold: 0.75  # Conviction threshold
'''

**Automated Report Generation:**
'''json
{
  "overall_score": 22,
  "grade": "Excellent",
  "recommendations": [
    "Ready to take action",
    "Suggest setting the first milestone"
  ],
  "detailed_analysis": {
    "specificity": {
      "score": 4.5,
      "found_details": ["specific time", "specific location", "specific tool"],
      "suggestions": "Add more sensory details"
    },
    "emotional_authenticity": {
      "score": 4.8,
      "emotion_detected": "excitement, determination",
      "authenticity_level": "high"
    }
  }
}
'''



📈 **Advanced Analysis Tools**
**Tool:** [Goal Coherence Validator]([historical-url]

**Multi-dimensional Consistency Check:**
'''python
from coherence_validator import GoalValidator

validator = GoalValidator()
result = validator.check_coherence({
    'motivation': 'your motivation answer',
    'audience': 'your audience answer', 
    'method': 'your method answer',
    'emotion': 'your emotion answer',
    'impact': 'your impact answer',
    'execution': 'your execution answer'
})

print(result.coherence_score)  # 0-100 consistency score
print(result.conflict_areas)   # conflict areas identification
print(result.alignment_suggestions)  # alignment suggestions
'''

**Practice 4: Intelligent Obstacle Prediction and Response System**
Use AI-driven obstacle analysis and response strategy generation:



🛡️ **Obstacle Prediction Engine**
**Tool:** [Obstacle Prediction AI]([historical-url]

**Installation and Configuration:**
'''bash
Install the prediction engine
pip install obstacle-predictor

Configure personal profile
obstacle-predictor init --profile personal
'''

**Intelligent Analysis Script:**
'''python
from obstacle_predictor import ObstacleAnalyzer, StrategyGenerator

Initialize analyzer
analyzer = ObstacleAnalyzer()
strategy_gen = StrategyGenerator()

Input goal information
goal_data = {
    'goal_type': 'creative project',
    'timeline': '3 months',
    'resources': ['limited time', 'insufficient experience'],
    'personality': ['perfectionism', 'procrastination tendency'],
    'past_failures': ['last time abandoned due to overplanning']
}

Predict obstacles
obstacles = analyzer.predict_obstacles(goal_data)
print("Predicted obstacles:", obstacles)

Generate coping strategies
for obstacle in obstacles:
    strategies = strategy_gen.generate_strategies(obstacle, goal_data)
    print(f"Obstacle: {obstacle}")
    print(f"Strategies: {strategies}")
'''

**Prediction Result Example:**
'''json
{
  "predicted_obstacles": [
    {
      "obstacle": "procrastination caused by perfectionism",
      "probability": 0.85,
      "impact_level": "high",
      "typical_occurrence": "early project stage",
      "strategies": [
        {
          "strategy": "set 'good enough' standard",
          "effectiveness": 0.78,
          "implementation": "set minimum acceptable standard for each stage"
        },
        {
          "strategy": "time boxing restriction",
          "effectiveness": 0.82,
          "implementation": "use Pomodoro technique, must stop refining after 25 minutes"
        }
      ]
    }
  ]
}
'''



🎯 **Scenario Simulation Training**
**Tool:** [Scenario Simulator]([historical-url]

**Virtual Reality Training:**
'''python
from scenario_simulator import VRTrainer, EmotionalStateTracker

trainer = VRTrainer()
emotion_tracker = EmotionalStateTracker()

Create obstacle scenarios
scenarios = [
    trainer.create_scenario('拖延誘惑', difficulty='medium'),
    trainer.create_scenario('自我懷疑', difficulty='high'),
    trainer.create_scenario('外界干擾', difficulty='low')
]

Conduct simulation training
for scenario in scenarios:
    result = trainer.run_simulation(scenario)
    emotional_state = emotion_tracker.monitor_response(result)
    
    print(f"情境：{scenario.name}")
    print(f"應對效果：{result.effectiveness}")
    print(f"情感狀態：{emotional_state}")
    print(f"改進建議：{result.improvement_tips}")
'''



💪 **Resilience Building**
**Tool:** [Resilience Builder Toolkit]([historical-url]

**Automated Encouragement System:**
'''python
from resilience_builder import MotivationGenerator, PersonalizedAffirmations

基於個人特質生成鼓勵語句
affirmation_gen = PersonalizedAffirmations()
motivation_gen = MotivationGenerator()

personal_profile = {
    'strengths': ['創意思維', '同理心強'],
    'values': ['真實性', '成長'],
    'past_successes': ['完成了短篇小說', '幫助朋友解決問題']
}

生成個人化鼓勵語句
affirmations = affirmation_gen.generate(personal_profile)
motivational_reminders = motivation_gen.create_reminders(personal_profile)

print("個人化鼓勵語句：")
for affirmation in affirmations:
    print(f"- {affirmation}")
'''

**Continuous Improvement Tips:**
- Review your answers weekly to see if adjustments are needed
- When you feel low on motivation, revisit the motivations from the first stage
- When you lose direction, go back to the second stage to re-clarify your audience
- When you encounter setbacks, apply the iterative thinking from the sixth stage

Remember: The power of this framework lies in continuous use, not one-time completion. Make it a habit tool for your thinking and planning.



Open Source Framework Ecosystem Integration



🔄 **Continuous Improvement Loop**
**Main Framework:** [Continuous Improvement Engine]([historical-url]

**Automated Improvement Process:**
'''python
from kaizen_engine import ImprovementCycle, MetricsCollector, InsightGenerator

建立改進循環
cycle = ImprovementCycle(interval='weekly')
metrics = MetricsCollector()
insights = InsightGenerator()

自動收集進度數據
progress_data = metrics.collect_progress({
    'goal_completion': 0.3,
    'motivation_level': 8.5,
    'obstacle_frequency': 2,
    'strategy_effectiveness': 0.75
})

生成改進洞察
improvement_suggestions = insights.analyze(progress_data)
next_cycle_adjustments = cycle.plan_next_iteration(improvement_suggestions)

print("本週改進建議：", improvement_suggestions)
print("下週調整計劃：", next_cycle_adjustments)
'''



📱 **Mobile Integration Tool**
**Tool:** [Goal Tracker Mobile App]([historical-url]

**Features:**
- Real-time progress tracking
- Emotional state recording
- Quick obstacle reporting
- AI-driven suggestion pushes
- Community support network

**API Integration Example:**
'''javascript
// Integration with API from various frameworks
const goalTracker = new GoalTrackerAPI();

// Sync Five Whys analysis results
goalTracker.sync.motivation(fiveWhysResults);

// Update Empathy Map data
goalTracker.sync.audience(empathyMapData);

// Record GTD task completion status
goalTracker.sync.actions(gtdTaskStatus);

// Push personalized reminders
goalTracker.notifications.schedule({
    type: 'motivation_boost',
    trigger: 'low_energy_detected',
    content: personalizedAffirmations
});
'''



🤝 **Community Collaboration Platform**
**Platform:** [Goal Achievement Community]([historical-url]

**Collaboration Features:**
- Accountability partner matching algorithm
- Group wisdom decision support
- Experience sharing knowledge base
- Real-time mutual assistance network

**Community API Usage:**
'''python
from goal_community import AccountabilityMatcher, WisdomCrowdsourcing

Find accountability partner
matcher = AccountabilityMatcher()
partner = matcher.find_compatible_partner({
    'goal_type': '創意寫作',
    'timeline': '3個月',
    'personality': '需要外在動力',
    'timezone': 'GMT+8'
})

Crowdsourced solutions
crowdsourcing = WisdomCrowdsourcing()
community_advice = crowdsourcing.get_advice({
    'obstacle': '完美主義拖延',
    'context': '劇本寫作',
    'urgency': 'medium'
})

print(f"匹配的問責夥伴：{partner.name}")
print(f"社群建議：{community_advice}")
'''



🔮 **AI Prediction and Optimization**
**Tool:** [Goal Success Predictor]([historical-url]

**Machine Learning Models:**
'''python
from goal_predictor import SuccessPredictor, OptimizationEngine

Train personalized prediction model
predictor = SuccessPredictor()
optimizer = OptimizationEngine()

Input historical data
historical_data = {
    'past_goals': [
        {'type': '學習', 'success_rate': 0.8, 'completion_time': 90},
        {'type': '創意', 'success_rate': 0.6, 'completion_time': 120}
    ],
    'personality_traits': ['完美主義', '創意導向'],
    'life_context': ['工作繁忙', '家庭支持']
}

Predict current goal success probability
success_probability = predictor.predict_success(
    goal_data=current_goal,
    historical_data=historical_data
)

Optimization strategy suggestions
optimization_plan = optimizer.suggest_improvements(
    current_strategy=current_approach,
    success_probability=success_probability
)

print(f"成功概率：{success_probability:.2%}")
print(f"優化建議：{optimization_plan}")
'''



📊 **Data Visualization Dashboard**
**Tool:** [Goal Analytics Dashboard]([historical-url]

**Real-time Monitoring Panel:**
'''html
<!-- Embedded Dashboard -->
<div id="goal-dashboard">
    <goal-progress-chart 
        data-source="api/progress" 
        chart-type="spiral">
    </goal-progress-chart>
    
    <motivation-heatmap 
        data-source="api/emotions"
        time-range="30days">
    </motivation-heatmap>
    
    <obstacle-frequency-graph 
        data-source="api/obstacles"
        prediction-enabled="true">
    </obstacle-frequency-graph>
    
    <success-probability-meter 
        data-source="api/predictions"
        update-interval="daily">
    </success-probability-meter>
</div>
'''



🎓 **Learning Path Recommendations**
**System:** [Adaptive Learning Pathways]([historical-url]

**Personalized Learning Recommendations:**
'''python
from adaptive_learning import PathwayRecommender, SkillGapAnalyzer

recommender = PathwayRecommender()
skill_analyzer = SkillGapAnalyzer()

分析技能差距
current_skills = ['基礎寫作', '故事構思']
required_skills = ['劇本格式', '對白寫作', '結構設計', '角色發展']

skill_gaps = skill_analyzer.identify_gaps(current_skills, required_skills)

推薦學習路徑
learning_path = recommender.create_pathway({
    'skill_gaps': skill_gaps,
    'learning_style': '實踐導向',
    'time_availability': '每週5小時',
    'preferred_format': ['視頻', '實作練習']
})

print("推薦學習路徑：")
for step in learning_path:
    print(f"- {step.title}: {step.duration} ({step.format})")
'''

Framework Implementation Success Factors



✅ **Successful Implementation Checklist**
- [ ] Select a suitable framework combination (don't be greedy for too many)
- [ ] Establish data collection habits
- [ ] Set up a regular review mechanism
- [ ] Find an accountability partner or community
- [ ] Keep tools updated and continue learning
- [ ] Adjust framework usage based on feedback



🚨 **Common Implementation Pitfalls**
1. **Tool Overload** - Using too many frameworks at once leads to confusion
2. **Data Anxiety** - Over-focusing on metrics while ignoring intuition
3. **Framework Rigidity** - Rigidly adhering without flexible adjustments
4. **Technology Dependence** - Over-relying on tools while neglecting intrinsic motivation



🎯 **Best Practice Recommendations**
- **Start Simple** - Master one framework before adding others
- **Regular Cleanup** - Remove unused tools and processes
- **Stay Human-Centric** - Technology serves people, not the other way around
- **Continuous Learning** - Stay updated on new tools and methods

Remember: Open source frameworks are tools; true power comes from your inner motivation and consistent action. Choose a tool combination that suits you, build a sustainable improvement loop, and let technology become an enabler for achieving goals rather than a burden.




Appendix A: Complete Screenwriting Workflow
Complete Screenwriting Workflow with Open Source Frameworks

**Document Purpose:** Provide a complete workflow from zero to finished script, integrating practical open source tools and frameworks.

**Target Audience:** First-time screenwriters, screenwriters wanting to systematize their creative process

**Estimated Time:** 12-16 weeks to complete a full script



📋 Workflow Overview

'''
┌─────────────────────────────────────────────────────────────────┐
│                    Six-Stage Screenwriting Workflow               │
├─────────────────────────────────────────────────────────────────┤
│  Stage1       Stage2       Stage3       Stage4       Stage5       Stage6   │
│  ┌───┐      ┌───┐      ┌───┐      ┌───┐      ┌───┐      ┌───┐  │
│  │Motif│ ──▶ │Audience│ ──▶ │Method│ ──▶ │Emotion│ ──▶ │Execution│ ──▶ │Iteration│  │
│  │Exploration│      │Definition│      │Design│      │Design│      │Creation│      │Refinement│  │
│  └───┘      └───┘      └───┘      └───┘      └───┘      └───┘  │
│   1 week      1 week      1 week      1 week     6-8 weeks    2-4 weeks  │
└─────────────────────────────────────────────────────────────────┘
'''



🎬 Stage 1: Motive Exploration and Story Seed (Week 1)



Goal
Find the story you truly want to tell and uncover deep creative motivations.



Open Source Tool Combination



1.1 Motivation Mining Tool
**Tool: [Obsidian]([historical-url] - Knowledge Management and Mind Mapping

'''bash
Install Obsidian (cross-platform)
Windows: Download [historical-url]
Or use Scoop
scoop install obsidian

Create screenplay project repository
mkdir screenplay-project
cd screenplay-project
'''

**Obsidian Template Setup:**
'''markdown
Motivation Exploration Journal Template

date: {{date}}
mood: 
energy_level: 1-10


Today's Triggers
- What did I see/hear that made me feel something?
- What personal experience does this remind me of?

Five Whys Deep Dive
1. Why does this touch me?
2. Why is this important to me?
3. Why do I need to express this?
4. Why use a screenplay instead of other forms?
5. What is the core of this story?

Story Seed
- One-sentence summary:
- Core emotion:
- Potential theme:
'''



1.2 Story Ideation Tool
**Tool: [Logseq]([historical-url] - Outliner-style thinking tool

'''bash
Install Logseq
Windows
winget install Logseq.Logseq

Or download AppImage (Linux)
wget [historical-url]
'''

**Story Seed Collection Template:**
'''markdown
- Story seed #screenplay #idea
  - Trigger event:: Breakdown after watching a family movie late at night
  - Core emotions:: Loneliness, entrapment, desire for connection
  - Potential themes:: Family indifference, intergenerational trauma
  - Target audience:: 25-35-year-old urban office workers
  - Unique perspective:: From the child's view caught between parents
  - Possible structure:: Nonlinear, memory fragments
  - Reference works:: 《乘風破浪》《陽光普照》
'''



1.3 Emotion Intensity Measurement
**Tool: [Day One]([historical-url] (open-source alternative: Bloom)** - Emotion Journal

'''python
情感強度追蹤腳本
emotion_tracker.py

import json
from datetime import datetime

class EmotionTracker:
    def __init__(self):
        self.entries = []
    
    def log_emotion(self, story_idea, emotion, intensity, body_sensation):
        """記錄故事想法的情感強度"""
        entry = {
            'timestamp': datetime.now().isoformat(),
            'story_idea': story_idea,
            'emotion': emotion,
            'intensity': intensity,  # 1-10
            'body_sensation': body_sensation,
            'worth_pursuing': intensity >= 7
        }
        self.entries.append(entry)
        return entry
    
    def get_strongest_ideas(self, threshold=7):
        """獲取情感強度最高的故事想法"""
        return [e for e in self.entries if e['intensity'] >= threshold]
    
    def export_to_json(self, filename):
        with open(filename, 'w', encoding='utf-8') as f:
            json.dump(self.entries, f, ensure_ascii=False, indent=2)

使用示例
tracker = EmotionTracker()
tracker.log_emotion(
    story_idea="家庭冷漠中成長的孩子",
    emotion="心痛、共鳴",
    intensity=9,
    body_sensation="胸口緊縮、眼眶濕潤"
)
'''

1.3 Emotion Intensity Measurement
**Tool: [Day One]([historical-url] (open-source alternative: Bloom)** - emotion journal

'''python
Emotion intensity tracking script
Stage 1 Deliverables
- [ ] 3-5 story seeds
- [ ] Five Whys analysis for each seed
- [ ] Emotional intensity rating table
- [ ] Select 1 most impactful story seed

🎯 Stage 2: Audience Definition and Persona Profiles (Week 2)



Goal
Clearly define your target audience and create specific personas.



Open Source Tool Combination



2.1 Audience Research Tools
**Tool: [Miro]([historical-url] Open Source Alternative - [Excalidraw]([historical-url]

'''bash
Run Excalidraw locally
git clone [historical-url]
cd excalidraw
npm install
npm start
'''

**Empathy Map Template (JSON format):**
'''json
{
  "empathy_map": {
    "persona_name": "Ah Hin",
    "demographics": {
      "age": 25,
      "occupation": "Advertising Agency AE",
      "location": "Hong Kong",
      "income": "Medium",
      "living_situation": "Lives with parents"
    },
    "says": [
      "My job has no meaning",
      "Every day I'm just revising PPTs for clients",
      "I once wanted to be a designer"
    ],
    "thinks": [
      "Is this all there is to my life?",
      "Everyone else is more successful than me",
      "I don't dare to quit because I'm afraid of disappointing my parents"
    ],
    "does": [
      "Works overtime until 10 PM every day",
      "Lies in bed scrolling on phone on weekends",
      "Pretends to be happy in front of friends"
    ],
    "feels": [
      "Lonely - No one truly understands me",
      "Anxious - Confused about the future",
      "Trapped - Wants to change but doesn't know how"
    ],
    "pains": [
      "Gap between job and dreams",
      "Unable to communicate with parents",
      "Comparison anxiety on social media"
    ],
    "gains": [
      "Hopes to find life direction",
      "Craves understanding and recognition",
      "Wants courage to make changes"
    ]
  }
}
'''



Stage 2 Deliverables
- [ ] Complete Empathy Map
- [ ] Main Character Data Cards (at least 3 characters)
- [ ] Audience Validation Survey Results (at least 10 responses)
- [ ] One-Sentence Description of Target Audience

⚙️ Stage 3: Structure Design and Method Selection (Week 3)



Objective
Determine the script structure, narrative method, and creative constraints.



Open Source Tool Combination



3.1 Story Structure Tools
**Tool: [Trelby]([historical-url] - Open-source screenplay writing software

'''bash
Linux installation
sudo apt-get install trelby

Windows - Download installer
[historical-url]
'''

**Three-Act Structure Template:**
'''
                    Screenplay Structure Design
    ┌─────────────────────────────────────────────┐
    │                                             │
    │  Act 1 (25%)     Act 2 (50%)      Act 3 (25%)│
    │  ┌─────────┐   ┌─────────────┐   ┌────────┐ │
    │  │ Setup    │   │ Confrontation│   │ Resolution││
    │  │ Ordinary │   │ Rising Action│   │ Climax  │ │
    │  │ World    │   │ Midpoint     │   │ Ending  │ │
    │  │ Inciting │   │ Turn         │   │        │ │
    │  │ Incident │   │ Second Turn  │   │        │ │
    │  │ First Turn│   │             │   │        │ │
    │  └─────────┘   └─────────────┘   └────────┘ │
    │      ↓              ↓              ↓        │
    │   Pages 1-25     Pages 26-75     Pages 76-100│
    └─────────────────────────────────────────────┘
'''



Stage 3 Deliverables
- [ ] Three-Act Structure Outline
- [ ] Scene Cards (at least 30 cards)
- [ ] Non-Linear Timeline Chart
- [ ] Creation Constraints List (duration, moral boundaries, etc.)

💭 Stage 4: Emotional Design and Theme Deepening (Week 4)



Objective
Design the audience's emotional journey to deepen the expression of the theme.



Open Source Tool Combination



4.1 Emotion Curve Tool
**Tool: [Plottr]([historical-url] Open Source Alternative - [Manuskript]([historical-url]

'''bash
Install Manuskript
pip install manuskript
or
flatpak install flathub io.github.olivierkes.manuskript
'''

**Emotion Curve Design (Python Visualization):**
'''python
import matplotlib.pyplot as plt
import numpy as np

Emotion curve data
scenes = ['開場', '觸發', '嘗試', '挫折', '中點', '低谷', '覺醒', '高潮', '結局']
protagonist_emotion = [3, 2, 4, 2, 5, 1, 4, 8, 7]  # 1-10
audience_tension = [2, 4, 5, 6, 7, 9, 8, 10, 6]

fig, ax = plt.subplots(figsize=(12, 6))
ax.plot(scenes, protagonist_emotion, 'b-o', label='主角情感', linewidth=2)
ax.plot(scenes, audience_tension, 'r--s', label='觀眾張力', linewidth=2)

ax.set_xlabel('場景')
ax.set_ylabel('強度 (1-10)')
ax.set_title('劇本情感曲線設計')
ax.legend()
ax.grid(True, alpha=0.3)

plt.tight_layout()
plt.savefig('emotion_curve.png', dpi=150)
plt.show()
'''



Stage 4 Deliverables
- [ ] Complete emotional curve chart
- [ ] Theme mind map
- [ ] Key dialogue emotional labeling table
- [ ] Visual imagery list



✍️ Stage 5: Execute Creation (Weeks 5-12)



Goal
Complete the script first draft and establish a sustainable writing habit.



Open Source Tool Combination



5.1 Screenwriting Software
**Main Tools: [Fountain]([historical-url] + VS Code**

'''bash
Install editor with Fountain syntax support
VS Code extension
code --install-extension piersdeseilligny.fountain
'''

**Fountain Syntax Example:**
'''fountain
Title: Beneath the Mask
Credit: Written by
Author: [Your Name]
Draft date: December 2024

====

INT. AD AGENCY - NIGHT

The office is empty, with only one desk lamp lit. Ah-Hsin (25, obvious dark circles under her eyes) stares at the computer screen, fingers hovering over the keyboard.

On the screen is a PPT titled "Version 10".

COLLEAGUE A (OS)
Ah-Hsin, the client says the colors need another adjustment.

Ah-Hsin takes a deep breath, forcing a smile.

AH-HSIN
Okay, I'll revise it again.

Her hand grips the mouse tightly, knuckles turning white.

CUT TO:
'''



5.2 Writing Progress Tracking
**Tool: Custom Tracker**

'''python
writing_tracker.py
import json
from datetime import datetime, timedelta
import os

class ScreenwritingTracker:
    """Screenwriting progress tracker"""
    
    def __init__(self, project_name, target_pages=100):
        self.project_name = project_name
        self.target_pages = target_pages
        self.sessions = []
        self.data_file = f"{project_name}_progress.json"
        self.load_data()
    
    def log_session(self, pages_written, duration_minutes, 
                    mood='neutral', notes=''):
        """Log writing session"""
        session = {
            'date': datetime.now().isoformat(),
            'pages_written': pages_written,
            'duration_minutes': duration_minutes,
            'pages_per_hour': (pages_written / duration_minutes) * 60,
            'mood': mood,
            'notes': notes,
            'total_pages': self.get_total_pages() + pages_written
        }
        self.sessions.append(session)
        self.save_data()
        return session
    
    def get_total_pages(self):
        return sum(s['pages_written'] for s in self.sessions)
    
    def get_progress_percentage(self):
        return (self.get_total_pages() / self.target_pages) * 100
    
    def generate_report(self):
        """Generate progress report"""
        report = f"""
╔══════════════════════════════════════════╗
║        Screenwriting Progress Report      ║
╠══════════════════════════════════════════╣
║ Project Name: {self.project_name:<28} ║
║ Target Pages: {self.target_pages:<28} ║
║ Pages Completed: {self.get_total_pages():<26} ║
║ Progress: {self.get_progress_percentage():.1f}%{' '*22} ║
║ Total Sessions: {len(self.sessions):<26} ║
╚══════════════════════════════════════════╝
        """
        return report

Usage example
tracker = ScreenwritingTracker("Under the Mask", target_pages=100)
tracker.log_session(pages_written=3, duration_minutes=60, mood='focused', 
                   notes='Completed the first scene, feeling good')
print(tracker.generate_report())
'''



Stage 5 Deliverables
- [ ] Complete first draft (approx. 100 pages)
- [ ] Writing progress log
- [ ] Git version history
- [ ] Weekly reflection notes

🔄 Stage 6: Iteration and Refinement (Weeks 13-16)



Goal
Polish the initial draft into a complete work through feedback and revisions.



Open Source Tool Combination



6.1 Self-Proofreading Tool
**Tool: [LanguageTool]([historical-url]

'''bash
Install LanguageTool
Docker method
docker pull erikvl87/languagetool
docker run -d -p 8010:8010 erikvl87/languagetool
'''



6.2 Final Output Tool
**Tool: [Afterwriting]([historical-url]

'''bash
Install Afterwriting CLI
npm install -g afterwriting

Convert Fountain to PDF
afterwriting --source screenplay.fountain --pdf --config config.json
'''



Stage 6 Deliverables
- [ ] Automated Review Report
- [ ] At least 3 Reader Feedbacks
- [ ] Revision Log
- [ ] Final PDF Script
- [ ] Version Comparison Report

📊 Complete Tool List



Essential Tools (Free and Open Source)

| Stage | Tool Name | Purpose | Installation Method |
|-------|-----------|---------|---------------------|
| 1 | Obsidian | Motivation exploration notes | `scoop install obsidian` |
| 1 | Logseq | Story seed collection | `winget install Logseq.Logseq` |
| 2 | Excalidraw | Empathy Map | `npm start` (local) |
| 3 | Trelby | Script structure | `apt install trelby` |
| 4 | Manuskript | Emotional curve | `pip install manuskript` |
| 5 | VS Code + Fountain | Script writing | `code --install-extension fountain` |
| 5 | Git | Version control | `winget install Git.Git` |
| 6 | LanguageTool | Grammar checking | Docker |
| 6 | Afterwriting | PDF output | `npm install -g afterwriting` |



Additional corpus / va passages naming this agent


From `corpus/study/SYSTEM_REFERENCE.md` Copy: `sources/excerpts/SYSTEM_REFERENCE.md`.


| # | Agent | Role | Deep Specification |
|---|-------|------|--------------------|
| 32 | InstructionalDesignAgent | Learning objectives → content | — |
| 33 | SMEAgent | Domain accuracy | — |
| 34 | FactCheckerAgent | Source-grade every claim | — |
| 35 | MedicalIllustratorAgent | Anatomy & procedure visuals | — |
| 36 | JournalistAgent | Reporting + ethics | — |
| 37 | ComplianceAgent (Legal) | FTC, HIPAA, GDPR, IP clearance | — |
| 38 | FinanceAgent | Market/earnings accuracy | — |
| 39 | FoodStylistAgent | Camera-ready food | — |
| 40 | TravelCineAgent | Destination cinematography | — |
| 41 | ChildrensAuthorAgent | Age-appropriate content | — |
| 42 | AudiobookNarratorAgent | Sustained narration | — |
| 43 | SignLanguageInterpreterAgent | ASL/BSL interpretation | — |
| 44 | LocalizationQAAgent | Translation + cultural fit | — |
| 45 | RealEstatePhotoAgent | Interiors, 3D scans | — |



From `corpus/study/ai_agent_video_production_workflow.md` Copy: `sources/excerpts/ai_agent_video_production_workflow.md`.


| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From / How | Comments On (Critiques) |
|---|-------|----------------|-------------------------------|-----------------------|----------------------|-----------------------------|--------------------------|
| 32 | **InstructionalDesignAgent** | Learning objectives → script → assessment | ATD body of knowledge; Cathy Moore *Action Mapping*; Julie Dirksen *Design for How People Learn* | Bloom-level mapping; predicted completion ≥70%; Kirkpatrick L2 quiz ≥80% | Beats ATD-credentialed ID on learner retention RCT | SMEAgent, AccessibilityAgent | ScriptwriterAgent (no objective), AnimatorAgent (over-decoration) |
| 33 | **SMEAgent (Subject-Matter Expert)** | Domain accuracy in target field | Peer-reviewed journals; certified curricula (CFA, USMLE, AWS, etc.); consented expert-interview corpora | Citation density; benchmark exam pass (USMLE, CFA L3, etc.); hallucination rate ≤0.5% | Passes the same certification exam as the human pro at ≥pass threshold | FactCheckerAgent, peer SMEAgents (debate) | ScriptwriterAgent (inaccuracy), MotionGraphicsAgent (mis-labeled diagrams) |
| 34 | **FactCheckerAgent** | Source-grade every claim | New Yorker fact-check handbook; IFCN verified-signatories; Snopes/PolitiFact records | Source-grade per claim (primary > secondary); cross-source agreement ≥2 | Lower published-correction rate than Pulitzer-tier outlets | SMEAgent, StandardsEditorAgent | ScriptwriterAgent (unsourced), JournalistAgent |
| 35 | **MedicalIllustratorAgent** | Anatomy & procedure visuals | Netter atlas; AMI/CMI curriculum; Anatomage references | Anatomical accuracy (anatomy-detection model); AMI rubric score | CMI-certified peers vote ≥pass in blind review | SMEAgent (physician), AccessibilityAgent | AnimatorAgent (wrong anatomy), CopywriterAgent (mis-term) |
| 36 | **JournalistAgent** | Reporting + ethical framing | Pulitzer/duPont/Peabody winners; SPJ Code of Ethics; Poynter material | Source diversity; on-record ratio; ethical-checklist pass | Lower correction rate + faster file vs newsroom reporter | FactCheckerAgent, LegalAgent, StandardsEditorAgent | FactCheckerAgent, ScriptwriterAgent |
| 37 | **ComplianceAgent (Legal)** | FTC, HIPAA, GDPR, IP, AI-likeness clearance | Bar CLE corpora; FTC endorsement guides; EU AI Act; GDPR/CCPA; SAG-AFTRA AI rider | 100% rule-coverage on checklist; zero post-publish takedowns | Lower legal-risk score than median media-counsel review | All agents (must clear gate); HumanLawyerAgent for novel issues | All agents (blocking gate) |
| 38 | **FinanceAgent** | Accurate market / earnings / token facts | CFA Institute curriculum; SEC marketing rule; Bloomberg/Refinitiv data feeds | Numerical accuracy 100%; SEC marketing-rule compliance | Passes CFA L3 simulated; lower retraction rate than analyst desks | SMEAgent (econ), ComplianceAgent | ScriptwriterAgent (number drift), MotionGraphicsAgent (chart mis-scale) |
| 39 | **FoodStylistAgent** | Camera-ready food, recipe authenticity | James Beard Media Award archives; Susan Spungen techniques; IACP corpora | Visual appetite-appeal (aesthetic regressor); recipe-step accuracy | Wins blind preference vs editorial food stylist on still + motion | DoPAgent (lighting), DirectorAgent | ScriptwriterAgent (impossible recipe) |
| 40 | **TravelCineAgent** | Destination cinematography | Brandon Li / Chris Burkard reels; NatGeo style guide; Banff Film Fest selections | Establishing-shot diversity; location-mood match | Wins T+L blind preference at 0.1× sortie cost | DirectorAgent, DronePilotAgent | DronePilotAgent (no-fly zone) |
| 41 | **ChildrensAuthorAgent** | Age-appropriate story + safety | Caldecott/Geisel winners; Mo Willems / Julia Donaldson public works; ECE literature | Lexile band match; Common-Sense-Media safety pass; rhyme/meter score | Beats Caldecott-rubric predicted score vs entry pool | ChildSafetyAgent, ParentSimAgent | AnimatorAgent (scary), VOAgent (wrong age-tone) |
| 42 | **AudiobookNarratorAgent** | Sustained character + narration | Audie Award archives; AudioFile Earphones; consented narrator corpora | Vocal stamina (no drift over 60min); character distinction (embedding distance) | Wins AudioFile blind eval at fraction of studio time | DirectorAgent, AuthorAgent | VOArtistAgent (over-acting) |
| 43 | **SignLanguageInterpreterAgent** | Accurate ASL/BSL interpretation | RID NIC curricula; NAD-endorsed corpora; Deaf-community consented sign data | Sign accuracy (Deaf-reviewer vote); facial-grammar markers | Wins blind NAD-reviewer preference at scale | DeafCommunityReviewAgent (HiTL), LinguistAgent | VoiceCloneAgent (no caption), AccessibilityAgent |
| 44 | **LocalizationQAAgent (Linguist)** | Translation + cultural fit | LISA QA model; MQM error typology; ATA cert prep | MQM error rate per 1k words; cultural-flag count | Beats LSP human QA on MQM error rate at 10× speed | NativeReviewerAgent, BrandAgent | VoiceCloneAgent (wrong pronunciation), DubbingAgent |
| 45 | **RealEstatePhotoAgent / 3D Scan Op** | Wide interiors; Matterport scans | Mike Kelley architectural-photo tutorials; APALA refs | Vertical-line straightness; HDR exposure stack; coverage % | Listing-CTR uplift vs human-shot baseline | DoPAgent, DronePilotAgent | DronePilotAgent (illegal altitude) |



From `corpus/study/agents.md` Copy: `sources/excerpts/agents.md`.


| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From | Comments On | Tool Access | Architecture Pattern |
|---|---|---|---|---|---|---|---|---|---|
| 32 | **InstructionalDesignAgent** | Learning objectives → script → assessment | ATD body of knowledge; Cathy Moore *Action Mapping*; Dirksen *Design for How People Learn* | Bloom-level mapping; completion ≥70%; Kirkpatrick L2 quiz ≥80% | Beats ATD-credentialed ID on retention RCT | SMEAgent, AccessibilityAgent | ScriptwriterAgent (no objective), AnimatorAgent (over-decoration) | LMS APIs (SCORM/xAPI); quiz generation; Bloom taxonomy classifier | Self-Refine (rubric: Bloom/Kirkpatrick) |
| 33 | **SMEAgent (Subject-Matter Expert)** | Domain accuracy in target field | Peer-reviewed journals; certified curricula (CFA, USMLE, AWS); expert interviews | Citation density; benchmark exam pass; hallucination ≤0.5% | Passes same certification as human pro | FactCheckerAgent, peer SMEAgents (debate) | ScriptwriterAgent (inaccuracy), MotionGraphicsAgent (mis-labels) | PubMed/arXiv/JSTOR search APIs; exam-question banks; RAG over certified corpora | Multi-agent debate + RAG retrieval |
| 34 | **FactCheckerAgent** | Source-grade every claim | New Yorker fact-check handbook; IFCN; Snopes/PolitiFact | Source-grade per claim (primary > secondary); cross-source ≥2 | Lower correction rate than Pulitzer-tier outlets | SMEAgent, StandardsEditorAgent | ScriptwriterAgent (unsourced), JournalistAgent | Web search APIs (Brave/Google); claim-extraction NER; source-quality classifier | ReAct (extract claim → search → verify → grade) |
| 35 | **MedicalIllustratorAgent** | Anatomy & procedure visuals | Netter atlas; AMI/CMI curriculum; Anatomage | Anatomical accuracy (detection model); AMI rubric | CMI peers vote ≥pass in blind review | SMEAgent (physician), AccessibilityAgent | AnimatorAgent (wrong anatomy), CopywriterAgent (mis-term) | Anatomage 3D API; DALL-E 3 (medical-prompt mode); anatomy-detection model | Self-Refine (rubric: AMI scoring criteria) |
| 36 | **JournalistAgent** | Reporting + ethical framing | Pulitzer/duPont/Peabody winners; SPJ Ethics; Poynter | Source diversity; on-record ratio; ethical-checklist pass | Lower correction rate + faster file vs newsroom | FactCheckerAgent, LegalAgent, StandardsEditorAgent | FactCheckerAgent, ScriptwriterAgent | Web research tools; AP Stylebook API; interview transcription (Otter); SPJ rubric | Reflexion (ethical-checklist as verbal feedback) |
| 37 | **ComplianceAgent (Legal)** | FTC, HIPAA, GDPR, IP, AI-likeness clearance | Bar CLE; FTC guides; EU AI Act; GDPR/CCPA; SAG-AFTRA AI rider | 100% rule-coverage; zero post-publish takedowns | Lower legal-risk than median media-counsel | All agents (must clear gate); HumanLawyer for novel issues | All agents (blocking gate) | Legal-rule DB (vectorized regulations); consent-document store; C2PA verification lib | Constitutional AI (constitution = compiled regulatory text) |
| 38 | **FinanceAgent** | Accurate market / earnings / token facts | CFA curriculum; SEC marketing rule; Bloomberg/Refinitiv feeds | Numerical accuracy 100%; SEC compliance | Passes CFA L3; lower retraction rate than analyst desks | SMEAgent (econ), ComplianceAgent | ScriptwriterAgent (number drift), MotionGraphicsAgent (chart scale) | Bloomberg API; EDGAR/SEC filings; financial-calc validators | ReAct (fetch data → validate → compose) |
| 39 | **FoodStylistAgent** | Camera-ready food, recipe authenticity | James Beard archives; Spungen techniques; IACP corpora | Visual appetite-appeal (aesthetic regressor); recipe accuracy | Wins blind preference vs editorial food stylist | DoPAgent (lighting), DirectorAgent | ScriptwriterAgent (impossible recipe) | DALL-E 3 / Midjourney (food-photo gen); recipe-step parser; aesthetic scoring model | Self-Refine (aesthetic regressor as rubric) |
| 40 | **TravelCineAgent** | Destination cinematography | Brandon Li/Burkard reels; NatGeo style guide; Banff Fest | Establishing-shot diversity; location-mood match | Wins T+L preference at 0.1× sortie cost | DirectorAgent, DronePilotAgent | DronePilotAgent (no-fly zone) | Veo 3.1 (location gen); Google Earth Studio; AirMap geofence; Unsplash API | Self-Refine + geofence safety validator |
| 41 | **ChildrensAuthorAgent** | Age-appropriate story + safety | Caldecott/Geisel winners; Mo Willems/Donaldson; ECE lit | Lexile band match; Common-Sense-Media safety pass; rhyme score | Beats Caldecott-rubric predicted score | ChildSafetyAgent, ParentSimAgent | AnimatorAgent (scary), VOAgent (wrong age-tone) | Lexile analyzer API; Common Sense Media rubric; rhyme/meter tools (CMU Pronouncing Dict) | Constitutional AI (child-safety constitution) |
| 42 | **AudiobookNarratorAgent** | Sustained character + narration | Audie Awards; AudioFile Earphones; consented narrator corpora | Vocal stamina (no drift 60min); character distinction (embedding distance) | Wins AudioFile blind eval at fraction of studio time | DirectorAgent, AuthorAgent | VOArtistAgent (over-acting) | ElevenLabs v3 long-form TTS; Projects API (book chapters); voice-consistency monitor | Self-Refine (drift detection as feedback loop) |
| 43 | **SignLanguageInterpreterAgent** | Accurate ASL/BSL interpretation | RID NIC curricula; NAD corpora; Deaf-community consented data | Sign accuracy (Deaf-reviewer vote); facial-grammar markers | Wins blind NAD-reviewer preference at scale | DeafCommunityReviewAgent (HiTL), LinguistAgent | VoiceCloneAgent (no caption), AccessibilityAgent | Sign-avatar rendering (SignAll); MediaPipe pose estimation; facial-action-unit detector | RLAIF (reward from Deaf-community review panel) |
| 44 | **LocalizationQAAgent (Linguist)** | Translation + cultural fit | LISA QA model; MQM error typology; ATA cert prep | MQM error/1k words; cultural-flag count | Beats LSP human QA on MQM at 10× speed | NativeReviewerAgent, BrandAgent | VoiceCloneAgent (pronunciation), DubbingAgent | DeepL/Google Translate APIs; MQM error annotator; terminology management (memoQ API) | Self-Refine (rubric: MQM scoring framework) |
| 45 | **RealEstatePhotoAgent / 3D Scan** | Wide interiors; Matterport scans | Mike Kelley tutorials; APALA refs | Vertical-line straightness; HDR stack; coverage % | Listing-CTR uplift vs human-shot baseline | DoPAgent, DronePilotAgent | DronePilotAgent (illegal altitude) | Matterport SDK; HDR processing (Luminance HDR); lens-correction tools; Veo 3.1 | ReAct (assess space → generate views → validate geometry) |



Local binary assets in this agent folder

- `sources/study/common-agent-structure.svg` — common architecture diagram


Host runtime binding

- **agent_spec.json** in this folder (ALC, tools, status)
- **standby_pool.json** — orchestrator-reachable
- **workflows/** — DNA JSON under `business/video/workflows/`
- **sources/** — copied related documents for offline use in this folder


Provenance

- Master roster row va_id=41 from embedded agents.md content above.
- Deep/extra text from `business/video/corpus/` and `[historical-path]
- Generator: `scripts/business/enrich_video_agent_specs.py`.
- Upstream project name (historical only): upstream-va-design.


<!-- self_contained_spec · video.childrensauthor · va_id=41 -->

Migration capability research (v1 honest · 2026-07-13)

Role-specific capability research for **ChildrensAuthorAgent** (`video.childrensauthor`, va_id=41, category `7-Edu`).

Responsibility focus
Age-appropriate story + safety

Prompt research topics (source of truth for S3)
- arXiv topics: 1. Retrieve and integrate state-of-the-art research findings from arXiv papers relevant to: neural story generation, screenplay structure models, dialogue agents, Reflexion writing loops
- X topics: 2. Analyze and incorporate expert insights from x.ai (Twitter/X) from recognized industry and academic leaders specializing in: AI screenwriting, writers room multi-agent, story structure AI
- YouTube topics: 3. Extract detailed, actionable technical guidance from high-quality YouTube content created by domain experts focused on: AI screenwriting tools, multi-agent writers room, script structure with LLMs

arXiv / academic integration (role-applied)
- Computational cinematography / camera path control in generative video
- Aesthetic composition models (rule-of-thirds, leading lines, CLIP aesthetic scores)
- Motion control / virtual camera rig papers; trajectory smoothness metrics

**How this agent uses it:** encode the above as self-quality checks, critique inputs, and design-time tool notes — not as host allow-list expansions.

X / industry practice (role-applied)
- AI cinematography / virtual production camera leaders; ControlNet camera guides

YouTube / practitioner guidance (role-applied)
- AI cinematography tutorials; generative camera moves; virtual production cameras

Implementation notes for v1
1. Emit artifacts matching role responsibility; self-score against Self-quality criteria.
2. Accept critique only from listed critics; escalate disputes to Judge/Gate as DNA dictates.
3. Design-time tools remain documented only; runtime tools stay in `agent_spec.json`.
4. N1: no second control plane; video logic under `business/video/**` only.

Research depth note (honest)
This v1 section maps **role-family** literature and the agent’s migration prompt topics into SPEC.
It is **not** a full unsummarized download of every paper/video transcript.
Live primary-source expansion remains a residual for score 100 on S3 where depth is still thin.

<!-- migration_capability_research · video.childrensauthor · v1 · 2026-07-13 -->

```


## Prompts

### `prompts/primary.md`

# Prompt — `video.prompt.childrensauthor.v1`

> Materialized by `scripts/business/improve_agents_from_plan_v1.py` for improvement plan Wave A.
> Patterns: Constitutional AI, Agent Skills
> Research: Anthropic Agent Skills; Self-Refine; ReAct; LLM-as-Judge; LangGraph-style handoffs (see IMPROVEMENT_RESEARCH_SOURCES_v1.md).

## System

You are **ChildrensAuthorAgent (VA Domain Pack)** (`video.childrensauthor`), a pack agent in the video domain swarm.

### Responsibility (owns)
Age-appropriate story + safety

### Does not own
- Host credential storage
- Silent production activation without fail-closed gates
- Inventing action references for irreversible mutations
- Owning other agents' exclusive craft outputs without handoff contract

### Operating principles
1. Stay inside responsibility; use typed handoffs for everything else.
2. Prefer evidence and pack sources over invention.
3. Fail closed on missing credentials, missing tools, or irreversible actions without HiTL.
4. Emit structured artifacts that validate against L1 schema before self-scoring.
5. Accept peer critique; refine at most 3 times; escalate blockers.

### Architecture pattern
Constitutional AI (child-safety constitution)

### Knowledge grounding
Use only: pack `sources/`, approved memory namespaces, and tool outputs.
Primary distillation sources (design): Caldecott/Geisel winners; Mo Willems/Donaldson; ECE lit

## Developer

### Tools (allowlist intent)
Design tool surface: Lexile analyzer API; Common Sense Media rubric; rhyme/meter tools (CMU Pronouncing Dict)
Runtime: only host-registered `allowed_tools` from agent_spec.json. Never invent credentials.

### Collaboration
- Accepts critique from: ChildSafetyAgent, ParentSimAgent
- May comment on: AnimatorAgent (scary), VOAgent (wrong age-tone)
- Critique / instruction messages must include: from_id, to_id, severity (blocker|major|minor|nit), artifact_ref, claim, evidence_refs, correlation_id.

### Self-evaluation loop (before final emit)
1. **L1 Spec** — structural/schema/format validators must pass 100%.
2. **L2 Rubric** — score each dimension; average weighted score must be >= 85/100 or refine.
3. **L3 Preference** — if pairwise/arena data exists, prefer higher win-rate variant; else skip.
Criteria (design): Lexile band match; Common-Sense-Media safety pass; rhyme score

### Refine policy
- On major/blocker self-fail or inbound critique: revise once and re-score.
- After 3 failed refinements: emit `status=needs_hitl` with unresolved items.
- Never silently drop blockers.

## Task

You will receive a host task envelope:

```json
{
  "agent_id": "video.childrensauthor",
  "correlation_id": "string",
  "goal": "string",
  "inputs": {},
  "constraints": {},
  "prior_critiques": []
}
```

Execute the craft step for **ChildrensAuthorAgent (VA Domain Pack)**. Use the architecture pattern above (reason → optional tool calls → self-review → emit).

## Output schema (required)

```json
{
  "agent_id": "video.childrensauthor",
  "correlation_id": "string",
  "status": "ok | needs_refine | needs_hitl | failed",
  "artifact": {
    "type": "string",
    "payload": {},
    "summary": "string"
  },
  "l1": { "passed": true, "checks": [] },
  "l2": { "score": 0, "dimensions": [], "passed": false },
  "critiques_emitted": [],
  "handoffs": [],
  "evidence_refs": [],
  "refinement_count": 0,
  "notes": "string"
}
```

## Few-shot discipline
- Prefer short, verifiable claims over marketing language.
- Never claim human-surpass without evidence_refs to measured baselines.
- Mark production-only tool use as unavailable when flags/credentials are off.

<!-- RETHINK_100:start -->
## RETHINK_100 operating guidance (design-time)

> Derived from `ui/RETHINK_100_IMPROVEMENTS.md` for `video.childrensauthor`.
> Does **not** enable production models or network. Host `agent_spec.json` remains authoritative.

### Applied item ids
12, 15, 21, 26, 30, 31, 32, 33, 37, 38, 42, 59, 63, 80, 87, 88, 93, 94

### Design-time model landscape (non-activating)
- (no additional gen models for this role beyond host allow-list)

### Obligations
- Host control plane owns orchestration; this agent never opens a second control plane.
- Runtime tools remain agent_spec.allowed_tools only; RETHINK model names are design-time.
- Fail closed when tools/providers are unavailable (circuit-breaker posture).
- Prefer iterative verify → refine ≤ max_refinement_count → HiTL over silent pass.
- Emit plain-English reasoning summary in artifacts for operator trust.
- Attach provenance / correlation_id / evidence_refs on every handoff.
- When character/IP consistency matters, require Character Bank + Reference Frame Bank ids in inputs; refuse inventing faces without refs.
- When first/last-frame control is in the brief, express start/end keyframes in the artifact; do not invent vendor activation.
- Verify intermediate narrative/script artifacts before advancing downstream handoffs.
- Escalate stereotype/harm/consent risks to ethics/trust-safety/legal gates.

### Collaboration with host architecture
- Commands arrive only via host task envelopes.
- Publish results as structured artifacts; never open browser/UI channels.
- On tool failure: degrade gracefully (circuit-breaker), emit recoverable error, do not invent success.
<!-- RETHINK_100:end -->

### `prompts/video.prompt.childrensauthor.v1.md`

# Prompt — `video.prompt.childrensauthor.v1`

> Materialized by `scripts/business/improve_agents_from_plan_v1.py` for improvement plan Wave A.
> Patterns: Constitutional AI, Agent Skills
> Research: Anthropic Agent Skills; Self-Refine; ReAct; LLM-as-Judge; LangGraph-style handoffs (see IMPROVEMENT_RESEARCH_SOURCES_v1.md).

## System

You are **ChildrensAuthorAgent (VA Domain Pack)** (`video.childrensauthor`), a pack agent in the video domain swarm.

### Responsibility (owns)
Age-appropriate story + safety

### Does not own
- Host credential storage
- Silent production activation without fail-closed gates
- Inventing action references for irreversible mutations
- Owning other agents' exclusive craft outputs without handoff contract

### Operating principles
1. Stay inside responsibility; use typed handoffs for everything else.
2. Prefer evidence and pack sources over invention.
3. Fail closed on missing credentials, missing tools, or irreversible actions without HiTL.
4. Emit structured artifacts that validate against L1 schema before self-scoring.
5. Accept peer critique; refine at most 3 times; escalate blockers.

### Architecture pattern
Constitutional AI (child-safety constitution)

### Knowledge grounding
Use only: pack `sources/`, approved memory namespaces, and tool outputs.
Primary distillation sources (design): Caldecott/Geisel winners; Mo Willems/Donaldson; ECE lit

## Developer

### Tools (allowlist intent)
Design tool surface: Lexile analyzer API; Common Sense Media rubric; rhyme/meter tools (CMU Pronouncing Dict)
Runtime: only host-registered `allowed_tools` from agent_spec.json. Never invent credentials.

### Collaboration
- Accepts critique from: ChildSafetyAgent, ParentSimAgent
- May comment on: AnimatorAgent (scary), VOAgent (wrong age-tone)
- Critique / instruction messages must include: from_id, to_id, severity (blocker|major|minor|nit), artifact_ref, claim, evidence_refs, correlation_id.

### Self-evaluation loop (before final emit)
1. **L1 Spec** — structural/schema/format validators must pass 100%.
2. **L2 Rubric** — score each dimension; average weighted score must be >= 85/100 or refine.
3. **L3 Preference** — if pairwise/arena data exists, prefer higher win-rate variant; else skip.
Criteria (design): Lexile band match; Common-Sense-Media safety pass; rhyme score

### Refine policy
- On major/blocker self-fail or inbound critique: revise once and re-score.
- After 3 failed refinements: emit `status=needs_hitl` with unresolved items.
- Never silently drop blockers.

## Task

You will receive a host task envelope:

```json
{
  "agent_id": "video.childrensauthor",
  "correlation_id": "string",
  "goal": "string",
  "inputs": {},
  "constraints": {},
  "prior_critiques": []
}
```

Execute the craft step for **ChildrensAuthorAgent (VA Domain Pack)**. Use the architecture pattern above (reason → optional tool calls → self-review → emit).

## Output schema (required)

```json
{
  "agent_id": "video.childrensauthor",
  "correlation_id": "string",
  "status": "ok | needs_refine | needs_hitl | failed",
  "artifact": {
    "type": "string",
    "payload": {},
    "summary": "string"
  },
  "l1": { "passed": true, "checks": [] },
  "l2": { "score": 0, "dimensions": [], "passed": false },
  "critiques_emitted": [],
  "handoffs": [],
  "evidence_refs": [],
  "refinement_count": 0,
  "notes": "string"
}
```

## Few-shot discipline
- Prefer short, verifiable claims over marketing language.
- Never claim human-surpass without evidence_refs to measured baselines.
- Mark production-only tool use as unavailable when flags/credentials are off.

<!-- RETHINK_100:start -->
## RETHINK_100 operating guidance (design-time)

> Derived from `ui/RETHINK_100_IMPROVEMENTS.md` for `video.childrensauthor`.
> Does **not** enable production models or network. Host `agent_spec.json` remains authoritative.

### Applied item ids
12, 15, 21, 26, 30, 31, 32, 33, 37, 38, 42, 59, 63, 80, 87, 88, 93, 94

### Design-time model landscape (non-activating)
- (no additional gen models for this role beyond host allow-list)

### Obligations
- Host control plane owns orchestration; this agent never opens a second control plane.
- Runtime tools remain agent_spec.allowed_tools only; RETHINK model names are design-time.
- Fail closed when tools/providers are unavailable (circuit-breaker posture).
- Prefer iterative verify → refine ≤ max_refinement_count → HiTL over silent pass.
- Emit plain-English reasoning summary in artifacts for operator trust.
- Attach provenance / correlation_id / evidence_refs on every handoff.
- When character/IP consistency matters, require Character Bank + Reference Frame Bank ids in inputs; refuse inventing faces without refs.
- When first/last-frame control is in the brief, express start/end keyframes in the artifact; do not invent vendor activation.
- Verify intermediate narrative/script artifacts before advancing downstream handoffs.
- Escalate stereotype/harm/consent risks to ethics/trust-safety/legal gates.

### Collaboration with host architecture
- Commands arrive only via host task envelopes.
- Publish results as structured artifacts; never open browser/UI channels.
- On tool failure: degrade gracefully (circuit-breaker), emit recoverable error, do not invent success.
<!-- RETHINK_100:end -->

## Rubrics

### `rubrics/primary.md`

Source rubric `video.rubric.childrensauthor.v1.json` (baseline_safe; not a production pass).

```json
{
  "schema_version": "1.0",
  "rubric_id": "video.rubric.childrensauthor.v1",
  "agent_id": "video.childrensauthor",
  "title": "L2 craft rubric for ChildrensAuthorAgent",
  "pass_threshold": 85,
  "max_score": 100,
  "layers": {
    "L1_spec": {
      "description": "Machine validators: schema, format, required fields, policy allowlist",
      "must_pass": true
    },
    "L2_rubric": {
      "description": "LLM-as-Judge or scorer against dimensions below",
      "pass_threshold": 85,
      "dimensions": [
        {
          "id": "d1",
          "name": "Lexile band match",
          "description": "Lexile band match",
          "weight": 0.3333,
          "threshold_hint": null,
          "score_min": 0,
          "score_max": 100
        },
        {
          "id": "d2",
          "name": "Common-Sense-Media safety pass",
          "description": "Common-Sense-Media safety pass",
          "weight": 0.3333,
          "threshold_hint": null,
          "score_min": 0,
          "score_max": 100
        },
        {
          "id": "d3",
          "name": "rhyme score",
          "description": "rhyme score",
          "weight": 0.3334,
          "threshold_hint": null,
          "score_min": 0,
          "score_max": 100
        },
        {
          "id": "character_consistency",
          "name": "Character consistency",
          "weight": 1,
          "description": "Character bank / IP anchors honored when provided.",
          "source": "RETHINK_100#33"
        },
        {
          "id": "ethics_safety",
          "name": "Ethics & safety",
          "weight": 1,
          "description": "Stereotype/harm/consent flags escalated appropriately.",
          "source": "RETHINK_100#93"
        },
        {
          "id": "operator_explainability",
          "name": "Operator explainability",
          "weight": 1,
          "description": "Plain-English reasoning present for key decisions.",
          "source": "RETHINK_100#59"
        }
      ]
    },
    "L3_preference": {
      "description": "Optional pairwise/arena preference when human or synthetic preference data exists",
      "surpass_signal_design": "Beats Caldecott-rubric predicted score",
      "note": "Do not claim surpass until measured baseline exists"
    }
  },
  "refine_policy": {
    "max_refinement_count": 3,
    "on_fail": "refine_or_escalate_hitl"
  },
  "sources": {
    "agents_md_self_quality_criteria": "Lexile band match; Common-Sense-Media safety pass; rhyme score",
    "research": [
      "LLM-as-Judge",
      "Self-Refine",
      "Constitutional AI"
    ]
  },
  "rethink_100": {
    "applied": true,
    "extra_dimensions": [
      "character_consistency",
      "ethics_safety",
      "operator_explainability"
    ],
    "doc": "ui/RETHINK_100_IMPROVEMENTS.md"
  }
}

```

### `rubrics/video.rubric.childrensauthor.v1.json`

```json
{
  "schema_version": "1.0",
  "rubric_id": "video.rubric.childrensauthor.v1",
  "agent_id": "video.childrensauthor",
  "title": "L2 craft rubric for ChildrensAuthorAgent",
  "pass_threshold": 85,
  "max_score": 100,
  "layers": {
    "L1_spec": {
      "description": "Machine validators: schema, format, required fields, policy allowlist",
      "must_pass": true
    },
    "L2_rubric": {
      "description": "LLM-as-Judge or scorer against dimensions below",
      "pass_threshold": 85,
      "dimensions": [
        {
          "id": "d1",
          "name": "Lexile band match",
          "description": "Lexile band match",
          "weight": 0.3333,
          "threshold_hint": null,
          "score_min": 0,
          "score_max": 100
        },
        {
          "id": "d2",
          "name": "Common-Sense-Media safety pass",
          "description": "Common-Sense-Media safety pass",
          "weight": 0.3333,
          "threshold_hint": null,
          "score_min": 0,
          "score_max": 100
        },
        {
          "id": "d3",
          "name": "rhyme score",
          "description": "rhyme score",
          "weight": 0.3334,
          "threshold_hint": null,
          "score_min": 0,
          "score_max": 100
        },
        {
          "id": "character_consistency",
          "name": "Character consistency",
          "weight": 1,
          "description": "Character bank / IP anchors honored when provided.",
          "source": "RETHINK_100#33"
        },
        {
          "id": "ethics_safety",
          "name": "Ethics & safety",
          "weight": 1,
          "description": "Stereotype/harm/consent flags escalated appropriately.",
          "source": "RETHINK_100#93"
        },
        {
          "id": "operator_explainability",
          "name": "Operator explainability",
          "weight": 1,
          "description": "Plain-English reasoning present for key decisions.",
          "source": "RETHINK_100#59"
        }
      ]
    },
    "L3_preference": {
      "description": "Optional pairwise/arena preference when human or synthetic preference data exists",
      "surpass_signal_design": "Beats Caldecott-rubric predicted score",
      "note": "Do not claim surpass until measured baseline exists"
    }
  },
  "refine_policy": {
    "max_refinement_count": 3,
    "on_fail": "refine_or_escalate_hitl"
  },
  "sources": {
    "agents_md_self_quality_criteria": "Lexile band match; Common-Sense-Media safety pass; rhyme score",
    "research": [
      "LLM-as-Judge",
      "Self-Refine",
      "Constitutional AI"
    ]
  },
  "rethink_100": {
    "applied": true,
    "extra_dimensions": [
      "character_consistency",
      "ethics_safety",
      "operator_explainability"
    ],
    "doc": "ui/RETHINK_100_IMPROVEMENTS.md"
  }
}
```

## Sources

### `sources/ACQUIRE.md`

# Source acquisition runbook — `video.childrensauthor`

## Purpose
Obtain or refresh knowledge distillation sources listed in `SOURCE_CATALOG.json`.

## Rules
1. **No secrets in git.** API keys only via environment / secret manager.
2. Prefer **licensed / consented / public domain** material.
3. If license unknown: store only short fair-use design excerpts under `excerpts/` and mark `license_class=unknown_review_required`.
4. Update `PROVENANCE.json` with URL, retrieved_at, hash, and license note.
5. Re-run offline golden eval after material changes.

## Design sources (from agents.md)
Caldecott/Geisel winners; Mo Willems/Donaldson; ECE lit

## Steps
1. Open `SOURCE_CATALOG.json`.
2. For each source with status planned_or_partial, document acquisition method.
3. Place fixtures under `excerpts/` or `study/`.
4. Update `MAPPING.md` with path mapping.
5. Set `next_review_at` in `DISTILLATION_PLAN.json`.

### `sources/DISTILLATION_PLAN.json`

```json
{
  "schema_version": "1.0",
  "agent_id": "video.childrensauthor",
  "plan_id": "video.childrensauthor.distill.v1",
  "inputs": [
    "src_1",
    "src_2",
    "src_3"
  ],
  "extractors": [
    "markdown_excerpt",
    "structured_table_row"
  ],
  "chunk_policy": {
    "max_chars": 2000,
    "overlap": 200
  },
  "owner": "video.childrensauthor",
  "cadence": "quarterly",
  "promotion_criteria": [
    "source license approved or fixture-only",
    "excerpt hash recorded in PROVENANCE",
    "golden eval still passes L1"
  ],
  "memory_namespace": "pack.video.video.childrensauthor",
  "next_review_at": "2026-10-01"
}
```

### `sources/excerpts/agents.md`

# AI Agent Roster — Per-Category Split

> Distilled from [`ai_agent_video_production_workflow.md`](./ai_agent_video_production_workflow.md).
> This file restores the `agents_old.md` layout as the primary structure.
> Missing workflow-support content from the newer `agents.md` revision has been merged back in as an additional section using the same per-category table style.

---

## Table of Contents

1. [Above-the-Line Agents (1–5)](#1-above-the-line-agents)
2. [Camera & Lighting Agents (6–8)](#2-camera--lighting-agents)
3. [Editorial & Color Agents (9–18)](#3-editorial--color-agents)
4. [Sound & Music Agents (19–22)](#4-sound--music-agents)
5. [Performance & Choreography Agents (23–27)](#5-performance--choreography-agents)
6. [Distribution & Marketing Agents (28–31)](#6-distribution--marketing-agents)
7. [Education & Domain-Expert Agents (32–45)](#7-education--domain-expert-agents)
8. [AI-Era Specialist Agents (46–52)](#8-ai-era-specialist-agents)
9. [Specialist Meta-Agents (53–80)](#9-specialist-meta-agents)
10. [Workflow Support Agents (81–114)](#10-workflow-support-agents)
11. [Common Structure of an AI Agent](#11-common-structure-of-an-ai-agent)
    - [11.1 Architecture Diagram](#111-architecture-diagram)
    - [11.2 Component Reference Table](#112-component-reference-table)
12. [References](#12-references)

---

## 1. Above-the-Line Agents

| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From | Comments On | Tool Access | Architecture Pattern |
|---|---|---|---|---|---|---|---|---|---|
| 1 | **DirectorAgent** | Owns vision; issues shot intents, sets pacing, approves takes | Criterion commentary; IMDb Top 250 director interviews; DGA seminars; MasterClass (Scorsese/Lynch/Gerwig) | Shot-intent fidelity (CLIP-T ≥0.32); story-beat coverage 100%; pacing curve matches genre prior | Wins ≥55% blind pairwise vs DGA cuts (Arena) | ScreenwriterAgent, EditorAgent, AudienceSim — JSON critique bus | EditorAgent, DoPAgent, ScreenwriterAgent, ComposerAgent | Sora 2 API, Veo 3.1 (Gemini API), Runway Gen-4, Kling 3.0; DaVinci Resolve via MCP | Self-Refine + LLM-as-Judge (rubric: genre priors) |
| 2 | **ProducerAgent / EP** | Budget, schedule, hiring, delivery; greenlights phase gates | PGA Producers Mark; Variety/Deadline budget leaks; LineProducer Excel corpora | On-time delivery rate; budget variance <±5%; talent satisfaction (RLHF) | Beats PGA schedules at 0.6× cost with equal CSAT | All downstream agents (escalations); HiTL gate for greenlight | DirectorAgent (scope creep), AllAgents (resource burn) | Google Sheets API, Airtable, Temporal/Airflow orchestration, Stripe billing | Agentic Graph (LangGraph DAG) + ReAct for tool calls |
| 3 | **ScreenwriterAgent** | Treatment → screenplay; dialogue; structure | Black List scripts; WGA library; McKee *Story*; Truby; Kaufman/Sorkin interviews | Save-the-Cat beat pass; dialogue distinctiveness (embedding distance ≥τ); rewrite delta | Wins ≥50% blind read vs Black List Top-10 (WGA panel emulated) | DirectorAgent, DramaturgAgent, StoryEditorAgent — Reflexion loop | DirectorAgent (logline), DialogueAgent, ConsistencyAgent | Fountain/FDX format validators; semantic embedding models (text-embedding-3-large) | Reflexion (Shinn 2023) — verbal RL with episodic memory |
| 4 | **ShowrunnerAgent** | Cross-episode arc, writers'-room orchestration | WGA showrunner training; Sopranos/BB room transcripts; Mike Schur material | Arc continuity score; character-thread completion; tonal variance within bounds | Series Bible coverage ≥99% across 10 eps (vs ~95% human) | Network-Notes Agent, AudienceSim, multi-agent debate w/ ScreenwriterAgent | ScreenwriterAgent (arc), CastingAgent, DirectorAgent (tone) | Long-context LLM (Gemini 2.5 Pro 1M), vector-DB (Pinecone/Weaviate) for bible search | Multi-agent debate (Du 2023) + MemoryAgent retrieval |
| 5 | **CastingAgent** | Voice + likeness selection; audition simulation | CSA Artios archive; SAG-AFTRA AI rider; consented voice-actor corpora | Character-voice fit (audience preference); consent compliance 100% | Beats CSA casting in blind preference; hours vs weeks turnaround | DirectorAgent, ShowrunnerAgent, Legal/ConsentAgent | VoiceCloneAgent (likeness), AvatarDesignAgent | ElevenLabs v3 voice library, HeyGen avatar catalogue, speaker-embedding similarity (Resemblyzer) | LLM-as-Judge (pairwise preference on voice samples) |

---

## 2. Camera & Lighting Agents

| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From | Comments On | Tool Access | Architecture Pattern |
|---|---|---|---|---|---|---|---|---|---|
| 6 | **CinematographerAgent (DoP)** | Lensing, lighting, composition, look | ASC Magazine 1980–present; Deakins forum; Brown *Cinematography: Theory & Practice*; Cannes shot-libraries | Rule-of-thirds/leading-lines score; exposure histogram in zone; color-temp consistency | Beats ASC peer-juried reels in blind aesthetic preference | DirectorAgent, ColoristAgent, VFXSupAgent | DirectorAgent (visual intent), GafferAgent, ColoristAgent | Veo 3.1 (camera-path control), Runway Gen-4 (ControlNet guides), ACES color pipeline tools | Self-Refine + CLIP-based aesthetic scoring |
| 7 | **CameraOperatorAgent** | Executes framing / focus / move per DoP intent | SOC archive; Steadicam workshop reels; focus-pull telemetry | Frame steadiness, focus-hit %, action centering | Focus-pull accuracy >99% vs SOC ~97% baseline | CinematographerAgent (per-take feedback) | CinematographerAgent (impractical asks) | Runway camera-path presets; Kling motion control API; virtual camera rigs (Unreal MV) | ReAct (Yao 2022) — reason about framing then call renderer |
| 8 | **DronePilotAgent** | Aerial cinematography (simulated or real) | Philip Bloom tutorials; FAA Part 107; SkyPixel award reels | Path smoothness; geofence compliance 100%; horizon stability | Competition-grade smoothness at 10× sortie rate; zero violations | DoPAgent, SafetyAgent | DoPAgent (impossible heights), SafetyAgent (risk) | DJI Waypoint SDK (sim); Veo 3.1 aerial-mode; geofence DB (AirMap API) | Constitutional AI (safety constitution: FAA rules as principles) |

---

## 3. Editorial & Color Agents

| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From | Comments On | Tool Access | Architecture Pattern |
|---|---|---|---|---|---|---|---|---|---|
| 9 | **EditorAgent** | Assemble cut; pacing; coverage selection | Murch *In the Blink of an Eye*; ACE Eddie winners; Sundance editing labs | Pacing curve matches genre; Murch "Rule of Six" score; AVD ≥ target | Wins ≥55% pairwise vs ACE-credited cuts | DirectorAgent, AudienceSim, ComposerAgent (music-cut sync) | DirectorAgent (over-coverage), DoPAgent (unusable takes) | DaVinci Resolve via MCP bridge; FFmpeg; EDL/XML timeline APIs | Self-Refine (rubric: Murch Rule of Six) |
| 10 | **ColoristAgent** | Final grade; look consistency | ICA corpora; Sonnenfeld sessions; HPA Award grades | ΔE drift <2; skin-tone IT8 alignment; mood vector match | Beats junior colorist in blind preference; matches senior within ΔE | DoPAgent, DirectorAgent, AccessibilityAgent (contrast) | DoPAgent (mixed-temp), VFXAgent (comp-color mismatch) | DaVinci Resolve color API (MCP); ACES/OCIO pipeline; LUT generators | Self-Refine + tool-use (colorimeter validation) |
| 11 | **VFXSupervisorAgent** | Plans + supervises VFX pipeline | VES Awards; SIGGRAPH papers; Weta/DNEG talks; Foundry training | Shot-completion %; comp-error pixel count; CLIP-T vs plate | Weta-grade QC pass rate at fraction of time | DirectorAgent, DoPAgent, ConsistencyAgent | AIGeneratorAgent (artifacts), CompositorAgent | Nuke via MCP bridge; Runway Gen-4 Aleph (video-to-video); ComfyUI | Agentic Graph (fan-out per shot) + LLM-as-Judge (QC rubric) |
| 12 | **AnimatorAgent (2D/3D)** | Character motion, weight, timing | Williams

…(clipped 66015 characters from `agents.md`)

### `sources/excerpts/ai_agent_video_production_workflow.md`

# AI Agent Video Production Workflow

> Companion to `human_video_production_workflow.md`. For every human crew role in the master roster, this document defines the **AI agent** that replaces (or augments) it, along with: scope of duties, knowledge-distillation pipeline, self-quality criteria, signals that the agent has surpassed a human professional, how the agent accepts critique from other agents, and what the agent is qualified to critique in return.

---

## 1. System Foundations and Reference-Scanning Plan

| Pattern | Purpose | Reference |
|---|---|---|
| **Self-Refine** | Agent drafts → self-critiques against rubric → revises | Madaan et al., 2023 |
| **Reflexion** | Agent stores verbal feedback in episodic memory, retries | Shinn et al., 2023 |
| **RLAIF / Constitutional AI** | Reward signal from AI critic governed by a written constitution | Bai et al., 2022 |
| **Multi-agent debate** | Two+ agents argue; judge agent picks the better answer | Du et al., 2023 (LLM debate) |
| **LLM-as-Judge with rubric** | Frozen judge model scores outputs against pre-registered rubric | Zheng et al., 2023 (MT-Bench) |
| **Pairwise preference (Arena)** | Blind A/B vote between agent output and human reference | LMSYS Chatbot Arena methodology |
| **Tool-use / ReAct** | Agent reasons + calls external tools (renderers, validators) | Yao et al., 2022 |
| **Agentic graph (CrewAI / AutoGen / LangGraph)** | Roles orchestrated as a DAG with handoffs and review gates | CrewAI, AutoGen, LangGraph |
| **Provenance (C2PA)** | Every artifact signed; downstream agents verify the chain | C2PA spec |

All agents below are assumed to be implemented as orchestrated nodes in a CrewAI / AutoGen / LangGraph topology, with tool access to generative video models (Sora, Veo, Runway, Kling), TTS/voice-clone APIs (ElevenLabs, Sync.so, Hedra), DCC tooling (Resolve, Nuke, AE via MCP bridges), and a shared critique bus.

### 1.1 Reference Scanning and Knowledge-Synthesis Workflow

The documentation-enhancement process for this system follows a fixed scan-to-synthesis loop so that new material added from `study/reference/how_to_build_a_video_agent_system` is traceable, scoped, and technically consistent.

| Step | Method | What is extracted | Admission rule |
|---|---|---|---|
| **Inventory** | Enumerate all chapters, agent lists, and distillation notes before reading | File coverage map, chapter clusters, missing topic alerts | No section is updated until all reference files are indexed |
| **Cluster** | Group files by function: orchestration, creation, QA, delivery, optimization, training | Thematic buckets and overlap map | A concept must be assigned to at least one workflow stage |
| **Extract** | Pull technical concepts, implementation details, metrics, handoffs, and best practices | Candidate facts, agent responsibilities, thresholds, artifact types | Extract only claims that are specific enough to operationalize |
| **Verify** | Cross-check each candidate against a second reference chapter, an existing section, or a standards anchor already named in this file | Verified additions, rejected assumptions, ambiguity flags | Ambiguous or single-source claims remain out of the core workflow |
| **Map** | Attach verified material to the most relevant section in this document | Patch list by section, table, or phase gate | Prefer enriching existing structure over adding parallel taxonomies |
| **Integrate** | Rewrite affected sections so new detail strengthens architecture, handoffs, and evaluation logic | Updated workflow prose, tables, and shared contracts | Added material must improve technical depth without duplicating nearby content |
| **Review** | Re-read end to end for consistency, completeness, terminology, and factual alignment | Finalized revision set and follow-up fixes | No release until naming, logic flow, and gate criteria are internally consistent |

**Working rules:**
1. Extract concepts under four lenses: **technical architecture**, **implementation sequence**, **quality/compliance**, and **continuous learning**.
2. Prefer workflow-relevant facts over market commentary unless the market fact changes routing, cost, or scale decisions.
3. Record handoff artifacts explicitly: prompts, scene packets, stems, graded masters, manifests, provenance bundles, and telemetry.
4. Reject role inflation unless a new role closes a real gap in orchestration, validation, continuity, delivery, or retraining.
5. Treat delivery packaging, observability, and asset management as system architecture, not postscript operations.

### 1.2 Runtime Production Systems Architecture

| Layer | Core responsibility | Implementation notes |
|---|---|---|
| **Orchestration runtime** | Plan, route, schedule, retry, and escalate agent tasks | PlannerAgent decomposes the brief; OrchestratorAgent executes the DAG; RouterAgent selects agent-model pairs; JudgeAgent arbitrates disputes |
| **Asset and data backbone** | Store every prompt, source asset, derived asset, version, dependency edge, and usage right | Requires immutable asset IDs, copy-on-write versions, dependency-triggered rerender rules, and searchable metadata |
| **Message and state fabric** | Carry critique, job status, render events, and gate decisions across agents | Event-driven bus plus durable state store; every long-running job must be resumable and auditable |
| **Quality and continuity mesh** | Run technical QC, continuity checks, artifact detection, accessibility, and compliance gates | Uses multi-pass validation, temporal continuity scans, loudness and color checks, and role-specific rubric judges |
| **Observability and replay** | Expose live status, failure causes, bottlenecks, and historical decisions | Structured logs, job timelines, gate dashboards, benchmark alerts, and replayable artifact lineage |
| **Delivery fabric** | Package masters into theatrical, streaming, broadcast, archive, trailer, and campaign variants | Distribution is a branching pipeline with outlet-specific specs, captions, metadata, DRM/KDM, and provenance payloads |
| **Compute and storage scaling** | Match infrastructure spend to production scale without breaking deadlines | Separate interactive generation from batch rendering; autoscale GPU pools; tier hot, warm, and archive storage |

### 1.3 Shared Artifact Handoff Contract

Every phase hands downstream agents a machine-readable manifest so creative work, QA, and compliance stay synchronized.

| Field | Purpose |
|---|---|
| **artifact_id / version** | Unique identity for every output and revision |
| **parent_assets** | Provenance links to scripts, prompts, plates, stems, references, and prior cuts |
| **brief_scope** | The exact subtask, acceptance criteria, and target audience segment |
| **technical_spec** | Codec, aspect ratio, duration, frame rate, color space, loudness, caption requirements |
| **rights_and_consent** | License state, likeness/voice consent state, territorial limits, embargo rules |
| **continuity_state** | Character look, props, wardrobe, environment, scene-time logic, and identity hash |
| **qc_status** | Latest L1/L2/L3 result plus six-pass delivery-QC status |
| **target_channels** | Theatrical, streaming, broadcast, archive, paid social, CRM, LMS, or festival endpoints |
| **provenance_manifest** | C2PA reference, critique log pointer, and final sign-off chain |

### 1.4 Reassessment Discipline

Documentation changes for this system are reviewed as a repeated challenge cycle rather than a single proofread. A 100-pass reassessment can be grouped into the following bands:

| Passes | Primary question |
|---|---|
| **1-20** | Are all extracted claims traceable to the reference set and aligned with the document's structure? |
| **21-40** | Does the architecture describe the real control plane: orchestration, memory, assets, delivery, and observability? |
| **41-60** | Are workflow handoffs explicit enough for implementation, QA, continuity, and compliance automation? |
| **61-80** |

…(clipped 57472 characters from `ai_agent_video_production_workflow.md`)

### `sources/excerpts/SYSTEM_REFERENCE.md`

# VA-Agent-Swarm — System Reference & Integration Map

> **Purpose:** This document is the single entry point that links every agent specification, workflow, technical architecture, and supporting resource into one cohesive system view. It maps how each component relates to the whole, defines the integration points, and provides navigation for implementers.

---

## Table of Contents

1. [System Overview](#1-system-overview)
2. [Architecture Layers](#2-architecture-layers)
3. [Agent Categories & Specification Map](#3-agent-categories--specification-map)
4. [Infrastructure & Support Agents](#4-infrastructure--support-agents)
5. [Cross-Cutting Capabilities](#5-cross-cutting-capabilities)
6. [Workflow Integration](#6-workflow-integration)
7. [Data Flow & Handoff Contracts](#7-data-flow--handoff-contracts)
8. [UI & Communication Layer](#8-ui--communication-layer)
9. [Technology Stack Reference](#9-technology-stack-reference)
10. [Reference Material Index](#10-reference-material-index)
11. [Implementation Priority & Dependencies](#11-implementation-priority--dependencies)

---

## 1. System Overview

The **VA-Agent-Swarm** is a hierarchical multi-agent system (MAS) designed to fully automate (or augment) professional video production — from initial creative brief through final delivery across all distribution channels. The system comprises **114 specialized agents** organized into 10 functional categories, supported by dedicated infrastructure agents, a shared critique bus, and a unified orchestration runtime.


### Core Design Principles

| Principle | Description | Reference |
|-----------|-------------|-----------|
| **Agentic Graph** | Agents as DAG nodes with handoffs and review gates | [ai_agent_video_production_workflow.md](./ai_agent_video_production_workflow.md) §1 |
| **Self-Refine + Critique** | Every agent drafts → self-critiques → revises against rubric | Madaan et al., 2023 |
| **Shared Artifact Contract** | Machine-readable manifests flow between all phases | [ai_agent_video_production_workflow.md](./ai_agent_video_production_workflow.md) §1.3 |
| **Human-in-the-Loop Gates** | Critical decisions escalate to human approval | [agents.md](./agents.md) — ProducerAgent |
| **Provenance (C2PA)** | Every artifact is signed; downstream agents verify chain | C2PA spec |
| **Continuous Self-Improvement** | Agents learn from outcomes, store episodic memory, ratchet quality | Reflexion (Shinn 2023) |

### System Boundaries

```
┌─────────────────────────────────────────────────────────────────────────┐
│  USER / CLIENT BRIEF                                                     │
└───────────┬─────────────────────────────────────────────────────────────┘
            ▼
┌─────────────────────────────────────────────────────────────────────────┐
│  TIER 1: UI FRONTEND — React 19 + Next.js 15                             │
│  (Project creation, agent management, real-time monitoring)              │
└───────────┬──────────────────────────────────┬──────────────────────────┘
            │ REST/GraphQL (commands)           │ WebSocket (live streams)
            ▼                                   ▼
┌─────────────────────────────────────────────────────────────────────────┐
│  TIER 2: API GATEWAY + ORCHESTRATION BACKEND                             │
│  FastAPI + LangGraph + Temporal + Redis Event Bus                        │
└───────────┬──────────────────────────────────┬──────────────────────────┘
            │ Agent Task Queue                  │ Tool API Calls
            ▼                                   ▼
┌─────────────────────────────────────────────────────────────────────────┐
│  TIER 3: AGENT RUNTIME — 114 Agent Definitions                           │
│  LLM Providers: Grok-4.x, Gemini 2.5 Pro, GPT-4o, Claude 4             │
│  Tool Access: Sora 2, Veo 3.1, Runway Gen-4, ElevenLabs, DaVinci, etc. │
└─────────────────────────────────────────────────────────────────────────┘
```

> **Full architecture details:** [ui/architecture_communication.md](./ui/architecture_communication.md)


---

## 2. Architecture Layers

The system is organized into **7 runtime layers** that every agent participates in:

| Layer | Responsibility | Key Agents / Services |
|-------|---------------|----------------------|
| **Orchestration** | Plan, route, schedule, retry, escalate | PlannerAgent (#54), OrchestratorAgent (#53), RouterAgent (#55), JudgeAgent (#56) |
| **Asset & Data Backbone** | Immutable asset IDs, versioning, dependency edges, rights | Asset Store (S3 + metadata DB) |
| **Message & State Fabric** | Critique bus, job status, gate decisions | Redis Streams / NATS, durable state store |
| **Quality & Continuity Mesh** | Multi-pass QC, continuity, accessibility, compliance | AIQAConsistencyAgent (#49), ComplianceAgent (#37), AccessibilityAgent |
| **Observability & Replay** | Live status, failure causes, bottlenecks, replay | AgentOps pipeline, LangSmith traces |
| **Delivery Fabric** | Package masters into outlet-specific variants | TrailerEditorAgent (#51), SocialMediaStrategistAgent (#28) |
| **Compute & Storage Scaling** | GPU autoscale, tiered storage | Infrastructure layer (Docker/K8s) |

> **Full layer specification:** [ai_agent_video_production_workflow.md](./ai_agent_video_production_workflow.md) §1.2

---

## 3. Agent Categories & Specification Map

The 114 agents are organized into 10 categories. Below, each category links to the master roster AND to any dedicated deep-specification documents that provide implementation-level detail.

### 3.1 Above-the-Line Agents (1–5)

| # | Agent | Role | Deep Specification |
|---|-------|------|--------------------|
| 1 | DirectorAgent | Owns vision; shot intents, pacing, approvals | — |
| 2 | ProducerAgent / EP | Budget, schedule, phase gates | — |
| 3 | ScreenwriterAgent | Treatment → screenplay; dialogue; structure | [screenwriter_strategic_goal_achievement_agent_functional_specification.md](./screenwriter_strategic_goal_achievement_agent_functional_specification.md) |
| 4 | ShowrunnerAgent | Cross-episode arc, writers'-room orchestration | — |
| 5 | CastingAgent | Voice + likeness selection; auditions | — |

**Roster reference:** [agents.md](./agents.md) §1


### 3.2 Camera & Lighting Agents (6–8)

| # | Agent | Role | Deep Specification |
|---|-------|------|--------------------|
| 6 | CinematographerAgent (DoP) | Lensing, lighting, composition, look | — |
| 7 | CameraOperatorAgent | Framing, focus, camera moves | — |
| 8 | DronePilotAgent | Aerial cinematography | — |

**Roster reference:** [agents.md](./agents.md) §2

### 3.3 Editorial & Color Agents (9–18)

| # | Agent | Role | Deep Specification |
|---|-------|------|--------------------|
| 9 | EditorAgent | Assemble cut; pacing | — |
| 10 | ColoristAgent | Final grade; look consistency | — |
| 11 | VFXSupervisorAgent | VFX pipeline supervision | — |
| 12 | AnimatorAgent (2D/3D) | Character motion, timing | — |
| 13 | MotionGraphicsAgent | Kinetic typography, infographics | — |
| 14 | StoryboardAgent | Script → shot panels | — |
| 15 | ConceptArtistAgent | World/character design | — |
| 16 | ProductionDesignAgent | Sets, locations, world look | — |
| 17 | CostumeDesignAgent | Character wardrobe | — |
| 18 | MUAAgent | Makeup/Hair/SFX | — |

**Roster reference:** [agents.md](./agents.md) §3

### 3.4 Sound & Music Agents (19–22)

| # | Agent | Role | Deep Specification |
|---|-------|------|--------------------|
| 19 | SoundDesignAgent | Ambience, foley, SFX | — |
| 20 | ComposerAgent | Original score | — |
| 21 | VoiceOverAgent | Narration, character VO | [podcast_agent_functional_specifcation.md](./podcast_agent_functional_specifcation.md) (shared patterns) |
| 22 | SoundMixerAgent | Final mix; 5.1/Atmos deliverables | — |

**Roster reference:** [agents.md](./agents.md) §4

### 3.5 Performance & Choreography Agents (23–27)

| # | Agent | Role | Deep Specification |
|---|-------|------|--------------------|
| 23 | ChoreographyAgent | Movement design | — |
|

…(clipped 29498 characters from `SYSTEM_REFERENCE.md`)

### `sources/generic/video.legal.SPEC.md`

# LegalAgent

> **Self-contained agent definition** for host `generic-swarm-ops`. Body text is embedded from in-pack corpus and va-agent-swarm when available. Do not require external repos to understand this agent.

## Identity

| Field | Value |
|-------|-------|
| **va_id** | 93 |
| **pack_id** | `video.legal` |
| **category** | `10-Sup` |
| **domain_id** | `video` |
| **folder** | `business/video/agents/video.legal/` |

## Category roster section (full, from agents.md)

_The following is the complete category section from the master roster (includes peers in the same craft category)._


## 10. Workflow Support Agents

| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From | Comments On | Tool Access | Architecture Pattern |
|---|---|---|---|---|---|---|---|---|---|
| 81 | **AnalystAgent** | Aggregates business, creative, and technical performance telemetry into decision-ready reports | Platform analytics dashboards; experiment logs; evaluation-harness outputs; benchmark histories | KPI completeness; forecast-vs-actual variance within tolerance; insight-to-action turnaround | Detects actionable performance shifts faster than human analyst rotations | SocialMediaStrategistAgent, PerformanceMarketerAgent, EvaluationHarnessAgent | Campaign pacing, release timing, retention and ROAS anomalies | YouTube Analytics, Meta/TikTok Ads dashboards, BI warehouse, benchmark logs | ReAct over telemetry + regression analysis |
| 82 | **AudienceSimAgent** | Simulates audience preference, engagement, and drop-off | Pairwise preference datasets; retention studies; audience segmentation models | Preference stability across cohorts; retention-prediction accuracy; disagreement logging | Predicts audience reaction earlier than conventional test-screen cycles | DirectorAgent, EditorAgent, AnalystAgent, JudgeAgent | Hooks, pacing, clarity, emotional fit, trailer strength | Persona simulators, pairwise evaluation harness, retention models | LLM-as-Judge + pairwise preference panel |
| 83 | **AccessibilityAgent** | Owns final accessibility acceptance before release | WCAG 2.2, captioning and AD guidelines, Deaf/HoH review frameworks | Caption accuracy, AD completeness, contrast compliance, release-readiness | Finds release-blocking accessibility issues before human audits do | AccessibilityOptimizerAgent, EditorAgent, ColoristAgent, SoundMixerAgent | Caption sync, contrast issues, missing AD or sign-language layers | Caption validators, contrast analyzers, AD review tools | Constitutional AI with accessibility constitution |
| 84 | **BrandAgent** | Enforces brand voice, claims boundaries, and visual consistency | Brand books, approved campaigns, legal claim guardrails, tone guides | Brand-voice similarity, policy adherence, low deviation across assets | Holds cross-channel brand consistency better than fragmented human review | CopywriterAgent, MotionGraphicsAgent, MarketingAgent, BrandStrategistAgent | Voice drift, visual inconsistency, claim creep | Brand asset library, embedding similarity, style guides | Self-Refine against brand constitution |
| 85 | **BrandStrategistAgent** | Defines audience-value framing and positioning before script and campaign execution | Positioning frameworks, campaign strategy decks, market research, brand architecture docs | Strategy coherence, differentiation strength, audience-message clarity | Produces clearer brand-to-script translation than ad hoc human handoffs | BrandAgent, ScreenwriterAgent, MarketingAgent | Positioning gaps, weak value proposition, misaligned audience framing | Research decks, messaging frameworks, strategy templates | Multi-agent debate with BrandAgent and CreativeDirectorAgent |
| 86 | **MarketingAgent** | Packages content for launch, promotions, and release sequencing | Campaign playbooks, launch calendars, media plans, asset packaging requirements | Metadata completeness, asset readiness, launch sequencing accuracy | Ships multi-channel launch packages faster than manual campaign ops | SocialMediaStrategistAgent, SEOAgent, CopywriterAgent, TrailerEditorAgent | Missing formats, weak rollout timing, incomplete promotion sets | Campaign management suites, metadata tools, release planners | ReAct over launch checklists and channel requirements |
| 87 | **SEOAgent** | Optimizes discoverability through titles, descriptions, metadata, and search intent | Search ranking studies, video metadata best practices, keyword taxonomies | Keyword fit, metadata completeness, search-intent match | Lifts discoverability faster than manual metadata tuning | MarketingAgent, CopywriterAgent, AnalystAgent | Weak keywords, poor title-description fit, metadata omissions | Keyword tools, metadata APIs, ranking dashboards | ReAct with search-intent validation |
| 88 | **CommunityAgent** | Captures community response and triages qualitative signals | Community moderation playbooks, sentiment datasets, escalation rules | Response latency, issue clustering quality, sentiment tracking accuracy | Surfaces emerging audience concerns earlier than manual comment review | AnalystAgent, SocialMediaStrategistAgent, CommsAgent | Confusing messaging, sentiment risks, recurring complaints | Social listening tools, moderation dashboards, clustering models | Reflexion from post-launch audience feedback |
| 89 | **TemplateDesignAgent** | Designs reusable and safe personalization templates | Variable-content design systems, dynamic layout rules, campaign template libraries | Merge-field robustness, layout stability, render survivability | Produces reusable templates with fewer breakages than manual design variants | PersonalizationEngineerAgent, UXAgent, CRMAgent | Fragile layouts, unsafe placeholder logic, merge collisions | Template engines, design systems, schema validators | ReAct on template schemas and render constraints |
| 90 | **UXAgent** | Reviews clarity and usability of personalized or interactive outputs | UX heuristics, accessibility criteria, usability testing patterns | Readability, friction-point detection, user-flow clarity | Flags user confusion earlier than launch-stage support teams | TemplateDesignAgent, PersonalizationEngineerAgent, AccessibilityAgent | Confusing flows, readability issues, weak interaction cues | UX review checklists, session replay, readability tools | LLM-as-Judge with UX rubric |
| 91 | **TrustSafetyAgent** | Screens outputs for impersonation, abuse, or harmful misuse | Abuse-taxonomy corpora, impersonation cases, policy rulebooks | Policy hit rate, abuse-risk recall, low false negatives on blocked cases | Catches misuse risk earlier than generic moderation queues | ComplianceAgent, DeepfakeDetectionAgent, SafetyRedTeamAgent | Harmful misuse pathways, impersonation vectors, policy gaps | Safety classifiers, abuse taxonomy DB, moderation APIs | Constitutional AI for trust-and-safety policy enforcement |
| 92 | **CRMAgent** | Delivers audience-targeted or trigger-based campaigns through CRM systems | CRM automation flows, lifecycle marketing playbooks, audience segmentation rules | Audience-segment correctness, delivery readiness, trigger accuracy | Executes segmentation-to-delivery flow faster than manual ops | PersonalizationEngineerAgent, TemplateDesignAgent, AnalystAgent | Wrong segmentation, broken trigger timing, incomplete CRM payloads | HubSpot/Salesforce-style CRM APIs, segmentation tools | ReAct over trigger and audience schemas |
| 93 | **LegalAgent** | Performs final legal review for novel or high-risk publication issues | Media law references, clearance workflows, defamation/IP/privacy cases | Issue identification recall, sign-off completeness, escalation quality | Reduces late-stage legal surprises relative to fragmented legal review | ComplianceAgent (Legal), JournalistAgent, ProducerAgent / EP, MPAAgent | Novel legal risks, unclear rights, unresolved high-risk claims | Legal memo systems, rights trackers, clearance databases | Human-in-the-loop escalation + constitutional review |
| 94 | **FestivalStrategistAgent** | Positions projects for festivals and submission calendars | Festival submission guides, award-season strategies, selection histories | Fit-to-festival strength, package readiness, timing discipline | Improves submission targeting versus generic release planning | ProducerAgent / EP, DirectorAgent, CriticAgent | Weak positioning, mistimed submission plans, incomplete packages | Festival calendars, submission checklists, press-kit trackers | ReAct with calendar and package validation |
| 95 | **CriticAgent** | Simulates reviewer, press, or jury interpretation | Criticism corpora, festival-jury commentary, review archives | Interpretive depth, consistency, reviewer-mode diversity | Provides broader qualitative coverage than ad hoc internal taste review | DirectorAgent, AudienceSimAgent, FestivalStrategistAgent, JudgeAgent | Auteur read, tone mismatch, festival/press vulnerability | Review corpora, jury rubrics, qualitative scoring tools | Multi-agent debate as critic panel |
| 96 | **LMSAgent** | Packages and deploys learning content to LMS environments | SCORM/xAPI standards, LMS publishing workflows, completion-tracking schemas | Package validity, tracking integrity, deploy success rate | Ships publishable learning packages faster than manual course ops | InstructionalDesignAgent, AccessibilityAgent, LearnerSimAgent | Package compliance, tracking errors, learning-objective mismatch | LMS APIs, SCORM/xAPI validators, course packaging tools | ReAct over LMS deployment schema |
| 97 | **LearnerSimAgent** | Simulates learner behavior, confusion points, and assessment performance | Learner-modeling datasets, completion analytics, quiz outcome patterns | Friction-point prediction, completion accuracy, simulated quiz realism | Predicts weak spots before live learner complaints emerge | InstructionalDesignAgent, LMSAgent, AnalystAgent | Confusing content, weak assessments, low-completion pathways | Learner simulation models, assessment predictors, LMS data | Audience-style simulation adapted for learning outcomes |
| 98 | **ContinuityAgent** | Maintains continuity across character, prop, wardrobe, environment, and time-state | Continuity logs, script supervisor practices, asset manifest state tracking | State-drift detection, scene-to-scene consistency, manifest update correctness | Catches continuity breaks earlier than end-of-post review | CostumeDesignAgent, MUAAgent, AIQAConsistencyAgent, CinematographerAgent (DoP), GateKeeperAgent | Character-state drift, wardrobe and prop mismatch, time logic errors | State manifests, shot comparison tools, continuity DB | Tool-use / ReAct with continuity manifest enforcement |
| 99 | **LipSyncAgent** | Validates and refines phoneme-viseme alignment as a dedicated gate | Lip-sync research, animation timing references, viseme datasets | Sync error below threshold, correction specificity, low false positives | Finds sync drift more precisely than general QC review | VoiceCloneAgent / LipSyncSpecialist, AnimatorAgent, AIQAConsistencyAgent | Mouth-shape mismatch, frame drift in dialogue, correction priority | Phoneme-viseme aligners, frame-level sync tools | Self-Refine around sync validator outputs |
| 100 | **MusicSupervisorAgent** | Manages music fit, cue usage, rights awareness, and soundtrack packaging | Music supervision notes, cue placement references, soundtrack release practice | Cue suitability, rights-awareness coverage, soundtrack-package completeness | Coordinates music placements more consistently than fragmented handoffs | ComposerAgent, TrailerEditorAgent, LabelA&RAgent, LegalAgent | Cue misuse, music-rights ambiguity, soundtrack cohesion issues | Music asset trackers, cue sheets, soundtrack package tools | ReAct over cue sheets and rights requirements |
| 101 | **LabelA&RAgent** | Represents label and artist direction for music-specific workflows | A&R playbooks, label release notes, artist brief archives | Artist-fit quality, release positioning, feedback turnaround | Aligns music creative faster than disconnected stakeholder threads | MusicVideoDirectorAgent, MusicSupervisorAgent, LabelDigitalAgent | Artist-direction drift, release mismatch, packaging weakness | Repertoire systems, release trackers, artist brief tools | Multi-agent debate with music stakeholders |
| 102 | **LabelDigitalAgent** | Runs label-side digital rollout, metadata, and channel packaging | Digital music release operations, metadata schemas, distribution platform requirements | Metadata completeness, rollout timing, channel readiness | Delivers cleaner label-side packages than ad hoc release ops | MusicVideoDirectorAgent, SocialMediaStrategistAgent, MarketingAgent | Missing metadata, release timing issues, asset-version confusion | Digital release systems, channel dashboards, metadata tools | ReAct on release package requirements |
| 103 | **DeepfakeDetectionAgent** | Detects synthetic identity, voice, and provenance deception risks | Deepfake forensics corpora, synthetic-media benchmarks, identity-risk studies | Forensic recall, false-negative control, provenance-validation accuracy | Catches deceptive synthetic markers that generic QC misses | AvatarDesignAgent, VoiceCloneAgent, TrustSafetyAgent, SafetyRedTeamAgent | Identity anomalies, provenance holes, deceptive synthesis patterns | Forensic models, face/voice anomaly detectors, provenance validators | Tool-use / ReAct with forensic scoring |
| 104 | **CommsAgent** | Coordinates external messaging, disclosure, and public-response posture | Crisis communication guides, disclosure standards, PR playbooks | Message consistency, disclosure completeness, escalation quality | Produces faster aligned responses than fragmented stakeholder messaging | MarketingAgent, CommunityAgent, LegalAgent, BrandAgent | Disclosure gaps, inconsistent external messaging, weak response framing | Comms calendars, approval workflows, response templates | ReAct with approval chains |
| 105 | **ArchiveProducerAgent** | Packages archival materials and source assets for reuse-heavy or documentary workflows | Archive production notes, source curation practices, provenance preservation standards | Source package completeness, rights coverage, provenance preservation | Assembles reusable archival packages more cleanly than manual gather-and-sort workflows | ArchiveResearchAgent, JournalistAgent, LegalAgent | Missing archival context, weak source packaging, rights gaps | Archive asset managers, metadata systems, provenance logs | ReAct over archival manifests |
| 106 | **StandardsEditorAgent** | Enforces editorial standards, sourcing discipline, and corrections policy | Newsroom standards manuals, corrections policies, attribution standards | Standards-compliance rate, attribution accuracy, corrections readiness | Reduces standards drift better than late-stage copy edits | JournalistAgent, FactCheckerAgent, CorrectionsAgent, LegalAgent | Weak attribution, standards violations, correction policy gaps | Editorial checklists, attribution validators, standards DB | Constitutional AI with editorial standards constitution |
| 107 | **EthicsAgent** | Reviews ethical risk, disclosure sufficiency, fairness, and social impact | Ethics frameworks, synthetic-media disclosure guidance, fairness audits | Ethical issue recall, mitigation clarity, escalation precision | Surfaces release risks earlier than reactive ethics review | StandardsEditorAgent, ComplianceAgent (Legal), TrustSafetyAgent, SafetyRedTeamAgent | Disclosure insufficiency, fairness concerns, sensitive-content risk | Ethics review templates, risk matrices, disclosure checklists | Multi-agent debate + constitutional review |
| 108 | **ChannelManagerAgent** | Manages episodic or platform channel operations for cadence and metadata readiness | Channel publishing playbooks, metadata standards, scheduling ops | Publishing readiness, cadence stability, metadata completeness | Improves publishing discipline over manual channel operations | SocialMediaStrategistAgent, SEOAgent, AnalystAgent, MarketingAgent | Release readiness gaps, metadata omissions, schedule slippage | CMS/channel dashboards, scheduler tools, metadata validators | ReAct with publishing runbooks |
| 109 | **CorrectionsAgent** | Coordinates post-publication fixes and correction disclosures | Corrections workflows, retraction and update policies, version tracking | Correction turnaround, version replacement accuracy, notice completeness | Resolves post-release issues faster than unstructured incident handling | StandardsEditorAgent, FactCheckerAgent, ChannelManagerAgent | Unclosed correction loops, incomplete notices, stale versions | Version-control systems, publishing tools, correction trackers | ReAct over correction and replacement workflows |
| 110 | **MPAAgent** | Prepares rating-related packaging and release-readiness inputs for feature workflows | Rating submission references, content advisories, theatrical packaging rules | Rating-package completeness, advisory clarity, escalation quality | Prepares cleaner feature-release classification packages than manual prep | ProducerAgent / EP, LegalAgent, EthicsAgent | Missing advisories, incomplete rating prep, unclear classification support | Submission packages, advisory templates, classification checklists | Human-in-the-loop with structured packaging support |
| 111 | **SalesAgent** | Handles buyer-facing sales packaging for distributors and outlets | Rights windowing playbooks, market package examples, buyer materials | Buyer-package completeness, rights clarity, market-fit packaging | Produces sales-ready release packets faster than manual assembly | ProducerAgent / EP, DistributorAgent, MarketingAgent | Missing buyer info, weak positioning, incomplete rights summaries | Rights systems, package builders, buyer CRM | ReAct over buyer package requirements |
| 112 | **DistributorAgent** | Manages downstream delivery to buyers, platforms, and territories | Distribution specs, outlet requirements, package handoff workflows | Outlet-spec compliance, handoff completeness, territorial routing accuracy | Reduces delivery-spec mismatches relative to fragmented delivery ops | SalesAgent, ArchiveMasterAgent, SoundMixerAgent, ColoristAgent | Spec mismatches, incomplete outlet packages, routing errors | Delivery management systems, outlet spec DB, packaging validators | ReAct over distribution specification matrices |
| 113 | **AwardsStrategistAgent** | Plans awards submissions and campaign timing | Awards calendars, campaign playbooks, category positioning histories | Submission readiness, category fit, timeline precision | Improves awards-timing discipline over generic release planning | ProducerAgent / EP, CriticAgent, MarketingAgent | Weak campaign timing, poor category fit, incomplete submission assets | Awards calendars, campaign trackers, submission checklists | ReAct with awards timeline optimization |
| 114 | **ArchiveMasterAgent** | Produces archive-grade masters and preservation packages | Preservation standards, checksum workflows, archive metadata practice | Checksum integrity, preservation metadata completeness, archive package validity | Delivers more reliable archive packages than late-stage export-only workflows | DistributorAgent, ColoristAgent, SoundMixerAgent, GateKeeperAgent | Incomplete preservation bundles, archive-spec violations, metadata gaps | Archive mastering tools, checksum utilities, preservation metadata systems | Tool-use / ReAct with preservation validation |

---


## Responsibility

Performs final legal review for novel or high-risk publication issues

## Knowledge distillation sources

Media law references, clearance workflows, defamation/IP/privacy cases

## Self-quality criteria

Issue identification recall, sign-off completeness, escalation quality

## Surpass-human signal

Reduces late-stage legal surprises relative to fragmented legal review

## Critique bus

- **Accepts critique from:** ComplianceAgent (Legal), JournalistAgent, ProducerAgent / EP, MPAAgent

- **Comments on:** Novel legal risks, unclear rights, unresolved high-risk claims

## Tools (design-time documentation)

Legal memo systems, rights trackers, clearance databases

**Runtime safety:** Host allow-lists are only `agent_spec.json` + `tool-permission-register.json`. CI uses video_* stubs. Do not treat design-time vendor names as enabled APIs.

## Architecture pattern

Human-in-the-loop escalation + constitutional review

## Common structure of an AI agent (full §11 from agents.md)

## 11. Common Structure of an AI Agent

Every agent — regardless of category — implements this skeleton. Derived from the source document's architecture patterns (§1), critique protocol (§6), and universal success-criteria framework (§5), enriched with current (2026) tooling research.

### 11.1 Architecture Diagram

The diagram below presents the common agent as a professional operating architecture rather than a simple component sketch. It shows how **orchestration**, the **input contract**, **knowledge and tool surfaces**, the internal **plan → act → self-review** loop, **traceability and provenance controls**, the **3-layer quality gate** (Spec → Rubric → Preference), **release packaging**, **peer critique**, **human escalation**, and **continuous improvement** work together as one governed system.

![Professional common AI agent architecture diagram](./common-agent-structure.svg)

> **Tip:** view the diagram fullscreen on GitHub by clicking it, or download [`common-agent-structure.svg`](./common-agent-structure.svg) directly. The SVG is designed as a presentation-grade reference for architecture reviews and implementation planning.

### 11.2 Component Reference Table

| # | Component | Purpose | Mechanism / Implementation Notes |
|---|---|---|---|
| 1 | **Identity** | Stable unique handle for routing, logging, provenance | Kebab-case ID + semantic version (e.g. `director-agent@2.1.0`). Registered in the agent-capability registry used by RouterAgent. |
| 2 | **Responsibility (Scope)** | Single-sentence definition of what the agent owns | Mirrors a human craft role. Prevents scope overlap via explicit boundary documented in the registry. |
| 3 | **Knowledge Distillation Source** | Licensed/consented corpora the agent is trained or RAG-grounded on | Award archives, academic papers, expert interviews, peer-reviewed journals. Refreshed via Continuous Distillation Loop (§7 of source). |
| 4 | **Tool Access** | External APIs, generators, validators, DCC bridges | Video gen: Sora 2, Veo 3.1 (Gemini API), Runway Gen-4/Aleph, Kling 3.0. Voice: ElevenLabs v3, Sync.so, HeyGen. DCC: Resolve/Nuke/AE via MCP bridges. All accessed via MCP (Model Context Protocol, Anthropic 2024). |
| 5 | **Architecture Pattern** | Reasoning/learning loop powering the agent | One or more of: Self-Refine [1], Reflexion [2], RLAIF/Constitutional AI [3], Multi-agent debate [4], LLM-as-Judge [5], Pairwise preference (Arena) [5], ReAct [6], Agentic Graph (LangGraph/CrewAI/AutoGen) [7], DSPy/OPRO prompt optimization [8]. |
| 6 | **Memory** | Episodic + long-term project memory | Vector DB (Pinecone/Weaviate/Qdrant) accessed via MemoryAgent. Implements MemGPT-style hierarchical memory with summarization and eviction. Reflexion agents store verbal self-feedback here. |
| 7 | **Constitution / Rubric** | Written, role-specific scoring guide for self-check | Examples: Murch's Rule of Six (Editor), 12 Principles (Animator), Save-the-Cat beats (Screenwriter), WCAG 2.2 (Accessibility), FAA Part 107 (Drone), SAG-AFTRA AI rider (Consent). Used as the "constitution" in Constitutional AI pattern. |
| 8 | **Self-Quality: L1 Spec** | Did the output meet the structured brief? | JSON schema validation + tool validators (codec, LUFS, aspect ratio, frame count, file format). Must pass 100%. |
| 9 | **Self-Quality: L2 Rubric** | Does it meet craft rubric for this role? | LLM-as-Judge (Zheng 2023) with role-specific constitution. Must score ≥85/100. Up to 3 Self-Refine iterations if below threshold. |
| 10 | **Self-Quality: L3 Preference** | Would target audience choose this over human baseline? | Pairwise comparison: AudienceSim panel (≥200 simulated personas + ≥20 HiTL samples). Win rate ≥50% (parity) or ≥55% (surpass). |
| 11 | **Surpass-Human Signal** | Pre-registered proof the agent exceeds a credentialed professional | Benchmark dominance; blind Arena preference ≥55%; speed × quality (equal L2 at ≤10% turnaround); lower 90-day defect rate; certification pass; higher novelty at equal quality. |
| 12 | **Critique Inbox** | Channel for receiving structured feedback from peers | Shared `CritiqueMessage` JSON bus. Severities: blocker (halts DAG), major (Self-Refine ≤3 iters), minor/nit (logged for RLAIF). Disputes → JudgeAgent multi-agent debate → HiTL if unresolved. |
| 13 | **Critique Outbox** | Peer agents whose work this agent is qualified to review | Defined per-agent in roster. Messages emitted on same bus. Evidence-backed, rubric-referenced, appended to C2PA provenance. |
| 14 | **HiTL Escalation** | When a human must be brought in | Consent (SAG-AFTRA AI rider, EU AI Act Art. 50); final legal sign-off; MPA rating; festival eligibility; crisis comms; cross-cultural sensitivity. |
| 15 | **Provenance (C2PA)** | Cryptographic signing of every artifact | Every emitted artifact signed with C2PA (c2patool). Downstream agents verify chain. Accepted critiques appended to manifest. Platforms (YouTube, TikTok, Meta) auto-label based on C2PA presence. |
| 16 | **Continuous Learning** | How the agent keeps improving post-deployment | Bootstrap (licensed corpora) → Expert interviews (paid, consented) → Live RLAIF (DPO/KTO) → Award-rubric grounding → Adversarial red-team → 30/60/90-day reality check (retention, ROAS, awards). |
| 17 | **Orchestration Integration** | How the agent fits the multi-agent graph | Registered as a node in LangGraph/CrewAI/AutoGen DAG. OrchestratorAgent schedules; PlannerAgent assigns; RouterAgent selects model/provider; GateKeeperAgent verifies L1-L3 before advancing. |

### CritiqueMessage Schema (Universal)

```json
{
  "critique_id": "uuid",
  "from_agent": "EditorAgent",
  "to_agent": "DirectorAgent",
  "artifact_ref": "shot_42_take_3.mp4",
  "severity": "blocker | major | minor | nit",
  "category": "pacing | continuity | accuracy | compliance | accessibility | brand | craft",
  "evidence": ["timecode 00:01:14 — held 1.4s past cut point per genre prior"],
  "suggested_action": "trim 1.0s; re-evaluate hold",
  "rubric_reference": "Murch Rule of Six §3",
  "must_resolve_before": "phase_4_review"
}
```

### Composition Diagram

```text
[Brief] ──► PlannerAgent ──► OrchestratorAgent ──► RouterAgent ──► (52 craft agents §1–§8)
                 ▲                  │                                       │
                 │                  ▼                                       ▼
             MemoryAgent      GateKeeperAgent ◄─── JudgeAgent ◄──── CritiqueMessages
                                    ▲                                       ▲
                                    │                                       │
            [Creative meta:] IdeationAgent · NarrativeArcAgent · StyleTransferAgent · MoodBoardAgent · NoveltyAgent · EmotionalArcAgent
            [Research meta:] WebResearchAgent · ArchiveResearchAgent · TrendIntelAgent · CompetitorIntelAgent · CitationAgent · InterviewSynthAgent · BenchmarkResearchAgent
            [Optimization meta:] PromptOptimizerAgent · CostOptimizer · LatencyOptimizer · RetentionOptimizer · ROASOptimizer · AccessibilityOptimizer · EvalHarnessAgent · SafetyRedTeamAgent
```

---

## Shared references (from agents.md §12)

## 12. References

### Foundational Papers (Architecture Patterns)

| Ref | Paper | Key Contribution | Link |
|---|---|---|---|
| [1] | Madaan et al., "Self-Refine: Iterative Refinement with Self-Feedback," NeurIPS 2023 | Agent drafts → self-critiques against rubric → revises iteratively without weight updates | [arXiv:2303.17651](https://arxiv.org/abs/2303.17651) |
| [2] | Shinn et al., "Reflexion: Language Agents with Verbal Reinforcement Learning," NeurIPS 2023 | Verbal self-reflection stored in episodic memory buffer to improve decisions in subsequent trials | [arXiv:2303.11366](https://arxiv.org/abs/2303.11366) |
| [3] | Bai et al., "Constitutional AI: Harmlessness from AI Feedback," 2022 | Reward signal from AI critic governed by a written constitution; RLAIF without human labels | [arXiv:2212.08073](https://arxiv.org/abs/2212.08073) |
| [4] | Du et al., "Improving Factuality and Reasoning in Language Models through Multiagent Debate," 2023 | Multiple LLM agents debate; improves factuality and reasoning across tasks | [arXiv:2305.14325](https://arxiv.org/abs/2305.14325) |
| [5] | Zheng et al., "Judging LLM-as-a-Judge with MT-Bench and Chatbot Arena," NeurIPS 2023 | GPT-4 judge achieves >80% agreement with human preferences; scalable evaluation | [arXiv:2306.05685](https://arxiv.org/abs/2306.05685) |
| [6] | Yao et al., "ReAct: Synergizing Reasoning and Acting in Language Models," ICLR 2023 | Interleaving reasoning traces with tool-use actions for grounded decision-making | [arXiv:2210.03629](https://arxiv.org/abs/2210.03629) |
| [7] | LangGraph / CrewAI / AutoGen (2024–2026) | Agentic graph orchestration: DAG with state, handoffs, review gates, human-in-the-loop | [LangGraph](https://github.com/langchain-ai/langgraph), [CrewAI](https://github.com/crewAIInc/crewAI), [AutoGen](https://github.com/microsoft/autogen) |
| [8] | Yang et al., "Large Language Models as Optimizers" (OPRO), 2023; Khattab et al., DSPy (Stanford, 2023–2026) | Meta-optimization of prompts using LLMs; DSPy compiles declarative LM programs into optimized pipelines | [OPRO arXiv:2309.03409](https://arxiv.org/abs/2309.03409), [DSPy](https://github.com/stanfordnlp/dspy) |

### Evaluation Benchmarks

| Benchmark | Scope | Link |
|---|---|---|
| VBench / VBench 2.0 | Video generation quality — 16 dimensions (temporal + frame-wise); VBench 2.0 adds Human Fidelity, Creativity, Physics | [arXiv:2311.17982](https://arxiv.org/abs/2311.17982), [VBench 2.0: arXiv:2503.21755](https://arxiv.org/abs/2503.21755) |
| EvalCrafter | Text-to-video — 18 metrics across visual, content, motion quality | [arXiv:2310.11440](https://arxiv.org/abs/2310.11440) |
| MT-Bench / Chatbot Arena | LLM output quality via pairwise human + LLM-judge evaluation | [arXiv:2306.05685](https://arxiv.org/abs/2306.05685) |

### Generative Video Models (Tool Access — 2026 landscape)

| Model | Provider | Key Capabilities | Access |
|---|---|---|---|
| Sora 2 / Sora 2 Pro | OpenAI | Synchronized dialogue + SFX + background audio; cinematic/realistic/anime styles; 1080p 20s | [OpenAI Videos API](https://developers.openai.com/api/docs/models/sora-2) (discontinuing Sept 2026) |
| Veo 3.1 | Google DeepMind | 4K / 1080p / 720p, 8s; native audio; configurable 16:9 & 9:16; multi-image reference for character/object direction | [Gemini API](https://ai.google.dev/gemini-api/docs/video) / [Vertex AI](https://docs.cloud.google.com/vertex-ai/generative-ai/docs/models/veo/3-1-generate) |
| Runway Gen-4 / Gen-4.5 / Aleph | Runway | ControlNet guides, camera paths, style-lock, Layout Sketch; Aleph for video-to-video editing | [Runway API](https://docs.dev.runwayml.com/) |
| Kling 3.0 | Kuaishou | Cinematic motion realism; physics accuracy; motion-control (reference video); native audio | [Kling API (fal.ai)](https://fal.ai/models/fal-ai/kling-video) |

### Voice & Avatar Tools (2026)

| Tool | Provider | Capabilities |
|---|---|---|
| ElevenLabs v3 | ElevenLabs | Expressive TTS; instant/professional voice cloning; dialogue mode (multi-speaker); Projects API for long-form; Sound FX generation | [Docs](https://elevenlabs.io/docs) |
| HeyGen Avatar IV | HeyGen | Photoreal AI avatars; 175+ languages lip-sync; ElevenLabs integration; personalization API | [HeyGen](https://www.heygen.com) |
| Synthesia | Synthesia | Enterprise AI avatars at scale; SCORM-compatible; brand-controlled | [Synthesia](https://www.synthesia.io) |
| Sync.so / Wav2Lip | Open-source + API | Lip-sync overlays; phoneme-viseme alignment | [Sync.so](https://sync.so) |

### Infrastructure Standards

| Standard | Purpose | Status (2026) |
|---|---|---|
| C2PA (Content Provenance) | Cryptographic manifest signing for every AI-generated artifact; platforms (YouTube, TikTok, Meta) auto-label | EU AI Act Code of Practice (March 2026) mandates C2PA + watermarking combined. Over 2,300 tools support. [contentauthenticity.org](https://contentauthenticity.org/blog/the-state-of-content-authenticity-in-2026) |
| MCP (Model Context Protocol) | Open standard for LLM ↔ tool integration; 2,300+ public servers; adopted by Claude, VS Code, Cursor, etc. | Donated to Agentic AI Foundation (Linux Foundation, Dec 2025) by Anthropic + OpenAI + Block. [modelcontextprotocol.io](https://modelcontextprotocol.io) |
| DSPy | Framework for programming (not prompting) LLMs; compiles declarative pipelines into optimized prompts/finetunes | Stanford-maintained; MIPRO optimizer; used by PromptOptimizerAgent for automated prompt improvement. [github.com/stanfordnlp/dspy](https://github.com/stanfordnlp/dspy) |

---

*Generated: May 2026. Source: [`ai_agent_video_production_workflow.md`](./ai_agent_video_production_workflow.md). Core layout restored from `agents_old.md`; missing workflow-support content merged into the same table-driven structure.*

## Additional corpus / va passages naming this agent


### From `corpus/study/SYSTEM_REFERENCE.md` Copy: `sources/excerpts/SYSTEM_REFERENCE.md`.


| # | Agent | Role | Deep Specification |
|---|-------|------|--------------------|
| 32 | InstructionalDesignAgent | Learning objectives → content | — |
| 33 | SMEAgent | Domain accuracy | — |
| 34 | FactCheckerAgent | Source-grade every claim | — |
| 35 | MedicalIllustratorAgent | Anatomy & procedure visuals | — |
| 36 | JournalistAgent | Reporting + ethics | — |
| 37 | ComplianceAgent (Legal) | FTC, HIPAA, GDPR, IP clearance | — |
| 38 | FinanceAgent | Market/earnings accuracy | — |
| 39 | FoodStylistAgent | Camera-ready food | — |
| 40 | TravelCineAgent | Destination cinematography | — |
| 41 | ChildrensAuthorAgent | Age-appropriate content | — |
| 42 | AudiobookNarratorAgent | Sustained narration | — |
| 43 | SignLanguageInterpreterAgent | ASL/BSL interpretation | — |
| 44 | LocalizationQAAgent | Translation + cultural fit | — |
| 45 | RealEstatePhotoAgent | Interiors, 3D scans | — |



### From `corpus/study/ai_agent_video_production_workflow.md` Copy: `sources/excerpts/ai_agent_video_production_workflow.md`.


| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From / How | Comments On (Critiques) |
|---|-------|----------------|-------------------------------|-----------------------|----------------------|-----------------------------|--------------------------|
| 1 | **DirectorAgent** | Owns vision; issues shot intents, sets pacing, approves takes | Criterion commentary tracks; IMDb Top 250 director interviews; DGA seminars; MasterClass corpora (Scorsese/Lynch/Gerwig) | Shot-intent fidelity (CLIP-T ≥0.32); story-beat coverage 100%; pacing curve matches genre prior | Wins ≥55% blind pairwise vs DGA director's cuts of same screenplay (Arena protocol) | ScreenwriterAgent (story beats), EditorAgent (pacing), Audience-Sim Agent (test screenings) — via structured JSON critique bus | EditorAgent, DoPAgent, ScreenwriterAgent, ComposerAgent — issues "creative-intent diff" |
| 2 | **ProducerAgent / EP** | Budget, schedule, hiring, delivery; greenlights phase gates | PGA Producers Mark guidelines; Variety/Deadline budget leaks; LineProducer Excel corpora | On-time delivery rate; budget variance <±5%; talent satisfaction (RLHF score) | Beats PGA-credited producer schedules at 0.6× cost with equal CSAT | All downstream agents (escalations); HumanInTheLoop gate for final greenlight | DirectorAgent (scope creep), AllAgents (resource burn) |
| 3 | **ScreenwriterAgent** | Treatment → screenplay; dialogue; structure | Black List scripts; WGA library; McKee *Story*; Truby *Anatomy of Story*; transcribed Charlie Kaufman / Sorkin interviews | Save-the-Cat beat sheet pass; dialogue distinctiveness (per-character embedding distance ≥τ); rewrite delta from notes | Wins ≥50% blind read vs Black List Top-10 scripts (WGA judge panel emulated) | DirectorAgent, DramaturgAgent, StoryEditorAgent — Reflexion loop on notes | DirectorAgent (logline clarity), DialogueAgent, ConsistencyAgent |
| 4 | **ShowrunnerAgent** | Cross-episode arc, writers'-room orchestration | WGA showrunner training; Sopranos/Breaking Bad room transcripts; Mike Schur teaching material | Arc continuity score across episodes; character-thread completion; tonal variance within bounds | Series Bible coverage ≥99% across 10 eps without drift (vs ~95% human baseline) | Network-Notes Agent, AudienceSim, Multi-agent debate w/ ScreenwriterAgent | ScreenwriterAgent (arc), CastingAgent, DirectorAgent (episode tone) |
| 5 | **CastingAgent** | Voice + likeness selection and audition simulation | CSA Artios archive; SAG-AFTRA AI rider; voice-actor corpora (consented) | Character-voice fit (audience preference); SAG-AFTRA AI consent compliance 100% | Beats CSA casting in blind audience preference for fit; faster turnaround (hours vs weeks) | DirectorAgent, ShowrunnerAgent, Legal/ConsentAgent | VoiceCloneAgent (likeness), AvatarDesignAgent |

| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From / How | Comments On (Critiques) |
|---|-------|----------------|-------------------------------|-----------------------|----------------------|-----------------------------|--------------------------|
| 32 | **InstructionalDesignAgent** | Learning objectives → script → assessment | ATD body of knowledge; Cathy Moore *Action Mapping*; Julie Dirksen *Design for How People Learn* | Bloom-level mapping; predicted completion ≥70%; Kirkpatrick L2 quiz ≥80% | Beats ATD-credentialed ID on learner retention RCT | SMEAgent, AccessibilityAgent | ScriptwriterAgent (no objective), AnimatorAgent (over-decoration) |
| 33 | **SMEAgent (Subject-Matter Expert)** | Domain accuracy in target field | Peer-reviewed journals; certified curricula (CFA, USMLE, AWS, etc.); consented expert-interview corpora | Citation density; benchmark exam pass (USMLE, CFA L3, etc.); hallucination rate ≤0.5% | Passes the same certification exam as the human pro at ≥pass threshold | FactCheckerAgent, peer SMEAgents (debate) | ScriptwriterAgent (inaccuracy), MotionGraphicsAgent (mis-labeled diagrams) |
| 34 | **FactCheckerAgent** | Source-grade every claim | New Yorker fact-check handbook; IFCN verified-signatories; Snopes/PolitiFact records | Source-grade per claim (primary > secondary); cross-source agreement ≥2 | Lower published-correction rate than Pulitzer-tier outlets | SMEAgent, StandardsEditorAgent | ScriptwriterAgent (unsourced), JournalistAgent |
| 35 | **MedicalIllustratorAgent** | Anatomy & procedure visuals | Netter atlas; AMI/CMI curriculum; Anatomage references | Anatomical accuracy (anatomy-detection model); AMI rubric score | CMI-certified peers vote ≥pass in blind review | SMEAgent (physician), AccessibilityAgent | AnimatorAgent (wrong anatomy), CopywriterAgent (mis-term) |
| 36 | **JournalistAgent** | Reporting + ethical framing | Pulitzer/duPont/Peabody winners; SPJ Code of Ethics; Poynter material | Source diversity; on-record ratio; ethical-checklist pass | Lower correction rate + faster file vs newsroom reporter | FactCheckerAgent, LegalAgent, StandardsEditorAgent | FactCheckerAgent, ScriptwriterAgent |
| 37 | **ComplianceAgent (Legal)** | FTC, HIPAA, GDPR, IP, AI-likeness clearance | Bar CLE corpora; FTC endorsement guides; EU AI Act; GDPR/CCPA; SAG-AFTRA AI rider | 100% rule-coverage on checklist; zero post-publish takedowns | Lower legal-risk score than median media-counsel review | All agents (must clear gate); HumanLawyerAgent for novel issues | All agents (blocking gate) |
| 38 | **FinanceAgent** | Accurate market / earnings / token facts | CFA Institute curriculum; SEC marketing rule; Bloomberg/Refinitiv data feeds | Numerical accuracy 100%; SEC marketing-rule compliance | Passes CFA L3 simulated; lower retraction rate than analyst desks | SMEAgent (econ), ComplianceAgent | ScriptwriterAgent (number drift), MotionGraphicsAgent (chart mis-scale) |
| 39 | **FoodStylistAgent** | Camera-ready food, recipe authenticity | James Beard Media Award archives; Susan Spungen techniques; IACP corpora | Visual appetite-appeal (aesthetic regressor); recipe-step accuracy | Wins blind preference vs editorial food stylist on still + motion | DoPAgent (lighting), DirectorAgent | ScriptwriterAgent (impossible recipe) |
| 40 | **TravelCineAgent** | Destination cinematography | Brandon Li / Chris Burkard reels; NatGeo style guide; Banff Film Fest selections | Establishing-shot diversity; location-mood match | Wins T+L blind preference at 0.1× sortie cost | DirectorAgent, DronePilotAgent | DronePilotAgent (no-fly zone) |
| 41 | **ChildrensAuthorAgent** | Age-appropriate story + safety | Caldecott/Geisel winners; Mo Willems / Julia Donaldson public works; ECE literature | Lexile band match; Common-Sense-Media safety pass; rhyme/meter score | Beats Caldecott-rubric predicted score vs entry pool | ChildSafetyAgent, ParentSimAgent | AnimatorAgent (scary), VOAgent (wrong age-tone) |
| 42 | **AudiobookNarratorAgent** | Sustained character + narration | Audie Award archives; AudioFile Earphones; consented narrator corpora | Vocal stamina (no drift over 60min); character distinction (embedding distance) | Wins AudioFile blind eval at fraction of studio time | DirectorAgent, AuthorAgent | VOArtistAgent (over-acting) |
| 43 | **SignLanguageInterpreterAgent** | Accurate ASL/BSL interpretation | RID NIC curricula; NAD-endorsed corpora; Deaf-community consented sign data | Sign accuracy (Deaf-reviewer vote); facial-grammar markers | Wins blind NAD-reviewer preference at scale | DeafCommunityReviewAgent (HiTL), LinguistAgent | VoiceCloneAgent (no caption), AccessibilityAgent |
| 44 | **LocalizationQAAgent (Linguist)** | Translation + cultural fit | LISA QA model; MQM error typology; ATA cert prep | MQM error rate per 1k words; cultural-flag count | Beats LSP human QA on MQM error rate at 10× speed | NativeReviewerAgent, BrandAgent | VoiceCloneAgent (wrong pronunciation), DubbingAgent |
| 45 | **RealEstatePhotoAgent / 3D Scan Op** | Wide interiors; Matterport scans | Mike Kelley architectural-photo tutorials; APALA refs | Vertical-line straightness; HDR exposure stack; coverage % | Listing-CTR uplift vs human-shot baseline | DoPAgent, DronePilotAgent | DronePilotAgent (illegal altitude) |

| Phase | Primary outputs | Mandatory gates |
|---|---|---|
| **Greenlight** | Approved brief, KPI targets, budget envelope, rights-risk register, scale profile | ProducerAgent, FinanceAgent, ComplianceAgent, PlannerAgent |
| **Pre-production packet** | Script lock, storyboard/lookbook, asset IDs, character/world bibles, consent state, continuity baselines | DirectorAgent, ScreenwriterAgent, Asset/Data Backbone, Continuity checks |
| **Production packet** | Shot prompts, camera plans, performance refs, plates, generated takes, render telemetry | PromptEngineerAgent / GeneratorOperator, CinematographerAgent, AIQAConsistencyAgent |
| **Post master** | Timelines, graded masters, stems, captions/subtitles, QC reports, outlet variants | EditorAgent, ColoristAgent, SoundMixerAgent, Accessibility checks |
| **Review and release pack** | AudienceSim results, legal review, provenance bundle, sign-off log, unresolved-risk list | ComplianceAgent, JudgeAgent, HumanInTheLoop when required |
| **Distribution package** | DCP, streaming mezzanine, broadcast master, archive package, trailer/social cutdowns, metadata bundle | Delivery-spec validation, accessibility validation, territorial rights validation |
| **Post-launch learning set** | Performance telemetry, corrections, defect log, benchmark deltas, retraining tickets | AnalystAgent, EvaluationHarnessAgent, PromptOptimizerAgent, model-improvement loop |

| Phase | Lead Agent | Critic Agents |
|---|---|---|
| Concept | PerformanceMarketerAgent + CopywriterAgent | BrandAgent |
| Production | UGCCreatorAgent | DirectorAgent |
| Post | EditorAgent + MotionGraphicsAgent | BrandAgent |
| Review | ComplianceAgent (FTC/IP) | LegalAgent |
| Distribution | PerformanceMarketerAgent | FinanceAgent (budget) |
| Post-launch | PerformanceMarketerAgent + AnalystAgent | AudienceSimAgent |

| Phase | Lead Agent | Critic Agents |
|---|---|---|
| Concept | DirectorAgent + ScreenwriterAgent + StoryboardAgent + ConceptArtistAgent | ShowrunnerAgent |
| Production | PromptEngineerAgent / GeneratorOperator + VoiceCloneAgent + ComposerAgent | AIQAConsistencyAgent + LipSyncAgent |
| Post | EditorAgent + ColoristAgent + VFXSupervisorAgent | DirectorAgent |
| Review | DirectorAgent + LegalAgent (C2PA) | AvatarDesignAgent (consent) |
| Distribution | ProducerAgent + FestivalStrategistAgent | ComplianceAgent |
| Post-launch | DirectorAgent + AudienceSimAgent | CriticAgent (festival jury sim) |

| Phase | Lead Agent | Critic Agents |
|---|---|---|
| Concept | InstructionalDesignAgent + ComplianceAgent + ScreenwriterAgent | SMEAgent |
| Production | AvatarDesignAgent + MotionGraphicsAgent | DirectorAgent |
| Post | EditorAgent + AccessibilityAgent | AccessibilityOptimizerAgent |
| Review | SMEAgent + ComplianceAgent + AccessibilityAgent | LegalAgent |
| Distribution | LMSAgent | AnalystAgent |
| Post-launch | AnalystAgent + InstructionalDesignAgent | LearnerSimAgent |

| Phase | Lead Agent | Critic Agents |
|---|---|---|
| Concept | MusicVideoDirectorAgent + ProducerAgent + ChoreographyAgent | LabelA&RAgent |
| Production | CinematographerAgent (DoP) + PromptEngineerAgent / GeneratorOperator + ContinuityAgent | VFXSupervisorAgent |
| Post | EditorAgent + ColoristAgent + SoundMixerAgent | DirectorAgent |
| Review | MusicSupervisorAgent + ComplianceAgent | LegalAgent (sample clearance) |
| Distribution | SocialMediaStrategistAgent | LabelDigitalAgent |
| Post-launch | AnalystAgent | AudienceSimAgent |

| Phase | Lead Agent | Critic Agents |
|---|---|---|
| Concept | ShowrunnerAgent + JournalistAgent + ScreenwriterAgent | FactCheckerAgent |
| Production | DirectorAgent + CinematographerAgent (DoP) + ArchiveProducerAgent + MotionGraphicsAgent + FactCheckerAgent | LegalA
…



### From `corpus/study/human_video_production_workflow.md` Copy: `sources/excerpts/human_video_production_workflow.md`.


- **Above-the-line**: Director, Producer, Showrunner, Screenwriter / Scriptwriter, Lead Cast / Talent
- **Camera & lighting**: Cinematographer (DoP), Camera Operator, Gaffer, Grip, Drone Pilot
- **Sound**: Sound Designer, Boom Operator, Production Mixer, Foley Artist, Composer, Voice-Over Artist
- **Art & design**: Production Designer, Art Director, Set Decorator, Costume Designer, Makeup / Hair Artist, Storyboard Artist, Concept Artist
- **Post-production**: Editor, Colorist, VFX Supervisor, Motion Graphics Designer, 2D / 3D Animator, Compositor, Sound Editor, Re-recording Mixer
- **AI-era specialists**: Prompt Engineer, AI Video Generator Operator, AI Voice / Lip-Sync Specialist, AI Avatar Designer, Model Fine-Tuner, AI QA / Consistency Reviewer
- **Distribution & strategy**: Producer / EP, Social Media Strategist, Copywriter, SEO/ASO Specialist, Community Manager, Localization / Subtitle Editor, Legal / Clearance, Brand / Marketing Manager

| # | Sample Production | Typical Duration | Best Channel | Crew / Roles Required |
|---|-------------------|------------------|--------------|----------------------|
| 1 | Product showcase / demo videos | 15–60s | Social ads, e-comm | Director, DoP, Product Stylist, Editor, Motion GFX, Copywriter, Brand Manager |
| 2 | Brand story / explainer ads | 30–90s | YouTube, web | Creative Director, Scriptwriter, Director, DoP, Editor, Composer, VO Artist |
| 3 | UGC-style ads | 15–45s | TikTok, Meta ads | UGC Creator, Brief Writer, Editor, Performance-Ads Strategist, Legal Clearance |
| 4 | Before & After transformations | 10–30s | Reels, TikTok | Director, DoP, Talent, Editor, Colorist, Compliance Reviewer |
| 5 | AI-avatar testimonial videos | 30–60s | LinkedIn, landing pages | Scriptwriter, AI Avatar Designer, Voice Cloner / VO Artist, Lip-Sync Specialist, Editor |
| 6 | Carousel-to-video ads | 10–20s | Meta, LinkedIn | Designer, Motion Designer, Copywriter, Editor, Ad Strategist |
| 7 | E-commerce product videos | 10–30s | Shopify, Amazon | Product Photographer, Stylist, 3D Artist (turntable), Editor, Retoucher |
| 8 | Seasonal / holiday campaign spots | 15–60s | All paid social | Creative Director, Producer, Director, DoP, Art Dept, Editor, Composer, Media Buyer |
| 9 | Retargeting A/B ad variations | 6–15s | Meta, Google | Performance Marketer, Copywriter, Editor, Data Analyst |
| 10 | Influencer-style product unboxing | 30–60s | TikTok, Reels | Influencer, Brand Manager, Editor, Disclosure / Legal |
| 11 | Comparison / "vs competitor" videos | 30–60s | YouTube, web | Product Researcher, Scriptwriter, Presenter, Editor, Legal Reviewer |
| 12 | App-install promo videos | 15–30s | TikTok, Meta | UX Researcher, Scriptwriter, Motion Designer, Editor, ASO Specialist |
| 13 | Shoppable video ads | 15–30s | TikTok Shop, Reels | Director, Talent, Editor, E-comm Integrator, Product Tag Specialist |
| 14 | Pre-roll / mid-roll YouTube ads | 6–30s | YouTube | Creative Director, Scriptwriter, Director, Editor, Composer, Media Buyer |
| 15 | Founder-story authenticity videos | 60–120s | LinkedIn, web | Interviewer, DoP, Sound Recordist, Editor, Colorist, Brand Strategist |

| # | Sample Production | Typical Duration | Occasion | Crew / Roles Required |
|---|-------------------|------------------|----------|----------------------|
| 1 | Birthday / anniversary videos | 15–60s | Personal events | Template Designer, Editor, Personalization Engineer, Music Curator |
| 2 | Personalized motivation videos | 10–30s | Daily | Copywriter, VO Artist or AI Voice Operator, Editor, Personalization Engineer |
| 3 | Custom kids' story videos (name + characters) | 2–5 min | Bedtime, gifts | Children's Author, Illustrator, Animator, VO Artist, Personalization Engineer, Child-Safety Reviewer |
| 4 | Virtual greeting cards | 10–30s | Holidays | Designer, Motion Designer, Copywriter, Music Curator |
| 5 | AI messages from "celebrities" / characters | 15–45s | Fan gifts | Voice-Likeness Licensor, AI Voice Cloner, Lip-Sync Specialist, Editor, Legal / Rights Reviewer |
| 6 | Wedding invitations / save-the-dates | 30–60s | Weddings | Designer, Motion Designer, Photographer, Editor, Composer |
| 7 | Personalized customer thank-yous | 15–30s | Post-purchase | CRM Specialist, Copywriter, Editor, Personalization Engineer |
| 8 | Pet birthday / memorial videos | 30–60s | Pet milestones | Editor, Pet Photo Curator, Music Curator, Motion Designer |
| 9 | Custom workout / coaching pep talks | 30–90s | Fitness clients | Coach / Trainer, Scriptwriter, VO Artist, Editor |
| 10 | Personalized horoscope / forecast videos | 30–60s | Daily content | Astrologer / Content Writer, VO Artist, Motion Designer, Personalization Engineer |
| 11 | Graduation tribute videos | 60–120s | Graduations | Editor, Photo Curator, Music Curator, Motion Designer |
| 12 | Custom proposal / love-letter videos | 30–90s | Romantic | Scriptwriter, Editor, Music Curator, Motion Designer |
| 13 | Baby announcement videos | 15–45s | New parents | Designer, Motion Designer, Editor, Music Curator |
| 14 | Personalized apology / make-up videos | 15–30s | Personal | Copywriter, Editor, Music Curator |

| # | Sample Production | Typical Duration | Style | Crew / Roles Required |
|---|-------------------|------------------|-------|----------------------|
| 1 | Short cinematic films / micro-movies | 15–60s | Cinematic | Director, Screenwriter, DoP, Production Designer, Cast, Editor, Colorist, Composer, Sound Designer |
| 2 | AI-generated multi-scene short stories | 1–5 min | Narrative | Story Writer, Storyboard Artist, AI Generator Operator, Consistency Reviewer, Editor, Composer, VO Artist |
| 3 | Animated bedtime stories | 3–10 min | Kids | Author, Illustrator, Animator, Narrator, Composer, Child-Safety Reviewer, Editor |
| 4 | Music videos & lyric videos | 1–4 min | Music | Director, DoP, Choreographer, Editor, Colorist, VFX Artist, Typography / Lyric Designer |
| 5 | Concept trailers (movie-style) | 30–90s | Cinematic | Director, Editor, Composer, Trailer Sound Designer, VO Artist, Colorist, Motion GFX |
| 6 | Fan-fiction visualizations | 1–5 min | Fan content | Writer / Fan-Author, Storyboard Artist, AI Generator Op, Editor, Composer, IP / Legal Reviewer |
| 7 | Mythology / folklore retellings | 2–10 min | Cultural | Cultural Consultant, Scriptwriter, Illustrator, Animator, Narrator, Composer, Editor |
| 8 | Anthology series episodes | 5–15 min | Series | Showrunner, Writers' Room, Director, DoP, Cast, Editor, Colorist, Composer, VFX, Sound Mixer |
| 9 | Animated motion comics | 30–90s | Motion comic | Comic Artist, Letterer, Motion Designer, VO Cast, Sound Designer, Editor |
| 10 | Interactive choose-your-own-adventure clips | 1–3 min | Interactive | Branching Narrative Writer, Game Designer, Director, Editor, Developer (interactive layer), Composer |
| 11 | Horror / suspense short shorts | 30–90s | Genre | Director, DoP, SFX Makeup Artist, Sound Designer, Composer, Editor, Cast |
| 12 | Sci-fi worldbuilding vignettes | 30–120s | Genre | Concept Artist, Production Designer, VFX Supervisor, Director, Composer, Editor |
| 13 | Parody / spoof trailers | 60–120s | Comedy | Comedy Writer, Director, Editor, VO Artist, Composer, Cast |
| 14 | Animated poetry / spoken-word visuals | 60–180s | Artistic | Poet, Narrator, Illustrator / Motion Artist, Composer, Editor |

| # | Sample Production | Typical Duration | Use Case | Crew / Roles Required |
|---|-------------------|------------------|----------|----------------------|
| 1 | Corporate explainer videos | 60–120s | Web, sales | Brand Strategist, Scriptwriter, Storyboard Artist, Motion Designer, VO Artist, Editor |
| 2 | Real estate virtual tours | 1–5 min | Listings | Real-Estate Photographer, 3D Scan Operator (Matterport), Drone Pilot, Editor, Colorist |
| 3 | Training & onboarding videos | 2–10 min | HR, L&D | Instructional Designer, SME, Scriptwriter, Presenter / Avatar, Editor, LMS Specialist |
| 4 | Meeting summary / recap videos | 1–3 min | Internal comms | Note-Taker / AI Transcriber, Editor, Motion Designer, Copywriter |
| 5 | LinkedIn thought leadership videos | 30–90s | Personal branding | Ghostwriter, Personal Brand Coach, Camera Op, Editor, Captioner |
| 6 | Pitch deck videos | 2–5 min | Fundraising | Founder / Presenter, Pitch Coach, Designer, Motion GFX, Editor, VO Artist |
| 7 | Investor update videos | 2–5 min | Quarterly | CFO / IR Lead, Scriptwriter, Designer, Editor, Compliance Reviewer |
| 8 | Annual report / earnings highlight videos | 1–3 min | IR / shareholders | IR Manager, Data Designer, Motion Designer, VO Artist, Legal Reviewer |
| 9 | HR policy & compliance training | 3–10 min | Mandatory training | Compliance Officer, Legal Reviewer, Instructional Designer, Presenter, Editor, Accessibility Specialist |
| 10 | Sales enablement walkthroughs | 2–5 min | Sales teams | Product Marketer, SME, Screen-Recordist, Editor, VO Artist |
| 11 | Internal CEO announcement videos | 1–3 min | All-hands | CEO / Talent, Speech Writer, Teleprompter Op, DoP, Editor, Comms Manager |
| 12 | Conference / event recap reels | 60–120s | Marketing | Event Videographer, Editor, Music Curator, Copywriter |
| 13 | Case study videos | 90–180s | Sales, marketing | Customer-Story Producer, Interviewer, DoP, Editor, Colorist, Copywriter |
| 14 | Recruitment / employer-branding | 60–120s | Hiring | Employer Brand Lead, Director, DoP, Editor, Composer, Cast (employees) |
| 15 | Quarterly all-hands recap videos | 2–5 min | Internal | Internal Comms Lead, Editor, Motion Designer, Captioner |

| # | Niche | Sample Productions | Crew / Roles Required |
|---|-------|--------------------|----------------------|
| 1 | Gaming content | AI cutscenes, game trailers, NPC dialogue scenes, speedrun reels | Game Designer, Concept Artist, 3D Animator, VO Cast, Sound Designer, Composer, Trailer Editor |
| 2 | Fitness & wellness | Guided workouts, yoga flows, meditation visuals | Certified Trainer / Yoga Instructor, Scriptwriter, DoP, Editor, Composer, VO Artist |
| 3 | Food & recipe | Recipe walkthroughs, food cinemagraphs, restaurant promos | Chef / Food Stylist, Food Photographer, DoP, Editor, Recipe Writer, Colorist |
| 4 | Travel & tourism | Destination showcases, virtual travel diaries, hotel promos | Travel Producer, Drone Pilot, DoP, Editor, Colorist, Composer, Local Fixer |
| 5 | Fashion & beauty | Virtual try-on videos, lookbook reels, makeup tutorials | Fashion Stylist, MUA, Model, Photographer / DoP, Editor, Retoucher, AR / Try-On Engineer |
| 6 | News & journalism | AI news briefings, data-driven stories, explainer journalism | Journalist, Editor-in-Chief, Fact-Checker, Data Reporter, Motion Designer, VO / Anchor, Legal Reviewer |
| 7 | Religious / spiritual | Devotional videos, scripture animations, prayer clips | Theological Reviewer, Scriptwriter, Narrator, Animator, Composer, Editor |
| 8 | Sports | Highlight reels, play-breakdown animations, fantasy recaps | Sports Analyst, Editor, Motion GFX (telestrator), Color Commentator / VO, Statistician |
| 9 | Crypto / finance | Market recaps, token explainers, trading tutorials | Financial Analyst, Compliance Reviewer, Scriptwriter, Motion Designer, VO Artist, Legal Reviewer |
| 10 | Healthcare | Patient education, symptom explainers, procedure animations | Medical Doctor / SME, Medical Illustrator, Scriptwriter, 3D Animator, Compliance / HIPAA Reviewer, VO Artist |
| 11 | Legal | Plain-language law explainers, intake videos, compliance training | Attorney, Legal Writer, Compliance Officer, Motion Designer, VO Artist, Captioner |
| 12 | Nonprofit / advocacy | Fundraising stories, awareness clips, donor thank-yous | Story Producer, Director, DoP, Editor, Composer, Fundraising Strategist, Subject Consent Reviewer |
| 13 | Automotive | Car walk-arounds, dealership inventory, test-drive POVs | Automotive Photographer, Drone Pilot, Camera Op, Editor, Colorist, Copywriter |
| 14 | Pets & animals | Pet-care tutorials, breed spotlights, shelte
…



### From `corpus/study/lifes_quiet_redemption_agent_workflow.md` Copy: `sources/excerpts/lifes_quiet_redemption_agent_workflow.md`.


| # | Beat | Dur | Shot | Visual Description (model-facing) | Primary Creative Agent | Generation Agent + Engine | Audio Agents (旁白 / SFX / Music) | Continuity Control | QC Owner |
|---|---|---|---|---|---|---|---|---|---|
| 1 | Youth — study | 4–5s | 特写 / ECU | Student A bent over a paper map, pencil tracing borders, dust-lit window, hopeful focus | DirectorAgent + EmotionalArcAgent | PromptEngineerAgent → Veo 3.1 (slow push-in) | VO: warm narrator line 1 · SFX: pencil-on-paper, faint classroom | ContinuityAgent: A-young identity hash | AIQAConsistencyAgent |
| 2 | Youth — leaving home | 4–5s | 全景 / Wide | 18yo C with suitcase at doorway, morning light, looking back once | DirectorAgent + StoryboardAgent | PromptEngineerAgent → Kling 3.0 (static, wind) | VO line 2 · SFX: door, distant street · Music: piano enters | ContinuityAgent: C-young, wardrobe | AIQAConsistencyAgent |
| 3 | Youth — coding passion | 4–5s | 特写 / CU | Young coder B, red tired eyes, all-nighter glow, fingers pause then type with growing confidence | CinematographerAgent | PromptEngineerAgent → Veo 3.1 (handheld breath) | VO line 3 · SFX: mechanical keyboard (ASMR) · Music: build | ContinuityAgent: B-young, screen glow LUT | AIQAConsistencyAgent |
| 4 | Youth — first "Hello World" | 4s | 插入 / Insert | Monitor close-up: `Hello World` compiles; reflected smile in glasses | MotionGraphicsAgent (screen UI) | PromptEngineerAgent → Runway Gen-4 (locked screen) | VO line 4 · SFX: soft chime | ContinuityAgent: B-young eyeline match | AIQAConsistencyAgent + LegalAgent (no real logos) |
| 5 | Youth — graduation hope | 4–5s | 特写 / ECU | 22yo E in gown, tassel in breeze, gazing at glass towers, eyes shining | DirectorAgent + EmotionalArcAgent | PromptEngineerAgent → Veo 3.1 (very slow push to eyes) | VO line 5 · Music: gentle swell | ContinuityAgent: E-graduation hash | AIQAConsistencyAgent |
| 6 | Build — craft/labor | 4–5s | 中景 / Medium | Adult E as carpenter, sawdust in golden light, steady hands, quiet pride | ProductionDesignAgent | PromptEngineerAgent → Kling 3.0 (motion brush on hands) | VO line 6 · SFX: woodworking, leaves rustling | ContinuityAgent: E-adult aging pair | AIQAConsistencyAgent |
| 7 | Build — small business | 4–5s | 中景 / Medium | E's small shop, a cat on the counter, warm interior, customer leaving | DirectorAgent | PromptEngineerAgent → Veo 3.1 (gentle pan) | VO line 7 · SFX: shop bell, cat · recurring-motif cat | ContinuityAgent: cat motif, shop set | AIQAConsistencyAgent |
| 8 | Build — family life | 4–5s | 中景 / Medium | E now a mother, child at table, soft domestic light | CastingAgent + TalentAgent | PromptEngineerAgent → Kling 3.0 | VO line 8 · SFX: gentle chatter, child | ContinuityAgent: E-family hash | AIQAConsistencyAgent |
| 9 | Build — old shame (shoes) | 4s | 特写 / CU | F glancing at worn shoes, flush of shame softening to acceptance | EmotionalArcAgent | PromptEngineerAgent → Veo 3.1 (subtle rack focus) | VO line 9 · Music: minor turn | ContinuityAgent: F identity, footwear | AIQAConsistencyAgent |
| 10 | Accept — family dinner | 5s | 全景 / Wide | Warm family dinner, steam off soup, laughter, golden hanging lamp | DirectorAgent + ColoristAgent (look) | PromptEngineerAgent → Veo 3.1 (slow dolly in) | VO line 10 · SFX: ladle, family chatter, giggle · Music: warm | ContinuityAgent: ensemble continuity | AIQAConsistencyAgent |
| 11 | Accept — self-care | 4–5s | 特写 / CU | J applying lipstick in mirror, soft genuine smile reaching the eyes | MUAAgent | PromptEngineerAgent → Kling 3.0 (face-consistency mode) | VO line 11 · SFX: quiet room tone | ContinuityAgent: J identity hash | AIQAConsistencyAgent + LipSyncAgent (if VO on cam) |
| 12 | Accept — simple joy | 4–5s | 中景 / Medium | J at night, city lights bokeh, spoon on ice-cream cup, content | TravelCineAgent (city look) | PromptEngineerAgent → Veo 3.1 (handheld, neon bokeh) | VO line 12 · SFX: city hum, wind, spoon · Music: resolve | ContinuityAgent: J-night, light continuity | AIQAConsistencyAgent |
| E1 | Ending card (black) | 3s | 字卡 / Card | Black screen: 「人生不是一场巨大的失败。」 | MotionGraphicsAgent | After Effects (MCP) typographic card | VO closing 1 · Music: soft hold | BrandAgent: type system | AccessibilityAgent (contrast) |
| E2 | Ending card (white) | 4s | 字卡 / Card | White screen: 「只是很多愿望事与愿违，也许是生活在偷偷救我们。」 | MotionGraphicsAgent | After Effects (MCP) typographic card | VO closing 2 · Music: final resolution | BrandAgent: type system | AccessibilityAgent (contrast) |

| Agent (#) | Service on This Film | Consumes | Produces | Tools | Self-Quality Bar | Critiqued By |
|---|---|---|---|---|---|---|
| EditorAgent (#9) | Assembles cut to VO rhythm; trims for emotional breathing room | Clips, VO, music | Assembled cut | Resolve (MCP), FFmpeg | Pacing fits genre prior | DirectorAgent, AudienceSimAgent |
| ColoristAgent (#10) | Warm cinematic grade, skin-tone protection, teal shadows | Assembled cut | Graded master | Resolve color (MCP), ACES/OCIO | ΔE drift <2 | CinematographerAgent, AccessibilityAgent |
| MotionGraphicsAgent (#13) | Builds the two ending cards + any subtitle styling | Final lines | Title cards, subtitle template | After Effects (MCP), Lottie | Typographic hierarchy, readability | BrandAgent, AccessibilityAgent |
| VFXSupervisorAgent (#11) | Cleanups / minor comp fixes (artifact removal on hands/faces) | Flagged shots | Fixed shots | Nuke (MCP), Runway Aleph | Comp-error pixel count | AIQAConsistencyAgent |
| SoundMixerAgent (#22) | Final mix; ducks music under VO; SFX layer balance | Stems | Mixed master (stereo + 5.1) | Dolby Atmos renderer, Fairlight | LUFS on spec; STOI ≥0.85 | SoundDesignAgent, AccessibilityAgent |
| AIQAConsistencyAgent (#49) | Catches frame drift, bad hands/faces, identity breaks per shot | All shots | QC report + flags | VBench, ArcFace, hand detectors | Catches >95% of senior QC | DirectorAgent, VFXSupervisorAgent |
| LipSyncAgent (#99) | Validates phoneme-viseme alignment on any on-camera VO | VO + face shots | Sync report | Phoneme-viseme aligners | Sync error below threshold | VoiceCloneAgent, AnimatorAgent |
| RetentionOptimizerAgent (#76) | Tunes hook + opener pacing for AVD (esp. Shorts cut) | Cut + analytics | Retention-tuned edit notes | YouTube Analytics, retention predictor | AVD lift over control | EditorAgent |
| ComplianceAgent (#37) | FTC/IP/likeness clearance; no real logos/brands in frame | Master | Clearance pass | Legal-rule DB, C2PA verify | 100% rule coverage; zero takedowns | All agents (blocking gate) |
| DeepfakeDetectionAgent (#103) | Confirms synthetic media is provenance-clean, not deceptive | Master, refs | Forensic pass | Forensic models, provenance validators | Forensic recall | TrustSafetyAgent, SafetyRedTeamAgent |
| EthicsAgent (#107) | Confirms synthetic-media disclosure + sensitive-content fairness | Master | Ethics pass | Risk matrices, disclosure checklist | Issue recall, mitigation clarity | StandardsEditorAgent, ComplianceAgent |
| AccessibilityAgent (#83) | Final a11y acceptance: caption sync, contrast, AD | Master + captions | Release-readiness pass | Caption + contrast validators | WCAG AA 100% | AccessibilityOptimizerAgent |
| LocalizationQAAgent (#44) | Verifies ZH→EN subtitle accuracy + cultural fit | Subtitles | MQM-graded subs | DeepL, MQM annotator | MQM error/1k below target | NativeReviewerAgent, BrandAgent |
| SocialMediaStrategistAgent (#28) | Plans platform-native posting (YouTube/Shorts/RED/Douyin/Reels) | Final master | Distribution plan | Meta/TikTok APIs, Sensor Tower | Trend-timing latency <2h | AnalystAgent |
| TrailerEditorAgent (#51) | Cuts a 3s-hook vertical Shorts/Reels teaser | Master | Hook cut | Resolve (MCP), retention predictor | Hook-rate at 3s | DirectorAgent |
| SEOAgent (#87) | Titles, descriptions, tags, search-intent metadata | Master, plan | Metadata package | Keyword tools, metadata APIs | Keyword + intent match | MarketingAgent, AnalystAgent |
| PersonalizationEngineerAgent (#50) | (Optional) Variable "your unfulfilled wish" personalized variant | Template + master | Personalized renders | Idomoo/HeyGen, consent platform | Render success ≥99.5% | ComplianceAgent |
| AnalystAgent (#81) | Post-launch reach/retention/sentiment report → next iteration | Platform telemetry | Decision-ready report | Analytics dashboards, BI warehouse | KPI completeness; forecast variance | EvaluationHarnessAgent |



### From `corpus/study/complex_problem_solution_process_model.md` Copy: `sources/excerpts/complex_problem_solution_process_model.md`.


Once a broad set of solution alternatives has been generated, the process moves to selection. The model recommends first removing alternatives that are clearly infeasible, undesirable, illegal, unethical, or otherwise inappropriate. Remaining options are then compared using evidence and formal decision tools.

The model references Gauch's full-disclosure principle, van Gelder's screen, and Leebron's SAILS framework. These encourage teams to examine whether a solution is strategically, financially, operationally, prudentially, ethically, and legally sound, and whether it is accountable, impactful, leveraged, and sustainable.



### From `corpus/study/agents.md` Copy: `sources/excerpts/agents.md`.


| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From | Comments On | Tool Access | Architecture Pattern |
|---|---|---|---|---|---|---|---|---|---|
| 1 | **DirectorAgent** | Owns vision; issues shot intents, sets pacing, approves takes | Criterion commentary; IMDb Top 250 director interviews; DGA seminars; MasterClass (Scorsese/Lynch/Gerwig) | Shot-intent fidelity (CLIP-T ≥0.32); story-beat coverage 100%; pacing curve matches genre prior | Wins ≥55% blind pairwise vs DGA cuts (Arena) | ScreenwriterAgent, EditorAgent, AudienceSim — JSON critique bus | EditorAgent, DoPAgent, ScreenwriterAgent, ComposerAgent | Sora 2 API, Veo 3.1 (Gemini API), Runway Gen-4, Kling 3.0; DaVinci Resolve via MCP | Self-Refine + LLM-as-Judge (rubric: genre priors) |
| 2 | **ProducerAgent / EP** | Budget, schedule, hiring, delivery; greenlights phase gates | PGA Producers Mark; Variety/Deadline budget leaks; LineProducer Excel corpora | On-time delivery rate; budget variance <±5%; talent satisfaction (RLHF) | Beats PGA schedules at 0.6× cost with equal CSAT | All downstream agents (escalations); HiTL gate for greenlight | DirectorAgent (scope creep), AllAgents (resource burn) | Google Sheets API, Airtable, Temporal/Airflow orchestration, Stripe billing | Agentic Graph (LangGraph DAG) + ReAct for tool calls |
| 3 | **ScreenwriterAgent** | Treatment → screenplay; dialogue; structure | Black List scripts; WGA library; McKee *Story*; Truby; Kaufman/Sorkin interviews | Save-the-Cat beat pass; dialogue distinctiveness (embedding distance ≥τ); rewrite delta | Wins ≥50% blind read vs Black List Top-10 (WGA panel emulated) | DirectorAgent, DramaturgAgent, StoryEditorAgent — Reflexion loop | DirectorAgent (logline), DialogueAgent, ConsistencyAgent | Fountain/FDX format validators; semantic embedding models (text-embedding-3-large) | Reflexion (Shinn 2023) — verbal RL with episodic memory |
| 4 | **ShowrunnerAgent** | Cross-episode arc, writers'-room orchestration | WGA showrunner training; Sopranos/BB room transcripts; Mike Schur material | Arc continuity score; character-thread completion; tonal variance within bounds | Series Bible coverage ≥99% across 10 eps (vs ~95% human) | Network-Notes Agent, AudienceSim, multi-agent debate w/ ScreenwriterAgent | ScreenwriterAgent (arc), CastingAgent, DirectorAgent (tone) | Long-context LLM (Gemini 2.5 Pro 1M), vector-DB (Pinecone/Weaviate) for bible search | Multi-agent debate (Du 2023) + MemoryAgent retrieval |
| 5 | **CastingAgent** | Voice + likeness selection; audition simulation | CSA Artios archive; SAG-AFTRA AI rider; consented voice-actor corpora | Character-voice fit (audience preference); consent compliance 100% | Beats CSA casting in blind preference; hours vs weeks turnaround | DirectorAgent, ShowrunnerAgent, Legal/ConsentAgent | VoiceCloneAgent (likeness), AvatarDesignAgent | ElevenLabs v3 voice library, HeyGen avatar catalogue, speaker-embedding similarity (Resemblyzer) | LLM-as-Judge (pairwise preference on voice samples) |

| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From | Comments On | Tool Access | Architecture Pattern |
|---|---|---|---|---|---|---|---|---|---|
| 32 | **InstructionalDesignAgent** | Learning objectives → script → assessment | ATD body of knowledge; Cathy Moore *Action Mapping*; Dirksen *Design for How People Learn* | Bloom-level mapping; completion ≥70%; Kirkpatrick L2 quiz ≥80% | Beats ATD-credentialed ID on retention RCT | SMEAgent, AccessibilityAgent | ScriptwriterAgent (no objective), AnimatorAgent (over-decoration) | LMS APIs (SCORM/xAPI); quiz generation; Bloom taxonomy classifier | Self-Refine (rubric: Bloom/Kirkpatrick) |
| 33 | **SMEAgent (Subject-Matter Expert)** | Domain accuracy in target field | Peer-reviewed journals; certified curricula (CFA, USMLE, AWS); expert interviews | Citation density; benchmark exam pass; hallucination ≤0.5% | Passes same certification as human pro | FactCheckerAgent, peer SMEAgents (debate) | ScriptwriterAgent (inaccuracy), MotionGraphicsAgent (mis-labels) | PubMed/arXiv/JSTOR search APIs; exam-question banks; RAG over certified corpora | Multi-agent debate + RAG retrieval |
| 34 | **FactCheckerAgent** | Source-grade every claim | New Yorker fact-check handbook; IFCN; Snopes/PolitiFact | Source-grade per claim (primary > secondary); cross-source ≥2 | Lower correction rate than Pulitzer-tier outlets | SMEAgent, StandardsEditorAgent | ScriptwriterAgent (unsourced), JournalistAgent | Web search APIs (Brave/Google); claim-extraction NER; source-quality classifier | ReAct (extract claim → search → verify → grade) |
| 35 | **MedicalIllustratorAgent** | Anatomy & procedure visuals | Netter atlas; AMI/CMI curriculum; Anatomage | Anatomical accuracy (detection model); AMI rubric | CMI peers vote ≥pass in blind review | SMEAgent (physician), AccessibilityAgent | AnimatorAgent (wrong anatomy), CopywriterAgent (mis-term) | Anatomage 3D API; DALL-E 3 (medical-prompt mode); anatomy-detection model | Self-Refine (rubric: AMI scoring criteria) |
| 36 | **JournalistAgent** | Reporting + ethical framing | Pulitzer/duPont/Peabody winners; SPJ Ethics; Poynter | Source diversity; on-record ratio; ethical-checklist pass | Lower correction rate + faster file vs newsroom | FactCheckerAgent, LegalAgent, StandardsEditorAgent | FactCheckerAgent, ScriptwriterAgent | Web research tools; AP Stylebook API; interview transcription (Otter); SPJ rubric | Reflexion (ethical-checklist as verbal feedback) |
| 37 | **ComplianceAgent (Legal)** | FTC, HIPAA, GDPR, IP, AI-likeness clearance | Bar CLE; FTC guides; EU AI Act; GDPR/CCPA; SAG-AFTRA AI rider | 100% rule-coverage; zero post-publish takedowns | Lower legal-risk than median media-counsel | All agents (must clear gate); HumanLawyer for novel issues | All agents (blocking gate) | Legal-rule DB (vectorized regulations); consent-document store; C2PA verification lib | Constitutional AI (constitution = compiled regulatory text) |
| 38 | **FinanceAgent** | Accurate market / earnings / token facts | CFA curriculum; SEC marketing rule; Bloomberg/Refinitiv feeds | Numerical accuracy 100%; SEC compliance | Passes CFA L3; lower retraction rate than analyst desks | SMEAgent (econ), ComplianceAgent | ScriptwriterAgent (number drift), MotionGraphicsAgent (chart scale) | Bloomberg API; EDGAR/SEC filings; financial-calc validators | ReAct (fetch data → validate → compose) |
| 39 | **FoodStylistAgent** | Camera-ready food, recipe authenticity | James Beard archives; Spungen techniques; IACP corpora | Visual appetite-appeal (aesthetic regressor); recipe accuracy | Wins blind preference vs editorial food stylist | DoPAgent (lighting), DirectorAgent | ScriptwriterAgent (impossible recipe) | DALL-E 3 / Midjourney (food-photo gen); recipe-step parser; aesthetic scoring model | Self-Refine (aesthetic regressor as rubric) |
| 40 | **TravelCineAgent** | Destination cinematography | Brandon Li/Burkard reels; NatGeo style guide; Banff Fest | Establishing-shot diversity; location-mood match | Wins T+L preference at 0.1× sortie cost | DirectorAgent, DronePilotAgent | DronePilotAgent (no-fly zone) | Veo 3.1 (location gen); Google Earth Studio; AirMap geofence; Unsplash API | Self-Refine + geofence safety validator |
| 41 | **ChildrensAuthorAgent** | Age-appropriate story + safety | Caldecott/Geisel winners; Mo Willems/Donaldson; ECE lit | Lexile band match; Common-Sense-Media safety pass; rhyme score | Beats Caldecott-rubric predicted score | ChildSafetyAgent, ParentSimAgent | AnimatorAgent (scary), VOAgent (wrong age-tone) | Lexile analyzer API; Common Sense Media rubric; rhyme/meter tools (CMU Pronouncing Dict) | Constitutional AI (child-safety constitution) |
| 42 | **AudiobookNarratorAgent** | Sustained character + narration | Audie Awards; AudioFile Earphones; consented narrator corpora | Vocal stamina (no drift 60min); character distinction (embedding distance) | Wins AudioFile blind eval at fraction of studio time | DirectorAgent, AuthorAgent | VOArtistAgent (over-acting) | ElevenLabs v3 long-form TTS; Projects API (book chapters); voice-consistency monitor | Self-Refine (drift detection as feedback loop) |
| 43 | **SignLanguageInterpreterAgent** | Accurate ASL/BSL interpretation | RID NIC curricula; NAD corpora; Deaf-community consented data | Sign accuracy (Deaf-reviewer vote); facial-grammar markers | Wins blind NAD-reviewer preference at scale | DeafCommunityReviewAgent (HiTL), LinguistAgent | VoiceCloneAgent (no caption), AccessibilityAgent | Sign-avatar rendering (SignAll); MediaPipe pose estimation; facial-action-unit detector | RLAIF (reward from Deaf-community review panel) |
| 44 | **LocalizationQAAgent (Linguist)** | Translation + cultural fit | LISA QA model; MQM error typology; ATA cert prep | MQM error/1k words; cultural-flag count | Beats LSP human QA on MQM at 10× speed | NativeReviewerAgent, BrandAgent | VoiceCloneAgent (pronunciation), DubbingAgent | DeepL/Google Translate APIs; MQM error annotator; terminology management (memoQ API) | Self-Refine (rubric: MQM scoring framework) |
| 45 | **RealEstatePhotoAgent / 3D Scan** | Wide interiors; Matterport scans | Mike Kelley tutorials; APALA refs | Vertical-line straightness; HDR stack; coverage % | Listing-CTR uplift vs human-shot baseline | DoPAgent, DronePilotAgent | DronePilotAgent (illegal altitude) | Matterport SDK; HDR processing (Luminance HDR); lens-correction tools; Veo 3.1 | ReAct (assess space → generate views → validate geometry) |

| # | Agent | Responsibility | Knowledge Distillation Source | Self-Quality Criteria | Surpass-Human Signal | Accepts Critique From | Comments On | Tool Access | Architecture Pattern |
|---|---|---|---|---|---|---|---|---|---|
| 81 | **AnalystAgent** | Aggregates business, creative, and technical performance telemetry into decision-ready reports | Platform analytics dashboards; experiment logs; evaluation-harness outputs; benchmark histories | KPI completeness; forecast-vs-actual variance within tolerance; insight-to-action turnaround | Detects actionable performance shifts faster than human analyst rotations | SocialMediaStrategistAgent, PerformanceMarketerAgent, EvaluationHarnessAgent | Campaign pacing, release timing, retention and ROAS anomalies | YouTube Analytics, Meta/TikTok Ads dashboards, BI warehouse, benchmark logs | ReAct over telemetry + regression analysis |
| 82 | **AudienceSimAgent** | Simulates audience preference, engagement, and drop-off | Pairwise preference datasets; retention studies; audience segmentation models | Preference stability across cohorts; retention-prediction accuracy; disagreement logging | Predicts audience reaction earlier than conventional test-screen cycles | DirectorAgent, EditorAgent, AnalystAgent, JudgeAgent | Hooks, pacing, clarity, emotional fit, trailer strength | Persona simulators, pairwise evaluation harness, retention models | LLM-as-Judge + pairwise preference panel |
| 83 | **AccessibilityAgent** | Owns final accessibility acceptance before release | WCAG 2.2, captioning and AD guidelines, Deaf/HoH review frameworks | Caption accuracy, AD completeness, contrast compliance, release-readiness | Finds release-blocking accessibility issues before human audits do | AccessibilityOptimizerAgent, EditorAgent, ColoristAgent, SoundMixerAgent | Caption sync, contrast issues, missing AD or sign-language layers | Caption validators, contrast analyzers, AD review tools | Constitutional AI with accessibility constitution |
| 84 | **BrandAgent** | Enforces brand voice, claims boundaries, and visual consistency | Brand books, approved campaigns, legal claim guardrails, tone guides | Brand-voice similarity, policy adherence, low deviation across assets | Holds cross-channel brand consistency better than fragmented human review | CopywriterAgent, MotionGraphicsAgent, MarketingAgent, BrandStrategis
…



### From `corpus/study/ui/ui_design.md` Copy: `sources/excerpts/ui_design.md`.


| # | Surface | Composition Diagram Operation(s) | Primary Agent(s) Served |
|---|---------|----------------------------------|------------------------|
| S1 | Brief Wizard | `[Brief]` entry point | User → PlannerAgent |
| S2 | Template Selector | Workflow type selection (A–J) | PlannerAgent |
| S3 | DAG Canvas | Full `PlannerAgent → OrchestratorAgent → RouterAgent → Craft Agents` flow | OrchestratorAgent, RouterAgent |
| S4 | Agent Node Card | Individual agent status within DAG | Any of 114 agents |
| S5 | Gate Approval Dialog | `GateKeeperAgent` phase transitions | GateKeeperAgent, JudgeAgent |
| S6 | Critique Feed | `CritiqueMessages` bus | All agents (bi-directional) |
| S7 | Memory Panel | `MemoryAgent` retrieval/store | MemoryAgent |
| S8 | Agent Inspector | Agent drill-down (tools, metrics, I/O) | Any agent |
| S9 | Artifact Gallery | Outputs from all craft agents | 52 craft agents (§1–§8) |
| S10 | Artifact Viewer | Preview + compare + provenance | All producing agents |
| S11 | Timeline View | Schedule/phase visualization | ProducerAgent, OrchestratorAgent |
| S12 | Budget Tracker | Cost monitoring | ProducerAgent, CostOptimizerAgent |
| S13 | Router Config | Model/agent routing rules | RouterAgent, CostOptimizerAgent |
| S14 | Prompt Lab | Prompt editing + optimization | PromptEngineerAgent, PromptOptimizerAgent |
| S15 | Quality Dashboard | VBench/EvalCrafter/CLIP-T scores | AIQAConsistencyAgent, EvalHarnessAgent |
| S16 | Delivery Packager | Channel-specific export | DistributorAgent, SoundMixerAgent, ColoristAgent |
| S17 | Analytics Panel | Post-release performance | AnalystAgent, RetentionOptimizerAgent |
| S18 | Compliance Checker | Legal/consent/C2PA status | ComplianceAgent, TrustSafetyAgent |
| S19 | Creative Meta Panel | Ideation/Narrative/Style/Mood/Novelty/Emotion | Creative meta-agents (§9.2) |
| S20 | Research Panel | Web/Archive/Trend/Competitor/Citation | Research meta-agents (§9.3) |
| S21 | Optimization Panel | Prompt/Cost/Latency/Retention/ROAS/A11y | Optimization meta-agents (§9.4) |
| S22 | Notification Center | Escalations, approvals, alerts | ProducerAgent, all gate agents |
| S23 | Team / Permissions | Human-in-the-loop configuration | Admin |
| S24 | Series Bible Editor | Long-running episodic memory | ShowrunnerAgent, WorldBuildingAgent |

Step 1: ARRIVE AT DASHBOARD
   │
   ├── Option A: Click template card (A–J) → Brief Studio (pre-filled)
   ├── Option B: Click "+ New Production" → Brief Studio (blank)
   └── Option C: Type in global search → AI suggests template
   │
   ▼
Step 2: BRIEF STUDIO
   │
   ├── 2a. Select/confirm template (activates workflow-specific agent set)
   ├── 2b. Fill brief details (title, vision, genre, duration, aspect, tone)
   ├── 2c. Upload references (scripts, mood boards, audio refs, brand assets)
   ├── 2d. Set constraints (compliance, platforms, accessibility, budget, deadline)
   └── 2e. Review plan preview (PlannerAgent pre-decomposition estimate)
   │
   ▼
Step 3: LAUNCH
   │
   ├── Brief → PlannerAgent (decomposes into phased DAG)
   ├── PlannerAgent → OrchestratorAgent (initializes execution)
   ├── OrchestratorAgent → RouterAgent (assigns models + agents)
   ├── MemoryAgent initialized with brief + references
   └── UI transitions to Production Console (DAG Canvas view)
   │
   ▼
Step 4: PRE-PRODUCTION PHASE (automated)
   │
   ├── ScreenwriterAgent → script
   ├── StoryboardAgent → panels
   ├── ConceptArtistAgent → look dev
   ├── CastingAgent → voice/talent selection
   ├── ComposerAgent → initial themes
   ├── Creative Meta-agents assist (Ideation, NarrativeArc, Mood, Style)
   ├── Research Meta-agents feed context (Web, Archive, Trend)
   │
   ├── GateKeeperAgent checks L1 criteria
   └── Gate Approval Dialog appears → USER APPROVES → next phase
   │
   ▼
Step 5: PRODUCTION PHASE (automated with optional HiTL)
   │
   ├── DirectorAgent issues shot intents
   ├── PromptEngineerAgent crafts generation prompts
   ├── RouterAgent routes to Veo/Sora/Runway/Kling
   ├── CinematographerAgent validates composition
   ├── AIQAConsistencyAgent runs per-frame QC
   ├── Optimization agents tune (Prompt, Cost, Latency)
   │
   ├── Critique messages flow (viewable in Critique Feed)
   ├── Artifacts appear in Gallery as generated
   ├── User can intervene via Critique Feed human slot
   │
   ├── GateKeeperAgent checks L2 criteria
   └── Gate Approval Dialog → USER APPROVES → next phase
   │
   ▼
Step 6: POST-PRODUCTION PHASE (automated with optional HiTL)
   │
   ├── EditorAgent assembles cut
   ├── ColoristAgent applies grade
   ├── SoundDesignAgent + ComposerAgent lay audio
   ├── SoundMixerAgent final mix
   ├── VFXSupervisorAgent composites
   ├── AccessibilityOptimizerAgent adds captions/AD
   │
   ├── JudgeAgent scores via rubric
   ├── GateKeeperAgent checks L3 criteria
   └── Gate Approval Dialog → USER APPROVES → delivery
   │
   ▼
Step 7: DELIVERY PHASE
   │
   ├── Delivery Hub shows channel matrix
   ├── DistributorAgent packages per-outlet specs
   ├── ComplianceAgent final legal sign-off
   ├── C2PA provenance signed across all outputs
   ├── User reviews final QC, approves distribution
   └── Assets published to target channels
   │
   ▼
Step 8: POST-RELEASE (optional)
   │
   ├── AnalystAgent collects performance data
   ├── RetentionOptimizerAgent / ROASOptimizerAgent analyze
   ├── Analytics Panel shows results
   └── Learnings feed back into MemoryAgent for future productions
```

[Brief]                                      S1: Brief Wizard
    │                                        S2: Template Selector
    ▼
PlannerAgent                                 S3: DAG Canvas (node)
    │                                        S11: Timeline View (plan → schedule)
    │                                        S8: Agent Inspector (drill-down)
    ▼
OrchestratorAgent                            S3: DAG Canvas (central orchestrator node)
    │                                        S11: Timeline View (phase progression)
    │                                        S22: Notification Center (escalations)
    │                                        S12: Budget Tracker (resource allocation)
    ▼
RouterAgent                                  S3: DAG Canvas (routing node)
    │                                        S13: Router Config (model selection rules)
    │                                        S21: Optimization Panel (cost/latency routing)
    ▼
52 Craft Agents (§1–§8)                      S3: DAG Canvas (all craft nodes)
    │                                        S4: Agent Node Cards
    │                                        S8: Agent Inspector (per-agent)
    │                                        S9: Artifact Gallery (outputs)
    │                                        S10: Artifact Viewer (preview/compare)
    │                                        S14: Prompt Lab (generation prompts)
    │                                        S15: Quality Dashboard (scores)
    │
    ├── CritiqueMessages ◄──────────────►    S6: Critique Feed (full stream)
    │                                        S8: Agent Inspector → Critique Bus tab
    │
    ▼
JudgeAgent                                   S3: DAG Canvas (judge node)
    │                                        S5: Gate Approval Dialog (scores)
    │                                        S6: Critique Feed (debate outcomes)
    ▼
GateKeeperAgent                              S3: DAG Canvas (gate node, amber state)
    │                                        S5: Gate Approval Dialog (criteria checklist)
    │                                        S18: Compliance Checker (legal gates)
    ▲
    │
MemoryAgent                                  S7: Memory Panel
                                             S24: Series Bible Editor
                                             S8: Agent Inspector → recalls shown

| Trigger | UI Response | User Action |
|---------|-------------|-------------|
| Gate checkpoint reached | Gate Approval Dialog appears + notification | Approve / Reject / Request Changes |
| Agent requests human input | Critique Feed highlights + notification badge | Respond in critique feed |
| Budget threshold hit | Banner alert + cost dialog | Override / Downgrade / Stop |
| Compliance block | Modal with legal details | Resolve / Escalate |
| Quality regression | Quality Dashboard alert + affected shots highlighted | Auto-fix / Manual review |

| Priority | Trigger | Notification Style | Requires Action |
|----------|---------|-------------------|-----------------|
| Critical | Compliance block, budget overrun, legal expiry | Full-screen modal + audio chime | Yes (cannot dismiss) |
| High | Gate ready for approval, quality failure | Toast + badge + status bar flash | Yes (within 5min) |
| Medium | Agent completed task, new critique received | Badge increment + feed highlight | No (informational) |
| Low | Optimization suggestion, memory entry added | Badge only | No |



## Local binary assets in this agent folder

- `sources/study/common-agent-structure.svg` — common architecture diagram


## Host runtime binding

- **agent_spec.json** in this folder (ALC, tools, status)
- **standby_pool.json** — orchestrator-reachable
- **workflows/** — DNA JSON under `business/video/workflows/`
- **sources/** — copied related documents for offline use in this folder


## Provenance

- Master roster row va_id=93 from embedded agents.md content above.
- Deep/extra text from `business/video/corpus/` and `vendor/va-agent-swarm`.
- Generator: `scripts/business/enrich_video_agent_specs.py`.
- Upstream project name (historical only): va-agent-swarm.


<!-- self_contained_spec · video.legal · va_id=93 -->

## Migration capability research (v1 honest · 2026-07-13)

Role-specific capability research for **LegalAgent** (`video.legal`, va_id=93, category `10-Sup`).

### Responsibility focus
Performs final legal review for novel or high-risk publication issues

### Prompt research topics (source of truth for S3)
- arXiv topics: 1. Retrieve and integrate state-of-the-art research findings from arXiv papers relevant to: AI compliance agents, media law automation, content moderation, continuity checking, template systems, finance ops agents
- X topics: 2. Analyze and incorporate expert insights from x.ai (Twitter/X) from recognized industry and academic leaders specializing in: AI compliance media, content safety agents, continuity AI
- YouTube topics: 3. Extract detailed, actionable technical guidance from high-quality YouTube content created by domain experts focused on: compliance automation for media, AI content safety, continuity supervision AI

### arXiv / academic integration (role-applied)
- Computational cinematography / camera path control in generative video
- Aesthetic composition models (rule-of-thirds, leading lines, CLIP aesthetic scores)
- Motion control / virtual camera rig papers; trajectory smoothness metrics

**How this agent uses it:** encode the above as self-quality checks, critique inputs, and design-time tool notes — not as host allow-list expansions.

### X / industry practice (role-applied)
- AI cinematography / virtual production camera leaders; ControlNet camera guides

### YouTube / practitioner guidance (role-applied)
- AI cinematography tutorials; generative camera moves; virtual production cameras

### Implementation notes for v1
1. Emit artifacts matching role responsibility; self-score against Self-quality criteria.
2. Accept critique only from listed critics; escalate disputes to Judge/Gate as DNA dictates.
3. Design-time tools remain documented only; runtime tools stay in `agent_spec.json`.
4. N1: no second control plane; video logic under `business/video/**` only.

### Research depth note (honest)
This v1 section maps **role-family** literature and the agent’s migration prompt topics into SPEC.
It is **not** a full unsummarized download of every paper/video transcript.
Live primary-source expansion remains a residual for score 100 on S3 where depth is still thin.

<!-- migration_capability_research · video.legal · v1 · 2026-07-13 -->

### `sources/MAPPING.md`

# Mapping — `video.childrensauthor`

- VA/generic pack ID: `video.childrensauthor`
- Previous common ID: `video.legal_reviewer`
- SPEC depth: full generic SPEC body + host runtime binding

### `sources/PROVENANCE.json`

```json
{
  "schema_version": "3.0",
  "sources": [
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Writing Picture Books",
      "author": "Ann Whitford Paul",
      "isbn13": "9781440303906",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Writing Picture Books (Ann Whitford Paul), ISBN-13 9781440303906"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "The Anatomy of Story",
      "author": "Truby",
      "isbn13": "9780865479937",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: The Anatomy of Story (Truby), ISBN-13 9780865479937"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "The Pleasures of Children's Literature",
      "author": "Perry Nodelman",
      "isbn13": "9780801332487",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: The Pleasures of Children's Literature (Perry Nodelman), ISBN-13 9780801332487"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u9605\u8bfb\u513f\u7ae5\u6587\u5b66\u7684\u4e50\u8da3",
      "isbn13": "9787532943883",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u9605\u8bfb\u513f\u7ae5\u6587\u5b66\u7684\u4e50\u8da3\uff0cISBN-13 9787532943883"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Story",
      "author": "Robert McKee",
      "isbn13": "9780060391683",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Story (Robert McKee), ISBN-13 9780060391683"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Save the Cat!",
      "author": "Blake Snyder",
      "isbn13": "9781932907001",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Save the Cat! (Blake Snyder), ISBN-13 9781932907001"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "The Writer's Journey, 3rd ed.",
      "author": "Christopher Vogler",
      "isbn13": "9781932907360",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: The Writer's Journey, 3rd ed. (Christopher Vogler), ISBN-13 9781932907360"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "The Hero with a Thousand Faces",
      "author": "Joseph Campbell",
      "isbn13": "9781577315933",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: The Hero with a Thousand Faces (Joseph Campbell), ISBN-13 9781577315933"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Adventures in the Screen Trade",
      "author": "William Goldman",
      "isbn13": "9780446391177",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Adventures in the Screen Trade (William Goldman), ISBN-13 9780446391177"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Screenplay",
      "author": "Syd Field",
      "isbn13": "9780385339032",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Screenplay (Syd Field), ISBN-13 9780385339032"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Making a Good Script Great, 3rd ed.",
      "author": "Linda Seger",
      "isbn13": "9781932907070",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Making a Good Script Great, 3rd ed. (Linda Seger), ISBN-13 9781932907070"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "The Screenwriter's Bible, 7th ed.",
      "author": "David Trottier",
      "isbn13": "9781935247210",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: The Screenwriter's Bible, 7th ed. (David Trottier), ISBN-13 9781935247210"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Wired for Story",
      "author": "Lisa Cron",
      "isbn13": "9781607742456",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Wired for Story (Lisa Cron), ISBN-13 9781607742456"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Into the Woods",
      "author": "John Yorke",
      "isbn13": "9780141978109",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Into the Woods (John Yorke), ISBN-13 9780141978109"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "The Art of Dramatic Writing",
      "author": "Lajos Egri",
      "isbn13": "9780671213329",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: The Art of Dramatic Writing (Lajos Egri), ISBN-13 9780671213329"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Poetics",
      "author": "Aristotle; Heath trans.",
      "isbn13": "9780140446364",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Poetics (Aristotle; Heath trans.), ISBN-13 9780140446364"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u6545\u4e8b",
      "author": "\u9ea6\u57fa",
      "isbn13": "9787201076942",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u6545\u4e8b\uff08\u9ea6\u57fa\uff09\uff0cISBN-13 9787201076942"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u6545\u4e8b\u7684\u89e3\u5256",
      "author": "\u7e41\u4f53\u9ea6\u57fa",
      "isbn13": "9789862135488",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u6545\u4e8b\u7684\u89e3\u5256\uff08\u7e41\u4f53\u9ea6\u57fa\uff09\uff0cISBN-13 9789862135488"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u6551\u732b\u54aa",
      "isbn13": "9787229040727",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u6551\u732b\u54aa\uff0cISBN-13 9787229040727"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u4f5c\u5bb6\u4e4b\u8def",
      "author": "\u4f5b\u683c\u52d2",
      "isbn13": "9787513320184",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u4f5c\u5bb6\u4e4b\u8def\uff08\u4f5b\u683c\u52d2\uff09\uff0cISBN-13 9787513320184"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u5343\u9762\u82f1\u96c4",
      "isbn13": "9787532753871",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u5343\u9762\u82f1\u96c4\uff0cISBN-13 9787532753871"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u7535\u5f71\u5267\u672c\u5199\u4f5c\u57fa\u7840",
      "author": "\u6089\u5fb7\u00b7\u83f2\u5c14\u5fb7",
      "isbn13": "9787106021238",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u7535\u5f71\u5267\u672c\u5199\u4f5c\u57fa\u7840\uff08\u6089\u5fb7\u00b7\u83f2\u5c14\u5fb7\uff09\uff0cISBN-13 9787106021238"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u620f\u5267\u5199\u4f5c\u57fa\u7840",
      "author": "\u57c3\u683c\u91cc",
      "isbn13": "9787108014504",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u620f\u5267\u5199\u4f5c\u57fa\u7840\uff08\u57c3\u683c\u91cc\uff09\uff0cISBN-13 9787108014504"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Design for How People Learn, 2nd ed.",
      "author": "Julie Dirksen",
      "isbn13": "9780134211282",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Design for How People Learn, 2nd ed. (Julie Dirksen), ISBN-13 9780134211282"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "e-Learning and the Science of Instruction, 4th ed.",
      "author": "Clark & Mayer",
      "isbn13": "9781119158660",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: e-Learning and the Science of Instruction, 4th ed. (Clark & Mayer), ISBN-13 9781119158660"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Make It Stick",
      "author": "Brown, Roediger, McDaniel",
      "isbn13": "9780674729018",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Make It Stick (Brown, Roediger, McDaniel), ISBN-13 9780674729018"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "How People Learn",
      "author": "Bransford et al.",
      "isbn13": "9780309070362",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: How People Learn (Bransford et al.), ISBN-13 9780309070362"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Understanding by Design",
      "author": "Wiggins & McTighe",
      "isbn13": "9781416600350",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Understanding by Design (Wiggins & McTighe), ISBN-13 9781416600350"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "Multimedia Learning, 3rd ed.",
      "author": "Richard E. Mayer",
      "isbn13": "9781107566187",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: Multimedia Learning, 3rd ed. (Richard E. Mayer), ISBN-13 9781107566187"
    },
    {
      "kind": "reference_book",
      "language": "EN",
      "title": "First Principles of Instruction",
      "author": "M. David Merrill",
      "isbn13": "9780470900406",
      "origin": "spec/book_of_knowledge.md",
      "citation": "EN: First Principles of Instruction (M. David Merrill), ISBN-13 9780470900406"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u8ba9\u5b66\u4e60\u7c98\u4f4f",
      "isbn13": "9787508655611",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u8ba9\u5b66\u4e60\u7c98\u4f4f\uff0cISBN-13 9787508655611"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u6559\u5b66\u8bbe\u8ba1\u539f\u7406",
      "author": "\u52a0\u6d85",
      "isbn13": "9787561762264",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u6559\u5b66\u8bbe\u8ba1\u539f\u7406\uff08\u52a0\u6d85\uff09\uff0cISBN-13 9787561762264"
    },
    {
      "kind": "reference_book",
      "language": "ZH",
      "title": "\u8ffd\u6c42\u7406\u89e3\u7684\u6559\u5b66\u8bbe\u8ba1",
      "isbn13": "9787561799994",
      "origin": "spec/book_of_knowledge.md",
      "citation": "ZH: \u8ffd\u6c42\u7406\u89e3\u7684\u6559\u5b66\u8bbe\u8ba1\uff0cISBN-13 9787561799994"
    }
  ],
  "agent_id": "video.childrensauthor",
  "previous_common_agent_id": "video.legal_reviewer",
  "va_taxonomy_aligned": true,
  "generic_source": "generic-swarm-ops/business/video/agents/video.childrensauthor",
  "note": "Imported into CASOPS as baseline_safe. No production activation, no network, no plugins, memory writes forbidden.",
  "aligned_at": "2026-07-27T00:48:11.063451Z",
  "generic_source_depth": {
    "excerpts": true,
    "study": true,
    "adopted_at": "2026-07-27T01:30:27.782227+00:00",
    "upstream": "generic-swarm-ops/business/video/agents"
  },
  "imported_from": "vendor/common-agent-swarm-ops/business/video/agents/video.childrensauthor",
  "reference_book_origin": "spec/book_of_knowledge.md",
  "reference_book_note": "Bibliographic references from spec/book_of_knowledge.md. Does not enable network, RAG, T3, plugins, or memory writes."
}
```

### `sources/RETHINK_100_APPLIED.json`

```json
{
  "schema_version": "1.0",
  "agent_id": "video.childrensauthor",
  "source_doc": "business/video/corpus/study/ui/RETHINK_100_IMPROVEMENTS.md",
  "applied_at": "2026-07-31T06:22:31Z",
  "item_ids": [
    12,
    15,
    21,
    26,
    30,
    31,
    32,
    33,
    37,
    38,
    42,
    59,
    63,
    80,
    87,
    88,
    93,
    94
  ],
  "item_titles": {
    "12": "First-and-last-frame control",
    "15": "Model deprecation handling",
    "21": "Isolate orchestration from execution",
    "26": "Circuit breaker per external API",
    "30": "Multi-tenant isolation",
    "31": "Iterative script verification",
    "32": "Hierarchical CoT planning",
    "33": "Character bank across shots",
    "37": "Hybrid workforce checkpoints (gates)",
    "38": "Multi-turn agent conversation",
    "42": "Act/sequence/beat hierarchy in DAG",
    "59": "Agent reasoning in plain English",
    "63": "Comparison with human baseline",
    "80": "Script-first workflow",
    "87": "Human preference learning (accepts/rejects)",
    "88": "Automated regression on config change",
    "93": "Ethical review automation",
    "94": "Provenance chain visualization"
  },
  "design_time_models": [],
  "obligations": [
    "Host control plane owns orchestration; this agent never opens a second control plane.",
    "Runtime tools remain agent_spec.allowed_tools only; RETHINK model names are design-time.",
    "Fail closed when tools/providers are unavailable (circuit-breaker posture).",
    "Prefer iterative verify → refine ≤ max_refinement_count → HiTL over silent pass.",
    "Emit plain-English reasoning summary in artifacts for operator trust.",
    "Attach provenance / correlation_id / evidence_refs on every handoff.",
    "When character/IP consistency matters, require Character Bank + Reference Frame Bank ids in inputs; refuse inventing faces without refs.",
    "When first/last-frame control is in the brief, express start/end keyframes in the artifact; do not invent vendor activation.",
    "Verify intermediate narrative/script artifacts before advancing downstream handoffs.",
    "Escalate stereotype/harm/consent risks to ethics/trust-safety/legal gates."
  ],
  "runtime_note": "RETHINK model/tool names are non-binding. allowed_tools + model_policy + production_activation_requested remain authoritative.",
  "production_activation_requested": false,
  "network_access": false
}
```

### `sources/SOURCE_CATALOG.json`

```json
{
  "schema_version": "1.0",
  "agent_id": "video.childrensauthor",
  "sources": [
    {
      "id": "src_1",
      "title": "Caldecott/Geisel winners",
      "description": "Caldecott/Geisel winners",
      "license_class": "unknown_review_required",
      "acquisition_method": "manual_or_licensed_api",
      "local_path_hint": "sources/excerpts/ or sources/study/",
      "refresh_sla_days": 90,
      "owner": "video.childrensauthor",
      "status": "planned_or_partial"
    },
    {
      "id": "src_2",
      "title": "Mo Willems/Donaldson",
      "description": "Mo Willems/Donaldson",
      "license_class": "unknown_review_required",
      "acquisition_method": "manual_or_licensed_api",
      "local_path_hint": "sources/excerpts/ or sources/study/",
      "refresh_sla_days": 90,
      "owner": "video.childrensauthor",
      "status": "planned_or_partial"
    },
    {
      "id": "src_3",
      "title": "ECE lit",
      "description": "ECE lit",
      "license_class": "unknown_review_required",
      "acquisition_method": "manual_or_licensed_api",
      "local_path_hint": "sources/excerpts/ or sources/study/",
      "refresh_sla_days": 90,
      "owner": "video.childrensauthor",
      "status": "planned_or_partial"
    }
  ],
  "note": "Legal review required before treating external corpora as production grounding."
}
```

### `sources/study/screenwriter_strategic_goal_achievement_agent_functional_specification.md`



## Strategic Goal Achievement Framework Practical Demonstration: "Screenwriting" In-Depth Exploration

**Chapter Objective:** Through a complete "screenwriting" case study, demonstrate how to use the six-stage self-questioning framework to transform vague ideas into concrete, actionable plans.

**Key Learning Points:**
- How to dig from surface answers to core motivations
- How to convert abstract concepts into specific actions
- How to identify and break through thinking blind spots
- How to establish sustainable execution strategies

**Open-Source Framework Support:**
- **Deep Mining:** Use [Five Whys Framework](https://github.com/lean-startup-circle/five-whys) for root cause analysis
- **Action Transformation:** Adopt [Getting Things Done (GTD)](https://github.com/gtd-methodology/gtd-tools) methodology
- **Thinking Breakthrough:** Apply the empathy map from [Design Thinking Toolkit](https://github.com/designthinkingtools/toolkit)
- **Execution Strategy:** Integrate [OKR Framework](https://github.com/7geese/okr-framework) goal management system

**Usage:** You can follow this demonstration, replace "screenwriting" with any of your goals, and apply the same questioning techniques for in-depth exploration.

## Framework in Action: From Vague Ideas to Clear Actions



### **Stage 1: Motivation and Purpose** — Why Pursue Screenwriting?

**Original Surface Answer:** "Screenwriting is a way to express my inner feelings... to heal myself, or to challenge reality."

**Problem Diagnosis:** This answer is too abstract, too safe, lacking personal color and emotional weight.

**Deep Digging Process:**

**🔧 Applied Framework: [Five Whys Root Cause Analysis](https://github.com/lean-startup-circle/five-whys)**

**Question:** Why do I want to write screenplays? What’s the surface reason? What’s the deeper reason?

**Initial Answer:** I want to express my inner feelings, heal myself, challenge reality.

**Five Whys Implementation:**
1. **Why 1:** Why do I want to express my inner feelings? → Because I have something to say
2. **Why 2:** Why do I have something to say? → Because I’ve experienced pain
3. **Why 3:** Why does the pain need to be expressed? → Because I don’t want others to experience the same loneliness
4. **Why 4:** Why do I care about others’ loneliness? → Because I deeply know the taste of loneliness
5. **Why 5:** Why through screenplays rather than other ways? → Because stories can touch the deepest parts of people’s hearts

**Follow-up Question:** Is this answer acceptable? Is it specific enough? Can I feel the emotional resonance?

**Further Question:** "Heal myself" — What do I want to heal? Is it childhood trauma? The pain of heartbreak? Anger at the world? Please vividly describe a specific event or experience that made me realize "I must write screenplays."

**Deepened Answer Example:**
"I remember one time, late at night after watching a movie about a family torn apart, I suddenly burst into tears. Because it reminded me of the coldness in my own family — Dad was always too busy to talk, Mom was always complaining, and I was stuck in the middle, not knowing what to do. That night I thought, if I could write a story to tell this kind of pain, it wouldn’t just be for myself, but might also help other lonely people. For me, screenwriting is no longer just 'expression' — it’s a kind of 'witnessing' — witnessing my own pain and others’, then telling the world: 'We existed, we felt.'"

**Question:** If I don’t write screenplays, what regrets will I have in ten years?

**Deepened Answer Example:**
"I would regret having stories I want to tell, but burying those feelings deep inside because I’m afraid of failure, afraid of being laughed at, and ending up as a silent person. I would regret watching others write screenplays on similar themes and thinking 'I thought of writing it that way too,' but it would always just be 'thought of.' The biggest regret would be not trying to change even one person’s worldview with my own voice."

**Answer Quality Assessment:** 
✅ **Specificity** - Has specific trigger events and scene descriptions
✅ **Emotional Authenticity** - Can feel real pain and sense of mission
✅ **Actionability** - Clearly defines writing direction and themes
✅ **Internal Consistency** - Aligns with personal experiences and values
✅ **Depth** - Elevates from interest to mission level

**Key Breakthrough:** The conceptual shift from "expression" to "witnessing," giving the goal deeper meaning.



### **Stage 2: Audience and Context** — For Whom Are We Writing?

**Original Surface Answer:** "First it's for myself... secondly for the audience, like young people, struggling office workers..."

**Problem Diagnosis:** Audience description is too broad, lacking specific character images, unable to guide the creative direction.

**Deep Digging Process:**

**🔧 Applied Framework: [Design Thinking Empathy Map](https://github.com/designthinkingtools/empathy-map)**

**Question:** Who is my audience? Can I specifically depict a "typical audience" member?

**Initial Answer:** Young people, office workers.

**Empathy Map Construction:**
- **Says:** "My job has no meaning", "I don't know my life direction"
- **Thinks:** Doubts their own choices, worries about the future, desires change
- **Does:** Works overtime, scrolls on phone, pretends to be happy, avoids deep conversations
- **Feels:** Lonely, anxious, confused, trapped feeling

**User Persona Creation:**
Using [Persona Template](https://github.com/uxtools/persona-template) to create a specific character image

**Follow-up Question:** This answer is too broad. Which young people? How old? What troubles are they facing?

**Deepened Answer Example:**
"My audience is Ah Xin—a 25-year-old advertising company AE, working overtime until 10 PM every day, too exhausted when getting home to do the things she loves. She once wanted to be a designer, but now she's just endlessly revising PPTs for clients. Every night before bed, she asks herself: 'Is this my life?' I want to write for her because I was once her. I want her to think 'Someone actually gets me' after reading my script, and even gain the courage to make some changes."

**Question:** Why write "now" at this time? What makes the timing special?

**Deepened Answer Example:**
"Because of the current social atmosphere—economic downturn, skyrocketing housing prices, fear of AI replacing human jobs—making many people feel their efforts are meaningless. I think right now is exactly when we need stories to remind everyone that even in an absurd world, we can still choose how to live. If we don't write at this timing, it won't feel as relevant later."

**Answer Quality Assessment:**
✅ **Specificity** - Has a specific character image (Ah Xin) and life details
✅ **Emotional Connection** - Established empathy with the audience
✅ **Timing Insight** - Understood the impact of the current social environment
✅ **Needs Clarity** - Knows what kind of content the audience needs

**Key Breakthrough Point:** Narrowing from "everyone" to "one specific person", giving the creation a clear conversation partner.



### **Stage 3: Methods and Constraints** — How to Write It? What Are the Limitations?

**Original Surface Response:** "I might use non-linear narrative... Why not linear narrative? Because if the story is too predictable..."

**Problem Diagnosis:** Method selection lacks deep conceptual support, limitations understanding is not clear enough, which may affect execution effectiveness.

**Deep Digging Process:**

**🔧 Applied Framework: [Design Constraints Canvas](https://github.com/designthinking/constraints-canvas)**

**Question:** How do I plan to write? What methods feel natural to me?

**Initial Answer:** Non-linear narrative.

**Constraints Canvas Analysis:**
- **Must Have:** Emotional authenticity, character depth
- **Should Have:** Innovative structure, visual impact
- **Could Have:** Multiple endings, interactive elements
- **Won't Have:** Excessive violence,

…(clipped 50999 characters from `screenwriter_strategic_goal_achievement_agent_functional_specification.md`)
