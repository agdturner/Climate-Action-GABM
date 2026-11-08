# Change Log


## Table of Contents
- [Overview](#overview)
- [Unreleased](#unreleased)
- [0.9](#09)
- [0.8](#08)
- [0.7](#07)
- [0.6](#06)
- [0.5](#05)
- [0.4](#04)
- [0.3](#03)
- [0.2](#02)
- [0.1](#01)


## Overview
Notable changes are to be documented in this file.

This is the release-oriented record of delivered changes. Future priorities
and unfinished work live in [ROADMAP.md](ROADMAP.md). Historical counts,
defaults, implementation locations, and version labels below describe their
development stage, not necessarily the current code or a verified public tag.


## [Unreleased]

- **Handover presentation ownership (2026-11-08).** Moved the HTML deck to
  `documentation/presentations/`. Stage and publish it verbatim as a standalone
  HTML page through Sphinx's extra-file mechanism, linked from site navigation.
  Cleanup removes its staged copy without changing the authored presentation.
  Presentation content and external font dependencies are retained.

- **Documentation index and dependency mirrors (2026-11-08).** Move the
  authored index to `documentation/README.md`, stage it under a separate page
  name, and generate both dependency pages from root manifests. Remove the
  tracked stale mirrors, preserve manifest content inside valid code fences,
  and clean generated mirrors after building.
  Combined validation: **722 passed, 1 skipped, 2 expected failures**, with
  the same 6 warnings; 29 documentation regression tests pass. Fresh Sphinx
  build succeeds with **221 warnings**. Published deck bytes match the original
  exactly; authored index, dependency mirror content, and cleanup were verified.

- **Supplementary-source ownership (2026-11-08).** Moved two literature/
  parameterisation drafts into `documentation/research/` and five historical
  guides, AIRE article notes, and planning snapshots into
  `documentation/archive/`. Retained historical bodies and original
  `supplementary_docs/` Sphinx paths. Added explicit research/history navigation
  and nested staged-path link/copy/cleanup contracts. Historical instructions,
  citation claims, and planned issue completion were not revalidated or
  consolidated as part of this move.
  Fresh Sphinx build succeeds with **225 warnings**, down from 272. All
  eighteen authored pages are generated, and historical replacement-guide,
  research, and nested source links plus cleanup preservation were verified.
  Full suite: **722 passed, 1 skipped, 2 expected failures**, with the same
  6 warnings, including 29 documentation regression tests. A parallel build
  also preserves all authored sources and removes nested staged copies.

- **Research-record ownership (2026-11-08).** Moved the design history,
  research notes, experiment results report, and survey documentation to
  `documentation/research/`. Preserved historical prose and numerical
  evidence, updating relocation-related links and write-up location references.
  Registered staging/cleanup under the existing page names and added explicit
  research/history navigation. Updated guide/entry-point/archive cross-links
  and notebook Markdown references without rewriting code or historical
  outputs. Supplementary/archive ownership and HTML deck publication remain
  pending slices.
  Validation: **23 documentation tests passed**; full suite **716 passed,
  1 skipped, 2 expected failures**, with the same 6 warnings. Fresh Sphinx
  build succeeds with **272 warnings**, down from 339. All eleven migrated
  pages, research/guide cross-links, and source-preserving cleanup were checked.
  Independent developer `make docs` also succeeded, reporting **161 warnings**.
  This is a separate build observation, not a directly comparable fresh-build
  warning count.

- **Maintained guide ownership (2026-11-08).** Moved the code tour, local LLM
  setup, prompts/personas V2, run output, and simulation configuration guides
  to `documentation/guides/`. Retained their Sphinx page names and registered
  staging/cleanup plus navigation. Updated source-relative links, root entry
  points, legacy references, and Markdown links in three notebooks without
  changing notebook code, outputs, or metadata. Research/archive material and
  the HTML handover deck remain pending; guide content consolidation is not
  part of this ownership slice.
  Validation: **19 documentation tests passed**; fresh Sphinx build succeeds
  with **339 warnings**, down from 393. All seven migrated guide pages and
  navigation links are present; cross-guide/source links, cleanup, and source
  preservation were checked. Guide prose and notebook code/outputs/metadata
  were verified unchanged except link relocation and one explanatory sentence.

- **AIRE authored-source ownership (2026-11-08).** Moved the quickstart and
  HPC primer to `documentation/guides/`, preserving content apart from
  relocation-related links. Registered their copies and cleanup in the shared
  Sphinx manifest, retained page names, and added them to site navigation.
  Staging now resolves links relative to nested source documents. Updated
  repository entry points and legacy guide references; added nested-source
  regression tests. Other guides, research/archive material, the handover
  deck, and AIRE content consolidation remain separate migration slices.
  Validation: **16 documentation tests passed**; fresh Sphinx build succeeds
  with **393 warnings** (previously 397). Guide content is unchanged except
  relocation links; rendered navigation, cross-guide/repository links, and
  cleanup preservation of authored sources were verified.
  Full suite: **709 passed, 1 skipped, 2 expected failures**, with the same
  6 warnings. A repeated parallel documentation build also passes and removes
  the staged AIRE copies without removing their sources.

- **Documentation staging safety (2026-11-08).** Stage the project README
  under a separate filename so building and cleanup preserve the authored
  documentation index. Make cleanup depend on a successful build even with
  parallel Make, preserve existing autosummary stubs, and ignore new generated
  stubs. Limit default pytest discovery to the test directory so Sphinx's
  downloaded Python examples are not collected. Stage the root user/developer
  guides, rewrite root-document links for Sphinx, and enable heading anchors.
  Added 10 staging/cleanup regression tests. A final fresh build succeeds with
  397 warnings, down from 752; remaining legacy warnings are recorded rather
  than globally suppressed. Two parallel builds preserve the authored index
  and tracked API stubs. Full suite after building: **703 passed, 1 skipped,
  2 expected failures**, with the same 6 warnings.

- **Published GABM 0.3.0 compatibility (2026-11-08).** Updated runtime,
  development, and Conda dependency pins. Survey politics/ethnicity/family
  types now use GABM's generic attribute bases in their existing CAG modules,
  preserving identifiers, labels, and representations. Updated source/test/
  sandbox imports and code-cell imports in 27 notebooks, without rewriting
  historical outputs. `SurveyedNation.place` remains a read/write alias for
  GABM's `name`; supplied survey maps are retained, and an omitted ethnicity
  map now defaults to CAG's survey map rather than the removed generic one.
  Added [compatibility contracts](tests/test_gabm_compatibility.py).
  Published-wheel validation: **693 passed, 1 skipped, 2 expected failures**;
  both original 0.2.18 golden scenarios remain unchanged, CLI smoke dry-run
  succeeds, and `pip check` passes. Checkpoint limitations remain unchanged.
  Independent developer installation and `make test` confirmed the same
  counts with 6 warnings in 11.95s.

- **Real-nation refactor baseline (2026-11-08).** Added
  [tests/test_integration_baseline.py](tests/test_integration_baseline.py) and
  [versioned golden data](data/fixtures/cag_integration_baseline.json) for
  repeatable package/single-policy runs with real citizens, real nation logic,
  and deterministic mocked LLM transport. Covers prompts, seeded/repaired
  networks, exposure/reach, peer messages, surveys, memory, CSV/JSON outputs,
  checkpoint hydration, and controlled continuation. Two strict expected
  failures expose the existing offline-message cursor resume limitation.
  Published GABM 0.2.18 validation: 686 passed, 1 skipped, 2 expected failures.
  Runtime code and dependency pins are unchanged; detailed evidence and
  checkpoint limitations are in [GABM_Refactor_Plan.md](GABM_Refactor_Plan.md).

- **CAG to GABM refactor plan (2026-11-08).** Added
  [GABM_Refactor_Plan.md](GABM_Refactor_Plan.md) with the published
  dependency audit, generic/domain ownership boundaries, phased extraction
  sequence, and behaviour-preservation gates. Linked it from the roadmap,
  developer guide, and documentation navigation. Documentation only; no
  runtime code or dependency pins changed.
- Clarified documentation ownership in the developer guide: author prose
  outside `docs/`, retain Sphinx configuration/navigation there, and migrate
  existing guides incrementally. Registered the root refactor plan in the
  shared documentation copy/cleanup manifest.
- Distinguished the forward-looking roadmap, release-oriented change log,
  dated development history, and detailed implementation plans in the developer
  guide.
- **Roadmap/history consolidation (2026-11-08).** Replaced historical release
  tables in [ROADMAP.md](ROADMAP.md) with forward-looking refactor priorities,
  documentation/data organisation, consolidated validation backlog, and
  longer-term goals. Existing release entries below already cover most of the
  removed deliverables; unique milestone evidence and the MVP dependency
  record are retained here. Older backlog items with uncertain completion are
  explicitly marked for evidence reconciliation.


## [0.9]
v0.9 is the first **behaviour-bearing** release after the v0.8 refactor track.

- **Peer-message reflection grounding — Option B (2026-07-24).** `generate_peer_message()` and `generate_package_peer_message()` in [src/cag/abm/agent.py](src/cag/abm/agent.py) now explicitly surface today's reflections inside the **user prompt**, making peer-message generation mechanistically grounded in what the agent heard from political broadcasts rather than only having those reflections available implicitly in the system-prompt context. Previously the user prompt was a bare *"Express your current thinking on the following policy"* with reflections buried in context; the LLM could easily produce generic policy opinion without relaying the broadcast signal. The new prompt opens with a peer-conversation framing (*"A peer asks what you think about: …"*), injects a bulleted `Your recent reflections on this:` block (filtered to `day == today` and `policy_id == target_policy_id`), and instructs the agent to draw explicitly on those reflections. When no reflections exist (e.g. the agent was not reached, or it is Day 0) the block is absent and the prompt degrades gracefully. The package-mode path (`generate_package_peer_message`) follows the same pattern, filtering on `PACKAGE_SCOPE`. This closes the causal gap in the committed-minority trickle-down mechanism: the relay chain `political message → reflection → peer message (carries signal) → neighbour reflection → survey` is now explicit rather than implicit. `test_simultaneous_update` in [tests/test_peer_messaging.py](tests/test_peer_messaging.py) updated to match the new prompt phrases (also fixing a pre-existing bug where the receive-phase detector `"conversations with some of your peers"` never matched the actual receive-prompt text). Smoke-tested in [notebooks/49_peer_message_reflection_grounding_smoke.ipynb](notebooks/49_peer_message_reflection_grounding_smoke.ipynb) (7 structural checks + optional real-LLM check with Qwen3-8B-4bit: 6/7 reflection keywords echoed in the generated peer message).

- **Cumulative opinion-update prompts (2026-07-12).** `_DEBIAS_STEP1_TEMPLATE` in [src/cag/abm/agent.py](src/cag/abm/agent.py) updated with two behavioural instructions: (1) agents are now told to update from their *current* (most recently stated) position rather than their original Day-0 position, so opinion changes compound across days rather than being anchored to Day 0; (2) agents receiving multiple messages on the same day are instructed to weigh them against each other — contradictory messages (pro- and anti-climate on the same day) should partially cancel out, while consistent messages should reinforce each other. `_DEBIAS_STEP2_TEMPLATE` updated to reinforce that the letter answer should reflect the updated opinion from Step-1 reasoning. Verified with [notebooks/47_debias_prompt_smoke.ipynb](notebooks/47_debias_prompt_smoke.ipynb): Day 0→1 opinion shifts observed; Day 1→2 shift confirmed for at least one agent under contradictory-message schedule. `__version__` bumped to 0.9.1. It adds a persona-null ablation (a manipulation check on whether the model conditions on personas), a broadcast-frequency-asymmetry CLI, and a simplified affinity-weight ladder, plus researcher-facing documentation of the affinity mechanism. Default behaviour is unchanged — `persona_mode="real"`, 1-vs-1 broadcasting, and `reach_targeting="random"` reproduce prior canon bit-for-bit.

- **Peer fan-out — degree/centrality-proportional relay (2026-07-10).** Peer chat (the `C` phase) was a flat *send* fan-out: every citizen relayed its reflection to the same `k = min(k_peers, degree)` randomly-chosen neighbours, so a well-connected hub spread its shifted view no wider than a two-tie leaf — the exact mechanism limitation the paper's targeting null flags as the "degree-proportional relay rule" re-test. New `SurveyedNation._compute_peer_fanout()` in [src/cag/abm/environment.py](src/cag/abm/environment.py) computes a per-citizen fan-out `k_i` scaled by a peer-graph measure (`degree` or `betweenness`, reusing the reach-targeting centrality machinery). Budget `additive` (default) lets the well-connected relay to more people so total peer talk grows with connectivity — the realistic posting-network reading; `preserve` instead redistributes a fixed total so the *mean* fan-out stays `k_peers` (isolating placement from volume). `k_i` is clipped at `peer_fanout_kmax` (default 10) and never exceeds a node's own degree; the map is memoised per parameter set. `mode="constant"` (the default) reproduces the historical rule bit-for-bit, so existing runs are unchanged. Three new `SIM_CONFIG` keys — `peer_fanout_mode` / `peer_fanout_budget` / `peer_fanout_kmax` (`scale`=1.0 and `kmin`=1 are baked internal defaults) — plus `--peer-fanout-mode/-budget/-kmax` CLI flags in [src/cag/__main__.py](src/cag/__main__.py), threaded through `run_peer_messaging` / `run_package_peer_messaging` and both `C`-phase dispatch sites in [src/cag/abm/sim.py](src/cag/abm/sim.py). Tests: `TestPeerFanout` (13) in [tests/test_peer_messaging.py](tests/test_peer_messaging.py). Docs: "Peer fan-out" section in [docs/Simulation_Configuration_Guide.md](documentation/guides/Simulation_Configuration_Guide.md); flag reference + worked example in [documentation/guides/AIRE_Quickstart.md](documentation/guides/AIRE_Quickstart.md). Infrastructure only — the hub-targeting re-run is deferred. Verified with [notebooks/48_peer_fanout_smoke.ipynb](notebooks/48_peer_fanout_smoke.ipynb): all five (mode, budget) combinations asserted on a synthetic star graph (hub degree=6, 6 leaves); `degree/additive` confirmed plumbed through `run_simulation` on a 10-agent SBM run (18 peer messages vs 16 under `constant`).
- **Per-side reach targeting — persuadable + network-centrality (2026-07-05).** `SurveyedNation.apply_reach_subsample` in [src/cag/abm/environment.py](src/cag/abm/environment.py) gains `targeting_a` / `targeting_b` ∈ `{"random", "persuadable", "degree", "betweenness"}`. `random` is the prior uniform without-replacement subsample (unchanged). `persuadable` hard-ranks a side's audience by closeness to the neutral midpoint of the package index (`|get_real_package_index()|` smallest = most undecided) and keeps the `floor(reach·n)` most-undecided; `degree` / `betweenness` hard-rank by NetworkX centrality on the peer graph and keep the most-central. A seeded permutation (the *same* seed as the random arm) breaks ties, so the modes differ only by selection criterion; all modes are a **no-op at `reach = 1.0`**. Because centrality needs the graph, `run_simulation` setup in [src/cag/abm/sim.py](src/cag/abm/sim.py) is **reordered** — the peer network is now built and repaired *before* `apply_reach_subsample`, so centrality sees the final graph. The `random` / `persuadable` arms and the shared `sim_step` counter are unaffected (bit-for-bit; verified by the full suite staying green through the reorder). New `SIM_CONFIG["reach_targeting_a"] / ["reach_targeting_b"] = "random"`, validated in `run_simulation`; `--reach-targeting-a/-b` flags in [src/cag/__main__.py](src/cag/__main__.py); both added to `_RESUME_HARD_KEYS` in [src/cag/io/checkpoint.py](src/cag/io/checkpoint.py). Tests: `TestReachTargeting` (10) in [tests/test_broadcast.py](tests/test_broadcast.py), `TestReachTargetingCLI` (2) in [tests/test_cli.py](tests/test_cli.py). Verified end-to-end on gpt-5-mini (NB 42, [docs/result_report.md](documentation/research/result_report.md)): persuadable kept mean |GT| 0.89 vs 2.04 dropped; degree kept mean degree 9.17 vs 3.67.
- **Observability layer — full prompt capture, reached flags, summary + diagnostic tables (2026-07-05).** New `agent_prompts.csv` records the exact `(system_prompt, user_prompt, response)` triple for every persona-facing LLM call, **gated to a stratified sample (one agent per exposure bucket)** so it stays bounded regardless of `n_citizens`. Mechanism: a `SurveyedCitizen._chat()` wrapper in [src/cag/abm/agent.py](src/cag/abm/agent.py) routes all nine `send_chat` sites (seed rationale, both survey steps, broadcast + peer reflections, peer-message generation — single and package variants) and appends to `self.prompt_log` when `_capture_prompts` is set; the sample is resolved once in [src/cag/abm/sim.py](src/cag/abm/sim.py) (one per bucket, or explicit `timeline_sample_agent_ids`) and shared with `agent_timeline`. New per-agent `reached_by_a` / `reached_by_b` booleans in `agent_attributes.csv` record post-subsample audience membership (the basis for treatment-on-treated / targeting analysis). New `bucket_summary.csv` (one row per run × bucket — n, Day-0 GT mean, end mean, drift, MAE, rank ρ, reached counts — designed as the **cross-run aggregation seed**) and `targeting_diagnostics.csv` (per side — mode, reach, reached-vs-dropped mean |GT|) via new `build_bucket_summary` / `build_targeting_diagnostics` in [src/cag/io/aggregators.py](src/cag/io/aggregators.py). `agent_prompts` is final-output-only (`_CHECKPOINT_SKIP_KEYS`); `survey_assembled_context.csv` — previously written for *every* agent though only the sampled rows are ever consumed — is now **gated to the same sample** at collection time, so it too scales with the ~4-agent sample rather than `n_citizens`. Tests: [tests/test_output_o1.py](tests/test_output_o1.py) (6).
- **New diagnostic figures + Day-0-anchor-aware trajectories (2026-07-05).** [src/cag/io/plots.py](src/cag/io/plots.py) `save_result_plots` gains eight figures: `opinion_trajectories_by_bucket` (per-policy bucket means + per-bucket GT), `polarization` (dispersion over time), `drift_from_gt`, `opinion_ridgeline` (Day-0→Day-N distribution joyplot), `network_before_after` (nodes coloured by opinion, sized by degree, reached nodes ringed), `targeting_mechanism` (reached-vs-unreached spillover), `reach_qc` (actually-reached counts per bucket), and `calibration_before_after`. The existing trajectory and by-bucket plots now render **Day 0 as a distinct anchor marker** — *conditional* on `day0_anchor` being a ground-truth mode, so an `llm_survey` Day 0 stays on the line — plus 95% CI ribbons, line markers, and per-bucket GT references (fixing the earlier population-only GT reference in the by-bucket panels). A str-cast in `plot_network_before_after` fixes an id-type mismatch (float `agent_id` vs string snapshot node id) that had rendered every node at opinion 0. All new plots return `None` on insufficient data. Tests: `TestO2Plots` in [tests/test_output_o1.py](tests/test_output_o1.py).
- **AIRE readiness-race fix + verification notebooks (2026-07-05).** [scripts/aire/run.sh](scripts/aire/run.sh) readiness gate switched from `curl /v1/models` (which returns 200 *before* vLLM registers the model, so the sim's first call 404'd) to a real chat-completion probe for `$HF_MODEL` — closing the race that crashed several node-shared sweep jobs. New notebooks [notebooks/42_reach_targeting_smoke.ipynb](notebooks/42_reach_targeting_smoke.ipynb) (gpt-5-mini; persuadable + centrality asserts + output checks) and [notebooks/43_observability_gallery.ipynb](notebooks/43_observability_gallery.ipynb) (prompt walkthrough + figure gallery); write-up in [docs/result_report.md](documentation/research/result_report.md).

- **Tier-P persona-null ablation (2026-07-03).** A manipulation check on *algorithmic fidelity*: does the model actually condition on each agent's assigned persona, or answer from a generic prior? New `SurveyedNation.apply_persona_mode(mode, seed)` in [src/cag/abm/environment.py](src/cag/abm/environment.py) rewrites every active citizen's persona under one of three arms — `"real"` (no-op, bit-for-bit identical to prior canon), `"shuffled"` (each agent gets *another* agent's whole persona verbatim via a derangement, so no agent keeps its own but every persona stays a coherent real UK person), `"neutral"` (every persona replaced by the generic `NEUTRAL_PERSONA_TEXT = "I am an adult living in the United Kingdom."`). **Ground truth is never touched** — real opinions are always read from `original_survey_data`, so the scoring target is identical across arms and any accuracy difference isolates persona-conditioning. Personas are snapshotted before any override so `shuffled` copies originals. Mechanism: new `SurveyedCitizen.persona_override` + `get_persona()` hook in [src/cag/abm/agent.py](src/cag/abm/agent.py). Wiring in [src/cag/abm/sim.py](src/cag/abm/sim.py): new `SIM_CONFIG["persona_mode"] = "real"` (→ 34 keys), `VALID_PERSONA_MODES = ("real", "shuffled", "neutral")`, validated in `_resolve_runtime`, applied in `run_simulation` alongside reach / audience-cap (fresh + resume paths); result stored on `nation.persona_map`. Audit trail: new `persona_map.csv` (`agent_id, source_agent_id, persona_mode`) via `_RESULT_CSV_SCHEMAS["persona_map"]` in [src/cag/io/results.py](src/cag/io/results.py) (final-output only, in `_CHECKPOINT_SKIP_KEYS`). `persona_mode` added to `_RESUME_HARD_KEYS` in [src/cag/io/checkpoint.py](src/cag/io/checkpoint.py). New `--persona-mode {real,shuffled,neutral}` CLI flag ([src/cag/__main__.py](src/cag/__main__.py)) and new `tierP` bundle in [src/cag/presets.py](src/cag/presets.py) (100 agents, single empty-phase Day-0-only day, package mode, `day0_anchor="llm_survey"`, `memory="persona_only"`). New sweep [scripts/aire/sweeps/tierP.txt](scripts/aire/sweeps/tierP.txt) (3 arms × seeds 42/43/44). Tests: new [tests/test_persona_mode.py](tests/test_persona_mode.py) (20 tests). Docs: [docs/Model_Design.md](documentation/research/Model_Design.md) §31, `persona_mode` entry in [docs/Simulation_Configuration_Guide.md](documentation/guides/Simulation_Configuration_Guide.md). NB demo deferred until AIRE run dirs return.
- **Broadcast-frequency-asymmetry CLI (2026-07-03).** The per-day `make_phases` shorthand (v0.5 §19) could already make one side broadcast more often than the other, but only via a hand-written `days` list. Three new flags in [src/cag/__main__.py](src/cag/__main__.py) apply the asymmetry to *every* day when `--days` is a plain integer: `--broadcasts-a N` / `--broadcasts-b M` (default 1/1) and `--interleave` / `--no-interleave` (default on; alternating `A,B,A,…` vs block `A,A,…,B`). New `build_days(n_days, broadcasts_a=1, broadcasts_b=1, interleave=True)` loops through `make_phases(..., a_first=(i % 2 == 0))` to preserve the alternate-first-speaker convention; `build_config` pops the three knobs from the merged dict, expands an integer `days`, and warns (ignoring them) if they are set while `days` is an explicit list. Peer chat (`C`) is always appended — disable with `--k-peers 0`. Default 1-vs-1 reproduces the classic schedule exactly. This is a **frequency** lever, orthogonal to `reach_a`/`reach_b` (audience *fraction* per broadcast). Tests: new `TestBroadcastFrequency` in [tests/test_cli.py](tests/test_cli.py) (9 tests). Docs: "Broadcast-frequency asymmetry from the command line" in [docs/Simulation_Configuration_Guide.md](documentation/guides/Simulation_Configuration_Guide.md), [docs/Model_Design.md](documentation/research/Model_Design.md) §32.
- **Affinity-weight three-tier ladder + AIRE run labels (2026-07-03).** The affinity-weight presets in [src/cag/abm/config/exposure.py](src/cag/abm/config/exposure.py) are simplified to an explainable factor-2 ladder. `balanced` (`DEFAULT_AFFINITY_WEIGHTS`): political signals (`brexit`, `politics`, `vote_bonus`) = 2.0, values (`openness`, `selftransc`, `conformtrad`, `sdo`, `rwa`) = 1.0, demographics (`age`, `education`, `region`) = 0.5 (anchors: Fletcher & Nielsen 2017 on selective exposure; Steg & de Groot 2010 on value-based environmental attitudes). `vote_dominant` keeps the ladder but pushes the political tier 2.0 → 4.0; `values_dominant` swaps the top two tiers (values 4.0, political 1.0, demographics 0.5). Because affinity scores only *order* citizens before slicing to the target cell shares, the weights change *who* lands in each audience cell but never the cell sizes. Caveat: NB 27's reported preset-agreement percentages predate this change and no longer match the shipped presets; NB 27 is left as a historical v0.5 pilot, not re-run. Separately, [scripts/aire/run.sh](scripts/aire/run.sh) now honours an optional `RUN_LABEL` env var appended as a suffix to the scratch output dir (`run_${SLURM_JOB_ID}${RUN_LABEL:+_${RUN_LABEL}}`) with a banner echo, so sweep jobs land in self-describing folders. Docs: researcher-facing affinity scorecard/sort-and-slice walkthrough + weight table added to [docs/Simulation_Configuration_Guide.md](documentation/guides/Simulation_Configuration_Guide.md); [docs/Model_Design.md](documentation/research/Model_Design.md) §33.
- **Test suite** — **680 passed, 1 skipped** (was 610 at the end of v0.8; +20 persona-mode, +9 frequency, +17 reach-targeting, +6 output/prompt-capture, +1 O2-plots, +13 peer fan-out, plus subtest coverage).
- **Versioning** — no `__version__` bump (carried from v0.8; the bump is left for the user to decide at release time).

### Historical milestone evidence

The earlier v0.9 roadmap snapshot recorded **647 passed, 1 skipped** after
persona-mode and broadcast-frequency coverage (20 and 9 new tests,
respectively), up from 610. The later 680-test result above supersedes that
snapshot. The roadmap also recorded the documentation update to the design
log's sections 31-33 and the 2026-07-03 development-history entries.


## [0.8]
v0.8 is the **refactor track**: pure structural splits of long-accumulated modules into focused single-responsibility units **plus** a behaviour-track refactor of the in-context memory assembly (zero net-call change but a new prompt order and one removed LLM call per agent at Day 0). All subsequent refactor work this cycle lands under this version. No `__version__` bump (deferred to the eventual feature-bearing release).

- **Configurable memory / prompt assembly (2026-07-01).** The hard-wired v2 tiered-memory pipeline (§28/§30 of [Model_Design.md](documentation/research/Model_Design.md)) is now declaratively configurable so social scientists can run memory-ablation experiments without editing `agent.py`. New subpackage [src/cag/abm/config/](src/cag/abm/config/): [config/exposure.py](src/cag/abm/config/exposure.py) **relocates** the exposure target/weight vocabularies out of [environment.py](src/cag/abm/environment.py) (which re-exports every public name with `# noqa: F401`, so existing imports keep working — this un-buries the exposure targets that were previously mixed into the environment module); [config/memory.py](src/cag/abm/config/memory.py) holds the new memory schema (`DEFAULT_MEMORY_CONFIG`, `MEMORY_PRESETS`, `resolve_memory_config`, `validate_memory_config`, `resolve_stage_memory`, and the window helpers `verbatim_days` / `summary_upper_exclusive` / `compression_target_day` — the single source of truth for the previously-scattered "last 2 days" constant). Six context sections (persona, Day-0 anchor, daily summaries, recent reflections, own reasoning, today-so-far) are individually toggleable; a single `verbatim_window_days` knob (default 2) couples §3/§4/§5 + `manage_memory`; `day0_anchor.ttl_days` retires the anchor after N days; an off-by-default `opinion_trajectory` numeric block can be revived; per-stage overrides (`peer_message` / `reflection` / `survey`) are supported. Presets: `default`, `short_memory`, `wide_memory`, `no_compression`, `no_anchor`, `anchor_ttl2`, `no_own_reasoning`, `reflections_only`, `persona_only`. Wiring: new `SIM_CONFIG["memory"] = "default"` key (→ 33 keys) resolved in `_resolve_runtime` and deep-copied onto each agent in `run()` ([sim.py](src/cag/abm/sim.py)); `"memory"` added to `_RESUME_HARD_KEYS` ([checkpoint.py](src/cag/io/checkpoint.py)); new `--memory` CLI flag (preset name or JSON dict) in [__main__.py](src/cag/__main__.py). `assemble_context` / `get_system_prompt` gained a `stage` parameter threaded through every call site in [agent.py](src/cag/abm/agent.py). **The default config reproduces the §28 behaviour bit-for-bit** — guaranteed by the unchanged golden portion of [tests/test_memory.py](tests/test_memory.py). New tests: [tests/test_memory_config.py](tests/test_memory_config.py) (schema/presets/validation/window-helper partition property) and `TestMemoryConfigToggles` in test_memory.py (every non-default toggle), plus `memory` resolution/resume/CLI cases in test_sim.py & test_cli.py. Demo: [notebooks/35_memory_ablation_demo.ipynb](notebooks/35_memory_ablation_demo.ipynb) (offline, no LLM). Docs: [Model_Design.md](documentation/research/Model_Design.md) §30, [USER_GUIDE.md](USER_GUIDE.md) v0.8 config path. Suite: **610 passed, 1 skipped**. No `__version__` bump.
- **`debias` option removed — two-step survey is now unconditional (2026-07-01).** The Condition B two-step survey (`debias=True`) has been research canon since v0.3 and the simulation loop always ran it (even the `llm_survey` Day-0 anchor); the non-debias single-call branch was dead. The whole toggle is now deleted rather than left as a no-op. In [src/cag/abm/agent.py](src/cag/abm/agent.py): the dead `get_user_prompt()` helper and the `if debias / else` branch in `administer_survey()` are gone (Step-1 reasoning + Step-2 answer now run unconditionally); the `debias` parameter is dropped from `administer_survey()` and `run_baseline()`. Threaded through [src/cag/abm/environment.py](src/cag/abm/environment.py) (`run_end_of_day_survey()`), [src/cag/abm/sim.py](src/cag/abm/sim.py) (`SIM_CONFIG["debias"]` key removed → 32 keys; `_run_baseline_surveys` / `_run_day0` params; runtime dict; EOD + Day-0 call sites; the "debias flag is ignored on Day 0" log line; `[llm]` config-log field), [src/cag/__main__.py](src/cag/__main__.py) (`--debias` flag removed), [src/cag/presets.py](src/cag/presets.py) (`debias` key dropped from `smoke` + `r14_canonical`), and [src/cag/io/checkpoint.py](src/cag/io/checkpoint.py) (`debias` dropped from `_RESUME_SOFT_KEYS`; checkpoint-safe — old checkpoints' `debias` key is simply never compared). The `_DEBIAS_STEP1/STEP2` templates and `survey_reasoning` (the "debias trace") are retained — they *are* the two-step mechanism, now non-optional. This also removes the ability to run a raw, un-debiased survey via `run_baseline()` (those helpers stay but are now implicitly two-step). Tests: non-debias cases dropped from `TestDebiasedSurvey`, the debias assertions/flags removed from [tests/test_cli.py](tests/test_cli.py), and `test_debias_default_true` + `test_debias_with_anchored_mode_logs_override` removed from [tests/test_sim.py](tests/test_sim.py). Docs: [docs/Simulation_Configuration_Guide.md](documentation/guides/Simulation_Configuration_Guide.md) `debias` row + section + resume note removed. `thinking` (also always-default in canon) deliberately kept — it is a live research toggle used with `True` in NB 24/25/34.
- **Day-0 anchor cross-step consistency fix (2026-06-28).** In **package mode** the Day-0 identity anchor (memory section 2) was present only at end-of-day survey time but absent during peer-message generation and reflection (those steps call `assemble_context` with `policy_id=PACKAGE_SCOPE` and no `target_policy_id`, leaving every target-scoped section empty). The agent effectively "forgot" its verbatim Day-0 position between steps and regained it at survey time — poor cognitive modelling and a validity concern (peer messages came from a thinner self-model than survey answers). New `_section_day0_anchor_all()` in [src/cag/abm/agent.py](src/cag/abm/agent.py) emits every policy's Day-0 rationale (canonical `SURVEY_QUESTIONS` order) under `Original prior positions:`; `assemble_context` now uses the focused single-policy anchor when there is a real `target_policy_id` (survey, unchanged) and the all-policy form for package-scoped steps with no single target (peer/reflection). **Only section 2 is propagated** — sections 5 (recent considered position, redundant with summaries+reflections in a holistic step) and 6 (today's answers-so-far, chronologically not yet taken) are deliberately left survey/target-scoped. Single-policy mode was already consistent and is unchanged. Tests: `TestDay0AnchorSection` gains `test_package_anchor_lists_all_policies_when_no_single_target` and `test_package_anchor_present_on_peer_reflection_path`; 557 passed, 1 skipped. Docs: [Model_Design.md](documentation/research/Model_Design.md) §20.7, [Prompts_and_Personas_Guide_v2.md](documentation/guides/Prompts_and_Personas_Guide_v2.md) §2.2.
- **v2 tiered memory architecture (2026-06-23).** [src/cag/abm/agent.py](src/cag/abm/agent.py) `assemble_context()` rewritten with an explicit 6-section order (skipping empties): (1) persona + values, (2) Day-0 anchor — verbatim Day-0 rationale for the **target** policy, (3) summary of recent days (`daily_summaries` for days `<d-1`), (4) recent reflections (days `d-1`, `d`), (5) own reasoning from days `d-1`, `d` (target-scoped), (6) today-so-far block (package mode only). New invariant: `policy_id` filters §3+§4 (the *context* scope) while `target_policy_id` scopes §2+§5+§6 (the *question* scope) — in package mode the EOD survey passes `context_policy_id=PACKAGE_SCOPE` (cross-policy reflections survive) but `target_policy_id=policy_id` (anchor and own-reasoning narrowed to the policy being asked). **Day-0 anchor compression step removed**: `agent.day0_anchors` dict, `compress_day0_anchor()` method, post-`_run_day0` compression loop in [src/cag/abm/sim.py](src/cag/abm/sim.py), `day0_anchors.csv` from `_RESULT_CSV_SCHEMAS` and checkpoint hydration — all gone. `_section_day0_anchor()` now reads `survey_reasoning` directly (one fewer LLM call per agent at Day 0; same numeric output, less drift surface). `manage_memory()` simplified to a single d-2 compression call before the EOD survey. Test suite covers the full 6-section ordering (`TestSectionOrder`, `TestDay0AnchorSection`); 556 passed, 1 skipped.
- **AIRE / operational fixes (2026-06-23).**
    - **Dead `SIM_CONFIG["output_dir"]` removed** from [src/cag/abm/sim.py](src/cag/abm/sim.py): never consumed (`__main__.py` reads `--outdir` and passes it directly to `save_results(output_dir=…)`). `SIM_CONFIG` now has 33 keys (was 34). Also stripped from [tests/test_checkpoint.py](tests/test_checkpoint.py) `_base_config()` and from [notebooks/32_v06_outputs_smoke.ipynb](notebooks/32_v06_outputs_smoke.ipynb) (which has a `set(config) == set(SIM_CONFIG)` parity assertion).
    - **Network-type-aware `[peer]` log line** in `_log_experiment_config()` ([src/cag/abm/sim.py](src/cag/abm/sim.py)): replaces hardcoded `p_intra` / `p_inter` (SBM-only, misleading for `watts_strogatz` / `barabasi_albert` / `erdos_renyi` / `homophily_weighted`) with the resolved `_resolve_network_params(cfg)` dict rendered as `params={k=v, …}`. SBM defaults render visually unchanged (`params={p_intra=0.15, p_inter=0.05}`); non-SBM topologies now show their actual parameters (e.g. `params={k=8, beta=0.2}` for Watts–Strogatz). Empty dicts render as `params={} (builder defaults)`.
    - **AIRE Quickstart §6 first-time-download callout** ([documentation/guides/AIRE_Quickstart.md](documentation/guides/AIRE_Quickstart.md)): new `> **Important — first-time model download.**` blockquote explaining the 1500 s vLLM-readiness wait and recommending `--time=06:00:00` on the very first submission with a fresh model. Subsequent cached-model runs warm up in <2 min.
- **New researcher-onboarding doc (2026-06-23).** [docs/Code_Tour.md](documentation/guides/Code_Tour.md) — ~25-page walkthrough of `src/cag/` for a newcomer who knows the science but hasn't opened the source. 8 sections: (A) audience and conventions, (B) 30-minute skim sequence, (C) 15 file-by-file walkthroughs (medium depth on `sim.py` + `agent.py` with annotated excerpts), (D) two side-trips (political-exposure rank assignment, v2 memory annotated example), (E) "I want to ___" cookbook (6 recipes), (F) glossary, (G) AIRE pre-flight checklist. Model-agnostic; targets newcomer onboarding for the codebase.
- **NB 34 v2 memory smoke** ([notebooks/34_memory_v2_smoke.ipynb](notebooks/34_memory_v2_smoke.ipynb)) added. End-to-end smoke validating the v2 memory architecture under local Qwen3-8B-4bit. Day-0 anchor compression delta cell removed (anchor is now verbatim from `survey_reasoning`, no per-token cost to track). Local execution shelved (Apple-Silicon throughput too low for a day-0 survey in <30 min on n=10); will run on AIRE.
- **`sim.py` modular split (2026-06-23, earlier in the day).** [src/cag/abm/sim.py](src/cag/abm/sim.py) reduced from **2755 → 838 lines** (orchestration only: `run_simulation`, `_run_one_day`, `_resolve_runtime`, `SIM_CONFIG`). Five focused modules extracted:
    - [src/cag/abm/network_repair.py](src/cag/abm/network_repair.py) (263 lines) — `_adjust_network_params_for_small_n`, `_auto_connect_components`, `_log_network_summary`, `_safe_network_diagnostics` (the v0.7 3-layer connectivity defence).
    - [src/cag/io/aggregators.py](src/cag/io/aggregators.py) (506 lines) — `_collect_results` post-processing builders: `build_package_index_by_bucket`, `build_opinion_shares_by_bucket`, `build_day0_vs_dayN_shifts`, `build_calibration_table`, `build_message_flow`, `build_agent_timeline`, `collect_agent_attributes`.
    - [src/cag/io/plots.py](src/cag/io/plots.py) (555 lines) — `save_result_plots` and every per-figure plotter (`plot_package_index_by_bucket`, `plot_opinion_shares_by_bucket`, `plot_gap_widening`, `plot_calibration_by_policy`, `plot_network_graph`, plus the legacy single-policy plotters).
    - [src/cag/io/results.py](src/cag/io/results.py) (512 lines) — `save_results`, `_RESULT_CSV_SCHEMAS`, `_write_all_csvs`, `_safe_network_snapshot`, JSON config/diagnostics serialisation.
    - [src/cag/io/checkpoint.py](src/cag/io/checkpoint.py) (366 lines) — `_write_checkpoint`, `_load_checkpoint`, `_CHECKPOINT_SKIP_KEYS`, resume-key validation, `sim_step` rehydration logic.
- **Validation.** End-to-end NB 32 re-run ([data/output/experiments/20260623_140314/](data/output/experiments/20260623_140314/)) compared against the pre-refactor baseline ([data/output/experiments/20260622_170436/](data/output/experiments/20260622_170436/)). All deterministic outputs (`config.json`, `ground_truth.csv`, `package_ground_truth.csv`, `agent_attributes.csv`, `network_snapshot.json`) are **bit-identical**. All 22 LLM-driven CSVs have **identical schemas and row counts**; numeric distributional stats (mean abs_shift, calibration MAE, signed shifts per bucket) match within gpt-5-mini @ T=0.5 stochasticity. Network: 10 nodes, 9 edges, bucket distribution `{A-only:1, B-only:1, both:3, neither:5}` both runs. The refactor preserves the determinism path, the schema contract, and the call-count contract.
- **Test suite** — **556 passed, 1 skipped, 21 subtests passed** (was 538 at end of v0.7; +18 from new v2-memory section-order tests). No tests rewritten; imports updated to the new module paths where symbols moved.
- **Versioning** — no `__version__` bump. v0.8 is a refactor-only label; the bump is held until the next behaviour change.

### Historical milestone evidence

The earlier v0.8 roadmap snapshot recorded **556 passed, 1 skipped, 21 subtests
passed**, with 18 additional tests for the verbatim/target-scoped memory path;
later configurable-memory work raised the suite to 610. It also recorded
[NB 34](notebooks/34_memory_v2_smoke.ipynb) configured for local Qwen3-8B-4bit,
with the full Day-0 run deferred to AIRE for throughput, and a first-model-
download callout recommending a six-hour cold-cache job in the AIRE quickstart.
The accompanying docs sweep updated the design log's sections 27-29 and the
2026-06-23 development-history entries. These are historical milestones, not
evidence that the deferred production validation has since completed.


## [0.7]
v0.7 consolidates a long block of work that had been accumulating under the in-progress "v0.6" label and grafts a substantial HPC/AIRE infrastructure layer on top. The release covers four headline themes — HPC-first infrastructure, a critical package-mode survey-context fix, a major outputs-and-instrumentation expansion (17 → 29 saved artefacts), and a 3-layer network connectivity defence — plus a coordinated bulk `__version__` bump that retires the long-standing 0.2.0 / 0.3.0 / 0.5.0 / 0.6.0 / 1.0.0 inconsistency across source modules.

- **AIRE / HPC infrastructure** — new [scripts/aire/run.sh](scripts/aire/run.sh) thin sbatch launcher that exposes every research knob as a CLI flag (no per-experiment script edits), [scripts/aire/sweep.sh](scripts/aire/sweep.sh) multi-job submitter reading a documented sweep file (one line per condition), and [scripts/aire/sweeps/](scripts/aire/sweeps/) directory with the v0.7 canonical sweep `r14_v2.txt` (3 split50 conditions). New [documentation/guides/AIRE_HPC_repo_primer.md](documentation/guides/AIRE_HPC_repo_primer.md) (cluster fundamentals, storage rules, hard constraints) and [documentation/guides/AIRE_Quickstart.md](documentation/guides/AIRE_Quickstart.md) (copy-pasteable walkthrough from zero to a split50 Run-14). vLLM server auto-starts on the GPU node with `$HF_MODEL` overrideable. Preset bundles live in the new [src/cag/presets.py](src/cag/presets.py) (`RUN_BUNDLE_PRESETS = {"smoke", "r14_canonical"}`) so adding a new experiment is one entry in a Python dict plus one line in a sweep file — no shell editing.
- **CLI refactor** ([src/cag/\_\_main\_\_.py](src/cag/__main__.py)) — full argparse coverage for every `SIM_CONFIG` knob: sizing, day plan, communication mode + package policies, day-0 anchor, peer count, LLM provider/model, survey model/provider override, thinking, debias, exposure mode/targets/weights, reach/audience, message source/set, network type/params, local-LLM keys, checkpoint, resume. New composition layer: `--preset NAME` loads a `RUN_BUNDLE_PRESETS` entry, individual flags layer on top, `--dry-run` previews the resolved config without I/O, `--list-presets` enumerates available bundles. Special argparse types: `_maybe_json` (preset name *or* literal dict), `_json_dict` (strict JSON), `_int_or_none` (accepts "none"/"null"/""), `_package_policies_arg` ("all" or comma-separated ints).
- **NB-31 package-mode survey-context fix** — `administer_survey()` and `run_end_of_day_survey()` in [src/cag/abm/agent.py](src/cag/abm/agent.py) / [src/cag/abm/environment.py](src/cag/abm/environment.py) now pass `PACKAGE_SCOPE` to `assemble_context()` when running in package mode, so the in-context memory is the union over all six climate policies instead of the empty per-policy slice. The bug had been silent since v0.4 (every package-mode survey was reading an effectively unchanging system prompt, so broadcasts had nothing to influence at the survey step). Discovery: NB 30 surgical replay across models. Validation: NB 31 fix-replay. Production confirmation: Run-14 v2 measured **+0.667 Day-5 cross-bucket gap-widening (vs +0.053 pre-fix) — a 12.6× amplification** matching the GPT-5.4-mini surgical-replay prediction within noise. Full write-up in [docs/result_report.md](documentation/research/result_report.md).
- **`k_peers=0` short-circuit** — `run_peer_messaging` and `run_package_peer_messaging` in [src/cag/abm/environment.py](src/cag/abm/environment.py) now early-return when `k_peers_per_day == 0`, skipping the inner-loop `generate_peer_message` calls that previously fired regardless. Saves ~240 wasted LLM calls per r14-style 5-day broadcast-only run. New `TestPeerMessagingKPeersZeroShortCircuits` class in [tests/test_peer_messaging.py](tests/test_peer_messaging.py).
- **Per-day checkpointing default-on (CLI)** — `--checkpoint-every-day` in [src/cag/\_\_main\_\_.py](src/cag/__main__.py) is now `argparse.BooleanOptionalAction, default=True` so every batch run is wall-clock-kill-recoverable without remembering the flag; `--no-checkpoint-every-day` opts out. The Python-side `run_simulation(..., checkpoint_every_day=False)` default is intentionally unchanged so interactive notebooks don't accumulate per-day artefacts unless asked. New tests in [tests/test_cli.py](tests/test_cli.py) (`test_checkpoint_default_on`, `test_checkpoint_opt_out`).
- **Outputs expansion (17 → 29 artefacts, Phases 1–5)** — the saved run bundle now answers every diagnostic question that previously required a notebook to derive from raw CSVs.
    - *Phase 1 — agent-attribute persistence.* `_assign_affinity_rank` in [src/cag/abm/environment.py](src/cag/abm/environment.py) caches `_affinity_score_a` and `_affinity_score_b` on every citizen (mirrors the existing in-place `political_exposure` write). New `collect_agent_attributes(nation)` in [src/cag/abm/sim.py](src/cag/abm/sim.py) returns a per-agent DataFrame keyed on `agent_id` with bucket, both affinity scores, the demographic IDs that drive the persona, and the full `get_persona()` text (no truncation). Written as `agent_attributes.csv` to checkpoints + final.
    - *Phase 2 — bucket-stratified CSVs.* `build_package_index_by_bucket`, `build_opinion_shares_by_bucket`, `build_day0_vs_dayN_shifts` — three pure-function builders joining `agent_attributes` to the per-day signals. The Run-14 v2 "+0.667 Day-5 gap-widening" headline is now derivable from `package_index_by_bucket.csv` alone.
    - *Phase 3 — bucket plots.* `plot_package_index_by_bucket` (one panel per bucket), `plot_opinion_shares_by_bucket` (`policy × bucket` mega-grid), `plot_gap_widening` (bold package-index gap + thin per-policy gap traces). All wired through `save_result_plots`.
    - *Phase 4 — calibration, message flow, network snapshot.* `build_calibration_table` (per `(policy_id, day)` `pearson_r / spearman_rho / mae / mean_signed_bias` vs `ground_truth`) + `plot_calibration_by_policy` (per-policy GT-vs-LLM scatter). `build_message_flow` joins `messages × agent_attributes` to a `(day × phase × sender_side × recipient_bucket)` aggregation — would have flagged the `k_peers=0` waste in one glance. `_safe_network_snapshot` writes a JSON-safe `{nodes:[{id,bucket,degree}], edges:[[u,v],...]}` to `network_snapshot.json`; `plot_network_graph` renders it with node colour by bucket, size by degree.
    - *Phase 5 — assembled survey context + agent timeline.* New `self.survey_assembled_context = {}` on `SurveyedCitizen` in [src/cag/abm/agent.py](src/cag/abm/agent.py); `administer_survey()` appends `(day, ctx_str)` immediately after `assemble_context()`. Captures the **exact ~1–18 KB system prompt** each agent saw at every survey call — the diagnostic affordance that would have caught NB-31 in week one. Two new `SIM_CONFIG` keys: `timeline_sample_size=3` (default) and `timeline_sample_agent_ids=None` (auto-stratify one agent per top-3-by-size exposure bucket; ties → sorted `agent_id`; <3 buckets → evenly-spaced). `build_agent_timeline` returns a long-format DataFrame with 9 event types (`broadcast_received, broadcast_reflection, peer_message_received, peer_message_sent, peer_reflection, survey_assembled_context, survey_raw_response, survey_reasoning, survey_numeric`) sorted by `(agent_id, sim_step)`. Final-output only via the new `_CHECKPOINT_SKIP_KEYS = frozenset({"agent_timeline"})` mechanism (can be GB-scale on long runs).
    - *Cross-cutting — `sim_step` instrumentation.* Monotonic `nation._sim_step` counter (lazy-init, restored to `max(sim_step)` across all loaded sources on resume) incremented at every event-logging site. New `sim_step` column on `messages`, `reflections`, `survey_reasoning`, `survey_raw_response`, `survey_assembled_context`, and `daily_summaries` CSVs. Sort key for any interleaved replay is now `(agent_id, sim_step)` — schema makes zero assumption about phase count, order, or repetition.
- **Network connectivity 3-layer defence** — disjoint peer networks (silent until now) become impossible going forward.
    - SBM `p_inter` default 0.02 → **0.05** in [src/cag/abm/networks.py](src/cag/abm/networks.py) and [src/cag/abm/sim.py](src/cag/abm/sim.py): drops the within-to-between ratio from 7.5:1 to 3:1, yielding ~25% cross-cutting exposure — within the Facebook ~24% of Bakshy et al. 2015 *Science* and the Twitter 18–26% of Halberstam & Knight 2016. Erdős–Rényi default `p` 0.05 → **0.10** (above the n=50 classical threshold ln(50)/50 ≈ 0.078). Watts–Strogatz, Barabási–Albert, and homophily_weighted defaults unchanged (always connected by construction).
    - *Layer 1.* `_adjust_network_params_for_small_n(cfg, n_agents)` called before `nation.create_network`: SBM `n < 30` → bump `p_inter` to `max(p_inter, 0.10)` and log WARNING; `30 ≤ n < 100` → bump to `max(p_inter, 0.06)` and log INFO. ER analogues. `n ≥ 100` left alone. Only ever raises values, never lowers — explicit higher overrides survive untouched.
    - *Layer 2.* `_auto_connect_components(nation, seed)` called after `nation.assign_network_blocks`: if `nx.is_connected(G)` is False, sorts components by `(-len, sorted_node_ids[0])` for determinism, uses `np.random.default_rng(seed)` to pick endpoints, adds exactly `(k − 1)` bridging edges from each smaller component to the largest, re-runs `assign_network_blocks()` to refresh agent `network_neighbors`, and logs a WARNING with component count, sizes, n_added, seed. Records `nation._auto_connected_edges`.
    - *Layer 3.* `_log_network_summary(nation)` emits a single INFO line `n_nodes / n_edges / n_components / mean_degree / auto_connected_edges`; `_safe_network_diagnostics` adds a new `auto_connected_edges` field in `network_diagnostics.json`.
    - Motivating empirical sweep in new [scripts/estimate_connectivity_threshold.py](scripts/estimate_connectivity_threshold.py): n=10 hopeless at any `p ≤ 0.15`; n=50 needs `p_inter ≥ 0.06` for 90% success.
- **`_safe_int` defensive fix carried over** ([src/cag/abm/environment.py](src/cag/abm/environment.py)) — the v0.5 `getattr(x, "id", x)` guard remains; complemented by the new `isinstance(G, nx.Graph)` guards on Layer 2/3 helpers so MagicMock-based unit tests don't crash on `nx.is_connected(mock)`.
- **Notebooks** — three new:
    - [notebooks/30_surgical_survey_replay.ipynb](notebooks/30_surgical_survey_replay.ipynb) — frozen-state replay of a single agent's package-mode survey across models; first observation of the empty-context bug.
    - [notebooks/31_package_mode_fix_validation.ipynb](notebooks/31_package_mode_fix_validation.ipynb) — confirmed the fix amplifies the cross-bucket gap as predicted.
    - [notebooks/32_v06_outputs_smoke.ipynb](notebooks/32_v06_outputs_smoke.ipynb) — canonical 10-agent × 2-day package-mode smoke that surfaces every new artefact (file inventory, per-CSV schema, bucket views, agent_timeline for sampled agents, every PNG inline). Also doubles as the live demo for the connectivity defence: at n=10, Layer 1 fires (`p_inter` 0.05 → 0.10) and Layer 2 fires (5 components → 1 with 4 bridging edges).
- **Test suite** — **538 passed, 1 skipped** (was 432 → +106 across the window). New file [tests/test_timeline_and_outputs.py](tests/test_timeline_and_outputs.py) (30 tests covering `sim_step` counter, `_safe_step`, `collect_agent_attributes`, network_snapshot, timeline sampling, all bucket builders, calibration, message_flow, `_CHECKPOINT_SKIP_KEYS`, `save_results` JSON emission). 13 new connectivity tests in [tests/test_networks.py](tests/test_networks.py) (`TestAdjustNetworkParamsForSmallN ×7`, `TestAutoConnectComponents ×4`, `TestNetworkDiagnosticsAutoConnectedField ×2`). Plus k_peers=0 and CLI-checkpoint tests above. Three existing tests updated for the new `sim_step` column.
- **Versioning** — `__version__` bulk-bumped to **0.7.0** across 18 source modules. Retires the long-standing inconsistency (0.2.0 / 0.3.0 / 0.5.0 / 0.6.0 / 1.0.0 across modules). The previously in-progress "v0.6" label is subsumed into v0.7: v0.6 was never tagged on `origin`, so the public version ladder is 0.5 → 0.7 with one rich release.
- **Docs sweep** — this CHANGE_LOG, [ROADMAP.md](ROADMAP.md), [DEVELOPMENT_HISTORY.md](DEVELOPMENT_HISTORY.md), [docs/Model_Design.md](documentation/research/Model_Design.md) §22–§26, [USER_GUIDE.md](USER_GUIDE.md) (new v0.7 section + HPC pointer), and [README.md](README.md) status all bumped together. [docs/result_report.md](documentation/research/result_report.md) already covered Run-14 v2, NB-31 fix, and the NB 32 v0.6-outputs + connectivity smoke validation. Deep rewrites of [docs/Run_Output_Guide.md](documentation/guides/Run_Output_Guide.md) and [docs/Simulation_Configuration_Guide.md](documentation/guides/Simulation_Configuration_Guide.md) deferred to a follow-up session.


## [0.6]

Historical internal consolidation label; the v0.7 entry records that this work
was subsumed into 0.7 rather than separately tagged on `origin`. The earlier
roadmap snapshot reported **465 passed, 1 skipped** during this consolidation.

- **Canonical SIM defaults refresh** — `SIM_CONFIG` in `src/cag/abm/sim.py` now defaults to the current research-canon profile: `n_citizens=100`; package-mode alternating day plan (`["P-A","P-B","C"]` / `["P-B","P-A","C"]`); `llm_provider="local"`; `llm_model="mlx-community/Qwen3-8B-4bit"`; `debias=True`; `day0_anchor="ground_truth_with_rationale"`; `political_message_source="offline"`; `political_message_set="v1"`.
- **Offline political-message subsystem promoted to first-class runtime path** — new loader/module `src/cag/abm/political_messages.py`, curated datasets under `data/political_messages/`, strict startup validation of required message cells, and deterministic selection/rotation behavior. Offline remains explicit default and there is no silent fallback when required cells are missing.
- **Broadcast provenance in outputs** — `messages.csv` now includes `political_message_id` so every political broadcast row can be traced back to a concrete entry in the message pool.
- **Resume contract tightened for message-source consistency** — `_RESUME_HARD_KEYS` now includes `political_message_source` and `political_message_set`, preventing incompatible resume mixes between curated/offline and generated/LLM political-message regimes.
- **Test-suite and harness alignment for new defaults** — added `tests/conftest.py` local-provider startup mocks and updated `tests/test_sim.py` assumptions where legacy defaults were hard-coded; added dedicated pool coverage in `tests/test_political_messages.py`.
- **New canonical docs/notebooks** — added `docs/Simulation_Configuration_Guide.md` (two-layer audience design: supervisor brief + developer matrix), `notebooks/28_offline_political_messages_smoke.ipynb`, and `notebooks/29_canonical_full_smoke.ipynb`.
- **Dataset/default wording correction** — documentation now reflects the source cohort as **YouGov April 2024** (not 2022 in runtime-context references) and aligns current default-population references to 100 where they describe active defaults.


## [0.5]
- **Political-agent prompt de-identification (2026-05-20)** — `_DEFAULT_PRO_CLIMATE_PROMPT` and `_DEFAULT_ANTI_CLIMATE_PROMPT` in `src/cag/abm/agent.py` reframed as a generic *fallback* path (research direction moves toward broadcasting real-world political messages). Removed every party and politician name (Green Party of England and Wales, Reform UK, Zack Polanski, Caroline Lucas, Nigel Farage, Richard Tice) and the explicit "campaigning in the style of …" framing. Trimmed non-climate spillover from the pro-climate brief (water companies, NHS, free public transport, the "For the Common Good" slogan, wealth-tax-on-the-super-rich content); narrowed target audience from "disillusioned Labour voters / public sector workers" to "renters / workers wanting a just transition". Parallel cuts to the anti-climate brief. `_ANTI_SYCOPHANCY` tightened by dropping the "Real people like you hold a WIDE range of views… That is expected and acceptable" sentence (over-leading). `_DEBIAS_STEP1_TEMPLATE` updated from "the messages and reflections from today, and how these might interact" to "the messages and reflections from today and previous days" so the wording matches the v0.5.1 multi-day daily-context surveys. `docs/Prompts_and_Personas_Guide_v2.md` updated: status banner rewritten as fallback framing with the de-identification note and the real-message-ingestion direction; §3.1 / §3.2 / debias step-1 verbatim quotes regenerated to match the trimmed prompts.
- **Affinity-based political-exposure sanity check (NB 27) + bug fixes** — `notebooks/27_affinity_exposure_demo.ipynb` validates the v0.5 committed-minority audience reframe on the full YouGov pool (N = 1483): `rule_affinity_rank` hits both shipped target presets (`committed_minority_symmetric` 0.11/0.11/0.33/0.45 and `committed_minority_uk_2024` 0.08/0.14/0.33/0.45) to within rounding, all four pre-registered validation gates pass (A-only mean openness 2.24 > pool +0.5 SD, A-only Remain share 96.3 %, B-only mean RWA 2.06 > pool +0.5 SD, B-only Leave share 98.2 %), and the three weight presets (`balanced` / `vote_dominant` / `values_dominant`) produce non-trivial cell-level disagreement (66 % vote-vs-values agreement at fixed target). Two bugs surfaced and fixed: (i) **`_safe_int` silently zeroed every GABM ordinal attribute** because `int(GABMAttributeID(n))` raises `TypeError`; rewritten to read `.id` first (then `.value`, then `int()`); new `TestSafeInt` regression class (4 tests) in `tests/test_exposure.py` closes the unit-test gap that allowed the bug to ship. (ii) **`rule_affinity_logistic` removed entirely** — independent Bernoulli sampling on anti-correlated A/B scores (`corr = -0.975` on YouGov) systematically missed cell-share targets by ±18 pp on average despite hitting per-side marginals; removed from `VALID_EXPOSURE_MODES`, the dispatcher, the `_assign_affinity_logistic` method, the `affinity_logistic_temperature` SIM_CONFIG key, the `_RESUME_HARD_KEYS` list, and the test suite. v0.5 ships with two modes only: `rule_priority_chain` (legacy) and `rule_affinity_rank` (new default). Full write-ups: `docs/result_report.md` §"Affinity-based political exposure: NB 27"; `docs/Model_Design.md` §18.15; `docs/Literature_Political_Exposure.md` §6 / §6.3 / §7. Test suite: **432 passed, 1 skipped** (430 → 432: −2 logistic tests, +4 `TestSafeInt` tests).
- **Prompt audit and unification (post local-LLM)** — every citizen-side LLM prompt in `src/cag/abm/agent.py` audited and brought into a consistent shape: (a) debias chain (`_ANTI_SYCOPHANCY`, `_DEBIAS_STEP1_TEMPLATE`, `_DEBIAS_STEP2_TEMPLATE`) and `seed_opinion_with_rationale` flipped from mixed 2P/3P to consistent first-person; NB 13's Condition B bias-reduction number not assumed to transfer (re-measurement deferred); (b) vanilla Day ≥ 1 survey framing and debias Step 1 factor list now explicitly reference the in-context memory (`assemble_context()` daily summaries / Day-0 rationales / recent reflections); (c) `get_persona()` is now the canonical public method returning demographics + values merged — old `get_persona()` and `get_narrative()` renamed to private `_build_demographics_text()` / `_build_values_text()`; end-of-context reminder line renamed to `"Remember who you are: "` and still uses demographics only; (d) new `SURVEY_SHORT_LABELS` dict in `opinion.py` fixes the Day-0 rationale bullet bug where `SURVEY_QUESTIONS[pid][:60]` produced six identical-looking labels by truncating inside the shared 84-character preamble; (e) `[P-A] / [P-B] / [C]` tags stripped from in-context reflection bullets (`reflections.csv` keeps them — full audit trail preserved); (f) `compress_memories` rewritten from 2 sentences to 4–5 first-person sentences, phase-agnostic, asking specifically about which messages were compelling vs pushed back on; (g) single-policy `receive_peer_messages` extended with *"about {policy_description}"* to mirror the package variant. Five existing test assertions updated; full suite **403 passing, 1 skipped** (unchanged). New canonical doc `docs/Prompts_and_Personas_Guide_v2.md` (verbatim quotes, real worked example from `data/output/experiments/20260425_082317/`); V1 guide preserved with superseded banner. v0.5 prompt-overhaul section appended to `docs/Model_Design.md` (§20).
- **Per-day broadcast-frequency sugar** — new `cag.abm.sim.make_phases(broadcasts_a, broadcasts_b, peer, interleave, a_first)` helper plus per-day config sugar keys (`broadcasts_a`, `broadcasts_b`, `peer`, `interleave`, `a_first`) for ergonomic political-agent resource-asymmetry experiments. Resolved internally by `_resolve_day_phases`; canonical `phases` list still wins, mixing canonical + sugar in a single day raises `ValueError`. Repeated broadcast tokens (e.g. `["P-A","P-A","P-B","C"]`) fire repeated `run_political_broadcast` calls — same audience subsample, fresh independent LLM message each time. Documented as a new appended section in `docs/Model_Design.md` (§19). 21 new tests (`TestMakePhases`, `TestResolveDayPhases`, `TestPerDayPhaseSugarInRunSimulation`); full suite 403 passing, 1 skipped.
- **Local LLM Provider** — new `provider="local"` branch in `cag.io.llm.send_chat`, routing to any OpenAI-compatible local server (mlx-lm, Ollama, vLLM, sglang, llama.cpp/llama-server, LM Studio). Substring-keyed `_MODEL_REGISTRY` auto-applies sampling presets and per-family quirks (Qwen3 `enable_thinking` toggle, DeepSeek-R1 reasoning defaults, Llama / Apertus / Mistral baselines). Unknown models work with bare defaults and a one-time INFO log.
- **Local-LLM SIM_CONFIG keys** — `local_base_url`, `local_extra_body`, `local_timeout_s` (all optional, with `CAG_LOCAL_BASE_URL` / `CAG_LOCAL_TIMEOUT_S` env-var fallbacks). Added to soft-warn list in `_check_resume_config_compatibility` for checkpoint reproducibility. `_resolve_runtime` calls `configure_local()` and `ping_local()` once at simulation start, so a missing or misconfigured local server fails fast with a remediation message instead of mid-run.
- **Empty-thinking truncation guard** — when a thinking-mode call returns empty content (reasoning budget exhausted), the local provider auto-retries once with thinking disabled and the non-thinking sampling preset, logging a WARNING.
- **`load_api_key("local")` short-circuit** — returns the `"not-needed"` sentinel without touching the CSV or environment, so `provider="local"` works on any machine without API-key plumbing.
- **Mixed-provider workflows** — cheap local broadcasts + high-fidelity cloud surveys are now a documented one-line config (`survey_provider="anthropic"` on top of `llm_provider="local"`). Wiring already supported it; v0.5 makes it explicit and tested.
- **`requirements-local.txt`** — new optional dependency file listing local-runtime extras (mlx-lm on Apple Silicon, vLLM on NVIDIA Linux, Ollama via binary install). Cloud-only users are unaffected.
- **Notebook 24** — first end-to-end local-LLM smoke test (Qwen3 8B 4-bit / mlx-lm / M1 16 GB / Ban Petrol Cars / 10 agents × 1 day). Headline: 0 errors, 46.6 min wall-time, reflections at 133-token median, Day-0 aggregate bias +0.50 (best on record). Full write-up in `docs/result_report.md`.
- **`docs/Local_LLM_Setup_Guide.md` rewritten to V3** — quickstart, alternative backends (mlx-lm / Ollama / vLLM / sglang / llama.cpp), model gallery (Qwen3 / Llama 3.x / Apertus / Mistral / DeepSeek-R1 distills with license + quant + RAM), `SIM_CONFIG` reference, registry-extension recipe, troubleshooting, HPC parallelism notes. V2 / V1 sections retained as legacy.
- **`tests/test_llm_local.py`** — 26 new tests covering dispatcher routing, base-URL / timeout resolution, `MODEL_REGISTRY` lookup, registry injection (Qwen3 thinking on/off, Llama no-extras, unknown model fallback), user `extra_body` override precedence, empty-thinking retry behaviour, and the `load_api_key("local")` short-circuit. Existing 339 tests unchanged.


## [0.4]
- **Package Communication Mode** — `communication_mode="package"` collapses the per-day broadcast and peer-messaging passes into a single phase covering all six climate policies; `compute_package_index()` averages the six responses into a −3..+3 index; new `package_index_trajectories` results DataFrame; `collect_package_ground_truth()` companion to `collect_ground_truth()`; `PACKAGE_SCOPE` sentinel propagated through `assemble_context()` and the survey path
- **Day-0 Ground-Truth Anchoring** — new `day0_anchor` config key with three modes (`llm_survey` | `ground_truth` | `ground_truth_with_rationale`); `seed_opinion_from_ground_truth()` and `seed_opinion_with_rationale()` on `SurveyedCitizen`; `_run_day0()` dispatcher in `sim.py`; `VALID_DAY0_ANCHORS` validation; aligns Day-0 cohort mean exactly with the YouGov sample mean so subsequent drift is attributable to simulation dynamics rather than baseline LLM bias
- **Memory Anchor Refactor** — removed the numeric "Your opinion trajectory so far: Day 0: C, Day 1: E, …" block from `assemble_context()` (strongest LLM self-consistency cue on prior survey answers); replaced with "Your earlier reasoning on these policies:" Day-0 rationale block via new `_build_day0_rationales()` helper; `opinion_history` unchanged at the data layer
- **Checkpoint + Resume** — `run_simulation()` now accepts `checkpoint_dir`, `resume`, and `checkpoint_every_day` parameters. With `checkpoint_every_day=True` a per-day CSV snapshot is written atomically (temp-file + `os.replace`) after each day's `manage_memory` step, capturing all four agent state fields plus `nation.message_log` and a `checkpoint_meta.json` fingerprint. With `resume=True` the run hydrates from the checkpoint, skips Day 0, and continues day numbering from `last_completed_day + 1`. Hard-fails on incompatible structural config (`n_citizens`, `random_seed`, `p_intra`, `p_inter`, `network_type`, `communication_mode`, `package_policies`, `day0_anchor`, agent ID set) and on a `cfg["days"][0:last_completed_day]` prefix mismatch (past days are immutable; future entries may be extended); warns on `llm_model`/`provider`/`debias`/`thinking`/`temperature` changes. `_load_checkpoint` normalises NaN cells to `None` (`df.where(pd.notna(df), None)`) and `_to_policy` early-returns `""` for NaN/None/empty inputs, preventing the literal string `'nan'` from poisoning `messages.csv` `policy_id` cells across multi-cycle resumes in package mode. `agent_ids` in `checkpoint_meta.json` are sorted by `str(...)` for stable on-disk fingerprints. Daily loop body extracted into `_run_one_day()`; `save_results` refactored to share `_write_all_csvs()` with the checkpoint writer (derived share CSVs are produced on every checkpoint as well, making the checkpoint dir drop-in usable as a result dir).
- **Broadcast Reach Controls** — new config knobs `reach_a` and `reach_b` plus `SurveyedNation.apply_reach_subsample()` allow deterministic subsampling of each political agent's broadcast audience before the run starts, enabling controlled asymmetric-reach experiments while preserving reproducibility under `random_seed`.
- **Audience Mirror Control** — new `audience_cap` config key plus `SurveyedNation.apply_audience_cap()` cap each political agent's audience before reach subsampling so symmetric and mirror conditions can be compared on equal-sized audiences; the cap is now part of the resume compatibility surface.
- **Notebooks 16–23** — package-mode, Day-0 anchoring, checkpoint/resume, production full-stack runs, reach-asymmetry pilots, broadcast-only mirror sweeps, Day-0 survey-path audits, and persona-signal evaluation notebooks are now part of the documented v0.4 workflow.
- **Result Documentation** — `docs/result_report.md` now covers the production package-mode run (Run 5 / NB 19), reach-asymmetry experiments (Runs 6–8 / NB 20–21), Day-0 survey-path accuracy audit (NB 22), and persona-signal validation work (NB 23).
- **340 tests collected (339 passed, 1 skipped)** across 15 test files


## [0.3]
- **Baseline Bias Investigation** (NB 11–14) — 6-model comparison showed all LLMs exhibit pro-climate bias (+0.7 to +2.2); third-person prompting was ineffective; 4-condition experiment found Condition D eliminates 97% aggregate bias; multi-policy generalization confirmed for 3 of 4 policies
- **Condition B Debias Integration** — two-step reasoning + anti-sycophancy preamble in `administer_survey()`, activated via `debias=True` config key; preserves original A–G letter scale while reducing aggregate bias by 37–57%
- **Survey Model Override** — `survey_model` / `survey_provider` config keys allow a separate (typically more capable) LLM for baseline and end-of-day surveys while keeping broadcast, peer messaging, and memory on a cheaper model
- **Anthropic Provider Support** — Claude models in `send_chat()` via the `anthropic` library; provider auto-detection from config
- **Extended Thinking Support** — `thinking=True` config key activates adaptive extended thinking for Anthropic models (`max_tokens=16000`)
- **Ground Truth Utility** — `collect_ground_truth()` in `sim.py` extracts each agent's real YouGov survey response for all 6 policies; saved as `ground_truth.csv`
- **Experiment Runs 1–4** — documented in `docs/result_report.md` with per-run configuration, ground truth comparison, bias trajectories, dynamics metrics, and reflections analysis
- **7 new notebooks** (09–15): YouGov EDA, experiment runner, model comparison, 3P prompt, bias mitigation, multi-policy generalization, full simulation + ground truth
- **276 tests** across 15 test files


## [0.2]
- **Climate Policy Opinion System** — 6 policy questions (`ClimatePolicyID`), 7-point response scale, `clamp_opinion_shift()`, shared constants in `opinion.py`
- **LLM Chat Integration** — `send_chat()` wrapper supporting OpenAI and Gemini, `load_api_key()` from CSV, `parse_letter_response()` for survey answers
- **Baseline Survey Administration** — `SurveyedCitizen` class with persona generation, system prompt, and Day 0 LLM-driven survey (`administer_survey()`, `run_baseline()`)
- **Political Agent Class** — `PoliticalAgent` with fixed stance and `generate_message()` for persuasive broadcast content
- **Network + Political Exposure** — `SurveyedNation` with stochastic block model network, exposure assignment from Brexit/UKGE2019 voting history
- **Political Broadcast Phases** — `run_political_broadcast()` implementing Phase P-A / P-B broadcast → citizen reflection cycle
- **Peer Messaging Phase** — `run_peer_messaging()` with simultaneous update: generate all messages first, then deliver and reflect
- **End-of-Day Survey + Clamping** — `administer_survey()` with day-context prompt, `clamp_opinion_shift()` enforcing ±1 per day maximum shift
- **Tiered Memory Architecture** — `assemble_context()`, `compress_daily_memory()`, `compress_weekly_memory()` with configurable intervals and persona reinforcement
- **Simulation Loop + Output** — `run_simulation()` in `sim.py`, `SIM_CONFIG` defaults, CSV/JSON export, panel plot utility in `output.py`
- **8 demo notebooks** (01–08) covering each simulation component
- **226 tests** across 14 test files

### Historical MVP delivery dependencies

The original roadmap organised the ten delivered MVP issues into foundation
(1-2), agents/network (3-5), simulation phases (6-8), memory (9), and loop/output
(10). Its dependency record is retained here for historical context, not as a
current implementation plan:

```text
Issues 1, 2 (independent)
    ├── Issue 3 (depends on 1, 2)
    ├── Issue 4 (depends on 1, 2)
    │       └── Issue 5 (depends on 4)
    │               ├── Issue 6 (depends on 3, 4, 5)
    │               │       ├── Issue 7 (depends on 5, 6)
    │               │       └── Issue 9 (depends on 6)
    │               └── Issue 8 (depends on 3, 6, 7)
    └── Issue 10 (depends on all)
```

## [0.1]
- README.md
- DEVELOPMENT_HISTORY.md
- CHANGE_LOG.md
- ROADMAP.md
- CODE_OF_CONDUCT.md
- DEV_GUIDE.md
- DEV_QUICKSTART.md
- USER_GUIDE.md
- CONTRIBUTORS
- LICENSE
- Makefile
- requirements.txt
- requirements-dev.txt
- docs
- tests
- scripts
- src/cag
- Simple ABM runs.

## Pre-versioning
- Exploratory code in modules and sandbox directories
