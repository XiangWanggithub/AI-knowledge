# Log

## [2026-04-09] vault initialized
- Established initial vault structure
- Defined directory semantics
- Added agent operating guides
- Created index and log files

## [2026-04-09] ingest | Andrej Karpathy - LLM Wiki
- Added source note for `llm-wiki.md`
- Added concept page `LLM Wiki`
- Added map page `Home`
- Updated `90 System/index.md`

## [2026-04-11] maintenance | Andrej Karpathy - LLM Wiki raw backfill
- Added raw capture `2026-04-11 - Andrej Karpathy - LLM Wiki`
- Linked the existing source note back to the raw note
- Updated `90 System/index.md`

## [2026-04-11] ingest | MemPO: Self-Memory Policy Optimization for Long-Horizon Agents
- Added raw capture and source note for the MemPO arXiv paper
- Added concept page `Memory Policy`
- Updated memory-related syntheses and open questions pages
- Updated `90 System/index.md`

## [2026-04-11] maintenance | MemPO arXiv backfill
- Downloaded the paper PDF into `01 Raw/` as the raw anchor artifact
- Added local PDF links to the raw note and source note
- Brought the paper closer to the current PDF-first arXiv ingest standard

## [2026-04-11] ingest | Alex Zhang - The Mismanaged Geniuses Hypothesis
- Added raw capture for the X article in `01 Raw/`
- Added source note `Alex Zhang - The Mismanaged Geniuses Hypothesis`
- Added concept pages `Task decomposition`, `Agent orchestration`, and `Recursive Language Models`
- Added synthesis page `Self-managing memory as an in-distribution control problem`
- Added synthesis page `Meta-skills for memory orchestration`
- Added topic page `Open questions in agent memory and decomposition`
- Added map page `Agent systems, decomposition, and memory`
- Added entity pages `Alex Zhang`, `Andrej Karpathy`, `Claude Code`, `OpenClaw`, and `Hermes Agent`
- Updated cross-links among source, concept, synthesis, topic, map, and entity pages
- Updated `90 System/index.md`

## [2026-04-12] ingest | Harness design for long-running application development
- Added raw capture and source note for the Anthropic engineering article
- Added concept page `Harness design`
- Added entity pages `Anthropic` and `Prithvi Rajasekaran`
- Updated `Agent orchestration` and the main agent/decomposition/memory map
- Updated `90 System/index.md`

## [2026-04-12] ingest | Scaling Managed Agents: Decoupling the brain from the hands
- Added raw capture and source note for the Anthropic managed-agents article
- Extended `Harness design` upward toward meta-harness / platform-abstraction framing
- Updated `Agent orchestration`, the main agent/decomposition/memory map, and `90 System/index.md`

## [2026-04-12] synthesis | Memory decomposition, MemPO, and meta-skills
- Extended memory-related syntheses with the idea that memory management may be OOD only globally but decomposable into in-distribution subproblems
- Added the stronger claim that the main bottleneck may be learning the correct decomposition policy over memory operations
- Updated the MemPO source note to emphasize trajectory-trained write/compress as a proof of trainability for one memory subproblem
- Expanded open questions around which memory operations are easiest to train and how trajectory signals can scale from local actions to higher-level memory orchestration
- Updated `90 System/index.md`

## [2026-04-12] maintenance | Topic-layer and navigation cleanup
- Added topic pages `Agent memory` and `Harnesses and managed agent systems`
- Linked topic pages into related concept and map pages
- Expanded the main agent/decomposition/memory map to include topic entry points
- Updated `90 System/index.md`

## [2026-04-13] ingest | Ascend HiFloat8 Format for Deep Learning
- Added raw capture and source note for the HiF8 arXiv paper
- Added topic page `Model quantization` as the starting point for a quantization cluster
- Updated `90 System/index.md`

## [2026-04-13] ingest | SmoothQuant: Accurate and Efficient Post-Training Quantization for Large Language Models
- Added raw capture and source note for the SmoothQuant paper
- Updated `Model quantization` to distinguish representation-design from distribution-reshaping / difficulty-migration routes
- Updated `90 System/index.md`

## [2026-04-20] ingest | Kerbl et al. - 3D Gaussian Splatting
- Added source note for the foundational 3DGS paper (SIGGRAPH 2023)
- Added concept page `3D Gaussian Splatting` covering core properties, splatting rendering, training, vs NeRF, vs point cloud, embodied AI input forms
- Updated `90 System/index.md`

## [2026-04-21] synthesis | 3D Spatial Representation for Embodied AI
- Added concept page `3D Spatial Representation` — necessity of spatial modality, language analogy, ideal properties, physical invariance, compositional structure, open questions
- Added concept page `Object-Centric Representation` — object as basic unit, compositional generalization, key approaches
- Added topic page `Spatial Intelligence for Embodied AI` — research directions, key papers (SPA, UniSplat, GROOT, Object-Centric 3DGS), open questions
- Updated `3D Gaussian Splatting` with cross-links to new pages
- Updated `90 System/index.md`

## 2026-04-22
- **Ingest**: ReKep (Huang et al., 2024, arXiv:2409.01652) — Li Fei-Fei 团队的关键点约束操控范式
  - Raw: PDF + raw note created
  - Source note created with Ethan's perspective on task decomposition as OOD mitigation
  - Updated [[Task decomposition]] — added embodied manipulation section, ReKep vs VLA comparison
  - Updated [[Spatial Intelligence for Embodied AI]] — added constraint-based manipulation section
  - Key insight from Ethan: 任务拆解消解 OOD 问题，与知识库已有思路一致

- **Ingest**: GigaWorld-Policy (GigaAI, 2026, arXiv:2603.17240) — Action-centered WAM, "训繁推简" causal mask 架构
  - Raw: URL-only (Tier 1), 详细架构分析
  - Source note created with method, experiments, generalization analysis, comparison with ReKep
  - Created [[World-Action Models]] concept page — WAM 范式综述、架构演进、路线对比
  - Updated [[Task decomposition]] — added WAM to route comparison
  - Updated [[Spatial Intelligence for Embodied AI]] — added WAM optimization section

- **Ingest**: RL Tokens (Physical Intelligence, 2026) — RL token 作为 VLA 与轻量 RL 专家的接口
  - Raw: URL-only (Tier 1)
  - Source note created with Ethan's insight on capability-level decomposition
  - Updated [[Task decomposition]] — added 拆解维度光谱：任务步骤拆解 (ReKep) vs 能力层级拆解 (RLT) vs 时间尺度拆解

- **Ingest**: ChemBot (Huang et al., 2026, arXiv:2604.15671) — Agent-as-Planner + VLA-as-Skill 框架
  - Raw: URL-only (Tier 1), 详细架构和记忆机制分析
  - Source note with Ethan's insight on memory asymmetry (上层有记忆，底层无记忆)
  - Updated [[Task decomposition]] — added ChemBot to interface spectrum (约束/token/子任务指令)
  - Updated [[Agent memory]] — added 具身智能中的记忆 section, memory asymmetry discussion
  - Key insight: 理想情况下两层都应有记忆——上层记策略经验，下层记操作经验

- **Ingest**: π*₀.6 (Physical Intelligence, 2025, arXiv:2511.14759) — Recap: advantage-conditioned offline RL for VLA self-improvement
  - Raw: URL-only (Tier 1)
  - Source note with PI 双路线分析 (π*₀.6 全模型 RL vs RL Tokens 轻量插件)
  - Updated [[Agent memory]] — added π*₀.6 as implicit memory, explicit+implicit combination insight
  - Updated [[Spatial Intelligence for Embodied AI]] — cross-link
  - Key relation: 隐式记忆(π*₀.6) + 显式记忆(ChemBot) = 理想双层记忆

- **Ingest**: π₀.5 (Physical Intelligence, 2025, arXiv:2504.16054) — open-world generalization VLA
  - Raw: URL-only (Tier 1), 详细架构和训练配方
  - Source note: 两层推理详解（半共享架构）、co-training 配方、vs ChemBot 对比
  - Key insight: 子任务 token 不 round-trip，在 embedding 空间内传递；97.6% 训练数据非目标场景
  - Updated [[Task decomposition]] — added π₀.5 as single-model decomposition example
  - Three architecture paradigms: 完全分离(ChemBot) / 半共享(π₀.5) / 完全端到端

- **Ingest**: π₀.7 (Physical Intelligence, 2026, arXiv:2604.15483) — steerable generalist VLA with emergent capabilities
  - Raw: URL-only (Tier 1), 9 维 model checklist
  - Source note: diversified prompt conditioning, subgoal images (BAGEL 14B), MEM 双记忆, verbal coaching
  - Key insights: subgoal image = VLA+WAM 融合桥梁; metadata conditioning = Recap 的泛化版本; verbal coaching = 教模型拆任务
  - Updated [[Memory in Embodied AI]] — π₀.7 为 PI 第一个双记忆 VLA
  - Updated [[Task decomposition]] — verbal coaching + subgoal as task decomposition
  - Updated [[Physical Intelligence]] — π₀.7 详情, RL 路线统一

## [2026-05-30] synthesis | Embodied Brain Models concept skeleton
- Established deployment-driven framework distinguishing brain (cloud) vs cerebellum (edge) models in embodied AI
- Defined three brain model schools via iterative discussion with Ethan:
  - LLM/VLM-as-brain (with Talker / Coder / Constraint / Affordance interface sub-branches; MCP-Toolkit retired as transitional)
  - Predictive Spatial Models (merged World Model and representation streams — prediction and representation as two sides of one problem)
  - VLA assigned special "transitional/being-fragmented" positioning instead of being a parallel school
- Identified interface dimension (NL / code / subgoal image / embedding / affordance / action token) and methodology dimension (scaling / sim2real / self-improvement / distillation / co-training / multi-embodiment) as orthogonal to school axis
- Mapped existing vault works onto school × interface matrix (π series, ChemBot, ReKep, RL Tokens, GigaWorld-Policy)
- Added per-school forward predictions across three layers: 2-3 yr (high certainty) / 5 yr+ (speculative) / reverse hypothesis (if wrong)
- Recorded Ethan's three core positions:
  - Monolithic VLA won't be cloud-brain mainstream
  - VLM-as-brain has best cloud-edge fit
  - World Model + Representation form a unified school (Predictive Spatial Models)
- Recorded deeper meta-observation: the real divide between schools is "how to acquire world understanding," not "what to output"
- Created skeleton page `Embodied Brain Models` intended for incremental fill-in as new materials are ingested
- Updated `Spatial Intelligence for Embodied AI` cross-link
- Updated `90 System/index.md`
- TODO: future companion page `Embodied Cerebellum Models` once cerebellum schools crystallize

## [2026-05-30] research + verification | VLA landscape and architecture coupling
- Ran background research on the global VLA landscape (US + Chinese players) feeding the brain-model survey
- Verified PhysBrain 1.0 (DeepCybo + Zhongguancun, arXiv:2512.16793): egocentric-video-only pretraining (E2E-3M, zero real-robot trajectories), Qwen3-VL backbone + FM DiT
  - Confirmed PhysBrain has NO open-source code/weights — the `ZGC-EmbodyAI/PhysBrain` repo is only the HTML project page (index.html/styles.css/imgs/videos)
  - Corrected secondary-source errors: backbone is Qwen3-VL (not Qwen2.5-VL); "PhysGR00T/PhysPI/TwinBrainVLA/LangForce" not in paper (some are separate real repos in the org, not paper content)
- Code-level verification of VLA VLM↔action coupling (key finding): two distinct paradigms
  - Paradigm A (Joint Attention / MoE-style): π series — separate weights per expert, KV concatenation, layer-wise lockstep, block-causal; NOT a true MoE (no router). Verified via openpi pi0_pytorch.py, lucidrains, open-pi-zero
  - Paradigm B (Cross-Attention / Encoder-Decoder): GR00T, PhysVLA — VLM runs once → embedding injected as per-layer K/V into DiT, cross/self interleaved. Verified via Isaac-GR00T dit.py
  - Cloud-edge implication: Paradigm A interface = per-layer KV cache (heavy); Paradigm B interface = single embedding tensor (light) → explains deployment-oriented players (NVIDIA, DeepCybo) choosing B, research-oriented (PI) choosing A
- Corrected earlier overstatement "dual-system is industry consensus" → "functional layering is consensus; physical split still diverging, deployment-oriented work tends to split"
- Corrected π₀.5 source note attention description (earlier wrongly said "shared attention layer" / "bidirectional"): actual is MoE two-expert + block-causal joint attention, code-verified
- Added "VLA 内部的两种耦合范式" subsection to `Embodied Brain Models`
- Updated `Physical Intelligence - pi0.5` source note with code-level coupling-paradigm verification
- Method note: every accurate coupling-mechanism conclusion required primary source / code reading; no secondary summary got it right

## [2026-05-30] verification + reorg | Full π series coupling verification and per-model notes
- Verified VLM↔action coupling for the ENTIRE π series from primary sources (previously only π₀ code + π₀.5 paper were verified):
  - π*₀.6 (arXiv:2511.14759): Paradigm A inherited ("otherwise the same"); action expert "can attend to the activations in the rest of the model"; value function is a SEPARATE 670M VLM, training-only, discarded at inference
  - π₀.7 (arXiv:2604.15483): Paradigm A base (Gemma3 4B + 860M FM expert); block-causal explicitly quoted; BAGEL world model is a SEPARATE external model feeding subgoal-image tokens (Paradigm-B-like interface); MEM is a video-history encoder feeding tokens
  - RL Tokens: freezes π₀ VLA (internal Paradigm A unchanged) + separate RL adapter (capability-level decomposition, not a coupling change)
  - Conclusion: the whole π series keeps Paradigm A (joint-attention MoE) unchanged 2024→2026; capability growth comes from bolt-on modules (value fn / BAGEL+MEM / RL adapter)
- Created the MISSING canonical note `Physical Intelligence - pi0 a Vision-Language-Action Flow Model for General Robot Control` (the most-verified model previously had no source note); holds the code-verified Paradigm A mechanism
- Reorganized: moved cross-cutting Paradigm A/B comparison + GR00T + PhysVLA details OUT of the π₀.5 note (they belong in the concept page / π₀ canonical note); π₀.5 note trimmed to π₀.5-specific facts (two-step subtask→action decomposition) + pointers
- Added concise verified coupling sections to π₀.6, π₀.7, RL Tokens notes, each pointing to the canonical π₀ note
- Backfilled index Sources (π₀, π₀.5, π₀.7 were missing) and updated `Physical Intelligence` entity page (π₀ source note link, Paradigm A annotation, full Related list)

## [2026-05-30] verification | π₀.5 code-level architecture confirmation + open-source boundary
- Confirmed open-source status: openpi releases ONLY π₀ / π₀-FAST / π₀.5; π*₀.6 / π₀.7 / RL Tokens are all closed (open-source ends at π₀.5 = PI's commercialization line)
- Code-verified π₀.5 architecture against openpi JAX source (src/openpi/models/pi0.py + pi0_config.py):
  - π₀.5 shares the SAME model class as π₀ (no separate pi05.py; only a `pi05: bool` flag in Pi0Config) — strongest possible evidence of architectural consistency
  - pi0_config.py documents exactly TWO differences from π₀, neither touching the VLM↔action coupling:
    1. state input moved to discrete language tokens in the prefix (vs continuous state token in the suffix)
    2. action expert uses adaRMSNorm to inject the flow-matching timestep
  - Same make_attn_mask (block-causal), same joint two-expert forward (PaliGemma.llm([prefix, suffix], mask)), same prefix-KV-cache-then-suffix-attends inference path
  - Upgraded π₀.5 note from "paper-verified inheritance" to "code-verified same model class"
- Firmed up π₀.7 open-source field from "未开源（大概率）" to definitive (openpi only to π₀.5)

## [2026-05-30] ingest | GR00T and PhysBrain source notes (Paradigm B representatives)
- Created `NVIDIA - GR00T N1 An Open Foundation Model for Generalist Humanoid Robots`:
  - Paradigm B (cross-attention encoder-decoder), code-verified via gr00t/model/modules/dit.py
  - Frozen VLM + diffusion DiT; N1 2B / N1.5+ 3B; N1.5 key changes (frozen VLM, simplified adapter+LayerNorm, FLARE loss 0.2, DreamGen synthetic data)
  - backbone evolution Eagle → Eagle 2.5 → Eagle → Cosmos-Reason2-2B (Qwen3-VL) at N1.7 — World Model × VLA fusion
  - Open-source: code Apache 2.0, weights NVIDIA Open Model License
  - Verified benchmarks (DreamGen 13.1→38.3, Language Table 52.8→93.2, etc.)
- Created `DeepCybo - PhysBrain Human Egocentric Data as a Bridge from VLMs to Physical Intelligence`:
  - VLM-as-brain school; PhysBrain = fine-tuned Qwen3-VL brain, PhysVLA = brain + FM DiT (Paradigm B)
  - Headline: zero-real-robot-trajectory pretraining on human egocentric video; E2E-3M (3M VQA, 7 modes, Ego4D/EgoDex/BuildAI)
  - Recorded corrections vs secondary sources: Qwen3-VL not Qwen2.5-VL; "PhysGR00T/PhysPI/TwinBrainVLA/LangForce" are marketing/separate-repo names not in paper; benchmark number v1/v2 discrepancies; NOT open-source (repo is just project HTML page)
- Updated index Sources + `Embodied Brain Models` (linked both notes in Paradigm B section, moved them from todo to done)

## [2026-05-30] research + synthesis | Player landscape: two-level coupling framework
- Verified VLM↔action coupling for Helix / AgiBot GO-1 / Galaxea G0 from primary sources (Figure blog, AgiBot World arXiv:2503.06669, Galaxea G0 arXiv:2509.00576)
- KEY FINDING: "coupling" has TWO orthogonal levels, previously conflated:
  - Level 1 (system interface, high-level brain → low-level executor): single latent vector (Helix) / discrete latent-action tokens via VQ-VAE (GO-1) / natural-language sub-tasks (G0, ChemBot) / subgoal images (π₀.7)
  - Level 2 (within-VLA VLM↔action coupling): Paradigm A (joint MoE) vs Paradigm B (cross-attention)
- The two levels are orthogonal: G0 decouples at system level (language sub-tasks) but G0-VLA is internally Paradigm A (PaliGemma + flow matching); GO-1 latent planner is also Paradigm A
- FALSIFIED the over-simple "deployment-oriented → Paradigm B" hypothesis; replaced with: deployment players pursue system-level decoupling + compressed interface via TWO routes — (1) single model with clean internal split (Paradigm B: GR00T, PhysVLA), or (2) explicit multi-system with compressed interface (Helix, GO-1, G0, ChemBot). Both avoid the tightly-coupled single-model joint-MoE (π's Paradigm A, hardest to split)
- Added a decoupling-degree spectrum (research→deployment) and a verified player landscape table to `Embodied Brain Models`
- Created 3 source notes: `Figure AI - Helix`, `AgiBot - GO-1 ViLLA`, `Galaxea - G0`
- Updated index Sources and concept-page source-note list

## [2026-05-30] deepen | GO-1 Latent Planner mechanism + latent-action synthesis candidate
- Re-verified GO-1 Latent Planner I/O from AgiBot World arXiv:2503.06669 and expanded the source note:
  - LAM = "question-setter": inverse-dynamics encoder I(z|I_t, I_{t+H}) + forward-dynamics decoder, VQ-VAE codebook (k=4), learnable from frame pairs alone (no action labels) → web/human video
  - Latent Planner = "answerer": inputs = multiview images + instruction + layer-wise VLM features (24 layers, Paradigm A joint); outputs = k=4 discrete latent-action tokens P(z_t|...)
  - Train vs inference crux: targets supervised by LAM from FUTURE frames (z_t := I(I_t^h, I_{t+H}^h)); at inference the planner predicts z_t from current obs+instruction only — the actual "planning"
  - Action Expert = "decoder": diffusion conditioned on latent tokens; planner=what-should-happen (embodiment-agnostic), expert=how-to-actuate (embodiment-specific) → cross-embodiment transfer
- Added a Synthesis candidate to `Embodied Brain Models`: "learn action/semantics from unlabeled video" trend line (GO-1 latent action, PhysBrain egocentric, LAPA, Genie)

## [2026-05-30] synthesis | Home robot architecture as a hierarchical embodied agent
- Created synthesis page `Home robot architecture - a hierarchical embodied agent` — the culmination of a multi-turn discussion arc (architecture verification → deployment reality → factory needs → home needs → architecture proposal)
- Core thesis: home general-purpose robot = hierarchical embodied agent, NOT a bigger VLA; the convergence point of the vault's two lines (embodied control + persistent agent cognition)
- Captured: four-axis deployment framework; capability-vs-dependability gap (with industry corroboration: Levine, Tedrake, Jang); dependability scaffolding with verified research lines (KnowNo, Sentinel, CBF/SHIELD, World Action Verifier); capability→architecture mapping; the refined hierarchical architecture (cloud reasoner+world-model+memory / edge expert+safety+procedural-skills+distilled-small-brain)
- Recorded critical refinements to Ethan's proposed architecture: (1) reasoner ≠ world model (propose-then-verify); (2) edge safety/monitoring layer is mandatory and must work offline; (3) edge expert needs local autonomy, not passive decoding; (4) interface is plan-level not action-level; (5) cloud-only intelligence → disconnection fragility, suggest distilled edge brain; (6) privacy vs cloud-memory tension → split/federated memory
- World-model multi-level necessity judgment: prediction is (very likely) necessary for the un-trainable long tail, but not necessarily a single decision-time generative MPC — more likely heavy world model in slow cloud + light/implicit prediction on edge + training-time use
- Dual-memory mapping (cloud explicit + edge procedural) maps to Memory in Embodied AI's ideal and to the biological cerebellum's skill-consolidation function
- Confidence markers throughout (established vs Ethan+Ada forward judgment)
- Updated index Syntheses; backlinks from Embodied Brain Models and Memory in Embodied AI

## [2026-05-30] entities | Embodied-AI company entity pages
- Created 6 organization entity pages referenced by the embodied source notes (resolving dangling links):
  - `NVIDIA` — full-stack player (GR00T VLA + Cosmos world model + Isaac sim + Jetson Thor); multi-school positioning
  - `Figure AI` — Brett Adcock, 2022, Sunnyvale; Helix dual-system, fully onboard, closed full-stack
  - `AgiBot 智元` — Deng Taihua + Peng Zhihui (稚晖君), 2023, Shanghai; GO-1 ViLLA + AgiBot World (open)
  - `Galaxea 星海图` — Xu Huazhe (Tsinghua+Stanford), 2023, Beijing; G0 dual-system (open)
  - `DeepCybo` — Chen Kai, Zhongguancun-incubated, Beijing; PhysBrain egocentric-video route (not open)
  - `LimX Dynamics 逐际动力` — Wei Zhang (张巍), 2022, Shenzhen; ChemBot fully-separated dual-layer
- Verified company facts from primary/secondary sources before writing (founders, founding year, HQ, Chinese names)
- CORRECTED an error introduced earlier: Galaxea's Chinese name is 星海图 (Xinghaitu), NOT 跨维智能 (that is a different company, Dexmal). Fixed the G0 source note (author metadata + entity wikilink)
- Backfilled index Entities (Physical Intelligence was also missing) + added the 6 new entities

## [2026-05-30] ingest | Galaxea G0.5 (autoregressive VLM-as-actor) — framework-reshaping
- Downloaded PDF to `01 Raw/2026 - Galaxea - G0.5.pdf`; read via pdftotext (Read-tool poppler unavailable)
- Created source note `Galaxea - G0.5 Autoregressive VLM-as-Actor VLA`
- KEY FINDING (direction-shaping): G0.5 introduces a MORE FUNDAMENTAL architectural axis than our Paradigm A/B — **VLM-as-actor (unified autoregressive, VLM produces actions) vs VLM-as-encoder (VLM conditions a separate flow/diffusion expert)**. Our Paradigm A (π joint MoE) and B (GR00T cross-attn) are BOTH sub-types of VLM-as-encoder; G0.5 is VLM-as-actor (RT-2/OpenVLA/π0-FAST lineage, scaled up)
- G0.5 architecture: single transformer decoder (Qwen3.5-2B init), single next-token objective, reasoning+action in one stream; 3 components — learnable cross-embodiment VQ ActionCodec (active-DoF, no padding, no new params per embodiment), native in-stream CoT (bbox + subtask text + 2D trace + action hint, prompt-switchable), visual memory; optional flow-matching head only as inference accelerator
- Galaxea PIVOTED: G0 (dual-system, VLM-as-encoder) → G0.5 (unified AR, VLM-as-actor) — strong signal the actor-vs-encoder debate is unsettled
- Argument: KI (π0.5) reintroducing AR action prediction implicitly concedes AR is the protective signal; VLA-0 shows plain-AR beats π0.5-KI/OpenVLA-OFT/SmolVLA on LIBERO
- Results: LIBERO 98.9 / RoboTwin2.0 93.3 / SimplerEnv-Bridge 87.3 / DROID zero-shot 82.5 / R1 real 76.7 (vs π0.5 53.3, GR00T-N1.7 24.4) / BEHAVIOR-1K 31.4
- Updated G0 source note (successor + pivot), Galaxea entity (pivot), index Sources
- TODO (proposed, pending user): restructure `Embodied Brain Models` coupling section around actor-vs-encoder as the top-level axis, with Paradigm A/B as encoder sub-types and unified-AR as a third class

## [2026-05-30] refine | Restructure VLA coupling axis (actor vs encoder) + raw-artifact policy
- Restructured `Embodied Brain Models` VLA section around **VLM-as-actor vs VLM-as-encoder** (per Ethan's scoping corrections):
  - SCOPED as a VLA-school-internal axis, explicitly NOT a cross-school top-level axis (World Model / Predictive Spatial noted as orthogonal)
  - TONED DOWN: "important, currently-unsettled architectural divergence", not "most fundamental"
  - VLM-as-encoder now contains Paradigm A (π joint MoE) + Paradigm B (GR00T/PhysVLA cross-attn); VLM-as-actor (unified AR: RT-2→OpenVLA→π0-FAST→G0.5) added as the other branch with both sides' arguments (unsettled)
  - Toned down the same wording in the G0.5 source note
- Raw-artifact policy: removed the 27MB G0.5 PDF from the repo (working tree + index); switched the note to URL-only (Tier 1), consistent with prior URL-only ingests (GigaWorld, RL Tokens)
  - Note: the blob remains in git history (commit 2b61d04); a full history purge would need a force-push — not done (non-destructive removal only)
  - Codified the practice in `90 System/AGENTS.md` 01 Raw section: large binaries (PDFs > a few MB) prefer URL-only; preserve local copies only when small/important

## [2026-05-30] deepen | G0.5 architecture + training details (from PDF)
- Re-read G0.5 PDF (cached text) to answer Ethan's precise questions; expanded the source note:
  - VLM: initialized from Qwen3.5-2B; core decoder essentially unchanged (no separate expert / MoE / cross-attn). Additions are minimal: vocabulary extension (action codes + DoF-group/noop special tokens), visual memory, external ActionCodec, optional FM head
  - Vocabulary unification: one AR stream holds three "sub-languages" sharing the vocab — text (Qwen native), spatial coords (`<loc####>` location tokens for bbox/trace), actions (`<action####>` RVQ codes + structural markers); one CE loss, one decoder
  - CoT = 4 self-describing primitives in fixed coarse-to-fine order: Subtask → BBox → Trace → ActionHint → Action; `<EOV>` marks reasoning→action boundary
  - ActionHint defined: frame-level natural-language gripper/motion directive (e.g., "close the left gripper while moving forward")
  - "When to reason vs act" is NOT free model choice — controlled by (1) self-describing labels + fixed order, (2) prompt directive selecting targets, (3) training over 8 CoT formats (incl. no-CoT); eval uses fixed no-CoT
  - Training: single next-token CE on generative segment only, no aux/distillation; ~100M VL co-training (50M web + 50M embodied + 5M in-house VQA), VQA:action 1:4; AdamW lr 1e-5
  - Autolabeling pipeline (key data trick): language (subtask/action-hint/instruction) via temporal segmentation + Gemini 3 / Doubao Seed 2.0 Pro API; bbox/masks via multimodal FM + SAM3 tracking; 2D traces via forward kinematics projected to head-camera plane → so the "reasoning" labels are partly DATA-LEVEL distillation from large multimodal models
- Updated checklist training-data row accordingly

## [2026-05-30] correct + deepen | G0.5 open-source status + AR-vs-FM CoT ablation
- CORRECTED over-optimistic open-source field: verified GitHub `OpenGalaxea/G05` is only the project webpage (TypeScript/Vite), `OpenGalaxea/G0` likewise (HTML); HF search finds only third-party fine-tunes — no official code/weights repo located. Softened metadata + checklist row 6 to "claimed but unverified; no code to reference"
- Added the §5.6 CoT × decoder-interface ablation (single checkpoint, inference-time toggle of AR-vs-FM head and CoT on/off):
  - Finding 1: CoT helps only on multi-stage long-horizon tasks (PP Bench single-stage ≤1.6pp; Air Fryer/Bacon clear gains)
  - Finding 2: AR follows CoT more closely than FM (Air Fryer 72 vs 48, Bacon 64 vs 44 language-following under matched CoT); hypothesis = decoding interface (AR attends CoT directly vs FM conditions on a pooled summary)
  - CoT quality equal across heads (~90/85/80%), supporting "interface not reasoning content"
- Recorded key clarification + limitations (resolving Ethan's questions): FM head conditions on a POOLED SUMMARY of the hidden state — NOT the full per-token embedding sequence, NOT cross-attention (Paradigm B); pooling is MORE compressed than B; exact pooling mechanism is underspecified and no code exists to check. Also flagged that the pooled FM baseline is not fully fair to the encoder camp, n=5 small samples, and the mechanism is an unverified hypothesis

## [2026-05-30] maintenance | Ingest-workflow cross-ref + history-purge correction
- Added a pointer in `90 System/AGENTS.md` Ingest workflow step 1 to the `01 Raw/` raw-tier rule (large PDFs → URL-only; keep local copy only when small/important), so the size-based capture decision is discoverable from the workflow itself, not only from the directory-semantics section
- Confirmed log↔reality consistency for the raw-tier rule: it is actually present in AGENTS.md (01 Raw section, "For large binaries... prefer URL-only"), matching the earlier log claim — verified, not just claimed
- CORRECTION to the earlier "refine ... raw-artifact policy" entry which said the G0.5 blob "remains in git history (force-push not done)": this was SUBSEQUENTLY superseded — the 27MB blob was fully purged from history via `git filter-branch` + `--force-with-lease` push (`.git` 40M→14M; backup branch + refs/original removed + reflog expire + gc --prune=now). Any other clones would need re-clone / hard reset to `origin/master`

## [2026-05-30] correct | π₀.5 action-expert size error (860M → 300M)
- While answering "π₀.5 vs π₀ differences", caught a cross-note inconsistency: π₀.5 note listed action expert as **860M**, but openpi config.py verifies all pi05 training configs use `Pi0Config(pi05=True)` → default `action_expert_variant="gemma_300m"` (300M), same as π₀. The 860M is **π₀.6's** action expert (Gemma 3 4B + 860M), mis-copied into the π₀.5 note
- Fixed both occurrences in `02 Sources/Physical Intelligence - pi0.5` (checklist row 2 + two-step section) with explicit note that 860M belongs to π₀.6
- Added a correction marker (not overwrite) to the `01 Raw` π₀.5 capture, per the raw-preservation principle, also flagging its stale "shared attention layer" wording
- Verified 860M is CORRECT for π₀.6 and π₀.7 notes (Gemma 3 4B + 860M) — left untouched
- Net: π₀.5 = π₀'s architecture (gemma_2b 3B + gemma_300m 300M, Paradigm A) + heterogeneous co-training recipe + two-step hierarchy + KI, all for open-world generalization; the two code-verified arch tweaks (state-as-discrete-token, adaRMS timestep) remain the only structural changes

## [2026-05-30] deepen | π₀.5 action-expert I/O + cross-subtask memory (precise mechanism)
- Added "Action expert 的 I/O 与跨子任务记忆" subsection to the π₀.5 source note (answering Ethan's 3 precise questions, code-verified):
  - Q1: action expert input does NOT include VLM hidden states — each expert computes its own K/V from its own hidden states; VLM enters via concatenated joint-attention K/V, not as input embeddings
  - Q2: action expert's direct token input = action (noise) tokens only (`if self.pi05: action_expert_tokens = action_tokens`); (image+instruction+subtask+state) are the prefix, attended via PER-LAYER KV cache (lockstep, not final-layer, not pooled — contrast GR00T cross-attn-to-final / G0.5 pooled FM head); proprio/state in prefix (default discrete; discrete_state_input configurable, pi05_libero=False)
  - Q3: NO cross-subtask retention — context rebuilt from current observation each inference; KV cache only for current prefix; progress is observation-driven, not KV-retained. This is the structural gap π₀.7's MEM later fills (→ Memory in Embodied AI)
- Also fixed a stale "共享 attention 层" wording in the existing 信息流详解 step 3

## [2026-06-09] ingest | TwinBrainVLA (DeepCybo) — anti-forgetting dual-VLM
- Created source note `DeepCybo - TwinBrainVLA Asymmetric Mixture-of-Transformers for Anti-Forgetting VLA` (arXiv:2601.14133). PDF read from /tmp (URL-only per raw-tier rule, ~6.8MB not committed)
- Same org/team as PhysBrain (DeepCybo / ZGC-EmbodyAI; authors overlap, Kai Chen corresponding)
- Core: structural fix for catastrophic forgetting in VLA fine-tuning. Quantified the problem: Qwen3-VL POPE 88.87% → 0.04% after standard VLA training; 1:1 co-training also fails
- Architecture: asymmetric dual-VLM — frozen "Left Brain" (generalist, preserves pretrained knowledge) + trainable "Right Brain" (specialist, +proprio, generates actions); AsyMoT (Asymmetric Mixture-of-Transformers) lets Right Brain attend joint KV [sg(K_L);K_R] (stop-grad on frozen Left) — joint attention, NOT cross-attention (paper distinguishes); fused rep conditions a flow-matching action expert. So: VLM-as-encoder, Paradigm-A (joint MoT) variant with TWO full VLMs
- Benchmarks: SimplerEnv 64.5% (>GR00T-N1.6 57.1% +7.4%), RoboCasa 54.6% (>47.6%), LIBERO 97.6%, real-robot ≈ π0.5; ablation: unfreezing Left Brain -7%
- Framework placement: added a "catastrophic-forgetting: three structural solutions" mini-table to `Embodied Brain Models` (KI/π0.5, unified-AR/G0.5, dual-VLM/TwinBrainVLA). Flagged naming caveat: TwinBrain's Left/Right = generalist-vs-specialist VLMs, NOT cloud-brain/edge-cerebellum
- Updated DeepCybo entity (two complementary lines: PhysBrain=data-side, TwinBrainVLA=architecture-side), PhysBrain note (TwinBrainVLA now ingested, not just a marketing term), index Sources, concept-page source-note list
- GitHub repo ZGC-EmbodyAI/TwinBrainVLA = README+assets only (no code), consistent with PhysBrain/G0 pattern

## [2026-06-09] clarify | G0.5 uses NO world model (anti-world-model stance)
- Verified from the G0.5 paper: it contains no world-model component — no future-frame/state prediction, no subgoal-image generation (that's π0.7/BAGEL), no synthetic-data world model (that's GR00T Cosmos/DreamGen). Components are only VQ ActionCodec + in-stream CoT (subtask/bbox/2D-trace/action-hint, all reasoning primitives not future prediction) + visual memory (past history, not future)
- "world action models" appears only as the 3rd baseline family it compares against (cites Fast-WAM, Motus in related work)
- Added a "与 Predictive Spatial / World Model 流派的关系：明确不用" paragraph to the G0.5 note — positions G0.5 as the deliberate opposite of the world-model route, contrasting π0.7 (BAGEL) / GR00T (Cosmos) on the "does a VLA bolt on a world model?" axis

## [2026-06-03] ingest | DyQ-VLA: Temporal-Dynamic-Aware Quantization for Embodied VLA Models
- Post-knowledge-cutoff paper (arXiv:2603.07904, submitted 2026-03-09, v2 2026-03-14) — located + verified via web search and arXiv abstract/HTML fetch; new ingest, not a backfill
- Raw: URL-only (Tier 1); raw note records the (partial verbatim) abstract + extracted method/eval, with an explicit caveat that mechanism details came from an automated HTML reader and are NOT yet hand-verified against the PDF
- Created source note `Zheng et al. - DyQ-VLA Temporal-Dynamic-Aware Quantization for Embodied Vision-Language-Action Models`
- KEY FRAMING: adds a THIRD route to `Model quantization` beside representation-design (HiFloat8) and distribution-reshaping (SmoothQuant): **dynamic / runtime-adaptive (input-conditioned) mixed precision** — bit allocation as a function of task temporal state. New orthogonal axis = *when the config is decided* (static vs runtime), above the existing *what you intervene on* (format vs distribution) axis
- First **embodied/VLA quantization** note in the vault and first bridge between the quantization cluster and the embodied/VLA cluster
- Method in one line: static W4 weights + dynamic activations (W4AX, X∈{2,4,8,BF16}) gated by a cheap real-time kinematic proxy (motion fineness + angular jerk → sensitivity score → BF16 fallback or offline-calibrated bit LUT); base model OpenVLA (VLM-as-actor lineage, cf. G0.5 note); uses the vault's existing SmoothQuant as a W4A4 baseline
- Results (high-confidence, triangulated across abstract/search/HTML): 99.5% perf at 30.9% memory; 1.49× sim (LIBERO) / up to 1.43× real-world
- Left light on purpose (incremental maintenance): deeper embodied-cluster integration (Embodied Brain Models cross-link, a dedicated VLA-quantization concept page) deferred pending a second source or user direction

## [2026-06-03] verification | DyQ-VLA mechanism hand-verified + open-source + raw-artifact decision
- Hand-verified mechanism/baselines/results by reading the full PDF (v2, 9 pp) directly — extracted text via `pypdf` (installed ad hoc; Read-tool poppler unavailable, as in prior ingests). The earlier automated-reader extraction proved accurate; this pass mainly added precision and caught items the secondary extraction missed
- CONFIRMED / REFINED:
  - Affiliations (were "unverified"): Peking University (lead — School of CS / School of EECS) + South China University of Technology + Beijing Normal University; corresponding = Xiang Chen (PKU)
  - Base = OpenVLA (~7B, autoregressive token-by-token, chosen for homogeneity); PTQ; W4AX = INT4-frozen weights + dynamic activations {2,4,8,BF16}
  - Proxy: Motion Fineness M=1−‖a_xyz‖/μ95 (macro, r=0.90), Angular Jerk J=‖Δa_rot‖/ν95 (micro, r=0.87) vs ground-truth s_t=D_T/e_t; fused S=max(0,λM̃+(1−λ)J̃); asymmetric hysteresis (instant upgrade, delayed downgrade via window K); offline-calibrated LUT Φ:S↦{2,4,8}; θ_fp=0.5, W_macro=10, W_micro=5
  - "QVLA" baseline is REAL (arXiv:2602.03782, per-channel) — removed the earlier "to verify" hedge; actual VLA-quant baselines = QVLA + SmoothQuant (SQAP-VLA arXiv:2509.09090 cited as related). EaqVLA is NOT used by this paper
  - Real-world results use QLoRA fine-tuning (rank 32, 4-bit frozen) for sim-to-real → not pure plug-in quantization (now flagged as a limitation)
  - Table-only critical read: DyQ-VLA beats QVLA by just +0.1% avg SR and at slightly MORE memory (4.7 vs 4.3 GB) → the real contribution is the dynamic paradigm + speed, not Pareto-dominating the static SOTA
  - Sibling work: same PKU group's KERV (kinematic-rectified speculative decoding, arXiv:2603.01581) reuses the same "kinematics as runtime signal" idea → broader thesis to watch
- OPEN SOURCE: none located — no release claim in the paper, no GitHub/project link, no repo found via web search (2026-06-03). Recorded as "none located"
- RAW-ARTIFACT DECISION: downloaded PDF measured 4.94 MB (> "a few MB") and is trivially re-accessible on arXiv → kept **URL-only (Tier 1), NOT committed**; matches the raw-tier rule and the G0.5 / GigaWorld / RL Tokens precedent. Temp PDF/text used only for verification, then deleted
- Upgraded both notes: caveats changed from "automated extraction, not hand-verified" → "hand-verified against PDF (v2)"; added verified formulas, full results tables, affiliations, open-source status, and the QVLA-margin / QLoRA / KERV refinements
- `Model quantization` topic + `index.md` left unchanged (re-checked, still accurate; avoided churn)

## [2026-06-03] ingest | Ω-QVLA: uniform-W4A4 VLA quantization (2nd VLA-quant source) + new `VLA quantization` concept page
- Ingested Ω-QVLA (Wang et al., McGill / Université de Montréal / Mila + BUPT / SJTU / SimpleWay.ai; arXiv:2605.28803, 2026-05-27) — the user's third quantization paper and second VLA-quant source
- Hand-verified against the full PDF (v1, 18 pp; pypdf). Raw: URL-only (Tier 1) — PDF measured 8.12 MB, not committed
- OPEN SOURCE verified REAL (not a landing page): https://github.com/UCMP13753/Omega-QVLA, Apache-2.0 — `gr00t/quantization/` modules + build/merge/eval scripts, weights via HF (contrast: DyQ-VLA released none)
- Method: first training-free PTQ to compress BOTH the LLM backbone AND the entire diffusion DiT action head to UNIFORM W4A4 (no mixed precision), overturning the "DiT action head too sensitive to uniformly quantize" belief. Two parts: (1) composite SVD·Hadamard rotation (SVD flattens weight row-energy; Hadamard diffuses residual activation outliers), block-wise (64) + zigzag weight-norm permutation; (2) per-step DiT activation scale table over T=8 Euler denoising steps. Asymmetric solver: GPTQ on LLM weights, plain RTN on DiT (rotation already flattens DiT weights → GPTQ there injects a harmful calibration bias)
- Models = π0.5 + GR00T N1.5 (both already in vault). Results: W4A4 ≈ FP16 (π0.5 98.0 vs 97.1; GR00T 87.8 vs 87.0), ~71–72% static memory saved; smoother real-world bimanual control (ARX R5) than QuantVLA. NOTE: NO wall-clock latency reported (deferred to kernel support) → cannot be compared to DyQ-VLA on speed
- KEY SYNTHESIS: Ω-QVLA and DyQ-VLA are opposite answers to "does VLA low-bit need mixed precision?", split by action-head architecture — DyQ-VLA (autoregressive OpenVLA) varies the BIT-WIDTH dynamically (route 3); Ω-QVLA (diffusion π0.5/GR00T) keeps UNIFORM W4A4 and varies only the SCALE per denoising step (route 2, rotation/reshaping). Both react to temporal dynamics but draw opposite conclusions
- Created concept page `VLA quantization` (second-source threshold met, as flagged in the prior DyQ-VLA ingest) holding the problem framing (why VLA quant ≠ LLM quant), the DyQ-VLA↔Ω-QVLA contrast table, the route mapping, and the cited landscape (QVLA arXiv:2602.03782, QuantVLA arXiv:2602.20309, SQAP-VLA arXiv:2509.09090, KERV arXiv:2603.01581)
- Updated `Model quantization` (Ω-QVLA under Route 2 = rotation/reshaping; VLA-quant sub-cluster pointer; new subthemes + the "does VLA need mixed precision?" open question) and `90 System/index.md` (Sources + new Concept)
- Cross-links: outbound wikilinks from the new notes to π0.5 / GR00T source notes (backlinks auto-surface in Obsidian); explicit backlinks into those notes deferred to avoid churn
- Transferable nugget recorded in the source note: AdaLayerNorm→per-step-scale — only the attention QKV layers reading the time-conditioned AdaLayerNorm output need per-step scales; plain-LayerNorm MLP paths don't. Candidate general DiT-quantization principle

## [2026-06-03] deepen | Ω-QVLA rotation internals — code + math deep-dive written into the source note
- Multi-turn discussion with Ethan dissecting Ω-QVLA's rotation; clone-read the repo (`UCMP13753/Omega-QVLA`) + worked the algebra. Added a `Method deep-dive — rotation internals` section to the Ω-QVLA source note (5 findings) and two new `What feels limited` bullets
- (1) Activation rotation is **online** (per-forward input perm + block rotation, plus an output "row restore"); only weight-side rotation is folded offline. DiT adds per-step scale dispatch online (T=8 × ~16 blocks). Released code is **fake-quant** (BF16/FP32 `F.linear`, no real INT4 GEMM) → rotation is pure overhead with no speedup; this is the code-level root cause of the paper's missing latency, and SVD (not a fast transform) is structurally hard to amortize vs QuaRot's FHT. Code refs: `gptq_layers.py:590–604/662–678/689–703`, `duquant_layers.py:591–600/635–648`, `dit_step_context.py`
- (2) Row energy depends only on U and σ because `WWᵀ = UΣ²Uᵀ` (V cancels via `VᵀV=I`); `‖w_i‖²=Σ_k σ_k² u_ik²` = diagonal of the Gram, and `σ_k²` are literally its eigenvalues. V drops out because right-mult by orthogonal Vᵀ is an isometry (preserves row length). After rotation `‖w̃_i‖²=σ_i²` (de-mixed, but spectrum still skewed)
- (3) Per-channel quant optimizes **crest factor** `max/rms` (`SQNR ∝ (rms/max)²`), not energy. Energy = the rms reference; SVD balances energy (necessary, not sufficient), Hadamard converts balanced L2 → low L∞ via `‖zH‖∞≤‖z‖₂/√n`. The paper *needing* Hadamard is the implicit admission energy alone is insufficient
- (4) **Incoherence, not orthogonality**, spreads the max: spike test → peak = `max_j|R_ij|`; Hadamard `=1/√n` guaranteed, SVD's U can `≈1` (no guarantee; U is the *least* incoherent / data-aligned rotation). Division of labor: SVD wins weights (26→6 vs H 19), Hadamard wins activations (20→1.6 vs SVD 17). **Ablation gap caught**: no Hadamard-only (SVD-removed) end-to-end row → SVD's necessity unproven (QuaRot/SpinQuant work with Hadamard/learned rotation alone)
- (5) **Figure 2 transpose trap**: input-axis orthogonal rotation **preserves** per-output-channel L2 norm, so Fig 2's changing "row norm" is NOT output-channel L2 norm — it's per-**input**-channel norm (code: `weight energy = mean(W²,axis=0)` over outputs, `plot_outlier_flow_3d.py:73`; text `σ_i²` = input channel). Text uses `[Cin,Cout]` (row=input ch), code/figures use `[out,in]` (row=output ch) → "row" flips meaning. Per-output-channel quant benefits via the "vertical stripe" mechanism (heavy input channel inflates every output channel's max → SVD+Hadamard lower the max, not the L2)
- No new pages; durable analysis filed into the existing source note. Temp clone removed after the dive

## [2026-06-03] deepen | Ω-QVLA DiT per-step activation quant — deep-dive findings (6)–(7)
- Continued the discussion into DiT activation quantization; extended the Ω-QVLA source note's `Method deep-dive` from 5 → 7 findings (renamed section from "rotation internals" since it now also covers DiT quant) + extended the latency `What feels limited` bullet
- (6) DiT activations are quantized **per-step × per-channel, offline-calibrated** (not per-token): `∆_{ℓ,t,j}=σ̂(X'_{t,:,j})/qmax`, retrieved by step index (`dit_step_context.py`). The two axes mirror **AdaLayerNorm**: `γ(τ),β(τ)` predicted from the timestep → per-channel (vector) × per-step (function of τ); drift localizes to post-adaLN QKV (App A.6, ~15–20% monotonic q999 drift), MLP path flat (its pre-norm is plain LN). Input genuinely differs each step (shared obs conditioning + changing action iterate x_τ + τ → γ(τ)). Why static-per-channel ≻ dynamic-per-token: (A) per-channel divides out the known γ_j(τ) structure, per-token is dominated by each token's biggest channel (wastes range on small-γ channels); (B) calibrated robust-peak clips spikes + deterministic (closed-loop) + stable on short action seqs. Trade: per-token factors out of matmul + needs no calib → per-channel is accuracy-over-deployability
- (7) The real cost is **not** the lookup (~free O(1) index; cheaper than per-token's runtime reduction) nor the per-channel multiply (same element-wise op as per-token) — it's that a per-channel **activation** scale sits on the contraction axis and **doesn't factor out of the matmul**: either dequant activations to FP (lose INT speedup) or fold per-step into weights (8× weights). SmoothQuant's per-channel scale is *static* → folds offline once (free); Ω-QVLA's is per-step → can't → more deployment-hostile than the lineage it extends. Moot in the released fake-quant code (BF16 matmul, no INT GEMM)
- Still no new pages; all filed into the existing source note

## [2026-06-03] ingest | QuantVLA (3rd VLA-quant source; Ω-QVLA's baseline) — completes a 3-way VLA-quant cluster
- Ingested QuantVLA (Zhang et al., Ohio State / Michigan / CityU HK; **CVPR 2026**; arXiv:2602.20309) at user request — it is Ω-QVLA's main baseline. Hand-verified against the full PDF (v4, 13pp incl. App A–G; pypdf). Raw: URL-only (Tier 1, PDF 3.99 MB)
- Open source verified real: https://github.com/AIoT-MLSys-Lab/QuantVLA (Apache-2.0, `gr00t/` quant code, 34★). **Disambiguation recorded: QuantVLA (Zhang, CVPR, scale-calibrated) ≠ QVLA (Xu, ICLR 2026, arXiv:2602.03782, per-channel)** — different papers, both Feb 2026. (Author Haokun Lin is DuQuant's first author.)
- Method: training-free, DuQuant-based rotation PTQ. (1) selective layout — integerize all LLM linear + all DiT MLP, KEEP DiT attention Q,K,V,O FP16 (preserve integer-GEMM operator schedule); (2) ATM (per-head α matching teacher/student logit Std → fixes softmax temperature √d/(s_q s_k)); (3) OHB (per-layer β matching output RMS → fixes residual energy s_v s_o). ATM/OHB folded into dequant scales → no new ops, no extra GEMM. Analytic contribution: first-order error-propagation account of DiT fragility
- Results (W4A8, LIBERO): π0.5 97.6% / 1.28 GB / 70% (> FP16 97.1%); GR00T N1.5 88.0% / 0.91 GB / 55% (> FP16 86.5%); also W4A4 π0.5 95.3%. Beats FP16. **Memory + accuracy only — NO wall-clock latency**, but designed for **real integer GEMMs** (unlike Ω-QVLA's fake-quant)
- KEY SYNTHESIS: QuantVLA + Ω-QVLA = a matched pair (same DuQuant lineage, same π0.5/GR00T, opposite bets) — QuantVLA keeps DiT attention FP16 + real int GEMM (conservative/deployable), Ω-QVLA quantizes it uniformly W4A4 (aggressive/fake-quant). "First" claims reconcile by granularity (DiT MLP vs whole DiT incl. attention). Neither reports latency, only DyQ-VLA does → latency is the cluster's systematically missing number. Three lenses on one fragile locus: QuantVLA temperature+residual-energy / Ω-QVLA AdaLayerNorm-QKV / DyQ-VLA fine-manipulation spike
- Upgraded `VLA quantization` to a **3-way** landscape (QuantVLA + 3-way table + "fragile locus" section + QuantVLA≠QVLA disambiguation); updated `Model quantization` (QuantVLA under Route 2; within-route DiT-attention disagreement) + `index.md` Sources. DuQuant flagged as candidate stub (now underpins 2 sources). Temp clone/PDF cleaned

## [2026-06-03] ingest | DuQuant (rotation-PTQ foundation of the VLA-quant cluster)
- Ingested DuQuant (Lin et al.; UCAS / Tsinghua / CASIA / CityU HK / ZJU; **NeurIPS 2024 Oral**; arXiv:2406.01721) at user request — the rotation-based W4A4 **LLM** quant method both QuantVLA and Ω-QVLA reparam over (QuantVLA shares its first author Haokun Lin). Hand-verified against the full PDF (v3, 29pp; pypdf). Raw: URL-only (Tier 1, PDF 22.86 MB — largest yet, not committed)
- Open source verified real: https://github.com/Hsu1023/DuQuant (MIT, `quantize/` + `get_rot.py`, 180★; DuQuant++ follow-up announced Apr 2026)
- Method: "dual transformation" = per-channel smoothing Λ + greedy **data-aware** block-diagonal rotation R̂(1) (uses outlier dims as prior; ≠ QuaRot's random Hadamard) + **zigzag permutation** P (balances inter-block variance, Thm 2) + 2nd rotation R̂(2); G=ΛR̂(1)PR̂(2) folded with G⁻¹ into weights. Per-token act / per-channel weight; RTN, no GPTQ. Two theorems (within-block max ↓; zigzag bounds per-block mean)
- KEY: first to localize **"massive outliers" at the FFN down-projection input** (few tokens, ~1000× the median) vs the long-known "normal outliers" — this is the **origin of Ω-QVLA's pathological `LLM.L02.down_proj` finding**. SmoothQuant fails on massive outliers (smoothing factor → new weight outliers)
- Results: SOTA W4A4 (LLaMA2-7B 6.28 PPL vs FP16 5.47, SmoothQuant 83); +5–10% QA over Atom; LLaMA3-8B robust (8.56 vs SmoothQuant 210). vs QuaRot: DuQuant-RTN ≈ QuaRot-GPTQ (skips GPTQ). **Reports REAL speedup** (2.08× prefill, 3.5× decode-mem, real W4A4 kernel; quantizes 7B in 50s) — notable that the LLM root reports latency while its VLA descendants don't
- Connections recorded in the source note: (a) DuQuant = the "orthogonal rotation + diagonal scaling" well-conditioned recipe from the κ(R) discussion; (b) greedy data-aware rotation = data-aware end vs QuaRot's data-independent Hadamard (same SVD-vs-Hadamard axis); (c) block-64 + zigzag is exactly what QuantVLA/Ω-QVLA inherit
- Updated `Model quantization` (DuQuant under Route 2 Sources + Route-2 narrative + Related) and `VLA quantization` (DuQuant linked as the ingested shared ancestor across taxonomy/landscape/related) + `index.md` Sources. Flagged QuaRot (arXiv:2404.00456) as the natural next ingest + a possible `Rotation-based quantization` concept page. Temp PDF/text cleaned

## [2026-06-13] ingest | Motus: A Unified Latent Action World Model (Tsinghua TSAIL × Horizon Robotics)
- Created source note `Bi et al. - Motus A Unified Latent Action World Model` (arXiv:2512.13030, v2 2025-12-25). Verified via arXiv abstract + HTML method/results sections (no PDF committed; URL-only Tier 1). Followed several multi-turn discussion turns on VLA inference data-flow / graph compilation / world-model-at-inference that set up this ingest
- Core: a unified **latent-action world model** that packs three experts — understanding (**Qwen3-VL-2B**) + video generation (**Wan 2.2 5B**) + action (flow-matching, AdaLN) — into one **MoT / 范式 A joint attention** ("Tri-model Joint Attention", shared MHSA). A **UniDiffuser-style per-modality timestep scheduler** turns one weight set into **5 switchable inference modes**: VLA / World Model / IDM / VGM / Joint Prediction
- Latent actions from **optical flow** (pixel-level "delta action"); **six-layer data pyramid** (web → egocentric human video → synthetic → task-agnostic → multi-robot → target-robot, quantity↓ quality↑) + **three-stage training** (VGM-only → unified w/ latent actions → SFT w/ real actions)
- Benchmarks (self-reported): RoboTwin 2.0 88.66% (+45% vs π0.5, +15% vs X-VLA); LIBERO-Long 97.6 (=X-VLA SOTA); real AC-One 63.22% vs π0.5 14.79%, Agilex-Aloha-2 59.30% vs 48.60%; +11~48% across real tasks. **No wall-clock/latency** (10 flow-matching steps stated). Open source: project page only (motus-robotics.github.io/motus), no code/weights located → treated as not-open
- KEY FRAMINGS recorded: (a) Motus makes "world model at inference" a **runtime knob** — a third path beyond train-time-only (GigaWorld/FLARE) and latent-compression (VPP/DreamVLA); (b) **structural rhyme with TwinBrainVLA** — both 3-transformer MoT joint attention, third slot = video generator (Motus) vs 2nd VLM (TwinBrain) → 范式 A's MoE slot is becoming a pluggable expansion socket; (c) vs GigaWorld-Policy: same "drop video at inference" goal, opposite mechanism (Motus timestep-mode-switching + bidirectional joint attention vs GigaWorld causal-mask hard-isolation + fixed drop); (d) vs G0.5: clean opposites on the world-model axis, yet both use latent/VQ-ish action tokens
- OPEN deployment question logged (no code/latency to resolve): in VLA mode, does the 5B video expert still run forward (tokens in joint attention) though video isn't denoised? Decides edge-deployability
- CORRECTION to `World-Action Models`: it had Motus mis-listed as "1st-gen Bidirectional (must generate video at inference)". Verified against the paper → Motus is **mode-switchable (VLA mode skips video)**; reworked the page's architecture-evolution into 4 generations (added "第四代: Mode-Switchable / 统一时间步调度"), wikilinked Motus + GigaWorld, added an explicit 修正记录 note
- Wiki updates: `Embodied Brain Models` (MoT "pluggable slot" note in 范式 A; Motus added to the latent-action synthesis candidate + a new "world-model-at-inference 4-tier" synthesis candidate); `World-Action Models` (4-gen rework + comparison-table + Related); wikilinked Motus in the G0.5 baseline reference; `index.md` Sources
- Horizon Robotics 地平线 flagged as a candidate entity page (not created — measured incremental maintenance; Motus is Tsinghua-led, Horizon is co-author)
- NOTE (pre-existing log quirk, not fixed): the [2026-06-03] quant-cluster block physically sits *after* the [2026-06-09] TwinBrainVLA/G0.5 entries (parallel work streams merged out of date order). Left as-is to avoid churn; candidate lint task if a chronological pass is wanted

## [2026-06-13] ingest | Kairos 3.0-4B (ACE Robotics) — edge generative video world model, NO PAPER, code-verified
- User request: add "Kairos 3.0 4B world model" + find its paper (gave GitHub kairos-agi/kairos-sensenova, couldn't find a paper)
- PAPER SEARCH RESULT: **no paper / no arXiv / no technical report exists** (as of 2026-06-13). Verified via: README "📑 Paper" badge = empty placeholder; arXiv search twice (general + arxiv.org-restricted) → nothing titled Kairos; 2026-03 launch press explicitly states no academic paper; June re-search found only reprints of the March press. → architecture verified directly from open code instead
- ORG puzzle resolved: **ACE Robotics (Shanghai), founded by Wang Xiaogang 王晓刚 = SenseTime co-founder** → repo/weights named `sensenova` (SenseTime/SenseNova lineage); GitHub org `kairos-agi` = "Kairos Team". Released 2026-03-13, Apache-2.0
- CODE-VERIFIED architecture (kairos_4b_config.py + kairos_dit.py): `KairosDiT` = video diffusion transformer, dim 2560 / 32 layers / 20 heads / ffn 10240, flow-matching, Conv3d patch [1,2,2]. **Hybrid linear attention CONFIRMED**: `use_linear_attns=[(i+1)%4==0...]` → every 4th layer GatedDeltaNet (FLA lib, chunked) + 3/4 full softmax = 1:3, 25% linear (this is the "custom hybrid linear attention operator"). VAE = Wan2.1; text encoder = Qwen2.5-VL-7B-AWQ; modes T2V/I2V/TI2V; edge variant via DMD (Distribution Matching Distillation)
- **KEY FINDING (verify-don't-assume)**: open release is a **pure video generator — NO action head, NO proprioceptive input, NO policy output** (Head outputs only video latents). PR's "unified understanding-generation-PREDICTION / action prediction / closed-loop control" is NOT in the open code → recorded the PR-vs-code gap explicitly; Kairos open = only the "world model" half of a WAM, action (if any) is external/unreleased
- Created source note `ACE Robotics - Kairos 3.0 a Real-Time Generative Video World Model` (separates code-verified facts / vendor-reported benchmarks / unverified action claims) + entity page `ACE Robotics`
- Wiki: `Embodied Brain Models` pixel-level WM row — added Kairos + softened the "云脑 imagination，不适合下端" claim (Kairos's 4B+linear-attn+DMD is an explicit edge-real-time attempt, to be reproduced); `World-Action Models` — added a "video WM ≠ WAM" boundary note (Cosmos/Kairos = the WM half only); index Sources + Entities
- Positioning recorded: vs NVIDIA Cosmos (explicit rival, "72× faster", DreamGen Bench); vs Motus (shared Wan+Qwen+flow-matching stack, opposite bet — Motus integrates an action expert, Kairos drops action for edge real-time)
- Benchmarks logged as vendor-reported only (PAI-Bench 80.03, WorldModelBench 8.94, VideoPHY 45.55; "1.5× real-time on Jetson Thor T5000"; 480P 11.7s/23.5GB on 1 A800) — no third-party reproduction, no paper
- Notable: a **real** open-source (code+weights, Apache-2.0) — the positive exception to the usual "PR-only / project-page-only" pattern in the China embodied cluster

## [2026-06-13] deepen | Kairos component relationship + DMD distillation (filed into the source note)
- Q from Ethan: how do the "4B" and Wan2.1 VAE + Qwen2.5-VL-7B + flow-matching relate, and what is DMD distillation? Added two subsections to the Kairos source note
- Component relationship: clarified the standard latent-video-diffusion stack — **"4B" = KairosDiT (the denoiser) ONLY**; Qwen2.5-VL-7B (text/MM encoder, frozen, 7B) and Wan2.1 VAE (pixel↔latent codec, frozen) are external/borrowed and NOT counted in the 4B; flow-matching is the DiT's generation math. SD/Flux-analogous. The "Wan video VAE + Qwen-VL + flow-matching" stack = a shared substrate with Motus (de-risks reading either note's size claims)
- DMD = Distribution Matching Distillation (Yin et al., MIT/Adobe, CVPR 2024; DMD2 follow-up): step-distillation (collapse ~30-step sampling to 1-4 steps, SAME params) via KL(student‖data) whose gradient = real-score(frozen teacher) − fake-score(online aux model), GAN-like. Distinguished from the vault's methodology-axis "Distillation 大模型→小模型" — that's SIZE distillation, DMD is STEP distillation (orthogonal). Kairos's edge trio = linear attention (per-step compute) × DMD (step count) × 4B (params), each cutting one multiplicative factor
- Honesty caveat recorded: DMD usage confirmed from filenames; DMD1-vs-2 / exact step count not line-verified. No new pages; deepened the existing source note only

## [2026-06-23] deepen | DuQuant rotation construction & relationship to QuaRot (filed into the source note)
- Multi-turn discussion with Ethan on *how* DuQuant builds its rotation R̃ (Eq. 2) and why it is not a Hadamard; added a `Rotation construction & relationship to QuaRot` section (6 points) to the DuQuant source note
- (1) **Right-mult row↔column duality**: X→XR̃, input column j fans out via ROW j of R̃; the outlier is swapped to col 1 (E_{d(1)}) → its fan-out is governed by R̃'s **first row**. (2) **Flat first row** spreads the col-1 outlier evenly → peak ↓ from |outlier| to |outlier|/√n (flat = L∞-minimal unit vector = optimal spreader for a spike). (3) **"uniform(flat)" ≠ "random orthonormal"**: both unit-norm, but flat = all |entries|=1/√n vs random = uneven (Haar max entry ~√(2 ln n)/√n, has peaks); the paper's "uniformly distributed" first row means flat, NOT uniformly-random
- (4) **Other rows = general random-orthogonal** because the non-outlier cols need no structure + randomness is robust (no fixed-structure adversarial alignment — exactly why QuaRot itself randomizes Hadamard) + fits the greedy scheme. HONEST SCOPING: DuQuant's win over QuaRot = the **data-aware flat-first-row + greedy targeting**, NOT random-vs-Hadamard (that completion is low-stakes). (5) **Hadamard boundary (all-or-nothing)**: flat first + flat orthogonal rest ≡ a (randomized) Hadamard (= QuaRot, by definition; orthogonality couples the rows); DuQuant = one flat row + random-orthogonal (uneven) rest ≠ Hadamard; flatten the rest → it collapses to QuaRot. (6) **Online cost**: both DuQuant & QuaRot rotate online (only Λ, G⁻¹ folded offline); DuQuant's ~8.9–9.3% ("Perm 1") amortizes into ~2.08× via a real W4A4 kernel, vs Ω-QVLA's same online rotation but fake-quant → pure overhead
- No new pages; durable analysis filed into the existing DuQuant source note (same pattern as the prior Ω-QVLA deep-dive). Dated 2026-06-23 per the append-only convention (after the 06-13 Motus/Kairos entries)

## [2026-06-13] lint | Embodied cluster optimization pass (audit → 4 fixes)
- Ethan asked "what can be optimized in the embodied cluster?" Ran a 2-agent parallel audit (structure/link-graph + content staleness), verified the high-value findings by hand (corrected one agent false-positive: table `[[X\|alias]]` backslashes are correct pipe-escapes, NOT broken links), then executed the four selected fixes
- FIX 1 (link hygiene): renamed `03 Wiki/Entities/Physical Intelligence.md` → `Physical Intelligence (π).md` via git mv — resolves ~8-13 dangling `[[Physical Intelligence (π)]]` links (the flagship-lab entity was unreachable due to filename mismatch; the whole vault incl. index refers to it WITH the π). Source-note links `[[Physical Intelligence - pi0...]]` are different files, unaffected. One archival `[[Physical Intelligence]]` (no π) in log.md left as-is (append-only history)
- FIX 2 (orphan): `Memory in Embodied AI` concept page existed but was absent from index.md → added to index Concepts (was undiscoverable)
- FIX 3 (biggest structural gap): created `03 Wiki/Concepts/Embodied Cerebellum Models` — the counterpart to Embodied Brain Models (the brain/cerebellum framing previously had only the brain half). Pulls together the scattered cerebellum material: the multi-rate control stack (50Hz VLA → 1kHz impedance/IK → 40kHz PD/FOC "spinal" floor; learning boundary stops above PD), four cerebellum forms (VLA-expert-downstreamed / native fast-head Helix S1 / edge world model Kairos / classical control), edge-deploy tech (size+step distillation, VLA quantization, hybrid linear attention, AOT graph compilation, action chunking+RTC), dependability scaffolding, edge procedural memory. Dropped the "（待建）" markers in Embodied Brain Models now that it exists
- FIX 4a (navigation): created `04 Maps/Embodied AI - VLAs, world models, and cerebellum` — the embodied cluster's first MOC (counterpart to the agent-memory map); the cluster is the vault's largest (20 sources) but had no nav hub. Entry points + narrative spine + themes + suggested additions
- FIX 4b (freshness): in Embodied Brain Models 前瞻预判 — marked two predictions as overtaken by ingested evidence: "World model + VLA 嫁接 (π0.7+BAGEL)" → 已确认 2026 (π0.7/Motus/GigaWorld/Kairos); "蒸馏 1-3B VLM 大脑" → 部分兑现 (Gemma 2-3B/Qwen3.5-2B/Qwen3-VL-4B). Refined the Kairos pixel-level-WM row to note the open release has no action head (only partial validation of edge-WAM viability)
- Updated index.md (2 new concepts + 1 new map) + this log. Audit also surfaced a known backlog (person pages Levine/Finn, academic baselines OpenVLA/RT-2/Cosmos, 2 synthesis candidates) — left for user direction
- Meta-finding: source→wiki integration is excellent (zero orphan sources); the lag was in the connective layer (cerebellum page, MOC) and the forward-looking layer (stale predictions) — ingest outran synthesis. This pass closed that gap

## [2026-06-16] ingest | NeuroVLA (HKUST-GZ × AI2 Robotics) — brain-inspired neuromorphic cortex/cerebellum/spinal VLA
- User request: ingest arXiv:2601.14628. Post-cutoff (v1 2026-01-21), verified from arXiv abstract + HTML + GitHub (no assumptions)
- Identity: **NeuroVLA** — "A Brain-inspired Embodied Intelligence for Fluid and Fast Reflexive Robotics Control", Guo et al., **HKUST-GZ (Hui Xiong) + AI2 Robotics (Shenzhen, Yandong Guo)**, cs.RO/cs.AI
- Open-source VERIFIED REAL: https://github.com/guoweiyu/NeuroVLA (Python, 258★, ~53MB, NeuroVLA/ pkg + deployment/ + scripts/ — not a project page)
- Architecture (verified v1 + code exists): three bio-inspired layers — **Cortex** = Qwen-VL + Layer-wise Q-Former → semantic latent (~10Hz, CUDA tier); **Cerebellum** = GRU (proprio state) + Gated FiLM (gain), 200Hz wrench/joint feedback, K=2 recurrence → stabilizes "intention tremor" (jerk −75.6%); **Spinal** = **SNN** (LIF, Deep Spiking Residual, "Continuous Integration Protocol" → smooth continuous actions) on a **customized neuromorphic FPGA** (LIF systolic-array, 20MHz, 2.19ms, 0.87mJ/inf, 0.4W). Safety reflex <20ms via "vestibulocerebellar loop" (wrench → cerebellar-spinal local correction, bypassing cortex). Temporal memory = SNN membrane potential (stateful LIF) + cerebellar GRU. SNN trained via surrogate gradient
- Benchmarks: beats OpenVLA/-OFT/UniVLA/WorldVLA on LIBERO/LIBERO-Plus + real bimanual humanoid; jerk −75.6%, accel −32.8~58%, collision recovery 54.8% (vs 0% baselines). "First neuromorphic VLA on real robots" = self-claim, logged as such
- PRECISION CALLS (verify-don't-assume): (a) the "neuromorphic" core is the **spinal SNN only**; the cerebellum is GRU+FiLM (conventional, stateful), not an SNN — did NOT over-claim "all-SNN". (b) NeuroVLA's cortex/cerebellum/spinal = **bio-structural + compute-substrate (CUDA vs neuromorphic-chip) axis, all on-board** — recorded the explicit caveat that this ≠ the vault's deployment-driven 大脑(cloud)/小脑(edge)/脊髓(classical MCU) axis (cf. TwinBrain left/right ≠ cloud/edge)
- Framework impact: (1) independent **corroboration** of the just-built [[Embodied Cerebellum Models]] three-layer functional decomposition; (2) **challenges** that page's "learning stops above PD / spinal stays classical" claim — NeuroVLA puts a LEARNED SNN in the <20ms reflex layer → softened to "boundary now descends to the reflex sub-layer; kHz FOC likely still classical"; (3) adds **neuromorphic/SNN as a new edge-efficiency route parallel to [[VLA quantization]]**; (4) adds a **third implicit-memory flavor** (runtime stateful membrane/hidden-state memory, ≠ weight-baked, ≠ retrieval) to [[Memory in Embodied AI]]
- Created source note `Guo et al. - NeuroVLA Brain-inspired Neuromorphic Cortex-Cerebellum-Spinal VLA` + entity `AI2 Robotics` (郭彦东/深圳; HKUST-GZ Hui Xiong as待补充 academic side). Updated Embodied Cerebellum Models (3 edits), Memory in Embodied AI (2), the embodied MOC, index (Sources + Entities)

## [2026-06-16] correct | NeuroVLA benchmark framing (Ethan caught the overstatement)
- Ethan questioned whether NeuroVLA uses standard sim benchmarks (LIBERO/RoboTwin) or its own designed tasks. Re-read the experiments section (HTML, enumerated all figures/tables) → he was right; my initial note overstated it
- VERIFIED: NeuroVLA reports **NO standard success-rate leaderboard table**. (a) The OpenVLA/-OFT/UniVLA/WorldVLA comparison is a **qualitative bar chart (Fig 8a–e) with no printed numbers** — "consistently outperforms" is unquantified. (b) LIBERO appears **only in an internal ablation (Fig 5d)** comparing NeuroVLA's own SNN variants, NOT external baselines. (c) RoboTwin is NOT used at all (that was Motus). (d) All headline numbers are **custom metrics on self-designed real-robot lab tasks**: MACJ jerk −75.6%, MACA accel, "Recover to Safe Area" recovery 54.8% vs 0%, FPGA energy 0.4W, <20ms reflex, "shake the cup" rhythmic memory
- Framing: this is partly a deliberate stance (they evaluate emergent "biological motor characteristics", not leaderboard SR) and partly a rigor gap (no numeric SOTA comparison)
- Fixed: source-note Benchmark row rewritten + added a "评测设计（用户核查后修正）" section; softened the index Sources line (removed "beats OpenVLA/..."). Demonstrates the vault's verify-don't-assume norm catching a same-session overstatement

## [2026-06-17] deepen | NeuroVLA cerebellar-function coverage — equation-level verification of ③④
- Ethan asked to read the methods EQUATIONS to settle two hedged points from the cerebellum-function discussion: ③ sensory cancellation / reafference suppression, ④ precise timing. Downloaded the PDF to a repo-external temp (22.6MB, NOT committed per raw-tier rule), extracted text via pypdf, read §4.3–4.4 + results §2.3 directly
- FINDINGS (equation-grounded): two functions are STRONGER than my earlier "神似" estimate, two confirmed absent:
  - ✅ Gain control: Gated FiLM z_mod=(1+γ)⊙(z_sem·g)+β, γ/β/g learned fns of h_t=GRU(state history) (§4.3.2)
  - ✅ Forward internal model: EXPLICIT K=2 Iterative Refinement z_mod^(k+1)←Refine(z_mod^(k),s_{t+1}), called "mental simulation", used to pre-compensate gravity/friction (§4.3.3) — upgraded from "◐神似" to "✅explicit"
  - ✅ Efference-copy FRAMING is explicit in the paper (z_sem=efference copy, h_t=re-afference, FiLM="sensory prediction error", §4.3.3 Biological Insight) — corrects my prior over-hedge
  - ③ ❌ reafference CANCELLATION: NOT implemented. No explicit (predicted − measured) force subtraction; γ/β/g are learned fns of RAW h_t; collision = "spike in h_t" (raw 6D wrench), not a residual. Self vs external forces not explicitly separated → self-motion could false-trigger. (Has a forward model, but uses it for feedforward pre-comp, not feedback cancellation.)
  - ④ ❌ explicit TIMING: only rhythmicity/phase-consistency (Shake-the-cup sinusoidal cycles, §2.3) + temporal working memory (LIF membrane u[τ]=βu[τ−1]+…, §4.4.1) — both EMERGENT from recurrent membrane dynamics, NOT explicit interval/event timing (no clock, no eyeblink-style predictive timing, no burst timing)
  - Systematic gap CONFIRMED + author-acknowledged: discussion states learning is offline behavior cloning, names online STDP as future work for fatigue/wear adaptation → no VOR-style online recalibration. Gaps cluster on the LEARNING side (missing deployment-time error loop; biology's climbing fiber has no analog here)
- Added a "小脑功能覆盖度（方程级核实，确认 ③④）" section to the NeuroVLA source note. Temp PDF removed after the read

## [2026-06-23] maintenance | AGENTS.md — "Reading source material" procedure + Windows PDF toolchain
- Set up & verified the Windows PDF-reading toolchain (the Read tool's native `pdftoppm` rendering had been broken): installed **pdfplumber** (structured tables) + official prebuilt **poppler-windows v26.02.0** (`pdftoppm`, added to User PATH) ; confirmed `pdftotext -layout`, PyMuPDF/`fitz`, `pypdf`, `tesseract`. ⚠️ choco's `poppler` package is a dud (ships source code only, no `.exe`) → used the `oschwartz10612/poppler-windows` release instead. Native `Read` PDF rendering works after a session restart (PATH refresh); tesseract too
- Codified the procedure into AGENTS.md as a new **"Reading source material"** section: (1) source-format priority **LaTeX/e-print > HTML > rendered images > extracted text > summarizer**; (2) per-need method map (tables→pdfplumber, equations→LaTeX/HTML, figures→render, scanned→tesseract, CJK→render-to-image); (3) reliability discipline — summarizers not authoritative for exact facts, read the primary source yourself, mark confidence by method, confirm a quantitative table exists before recording a comparative claim. Cross-referenced from Ingest workflow step 1
- Motivated by this session's NeuroVLA benchmark overstatement (a summarizer's "outperforms OpenVLA" hid that there was no quantitative table) — the rule operationalizes the verify-don't-assume norm at the source-reading layer

## [2026-06-23] synthesis | Cloud-edge co-evolving embodied agent — framework archived (brainstormed with Ethan)
- Long multi-turn brainstorm (used the brainstorming skill) co-designing a **cloud-edge continuous co-evolution framework** for embodied agents, then archived it as a Synthesis. Two files:
  - `03 Wiki/Syntheses/Cloud-edge co-evolving embodied agent - a continuous-evolution framework` — the framework
  - `03 Wiki/Syntheses/Cloud-edge co-evolving embodied agent - figures and evidence` — verified-data table (with sources) + 5 reconstructable SVG figures
- Framework content: **two core problems** (Ethan's framing — ① edge inference-vs-continuous-learning compute contention; ② personalization scenario diversity → cross-scenario co-evolution); reframe = "keep learning alive under embodied deployment constraints, not 'how to learn'". **Symmetric bridge + two asymmetric engines**; **B = modular independent experts**; edge **3 categories (学得好/稳/协同) + ports (hexagonal/HAL-redeploy-network-runtime)**; cloud **4 categories** (continual-learning / fleet-aggregation / skill-factory+governance / collaboration); the **evolution interface** under B (no weight push — capability registry + contract co-versioning + gap-signaling); **four key technologies (2+2 matrix)**: T1 efficient on-device self-evolution (LoRA+CLS+DMD+DSA), T2 safe self-evolution (Simplex + gates + classical floor), T3 modular federated co-evolution, T4 capability-registry + contract co-versioning
- Evidence (honesty-graded): core① hard data (Thor/Orin per-precision compute+bandwidth, training 8× memory, NVIDIA three-computer = Thor inference-only, TinyML/LoRA) — with the **honest correction** that for 2B/128GB memory FITS → real bottleneck is real-time compute contention + power + throughput (so the primary figure is contention→latency, not memory overflow; memory-overflow figure deprecated to a conditional footnote). core② is structural/scaling (siloed-vs-collaborative topology + linear-vs-sublinear cost), labeled conceptual not measured
- Figures verified during the session via the visualize tool; archived as fenced SVG (host-injected classes — re-render by pasting back into show_widget). Several numbers labeled 示意 (illustrative typical magnitudes) vs 已核实 (cited) — distinction preserved
- Cross-linked from `index.md` (Syntheses), the embodied MOC (`04 Maps/...`), and `Embodied Cerebellum Models` (Related). Outbound links to Embodied Brain/Cerebellum Models, Home robot architecture, VLA quantization, Memory in Embodied AI, NeuroVLA, Kairos, π0.6, GO-1/Motus, NVIDIA
- Follow-up: added figures for **T3 (modular federated co-evolution)** and **T4 (capability registry + contract co-versioning)** to the figures companion (now 7 reconstructable SVGs); updated index + MOC counts (5 → 7)
- Follow-up 2 (per Ethan, for future readability): converted all 7 figures from host-class ```svg code blocks → **self-contained `.svg` files** in `03 Wiki/Syntheses/assets/` (inline `<style>` defining the c-*/t/ts/th classes + light bg + concrete font/colors replacing `var(--*)`), embedded via `![[…]]` so they **display directly in Obsidian** yet stay editable vector text. Replaced the code blocks with embeds; updated the companion's intro. Decision recorded: keep only the viewable self-contained .svg (NOT PNG — vector stays editable/diffable), with data table + sources as searchable text

## [2026-06-23] verify + maintenance | Source-reading toolchain: native PDF Read confirmed (+ correction), Chinese OCR added, AGENTS.md hardened
- VERIFIED the prior entry's native-`Read` claim, with a CORRECTION: it works only after a **full Claude app restart**, NOT a mere new chat / "session restart". A new session reuses the same harness process, which keeps its original environment block, so the User-PATH poppler entry is not inherited and `Read` keeps failing with `pdftoppm failed: Command 'pdftoppm' not found`. After fully quitting + reopening the app, native rendering works (confirmed by `Read`-ing MemPO & ReKep page 1). Supersedes the prior "works after a session restart (PATH refresh)" wording
- Chinese OCR gap found + fixed: the prior "confirmed tesseract" covered only the binary — its tessdata had **English only** (`eng`/`osd`), so CJK scans would OCR to garbage. The default tessdata (under `C:\Program Files`) is not user-writable, so installed `chi_sim`/`chi_tra` (+ copied `eng`/`osd` for a complete set) to **`%LOCALAPPDATA%\tessdata`**; invoke via `tesseract --tessdata-dir "$env:LOCALAPPDATA\tessdata" -l chi_sim+eng` (verified via `--list-langs`). Chose `--tessdata-dir` over `TESSDATA_PREFIX` (version-ambiguous + would need a process restart to inherit)
- Hardened the AGENTS.md "Reading source material" section: (1) the Scanned/OCR line now documents the Chinese `--tessdata-dir` invocation (the default install is English-only); (2) added a recovery bullet — a tool reporting *not found* despite being installed is a harness-process-**PATH** issue, not a missing install → fully restart the Claude app, don't reinstall. Re-verified the rest of the toolchain is genuinely present (pdfplumber / pypdf / PyMuPDF / poppler / tesseract)

## [2026-06-23] asset | Interactive HiF8/FP8 value-density visualization
- Created `assets/hif8_value_density.html` — standalone, self-contained (no CDN, works offline) interactive stepped chart: representable values per **octave (binade)** on a log₂ axis for HiF8 vs FP8-E4M3 / E5M2. Each format's precision-change boundaries are labelled on the x-axis (coloured per-format rows); hover any octave to read its actual representable values. Data enumerated from all 256 codes → exact, including the top-octave dips (E4M3 7/oct at 2⁸ = NaN code; HiF8 1/oct at 2¹⁵ = Inf code). Conveys "same 8-bit budget, spent differently": HiF8 tapered 8→1, E4M3 flat-dense-narrow, E5M2 flat-coarse-wide
- Established `assets/` as the vault's folder for non-markdown attachments (none existed; Obsidian had no attachment folder configured → defaulted to root)
- Linked from [[Ascend HiFloat8 Format for Deep Learning]] (new Visualization section) and [[Model quantization]] (Figures entry under route 1, representation design)
- Origin: generated this session while reading the HiF8 paper (arXiv:2409.16626) via the now-working native PDF Read; exercised the value-density discussion (per-octave density as the readable alternative to a representable-value ruler)

## [2026-06-23] maintenance | HiF8 arXiv PDF backfill (small + important)
- Backfilled `01 Raw/2026-04-13 - Luo et al. - Ascend HiFloat8 Format for Deep Learning.pdf` (arXiv:2409.16626 **v2**, 0.72 MB) — the HiF8 raw note had been URL-only (Tier 1). Kept per the `01 Raw/` rule ("preserve a local copy when small and important"): HiF8 anchors the [[Model quantization]] cluster, and committing it freezes the exact version the source note + deepened analysis + value-density viz are based on. Mirrors the earlier MemPO PDF backfill; consistent with the ReKep PDF already kept
- Added local-PDF wikilinks to the raw note and the [[Ascend HiFloat8 Format for Deep Learning]] source note

## [2026-06-25] asset | Two-axis functional-evolution trend figure → Embodied Brain Models
- Created `03 Wiki/Concepts/assets/fig-two-axis-evolution.svg` — self-contained SVG (same `<style>`+light-bg pattern as the co-evolution figures): cross-company functional-evolution map on **two technology axes × 3 stages each** — ① 统一模型轴 U1→U2→U3 (base VLA → in-model reasoning → world-model/memory/self-improvement) and ② 大小脑分层轴 L1→L2→L3 (dual-system thin head → cerebellum-FM → multi-expert skill-library + brain orchestration), plus the Galaxea G0→G0.5 cross-traffic ("跳轨") arrow and an interaction-deepens annotation
- Embedded into [[Embodied Brain Models]] as a new section "功能演进趋势:统一模型轴 vs 大小脑分层轴(跨公司)" (after 玩家分布表, before 接口维度); complements the existing 解耦程度光谱 (research↔deployment) with a time-evolution view
- Reliability graded per the vault norm: `~` = vendor/news-reported (Helix, Atlas, AgiBot BFM-2/GCFM); others paper- or code-verified. L3 backed by third-party real instances (Being-0 arXiv:2503.12533, MetaWorld-X arXiv:2603.08572), not just our proposal. MoE flagged as a cross-cutting "multi-expert ≠ layered" technique, not a stage
- Origin: discussed this session — converged a defensible two-axis framing (after rejecting an unbalanced three-axis version), did light cross-company verification (found Being-0 / MetaWorld-X / Atlas fill L1–L3 with real instances), then rendered + archived

## [2026-06-25] ingest | Humanoid-GPT / AstraBrain-WBC 0.5 (Galbot 银河通用) — whole-body-control cerebellum FM, PDF+code-verified
- Added source note [[Qi et al. - Humanoid-GPT (AstraBrain-WBC) Scaling Data and Structure for Zero-Shot Motion Tracking]] — GPT-style causal Transformer for whole-body real-time control, distilled from hundreds of RL experts (DAgger BC) → per-joint PD targets; demonstrates a **scaling law for motion control** (tracking SR 76.89%→83.26%→92.58% as data 2M→2B frames & params 0.25M→5.7M→80.4M; MLP/TCN saturate, even regress). arXiv:2606.03985, **CVPR 2026**; latency 0.39ms (optimized C++/TensorRT/cache) / <1.5ms on RTX 4090; target Unitree G1. Pure cerebellum/motion-tracker — **not a VLA, no vision-language, no world model**
- Backfilled `01 Raw/2026-06-02 - Qi et al. - Humanoid-GPT ....pdf` (arXiv v1, 8.84 MB); facts extracted via pdftotext and read directly (not via web summarizer — per AGENTS.md source-reading rule)
- **Naming/attribution verified per Ethan's caution**: product name **AstraBrain-WBC 0.5** (Galbot press, 2026-06-19) vs paper/code name **Humanoid-GPT**. Judged the same work at very-high confidence — paper affiliation #2 = Galbot Inc., GitHub org = GalaxyGeneralRobotics, He Wang (Galbot founder) corresponding author, specs match exactly — but **the paper never says "AstraBrain" and no single doc equates the two names**, so logged as a strong inference, not literal cross-citation
- **Code status (code-verified)**: github.com/GalaxyGeneralRobotics/Humanoid-GPT, Apache-2.0; **inference+deploy code + ONNX checkpoint released now, but training code + 2B-frame data still TODO** — press claims of "fully open-sourced" are an overstatement (corrected in the note)
- Created entity [[Galbot 银河通用]] (王鹤 / PKU EPIC) with explicit **≠ [[Galaxea 星海图]]** disambiguation (reciprocated in the Galaxea entity's naming-caution callout); added Galbot to [[Embodied AI - VLAs, world models, and cerebellum]] Entities
- Placed as a hard **L2 (cerebellum = general motion-control FM)** instance: added to the two-axis figure `fig-two-axis-evolution.svg` (L2, alongside NeuroVLA; 智元 BFM-2/GCFM moved to the vendor-reported sub-line) and the [[Embodied Brain Models]] two-axis section; recorded in [[Embodied Cerebellum Models]] as an early instance of the predicted "independently-designed edge motion-control architecture" (a new cerebellum form beyond the original four)
- Updated `90 System/index.md` (Sources + Entities)

## [2026-06-25] deepen + fix | Humanoid-GPT — WBC-tracker clarification, eval-protocol detail, oversized PDF removed per Raw rule
- Source note: added section **"关键区分:它是 WBC tracker,不是子任务执行器"** (it takes a fully-specified reference motion → reproduces it stably; NOT "take a subtask → figure out the motion"; a different functional layer from the skill/subtask cerebellum we'd been discussing; occupies the **WBC rung** of the frequency ladder) and **"评测协议与通用性边界"** (test sets = AMASS-test held-out split tracking in MuJoCo + 4 unseen dances on real G1 + online teleop — **a motion-tracking eval, NOT a task-success leaderboard**; generality = motion-space zero-shot only, **not task-level, not cross-embodiment, tracking-not-autonomy**; param family 0.25M→5.7M→~22M→80.4M, headline L=80.4M≈GPT-1 scale)
- [[Embodied Cerebellum Models]]: annotated the frequency ladder — the **WBC (全身/关节空间控制) rung's "learnable? = 边界"** is now effectively ✅ (Humanoid-GPT learns whole-body control as a GPT), classical floor reduced to the kHz FOC spinal layer
- **Fix (self-caught rule violation)**: committing the 8.84 MB PDF in the previous commit **violated the existing AGENTS.md `01 Raw` rule** (PDFs more than a few MB → URL-only, do not commit). `git rm`'d the PDF; source note's Raw line changed to URL-only (facts were already pdftotext-extracted). Note: the blob remains in git history (no history rewrite); a filter-repo + force-push could reclaim ~9 MB if ever wanted
- Trigger: Ethan's question — this "cerebellum" reproduces mocap motions (tracking), which is a different layer from "cerebellum executes a subtask"; clarified to prevent future conflation

## [2026-06-25] maintenance | git history purge — reclaim oversized Raw PDFs (Humanoid-GPT 8.8MB + ReKep 13.8MB)
- Rewrote history with `git filter-repo --invert-paths` to excise two PDFs that violated the `01 Raw` "PDFs > a few MB → URL-only" rule: `01 Raw/2026-06-02 - Qi et al. - Humanoid-GPT …pdf` (8.84 MB, added then removed earlier today) and `01 Raw/2026-04-21 - Huang et al. - ReKep …pdf` (13.8 MB, a previously-kept live file — Ethan opted to reclaim it too)
- ReKep converted to **URL-only**: removed the live PDF; raw note's "Local PDF" line now points to arXiv 2409.01652 (source note already had the arXiv link)
- Reclaimed ~22 MB from history; **force-pushed** rewritten master (commit SHAs from the first PDF-introducing commit onward changed). A full-history backup bundle was created at a repo-external temp before the rewrite
- Remaining `01 Raw` PDFs (HiF8 0.75 MB, MemPO 0.54 MB) comply with the rule and were kept

## [2026-06-25] maintenance | AGENTS.md — concrete Raw-binary commit rule (>2 MB → URL-only + pre-commit size check)
- Replaced the fuzzy "PDFs more than a few MB" with a **concrete 2 MB threshold** across all three places that state the rule (`01 Raw/` section, ingest-workflow step 1, Reading-source section): binaries > 2 MB → URL-only by default; committed copy only when ≤ 2 MB and important, or hard to re-access; arXiv stable → arXiv PDFs default URL-only
- Added an explicit **pre-commit size-check hook**: check size before `git add` of any `01 Raw/` binary; if > 2 MB, don't add → URL-only. This is the enforcement step whose absence let the Humanoid-GPT (8.8 MB) and ReKep (13.8 MB) PDFs slip into history (both since purged via filter-repo)

## [2026-06-25] ingest | BFM-2 (AgiBot 智元) — generative whole-body-control 运动小脑 (vendor PR-only)
- Added source note [[AgiBot - BFM-2 Motion-Between Whole-Body Motion Foundation Model]] — generative WBC motion foundation model (two-stage "Motion-Between" + DOF Feather Motion Generator; models the full-body dynamics state-space distribution → generates a trajectory from any state to any target → disturbance rejection / balance recovery / get-up). Announced 2026-05-25
- **Reliability: vendor PR-only** — official site + multiple tech-media + a dedicated paper/code search found **NO arXiv paper, NO technical report, NO GitHub code** (AgiBot open-sources Link-U-OS / AimRT / AgiBot-World, but not BFM-2). Flagged as the least-verifiable L2 cerebellum FM (vs Humanoid-GPT's arXiv+CVPR+Apache-2.0); params / data / generative mechanism (diffusion/flow/transformer) all undisclosed
- Linked under [[AgiBot 智元]] (added the GO brain-line ↔ BFM motion-cerebellum-line structure; BFM-3 pre-announced); wikilinked in the two-axis L2 ([[Embodied Brain Models]]); added to [[Embodied Cerebellum Models]] as the 2nd "通用运控基座" instance
- Added a new **4-level feedback-loop taxonomy** to [[Embodied Cerebellum Models]] (L1 control/disturbance · L2 forward-model · L3 failure-detect-recovery · L4 self-improvement), prompted by Ethan's "can a cerebellum self-close the loop?" question. Verdict recorded: BFM-2's "动态任务闭环" = L1 control loop + autonomous motion recovery (feedback = full-body dynamics + contact + command → generative re-planning, not fixed clips); no forward-model / task-verification / self-improvement
- MOC + index updated. No PDF (PR-only → URL-only, complies with the just-tightened >2 MB Raw rule)

## [2026-06-25] verify | GCFM (AgiBot) confirmed real — generative control FM; corrected BFM-2 note's "unverified" placeholder
- Verified **GCFM = Generative Control Foundation Model (生成式运控模型)**, AgiBot, announced at its **2026-04 partner conference** ("一体三智" full-stack, 1 of 8 foundation models): **text / audio / video → real-time natural motion** (文生动作、音频配肢体语言), real-time improvisation. Still **PR-only** (no paper/code found). So GCFM was NOT fabricated — it had been carried unverified in the two-axis figure; now substantiated
- Clarified **GCFM ≠ BFM-2 in function**: GCFM = prompt→motion generation; BFM-2 = robust whole-body control / recovery. Both AgiBot motion-side, both PR-only
- Updated [[AgiBot - BFM-2 Motion-Between Whole-Body Motion Foundation Model|BFM-2]] note (replaced the "GCFM 未核实" placeholder with verified facts; clarified BFM ≈ Behavior Foundation Model, BFM(1) ~1.2M→42M params / 100M frames / 700h mocap) and the [[AgiBot 智元]] entity ("一体三智" line: GO brain + BFM/BFM-2/GCFM motion). Two-axis figure's "GCFM~" kept (still vendor-reported, now justified)
- 〔follow-up 2026-06-25〕 Dedicated GCFM paper/code re-check (arXiv + GitHub + official research page, EN/CN) → still **none**. Recorded the trace in the BFM-2 note + a disambiguation note: the academic **BFM** (arXiv:2509.13780, bfm4humanoid.github.io; CVAE + masked distillation) is a **different group's work ≠ AgiBot's BFM/GCFM** (name collision). Noted the structural pattern: AgiBot's motion side (BFM-2, GCFM) is all PR-only; only its brain/data side (GO-1, AgiBot-World) is published/open

## [2026-06-29] ingest | LeWorldModel (LeWM) — LeCun et al., stable end-to-end JEPA world model
- Added source note [[Maes et al. - LeWorldModel (LeWM) Stable End-to-End JEPA from Pixels]] (arXiv:2603.19312, v3 2026-06; Maes/Le Lidec/Scieur/**LeCun**/Balestriero). First JEPA that trains stably end-to-end from raw pixels with only **2 losses** (next-embedding MSE + **SIGReg** Gaussian regularizer, provable anti-collapse) — no EMA/stop-grad/pretrained-encoder/reconstruction/reward; loss hyperparams 6→1 vs PLDM. ~15M params, single GPU; latent-space planning **~48× faster than DINO-WM** (~200× fewer tokens); beats DINO-WM on Push-T/OGBench-Cube at fixed FLOPs; latent probes physical quantities + violation-of-expectation (surprise) detection. Code open
- Created entity [[Yann LeCun]] (JEPA/world-model advocate, Turing laureate; paper affiliation = NYU — current Meta status left to first-party sources, not asserted)
- Placement: [[Embodied Brain Models]] Predictive Spatial → 潜在世界模型 (alongside V-JEPA/Dreamer); MOC Sources—world models + Entities; flagged in [[Embodied Cerebellum Models]] edge-WM open question as evidence that an edge world model is more likely a small latent JEPA than a big pixel WM (vs Kairos)
- **No PDF committed**: arXiv stable → URL-only; 5.66 MB PDF downloaded to a repo-external temp, read via pdftotext, then cleaned up (complies with the >2 MB Raw rule)
- index updated

## [2026-06-29] concept | JEPA concept page (groundwork for world-model trends)
- Created concept page [[JEPA]]: definition (latent, **non-generative**, energy-based; LeCun 2022 *A Path Towards Autonomous Machine Intelligence*), the **anti-collapse spectrum** (contrastive / EMA+stop-grad / VICReg / whitening / frozen-encoder / **SIGReg**) as the axis separating JEPA variants, the **family tree** (representation branch I-JEPA→V-JEPA→V-JEPA 2; action-conditioned/world-model branch DINO-WM / PLDM / **V-JEPA 2-AC** / LeWM), the "acts via planning not policy" note, and a **JEPA vs generative world models** table seeding the upcoming trends discussion
- External facts search-verified this session: V-JEPA 2 (arXiv:2506.09985, Meta 2025-06) + **V-JEPA 2-AC** (300M action-conditioned WM, Droid <62h, zero-shot Franka pick-place via image-goal MPC); DINO-WM (arXiv:2411.04983, frozen DINOv2); **PLDM = Planning with Latent Dynamics Models** (arXiv:2502.14819, VICReg 7-term); I-JEPA (arXiv:2301.08243); LeCun path paper (2022)
- Linked from [[Embodied Brain Models]] (Predictive Spatial), [[Maes et al. - LeWorldModel (LeWM) Stable End-to-End JEPA from Pixels]], [[Yann LeCun]], MOC, index. **Priority to-add source notes flagged**: V-JEPA 2 / V-JEPA 2-AC (for trends), DINO-WM, PLDM, I-JEPA

## [2026-06-30] synthesis | World model trends (architecture / scale / function / hardware)
- Created [[World model trends - architecture, scale, function, hardware]] — capstone of the multi-turn WM-trends discussion across **5 blocks**: architecture (Transformer-backbone convergence + objective divergence; 范式 B 串行 vs A 并行-耦合 MoT), scale (two divergent curves: B-level generative vs M-level latent), function (taxonomy by output representation + orthogonal input/purpose axes), training-HW (data-movement-bound + heterogeneous), inference-HW (latency / search-in-loop / iterative-generation bound). **Unifying thesis: output space is the master variable** — determines architecture, scale, function, and both hardware profiles
- Self-contained figure `assets/fig-wm-trends-output-space.svg`: pixels↔latent spectrum × the 5 dimensions (left=generative pole, right=predictive pole)
- Covers Dreamer V1-4 / Cosmos / Genie 1-3 / Sora / Marble / Kairos / Motus / MuZero / OccWorld + the JEPA line; model facts search-verified this session (arXiv ids in note), timeline/hardware/future = analysis
- Linked from MOC (Syntheses), index, [[JEPA]]; cross-refs [[Cloud-edge co-evolving embodied agent - a continuous-evolution framework]] (EAL / hardware) and [[Yann LeCun]]. No PDF beyond the SVG (Raw rule OK)

## [2026-06-30] ingest | LaWAM — latent World-Action Model (Chen et al.), 5th-gen WAM
- Added source note [[Chen et al. - LaWAM Latent World Action Models for Efficient Dynamics-Aware Robot Policies]] (arXiv:2606.15768, 2026-06-14; 清华/吉大/南开/北大/哈工大/中关村学院/Striding.AI/Infinigence AI). Trains a latent-action model in a frozen **DINOv3** latent space and **repurposes the LAM decoder as the world model (LaWM, 230M)**; single forward pass → latent visual subgoal → Alternate-DiT action expert. **~95% fewer world-modeling params than the 5B WAN backbone, ~24× lower latency (187ms) than pixel WAMs**; **LIBERO 98.6% / RoboTwin 91.22%** (standard benchmarks — stronger reliability than custom-metric papers). Trained on ~3000h robot + 1500h egocentric human video (open-source data). **Code: no explicit release link found**
- Placement: added as the **第五代 (Latent-Subgoal, 跳出像素空间)** of [[World-Action Models]] (prior 4 gens were all about "generate video or not"; LaWAM departs by going fully latent + single-pass); added to [[World model trends - architecture, scale, function, hardware]] reference table as a fresh "产隐→轻/快" exemplar; linked from [[JEPA]], MOC, index
- Convergence point of three vault threads: JEPA/DINO latent prediction + latent-action (GO-1/LAPA) + WAM-for-control, via "a LAM's decoder already is a latent world model" (concurrent w/ Garrido et al.). Cites in-vault Motus + GigaWorld-Policy
- PDF read from repo-external temp (9.85MB), not committed; cleaned up

## [2026-06-30] synthesis | Embodied model function evolution — generalization as the master line
- Created [[Embodied model function evolution - generalization as the master line]] — re-narration of the embodied-model function trend (端到端 → 大小脑协同 → 端云自闭环 → **Agentic**) driven by the **generalization/usability wall** rather than raw capability. Master variable: **the unit of generalization shifts 模型 → 组合**. Prompted by expert feedback that the trend must fold in "poor generalization + per-scene real-robot RL/teleop is unsustainable"
- Content: 4-stage arc table (功能/泛化载体/墙/例子); long-horizon-collapse support (**p^N × missing L3 task-loop**; per-scene RL = linear dead-end; Agentic two knives = shorten chains + inter-skill correction); examples pool + brain/cerebellum pairing table + "内部 action expert ≠ 大小脑" purity spectrum; report-ready one-paragraph framing
- Self-contained figure `assets/fig-embodied-function-generalization.svg`: 4-stage cards (功能/泛化载体/墙) + generalization-carrier arrow + linear→sublinear cost band
- Ties together two-axis L3 + co-evolution framework + capability-vs-dependability + the 4-layer feedback loop under "generalization". Linked from Embodied Brain Models, MOC, index. Analysis-level; model examples vault-verified (BFM-2 marked vendor-reported)

## [2026-06-23] ingest | QVLA (4th VLA-quant source; DyQ-VLA's baseline) — completes a strategy×architecture 2×2
- Ingested QVLA (Xu et al., SJTU AutoLab + CASIA + UCAS + Ant Group; **ICLR 2026**; arXiv:2602.03782) at user request — DyQ-VLA's per-channel baseline. Hand-verified against the full PDF (v1, 17pp incl. App A–E; pypdf). Raw: URL-only (3.47 MB, complies with the new >2 MB rule)
- Open source: https://github.com/AutoLab-SAI-SJTU/QVLA (real code: sensitivity proxy + greedy gate assignment + eval, 44★). NB eval is `fakew` (fake-quant); LICENSE unstated. ⚠️ **QVLA (Xu, ICLR) ≠ QuantVLA (Zhang, CVPR)**; also called "AutoQVLA" in its own appendix tables
- Method: first **action-centric** VLA quant. Per-output-channel bit allocation {0,2,4,8,16} (0-bit = pruning → unifies quant + prune) driven by **action-space sensitivity** (single-step Action-MSE + cumulative long-horizon; Taylor/Jacobian proxy → greedy demotion by sensitivity-per-bit ratio). **Activations uniform-bit** (branch-free); keeps **projector + action head FP16** (most sensitive). Static/offline (HAWQ lineage, made action-guided)
- Base: OpenVLA / OpenVLA-OFT (autoregressive) + UniVLA + CALVIN (appendix) + π0 real-world (W8A16). W4A4 OpenVLA-OFT 96.0% (98.9% retained) @ 29.2% VRAM, **1.49× speedup** (+22.6% vs SmoothQuant); reports measured speedup though the release is fakew
- KEY SYNTHESIS: completes a **strategy × architecture 2×2** — autoregressive (OpenVLA) methods use **sensitivity-driven bit allocation** (QVLA static / DyQ-VLA dynamic); diffusion-DiT methods use **rotation/reshaping** (QuantVLA selective / Ω-QVLA uniform); off-diagonal empty. **QVLA = DyQ-VLA's static sibling** (DyQ-VLA uses it as baseline, wins by only ~0.1% → dynamic upside marginal). Cross-cutting "protect the multimodal→action interface": QVLA (projector+action-head FP) / QuantVLA (DiT-attn FP) / DyQ-VLA (BF16 fallback) — only Ω-QVLA quantizes it
- Rewrote `VLA quantization` to a **4-way** landscape (4-way table + strategy×architecture diagonal + 4-lens fragile-locus + QVLA moved cited→ingested); updated `Model quantization` (QVLA in Sources / Route-3 static-sibling / Related) + `index.md` Sources. Remaining cited VLA-quant: EaqVLA (2505.21567), SQAP-VLA (2509.09090). Dated 06-23 per the QVLA notes (vault has since advanced to 06-30 via parallel work; left out-of-order per the established convention)

## [2026-06-30] verify | QVLA 1.49× speedup — no mixed-bit kernel, not reproducible from release
- Follow-up to a user question ("if there's no custom kernel for mixed-bit weights, how was 1.49× measured?"). Re-verified QVLA's arXiv full text: the paper describes **no custom kernel** for `{0,2,4,8,16}` mixed-bit weights (only *"weights stored per-row with own scale/zero-point, dequantized upon access"*), gives **no timing methodology**, names only the GPU (RTX 4090 sim / 4070 deploy) — no CUTLASS/backend. Released code is `fakew` (accuracy-only, BF16) ⇒ **cannot** produce the 1.49×
- Conclusion recorded: the 1.49× is **bandwidth-plausible** (autoregressive OpenVLA decode is memory-bound → weight-only dequant kernel makes speedup ≈ weight-compression ratio, no INT-GEMM needed) but **unsubstantiated by QVLA's own artifact**. DyQ-VLA reports the same 1.49× on a **real CUTLASS kernel** (and re-measures a QVLA-style static W4A4 at 1.49× itself) — so the figure is achievable, just not demonstrated by QVLA. This is exactly why the comparison's "real INT kernel?" axis marks QVLA amber (fakew), DyQ-VLA green (measured)
- Wrote into: QVLA raw note (verified-facts line) + source note (What feels limited + Q1 now answered) + `VLA quantization` Open questions ("Latency, honestly"). No new sources


## [2026-07-06] lint + maintenance | Link-integrity repair, navigation refresh, VLA base concept + author entities
- Ran a full wikilink-graph lint (106 notes) at user request. **Root cause found:** source notes use "Author - Title" filenames but were linked by clean paper titles ("QuantVLA: ...", with a colon — illegal in Windows filenames) → ~99 unresolved links and 11 orphaned source notes (the whole quantization cluster + early agent notes were floating off the graph, invisible because Obsidian renders unresolved links as grey placeholder nodes)
- **P0 link repair (99 replacements, 21 files):** rewrote broken link TARGETS to the real filenames, preserving `|short-alias` display (e.g. `[[QuantVLA: ...]]` → `[[Zhang et al. - QuantVLA ...|QuantVLA]]`). Covered the 10 colon-title notes (Ω-QVLA / DyQ-VLA / QuantVLA / SmoothQuant / DuQuant / QVLA / Ascend-HiF8 / MemPO / Harness-design / Scaling-Managed-Agents) + 3 variant-name links ([[Alex Zhang - The Mismanaged Geniuses Hypothesis|Mismanaged Geniuses]], [[Bi et al. - Motus A Unified Latent Action World Model|Motus]], π0.5) + the pi0.7 source note's raw backlink stray `.md` suffix. **Orphans 12 → 1** (only root `AGENTS.md`, the intended entry pointer). `90 System/log.md` intentionally left untouched (append-only history keeps its historical links as-is)
- **P1 navigation:** rewrote `04 Maps/Home.md` from its stale initial state (only [[LLM Wiki]] + Karpathy) into a proper **map-of-maps** — the two cluster MOCs + per-cluster concept/synthesis entry points + vault-layer explanation + system pages. Fixed non-resolving folder links (`[[00 Inbox]]` / `[[01 Raw]]` / `[[02 Sources]]` / `[[03 Wiki]]`) in Home + index; Inbox marked empty (the folder does not currently exist)
- **P2 new pages:** created the missing base concept [[VLA - Vision-Language-Action Models]] (referenced 7× across source notes but never created) as a **hub** — definition, boundary clarifications (vs WAM / vs pure motion controller / VLA's transitional positioning), architecture axes (actor-vs-encoder, Paradigm A/B), and an instance table. Created 4 person entity pages resolving recurring dangling links: [[Sergey Levine]], [[Chelsea Finn]] (π series, 4× each — were on the Embodied MOC's own to-do list), [[Li Fei-Fei]] (ReKep / spatial-intelligence anchor), [[Song Han]] (SmoothQuant / the quant cluster's reshaping-lineage upstream). All follow the [[Yann LeCun]] confidence-discipline style (no unverified current-title claims)
- Updated `90 System/index.md` (added VLA concept + 4 people; removed the dead folder-link bullets) and the Embodied-AI MOC (VLA concept in Concepts; Entities split into Orgs/People + added [[AI2 Robotics]]; marked the Levine/Finn to-do done). Fixed a stale `(to be created)` marker on [[World-Action Models]] in the GigaWorld source note (that page exists)
- **Remaining dangling links (35, all intentional):** one-off paper co-authors + not-yet-created concept pages (`AI coding agents`, `Keypoint-based Manipulation`, `Task Decomposition as OOD Mitigation`, …) + org stubs (`GigaAI`, `Huawei`) — deliberately left per the vault's "link aggressively / future pages" convention. Verified: no new broken links introduced by the new pages; broken-embed report (SVG/jpg/html) are lint false-positives (nested `assets/` dirs) that resolve in Obsidian


## [2026-07-06] fill-in | Missing concept + entity pages (resolve intentional dangling links)
- Built the 7 remaining not-yet-created pages that were dangling links, at user request (follow-up to the 07-06 lint + author-unbracketing pass)
- **Concepts (4):** [[Task Decomposition as OOD Mitigation]] — cross-cluster thesis (OOD task → in-distribution subtasks; ReKep / RL Tokens / ChemBot / MGH; the OOD lens on [[Task decomposition]]); [[Keypoint-based Manipulation]] — semantic-3D-keypoint + constraint manipulation (ReKep anchor); [[Constrained Optimization for Robot Control]] — task-as-optimization vs learned policy (ReKep's execution half + CBF/SHIELD safety tie-in); [[AI coding agents]] — LM systems that plan / spawn subagents (the vault's MGH evidence; Claude Code / OpenClaw / Hermes)
- **Entities (3):** [[GigaAI]] — world-model company (GigaWorld-Policy); [[Stanford Vision and Learning Lab]] — ReKep source group (with [[Li Fei-Fei]]); [[Huawei]] — Ascend / HiFloat8 FP8 format. Written with confidence discipline (vault-supported facts stated; org background beyond the vault flagged, esp. GigaAI)
- De-annotated the stale `(to be created)` on [[Task Decomposition as OOD Mitigation]] in the ReKep note. Wired all 7 into `index.md` (Concepts + Entities); added [[AI coding agents]] + [[Task Decomposition as OOD Mitigation]] to the Agent MOC and [[GigaAI]] to the Embodied MOC Orgs
- Lint after (118 notes): no person/concept dangling links remain except (a) [[hif8_value_density.html]] (a real asset that resolves in Obsidian — lint false-positive) and (b) folder/example fragments inside this log (append-only history, left as-is). Orphans still 1 (root AGENTS.md). No new broken links introduced by the new pages


## [2026-07-06] tooling | Vault link-linter installed
- Added `90 System/scripts/vault_lint.py` — the link-integrity self-check used in the 07-06 passes, cleaned up into a permanent tool (plain Python 3, no deps; auto-locates the vault two levels up from itself). Reports broken wikilinks (**A** = target exists under a different filename → real bug; **B** = no match → dangling/future page), orphan notes, and duplicate basenames
- Improvements over the throwaway version: indexes nested `assets/` + non-md targets (svg/pdf/html/jpg) so embeds & asset links resolve (kills the earlier false-positives); strips fenced/inline code so doc examples aren't miscounted as links; excludes append-only `90 System/log.md` from the broken-link scan by default (`--include-log` to override); flags `--broken` / `--orphans`
- Added usage note [[Vault linting]] (how to run, resolution model, noise control, known-benign baseline) and referenced it from the [[90 System/AGENTS|Lint workflow]] + the index System section
- Baseline clean run: **0 broken-A / 0 broken-B / 1 orphan** (root `AGENTS.md`, the entry pointer) **/ 1 duplicate** (`agents`: root vs `90 System/AGENTS.md`) over 119 notes + 15 assets


## [2026-07-06] synthesis | Future embodied Agent framework — integrated view
- Created the single-entry overview [[Future embodied Agent framework - integrated view]] at user request, stitching the vault's embodied-Agent vision (previously spread across 4 syntheses) into one **why / what / how / foundation** page
- Structure: ① **why** — 泛化墙 → Agentic (泛化载体 模型→组合); ② **what** — hierarchical agent (cloud brain propose-then-verify / plan-level interface / edge experts+safety+procedural+distilled; dual memory); ③ **how** — 端云 co-evolution (asymmetric engines + symmetric bridge, modular experts=choice B, evolution interface carries capability-profile **not weights**, 4 techs 2+2); ④ **foundation** — capability ⟂ dependability
- The page's own contribution (not just a digest): the cloud↔edge coupling is **two channels** — runtime (plan↓ / obs↑) vs evolution (experience↑ / skills↓); the "what" and "how" syntheses are the **static vs dynamic slices of one framework**
- Self-contained figure `assets/fig-future-embodied-agent-framework.svg` (layered architecture + two channels + foundation bar), house SVG style
- Wired: index Syntheses + Embodied MOC Syntheses + Home key-syntheses (marked integrated entry); added 🧭 back-pointers from the 3 source syntheses (function-evolution=why / home-arch=what / co-evolution=how)
- Confidence: model anchors (π / GR00T / GO-1 / Helix / ChemBot) verified; layered form + two-channel split + sublinear-cost mainline = Ethan+Ada forward judgment (flagged). Lint clean: 0 broken / 1 orphan (root AGENTS.md) / 1 dup (agents); 120 notes, 16 assets


## [2026-07-07] synthesis | Real-robot data collection — teleop vs UMI-class + model-in-the-loop quality
- Ran the deep-research workflow on Ethan's question (真机数采趋势/挑战 × 计算系统视角)。工作流两次在 WebFetch 上挂死（rai-inst.com 对非浏览器客户端 200+空 body；技术上是无超时兜底的连接挂起），第二次确认为确定性挂死后放弃重试：杀掉工作流，从 journal 抢救 45 份提取结果（~22 个独立来源 × 双路提取，215 条声明），缺失 2 来源用 curl 补查（一个 bot-blocked、一个正文仅 11 词，均无损失），由主会话完成综合
- Created [[Real-robot data collection - teleop vs UMI-class, and the model-in-the-loop quality problem]]：两范式对比表（UMI $73 BOM/3× 吞吐/ATE 6.1mm vs AgiBot World 1M 轨迹/human-in-loop 核验）；质量评估三代谱系（规则 RINSE→模型判别 DemInf/CUPID/QoQ/DataMIL/Re-Mix→质量条件化 Recap/π0.7，后者接通 vault 既有 π 系列笔记）；闭环数据价值度量的三类计算系统负载（influence 近似算力墙、L0–L3 四层评估栈 AutoEval/SIMPLER/WorldEval 量化表、数据引擎调度）；数据管线基础设施（LeRobot v3/Robo-DM 50× 解码差距/EAI-DM survey）
- **核实更正**（用户前提）：截至 2026-04 报道，星海图**无** UMI 类硬件产品，"UMI 数据"仅为其数据金字塔类别；GOD 数据集为 R1 Lite 单本体遥操。穿戴离机采集的中国代表是它石智航
- New entity [[TARS 它石智航]]（全 vendor/media 口径，标注清楚）；[[Galaxea 星海图]] 增补数据战略节 + B+ 轮估值更新。Wired: Embodied MOC（Syntheses + Orgs）、index（Syntheses + Entities）
- 置信度纪律：对抗验证阶段被跳过 → 笔记顶部与"未覆盖与存疑"节明确声明"关键数字进汇报前需回读原文"；secondary 来源全部标 media/vendor
- Follow-up (同日): 综合笔记 §1 增补"UMI 数据 ≠ human-centric 数据"概念澄清节——判据=动作空间属于谁的本体（机器人末端代理 vs 人手/无动作）、四范式谱系表、DexUMI 边界案例、"采集成本→管线模型加工负载转移"的系统含义
- Follow-up (同日): §1 增补"三层数据金字塔的分层采集趋势"节（数智前线 2026-05 框架收口）——顶层"卖里程→卖闭环"(工厂化/商品化/经验化)、中层"物理引擎→双引擎+兼评估器"、底层"捡数据→穿戴式主动生产+加工模型化"；跨层 meta 趋势(职能分化/边界移动/采集+模型加工复合管线)；记录 3% 可用率 × 500–1000 元/小时 → "竞争从采集规模换轴到数据引擎效率"论点；⚠️ 标注与 leaderobot"万元/小时"的量级矛盾待核
- **Correction (同日, Ethan 指正 + 回读原文核实)**: "3% 可用率"属**底层工厂视频数据**（李永露："11万小时工厂视频…乐观估计可用约3%"），非真机遥操——初版误挂。同源补充第二例：12万小时 Ego-centric 筛后可用于 VLA 预训练 ≤5000h（≈4%）；"500–1000元/小时"确认为真机**售价**口径（姚卯青，另称无本体效率≈真机2–3倍）。修正后论点重锚：可用率个位数是底层核心事实（"低成本"=毛成本幻觉，成本大头在清洗/筛选算力），"竞争换轴到数据引擎效率"结论保留且对底层最尖锐；顶层趋势证据改为纯"售价商品化"
- Follow-up (同日): 应 Ethan 追问，把中层"资产→可重生成管线"压缩语展开成表内注——本体贬值机制、管线=源码/数据集=构建产物/改版=重编译类比、系统含义（rev 触发突发重生成负载、数据 CI/CD 谱系）、vendor 折扣
- Follow-up (同日): 应 Ethan 追问补"中层 sim-to-real 六条趋势线"表内注（消解/校准/绕过/承认/融合/转岗：3DGS real-to-sim 资产化、可微系统辨识 D-REX/NeRD、世界模型产数据 DreamGen/Cosmos-Transfer、real 锚点混训、Real-is-Sim 动态孪生、仿真转岗评估器）+ "gap 换轴成算力问题"收口 + NVIDIA 栈垂直整合观察；2 轮 WebSearch 补源（DreamGen 2505.12705、Real-is-Sim 2504.03597 等），NeRD/D-REX 标搜索摘要级
- Follow-up (同日): §2 增补"两级体系 + 昂贵 oracle 代理层级"节（Ethan 问"是否主要靠训练后评测判数据"）——回答：最终裁决是（全部公司用下游表现背书数据价值），但运营是两级（样本级门禁 / 聚合级训练裁决）；per-sample 模型判别唯一工业化处=Recap value function（训练一次判别器换 per-sample 推理）；三层裁决回路差异（底层最粗/中层唯一自闭环/顶层最贵）；QA 体系=多级代理缓存层级、相关性系数≈缓存一致性、调度目标=最小化顶层 oracle 调用
- Follow-up (同日): §2 增补"各层判别好坏的具体例子"（Ethan 追问）——顶层判"演示对策略好不好"(人工核验/RINSE平滑度/DemInf互信息/CUPID influence/Recap advantage)、中层判"够不够真"(仿真自带成功标签/SIMPLER相关性=质检证书/WorldEval动作跟随性/DreamGen梦境过滤[记忆源])、底层判"能否转化"(工厂视频3%/Ego筛除96%/FastUMI SLAM门禁/Datacore置信度)；结论：三层"坏"定义不同→不存在统一质量分，判别成本不对称→QA基础设施形态迥异
- Follow-up (同日): §2 增补"机制辨析：哪些是真·训练后看表现"A/B/C/D 四分类（Ethan 追问）——A 聚合级数据集裁决(人人都做)、B 样本级仅 influence/datamodels 家族(DataMIL→CUPID→QoQ 逐级降价)、C 训练裁判=买断制(DemInf VAE统计量/Recap value function，工业化选C不选B的经济学)、D 无训练；"模型在环≠训练后看精度"、只有 A/B 调用昂贵 oracle
- Follow-up (同日): 增补"训练阶段×数据层矩阵"（Ethan 问 AgiBot World/WIYH/GraspVLA/FastUMI-100K 归类与阶段映射）——四数据集恰各占一类（真机遥操/穿戴人类/仿真合成/UMI桥）；四段管线（VLM底座→具身预训练三层混吃·模仿目标→真机SFT→仿真RL吃环境交互·真机RL吃部署经验）；修正两个混淆（仿真数据主通道=模仿预训练非仿真RL；遥操数据集不喂真机RL）；判断：部署经验是唯一随保有量自动增长的数据类
- Follow-up (同日): §3 新增 (d)"供给侧：为数据验证吞吐提速的训练管线优化"（Ethan 追问各公司有无专门优化）——五层哑铃形成熟度：I/O格式层(Robo-DM 50×/LeRobot v3 流式，证据最硬)、缩小oracle(冻结骨干+小头/小模型scaling代理)、验证折进训练(Recap/π0.7 消灭独立验证循环，最深)、仿真评估吞吐(万级并行+Tesla影子模式模板[存疑])、编排调度层(仅OSMO/重生成管线有痕迹——消融树调度/warm-start/增量估值近乎空白=空档)；标注研究机会：数据验证吞吐作为一等系统指标

## [2026-07-25] concept | 视觉 token 预算：剪枝 vs 压缩（EVS × π0.7 MEM）
- 起点：Ethan 问"Cosmos 3 是否用了 EVS"。库内 grep 全空（无 Cosmos 源笔记、0 处 EVS），外部核实后沉淀为新概念页 [[Visual token budget - pruning vs compression]]
- **一手核实**：下载 Cosmos 3 技术报告 28 MB PDF 到 repo 外 temp，`pdftotext` 全文检索 —— **`EVS` / `Efficient Video Sampling` 0 命中**（唯一 "pruning" 命中是数据筛选，无关）。EVS 只见于 NVIDIA 开发者博客 + NIM 服务文档，作用于 **Reasoner（AR/VLM 塔）推理阶段**。结论：**部署层可开关旋钮，非模型固有属性**，引用须限定到 NIM 层。合规 >2 MB Raw 规则，未提交 PDF
- EVS 论文（[arXiv:2510.14624](https://arxiv.org/abs/2510.14624)，NVIDIA，Bagrov 等）**逐表核实**，纠正二手摘要三处偏差：
  - **position ID 结论是分情况的**，非"position-preserving 一律更优"。原文 §3.3 + Table 2 九组逐格计票：**plug-in 下 Sequential 胜 6/9；uptrain 下 Position-preserving 胜 7/9**。机理：模型预训练未见过带洞位置 ID，硬保留是 OOD 输入，须 uptrain 才转为收益
  - **"4×" 是 LLM-only**。Table 6 自行换算：q=0.75 时 TTFT_llm 3.9×(7B)/4.1×(14B)，但 **TTFT_vlm 仅 1.78×/2.09×**，且模型越小越差 —— ViT 不省，原文 Future Work 自承 *"we pass the entire frame through the vision encoder and only perform masked selection before sending input to the language model"*
  - **"无需重训"仅架构层成立**。Table 5 q=0.75：VideoMME plug-in **−6.85%**，uptrain（beta 分布采样 q）后 −2.83%；TempCompass/nv-Metropolis uptrain 后转正
- ⚠️ **论文自相矛盾（已标存疑）**：§4.3 正文称 q=0.9 有 "13× TTFT reduction of LLM"，其 Table 6 实为 **8.3×(7B)/8.6×(14B)**，13× 要到 q=0.95。引用以 Table 6 为准
- 页面主论点：**同一根 token 预算轴，视频理解侧收敛到剪枝、具身侧收敛到压缩**，因量级差三个数量级（原文：2 分钟 24 FPS = 200 万 token；VLA 3 帧×2 视角 ≈ 1–2k）。具身侧四解法（π0.7 MEM 固定预算 O(1) / action chunking 减次数 / WAM 三代丢视频分支 / LaWAM 跳出像素）无一是剪枝
- 分析部分（页内明标"非论文结论"）：单帧 VLA 上 EVS 是 **no-op 而非精度下降**（T=1 无合法 t，M₀ 全保留）；失效诱因是"相机相对场景在动"而非"时间不连续"；不规则 Δt 破坏 position-preserving 的规则网格前提
- **诚实记录反证**：论文 nv-Metropolis 明写 *"single **moving** camera per scene"*，EVS 在其上 q=0.75 plug-in 仅掉 1.28%（四 benchmark 最小），**削弱**"相机运动必然使 EVS 失效"的强断言。张力未解决，已入 Open questions
- 论文 Future Work **点名机器人但作为未做方向**（流式关键帧 + KV-cache 跨调用复用 + 中间帧剪枝）—— 恰是绕开上述障碍的改造路径，已记为这条轴的移动方向
- Wired: index Concepts；[[VLA quantization]] 姊妹页互链；[[World-Action Models]] / [[VLA - Vision-Language-Action Models]] / [[NVIDIA]] / Embodied MOC。**Cosmos 3 源笔记仍缺**（地图页 backlog 早已标记），本次未建悬空链接


## [2026-07-07] restructure | 具身数据 synthesis 按三层金字塔重组
- 应 Ethan 要求把 [[Real-robot data collection - teleop vs UMI-class, and the model-in-the-loop quality problem]] 从"遥操 vs UMI 范式优先"重写为**三层数据金字塔五段式**：§1 特征对比(大表+UMI桥1.1+遥操vsUMI细表1.2+部署经验1.3+阶段×数据矩阵1.4) → §2 每层例子(顶层/桥/中层/底层四表+星海图核实框) → §3 每层趋势(卖里程→卖闭环 / 双引擎+可重生成管线+sim-to-real六线 / 穿戴式主动生产+可用率个位数;跨层meta) → §4 评估体系(定义收敛+三代谱系+两级体系+三层裁决回路+判别例子+A/B/C/D辨析+分层回答) → §5 计算系统挑战(oracle代理层级+L0–L3评估栈 / 闭环三负载 / 管线基础设施 / 供给侧五层 / **新增三层×算力形态收口表**：顶层贵在评估、中层贵在生成、底层贵在清洗)
- 对话中八轮追问补丁全部归位；新增内容仅 §5.5 收口表与"第二个异构性"论点；文件名保留(避免断链)，H1 改为三层主题；§6 集中列出记忆源清单(robomimic/DreamGen过滤/SynGrasp-1B/Tesla影子/OSMO)
- 同步更新 Embodied MOC 与 index 的条目描述。Lint 待验
- Follow-up (同日): **§6 未覆盖/存疑清单结清并删除**（Ethan 要求）——定点核实 9 项并归位正文：RoboMIND(2412.13877, RSS 2025: 107k 轨迹/479 任务/四本体/**5k 条带失败原因标注的失败演示**→入§2 顶层表)、OXE(2310.08864: 1M+/22 本体/60 数据集/527 技能→入§2)、ALOHA ~$20k+GELLO <$300(→§1.2 成本行, 三种价格口径 reconcile: 学术站造价/工业站造价/数据售价)、Figure Helix ~500h(官方博客→§2)、π 系列数据口径(vault 笔记补位: π0.5 400h MM/97.6% 迁移)、SynGrasp-1B(2505.03233 转正 primary: 十亿帧/10k 物体/240 类)、robomimic(2108.03298 转正: 6 操作员混合质量)、DreamGen(4 阶段管线+DreamGen Bench 替换未确认的"VLM 过滤"表述)、OSMO(转正并升级: 开源/YAML 工作流/数据谱系+版本化/CI-CD 夜间回归——"数据 CI/CD 现实雏形", §5.4 层5 改"唯一实例+空档")。纯 vendor 项(SynaData 200×/WIYH 8→60/Datacore/星海图估值)不可独立核实, 行内标注为最终状态。头部方法声明与 index 条目同步更新
- Follow-up (同日): §1.3 扩充"真机自演进的数据配方=双组分杠杆"（Ethan 问自演进是否主要靠少量高价值真实数据）——核实并入表：RoboCat(2306.11706: 100–1000 演示→自主练习~1万次, 1:10–100)、HIL-SERL(2410.21845/Sci Robotics: 1–2.5h 真机训练达近完美成功率, 奖励分类器+按需干预)、Recap(不筛数据全量+advantage 条件化)、Scanford(零人类信号特例)；回答：''少而贵''只描述人类信号半边, 自演进本质=把数据获取转化为质量信号提取, 稀缺的是人类注意力与质量信号；系统含义：打分算力=常驻负载、接管时机=主动学习(优化每次干预的信息量)。Sources 加自演进行
- Follow-up (同日): 自绘配图 `assets/fig-self-improvement-data-lever.svg`（Ethan 问有无图能展示自演进中人类信号 vs 自主数据比例；论文现成图仅有 HIL-SERL 干预率衰减曲线/RoboCat 循环示意，无一张以比例为主角）——双面板 house 风格：A 概念示意（累计数据构成堆叠面积：演示种子恒定带/干预带衰减→~0/自主经验超线性增长，末端高度比按线性轴压缩为 ~7:1 并在脚注声明真实比例见 B）；B 已核实量级（RoboCat log 轴配方 1:10–100 + HIL-SERL/Recap/Scanford 事实行，不同单位不混轴）；嵌入 §1.3。几何自检修正 5 处标签碰撞/越界；XML 校验通过


## [2026-07-30] ingest | LEACL — LLM-enhanced automatic curriculum learning (技能获取方法学首条)
- Ingested **LEACL** (Heravi et al., **UT Austin LARG / Peter Stone** + NTU + Sony AI; arXiv:2607.23515 v1, 2026-07-26) at user request. **HTML 全文自读核实**(LaTeXML v1);raw = **URL-only**(PDF 6.14 MB > 2 MB 规则)。检索侧记:该文太新(本月),关键词搜索搜不到,是用户直接给的 URL;搜索只捞到其前身——同一一作的 **UT Austin 硕士论文**(2025-05),arXiv 版参考文献 [4] 还留着盲审匿名
- **核心创新 = 换掉 LLM 的输出目标**:不写 dense reward(LEAGUE++/Text2Reward/CurricuLLM/ARCHIE 路线),而是生成 **ACL 所缺的任务规格**——① **参数化任务空间**(LLM 写 Python 生成函数,控制向量 c → 合法 PDDL 规格子集)② **难度排序**(按难度排好的 D 个参数向量);再接现成 ACL(**ADR** / TeachMyAgent)**只用稀疏完成奖励** + PPO(MLP 2×128)训练。三阶段:LLM 拆解→PDDL(双层 prompt + reflection) / meta-task 生成 / plug-and-play ACL
- **填两边各一个洞**:ACL 侧"任务参数空间+难度度量需人工设计"→ 交给 LLM;LLM+RL 侧"每个子任务仍需 dense reward(需模板、需人调、与稀疏目标错位)"→ 彻底绕开
- **结果**(5 seeds × 1000 ep, 95% CI, ≥500k steps):5 个 LIBERO+ 长程任务。**胜专家手工 dense reward(LEAGUE) 4/5**(LEAGUE 在 T5 崩到 0.0,方差 ±50.6/±37.4);人类课程上界仍胜 3/5,但 **T3 被 LEACL 反超**(89.4 vs 86.3),且 LEACL CI 明显更窄。dense reward 的失败机理讲得具体:诱导 "sloppy" 行为,精度不足以满足 goal predicate **合取**;稀疏+成功即终止反而更精确
- **⚠️ 两条限定入笔记**:(1) **低维状态 PPO、非像素非 VLA、LIBERO+ 自造 5 任务** → 分数**不可**与本库 LaWAM 98.6 / G0.5 98.9 / Motus LIBERO-Long 97.6 横比;(2) **自核对发现原文内部不一致** — 正文称 LEACL w/o ACL 得 32.8%,Table II 该格为 11.8 ± 15.4(以表格为准,标存疑)
- **对本库最有价值的一点 = 它反证了我们的论点**:在 [[Task Decomposition as OOD Mitigation]] 加"边界条件"节 —— **拆解 + 稀疏奖励 ≈ 0%**(3/5 任务全 0)。拆解把长程变短程,却没让子任务**可学**;即**拆解解决长度/信用分配,不解决探索**,段内仍需易→难脚手架。对 Agentic 框架的分工修正:**L3 管段间纠错,课程管段内可学性**
- 接线:[[Task decomposition]] 新增"**训练时拆解(课程生成)**"轴(此前光谱全是推理时拆解);[[Cloud-edge co-evolving embodied agent - a continuous-evolution framework|端云 co-evolution]] **云③技能工厂**补"课程生成"这一环(替掉逐任务手工 dense reward 这项线性人力成本 → 服务线性→亚线性主线);Embodied MOC 新增 "Sources — skill acquisition / training methodology" 小节;index Raw + Sources
- 开源:**LIBERO+ 仓库公开**(fheravi/LIBERO-plus, 2★, license 未标注);**LEACL 自身 pipeline 未见明确发布**。Cited-but-not-ingested 记入:CurricuLLM(ICRA 2025)、LEAGUE/LEAGUE++、Text2Reward、ARCHIE、IKER、Eurekaverse + ACL 侧(APT-Gen/ALP-GMM/PLR/ADR/SPDL/TeachMyAgent)
- 填补空缺:此前全库 "curriculum"/"sparse reward" **零命中**。Lint 干净:0 broken-A,新笔记零断链;125 notes


## [2026-07-30] refine | LEACL 定位 + 技能供给成本结构(teleop vs sim RL)
- 起因:用户指出这篇读起来"和 VLA 背景配不上",并追问"VLA 在 LIBERO 已 97–99%,那这么做的意义是什么"。补两处正面论述(此前笔记只有限定条款,没把"它的战场在哪"讲透)
- **LEACL 源笔记新增「定位:它的战场是零演示,不是 LIBERO 榜分」**:两 setting 的输入差异(VLA = 每任务几十条人类演示 + 3B 预训练 vs LEACL = 零演示零预训练,只要任务描述+仿真器+成功判据);**有意义的 delta 不是 89% vs 98%,而是 0% → 60–90%**;"移除人力"的五级链条(纯稀疏 0% → 演示(人力线性)→ 手工 dense reward(不稳,T5=0.0/±50.6)→ LLM 生成奖励(错位)→ LEACL(无人工且不写奖励));并明确按**方向性证据而非性能结果**使用(privileged state / 产出非可部署技能 / 依赖谓词词表 + 成功判据 / v1 小规模)
- **记入一般判断**:"benchmark 分数高"≠"问题解决了"——LIBERO 的饱和建立在**演示数据被无偿假定存在**之上,把演示拿掉立刻回 0%。**⇒ VLA 的进步不会自动降低技能获取成本**,那是一条独立且基本未解的战线(这解释了为何技能工厂目前只能写"teleop 为主要示范源")
- **co-evolution 框架 云③ 新增「技能供给的成本结构:teleop(人力线性) vs sim RL(算力)」小节**:两路线的成本性质与上限对照(BC 受示范者水平限制 vs RL 直接优化真实目标可超越);**库内先例** = [[Qi et al. - Humanoid-GPT (AstraBrain-WBC) Scaling Data and Structure for Zero-Shot Motion Tracking|Humanoid-GPT]] 从数百 RL 专家蒸馏(零人类演示)⇒ "sim RL 训专家→蒸馏部署"已被验证,LEACL 攻其第一步;**适用边界**(需可仿真 + 成功判据可定义 → 刚体/明确目标适用,形变/流体/新奇物体受限);**前瞻判断 = 双轨供给**,亚线性成立程度 ≈ sim RL 能吃下的比例,"把新技能化归为可判定的仿真任务"成为技能工厂的关键工程能力
- 这是技能工厂第一次有明确的**供给侧成本论证**(此前只有"模仿优先 + RL refinement"的做法陈述,没有成本结构分析)。Lint 干净(0 broken-A)


## [2026-07-30] concept | Robot data engine(数据引擎概念页;解析最后一个悬空链接)
- 建 [[Robot data engine]] —— 三层金字塔综述里自己标的"未来页(证据累积后可独立成 concept 页)"如今证据已足,遂收口。定位为**概念层**:定义/结构/索引,不复述综述的调研内容
- 内容:**数据集 vs 引擎的判据**(交付一批轨迹 vs 一条能反复吐轨迹并自判好坏的管线;后者资产是管线,本体只是可替换输入);**为什么具身必须要引擎**(根因 = 具身没有 LLM 那样便宜的内在质量代理,轨迹好坏只能由下游闭环表现定义 ⇒ 模型和训练进入度量回路 ⇒ 成本从人力/设备转向算力);**四部件**(产出/加工/判别/评估);**核心结构 = 昂贵 oracle 的多级代理层级**,⇒ **调度目标 = 最小化对顶层 oracle 的调用次数**(本页最具操作性的一句),含"训一次判别器 vs 每条跑 influence"的买断-vs-按次经济学
- **新增一条分类轴(本页自己的贡献)**:**生产型(produce-then-verify)vs 自演进型(deploy-then-harvest)** —— 数据来源/增长方式/引擎主要工作/真正稀缺资源/代表 五维对照。自演进型把"数据获取"转化为"**质量信号提取**",稀缺资源从数据变成**人类注意力**;并点明"自主经验免费但打分算力不免费"
- 收录两个异构性(统一引擎必须容纳):**质量度量异构**(顶层=教坏策略/中层=不够真/底层=转化不出 ⇒ 无统一质量分)+ **算力瓶颈异构**(顶层贵在评估/中层贵在生成/底层贵在清洗)
- 接线:综述末尾"未来页"标注改为实链(标注已建);co-evolution 的"技能供给成本结构"节加概念层指针;index Concepts;Embodied MOC Concepts
- **自己踩了一次 colon/filename 坑并即时修正**:该综述 H1 已改成"Embodied data — 三层数据金字塔…"但**文件名仍是旧的** `Real-robot data collection - teleop vs UMI-class...`;初稿按标题链接会断,已改为按文件名 + 别名,并在 Related 里就地标注该页"改版未改名,链接须用文件名"以免后人再踩
- **Lint 回到完全干净基线:0 broken-A / 0 broken-B / 1 orphan(根 AGENTS.md) / 1 dup(agents)**;126 notes, 17 assets。至此全库无悬空链接


## [2026-07-30] deepen | Task decomposition 训练时拆解:补 PDDL 符号层与 sparse/dense/ACL 三方关系
- 用户(VLA 背景)追问"PDDL 规格子集是什么""dense vs 稀疏奖励什么区别"——原节只写了 LEACL 的机制与结论,缺经典 RL/规划侧的背景。补两小节进 [[Task decomposition]] 的"训练时拆解(课程生成)"
- **背景一:为什么训练时拆解要落到符号规格上** — `τ=⟨M,F,R,P,I,G⟩` 构件 + `Open(drawer,0.3)` 实例;**关键连接:`I` 定义 RL 环境 reset 分布、`G` 定义成功判据 ⇒ 一份 PDDL 规格实质是在定义一个 RL 环境**。**决定性理由:稀疏奖励需要机器可判定的成功条件**——自然语言"抽屉开了"仿真器无法求值,`Open(drawer,0.3)` 可以;没有符号层就无法自动发奖励,整套稀疏 RL 跑不起来(故让 LLM 输出形式语言是工程必需,代价是需 reflection 纠语法)
- **"参数化任务空间 = 规格子集"就是难度旋钮**:谓词参数化(`open(object)`→`open(object,?o)`,LIBERO+ 的改动)+ LLM 写 Python 生成函数,其**值域 𝒯ᵢ⊂𝒯 = 同一子任务的全部难度变体**(柜子贴夹爪+开 0.05m ↔ 柜子远+全关+开 0.4m),ACL 在子集内按水平采样
- **背景二:sparse / dense / ACL 三方关系** — 稀疏=无偏但探索会死(纯稀疏基线全 0.0%);dense=有梯度但是"人对什么算进步的猜测",三个坑(设计细节极敏感:夹爪高度 vs 物体高度、碗 vs 番茄酱瓶 / 权重难平衡 / **诱导 sloppy 行为:增量进展但精度不足以满足目标谓词合取**)
- **收口洞见(记入引用块)**:**dense reward = 改造奖励制造梯度(引入偏置);ACL = 不动奖励,改造任务难度制造成功(奖励保持无偏)**。学习信号来自难度调度而非奖励塑形 ⇒ 同时拿到 dense 的可学性 + sparse 的无偏性,解释了 LEACL "更省人力且成功率更高"(胜专家 dense reward 4/5)这个反直觉结果
- 现在这节可自足阅读/对外讲解,不必回查论文。Lint 干净


## [2026-08-06] concept + synthesis | 真机评测:填补"评测作为测量学"的空缺
- **触发**:Ethan 提出真机评测的三分法(① 跑哪些任务 ② 任务配置 ③ 怎么打分),并给出自家现状(桌面机械臂单臂+双臂、抓瓶子/双臂交接果汁盒/叠 2 碗、采真机数据微调 π0、计划采购抽屉)
- **识别的结构性空档**:全库此前**没有评测的独立页面**。L0–L3 评估栈寄生在 [[Real-robot data collection - teleop vs UMI-class, and the model-in-the-loop quality problem|三层数据金字塔综述]] §5.1 里,语义是"数据质量判别的代理层级"——评测在那里是**被调用的 oracle**。而"评测作为测量学"(任务集设计、初始状态控制、统计功效、指标分层、可比性)无落脚点,导致 Ω-QVLA"10 rollouts 在噪声内"、G0.5"n=5"、NeuroVLA"自定义指标不可比"**三处同类批注散落在三篇 source note 里,没有汇聚成可复用判据**
- **拆成两页(生命周期不同,不合并)**:
  - [[Real-robot evaluation]](Concepts)—— 持久知识,随行业慢速演进,会被 map/其他概念页引用
  - [[Real-robot eval bench - task suite design and setup checklist]](Syntheses)—— **团队专属、有时效**,换本体或改 roadmap 即作废,页首列了适用假设表;**不应被其他页引用**
- **概念页三条判据(本库自有综合)**:
  1. **任务 vs 条件** —— "一个任务值不值得占评测位,看它能不能暴露别的任务暴露不了的失败模式;只换物体/位置/措辞的是 condition"。推论:**运动轴=线性人力成本(极度吝啬),指令/泛化/扰动轴=近零边际成本(极度慷慨)**,与"线性→亚线性"主线同构 ⇒ **评测集也有它的数据引擎问题**
  2. **复位成本是与能力覆盖正交的第二维** —— 自复位任务(终态可由逆操作回初态)当高精度探针(n 数百),高复位成本任务当低精度覆盖(n 数十),**两类不该用同一个 n 和同一套指标要求**
  3. **难度必须校准到基线 40–70%** —— 太高天花板、太低地板(LEACL"5 任务 3 个全 0"是地板效应教科书案例)
- **能力轴**:8 条运动轴按**质变点**(什么一变原 policy 就失效)划分,不按物体划;**轴 5 铰接与轴 8 双臂同步同属闭链问题**(臂-环境 vs 臂-臂),核心是**约束流形——垂直于流形的误差不再被容差吸收而是转换成内力**;指令/结构/泛化/扰动轴全部用 condition 实现
- **统计现实**:Clopper-Pearson,±10pp→±2pp 需 ~15× rollouts;**二元化每次 rollout 只带回 1 bit**,而物理时间不可压缩 ⇒ 用连续指标的理由是**信息密度**,不是某个连续量本身重要
- **指标四层分层(回应 Ethan 的正确质疑"平滑度阈值定不出来")**:验收/检测/诊断/硬约束,**只有验收需要绝对阈值**;回归测试有 FP16 基线 ⇒ 检测层用配对差值分布,不需阈值;平滑度只在对应物理约束时才是验收指标,**且阈值来自本体规格书不来自评测设计**
  - **平滑度的方向性漏洞**:"**什么都不做是最平滑的**"——畏缩型退化的 SPARC 反而更好 ⇒ 必须只在成功 rollout 上算。这解释了本库给 NeuroVLA 打 ⚠️ 的原因(把诊断量提拔成能力声明)
  - **更好的一等连续指标 = time-to-success CDF**:**成功率 = 该 CDF 在 timeout 处的取值**(失败即右删失)⇒ 严格包含成功率 + 速度分布,**没有代理缺口**
- **清单页**:8 轴覆盖诊断(现覆盖 2.5 条,**双臂同步闭链是最大空白——买了双臂硬件但一半能力从未被测**);Tier 0 五任务(只需买两个碗+一个抽屉)/ Tier 1 四任务;**抽屉专章**——`open→close` **自复位 ⇒ 唯一能便宜拿到 n=300+ 的高精度回归探针**,把手类型是第一难度旋钮,v0→v3 升级路径用同一套资产从轴 5 吃到轴 8,三个坑(柜体必须固定死否则配对统计作废 / 力矩保护须单列为一类失败否则归因错乱 / 硬件漂移是真机独有的基线污染源)
- **⚠️ 核实状态(两页页首均已标注)**:本轮引用的外部 benchmark 全部来自 **WebSearch/WebFetch 摘要器,未对照原文核实**——RoboDojo(arXiv 2607.04434,五维/18 real tasks/10 trials/三人双盲/π0.5 12.8% vs 人类 100%)、ATOM-Bench(arXiv 2606.16826,motor×instruction atoms/30+24/单臂双臂配对赛道/AS+CFS)、PhAIL(arXiv 2605.29710,time-to-success CDF+HRT+KS)、NVIDIA RoboLab(Clopper-Pearson 数字、三 competency、措辞三档)。**按 reliability discipline 未建 02 Sources 源笔记**——数字要引用前须回读原文
- **待办**:① 上述四个外部源值得正式 ingest 成 source note(尤其 RoboDojo 和 ATOM-Bench);② **ATOM-Bench"强原子技能不可靠地迁移到留出组合任务"是给 [[Task Decomposition as OOD Mitigation]] 的第二个反证**(LEACL 给的是"拆解不解决探索",这条给的是"原子会了不等于组合会")——该页修正应加一句"**也不自动解决组合**",待回读原文后回填;③ 子问题 ②(初始状态可复现性)与 ③(打分细则)尚未展开,而所有配对统计都建立在 ② 之上
- Lint 干净:**0 broken-A / 0 broken-B / 1 orphan(根 AGENTS.md) / 1 dup(agents)** —— 与既有基线一致;128 notes, 17 assets

## [2026-08-06] concept | Embodied failure detection — harness 侧失败检测的设计空间
- **触发**:讨论"具身 Agent 系统 vs LLM Agent 系统"时,Ethan 追问"失败检测 harness 侧具体能做什么"。此前这条线散在三处——[[Home robot architecture - a hierarchical embodied agent|dependability 脚手架]](只列研究线,未组织成设计空间)、[[Robot data engine]](质量信号视角)、[[Harness design]](通用 harness),无收口页
- **核心命题**:LLM agent 的失败信号是**免费**的(exception / traceback / 测试红绿,离散且可靠);**具身环境不报错** ⇒ 具身 harness 的一项本职工作是"**给自己造 exception**"。且这些机制**绝大多数不动策略权重** ⇒ 是三条提升途径里**最便宜的一条**(不要数据/不要训练/不要新硬件)
- **维度一 · 四类失败**:执行失败(本体可测,覆盖最好)/ **语义失败**(抓错物体、假成功 — 扰动场景主因,最难)/ **进展停滞**(长程最常见、最易漏,但检测极便宜)/ **不可逆事件**(检测到已晚 ⇒ 必须前置预防)。**现有工作多只覆盖第一类**
- **维度二 · 三个时机**:事前(唯一能挡不可逆)/ 事中(**必须端侧、断网可用**)/ 事后(回合级裁决 → 喂学习与记忆)。直接映射云-端分层与延迟预算
- **七种机制(按成本排序)**:①前/后置条件契约(只用本体可测量:夹爪宽度、**末端移动时物体是否跟随**、力阈值、关节位移=PDDL 谓词那套)②停滞/no-progress 超时(**性价比最高**)③**策略自身分歧信号**(多采样 action chunk 看方差 — π 系 flow matching 天然可多采;零额外模型零标注;= FAIL-Detect 2503.08558 / Sentinel 2410.04640 线)④预期-实测 assertion(调用前声明预期后置状态,VLM 核对)⑤**学出的判别器**(AutoEval 微调 PaliGemma 与人工 Pearson 0.942 / HIL-SERL 二值奖励分类器 / Recap value function — 三者皆"训一次、之后 per-sample 只花推理"的**买断制**;真实门槛 = 需采失败样本)⑥不确定→求助(KnowNo 2307.01928,把"检测失败"**前移**为"失败前求助")⑦世界模型行动前验证(World Action Verifier 2604.01985 / Ctrl-World 2510.10125)+ 端侧安全脊髓(CBF/SHIELD 2505.11494) — 最贵,**只对不可逆动作开**
- **落地优先级(分析判断)**:先 **1+2+3** — 零标注、零训练、可端侧、断网可用,即可吃掉**执行失败 + 进展停滞**两大类,而这两类正是长程 p^N 崩塌的主要贡献者;⑤有标注成本列第二步
- **两个设计原则(本页原创贡献)**:
  ① **检测器本身就是 harness 组件 ⇒ 同样适用 load-bearing 原则** — 每个检测器都编码"策略在这里不可靠"的假设;策略变强后会从"救命"退化为"添乱"(无谓重试),应**可度量贡献、可退役**。**目前无任何工作这么做(研究机会)**
  ② **漏报/误报代价不对称,且方向会翻转** — 长程里漏报(该停没停)代价远大于误报(错误沿链传播,正是 p^N 机制)⇒ 应偏保守;但真机重试有物理成本(时间/磨损/反复接触可能损坏)⇒ 又不能太保守。**该 trade-off 在仿真里根本不存在(重试免费),故现有工作全未处理**。给出真实目标函数:最小化(漏报传播代价 + 误报物理代价)
- **最有价值的推论(闭环)**:机制⑤训出的判别器**同时就是数据引擎的质量信号** ⇒ **做失败检测与做数据飞轮是同一件事的两面**(能判断"这次做成了吗"的东西,正好能判断"这条轨迹值不值得学")。已在 [[Robot data engine]] 加"与失败检测的同构"一节双向互指
- **顺带补溯源**:回应 Ethan 追问"harness 理念来自哪",给 [[Harness design]] 加溯源块 —— 明确综合自**两篇 Anthropic 工程博客**(同日 2026-04-12 ingest;核心论点/部件清单/**load-bearing** 来自 Rajasekaran 篇,**meta-harness + session/harness/sandbox 三层**来自 Scaling Managed Agents 篇),并如实标注 **⚠️ 二者均为厂商工程案例文章、非同行评审无对照实验(两篇源笔记各自已自标此局限),且库内无学术性 harness/scaffolding 文献**;补链 [[Alex Zhang - The Mismanaged Geniuses Hypothesis|MGH]](此前"脚手架 vs 基座模型"论点未直接链源)
- 接线:Embodied MOC Concepts、index Concepts、Home robot architecture 的"关键 meta 判断"处加展开指针。⚠️ **Harness VLA(2607.08448)本页以纯文本引用(尚未 ingest)**,避免制造悬空链接
- Lint 干净:**0 broken-A / 0 broken-B / 1 orphan / 1 dup**;129 notes, 17 assets

## [2026-08-06] maintenance | 术语去黑话:oracle → 各自的实际所指
- **触发**:Ethan 问"啥是 oracle,你一直在提";听完解释后判断"**不如直接换成它代表的意思,用太多术语会让文档变得晦涩难懂**"。采纳
- **换之前先发现的问题**:同一个词在库里其实指了**三件不同的事**——① 数据质量语境 = "全训练+真机评测"这个昂贵权威判定;② HarnessVLA 语境 = 仿真器给的成功判据;③ "oracle object coordinates" = 仿真器内部真值状态。**一词多指正是它让人卡壳的原因**,所以换成各自所指反而更准确,不只是更通俗
- **替换方案**:数据质量/评测语境统一为「**金标准**」(它本来就是"其余一切都在近似的权威参照",中文技术写作里通用、无需解释,且天然支撑"代理/缓存层级"的说法);[[Embodied failure detection]] 里 HarnessVLA 那处换成实际所指「**仿真器成功判据**」
- **范围**:**25 处 / 7 个文件** —— [[Robot data engine]](4)、[[Real-robot evaluation]](3)、[[Embodied failure detection]](1)、[[Real-robot data collection - teleop vs UMI-class, and the model-in-the-loop quality problem|三层数据金字塔综述]](8)、[[Real-robot eval bench - task suite design and setup checklist]](1)、Embodied MOC(4)、index(4)。脚本替换 + 逐行 diff 目视核对,顺带吸掉中英混排空格
- **`90 System/log.md` 未改** —— append-only 历史,与此前 colon-title 链接修复时同一原则:历史条目保留当时的措辞
- **保留一处术语指针**(经用户口味权衡后的折中):[[Robot data engine]] 定义处加行内小注"(权威但贵到调不起的那个判定;文献中多称 *oracle*)" —— 让读者能按论文里的说法反查,但正文不再依赖该词。若嫌多余可删
- Lint 干净:0 broken-A / 0 broken-B / 1 orphan / 1 dup

## [2026-08-06] ingest + deepen | Harness VLA(清华)+ 具身 harness 三处深化
一次讨论(具身 Agent vs LLM Agent → harness → 失败检测 → τ 真机可行性)的四项收口,一并落盘。

### ① Ingest: [[Zhang et al. - Harness VLA Steering Frozen VLAs into Reliable Manipulation Primitives via Memory-Guided Agents|Harness VLA]]
- arXiv:2607.08448 v1(2026-07-09,cs.RO,CC BY 4.0);**清华** + Striding AI + Purdue + 中科院自动化所 + **无问芯穹** + 中关村学院 + 港科大;通讯 Chao Yu。raw = URL-only(**HTML 全文自读核实**)。⚠️ 用户最初称"清华提出的",我一度说无法核实作者单位,**后经全文确认属实**
- **机制**:冻结 VLA(π0.5-SFT / RLDX-1 / LingBot-VLA 三 backend)降级为单个 primitive `vla_act`,与**固定小解析原语库**由 agentic planner 用 JSON 编排;planner 从不发力矩/关节目标/action chunk。**词表评测前固定,planner 不能发明新原语**
- **三个值得记的机制**:① **接口载荷 = (prompt, 终止判据 τ)**,τ ∈ {lift-and-grasp / contact-state / **benchmark predicate** / chunk budget} —— 一个参数把通用专家特化成多个局部专家,零权重改动;② **两层判定**(执行中环境按 τ 判何时停手 ≠ 返回后 planner 判成没成;论文自划界"post-condition 不是 task success 的替代");③ **re-staging = 重选交棒点**(改 approach pose/viewpoint/staging = 在 `o₀` 上搜索,把机器人送进 VLA 能力域),**不是回退世界**
- **双记忆**:TSM(程序性 trace = 任务级解法骨架,**空间参数是 reference-scene binding 须重新接地**)+ GM(success rules + failure models);**refine 而非累积**
- **结果**:不微调 LIBERO-Pro **+38.6pp** / RoboCasa365 **+25.4pp** / RoboTwin C2R 58.4%,标准 LIBERO 不退化
- **⚠️ 按用户要求设"真机部署时无法实现的技术点"专章**(6 条 + 替换方案):① benchmark completion predicate 作成功判据**且已进入决策回路**(GM 明写"check the benchmark success signal")② **τ 可直接取 benchmark predicate**(连终止条件都能挂仿真判据)③ 重试近乎免费(真机有时间/磨损/损坏成本)④ 回合自动复位(真机复位成本是与能力覆盖正交的第二维)⑤ 不可恢复失败只标注不处理 ⑥ 无噪声本体/深度观测。**公平之处**:空间真值上克制(不给物体坐标,强制 RGB-D 自定位)⇒ 问题不在感知作弊,**在"谁告诉你成功了"**
- **对本库的意义**:**[[Harness design]] 概念的首个学术量化证据**(此前仅靠两篇 Anthropic 厂商博客);**[[Alex Zhang - The Mismanaged Geniuses Hypothesis|MGH]] 在具身侧的强验证**(完全冻结的 π0.5 +38.6pp ⇒ 能力本就在权重里,是脚手架浪费了它);化解"扩库 vs 冻结库"张力 ⇒ **扩库必须在有验证门的一侧,部署时只许学会用现有的**

### ② [[Embodied failure detection]] 三处深化
- **新增「谁来判、判什么:三层分工」** —— L1 本体谓词(wrapper 固定小谓词库,控制环频率)/ L2 学出的判别器(语义级,~10Hz)/ L3 planner(秒级)。**澄清常见误解:τ 不是动作模型的职责**,判定在包着 VLA 的 wrapper 代码里,故"VLA 没被训练做判别"不构成障碍
- **τ 四形式的真机可行性表**:chunk budget ✅ / contact-state ✅(**真机上甚至更自然**,有 F/T 传感器)/ lift-and-grasp ✅ / **benchmark predicate ❌ 仿真专属**。⇒ 真机执行期判定可行且必须存在,但**只能基于本体可测量**
- **由此推出机制⑤的结构性理由**(此前只给了功能性理由):真机 τ 只能"很笨"⇒ 判定压力上移 ⇒ planner 秒级接不住 ⇒ **中间频率鸿沟必须由端侧学出的判别器填**,它填的是[[Embodied Cerebellum Models|多速率栈]]的一个空档
- **回答"规则会不会爆炸"**:不会——**任务无穷但物理事件类型有限**(八类);按"**固定谓词 × 任务参数**"组织即可(同 PDDL/LEACL/Harness VLA 的"小而固定的库"哲学)。分工:谓词实现=工程一次性、跨任务复用;谓词选择与参数=planner 调用时绑定。**爆炸只发生在按任务写规则时**。剩余真实成本=阈值标定(**按本体一次性,不随任务数增长**)
- **新增「主动探测 active probing」** —— harness 特有、模型做不到的一招:**主动改变观测来消除歧义**(不确定抓住没有 → 轻轻抬 2cm 看物体跟不跟)。**与 LLM agent"跑一下测试"完全同构**;绕开阈值精度问题;天然受"失败可逆"约束(探测动作须廉价可逆)。⇒ 设计规则:**每个高风险 primitive 配一个廉价探测后缀**(目前无工作系统化做)
- **前置条件改为中性表述**:Harness VLA 无显式前置守卫是**设计选择而非遗漏**(load-bearing 原则:planner 够强则该部件不承重);但保留其独立价值——**最便宜的事前拦截**,位于"什么都不做"与"世界模型验证(最贵)"之间,可挡掉一部分不可逆失败

### ③ [[Future embodied Agent framework - integrated view]]:计划级接口的具体形态
"接口是计划级"此前只是抽象说法 ⇒ 补入实证形态:**载荷 = (目标, 终止判据) 二元组**——planner 下发的不只是"做什么",还包括"**什么时候算做完**"。比"结构化计划/子目标"具体一档

### ④ [[Cloud-edge co-evolving embodied agent - a continuous-evolution framework]]:能力画像的精确化
从抽象说法收紧为:**能力画像的本质 = 这个技能的「能力域」边界在哪**(`p(success|o₀)` 中什么样的 `o₀` 能成);⇒ **大脑的工作 = 把系统送进能力域再交棒**;落地形态**不是数值向量**而是成功规则+失败模型+解法骨架(空间参数须标为参考场景绑定);**补一个此前遗漏的维度:失败后果是否可逆**(决定能否自主重试)

- 接线:Embodied MOC 新增 "Sources — embodied harness / agentic scaffolding" 小节、index Raw+Sources。Lint 干净:**0 broken-A / 0 broken-B / 1 orphan / 1 dup**;131 notes, 17 assets

## [2026-08-06] ingest + correct | Sentinel:失败检测的真实机制(并修正三处我编的说法)
- **触发**:Ethan 追问"FAIL-Detect 具体怎么用策略自身信号做失败检测""和不确定求助有无关联",继而追问 STAC 与 VLM 的具体机制。**我此前只从 dependability 表里引用这两篇、从未读过**,给出的"多采样 action chunk 看方差"是**自己的推断**。读原文后发现说错了 ⇒ 本条含三处更正
- **Ingest [[Agia et al. - Sentinel Runtime Monitoring of Consistency and Progress for Generative Policies|Sentinel]]**(arXiv:2410.04640,Agia/Sinha/Pavone/Bohg 等;raw = URL-only,**HTML 全文自读**含附录 prompt 模板)
- **STAC 真实机制**:生成式策略每 `k` 步重规划但预测 `h` 步(`k<h`)⇒ **t 与 t+k 的 chunk 时间重叠**;STAC = 两分布在重叠窗口上的**统计距离** `D(π̄_t, π̃_{t+k})`,用 **MMD+RBF** 经验近似。**假设(原文)**:策略相当于"possessing an **internal world model**",分布内则它会同意自己刚才的预测,OOD 时**自我矛盾**。⇒ 测的是**跨时刻自一致性**,不是单时刻不确定度。**策略无关**、成本可忽略、校准只需少量成功 rollout、附录有 **conformal 保证 + 证明**
- **VLM 监控**:**不微调**,零样本 prompt 现成闭源模型(GPT-4o / Claude 3.5 Sonnet / Gemini 1.5 Pro,同一套 prompt);**输入 = 抽帧视频**(~1Hz,ν∈{1,2})+ 任务描述 + **时间限制 + 已用时间**;prompt **三段式强制自问自答**(Questions→Answers→Analysis,显式要求对比已用/限时 + "除非不太可能完成否则别判失败"防误报);**每 episode 仅查 2 次**、**非阻塞 API**
- **结果**:STAC 检出 erratic **99%**;Sentinel 并行 **>97%**、比单用任一 **+18%**;task-progression 上 STAC 单独仅 **44% TPR**、组合 **93% TPR**(FPR 仅 +7%);erratic 上 VLM 仅 **77% TPR** 且慢;**真机 Push Chair 总准确率 95%**(VLM 真机 90/100,优于仿真)
- **⚠️ 更正一(机制③的描述是错的)**:我写的"多采样看方差"——**朴素的 Diffusion Output Variance 恰恰是 Sentinel 里被 STAC 击败的 baseline**,原文并指出它"does not quantify epistemic model uncertainty"。且消融显示**用非统计距离(min. distance)比 baseline 还差**,因为抹掉了动作多模态性 ⇒ **必须用分布距离**。已改写机制③并加"两个必须记住的更正"框
- **⚠️ 更正二(③ 与 ⑥ 不是并列)**:实为**一条流水线** —— 信号提取 → **conformal prediction 校准** → 有保证的决策(报警/求助)。**CP 是共同连接组织**:KnowNo(语义层)、FAIL-Detect(执行监控层)、STAC(动作一致性层)是同一套机器施加在不同层次;**CP 的 α 就是本页"漏报/误报权衡"原则的可调旋钮**(如何按代价选 α 列为 open question)
- **⚠️ 更正三(机制⑤门槛过强)**:我标的"真实门槛=要采失败样本"被证伪 —— FAIL-Detect 整篇论证 *"detect failures **without failure data**"*(仅用成功数据),STAC 校准同样只需成功 rollout。代价是问题弱化为"是否偏离训练分布"(OOD ≠ 一定失败),但**对冷启动极有价值**。已改为"需正负样本的是更强但更贵的一档,不是唯一入口"
- **新增结论(本轮最有价值)**:**分层依据是三维,不只是成本** —— 检测成本 × 干预紧迫性 × **信号模态**。第三维最本质:erratic 在**动作空间**明显而**视觉细微**(VLM 77%),task-progression 在**视觉明显**而**动作空间自洽**(STAC 44%)⇒ **两类失败在不同表征空间才可见,这才是"必须有两个检测器"的根本原因**;成本与紧迫性只决定放哪个频率层。已写入维度一之后
- **旁证**:Sentinel 独立验证了本库此前推导的三层频率分工(便宜的管时间敏感、贵的管不时间敏感),且**失败检测这条线的真机成熟度高于 harness 编排那条线**(Sentinel 真机 95% vs Harness VLA 全仿真)
- **FAIL-Detect 仍为摘要级**(2503.08558,未读全文,页内已标注)——值得单独 ingest
- 接线:Embodied MOC 新增 "Sources — failure detection / runtime monitoring" 小节、index Raw+Sources。Lint 干净:0 broken;133 notes

## [2026-08-06] ingest | FAIL-Detect(TRI):"检测失败但不需要失败数据",并回填两条限定
- **触发**:Ethan 追问"FAIL-Detect 怎么把输入输出蒸馏成标量信号""CP 是什么意思"。此前该篇在库内仅**摘要级**,遂读全文 ingest([[Xu et al. - FAIL-Detect Uncertainty-Aware Runtime Failure Detection for Imitation Learning Policies]],arXiv:2503.08558 v3;raw = URL-only,HTML 全文自读)
- **作者/机构核实**:Chen Xu 等,**Toyota Research Institute (TRI)** + Woven by Toyota —— 本库 dependability 表里已有的 "TRI LBM" 同源
- **两阶段框架**:① 打分 `D_M(A_t, O_t; θ)→标量`,**输入 = 最近 `T_O=2` 步观测(机器人状态+视觉特征)+ 策略生成的未来动作**,**刻意不喂增长的历史轨迹**(防在历史上过拟合);② **conformal prediction 构造时变阈值**
- **四类打分器(全部只用成功数据)**:(a) 学出的数据密度(logpO / **logpZO**)(b) 二阶分布(NatPN Dirichlet 先验、DER 多元证据回归 —— **分离 aleatoric/epistemic**)(c) 单类(CFM、RND)(d) post-hoc 不学习(**SPARC 动作平滑度**、PCA-kmeans、**STAC**)
- **logpZO(本文最佳,机制值得记)**:logpO 直接算 `log p(O_t)` 需**沿 ODE 积分 `f_θ` 的散度**,高维难估;logpZO 改为用同一 CNF 跑**前向 ODE** 把 `O_t` 推到噪声空间得 `Z_{O_t}`,**分布内时近似标准高斯** ⇒ `p(Z)=C·exp(−0.5‖Z‖²)` ⇒ **分数本质 = ‖Z‖²**。**绕开散度积分**,实测 **0.04 s(Square)/0.033 s(Transport) 每步**
- **CP 的具体用法(比标准 CP 进一步)**:**单侧 + 时变** band —— 单侧因只关心分数偏高;时变因各时刻正常水平不同,故从**成功 rollout 校准集**算每时刻 `μ_t` 与带宽 `h_t`(带宽取"**最大偏差**"分位数以覆盖整条轨迹)。**两种标定**:setting-dependent vs **ID-only**;仿真中 **ID-only 即可覆盖 ID+OOD 测试,实践上更可取(无需预采 OOD 数据)**。对比:**STAC 用单一常数阈值**,本文改进之一即以时变 band 取代之
- **结果**:**learned > post-hoc** 且**更快**(准确与速度不取舍);**logpZO 最一致**(combined accuracy top-1 10/16;硬件小样本 8/12 top-1、11/12 top-3);STAC top-1 仅 3/16,PCA-kmeans 从未最佳,SPARC 最快但从未 top-1。定性:Square 上**分数陡增恰对应夹爪脱手瞬间**
- **实验**:仿真 Robomimic(Square/Transport/Can/ToolHang,略去 Lift 因两策略均 100%),OOD 由 **t=50 模拟相机碰撞**;真机**双臂 Franka Panda** 的 FoldRedTowel / CleanUpSpill(OOD = 皱毛巾+蓝铲干扰、换绿毛巾;另有人为拉扯)。**两种 backbone:FM 与 DP**;rollout 仿真 2000 / 硬件仅 50
- **⚠️ 回填限定一(推翻上一条 log 的判断)**:**STAC 未必能放端侧实时跑** —— FAIL-Detect 硬件实验**没跑 STAC**,原文 "*slow to run on hardware in real-time*",因其**每步需 256 条动作预测**(少采会损害统计性质)。Sentinel 自称"negligible cost"是**相对 VLM** 而言。⇒ 已在 [[Embodied failure detection]] 机制③加限定框:**"便宜"要分清相对谁**
- **⚠️ 回填限定二**:**"策略自身信号 = 免费"要收紧** —— 真正好用的是 **learned** 信号(需离线训小流模型);**post-hoc 免费信号(采样方差/SPARC/PCA-kmeans)在两篇论文里都被系统性击败**。正确表述:**"离线训一次(只用成功数据)+ 在线推理便宜"** = [[Robot data engine]] 的**买断制**结构再次出现
- **另补**:机制⑤门槛条additionally 注明 **ID-only 校准即可覆盖 OOD**(冷启动无需预采 OOD 数据);机制③的 FAIL-Detect 条目由"摘要级"升为全文核实并写入 logpZO 机制
- **CP 的第三个落点确认**:本文 related work **自己就把 KnowNo 归为 CP 的另一应用**(为 LLM planner 的动作构造不确定性集合、有歧义时请求人工)⇒ 印证"KnowNo(语义层)/ STAC(动作一致性层)/ FAIL-Detect(执行监控层)是同一套机器施加在不同层次"
- **两篇姊妹工作的互补性未被任何一方测过**(logpZO 强在 erratic/OOD、Sentinel 的 VLM 强在 task-progression)——已列为两篇源笔记的 open question
- Lint 干净:0 broken-A / 0 broken-B / 1 orphan / 1 dup;135 notes

## [2026-08-06] deepen | Harness VLA 回填五处(planner 身份 / 感知管线 / 零训练 / TSM 消融)
连续追问("planner 是什么模型""是不是没真正训练""需要多模态吗""observation 是仿真图像吗")逼出的五处核实,原源笔记均缺。
- **① planner = 现成编码 agent,零微调** —— **Codex**(OpenAI)与 **Claude Code**(CC)两个实例,共享同一 harness/记忆接口/原语库/冻结 VLA 接口/评测协议,**仅 backbone 不同**
- **② ⚠️ 两个 headline 数字来自不同实例**(此前我写成同一套结果,不准确):LIBERO-Pro **82.4% 用 CC**(+38.6pp vs RATS),RoboCasa365 **55.4% 用 Codex**(+25.4pp vs RLDX-1);RoboTwin C2R 两者接近(58.0/58.4);标准 LIBERO CC 96.0%(384/400)vs 冻结 RLinf 95.3%
- **③ File-Mediated REPL Protocol**(附录 A):environment worker 持有实时仿真态,planner **只通过文件**交互(写 `command.json` → 等 `done_NN.flag` → 读 state/log/images/depth/**world maps**),**不接触特权状态/物体位姿/控制器内部**。原文点睛:"**every primitive call is treated as an experiment whose result must be observed before the next command is issued**" —— 与 [[Embodied failure detection]] 的**主动探测**同一心智模型。⇒ **把"操作机器人"包装成"读写文件",通用编码 agent 无需机器人专用改造即可上手**,这才是它能用 Codex/CC 的真正原因
- **④ 感知管线(重度多模态)**:**RGB 管语义**(杂乱/身份)、**共对齐深度图 + 本体感知管度量**。因禁止拿物体坐标,prompt 给六条定位规程(RGB 识别 → 可见表面挑像素 → 索引**预计算 world map** → **多采取中位数** → 避开边缘/孔洞/反光/背景 → 状态一变即重定位)。**本库判断**:这是**把"精确 3D 定位"这件 VLM 做不好的事,降级成"指几个像素"这件 VLM 做得还行的事** —— 语义由 VLM 出、精度由深度出,**VLM 只指哪儿不算坐标**;④⑤ 两条是在用采样/拒绝规则补偿单点深度不可靠。**⚠️ 隐藏真机成本:整套定位高度依赖深度质量**(真机有空洞/反光失效/标定漂移),比"成功判据"更易被忽略
- **⑤ "learn 适用范围"的准确含义**:拆成**三个可回答的问题**(哪些子问题走解析式 / 何时调 `vla_act` / 失败怎么重摆位),分别由 GM 成功规则、GM+TSM trace、GM 失败模型承担。**且 learn ≠ 训练**:三层全零梯度(解析式原语 "require no training data"、VLA 冻结、planner 无微调);论文**自列为局限**并指向未来 **GRPO**("open feedback loop""lacks joint fine-tuning")
- **⑥ TSM 消融(对能力画像这条线最有用)**:LIBERO-Pro Goal 严格零样本撤掉 TSM,得 **31.0%(Pos-S)/79.0%(Task-T)**,**仍胜 Cap-X 25.6%/16.8%** ⇒ **记忆是加成不是必需;基座 planner 决定"没有记忆时的地板"**
- **回填到 [[Cloud-edge co-evolving embodied agent - a continuous-evolution framework|co-evolution 框架]] 的能力画像段**:① 画像是**增量可测量的组件**而非系统前提;② 随基座变强其边际价值可能下降(**load-bearing**);③ **载体是文本而非权重**的双面代价 —— 零训练成本/可读可编辑/**可直接复制到另一台机器人(车队共智的极便宜通道)**,但受上下文限制、**软约束不保证遵守**、**无法像权重那样插值泛化**
- Lint 干净:0 broken;135 notes

## [2026-08-06] ingest | HELM:"harness 直接建在 VLA 上"这一类的代表
- **触发**:Ethan 问"有没有不是 planner+原子原语、而是直接在 VLA/WA 上建 harness 的工作"。搜索发现这是**一整簇**(四类:包住执行环 / 测试时采样+验证 / 冻结 VLA 上的失败恢复 / 世界模型当 harness),先 ingest 最直接的一篇
- **[[Zeng et al. - HELM Harness-Enhanced Long-horizon Memory for VLA Manipulation|HELM]]**(arXiv:2604.18791 v1,2026-04-20,cs.LG;**清华 + 阿里** + 蚌埠学院;raw = URL-only,HTML 正文自读)
- **与 [[Zhang et al. - Harness VLA Steering Frozen VLAs into Reliable Manipulation Primitives via Memory-Guided Agents|Harness VLA]] 的关键分野**:同样是冻结 VLA + 记忆 + 验证 + 恢复,但**VLA 的角色相反** —— HELM 里 VLA **仍是主执行者**(harness 只补它缺的),Harness VLA 里 VLA 被**降级成原语库里的一个 primitive**。两篇合看说明"具身 harness"是**正在成形的方法族**,不是孤例
- **立论(硬对照实验)**:LIBERO-SPATIAL(2.3 subgoal)91.2% vs LIBERO-LONG(5.8 subgoal)**58.4%**;**把上下文 H=8→32(4×)只涨到 63.8%(+5.4pp)**,余 17.7pp 无法解释 ⇒ **缺的不是窗口长度,是执行环三个缺口**
- **三缺口(失败分类学)**:**memory**(丢弃已完成子目标证据;原文实例"**t=47 时想不起 t=12 已把杯子放进柜子,于是重做一遍、污染任务状态**" ⇒ 这里的"阶段"= **subgoal**,失败模式是"忘了已经干过"而非"忘了要干什么")/ **verification**(反应式提动作,执行前无检查,不可行抓取/抓错物体/越工作空间**静默执行并传播**)/ **recovery**(在被污染状态上继续 → 跨子目标级联)
- **EMM**:CLIP ViT-B/32 索引的 key-value;value 含关键帧/活动子目标/**完成状态**/时间步/状态 delta。写于**子目标完成 / 检测到失败 / 每 20 步 checkpoint**;top-**3** 检索后**序列化成结构化文本追加进 VLA 的语言输入**;超 50 条按子目标压缩
- **SV(核心贡献)**:`P(fail_t | o_t, a_t, g_t, M_t)` —— **记忆条件化的执行前失败预测**。3 层 MLP[1024→512→256→1],输入 = 当前观测 CLIP embedding **拼 top-1 记忆 key** + 投影动作 + 子目标文本;50K 三元组(**y=1 若 5 步内失败**),BCE pos-weight 4.0,**单卡 A100 ~2h**;θ_v=0.65,**12 ms/步**。**去掉记忆 AUROC 0.847→0.791**;论文明说 MLP 是**为低延迟刻意选的**,消融证明**关键是记忆增强的输入而非容量**
  - **金句(全篇最深)**:"whether an action is valid often depends on **what has already been completed** — placing an object that was already placed is a failure **regardless of current visual feasibility**" ⇒ **把前置条件从几何可行性提升到任务状态语义**;纯几何前置条件根本表达不了"这东西已经放过了"
- **HC 怎么回滚(回答 Ethan 的问题)**:维护 **subgoal 栈**(初始由**提示 VLA 自己分解任务**)+ **completion detector**(与 SV 同架构、训练在完成标签上)。触发 `p_fail>θ_v` 或完成检测判负 → ① 从 EMM 取最近 checkpoint/success 条目 → ② 发**目标条件化恢复序列**,prompt = **"return to the state shown"** → ③ **失败 subgoal 重新压回栈** → ④ 失败条目入上下文;**最多 3 次**
  - ⚠️ **"回滚"不是仿真器 reset,而是拿历史关键帧当视觉目标、让 VLA 自己把世界开回去** —— **由策略执行的物理回归**,故原则上真机可行但受"回得去吗"限制。论文自列 **"rollback feasibility in real-world settings"** 为局限,并给 **HELM-Fwd 前向恢复变体**(从当前受损状态生成前向计划)。**直接对应本库"失败可逆性"判据**
- **结果**:**58.4%→81.5%(+23.1pp)**;SV +8.4pp > rule verifier +6.8pp,ensemble +9.5pp 但**需 5× 推理成本**;SV 去记忆退化 6.1pp;**F_R 降幅最大 82%,由 rollback 驱动**;评测 LIBERO-LONG(500 ep)/ CALVIN ABC→D / **LIBERO-Recovery(本文发布的扰动注入恢复评测协议)**;9 个 baseline 含 oracle memory、long-context、same-budget LoRA
- **对本库最有价值的三点**:① **SV = 我们此前推演的"前置守卫"的已实现版本**,且比设想更进一步(必须条件化于任务历史);② **"记忆 ≠ 更长上下文"的定量证据**(4× 上下文 +5.4pp vs 结构化记忆 +23.1pp)—— 可直接引进 [[Memory in Embodied AI]];③ 三缺口 memory/verification/recovery 与本库 [[Embodied failure detection]] 的"四类失败 × 三个时机"可对齐,且指出 **memory 是事前与事后共同依赖的上下文底座**(本库此前没有这一层)
- **⚠️ 局限**:纯仿真无真机(而回滚可行性恰是真机问题);**SV 需失败标签**(50K 三元组)—— 与 [[Xu et al. - FAIL-Detect Uncertainty-Aware Runtime Failure Detection for Imitation Learning Policies|FAIL-Detect]] 的"**只用成功数据**"形成直接对比,冷启动成本更高;基座主要 OpenVLA(自回归),对 flow-matching/diffusion 未验证
- **同族待 ingest(搜索级,已记入源笔记 open questions)**:测试时采样+验证一族(**RoboMonkey** / **RoVer** 2510.10975 / **MG-Select** 2510.05681 ICLR26 verifier-free 用内部 KL / **DREAM-Chunk** 2606.18589)、冻结 VLA 恢复一族(**B2FF** 2606.09258 —— **在子目标空间 re-staging**,给 VLA 一张熟悉的未来图像而非移动机器人 / **ReCoVLA** / **FAR**)、世界模型当 harness 一族(**Ctrl-World** 2510.10125 ICLR26,**库内已引用但无笔记**,想象中 rollout 排序策略、合成轨迹 SFT +44.7% / **PiL-World** / VLAW / WMPO)
- Lint 干净:0 broken;137 notes

## [2026-08-06] verify + framework | RoboOS 核实 → 识别"第三条通道"空缺;并把"架构吻合≠已验证"写进核实纪律
- **背景(一次值得记的连环纠错)**:把搜索范围从 "harness" 扩到"具身 Agent 框架/系统"后找到一批系统,我**基于搜索摘要**把 **ABot-AgentOS** 排第一(因其组件清单与本框架逐条吻合:agent harness / skill runner / 端云双 LLM)。**Ethan 质疑"它训的都是语言模型、评测都是语言任务"** —— 核实后**质疑成立**
- **ABot-AgentOS 核实结论**(arXiv:2607.10350,**AMAP CV Lab 高德**,**cs.AI**):训练的是 **Writer / Answerer** 模型(记忆写入+问答,非控制器);量化全在 **LoCoMo 87.5 / OpenEQA 59.9 / Mem-Gallery 88.6 / NExT-QA 76.5 / EgoLife** 等**记忆与 QA benchmark**;唯一具身评测是**自建的 EmbodiedWorldBench**(`NPC`×23、`Unreal`×4 ⇒ **Unreal 仿真场景**,任务为导航/物体搜索/NPC 对话,**非操控**),且只跑 **"initial subset"、摘要未给数字**;`real robot`/`LIBERO`/`CALVIN`/`robot arm` 全 0 命中。**架构描述属实**(Agent Harness 三件套、Skill Runner、端侧 Tiny LLM 按需升级云端 Large LLM 均在 §2.2)⇒ **架构真实、具身实证薄**,只能当**架构参考**
- **⇒ 新增核实纪律条款(写入 [[90 System/AGENTS]] Reliability discipline)**:**"架构吻合 ≠ 已验证"** —— 系统论文的组件清单**写起来不花任何证据成本**,可以与你已有的框架完美对齐而全无验证。**排序/推荐系统类论文前,先问"量化结果究竟测在什么任务上",再看架构图**。附具体识别信号(名字带 robotic/embodied 但 benchmark 全是 QA/记忆;唯一具身 benchmark 是自建且只报 subset;全文无 success rate;训练的是 writer/answerer 而非控制器;arXiv 分类 cs.AI/cs.CL 而非 cs.RO),并要求笔记里**显式分开记录"架构声称什么"与"数字覆盖什么"**
- **RoboOS 核实**(arXiv:2505.03673 v2):架构与真机为真 —— Brain-Cerebellum 分层(**它自己就用这个说法**)+ RoboBrain(MLLM 大脑)+ Cerebellum Skill Library + **Real-Time Shared Memory**(多智能体状态时空同步);真机覆盖**单臂/双臂/人形/轮式**,场景餐厅/家庭/超市;自称首个开源同类系统。**⚠️ 但 `success rate` 全文 0 命中**——量化集中在**大脑模型 RoboBrain 的四项 benchmark**(多机规划=**工具调用 AR**,每场景 200 条生成样本 / Where2Place pointing / AGD20K affordance / ShareRobot trajectory)+ FlagScale 推理效率;**真机为定性演示**。⇒ 同一模式的较轻版本,**引架构可、勿引为系统级性能证据**
- **对本框架的真实增量(本轮最有价值)——识别出缺失的第三条通道**:此前两条通道都是**云↔端**,**框架隐含单机**;多台机器人**同时在同一物理世界协作同一任务**时需要**共享且一致的世界状态**,这在"单机+云"里不存在。写入 [[Future embodied Agent framework - integrated view]] 新增小节,含三通道性质对照表:
  - 运行时(云↔端,低频,**可断**,传计划/观测)/ 演进(云↔车队,离线,**完全可断**,传能力画像)/ **协同(端↔端,实时,最不能断,传共享世界状态)**
  - **⚠️ 与四约束之一直接冲突**:"断网必须能活"在协同场景下**只能降级为"退回各自单机作业"**,而非维持协作 —— 本框架此前未处理的设计张力
- **能力画像的第二种用途**(写入 [[Cloud-edge co-evolving embodied agent - a continuous-evolution framework]]):从**单机能力域判断**扩展到**车队级能力路由**("派哪台机器人去做",对应 RoboOS 的 topology-aware 子任务分配);⇒ 要求画像**跨本体可比**,对"接口契约共版本化"提出更强要求(不只两侧对齐,而是**全车队对齐**)
- **定位观察**:RoboOS 自己也用 "Brain-Cerebellum",故该隐喻非本库独有;但本库版本是**部署驱动的可证伪定义**(云=脑/端=小脑),而非神经科学类比 —— 对外讲时值得强调这一区别
- 两篇均**未建源笔记**(证据强度不足以支撑独立笔记),以行内引用 + 证据限定出现。Lint 干净:0 broken;137 notes
## [2026-08-06] synthesis | 面向具身计算系统优化的仿真评测套件 v0.1
- **触发**：Ethan 明确问题不是“如何评价仿真器”，而是团队优化具身 Agent、VLA 推理、渲染、物理和 3DGS 后，应该用哪些仿真任务判断端到端精度是否退化，以及 π0.5 与任务配置如何标准化
- 新建 [[Embodied simulation benchmark suite for systems optimization]]：提出“**共同核心回归集 + 优化点专项集**”，而非所有优化共用一张总榜
- 三套工作负载草案：`Embodied-Core` = LIBERO 四套件；`Embodied-Manipulation-Stress` = 内部提出的 RoboTwin-System-10 + clean/visual-hard/physics-hard/control-hard；`Embodied-Agent` = BEHAVIOR-Core-20 / Full-100；ManiSkill 作为物理组件探针
- 冻结第一版 π0.5-LIBERO reference：官方 30k checkpoint、BF16、action horizon 10、flow steps 10、replan 5、224×224、两视角、50 rollouts/task、seed 7、四套件 timeout；外部事实均回读 OpenPI / RoboTwin / BEHAVIOR / ManiSkill 官方代码或文档
- 关键方法：环境 seed 与 π0.5 flow noise seed 双冻结；reference/candidate 做逐 episode 配对；Canonical 与 Stress 分开；物理引擎同时用固定 action trace、scripted controller、π0.5 闭环三种方式归因
- **状态**：v0.1 讨论稿。待冻结 RoboTwin-System-10、BEHAVIOR-Core-20、算力预算、各 benchmark 的 π0.5 checkpoint、非劣性阈值与 trace 格式

## [2026-08-06] deepen | RoboTwin 官方两档 vs 内部三类 hard
- **澄清**：RoboTwin 2.0 官方 benchmark / leaderboard 只有 `demo_clean` 与 `demo_randomized` 两档；此前提出的 `visual-hard / physics-hard / control-hard` 是为了系统优化归因而设计的**团队内部扩展**，不是官方现成配置
- 官方 randomized 主要覆盖背景/纹理、杂物、光照、头部相机位移、桌面高度与实验性本体随机化；官方通用配置未提供质量/摩擦/阻尼/接触刚度或控制延迟/丢帧等字段
- 文档改为五 profile：`official_clean` / `official_randomized` 保证外部可比；`internal_visual_hard` 主要复用 YAML；`internal_physics_hard` 需在 reset/asset load 扩展 SAPIEN 参数；`internal_control_hard` 需在 policy–environment wrapper 注入延迟、丢帧、action repeat 与传感器不同步
- 三类内部 hard 优先采用单因素实验；只在最终综合压力测试增加不可归因的 `mixed-hard`


## [2026-08-06] ingest ×2 + framework | Being 团队的范式迁移:Being-0(agent 框架)与 Being-H0.7(latent WAM)
- **触发**:Ethan 问"Being-0 算 Agent 系统还是模型方案设计",继而问"Being 最新架构是不是推翻了这种范式"。两问都需读原文,遂一并 ingest 两篇 + 记录判断
- **[[Being-0 - a Humanoid Robotic Agent with VLMs and Modular Skills|Being-0]]**(arXiv:2503.12533,2025-03;HTML 正文自读)
  - **血统是 LLM agent**:框架**改编自 Cradle**(做开放世界游戏/软件操作的 GPT-4o agent 框架)——原话 "we adapt the Cradle framework to build a generalist agent for humanoid robots"
  - **分层归属**:FM = **现成 GPT-4o(云)** / Agent 框架 = 现成 / **Connector = 自训**(VideoLLaMA2 微调,训练数据 = 室内导航第一视角图 + 语言指令 + 物体标签 + bbox) / 技能库 = **遥操 + 模仿学习**(ALOHA 系方法)获得
  - **为什么必须训中间层**(核心论证):① GPT-4o 云端延迟高,而**人形双足本身不稳、需频繁调整运动指令做误差修正**,开环序列不行;② GPT-4o **3D 场景理解差**("failing to estimate the direction and depth of navigation targets")→ 技能规划出错。训完 Connector **板载推理 ~1 秒**
  - **pose adjustment**:除 bbox 外还预测**机器人相对物体的最佳对齐方向**,偏了触发复合调整;抓取 **+0.4** 成功率。**⇒ 与 [[Zhang et al. - Harness VLA Steering Frozen VLAs into Reliable Manipulation Primitives via Memory-Guided Agents|Harness VLA]] 的 re-staging 独立收敛**(2025-03 vs 2026-07,不同团队/路线,同一机制:"交棒前先把机器人摆到对下游技能有利的位姿")
  - **部署边界极简**:"all components, **except the FM**, deployable on low-cost onboard devices" ⇒ **只有 FM 在云**,比本库整合视图更激进且**真机验证过**
  - **结果**:长程 **84.4%**;无 Connector 移动速度差 **4.2×**、远距导航全失败;**没有任何固定相机俯仰角能同时兼顾导航与操作**(主动相机全任务满分);导航 同房间 1.0 / 未见布局 −0.2 / 跨房间 0.8
  - **分类学(回答 Ethan 的问题)**:落在**"纯 harness"与"模型方案"之间的第三格 —— "harness + 训练的粘合层"**(同格:HELM 的 SV)。**⇒ 纯 harness 有天花板:基座在某个具体能力上不行时,prompt/记忆/检索补不上,必须训**。按 load-bearing 原则,Connector **用训练而非 prompt 来承重**。**对本库启示:"计划级接口"可能不能只是协议,可能得是一个训练出来的翻译器**
- **[[BeingBeyond - Being-H0.7 a Latent World-Action Model from Egocentric Videos|Being-H0.7]]**(arXiv:2605.00078,2026-04;HTML 自读)
  - **给 [[World-Action Models]] 第五代补第二个独立实例** ⇒ 此前仅 LaWAM 一例,**单例撑不住代际划分,现在成立**
  - **双重诊断**:VLA 的**稀疏动作监督 → shortcut mapping**(学不到 dynamics/contact/task-progress);像素 WAM 的**未来帧生成是"costly and indirect substrate for control"**
  - **机制**:多模态上下文与带噪动作之间插一组 **learnable latent query** 当推理接口;**未来知情双分支** —— prior(可部署)vs posterior(仅训练,未来观测经**冻结 ViT + Perceiver resampler** 压成 K 个嵌入替换 query);两支共享 context/backbone/动作通路(**单次前向**),在 latent 位置**逐点隐状态对齐** + **防 latent collapse 正则**;**推理丢弃 posterior、无视觉 rollout**。**本质 = privileged distillation**,与 [[JEPA]] 防塌缩谱系同源
  - **第五代内部分两支**(已写入 WAM 概念页):**隐子目标支**(LaWAM,显式产未来观测特征当子目标)vs **隐推理支**(Being-H0.7,无显式子目标,把未来蒸进 latent query)
  - 骨干 InternVL3.5(理解)+ Qwen3(动作),建在 Being-H0.5 上,人类+机器人混合数据(UniHand 2.0 格式)。**六仿真 benchmark 总体 SOTA/平均排名最高**、**LIBERO-plus 微调后 84.8%**、**灵巧人形 49.2%**、真机跨本体(ARX 为主)
- **⚠️ 范式迁移的核实结果**:**Being-H0.7 全文 0 次提及 Being-0 / agent framework / Connector / skill library / GPT-4o**。团队轨迹:agent 框架(2025-03)→ VLA(2025-07)→ 跨本体 VLA(2026-01)→ **latent WAM**(2026-04),**一年出头从"编排现成 FM+技能"走到"自造端到端基座"**
- **写入 [[Embodied model function evolution - generalization as the master line]] 新增「反方向的证据点」节**:同一现象两种归因(**系统结构** vs **表征学习**),Being 与 [[Galaxea - G0.5 Autoregressive VLM-as-Actor VLA|Galaxea G0→G0.5]] 并列为"系统派 vs 模型派钟摆"的证据。**但公平标注三条**:① Being-0 的论证(误差累积+模块延迟)**没被驳倒,只是被绕开**(单体策略无多模块延迟);② Being-H 修的恰是 Being-0 里用现成方法凑的技能库(H0 卖点="需要少得多的遥操演示")⇒ 可读作"先搭系统再补最弱层";③ 两层历史上交替推进,非零和
- **⇒ 对本页主线的修正(重要)**:"泛化载体走向组合"应表述为**方向性判断而非既成事实**;当前模型层仍在快速兑现收益。且与 Harness VLA 不矛盾——后者证明的是"**在给定模型上**组合能榨出 +38.6pp",而非"组合优于把模型做强"
- Lint 干净:0 broken;141 notes


## [2026-08-06] ingest | B2FF:"在条件空间恢复" —— 恢复设计空间补齐第三格
- **触发**:Ethan 问"什么叫把 milestone 图像作为 fixed future-image anchor?怎么 anchor 进去的?visual-foresight VLA 是以这帧图为基础开始推理吗?那不会不准确吗?" —— 三问全是机制细节,读原文后 ingest
- **[[Shin et al. - B2FF Failure Recovery for VLA Policies via Pre-Imagined Milestone Selection|B2FF]]**(arXiv:2606.09258,2026-06-08;**首尔大 Byoung-Tak Zhang 组** + 延世 + 崇实;raw = URL-only,HTML 自读)
- **"anchor"的确切含义(回答问题1)**:基座是 **foresight-driven VLA**,正常时**联合生成「子目标图像 + 动作」**;恢复时把未来图像那一路的变量**钉死(clamp)**为选中的 milestone,**只对动作去噪** —— 论文称 **action-only denoising**:
  `π(v_t, a_t | I, o_t)` (正常) vs `π(a_t | I, o_t ; v_t ← v*)` (恢复)
- **不是"以那帧图为基础推理"(回答问题2)**:**`o_t`(当前偏离观测)始终在条件中**;被替换的是**策略自己预测的未来**,不是当前状态。策略同时看"我在哪"与"该去哪",生成动作把两者接起来
- **"不会不准确吗"(回答问题3)——这正是立论**:偏离后 `o_t` 落在不熟悉状态空间,从 OOD 观测**重新预测未来**本身就不可靠("direct re-planning frequently **destabilizes action sequences**")。⇒ **宁可要不精确但在分布内的目标**,因为动作头只被训练过朝熟悉的未来行动。原文金句:**"need not pixel-match the failed observation, but it must contain a milestone that provides a useful action-guiding condition"** ⇒ **milestone 不是预测,是靶子**
- **"对不上"由 selector 兜**:`v* = argmax F_φ(ṽ | o_f, H_f, C_f)` —— 打分**条件含当前失败观测**+历史+**局部候选集**(非整个 bank)⇒ 挑"从我现在这个烂状态出发**最够得着的**"熟悉未来,这就是 recoverability 的含义。实现:冻结 tokenizer → 投影器 → **Perceiver 注意力** → MLP 打分头;训练三阶段 = **TCN 时间对比学习**做进度初始化 → **对每个候选真跑一遍 action-only denoising 收反事实标签** → 监督 warm-start + **one-step actor-critic 式微调**
- **bank 构造**:执行前从**干净初始观测**递归查询**冻结 VLA 的 future-image 边缘分布** ⇒ 存下的都是"策略在正常状态下会想象出的未来",**天然在分布内**
- **结果**:failure-injected LIBERO **56.3%→74.0%(+17.7pp)**,**不微调低层动作生成器**;真机三任务(堆叠/pick-and-place/关抽屉并放置),"lightweight selector tuning"后迁移成立
- **⚠️ 两条必记前提**:① 主结果在 **controlled recovery timing**(触发与注入扰动对齐)下取得,在线变体仅用本体感知历史估计;原文明说 **"We treat trigger estimation as an interchangeable entry point"** ⇒ **它解决"怎么恢复",不解决"何时恢复"**;② **明确不处理语义失败**(任务理解错/物体 grounding 错)**与不可逆失败**(离开工作空间/不可逆环境改变)
- **写入 [[Embodied failure detection]] 新增「检测之后:恢复的三格设计空间」**:
  | 工作 | 改什么 | 真机代价 |
  |---|---|---|
  | Harness VLA | **物理位形**(re-staging) | 要真移动:时间、磨损 |
  | HELM | **世界状态**(历史关键帧当视觉目标开回去) | 要真开回去,"回得去吗"存疑 |
  | **B2FF** | **喂给策略的目标** | **零物理代价** |
- **由此得出的判断(本库综合)**:**动作头的能力域不只由当前状态定义,还由你给它的目标定义** —— `p(success | o₀, goal)` 是**两个变量**的函数 ⇒ **恢复分布内性有两条路:移动机器人,或换个目标**。后者真机更便宜,补上了此前"真机重试有物理成本"讨论缺的一半
- **外部对本库分类学的独立印证**:B2FF 的适用边界(只处理可恢复偏离,不碰语义/不可逆)与本库**四类失败**及**失败可逆性**判据**逐条对齐**
- **留白**:B2FF 把触发外置、Sentinel/FAIL-Detect 专做检测 ⇒ **两者是天然互补组合而无人做过**;另记一条 open question:这套"钉死条件槽"能否迁到 **WAM 的 latent 子目标**(LaWAM 隐视觉子目标 / Being-H0.7 latent query)⇒ **在 latent 空间恢复**,比像素更便宜
- **未核实**:基座 VLA 具体身份(通篇泛称 foresight-driven VLA);代码发布情况
- Lint 干净:0 broken;142 notes


## [2026-08-06] ingest | FAR:恢复四格补齐 + 本库第一个闭合"恢复→数据→改进"环的工作
- **触发**:Ethan 指出 FAR 用在线学习做重试修正,"猜中了在线学习和失败重试两个领域" —— 判断成立,它确实落在两条线的交叉点
- **[[FAR - Failure-Aware Retry for Test-Time Recovery and Continual Policy Improvement|FAR]]**(arXiv:2607.01111;raw = URL-only,HTML 自读)。⚠️ **作者与机构未在提取中定位**
- **问题诊断(准)**:失败状态**很少被离线演示覆盖、对预训练策略是 OOD** ⇒ **朴素重试只重复同样的错误**;且现有恢复方法**多依赖人工介入**,FAR 定位于**自主**
- **四部件**:① **IQL** 价值学习,同训 `Q_φ` 与 `V_ψ`,用**时序价值差定位失败诱因动作**;② **FCPA**(Failure-Contrastive Preference Adaptation)——失败经验构**偏好数据**(失败动作为负例 + 替代正例),**测试时更新策略**;③ **轻量动作扰动**——FCPA **受限于离线策略的 support**,扰动才能在 OOD 状态扩 support(仿真中**简单高斯扰动通常足够**);④ **成功恢复轨迹进 replay buffer** → 持续改进,原文:"provide supervision on **hard states where the initial policy fails**, improving both policy robustness **and value estimation** over time"
- **结果**:仿真 **+17.6%** / 真机 **+11.7%**(vs 标准 diffusion policy);**"enables recovery without environment resets"**;**reset budget 与 timestep budget 两种预算下数据效率均显著提升**;3 sim benchmark/9 任务(50 ep、**≤5 次尝试**、3 seeds)+ **7-DoF xArm** 3 任务(20 ep、≤3 次尝试)。⚠️ **未用 LIBERO/CALVIN/RoboCasa**(0 命中),横向可比性弱
- **核实过程的一个小坑**:`LoRA` 全文 22 次命中,一度以为是方法组件;**回读上下文发现全在参考文献,方法中未使用**(我的行长过滤器漏判)。⇒ **词频命中 ≠ 方法组件**,又一次"先看上下文再下结论"
- **恢复设计空间由三格扩到四格**(写入 [[Embodied failure detection]]):Harness VLA 改**物理位形** / HELM 改**世界状态** / B2FF 改**目标** / **FAR 改策略本身**。**前三格都冻结策略、在"绕过"其不足;FAR 在"修正"它** ⇒ 取舍:**冻结 = 零训练成本、行为可预测;更新 = 能真正学会,但有在线训练与稳定性风险**
- **最有价值的一点:本库第一个闭合的环**。此前框架有**运行时通道(恢复)**与**演进通道(经验↑/技能↓)**,但**无任何工作把两者接起来**。FAR 的环:失败 → 价值差定位 → 偏好适配+扰动 → **恢复成功** → 轨迹进 replay buffer → 持续改进(**价值估计一并变好**,自举)
- **对 [[Robot data engine]] 的含义**:数据引擎页指出自演进型引擎的本质是"**质量信号提取**",且**双组分杠杆**里人类信号是支点。**FAR 用 IQL 学出的价值函数替掉了这个支点** ⇒ **双组分杠杆存在可自主化的子类**。且它自动产出的"成功恢复轨迹"**按定义落在策略失败分布上** —— 正是数据引擎页判定"价值密度最高"的那类数据,而这里是**自主**产生的。对"人类注意力是真正稀缺资源"是**正面缓解而非推翻**(仍需可靠的价值函数)
- **与 [[Physical Intelligence - pi0.6 a VLA That Learns From Experience|π*₀.6 Recap]] 的对照**:同为"价值函数把部署经验转成训练信号",但**时间尺度不同** —— Recap 是**离线/车队级/事后**,FAR 是**在线/单机/就在这一集内**。⇒ 同一思想的两个尺度,正好对应框架的**演进通道(慢)**与**运行时通道(快)**
- **留白**:① +17.6% 里 FCPA 与扰动各占多少(即"改策略"是否必要,还是扰动就够)② 价值函数**恰恰在 OOD 失败状态上被调用**,可靠性存疑——能否用 FAIL-Detect 那类 OOD 分数加护栏 ③ **测试时更新的权重如何回流云端**(FAR 只做单机闭环,无车队聚合)④ 与 B2FF 组合:**先换目标(零物理代价)、不行再改策略**是否构成自然的恢复升级阶梯
- Lint 干净:0 broken;144 notes


## [2026-08-06] synthesis | ESAS-RoboTwin：从公开开发回归到私有系统验收
- 更新 [[Embodied simulation benchmark suite for systems optimization]] 至 v0.2，将 RoboTwin 使用方式拆成两层：开发团队运行官方全 50 任务 × clean/randomized；评估团队维护 ESAS（Embodied System Acceptance Suite）中的私有 `ESAS-RoboTwin`。
- 将原 `RoboTwin-System-10` 降级为按能力覆盖选择的早期 `Capability-Stress` / 快速诊断候选；记录 Motus 自训 π0.5 的地板、天花板与协议边界，不再把它视为经精度分布校准的最终验收集。
- 冻结 ESAS-RoboTwin 五轴结构：Canonical / Visual / Physics / Control / Compound；前三个压力轴优先做单因素实验，Compound 只用于最终综合压力。
- 建立 Public Dev → Private Validation → Sealed Final Holdout 的数据隔离，以及聚合反馈、提交频率限制、实例轮换和版本哈希等防过拟合治理。
- 最终验收采用相同隐藏 episodes 上的 reference–candidate 配对非劣性检验；先运行 100 episodes/task，对临界项顺序扩样至 300–500。


## [2026-08-06] correct + deepen | NVIDIA 在具身 Agent 层的站位;OSMO 定性修正 + Isaac Lab-Arena 补入
- **触发**:Ethan 问"NVIDIA 作为算力提供商,有没有对具身 Agent 做技术部署",继而追问 OSMO 细节并质疑"它是不是就是个训练+评测编排,和具身 Agent 没太大关系"。**质疑成立**
- **一次自我纠错链(值得记的过程)**:搜索摘要称 OSMO 为 "open-source **agentic** orchestrator" → 我据此把它往 agent 层归 → Ethan 追问 → 读官方文档发现 **"agentic" 指"能被编码 agent 操作"**(仓库带 `AGENTS.md`/`CLAUDE.md`/`.claude/agents/`,支持 prompt-driven 开发),**不是"编排具身 agent"** → 我又过度解读成"为 coding agent 准备的" → Ethan 再质疑"人类开发员不亲和吗" → 读 README 确认**主受众明确是人类开发者**("no infrastructure expertise required"、YAML 而非 Python、对标 SLURM),agent 上下文文件只是**附加可及性**。**两轮过度解读均由用户质疑纠正**
- **OSMO 的准确定性**:**面向 physical AI 的领域专用**工作流编排(官方明确对标并区别于 SLURM,**非通用**);统一训练集群+仿真+边缘硬件于单一控制面;覆盖 数据生成→RL→训练→仿真验证→**SIL/HIL 评估**;YAML 主接口 + CLI + VSCode/Jupyter/SSH。**边界(官方原话)**:"OSMO prepares trained policies, datasets, and artifacts, but **deployment into production systems is outside its scope**" ⇒ **纯开发/训练期,不是运行时,与具身 Agent 系统无直接关系**;在本框架里只落**演进通道云侧**(云①/云③/**云④验证门**的执行底座)
- **⚠️ 修正两处既有表述**([[Robot data engine]] + [[Real-robot data collection - teleop vs UMI-class, and the model-in-the-loop quality problem|数据金字塔综述]]):原写"**但它是通用工作流编排**"**不准确**。**"为数据验证优化的调度仍是公开空白"这个结论不变,但理由要换** —— 不是"它太通用",而是**它把"验证"当作工作流里的一个普通阶段,未把验证吞吐当成一等优化目标**
- **新增 [[Real-robot data collection - teleop vs UMI-class, and the model-in-the-loop quality problem|数据金字塔综述]] §5.4 第 6 条:仿真评测层 = NVIDIA Isaac Lab-Arena**(开源,商业许可):解决"大规模策略评测搭建又繁又手工";**乐高式模块化**(Objects / **Affordances** `Openable`/`Pressable` 用于任务泛化 / Scenes / Embodiments GR1·Franka / Tasks 封装目标与成功判据)**按需即时组装环境**;**GPU 并行 40× 于串行**(复杂任务 **0.76h vs 34.9h**);扩展自 Isaac Lab,GEAR Lab 用它基准 GR00T N 系,**以 OSMO 为 CI/CD 部署环境**
  - **意义**:这是本库"**评估算力第一次与训练算力并列成为预算项**"判断的**商业佐证** —— **算力供应商专门为评测吞吐做开源产品、以加速比为卖点**(不是论文说的,是卖算力的人用产品投票)
  - 另注:其 **Affordance × 物体 × 场景 × 本体**的组合式任务生成,与 [[Task decomposition]] 的"**固定谓词 × 任务参数所以规则不爆炸**"结构同构 —— 又一次独立收敛
- **[[NVIDIA]] 实体页新增「在具身 Agent 层的站位」节**:核实结论 = **agent 能力分成两处、且都不是运行时** —— ① **吸收进模型**(GR00T System 2,N1.7 用自家 **Cosmos-Reason2-2B**,"Open Reasoning VLA" + enhanced task decomposition ⇒ **规划/推理做进权重,不外挂 harness**);② **落在开发基建**(OSMO 编排 + Arena 评测);③ **运行时 agent harness = 没有**
- **产业结构判断(本轮最有价值)**:与 [[AgiBot 智元]] 的 AIMA "1+3+X" 形成对照 —— AgiBot 把 **"X = 具身智能体框架"明确列为栈里的生态位(要占位)**;NVIDIA **把 agent 拆进模型与开发基建、运行时框架留白(不占,卖底座)**。⇒ **"具身 Agent 框架"这一层目前没有平台方标准化**:学术侧各做各的,产业侧一个占位一个留白。**对本框架"接口契约共版本化"是现实提醒——该契约目前没有事实标准的制定者**
- **一条被砍掉的候选**:曾想记"agent readiness 成为软件交付物"(仓库放 `AGENTS.md` 等),**证据只有一个仓库,太薄,暂不记**,待再见两三例
- Lint 干净:0 broken;144 notes


## [2026-08-06] ingest | Isaac Lab-Arena 源笔记(评测基础设施第一篇)
- 应 Ethan 要求把上一条只在实体页提及的 Arena 收成独立源笔记。**这次没依赖摘要器**——curl 抓原文自读(19.5k 字符),因而补到摘要器没给的几处关键信息
- **[[NVIDIA - Isaac Lab-Arena Scalable Robot Policy Evaluation in Simulation]]**(NVIDIA Technical Blog,**2026-01-05**,2026-02-03 更新补入性能;5 位作者;**与 Lightwheel 共同开发**;开源+商业许可;**pre-alpha**)
- **摘要器漏掉而原文有的**:① **与 Lightwheel 共同开发**(physical AI 基础设施公司)② **pre-alpha**,原文自述 *"intentionally an early framework skeleton with **limited features**"* ③ 完整性能设置 ④ 生态细节 ⑤ 路线图
- **核心机制**:**Object / Scene / Embodiment / Task 四类独立积木即时编译**成 Isaac Lab 环境(替代"整块写死的任务描述")+ **Affordance 系统**(`Openable`/`Pressable`)标准化交互**使一个任务跨物体复用**;`Task` 封装目标/成功判据/终止逻辑/事件/指标;换物体(microwave→power_drill)、换本体(GR1→Franka)、换场景(kitchen→packing_table)**均不需重建环境或管线**;**策略无关**
- **性能(Lightwheel 实测)**:**GR00T N1.5 × 10 个 RoboCasa 任务 × 每任务 4096 同构环境变体 × 8×6000D GPU** → **并行 0.76h vs 串行 34.9h**
  - ⚠️ **易被误引的点**:**"40×" 是 Arena 并行 vs Arena 串行的内部对照**,**不是**相对原 MuJoCo(RoboCasa) 实现;原文提到也与 MuJoCo 版比过但正文未给该数字
- **生态**(比框架本身更值得注意):Lightwheel 用它开源 **250+ 任务**(Lightwheel-RoboCasa-Tasks / Lightwheel-LIBERO-Tasks)+ 工业基准 **RoboFinals**;接入 **HF LeRobot Environment Hub**(可后训练/评测 **GR00T N / π0 / SmolVLA**);**RoboTwin** 用它建 RoboTwin 2.0 扩展版与长程基准;GEAR Lab 基准 GR00T N 系;Seattle Robotics Lab 并入语言条件任务套件。与 Isaac Lab-Teleop / Isaac Lab-Mimic / GR00T N 后训练打通;部署可本地或 **OSMO** 做 CI/CD
- **路线图与本库 L0–L3 评估栈独立吻合**:近期 = 自然语言指定物体摆放、**复合任务(串联原子技能)**、RL 任务设置、**异构并行评测**;更远 = **Omniverse NuRec 做 real-to-sim(= L2)** + **Cosmos 世界模型驱动的神经仿真(= L3)**
- **四条 Why it matters**:① **"评估算力成为一等预算项"最强的一类证据**(卖算力的人用产品投票)② 路线图沿 L0–L3 往上走 ③ **Affordance × Object × Scene × Embodiment 的组合式任务生成 = "固定谓词 × 任务参数"设计原则的第三次独立出现**(前两次:LEACL 参数化 PDDL、Harness VLA 固定小原语库)④ **评测环境开始有"分发中心"**(LeRobot Env Hub 可注册可发现)—— 与刚记下的"**具身 Agent 框架层至今无人标准化**"形成对照:**评测这一层已经开始标准化了**
- **⚠️ 最重要的限定**:**它只解决"可比 + 快",完全没碰"可信"** —— **全文未报任何 sim-to-real 相关性数字**(对照 SIMPLER 的 r=0.924 是这层的"质检证书")⇒ **是吞吐工具,不是保真度工具**;用它得出的排名能否代表真机仍需另行校准。这正好落在 [[Real-robot evaluation]] 的核心矛盾("仿真可比不可信 / 真机可信不可比")上,两页互为对位
- 接线:[[NVIDIA]] 实体页 Arena 节加源笔记指针;Embodied MOC 新增 "Sources — evaluation infrastructure" 小节;index Sources。Lint 干净:0 broken;145 notes


## [2026-08-10] synthesis | ESAS-LIBERO：纳入 LIBERO-Plus 与 LIBERO-PRO
- 更新 [[Embodied simulation benchmark suite for systems optimization]] 至 v0.3，将 LIBERO 拆成 Public Compatibility（原始 40 任务）、Public Robustness/Generalization（Plus/PRO）和 Private Acceptance（ESAS-LIBERO）三层。
- 明确 LIBERO-Plus 主要测试任务语义不变时的七轴条件鲁棒性与 covariate shift，适合渲染、3DGS、视觉编码、相机和传感器链路；区分 zero-shot 与 Plus-finetuned 协议。
- 明确 LIBERO-PRO 主要测试 Object/Position/Semantic/Task/Environment 下的 grounding、任务泛化与反记忆；记录作者 π0.5 结果中的 Task/困难 Position 地板效应，不能用于小幅精度回退守门。
- 新增 ESAS-LIBERO：Canonical-Heldout / Covariate-Robustness / Grounding / Task-Generalization / Control / Compound；复用 Plus/PRO 设计但隐藏具体 seed、资产、指令、位置和任务组合。
- 配置标准改为 Public Canonical、Private Canonical-Heldout、Stress 三类；复杂物理仍由 ESAS-RoboTwin 与 ManiSkill 主承载。


## [2026-08-10] synthesis | 冻结 π0.5-LIBERO baseline 运行协议
- 更新 [[Embodied simulation benchmark suite for systems optimization]] 至 v0.4；撤销 v0.3 中的 `ESAS-LIBERO/Control` 数据轴。推理时延与 scheduling 由开发团队自行验证，评估团队只冻结统一闭环协议。
- 基于当前 OpenPI 官方配置冻结 LIBERO v1 reference：π0.5 30k checkpoint、BF16、flow integration steps=10、predicted horizon=10、每次执行前 5 actions 后重新观测。
- 补齐图像与状态协议：256 render、旋转 180°、resize-with-pad 到 224、agent+wrist 两路相机、right-wrist 零图并 mask、8D proprioception、LIBERO 原生 7D delta action、checkpoint norm stats。
- 补齐评测协议：官方复现 seed=7 / 50 episodes；ESAS 使用隐藏 manifest，先 100 episodes，临界项扩到 300–500；成对比较还需固定或可追踪 policy flow noise。
- 采用单一声明变量原则：量化/算子保持 10/10/5；flow-step reduction 可改变第一项并显式命名；horizon/execute 变化作为独立 scheduling 实验，不进入标准 LIBERO 精度榜。

## [2026-08-10] synthesis | 纳入 RoboCasa365 与 π0.5-RoboCasa 运行协议

- 更新 [[Embodied simulation benchmark suite for systems optimization]] 至 v0.5，将 RoboCasa365 定位为 MuJoCo 主任务集：Public-50 用于公开兼容性回归，ESAS-RoboCasa 承担 Precision-Core、Physics-Core、Scene-Object-Heldout 与 Capability-Stress。
- 记录当前 50-task leaderboard 的 Atomic-Seen 18 / Composite-Seen 16 / Composite-Unseen 16，以及 RoboCasa 团队复现 π0.5 的 39.6% / 7.1% / 1.2%；明确该提交基于 RoboCasa 1.0.0，正式门槛必须在 1.0.1 的 1.5× horizon 协议下重建 reference。
- 冻结 π0.5-RoboCasa 候选 baseline：RoboCasa OpenPI fork commit `ca4c6d710db75e276bc7c866a57bd7e4aee5b6e8`、Human300 75k checkpoint、BF16、flow steps 10、predicted horizon 50、每 chunk 执行 5 actions、三路 224 图像、16D state、12D 有效 action 与官方 `convert_action()`。
- 冻结公开采样起点：`pretrain` split、seed 7、每任务 50 episodes、逐任务 `get_task_horizon()` 和 `info["success"]`；ESAS 先跑 100 个配对 episodes，临界任务扩到 300–500，并固定环境与 policy flow noise。
- Atomic-Seen 具体任务名单暂不预选；待用户完成 RoboCasa 1.0.1 reference 实测后，按逐任务成功率、重复方差、接触覆盖与失败模式冻结 Precision-Core / Physics-Core。

## [2026-08-10] synthesis | 区分 LIBERO、LIBERO-PRO 与 LIBERO-Plus 运行协议

- 更新 [[Embodied simulation benchmark suite for systems optimization]] 至 v0.6，将第 7.1–7.2 节明确定位为团队统一的 π0.5 Policy Contract，而不是 Plus/PRO 论文已披露的官方模型配置。
- 明确 LIBERO-Plus 论文没有报告 π0.5；团队运行时自行冻结 BF16、flow/horizon/execute=10/10/5，并仅允许 benchmark manifest 指定的 Camera、Robot、Language、Light、Background、Noise、Layout 变量变化。
- 修正采样口径：LIBERO-Plus 全量是 10,030 个已展开 fixed perturbed instances，各运行一次；不能给每个实例机械套用 50 episodes。论文从 14,000 候选过滤为 10,030 个 test-only 实例。
- 明确 LIBERO-PRO 每个 task/profile 运行 50 episodes，并沿用 220/280/300/520 max steps；但官方没有完整披露 π0.5 flow steps、action horizon、chunk execution、policy noise 与初始等待，团队复现统一按 Policy Contract 补齐。
- 将第 7.3 节改成 Public LIBERO / LIBERO-PRO / LIBERO-Plus / ESAS-LIBERO 四列 benchmark-specific 协议，分别冻结 workload unit、规模、随机性、重复次数、instruction、success predicate 与异常处理。

## [2026-08-10] synthesis | 明确 ESAS-LIBERO Canonical-Heldout 边界

- 在 [[Embodied simulation benchmark suite for systems optimization]] 中补充 Canonical-Heldout 字段表：task/BDDL、instruction、success predicate、simulator/config 保持不变；initial states 使用评估团队隐藏的新同分布样本；environment seed 与 policy noise 隐藏并冻结。
- 明确 `initial_state_id`、`environment_seed`、`policy_noise_seed` 的层次区别，并要求它们与 manifest hash 一起记录、在 reference/candidate 间逐 episode 配对。
- 约束 Canonical-Heldout 不混入视觉、语言、任务或物理 hardening；这些变化只能进入 Covariate、Grounding、Task-Generalization、Compound 等 Stress profile。

## [2026-08-14] source | 深度核实 Recap（π*0.6）方法机制

- 自读 arXiv 2511.14759 HTML 全文 + 附录 A-C，大幅扩写 [[Physical Intelligence - pi0.6 a VLA That Learns From Experience]] 的 Method 节。
- **厘清 Recap 训的不是 π0.6**：π0.6 是基座（训练另见模型卡，不在本文），π*0.6 = π0.6 + 二值优势指示位 I_t 的条件通路；Phase 1 的数据是 D_demo（演示 + 网络图文），**不含自主经验**。
- 补 §IV-A：分布值函数为原文用语（B=201 个 value bin，交叉熵训练，Monte Carlo 估计），目标为"到成功还差多少步"，归一化到 (−1,0)；作者自认 on-policy 估计次优但可靠。
- 补 §IV-B 完整推导链：贝叶斯改写 → Eq.2 CFG 形式 → β=1 特例（改进策略 = 以"好"为条件的参考策略）→ Eq.3 双项目标。明确 −α·log π(a|I,o,ℓ) 的作用是**分开好/坏两支**，坏数据用于提供对比而非模仿目标（对照 AWR 的过滤式做法）。
- 补 ε_ℓ 取 30% 分位数，以及不调 β 的第二条理由：**CFG 权重管不到模型的自回归部分**。
- 补附录 A-C：Eq.3 中连续部分是 **ELBO 代理**（加权 L2，噪声权重 w(η)=e^{−η/2}），非真似然——这是绕开 policy gradient 的关键。
- 新增"两个防退化机制"表：**KI 防遗忘（继承自 π0.5）** 与 **每轮退回预训练 checkpoint 防迭代漂移**是两回事 ⇒ 持续学习第三层挂着两个代价。
- 修正两处过度外推：**"车队级"是本库外推**（迭代实验用单一静态双臂平台）；"慢"不在轮数（常一轮即可）而在**单轮粒度**（laundry 消融每轮 600 条轨迹）。
- 在 [[FAR - Failure-Aware Retry for Test-Time Recovery and Continual Policy Improvement]] 补时间尺度差异的**机械根源**：MC 回报需集终止 vs 集内时序价值差，非工程选择。

## [2026-08-15] source | Ingest 三篇运行时失败检测/自适应重规划工作（VLA-FAIL、FIPER、DVAC）

- 三篇均**自读 arXiv HTML 全文核实**（未走摘要器），各建 `01 Raw` URL-only note + `02 Sources` 源笔记：
  - [[Seligmann et al. - VLA-FAIL Efficient Task Failure Detection for Finetuned Vision-Language-Action Models]]（FZI + KIT，arXiv:2606.21386）
  - [[Romer et al. - FIPER Failure Prediction at Runtime for Generative Robot Policies]]（TUM，NeurIPS 2025，arXiv:2510.09459）
  - [[Feng et al. - DVAC Denoising-Variance Adaptive Chunking for Flow-Based Robot Policies]]（深圳河套 + 港中深，arXiv:2606.03847）
- **归类判断：DVAC 不是失败检测工作**（全文 `failure detection` / `conformal` 均 0 命中，作者自陈是 empirical proxy 而非校准过的不确定性）。故它**不挂在 [[Embodied failure detection]] 的机制表下**，而是作为"同族信号的第二种用法"单列，主链接落到 [[Embodied Cerebellum Models]] 的 chunk 消费层。
- [[Embodied failure detection]] 大幅扩写，五处结构性更新：
  1. **机制③拆成三个取信号的位置**（观测侧 / **表征侧** / 动作侧）。表征侧（VLA-FAIL 的 LLMD）是本库此前缺的一格，且它擅长抓**最易漏的"进展停滞"类**（死循环重试、默认动作）—— 该类此前只有停滞超时（很粗）与 VLM（很贵）两档。
  2. **成本前沿下移，修正本页旧结论**：此前记"STAC 未必能端侧实时跑"（每步 256 采样，FAIL-Detect 硬件实验没跑它）；**ACC 是 STAC 的单样本速度归一化估计，真机上几乎全面胜过它** ⇒ "策略自身信号=免费"在用对估计量的前提下**重新成立**。新增按额外算力排的成本前沿表。买断制结构未消失，只是移到了 LLMD 的数据预处理 / RND-OE 的离线训练上。
  3. **新增组合逻辑一节（AND vs OR）**：FIPER 用 AND（附 Proposition 1：两分数不独立时合取仍守同一误报上界），VLA-FAIL 用 OR。**代价被 FIPER 自家主表量化**——DT 0.18/0.25（单用）→ 0.30（AND），准确率顺序相反。⇒ 本页原则②第一次有了两个可比落点。
  4. **阈值类型之争被化解**：FIPER 附录 D 自陈时变阈值的失效条件（完成方式时序多变、rollout 长度不一）**恰好就是 VLA-FAIL 拒绝时变的理由** ⇒ 两边同意底层判据，只是任务集把它们推到两端。提炼成部署规则记入。
  5. **benign OOD**：本页原先把"只用成功数据"的代价记为"OOD ≠ 一定失败"；FIPER 的四象限（Success OOD vs Fail ID）正面攻击了这道缝，可从"限制"改写为"已被专门攻击的子问题"，但**远未解决**（准确率 0.78，作者自陈对装配线不够）。
- **两处独立收敛值得记**：(a) **VLA-FAIL 与 FIPER 各自独立诊断出 STAC 在"策略选择行为模态"时误报** —— 把本页旧教训"必须用分布距离"推进一层：**用了分布距离仍不够，距离在模态切换处本身就大**；(b) **AUCPDT 与 TWA 是两个组独立提出的同一类指标修正**（把检测时间折进主指标，堵住"等到最后再预测"与"第一步全报警"两种套利）。
- [[Embodied Cerebellum Models]]：chunk 消费层补上"**块该多长**"这一半（此前只有 RTC 管"块与块怎么接"）。
- 同步 [[04 Maps/Embodied AI - VLAs, world models, and cerebellum|Embodied MOC]] 的 failure detection 小节（+3 条）与 `index.md`（Raw ×3、Sources ×3）。

## [2026-08-14] source | 二次核实 FAR 的 critic 训练数据与复位口径

- 自读 arXiv 2607.01111 §3 Setting / §4.1 / §4.2，补进 [[FAR - Failure-Aware Retry for Test-Time Recovery and Continual Policy Improvement]]。
- **修正"无需环境复位"的表述**：原文实为 *preserve the scene state, return the robot to a predefined start pose* ⇒ **只复位机器人本体，保留世界状态**。这是"真机重试只能复位本体、不能复位世界"的第四次独立出现（Harness VLA re-staging / ENPIRE 复位到最难段起点 / B2FF 换目标 / FAR 送回起始位姿），已标记为可升格的设计规律。
- **补起步条件**：critic 必须先用离线专家演示训好，且 *"Reward signals are used for critic training"*；测试时才降级为只需成/败的 outcome feedback。⇒ "在线、单机、当场改"的定位要打折扣，它有离线前置阶段。原文未说明 critic 训练用稠密还是稀疏奖励，已标注为未定。
- **补此前完全漏记的 actor/critic 数据不对称**：三个 buffer（D_exp / D_succ / D_fail），**critic 三个全用（含失败），actor 只用 D_exp ∪ D_succ**（原文理由 "To avoid learning poor behaviors"）；策略更新是 **AWR**（A=Q−V，w=exp(A/η)，优势加权去噪目标）。
- 补 IQL 期望分位损失式子，以及 chunk-conditioned critic 的实现细节（Q 给动作块打分，TD 目标用时序聚合后实际执行的单步动作 ã=g(a)）。
- 新增 Why-it-matters 第 6 条：与 **LWD**（arXiv:2605.00416，待 ingest）的对照——LWD 批评的 *"use only part of the available experience"* 正命中 FAR 的 actor 更新；并指出 AWR-vs-QAM 的分水岭是模型尺度，与 Recap / RL Tokens 同属"规模决定手法"规律。

## 2026-08-17 — 具身 harness 开发基座选型 + VLA harness 设计（多轮讨论收口）

- **两个代码仓 clone 逐文件审计**（非 WebFetch 摘要）：[[openJiuwen - JiuwenSymbiosis Physical AI Assistant Framework]]（华为，Apache-2.0，24.8k+19.2k 测试）与 [[RLinf - RPent Recursive Physical Agent Framework]]（**核实为 Harness VLA 的代码仓真身**——README 明认；无 LICENSE、无测试、仅 LIBERO）。各配 01 Raw capture。
- **选型决策记录**：[[Harness development base - JiuwenSymbiosis selection and build plan]]。根本原因 = 机制 vs 嘱咐（RPent 的 harness 在 markdown：Python 中 staging/postcondition/verif 命中 0）+ 部署终局 + rails-off 即基线。推进 8 步，评测环境与成功信号先于四特性。
- **新概念页**：[[Harness granularity]] —— harness 挂载粒度必须等于执行器决策粒度；"事中"监控住进复合算子内部（伺服环先例 → `vla_until` 设计）；策略侧信号可中止无权定罪 / 世界侧证据正式裁决。
- **[[Embodied failure detection]] 增补**：检测管线四段分工（拦截/裁决/善后/转述）——工业实现的"裁决"段是空的（DiagnosisRail `_is_failed` 三通道全自报、零判断）；DetectionRail（裁判）vs DiagnosisRail（解说员）之辨；叠加图回传 planner 的廉价 L2 机制。
- **[[Cloud-edge co-evolving embodied agent - a continuous-evolution framework]] 增补**："演进通道能否去人：检测信号质量是闸门"（ENPIRE 全自动 / 华为人审 / RLinf 人审三点外证）+ "coding agent 属于演进通道，进运行时环就出不了仿真"。
- **[[Zhang et al. - Harness VLA Steering Frozen VLAs into Reliable Manipulation Primitives via Memory-Guided Agents]] 补代码发布信息**（RPent + 实现暴露的三件事）。
- 顺带修正本 session 早前一个错误结论："NVIDIA 在具身 Agent 层没做过具体工作"为假——**ENPIRE（arXiv:2606.19980）是演进通道 harness**（自称 "a harness framework for coding agents"，8 台真机双臂 YAM，99% pass@8）；NVIDIA 的准确站位 = 造 agent harness 但只围开发/研究循环，不围机器人任务。**ENPIRE 待 ingest**；[[NVIDIA]] 实体页"运行时 harness｜没有"一行仍为真、无需改，但可补演进通道条目（待办）。

## 2026-08-17（补）— PPT 画图流程沉淀

- 制作《具身Agent系统逻辑架构.pptx》（库根，不进 git；经三轮迭代：深底→白底→拓扑修正为 决策层/Rail/工具层/本体接入层 + 侧挂服务，用户手改措辞均保留）。
- 新增 [[PPT diagram workflow]]（90 System 操作文档）：pptxgenjs + PowerPoint COM 渲染 QA 五步循环、负 extent 陷阱（PowerPoint 报 0x80070570）、validate.py 中文 locale 假阳、风格约定（白底淡彩/琥珀=待建）、生成器索引。
- 生成器脚本入库：`90 System/scripts/pptx/gen_embodied_agent_arch.js`（一图一脚本，保证可重生成）。
- 同步写入 Claude 持久记忆三条（工具链 / 负 extent 坑 / 交付与"先提取用户手改再重生成"约定）。

## [2026-09-01] synthesis | 五方向 × 三档仿真评测矩阵（方向优先重排）

- 应 Ethan 要求，把 [[Embodied simulation benchmark suite for systems optimization]]（v0.7）的"基准优先"组织重排为**方向优先视图**：新建 [[Embodied sim eval - three-tier matrix by research direction]]，逐方向罗列开源与私有（ESAS）评测条目。
- **分档原则**：一档·基础保全（离线筛查 + 饱和区 reference ≳90%，打回制）/ 二档·敏感判别（判别区 20–80% + mild/medium 扰动，Nam–Tango 配对非劣）/ 三档·挑战压力（地板区 <20%、hard 档、多轴组合、非确定长程，不设门槛单独报告）。成绩区间是启发式、功能优先——Canonical-Heldout 处高分区仍归二档（稀疏不一致对由 exact/Bayesian 兜底），已在 §1 显式说明。
- 两个正交关系入档：**档位（测什么）⟂ 流水线站位（何时/谁/判多严）**，Sealed Holdout = 二档内容的发布级重跑；**一档全开源**（私有集不做冒烟，高频接触 ESAS 违反治理）。
- 主页 §5 与 Related 加双向链接；**顺带修复 index.md 漏项**——主评测方案页此前从未入索引，本次与新页一并补入。
- 待冻结项继承主页 §6：mild/medium 强度校准、Precision-Core 名单、MuJoCo 探针集、Agent composite 验收触发条件，另新增一档打回阈值（R0 容差、smoke 掉分幅度）。

## [2026-09-01]（补）| R0 打回阈值校准协议入档

- 起因：Ethan 问"动作分歧多大算异常"——查证 [[VLA quantization]] 确认**文献无公认阈值**（四篇 VLA 量化工作只报成功率，Action-MSE 仅作敏感度排序信号），且分歧→成功率受闭环误差复合与任务相位调制、本质非线性，绝对阈值不成立。
- 在 [[Embodied sim eval - three-tier matrix by research direction]] 新增 §9.1：**三条参照带**（噪声地板 = reference 自分歧 / 良性差异带 = 已验证等价的实现变体互比 / 坏版本带 = 故意做坏的版本含喂错翻转约定）夹出相对阈值；判别力检验内建（坏版本与良性带重叠 ⇒ R0 对该故障不敏感，拦截职责后移闭环）；统计看尾部（逐维归一化 P95/P99/max）；**安全门绝对阈值是唯一例外**（本体限值 + norm stats P99.9，可立即冻结）；阈值只用于打回、不用于通过。
- 三条带测量与主页 §4"评估团队第一动作"（reference 方差/自翻转率）并入同一校准 sprint。
- [[Real-robot eval bench - task suite design and setup checklist]] R0 节加一行指针。

## [2026-09-01]（补2）| 矩阵笔记移除开发常识类条目

- Ethan 反馈：PR smoke 这类开发团队自然会做的小冒烟不需要入档。从 [[Embodied sim eval - three-tier matrix by research direction]] 移除：PR smoke（推理优化）、框架单测 + LIBERO-10 smoke（Agent）、固定 policy 冒烟（RL）；"trace 重放 smoke"改名"trace 重放筛查"（它是需定容差的设计机制，保留）。
- 取舍原则本身写入 §1 第一条补充：**一档条目准入 = 需要专门设计/校准/约定**（R0 阈值、探针、trace 容差、确定性容差、冻结协议的饱和全量），开发常识不入档。
- 主页 [[Embodied simulation benchmark suite for systems optimization]] §4/§5 流水线中的 PR smoke 未动（那里描述的是站位节奏，非评测集清单）。

## [2026-09-01]（补3）| 修正矩阵笔记 "Plus hard" 表述

- Ethan 质疑"LIBERO-Plus 有 Hard 子集吗"——**没有**：Plus 是 7 维 21 子维 × 10,030 实例的平铺结构，唯一难度概念 L1–L5 是四个旧模型（不含 π0.5）成败事后分层的经验标签（主页 §2.2 早有记录，矩阵笔记引用时嫁接了 ESAS OR 私有 hard 档的概念，属转写失真）。
- [[Embodied sim eval - three-tier matrix by research direction]] 三处修正：推理优化三档改为 **"Plus 低分子维抽样"**（依据团队 reference 逐子维成功率，L4–L5 至多作粗筛候选）；渲染三档总览格改回 OR hard/Compound（私有）。"hard 档"仅保留在 ESAS OR（自校准）与 RoboTwin randomized（官方 Hard）两处合法出处。

## [2026-09-01]（补4）| Plus 判别子集升入推理优化二档

- Ethan 质疑推理优化二档为何不排 LIBERO-Plus（π0.5 在部分 Plus 子维的成功率可能高于 Atomic-Seen 的 39.6%）。复盘结论：原映射（继承主页 §5）按"主敏感面"把 Plus 整块分给渲染方向，**混淆了归因与覆盖**——配对设计下归因不是问题（只改后端，差异全归 candidate），真正的问题是覆盖：量化误差与输入分布相关（PTQ 敏感度分析/rotation 校准均在校准集分布上离线完成，见 [[VLA quantization]]），观测偏移把 activation 推到校准集外，clean Canonical 测不到该失效面。
- [[Embodied sim eval - three-tier matrix by research direction]] 修改：推理优化二档新增 **Plus-Sensitive**（校准后按 reference 逐子维成功率选 20–80% 判别区子维；与渲染共用同一份 π0.5-Plus reference 跑分）；三档相应改为 **Plus 地板子维**（<20% 只查崩塌），两档按判别区边界切分。§9 待冻结项 1 加入 Plus-Sensitive 名单。
- 边界保持：ESAS 验收面不变（Canonical-Heldout + Precision-Core），Plus-Sensitive 属开源自报层；π0.5-Plus 无官方成绩，名单待 reference 跑分后冻结。

## [2026-09-01]（补5）| 澄清：开发常跑的地板集不因此升一档

- Ethan 提出 Agent 开发中已常测 PRO swap 轴与 RoboCasa，问是否可入一档。结论：**不入**——swap（Position，π0.5 0.08–0.38）与 RoboCasa Composite（7.1/1.2）均在地板区，打回制的前提"坏了一眼可见"在地板区结构性不成立（小 n 下退化与噪声不可分，检测低基线崩塌反而需要大样本）；一档偏爱饱和区是功效结构问题，非品味。
- [[Embodied sim eval - three-tier matrix by research direction]] §1"档位⟂站位"补充反向应用：开发日常高频跑二/三档小样本作趋势观察合理且应该，但判据与归档不变；地板集的正路是升档迁移（Composite 抬进判别区 → ESAS 验收集实例化）。
- 另记：RoboCasa Atomic 对 Agent 方向意义有限——单步任务几乎不经过规划层，Agent 框架不动底层 policy。

## [2026-09-01]（补6）| 修正：Atomic-Seen 对 harness 型 Agent 框架有效，入二档

- 撤回补5 末行"Atomic 对 Agent 方向意义有限"——该判断隐含假设 Agent 框架是纯规划器。Ethan 澄清团队框架是**每调用包一层的 harness**（staging 改善 VLA 初始状态、失败记忆与改善机制），即 [[Harness granularity]] 的"挂载粒度=执行器决策粒度"一路：一个 atomic 任务恰是一个完整 harness 周期（stage→invoke→verify→recover），无长程复合干扰，反而是单周期 harness 质量最干净的信号。
- [[Embodied sim eval - three-tier matrix by research direction]] Agent 二档新增 **Atomic-Seen harness-on/off 配对**（三态：rails-off 裸 VLA / harness 旧版 / 新版；rails-off 即基线出自 [[Harness development base - JiuwenSymbiosis selection and build plan]]）。观察量含每成功一次的调用数/时间开销（防重试买成功率）。两个协议点：horizon 冻结 1.5×、staging/重试步数属被测成本；跨 episode 持久记忆破坏 episode 独立性，默认评测态 per-episode 记忆复位、跨 episode 记忆另设声明 suite。
- 归档仍为二档非一档：39.6% 判别区适合配对判别，打回制的饱和区前提不满足。

## [2026-09-01]（补7）| LIBERO 侧物理归因缺口：按需 trace 重放 + 探针集配置覆盖

- Ethan 问是否需要 ESAS-LIBERO Physics-Core。拆解：**机制类型**上不需要（主页 §3.4 选址理由仍成立——LIBERO 接触稀疏，分歧信号是 RoboCasa 的真子集，低信号常驻布点浪费算力）；但**配置栈**上存在真实缺口——两家 solver/integrator/timestep/controller 指纹不同（主页早记"同一引擎名 ≠ 同一物理栈"），引擎改动可能只在 LIBERO 配置路径出问题，而 LIBERO 侧此前只有闭环、无隔离层可归因。
- 补法不建常驻 Physics-Core，两条便宜手段入 [[Embodied sim eval - three-tier matrix by research direction]]：①物理方向二档新增 **LIBERO trace 重放（按需诊断，不常驻、不设门槛）**——harness 引擎通用，顺带录 LIBERO trace 冻结备用，仅在"LIBERO-40 闭环回退 + RoboCasa 物理层干净"场景启用；②§9 探针集待冻结项加硬需求：覆盖两家配置指纹，配置路径覆盖由组件层系统性解决。

## [2026-09-01]（补8）| LIBERO trace 重放从按需诊断升入一档常驻

- Ethan 追问：既然轻量为何不常驻一档。复盘承认补7 的"按需"定位保守错位——**"低信号处不重复布点"（主页 §3.4）针对的是常驻闭环评测基础设施的算力投放，不适用于不跑模型的 trace 重放**；重放的真实约束是容差校准（按配置栈各做自重放噪声带）与误报分诊，均很小。既已决定录 trace 冻结，"录而不常跑"等于放弃每提交的配置覆盖。
- [[Embodied sim eval - three-tier matrix by research direction]] 修改：一档条目改为 **trace 重放筛查（RoboCasa + LIBERO 双配置栈）**——RoboCasa trace 管机制覆盖，LIBERO trace 管第二套配置指纹；LIBERO trace 按接触/铰接密度选任务（自由空间轨迹不敏感，不选），兼任闭环回退的归因工具。二档撤销"按需诊断"条目；§9 项 2 改为双栈分别自重放校准（方法同 §9.1）。

## [2026-09-01]（补9）| 矩阵笔记全文复审 → v0.2

- Ethan 切换 Fable 5.1 后要求重审。逐行复审 [[Embodied sim eval - three-tier matrix by research direction]]，修 12 处，三类：
  - **违反自定规则 / 内部矛盾**：①chunk 写成 "10/5""50/5""50/50"，违反 §8 自己规定的三元组必须写全，改为 10/10/5、10/50/5、10/50/50；②"不一致率 ψ 高 → 功效高"表述错误——配对方差 ≈ ψ/n，ψ 高反而增大所需 n，正确论证是非饱和区同等损伤表现为更大效应量；**主页 §3.4 同一处一并修正**；③R0 三处误标【开源】——R0 用团队自录真机数据，改【自有数据】，§1 "一档全开源"改为"不依赖 ESAS 隐藏集、对开发透明"。
  - **事实精度**：RoboTwin 70.7/46.0 补 recipe 警告（差近 30 点，重建后须复核仍在判别区）；Plus-Sensitive 功效改为"2pp 级、≳3.7k 对达 1pp"；RL 三档 BEHAVIOR 加条件（仅当框架接入 OmniGibson/Isaac 栈）；渲染二档 Plus 注明七轴中 Robot/Language 不归因渲染。
  - **结构一致性**：§2 推理优化二档格括号重写；§1 列表断行、一档"数据集特征"覆盖 trace/探针；各方向子标题统一带判据后缀；探针/数值稳定性/图像层指标补【自建】标签；Agent 观察量注明 predicate progress 仅 LIBERO 侧可插桩。
- 版本升 **v0.2**，头部记修订要点。
