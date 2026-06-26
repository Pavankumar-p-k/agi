# JARVIS — Architecture Guide for AI Coding Assistants

This document helps AI coding tools understand the JARVIS codebase structure, conventions, and patterns.

## Phase Status

| Phase | Status | Evidence |
|-------|--------|----------|
| **1** — Infrastructure (browser, build, workflow engine) | **COMPLETE** | All tools working, 59/59 tests, 8/8 durability |
| **2** — Shared Data Plane (context, artifacts, cross-system) | **COMPLETE** | Browser→Build→Email handoff via artifact IDs, 59/59 tests |
| **3** — Planner Layer (templates, decomposition, state machine) | **COMPLETE** | **5/5 benchmarks pass (100%)** — determinism + enforcement proven on qwen2.5:7b |
| **3.2** — Goal Decomposition (parallel features) | **COMPLETE** | Benchmark E: 5 features extracted, email sent, 82.3s |
| **3.2.1** — Hierarchical Decomposition (nested projects) | **COMPLETE** | Benchmark F: depth-2 tree, email sent, 48.8s |
| **4** — Multi-Agent Routing (parallel features) | **COMPLETE** | G5: 100% routing accuracy, G6: 5-agent artifact chain PASS |
| **5** — Activity Graph (persistent long-horizon execution) | **COMPLETE** | 113/113 tests, 8 files: models, storage, manager, recorder, resume engine, planner + workflow hooks |
| **6** — Activity Scheduler (time-driven autonomous continuation) | **COMPLETE** | 20/20 tests, 6 files: scheduler, policies, queue, worker, metrics, models |
| **7.1–7.5** — Research Memory, Knowledge Graph, Planning, Reasoning | **COMPLETE** | 29 unit tests, 20 benchmarks (R1-R5, K1-K5, P1-P5, Reasoning R1-R5) |
| **8.1** — Repository Understanding (indexer, dependency graph, architecture map, impact analyzer) | **COMPLETE** | 31 tests, 4 files in core/coding/ |
| **8.2** — Change Planning (change planner, refactor safety, change simulation) | **COMPLETE** | 28 tests, 3 files in core/coding/ |
| **8.3** — Safe Refactoring (patch generation, import fixing, snapshot/rollback) | **COMPLETE** | 25 tests, 1 file in core/coding/ |
| **8.4** — Architecture Reasoning (scoring, design analysis, tradeoff, migration planning) | **COMPLETE** | 20 tests, 1 file in core/coding/ |
| **14.0** — Principle Discovery (Structural Property Registry, discrimination-based extractor, threshold-gated validator) | **COMPLETE** | 44 tests, 5 files in core/generalization/ |
| **9** — Long-Term Memory & Knowledge Consolidation (experience extraction, knowledge synthesis, behavior adapter, consolidator) | **COMPLETE** | 40 tests, 6 files in core/long_term_memory/ |
| **10** — Adaptive Behavior System (improvement detection, proposal engine, experiment runner, safe promotion, knob store) | **COMPLETE** | 39 tests, 6 files in core/improvement/ |
| **11** — Multi-Agent Collaboration (coordinator, consensus, review, negotiation) | **COMPLETE** | 34 tests, 5 files in core/collaboration/ |
| **11.1** — Collaboration Wiring Fix (coordinator uses ConsensusEngine + NegotiationEngine, canonical flow) | **COMPLETE** | Wired: produce→review→negotiate→consensus→revise/complete |
| **12** — Strategic Reasoning (generator, predictor, evaluator, selector, memory adapter) | **COMPLETE** | 43 tests, 7 files in core/strategy/ |
| **12.6** — Similarity Scoring (evidence quality via goal-activity similarity) | **COMPLETE** | +11 tests, SimilarityScorer in core/strategy/similarity.py |
| **13.0** — Automated Build Adapter (wraps AutomationLoop as tool with ActivityGraph + Calibration + KnowledgeStore) | **COMPLETE** | 30 tests, core/tools/automated_build.py |
| **13.1** — Build Benchmarking & Promotion Framework (compares build_project vs automated_build) | **COMPLETE** | 25 tests, core/coding/build_benchmark.py |
| **14.1** — Proposal Engine (principle→proposal generation + prioritization) | **COMPLETE** | 32 tests in core/generalization/proposals.py + prioritizer.py |
| **14.3** — Causal Filter (confounder-controlled discrimination analysis) | **COMPLETE** | 15 tests in core/generalization/causal.py |
| **14.4** — Derived Property Extraction (aggregate numeric DERIVED properties) | **COMPLETE** | 10 tests in core/generalization/derived.py |
| **15.0** — Proposal Executor (bridges approved proposals → experiments → outcome data points) | **COMPLETE** | 8 tests in core/generalization/executor.py |
| **15.1** — Strategic Reasoning Layer (planner, predictor, tradeoffs, evaluator, selector) | **COMPLETE** | 39 tests, 7 files in core/strategy_v2/ |
| **15.1a** — StrategyExecutor (bridges StrategicDecision → ProposalExecutor → experiment → learning) | **COMPLETE** | 10 tests in core/strategy_v2/executor.py |
| **15.2** — Resource-Constrained Portfolio Optimization (budget-aware knapsack selection, selected + deferred allocation) | **COMPLETE** | 12 tests in core/strategy_v2/portfolio.py |
| **15.2+** — Future Option Value (dependency-aware option value scoring, enables strategies that unlock future improvements) | **COMPLETE** | 8 tests in core/strategy_v2/tradeoffs.py |
| **21** — Opportunity Forecasting (trend analysis, velocity estimation, bottleneck pressure, horizon classification) | **COMPLETE** | 60 tests in core/opportunity/forecasting.py |

**Key empirical finding: planner authority > model size.** With enforcement architecture (Phase 3.3), the same qwen2.5:7b went from 50% → 100% on the original suite + Benchmark E, without any model change.

## Location of Key Files

| Component | Path |
|-----------|------|
| Entry point | `jarvis.py` (simplified CLI: chat, code, build, run, understand, workspace, doctor, models, settings, advanced) |
| CLI commands | `cli_commands.py` |
| CLI request helpers | `cli_requests.py` |
| CLI server management | `cli_server.py` |
| Workspace Intelligence | `core/workspace_manager.py` (WorkspaceManager, ProjectMap) |
| Repository Analysis | `core/repository_analyzer.py` (RepositoryAnalyzer — import graphs, auth, DB, API routes) |
| Agent Orchestrator | `core/agent_orchestrator.py` (unified code/build/run/understand API) |
| Config schema | `core/config_schema.py` |
| Agent loop | `core/agent_loop.py` |
| Tool execution | `core/tools/execution.py` |
| Tool implementations | `core/tools/skill_tools.py`, `settings_tools.py`, `admin_tools.py`, `cookbook_tools.py` |
| Persistent shell | `core/tools/persistent_shell.py` (now captures exit_code, cwd, duration) |
| Skill loader | `core/skill_loader.py` |
| Prompt security | `core/prompt_security.py` |
| SSRF protection | `core/ssrf.py` |
| API key vault | `core/api_key_vault.py` |
| Docker sandbox | `ai_os/docker_sandbox.py` |
| Diagnostics | `core/diagnostics.py` |
| FastAPI app | `core/main.py` |
| Skill index (SKILL.md format) | `core/tools/skill_tools.py` (`do_manage_skills`) |
| Media player | `media/player.py` |
| Voice Engine | `assistant/voice_pipeline.py` (VoiceEngine — replaces VoicePipeline + VoiceLoop) |
| STT providers | `assistant/stt.py`, `assistant/stt_protocol.py`, `assistant/providers/faster_whisper.py`, `deepgram.py`, `azure_speech.py` |
| TTS providers | `assistant/tts.py`, `assistant/tts_protocol.py`, `assistant/providers/kokoro_tts.py`, `edge_tts_provider.py` |
| Wake word | `assistant/wake_word.py` (WakeWordDetector + WakeWordRegistry + WatchdogService) |
| Voice API routes | `core/routes/voice.py` |
| Audio emotion | `core/audio_emotion.py` |
| Voice config | `core/config_registry.py` (voice.* entries lines 91-118) |
| Tests | `tests/unit/` |
| **Browser Planner** | `benchmarks/browser_planner.py` (`BrowserPlanner` — 4 rules: auto-snapshot, search-fill, result-detection, loop-breaker) |
| **Activity Models** | `core/activity/models.py` (ActivityNode, ActivityEdge, ActivityStatus) |
| **Activity Storage** | `core/activity/storage.py` (ActivityStore — SQLite, tree queries, timeline, active/incomplete queries) |
| **Activity Manager** | `core/activity/manager.py` (ActivityManager — create_activity, subgoals, tasks, mark_completed, resume_candidates) |
| **Resume Engine** | `core/activity/resume.py` (ResumeEngine — find resume point, reconstruct context, mark_resumed) |
| **Activity Recorder** | `core/activity/recorder.py` (ActivityRecorder — planner-side recording hook) |
| **Scheduler Models** | `core/scheduler/models.py` (ScheduledActivity dataclass) |
| **Priority Policy** | `core/scheduler/policies.py` (PriorityPolicy — deterministic scoring: priority, urgency, retry, waiting time, user bonus) |
| **Scheduler Queue** | `core/scheduler/queue.py` (SchedulerQueue — dependency-aware activity loading + ranking) |
| **Scheduler Loop** | `core/scheduler/scheduler.py` (Scheduler — async tick loop, picks highest-scored ready activity, delegates to ResumeEngine) |
| **Scheduler Worker** | `core/scheduler/worker.py` (SchedulerWorker — thin bridge from scheduler tick to PlannerStateMachine execution) |
| **Repository Indexer** | `core/coding/repository_indexer.py` (RepositoryIndexer — SQLite-backed file index, import/export extraction, incremental re-index) |
| **Dependency Graph** | `core/coding/dependency_graph.py` (DependencyGraph — transitive deps, reverse deps, circular detection, centrality, DOT export) |
| **Architecture Mapper** | `core/coding/architecture_map.py` (ArchitectureMapper — layer assignment, pattern detection, cross-layer edges, violations) |
| **Impact Analyzer** | `core/coding/impact_analyzer.py` (ImpactAnalyzer — risk scoring, test selection, feature analysis) |
| **Change Planner** | `core/coding/change_planner.py` (ChangePlanner — structured change plans, risk assessment, execution ordering) |
| **Refactor Safety** | `core/coding/refactor_safety.py` (RefactorSafetyEngine — pre-edit safety checks, architecture violations) |
| **Change Simulation** | `core/coding/change_simulation.py` (ChangeSimulation — breakage prediction, conflict detection, test selection) |
| **Refactoring Engine** | `core/coding/refactoring_engine.py` (RefactoringEngine — patch generation, import fixing, snapshot/rollback, recipes) |
| **Research Memory** | `core/research/` — Fact model, FactStore (SQLite), FactExtractor (deterministic text→facts), FactRetriever (multi-source grouping), FactReasoner (contradiction/agreement/gap analysis), FactSynthesizer (structured research reports), benchmark (R1–R5) |
| **Compiler Repair Engine** | `brain/compiler_repair_engine.py` (`CompilerRepairEngine` — 60 error parsers, 22 fix actions, PatternFailureMemory integration) |
| **Compiler Repair Engine** | `brain/compiler_repair_engine.py` (`CompilerRepairEngine` — 60 error parsers, 22 fix actions, PatternFailureMemory integration) |
| **Repair Modules** | `brain/repair_modules/` (7 modules: fix_imports, fix_class_names, fix_manifest, fix_layouts, fix_resources, fix_gradle, fix_dependencies) |
| **Build Output Audit** | `benchmarks/project_build_audit.py` — validates parse coverage across fixture files |
| **Real Repo Recovery** | `benchmarks/real_repo_recovery.py` — end-to-end recovery benchmark against real Android repos |
| **AutoBuild Loop** | `brain/automation/loop.py` (`AutomationLoop` — plan→generate→verify→build→test phase pipeline) |
| **Repair Chaining** | `brain/repair_chaining.py` (`RepairChain` — iterative fix→rebuild→detect→fix with rollback, loop detection, and priority ordering) |
| **Repair Chaining Benchmark** | `benchmarks/repair_chaining_benchmark.py` — validates chain on 4 synthetic projects (2–6 errors) |
| **Pattern Failure Memory** | `core/pattern_failure_memory.py` (`PatternFailureMemory` — JSON-backed, auto-generalization, record_success/record_failure, regex match) |
| **Legacy Failure Memory** | `brain/automation/loop.py` (`FailureMemory` — SQLite-backed, exact/prefix/pattern lookup) |
| **Knowledge Store** | `core/long_term_memory/store.py` (KnowledgeStore — SQLite-backed knowledge_item + experience_summary tables) |
| **Experience Extractor** | `core/long_term_memory/extractor.py` (ExperienceExtractor — compresses completed activity DAGs into ExperienceSummary) |
| **Knowledge Synthesizer** | `core/long_term_memory/synthesizer.py` (KnowledgeSynthesizer — cross-activity pattern detection: domain, tool, failure, principle) |
| **Behavior Adapter** | `core/long_term_memory/adapter.py` (BehaviorAdapter — injects knowledge into planner/research/coding) |
| **Consolidator** | `core/long_term_memory/consolidator.py` (Consolidator — periodic 300s background extraction→synthesis→prune loop) |
| **Improvement Detector** | `core/improvement/detector.py` (ImprovementDetector — scans Phase 9 knowledge for improvement opportunities) |
| **Proposal Engine** | `core/improvement/proposals.py` (ProposalEngine — maps proposals to concrete knob changes) |
| **Experiment Runner** | `core/improvement/experiment.py` (ExperimentRunner — A/B test lifecycle, SQLite-backed experiments) |
| **Safe Promotion** | `core/improvement/promoter.py` (SafePromotion — safety-gated keep/revert with rollback guarantees) |
| **Knob Store** | `core/improvement/knob_store.py` (KnobStore — persistent JSON-backed knob values with bounds enforcement) |
| **Collaboration Models** | `core/collaboration/models.py` (CollaborationSession, ArtifactReview, ConsensusVote, ReviewRound) |
| **Collaboration Coordinator** | `core/collaboration/coordinator.py` (CollaborationCoordinator — session lifecycle, produce→review→revise→complete) |
| **Consensus Engine** | `core/collaboration/consensus.py` (ConsensusEngine — voting, supermajority rules, tiebreaker escalation) |
| **Artifact Reviewer** | `core/collaboration/review.py` (ArtifactReviewer — deterministic pattern-based review checks) |
| **Negotiation Engine** | `core/collaboration/negotiation.py` (NegotiationEngine — position-based merge, concession, escalation) |
| **Strategy Models** | `core/strategy/models.py` (Strategy, Prediction, StrategyDecision, StrategyTag) |
| **Strategy Generator** | `core/strategy/generator.py` (StrategyGenerator — candidate strategies per goal type) |
| **Outcome Predictor** | `core/strategy/predictor.py` (OutcomePredictor — base × modifier heuristics, evidence-based) |
| **Strategy Evaluator** | `core/strategy/evaluator.py` (StrategyEvaluator — deterministic weighted scoring) |
| **Strategy Selector** | `core/strategy/selector.py` (StrategySelector — highest score, tiebreaker, reasoning trace) |
| **Memory Adapter** | `core/strategy/memory_adapter.py` (MemoryAdapter — bridge to ActivityGraph, KnowledgeStore, ResearchMemory, ExperimentResults) |
| **Similarity Scorer** | `core/strategy/similarity.py` (SimilarityScorer — 4-dimensional goal-activity similarity scoring for evidence quality) |
| **Automated Build** | `core/tools/automated_build.py` (do_automated_build, BuildExecutionRecord, _record_activity_nodes, _record_calibration, _record_knowledge) |
| **Build Benchmark** | `core/coding/build_benchmark.py` (run_benchmark, BenchmarkSession, compute_comparison, decide_promotion, get_strategy_prediction) |
| **Structural Property Registry** | `core/generalization/registry.py` (StructuralPropertyRegistry — property definitions + system profiles, SQLite-backed, built-in static & derived properties, 5 bool properties for build tools) |
| **Principle Extractor** | `core/generalization/extractor.py` (PrincipleExtractor — discrimination-based correlation: P(success|prop) - P(success|¬prop), outputs candidates per varying property, supports boolean + numeric median-split extraction) |
| **Principle Validator** | `core/generalization/validator.py` (PrincipleValidator — 5 gates: sample_size>=10, domains>=3, support_rate>=0.70, discrimination>=0.20, confidence>=0.80, configurable thresholds) |
| **Principle Models** | `core/generalization/models.py` (StructuralProperty, SystemProfile, PrincipleDataPoint, PrincipleCandidate, Principle, 5 enum types) |
| **Principle Store** | `core/generalization/store.py` (PrincipleStore — SQLite persistence for data points + principles, save_candidate_as_principle promotion) |

## Key Architecture Rules

1. **NO silent except blocks** — every `except` must log with `logger.warning()` and include `as e`. Zero remaining in live code.
2. **NO shell=True** in `subprocess` calls — always use `shell=False` with a list argument.
3. **ALL API keys** must come from environment variables or `core/config.py`, never hardcoded.
4. **Config** is type-validated by `core/config_schema.py` (`JarvisConfig` pydantic model).
5. **Tools** are registered in `core/tools/execution.py` `_TOOL_HANDLERS` dict — add new tools there plus in `core/tools/index.py` (description), `core/agent_prompts.py` (usage docs), and `core/agent_helpers.py` (ALWAYS_AVAILABLE list).
6. **New primary CLI commands** go in `jarvis.py` via `build_parser()` and `cli_commands.py` as handler functions. Use `core/agent_orchestrator.py` for multi-step code/build/run/understand workflows.
7. **Workspace scanning** should use `core/workspace_manager.py` (os.walk with skip dirs, not rglob) for performance on large projects.

## Adding a New Tool

1. Add implementation function in `core/tools/` (e.g., `skill_tools.py`, `settings_tools.py`)
2. Export it via `core/tools/implementations.py`
3. Add handler + register in `core/tools/execution.py` `_TOOL_HANDLERS`
4. Add doc line in `core/agent_prompts.py`
5. Add index entry in `core/tools/index.py`
6. Add to `ALWAYS_AVAILABLE` in `core/agent_helpers.py` if it should be available in every turn

## Import Convention

- `jarvis_os/` provides `bootstrap.py`, `core/planner.py`, `memory/memory_manager.py` — these are stubs imported by `cli_requests.py`, `api/os_routes.py`, `ai_os/`
- `skills/` contains `{name}.md` (frontmatter + triggers) + `{name}.py` (handler)
- `core/` contains all core logic — no deep nesting beyond 1 level

## Agent-Browser Wiring Fix (June 17, 2026)

The agent pipeline for local Ollama models was broken by **9 bugs** across 6 files. Summary:

| Bug | File | Fix |
|-----|------|-----|
| `TOOL_TAGS` missing all browser tools | `core/tools/_constants.py` | Added 22 browser tool names |
| `_TOOL_NAME_MAP` no browser aliases | `core/tools/parsing.py` | Added 40+ browser tool aliases |
| `_TOOL_SHORTLIST` hardcoded 6 code tools | `core/agent_prompts.py` | Dynamic `_build_tool_shortlist()` |
| `_TOOL_SECTIONS` never injected | `core/agent_prompts.py` | Now appended for relevant tools |
| `_build_base_prompt` passes `set()` for tools | `core/agent_prompts.py` | Changed to `relevant_tools or set()` |
| Graph never calls `route_node` after `think` | `core/graph/__init__.py` | Added `think`→`route` edge |
| `ToolBlock` not imported | `core/agent_helpers.py` | Added import |
| `_cached_skill_index_block` no `global` | `core/agent_prompts.py` | Added `global` declaration |
| `OLLAMA_KEEP_ALIVE=-1` invalid duration | `core/llm_providers.py` | Added keep_alive validation |

**Result:** Pipeline infrastructure works (`setup→think→route→tool_call→dispatch`).  

### Tool Selection Benchmark (June 18-19, 2026)

100 agent-choice tasks across 10 categories (search, read, login, docs, GitHub, shopping, forms, research, learning, multi-page). Every task required a browser tool.

| Approach | Tool Choice | Count | Accuracy |
|----------|------------|-------|----------|
| **Fenced code blocks** (without tool schemas) | `no_tool` | 57/100 | **0%** |
| | `python` | 31/100 | |
| | `bash` | 10/100 | |
| | `browser_*` | 0/100 | |
| **Native function calling** (with tool schemas) | `browser_navigate` | **100/100** | **100%** |

**Root cause confirmed:** `qwen2.5-coder:3b` (and all tested local models) cannot generate ````browser_navigate```` fenced code blocks (0% accuracy). **The fix is to send browser tool schemas via Ollama's native `tools` parameter** — with schemas, `qwen2.5:7b` achieves 100% browser tool selection. The pipeline infrastructure (setup→think→route→tool_call→dispatch) works correctly; the bottleneck was the free-form code block generation format.

**Architectural changes made:**

1. Created `core/tools/schemas_browser.py` — JSON Schema definitions for all 23 browser tools (OpenAI function calling format)
2. Registered in `core/tools/schemas.py` — browser schemas now part of `FUNCTION_TOOL_SCHEMAS`
3. Added browser arg parsing in `function_call_to_tool_block()` — converts structured `{"selector": "...", "text": "..."}` to the content string format expected by handlers
4. Removed `is_api_model` gate in `think_node()` — local Ollama models now receive tool schemas (previously set to `[]`)
5. Fixed Ollama SSE response parser in `llm_core.py` — now detects and normalizes `message.tool_calls` from Ollama responses, converting from Ollama's `{"function": {"name": ..., "arguments": {...}}}` to the normalized `{"name": ..., "arguments": "..."}` format consumed by `_resolve_tool_blocks`

## Current Architecture

```
User
 │
 ▼
 Planner
 │  (auto-snapshot, search-fill, result-detection, loop-breaker)
 ▼
 LLM (tool selection + action planning)
 │
 ▼
 Tool Execution (browser, code, shell, etc.)
 │
 ▼
 Verification
 │
 ▼
 Memory (PatternFailureMemory + FailureMemory, bidirectionally synced)
 │
 ▼
 Learning (success/failure tracking, pattern generalization)
```

## Compiler Repair Pipeline

The `brain/compiler_repair_engine.py` implements a deterministic repair pipeline:

```
Build Output
    ↓
 60 Regex Parsers (javac, AAPT2, Gradle, Room, D8, NDK, Navigation, etc.)
    ↓
 Structured JavacError {file, line, category, symbol, message}
    ↓
 Priority 1: PatternFailureMemory match (exact → regex)
 Priority 2: Deterministic repair rule (~22 action types)
 Priority 3: LLM fallback (last resort)
    ↓
 success → PatternFailureMemory.record_success() → FailureMemory.store()
 failure → PatternFailureMemory.record_failure() (prevents repeat loops)
```

### Build Output Audit (June 20, 2026)

`benchmarks/project_build_audit.py` validates parse coverage against real-world build output:

| Metric | Before | After (4 parsers added) |
|--------|--------|------------------------|
| Parse rate | 73.3% (11/15 files) | **100% (15/15 files)** |
| Total errors parsed | 80 | 90 |
| Unique categories | 26 | 30 |
| False positives | 0 | 0 |
| Taxonomy conformity | 100% | 100% |

**4 gap parsers added**: `d8_duplicate_class`, `kotlin_jvm_target`, `d8_desugar_error`, `ndk_build_error`.

### Repair Chaining (June 20, 2026)

`brain/repair_chaining.py` (`RepairChain`) implements iterative multi-turn repair:

```
Build
  ↓
Parse
  ↓
0 errors? ──Yes──→ Success
  │ No
  ↓
Safety Checks:
  • max_iterations (25) → Stop
  • loop detected (same error signature 3×) → Stop
  • no progress (error count not decreasing) → Stop
  │ Pass
  ↓
Snapshot affected files → Apply Fix #1 → Rebuild → Errors ↓?
  │ No → Rollback → Try next error
  │ Yes → Record Success → Repeat
```

Chaining benchmark (`benchmarks/repair_chaining_benchmark.py`):

| Project | Errors | Fixes | Iterations | Status |
|---------|--------|-------|------------|--------|
| A (2 fixable) | syntax + import | 2/2 | 3 | PASS |
| B (4 fixable) | syntax + LiveData + color + string | 4/4 | 5 | PASS |
| C (1 fixable, 1 unfixable) | syntax + ndk | 1/2 | 3 | PASS |
| D (6 fixable) | syntax + 5 imports/resources | 6/6 | 7 | PASS |

**Key metrics**: 13/14 errors fixed deterministically (93%), 0 rollbacks, 0 loop detections.

### Safety Guards
- `max_iterations` (default 25) prevents infinite loops
- `error_signature()` hashes (file, line, category) sets — if same set seen 3+ times, chain stops
- `max_no_progress_count` (default 2) — if error count doesn't decrease, chain stops
- `FileSnapshot` — backs up .java/.xml/.gradle files before each fix, restores on rollback

### Priority Order
Syntax → imports → build config → resources → structure → class/symbol → Room → Manifest → fallback

Missing: `fix_room.py`, `fix_navigation.py`, `fix_override.py` repair modules (inline implementations exist but lack dedicated modules). Automated tests for engine + repair modules.

## Browser Planner v3 (`core/tools/browser_planner.py`) — June 21, 2026

Moved from `benchmarks/` to production. Integrated into the agent graph as a `plan_node`
between `route` and `tool_call`. The planner is a stateless computation — all state lives
in `AgentState.browser_planner_ctx` (dict), avoiding serialisation issues.

### Integration

```
think → route → plan (pre_plan) → tool_call (execution + post_plan loop) → verify → think
```

| Phase | Location | Rules |
|-------|----------|-------|
| pre_plan | `plan_node` (core/graph/nodes.py) | auto-snapshot after navigate |
| post_plan | `tool_call_node` (core/graph/nodes.py) | search-fill, result-detection, loop-breaker, login-detection |

The post_plan loop runs inside `tool_call_node` with a max of 5 iterations per round.
Each iteration can inject new ToolBlocks (evaluate, fill, press, snapshot) which are
executed immediately via `asyncio.gather` before the next iteration.

### Rules (5)

| # | Rule | Phase | Trigger | Action |
|---|------|-------|---------|--------|
| 1 | auto-snapshot | pre_plan | After `browser_navigate` | Inject `browser_snapshot` |
| 2 | search-fill | post_plan | Search form in snapshot DOM + task has query | Inject `browser_evaluate` (probe) → `browser_fill` + `browser_press(Enter)` |
| 3 | result-detection | post_plan | One turn after search-fill | Check URL/DOM → inject `browser_snapshot` |
| 4 | loop-breaker | post_plan | Same tool sequence ≥3× | Inject `browser_snapshot` |
| 5 | login-detection | post_plan | Email+password fields detected | Inject `browser_snapshot` with note (reports, does not auto-fill) |

### State Lifecycle

- `BrowserPlanner.init(task_prompt)` → initial ctx dict with extracted query
- Created on first round in `plan_node` (from last user message)
- Updated by each `post_plan` call, stored on `AgentState.browser_planner_ctx`
- Survives graph round transitions, serialization, and crash recovery (plain dict)

### Key Files

| File | Role |
|------|------|
| `core/tools/browser_planner.py` | BrowserPlanner class (init, pre_plan, post_plan, helpers) |
| `core/graph/nodes.py:plan_node` | pre_plan integration node |
| `core/graph/nodes.py:tool_call_node` | post_plan loop (max 5 iterations) |
| `core/graph/__init__.py` | Graph wiring: route → plan → tool_call |
| `core/graph/state.py` | `browser_planner_ctx` field on AgentState |

## Legacy Browser Planner (benchmarks/)

The `benchmarks/browser_planner.py` implements 4 deterministic rules that run BEFORE and AFTER each LLM tool call:

| Rule | Phase | Trigger | Action |
|------|-------|---------|--------|
| auto-snapshot | pre_plan | After `browser_navigate` | Inject `browser_snapshot` |
| search-fill | post_plan | Search form detected on page | Inject `browser_fill` + `browser_press` |
| result-detection | post_plan | One turn after search-fill | Check URL/DOM for results → inject `browser_snapshot` |
| loop-breaker | post_plan | Same tool sequence ≥3× | Inject `browser_snapshot` |

The planner lives in `benchmarks/` — move to `core/tools/` for agent pipeline integration when stable.

## Failure Memory (Two Systems, One Interface)

| System | Storage | Scope | Used By |
|--------|---------|-------|---------|
| `PatternFailureMemory` (core/) | JSON file (`~/.jarvis/pattern_failures.json`) | Generalized regex patterns | CompilerRepairEngine, CLI commands |
| `FailureMemory` (brain/automation/) | SQLite (`data/failure_memory.db`) | Exact + prefix + pattern | AutomationLoop legacy fallback |

**Now bidirectionally synced:** Successes/failures from either system feed into the other after each repair cycle. Failed repairs are recorded with `FAILED:` prefix to prevent repeat attempts.

## Browser E2E Benchmark (June 2026)

### Key Findings

| Finding | Evidence |
|---------|----------|
| Tool selection solved | qwen2.5:7b achieves 100% browser tool selection with native function calling |
| Page inspection partially solved | Model reads pages (snapshot) when prompted but not reliably |
| Form interaction unsolved | `browser_fill`/`browser_press` usage near zero across 100 tasks |
| Action planning is the bottleneck | Model navigates once and stops — cannot plan multi-step workflows |

### Planner v2 (4 rules)

| Rule | Phase | Trigger | Action |
|------|-------|---------|--------|
| auto-snapshot | pre_plan | After `browser_navigate` | Inject `browser_snapshot` |
| search-fill | post_plan | Search form detected on page | Inject `browser_fill` + `browser_press` |
| result-detection | post_plan | One turn after search-fill | Check URL/DOM for results → inject `browser_snapshot` |
| loop-breaker | post_plan | Same tool sequence ≥3× | Inject `browser_snapshot` |

### June 25 Fix: Fast Search JS

Replaced 3-attempt multi-pass evaluate probe loop with single-shot `_FAST_SEARCH_JS` that tries 12 common selectors in one call. Results:
- Planner injections -72% (60→17), evaluate probes -80% (40→8)
- llama3.1 planner success doubled (20%→40%)
- Planner accuracy jumped +25% (45%→70%)

### Running the Benchmark

```powershell
$env:MAX_TASKS="10"; $env:USE_PLANNER="1"; python benchmarks/browser_e2e_benchmark.py
```

## Long-Horizon Execution Benchmark (June 25-26, 2026)

`benchmarks/long_horizon_benchmark.py` — 6 multi-phase tasks testing deterministic phase enforcement.

### Results (qwen2.5:7b)

| Config | Phase% | Pass Rate | Injections | Key Finding |
|--------|--------|-----------|------------|-------------|
| raw | 0% | 0% (0/6) | 0 | Model cannot sequence multi-phase projects alone |
| workflow | 76% | 0% (0/6) | 109 | Phase enforcement works but model loops within phases |
| workflow (fixed v2) | 56% | **16.7% (1/6)** | 66 | Auto-inject on loop detection + model-only call tracking |

### Three bugs found and fixed

| Bug | Fix |
|-----|-----|
| `self._phase_index` NameError in `run_task` | Changed `self._phase_index` → `_phase_index` (module-level function) |
| Injected tools pollute loop detection | Added `_model_tool_calls` separate list tracking model calls only |
| Tool loop detector breaks task instead of advancing | Changed to auto-inject next phase tool when 4+ same-tool loop detected |

### Key empirical finding

Phase enforcement jumps phase completion from **0% to 76%** (same pattern as planner enforcement: 0%→100%). The remaining gap is **tool-level looping within phases** — model calls `runtime_validate`/`build_project` 20+ times. Fixed by auto-injecting next phase tool at loop detection.

### Three bugs fixed (June 26, 2026)

| Bug | Fix |
|-----|-----|
| `self._phase_index` NameError in `run_task` | Changed to module-level `_phase_index` variable |
| Injected tools pollute loop detection | Added `_model_tool_calls` separate list tracking model calls only |
| Tool loop detector breaks task instead of advancing | Changed to auto-inject next phase tool when 4+ same-tool loop detected |

### Fixed v2 Results

| Task | Phases Executed | Final Phase | Pass |
|------|----------------|-------------|------|
| research_and_build | 2/7 | validate | FAIL |
| build_test_2 | **7/7** | complete | **PASS** |
| multi_phase_research | 2/7 | research_2 | FAIL |
| research_and_build_2 | 4/7 | validate | FAIL |
| multi_phase_build | 2/7 | build_1 | FAIL |
| long_research_build_test | 3/7 | test | FAIL |
| **Overall** | **~56%** | — | **16.7%** |

## Research Quality Benchmark (June 26, 2026)

`benchmarks/research_quality_benchmark.py` — 2 datasets with ground-truth facts, compares LLM-only (`raw`) vs full Research Pipeline (`pipeline`).

### Results (qwen2.5:7b)

| Config | Recall | Coverage | Contradictions | Hallucinations | Duration |
|--------|--------|----------|---------------|---------------|----------|
| raw | 30.0% | 52.5% | 0 | 58 | 34.4s |
| pipeline | 18.8% | 20.0% | 1 | **0** | **0.1s** |

### Key findings

1. **Pipeline produces ZERO hallucinations** — deterministic extraction is 100% fact-based
2. **Pipeline is 344x faster** (0.1s vs 34.4s) — no LLM latency
3. **Pipeline recall is lower (18.8% vs 30.0%)** — FactExtractor splits entity-attribute connections across sentences
4. **Pipeline found 1 contradiction** (false positive: version release dates) — raw found 0
5. **Tradeoff confirmed**: hallucination-free speed vs LLM's broad recall

### Running

```powershell
$env:AGENT_MODEL="qwen2.5:7b"; python benchmarks/research_quality_benchmark.py
```

## Testing

- `pytest tests/unit/` for unit tests
- `pytest tests/integration/` for integration tests
- Tests must NOT depend on external services — use `mock_external_calls` autouse fixture in `tests/conftest.py`
- Do NOT use the `db_init` fixture unless the test actually needs a database

## Workflow Engine v1.5 (June 21, 2026)

### 1. Timeout Enforcement (`core/workflow/engine.py:_execute_step`)
Each step can specify `timeout_seconds` — `asyncio.wait_for` wraps `execute_tool_block`. On timeout, the step is marked FAILED and retry logic applies.

### 2. Retry Budget (`core/workflow/models.py`, `core/workflow/engine.py`)
Workflow-level `retry_budget` limits total retries across all steps (0 = unlimited). Checked at two points: when entering the retry branch and when deciding whether to `continue` after failure.

### 3. Heartbeat Monitor (`core/workflow/heartbeat_monitor.py`)
Background asyncio task scanning for stale RUNNING/COMPENSATING workflows at configurable interval (default 10s). Stale threshold 60s. Integrates into `core/lifespan.py`.

### Unit Tests
19/19 tests pass (7 failure-mode + 6 compensation + 6 v1.5). 8/8 durability scenarios pass.

## Workflow Engine v2 — Phase 2.1 (June 21, 2026)

### ExecutionContext (`core/workflow/context.py`)

Shared state fabric for multi-step workflows. Each workflow gets an isolated context at `start_workflow()` time.

**ExecutionContext dataclass:**
- `workflow_id`, `owner`, `session_id`
- `variables` — universal key-value dict for step-to-step data passing
- `metadata` — runtime metadata
- `created_at`, `updated_at`

**ContextManager:**
- `create_context()`, `get_context()`, `update_context()`, `delete_context()`
- All CRUD routed through `WorkflowStore` → `workflow_contexts` SQLite table

**Engine integration:**
- Context created in `start_workflow()`, loaded on resume in `_run_workflow()`
- Passed to `_execute_step()` → forwarded to `execute_tool_block()` as optional `context=`
- Survives crash recovery, compensation, heartbeat-driven resume cycles

**`execute_tool_block()`** in `core/tools/execution.py` now accepts `context: Any | None = None` — fully backward compatible. No existing callers modified.

### Success Criteria (all met)

✓ Context survives workflow restart  
✓ Context survives crash recovery (`test_07`)  
✓ Context available inside step execution (`test_06`)  
✓ Context updates persist to SQLite (`test_02`)  
✓ Existing workflows unchanged (19/19 pass)  
✓ Durability benchmark still passes (8/8)  
✓ Context isolation between concurrent workflows (`test_09`)  

### Unit Tests

`tests/unit/test_workflow_context.py` — 9 tests: lifecycle, persistence, crash recovery, engine integration, compensation, isolation. 28/28 total workflow tests pass.

## Workflow Engine v2 — Phase 2.2 (June 21, 2026)

### Artifact Store (`core/workflow/artifact_store.py`)

Filesystem-backed artifact registry. Each artifact gets a SHA-256 checksum, size, type, and metadata.

**ArtifactRef dataclass:**
- `artifact_id`, `workflow_id`, `name`, `artifact_type`
- `path`, `size_bytes`, `checksum`
- `metadata`, `created_at`

**ArtifactStore:**
- `register_artifact()` — persists file metadata, computes checksum
- `get_artifact()` — by ID
- `list_artifacts()` — by workflow_id
- `delete_artifact()` — by ID

### ExecutionContext Extended

`ExecutionContext.artifacts: dict[str, str]` maps names to artifact IDs. Persisted via `artifacts_json` column in `workflow_contexts` table.

### SQLite Tables

`workflow_artifacts` table with index on `workflow_id`.  
`workflow_contexts` extended with `artifacts_json TEXT`.

### Engine Integration

`WorkflowEngine.artifact_store` property provides access.  
`WorkflowEngine.__init__` creates `ArtifactStore(store)`.

### Unit Tests

`tests/unit/test_workflow_artifacts.py` — 9 tests: lifecycle, persistence, crash recovery, isolation, checksum, context integration. 37/37 total workflow tests pass. 8/8 durability scenarios pass.

## Real Repository Recovery Benchmark (June 21, 2026)

5 cloned DataScheduler projects with real injected errors, built with real Gradle 9.5.1 + Android SDK.

| Metric | Result | Target |
|--------|--------|--------|
| Recovery Rate | **80%** (4/5) | >50% |
| Parse Rate | **100%** (14/14) | >95% |
| Avg Iterations | 2.0 | <10 |
| LLM Fallback | 0% | <30% |
| Deterministic Rate | 100% | High |
| Avg Recovery Time | 47s | — |

### Recovery Funnel
```
5 repos → 5 parsed (100%) → 5 categorized (100%) → 5 repairable (100%) → 4 recovered (80%)
```

### 12 bugs found and fixed
Windows path regex (`[\w/]+` → `[\w/\\:.]+`), multi-line parser `\s*\n\s*` → `re.DOTALL` + `.*?`, missing_import too broad (stealing R.* matches), `_create_class` hardcoded `src/main/java`, type_mismatch only handled `=`, `.cmd` shim detection, Unicode encoding, etc.

### Key finding
Structural parameter type changes (e.g., `int hour` → `String hour`) are the only unfixable error class. All other error types (missing layout, import, class, syntax) are 100% fixable deterministically without LLM.

## Workflow Engine v2 — Phase 2.3 (June 21, 2026)

### Build Tool Artifact Integration

Build outputs (APK, AAB, logs, reports, coverage) are automatically registered as artifacts and linked to `ExecutionContext.artifacts`.

**Injection points:**
- `core/tools/execution.py:_hdl_build_project` — after successful build, calls `_register_build_artifacts()` to scan `project_dir` for output files
- `_hdl_repair_project`, `_hdl_run_tests`, `_hdl_runtime_validate` — same pattern
- Artifact refs are stored in step result as `_artifacts` dict

**Engine integration:**
- `core/tools/execution.py:execute_tool_block` now forwards `context` to handlers
- `core/workflow/engine.py:_execute_step` picks up `_artifacts` from successful step results and updates `context.artifacts` via `ContextManager`

**Artifact scanning patterns:**
- `.apk` → type `apk`
- `.aab` → type `aab`
- `build.log` / `.log` → type `build_log`
- `.html` → type `report`
- `coverage.xml` → type `coverage`
- `test-results.xml` → type `test_result`

**Unit Tests:** `tests/unit/test_workflow_build_artifacts.py` — 6 tests: engine registration, failure isolation, project dir scanning, crash recovery, multi-artifact, non-build unaffected. **43/43 total workflow tests pass.** 8/8 durability scenarios pass.

## Workflow Engine v2 — Phase 2.4 (June 21, 2026)

### Browser Artifact Integration

Browser outputs (screenshots, DOM snapshots) are automatically saved to disk and registered as workflow artifacts.

**Implementation:**
- `core/tools/execution.py:_register_browser_artifacts` — module-level helper saves `browser_screenshot` (base64 PNG → `.png`) and `browser_snapshot` (DOM data → `.json`) to `data/workflow_artifacts/{wf_id}/`
- Registered artifacts linked to `ExecutionContext.artifacts` via `_artifacts` result dict (same pattern as build artifacts)
- `_hdl_browser_screenshot` and `_hdl_browser_snapshot` handlers call `_register_browser_artifacts` on success, attaching `_artifacts` to result
- Engine `_execute_step` picks up `_artifacts` and updates `context.artifacts` via `ContextManager`

**Injection points:**
- `browser_screenshot` → artifact type `screenshot`
- `browser_snapshot` → artifact type `html_snapshot`
- Other 21 browser tools (navigate, click, fill, etc.) don't produce artifacts

**Unit Tests:** `tests/unit/test_workflow_browser_artifacts.py` — 5 tests: screenshot artifact, snapshot artifact, error isolation, crash+recovery, multi-artifact. **48/48 total workflow tests pass** (47/48 all-sequential, 1 timing flake in idempotency test). **8/8 durability scenarios pass.**

## Workflow Engine v2 — Phase 2.5 (June 21, 2026)

### Email Artifact Integration

Email attachments accept `artifact:` prefixed references (e.g. `artifact:art_abc123`) resolved to file paths via `ArtifactStore`. Sent emails are registered as `email_sent` artifacts with metadata (to, subject, message_id, timestamp).

**Implementation:**

**`core/tools/email_utils.py`** — Shared `attach_files_to_msg()` utility reads files or binary data and attaches to `EmailMessage`. Used by both the MCP email server and the tool layer.

**`core/tools/schemas_email.py`** — `send_email` schema extended with `attachments: string[]` parameter.

**`core/tools/execution.py`:**
- `_resolve_artifact_attachments()` — module-level function scans attachment list, resolves `artifact:` prefixed strings via `ArtifactStore.get()`, replaces with resolved file path
- `_register_email_artifact()` — module-level function registers sent email as `email_sent` artifact with metadata
- Injected into `mcp__email__send_email` MCP dispatch: resolves artifact refs before the MCP call, registers email artifact after successful send

**`mcp/email_server.py`:**
- `_send_email()` now accepts `attachments` parameter, calls `attach_files_to_msg()`
- MCP `call_tool` handler passes `attachments` from arguments to `_send_email()`

**Resolution flow:**
```
send_email(attachments=["artifact:art_abc123"])
    │
    ▼
_resolve_artifact_attachments → ArtifactStore.get() → file path
    │
    ▼
mcp.call_tool("mcp__email__send_email", args={..., "attachments": ["/resolved/path"]})
    │
    ▼
_attach_files_to_msg → EmailMessage.add_attachment()
    │
    ▼
_register_email_artifact → email_sent artifact → ExecutionContext.artifacts
```

**Unit Tests:** `tests/unit/test_workflow_email_artifacts.py` — 11 tests: artifact ref resolution (valid, invalid, mixed, no-context), email artifact registration, engine end-to-end via mocked MCP, `attach_files_to_msg` file I/O. **59/59 total workflow tests pass.** 8/8 durability scenarios pass.

## Phase 12.6 — Similarity Scoring (June 23, 2026)

`core/strategy/similarity.py` — stateless, deterministic 4-dimensional similarity scorer.

### Scoring Dimensions

| Dimension | Weight | Method |
|-----------|--------|--------|
| goal_type_match | 0.40 | Same category (build/research/refactor/explore) → 1.0, otherwise 0.0 |
| tag_overlap | 0.25 | Jaccard similarity over string tags |
| domain_match | 0.20 | Domain keyword overlap between goal strings |
| text_similarity | 0.15 | Word-overlap (intersection / union of tokens) |

### Key Design

- `score_experience(goal, activity_node)` → `ExperienceScore(similarity, breakdown)` — per-experience scoring
- `filter_and_score(goal, experiences, min_similarity=0.10, max_results=20)` → sorted [(score, exp), ...]
- `classify_goal(goal_text)` → `"build" | "research" | "refactor" | "explore"` — matches StrategyGenerator taxonomy
- MemoryAdapter now scores and filters experiences before assembling EvidenceBundle
- New `avg_similarity` field on `EvidenceBundle` for prediction blending awareness

### Integration

SimilarityScorer is injected into `MemoryAdapter._collect_experience_evidence()`. Each experience from ActivityGraph is scored against the current goal, filtered by `MIN_SIMILARITY=0.10`, and the top `MAX_RESULTS=20` scores contribute to `EvidenceBundle.similar_activities` and `avg_similarity`.

**Backward compatible**: existing callers pass through unchanged — `SimilarityScorer` is a pure function with no state.

### Tests

11 tests (140-150) in `tests/unit/test_strategy.py`: identical goals (140), different goal_type (141), tag overlap (142), domain mismatch (143), filter sorting (144), threshold exclusion (145), max_results cap (146), avg_similarity in bundle (148), goal_type exclusion (149), empty input (150).

## Phase 13.0 — Automated Build Tool (June 23, 2026)

`core/tools/automated_build.py` — wraps `AutomationLoop._build_project()` as a synchronous tool surface.

### Architecture

```
do_automated_build(goal, project_dir)
  │
  ├── BuildPhaseRecord (planning → generation → building → testing → packaging)
  ├── BuildExecutionRecord (phases + artifacts + metrics)
  │
  ├── _record_activity_nodes → ActivityGraph
  │     ├── parent: build_project (type: build_execution)
  │     ├── phase children (type: build_phase)
  │     └── artifact children under packaging phase (type: artifact)
  │
  ├── _record_calibration → CalibrationStore
  │     └── virtual StrategyDecision with predicted/actual metrics
  │
  └── _record_knowledge → KnowledgeStore (via ExperienceExtractor)
```

### Key Design Decisions

1. **No LLM gateway**: Calls `AutomationLoop._build_project()` directly, not through `start() → _run_loop() → _tick()`.
2. **Existing `build_project` untouched**: Parallel registration as `"automated_build"` in `execution.py`.
3. **Typed artifacts**: `_find_build_artifacts()` scans for `.apk` (type: apk), `.aab` (aab), `build.log` (build_log), `*.html` (report), `coverage.xml` (coverage), `test-results.xml` (test_result).
4. **Progress events**: Every phase emits `{execution_id, phase, status, progress, message, timestamp}` for concurrent build isolation.
5. **First autonomous subsystem with full learning feedback**: ActivityGraph + CalibrationStore + KnowledgeStore all updated post-execution.

### Tests

30 tests in `tests/unit/test_automated_build.py`: models (6), artifact scanning (6), progress events (3), ActivityGraph (3), calibration (3), build execution (7), cancellation (1).

## Phase 13.1 — Build Benchmarking & Promotion Framework (June 23, 2026)

`core/coding/build_benchmark.py` — compares `build_project` vs `automated_build` on identical goals.

### Models

| Model | Purpose |
|-------|---------|
| `BenchmarkRun` | Single build execution with method, success, duration, repairs, artifacts, predictions |
| `MetricComparison` | Per-metric comparison (success, duration_seconds, repair_cycles, artifact_count) with `is_tie` support |
| `ComparisonResult` | Aggregated comparison with `overall_score` (positive = automated_build better) |
| `PromotionDecision` | Action (promote_automated/keep_both/inconclusive/promote_build_project) + confidence + reasoning |
| `BenchmarkSession` | Full benchmark: two runs + comparison + promotion decision |

### Comparison Logic

Weighted scoring against 4 metrics:

| Metric | Weight | Higher is Better |
|--------|--------|-----------------|
| success | 0.40 | Yes |
| duration_seconds | 0.30 | No (faster is better) |
| repair_cycles | 0.20 | No (fewer is better) |
| artifact_count | 0.10 | Yes |

`overall_score` = weighted sum of normalized margins per metric. Tie detection uses `is_tie` flag to avoid counting equals as wins.

### Promotion Decision (6 bands)

| Condition | Action |
|-----------|--------|
| adjusted_score > +0.2 | PROMOTE_AUTOMATED |
| adjusted_score < -0.2 | PROMOTE_BUILD_PROJECT |
| abs(adjusted_score) < 0.05 | INCONCLUSIVE |
| otherwise | KEEP_BOTH |

Adjusted score = overall_score + 0.05 capability_bonus (automated_build has repair + richer artifact advantage).

### Tests

25 tests in `tests/unit/test_build_benchmark.py`: models (7), comparison (5), promotion (4), strategy prediction (2), ActivityGraph (2), session (1), integration (3), knowledge store (1).

## Research Quality Benchmark (June 26, 2026)

`benchmarks/research_quality_benchmark.py` — 2 datasets with ground-truth facts, compares LLM-only (`raw`) vs full Research Pipeline (`pipeline`).

### Results (qwen2.5:7b)

| Config | Recall | Coverage | Contradictions | Hallucinations | Duration |
|--------|--------|----------|---------------|---------------|----------|
| raw | 30.0% | 52.5% | 0 | 58 | 34.4s |
| pipeline | 18.8% | 20.0% | 1 | **0** | **0.1s** |

### Key findings

1. **Pipeline produces ZERO hallucinations** — deterministic extraction is 100% fact-based
2. **Pipeline is 344x faster** (0.1s vs 34.4s) — no LLM latency
3. **Pipeline recall is lower (18.8% vs 30.0%)** — FactExtractor splits entity-attribute connections across sentences
4. **Pipeline found 1 contradiction** (false positive: version release dates) — raw found 0
5. **Tradeoff confirmed**: hallucination-free speed vs LLM's broad recall

### Running

```powershell
$env:AGENT_MODEL="qwen2.5:7b"; python benchmarks/research_quality_benchmark.py
```

### Integration Points

- **ActivityGraph**: Full lineage `benchmark_session → strategy_decision → build_project_run / automated_build_run → artifact_children → comparison_result → promotion_decision`
- **CalibrationStore**: Both runs recorded with strategy predictions for prediction-vs-actual learning
- **KnowledgeStore**: Outcome fed via ExperienceExtractor for persistent learning stream
- **Strategy Pipeline**: `get_strategy_prediction()` wires through real `StrategyGenerator → OutcomePredictor → StrategyEvaluator → StrategySelector`

### Tests

25 tests in `tests/unit/test_build_benchmark.py`: models (7), comparison (5), promotion (4), strategy prediction (2), ActivityGraph (2), session (1), integration (3), knowledge store (1).

## Current System Architecture

```
                    Workflow Engine
                           │
                           ▼
                    ExecutionContext
                           │
      ┌────────────────────┼────────────────────┐
      ▼                    ▼                    ▼
   Variables          ArtifactStore         Metadata
      │                    │                    │
      └────────────────────┼────────────────────┘
                           │
     ┌──────────────┬──────┼──────┬──────────────┐
     ▼              ▼      ▼      ▼              ▼
 Browser         Build   Email  Memory      Automation

Cross-subsystem state sharing flows through:
  Tool Output → Artifact → Workflow Context → Another Tool

                  Strategy Pipeline
                         │
               StrategyGenerator
                         │
               OutcomePredictor
                  │       ▲
                  ▼       │
            EvidenceBundle ─── SimilarityScorer ← ActivityGraph
                  │
               StrategyEvaluator → StrategySelector → StrategyDecision
                         │
                         ▼
              [build_project | automated_build]
                         │
              ┌──────────┴──────────┐
              ▼                     ▼
        CalibrationStore    ActivityGraph
                         │         │
                         ▼         ▼
                    KnowledgeStore (ExperienceExtractor)
                         │
                         ▼
                    BehaviorAdapter (Planner/Coding/Research)
                         │
                         ▼
              ImprovementDetector → ProposalEngine → ExperimentRunner → SafePromotion
                         │
                         ▼
                    KnobStore (behavior tuning)
```

## Autonomous Workflow Benchmark (June 21, 2026)

All 4 benchmarks run against qwen2.5:7b with real WorkflowEngine + execute_tool_block dispatch.
Only mocks: Android SDK build targets and SMTP (email).

### Phase 2 Results (No Planner — Baseline)

| Benchmark | Type | Result | Turns | Key Failure |
|-----------|------|--------|-------|-------------|
| A | Research → Build → Validate → Email | **FAIL** | 14 | Never emailed; researched after building; hallucinated 2 tools |
| B | Research → Android APK Delivery | **FAIL** | 4 | No research, no email; stopped after 4 calls |
| C | Long Running Recovery | **PASS** | 3 | Recovery 0.09s; no duplicate execution |
| D | Compensation Stress Test | **PASS** | — | COMPENSATED; both steps rolled back |

### Phase 3 Results (Deterministic Planner + Enforcement)

Planner package (`core/planner/`) integrated with two distinct modes:

**Phase 3a — Re-prompt mode (failed):** Planner detects missing steps and re-prompts the LLM. The model ignores re-prompts. Confirmed: qwen2.5:7b consistently refuses to call `send_email` as a terminal step, even after 14 explicit directives.

**Phase 3b — Enforcement mode (100%):** Planner detects missing steps and enforces them by directly executing the corresponding tool via `PlannerExecutor.inject_task()`. The LLM provides **parameters only** (narrow prompt for to/subject/body); the planner owns the execution decision.

```
# Phase 3a (re-prompt — broken architecture)
Planner → "email still required" → LLM decides → ignores → FAIL

# Phase 3b (enforcement — working architecture)
Planner → inject_task(send_email) → LLM provides args → executor runs → PASS
```

| Benchmark | Phase 2 | Phase 3b | Phase 3.4 SM | Phase 3.2 Goal Decomp |
|-----------|---------|----------|--------------|------------------------|
| A | FAIL | **PASS** | **PASS** | **PASS** |
| B | FAIL | **PASS** | **PASS** | **PASS** |
| C | PASS | **PASS** | **PASS** | **PASS** |
| D | PASS | **PASS** | **PASS** | **PASS** |
| E (Parallel) | — | — | — | **PASS** |
| F (Hierarchical) | — | — | — | **PASS** |
| **Overall** | **50%** | **100%** | **100%** | **100%** |

**Key finding: Planner authority > model size.** The same qwen2.5:7b model went from 50% to 100% without any model change. The only change was architectural: the planner enforces required steps instead of asking the LLM to perform them.

### Benchmark E Detail (Parallel Feature Decomposition)

| Metric | Value |
|--------|-------|
| Goal | "Build coffee shop app with loyalty, payment, admin, customer app, analytics + research + test + email" |
| Features extracted | 5/5 (loyalty system, payment integration, admin dashboard, customer app, analytics) |
| Feature names clean | Yes (no "and" artifacts) |
| Email artifact | `email_sent` |
| Elapsed | 82.3s |
| Tool sequence | build_project → run_tests → browser_navigate → vision_browser → send_email |
| Decomposition quality | 9 sub-goals (1 research, 1 test, 5 features, 1 email, 1 research duplicate) |

**Key additions**: `TOOL_STEP_ALIASES` (`build_project` satisfies both `build` and `apk`), `_find_features` now only scans first sentence, features extracted even in multi-phase goals.

### Benchmark F Detail (Hierarchical Project Decomposition)

| Metric | Value |
|--------|-------|
| Goal | "Build coffee shop platform. Android app (UI, payments, loyalty). Admin dashboard. Analytics. Deploy via email." |
| Top-level components | 5 (Android App, Admin Dashboard, Analytics, Deploy via email, email: send results) |
| Components with children | 1 (Android App → UI, payments, loyalty system) |
| Max depth | 2 (hierarchical) |
| Email artifact | `email_sent` |
| Elapsed | 48.8s |
| Tool sequence | browser_navigate → build_project → run_tests → build_project → send_email |
| Enforced steps | build, test, apk, email |
| Decomposition pass | Both sentence-list and Requirements: formats |
| Features clean | Yes (no "and" artifacts) |

**Key decomposer extensions**: `_find_project_components()` handles three patterns —
"Requirements:" sections (with parenthetical children), "X with Y" sentence patterns,
and sentence-list goals. Two-step split (commas then "and") fixes the bug where
`\s*,\s*` in a single alternation ate the space before "and".

This proves the user's thesis: **the bottleneck was never model capability — it was planner architecture.** A stronger model would likely improve the re-prompt approach but enforcement is necessary regardless of model quality.

### Phase 3b Architecture

| Component | File | Purpose |
|-----------|------|---------|
| `STEP_TO_PRIMARY_TOOL` | `core/planner/executor.py` | Maps abstract step names to concrete tool names |
| `STEP_DEFAULT_ARGS` | `core/planner/executor.py` | Default argument templates per step |
| `get_task_for_step()` | `core/planner/executor.py` | Resolves step→tool with args from plan parameters |
| `inject_task()` | `core/planner/executor.py` | Enforces a step via caller-provided `execute_fn` callback |
| `enforce_step` (benchmark) | `benchmarks/...:run_dynamic` | Narrow LLM prompt for parameters only, then `execute_tool_block` |
| Pattern loop detection | `benchmarks/...:run_dynamic` | Detects repeating sequences of 3-6 tools occurring ≥4× |

**Enforcement flow:**
```
LLM stops early
    ↓
Planner.check_early_termination() → missing = ["email"]
    ↓
for step in missing:
    enforce_step(tool="send_email", default_args={"to": ..., ...})
        ↓
    LLM asked ONLY for parameters ("provide to, subject, body")
    LLM provides args → ToolBlock constructed → execute_tool_block()
        ↓
    Planner.record_step(step, success=True)
    ↓
Planner.is_workflow_complete() → True
```

### Infrastructure vs Planner Pass Rate (All Phases)

| Layer | Phase 2 | Phase 3a | Phase 3b | Interpretation |
|-------|---------|----------|----------|----------------|
| Infrastructure (C+D) | **100%** | **100%** | **100%** | Recovery, compensation, artifact store proven |
| Planner (A+B) | **0%** | **0%** | **100%** | Enforcement architecture solves multi-step gap |

### Key Insight: Planner Authority > Model Quality

Proven: **planner authority** is the missing architectural layer, not model size.

Before: `LLM → decides what to do → may or may not execute`
After: `Planner → decides what to do → LLM fills params → executor runs`

**This is the architecture conclusion of Phase 3:** The planner must own the workflow sequence. The LLM should only parameterize individual steps. Any design where the LLM can veto a required workflow step is architecturally broken for autonomous multi-step workflows.

### Next Steps

With 100% pass rate on qwen2.5:7b, the infrastructure + planner layers are proven. Next priorities:

1. **Multi-model benchmark** — run Phase 3b against `gemma4:e4b`, `mistral:7b`, `llama3.1:8b` to confirm model-independent
2. **Goal decomposition (Phase 3.2)** — break "Build Android coffee shop app and email the APK" into sub-goals automatically
3. **Multi-agent (Phase 3.5)** — dedicated agents for research, build, email under master planner
4. **Activity graph memory** — long-term personal OS memory (projects, builds, emails, sessions)

### 7 Infrastructure Bugs Found and Fixed During Phase 2 Benchmark Setup

| Bug | File | Fix |
|-----|------|-----|
| RBAC blocked `owner="bench"` | benchmark | Changed to `owner="dev"` |
| `recover_active_workflows` returns dicts not objects | benchmark | Fixed `w["workflow_id"]` access |
| `WorkflowStatus.CREATED` doesn't exist | benchmark | Changed to `PENDING` |
| Unicode chars crash Windows cp1252 console | benchmark | Replaced `≥`/`→` with ASCII |
| CORE_MAPPING can't parse JSON content from engine steps | `core/tools/execution.py` | Added JSON fallback in `_resolve_tool_path` dispatch |
| Email tool names not mapped to MCP prefix in engine dispatch | `core/tools/execution.py` | Added `_BARE_EMAIL_TOOLS` mapping |
| `/tmp/report.md` path fails on Windows | benchmark | Changed to `data/` path |

### Classification System for Future Runs

Failures should be classified into one of three categories:

1. **Infrastructure Failure** — engine, store, dispatch, or recovery bug
2. **Planner Failure** — missing steps, wrong order, hallucinated tools, early stop
3. **Model Capability Failure** — model cannot perform the reasoning required even with correct planning

Current classification for qwen2.5:7b: all planner failures.

### Key Files

- `benchmarks/autonomous_workflow_benchmark.py` — 4 benchmarks in one file
- `benchmarks/browser_automation_benchmark.py` — 15 browser tasks, 3 configs, 3 models tested (June 25)
- `benchmarks/long_horizon_benchmark.py` — 6 multi-phase tasks, phase state machine enforcement (June 25-26)
- `benchmarks/research_quality_benchmark.py` — LLM-only vs pipeline comparison with ground-truth facts (June 26)
- `benchmarks/ablation_benchmark.py` — Component ablation: Full vs No-Planner vs No-Memory vs No-Scheduler vs No-Belief vs No-Negotiation
- `benchmark_reports/autonomous_qwen2.5_7b.json` — saved report for model comparison

## Current Architecture

```
User
 │
 ▼
 Planner (templates + decomposition + state machine)
 │
 ▼
 Agent Router (find_best_agent_for_subgoal)
 │
 ▼
 Agent Graph (parallel execution + artifact handoff)
 │
 ▼
 Workflow Engine (durable steps, retry, compensation)
 │
 ▼
 Artifact Store (checksummed, survivable)
 │
 ▼
 Activity Graph (ActivityManager → ActivityRecorder)
 │    │
 │    ├── Subgoals
 │    ├── Agent tasks
 │    ├── Tool calls
 │    ├── Artifact lineage
 │    └── Execution timeline
 │
 ▼
 Resume Engine (find incomplete leaf → reconstruct context)
 │
 ▼
 Memory (PatternFailureMemory + FailureMemory)
 │
 ▼
 Verification (artifact-driven checks)
```

## Maturity Assessment (June 26, 2026)

| Subsystem | Score | Notes |
|-----------|-------|-------|
| Tool Infrastructure | 9/10 | Mature |
| Workflow Engine | 9/10 | Durable, recoverable, compensation, retry |
| Recovery & Durability | 9.5/10 | 0.09s recovery, 8/8 durability, no duplicates |
| Compensation Layer | 9/10 | Reverse-order rollback proven |
| ExecutionContext | 8.5/10 | Shared state across steps, survives crash |
| Artifact Store | 9/10 | Checksummed, survivable, cross-system refs |
| Cross-System Integration | 8/10 | Browser→Build→Email via artifact IDs |
| Memory | 9/10 | Bidirectional PatternFailureMemory + SQLite |
| Voice | 7/10 | STT/TTS pipeline |
| Browser Automation | 8/10 | 23 tools, planner driver (auto-snapshot, search-fill, loop-breaker) |
| Planner State Machine | 9.5/10 | PLAN→DECOMPOSE→ROUTE→EXECUTE→VERIFY→COMPLETE |
| Goal Decomposition | 9/10 | 5-feature parallel + hierarchical depth-2 extraction |
| Multi-Agent Coordination | 8/10 | Agent graph, dependency edges, artifact handoff |
| Activity Graph | 8.5/10 | Persistent DAG: goals, subgoals, agents, tools, artifacts |
| Long-Horizon Execution | 6/10 | Phase enforcement proven (76%), tool-looping gap exposed |
| **Activity Scheduler** | **8/10** | Core loop, policy, queue, worker, metrics all passing |
| **Repository Understanding** | **8.5/10** | Indexer, dependency graph, architecture mapper, impact analyzer (31 tests) |
| **Strategic Reasoning** | **7.5/10** | Strategy pipeline + similarity scoring (105 tests, 8 files) |
| **Automated Build** | **8/10** | First subsystem with full ActivityGraph + Calibration + KnowledgeStore learning loop |
| **Build Benchmark** | **7/10** | Comparison framework + promotion decisions fully wired, no multi-sample statistics yet |
| **Principle Discovery** | **7/10** | Registry + extractor + validator + store proven, no cross-domain proposal engine yet |
| **Research Pipeline** | **8/10** | FactStore, extractor, retriever, reasoner, synthesizer all tested (29 unit, 20 benchmarks) |
| **Research Quality** | **7/10** | Hallucination-free but recall lower than LLM; entity-attribute splitting is biggest gap |
| **Browser Workflow Automation** | **5/10** | Multi-step browser tasks still near zero; planner helps but action sequencing unsolved |
| **Benchmark Infrastructure** | **8/10** | 5 benchmarks covering browser, long-horizon, research quality, autonomous workflow, ablation |

## What Phase 5 Actually Changed

Before:

```
Goal
 ↓
Execute
 ↓
Artifacts
```

After:

```
Activity
 │
 ├── Goal
 │
 ├── Subgoal A
 │     ├── Agent
 │     └── Artifacts
 │
 ├── Subgoal B
 │     ├── Agent
 │     └── Artifacts
 │
 └── Workflow
        ├── Steps
        ├── Results
        └── Resume Point
```

Now JARVIS can answer:
- What was I doing yesterday?
- Which agent produced this artifact?
- Which workflow created this APK?
- What failed?
- Where should execution resume?
- What tasks are still incomplete?

## Phase 8.1 — Repository Understanding (June 22, 2026)

Four files in `core/coding/` that build a deep understanding layer on top of the existing `WorkspaceManager` and `RepositoryAnalyzer`:

| Component | File | Purpose |
|-----------|------|---------|
| **RepositoryIndexer** | `core/coding/repository_indexer.py` | Persistent SQLite-backed file index. Walks source files, extracts imports/exports/class names/function names per language (Python, JS/TS, Java, Kotlin, Rust, Go). Incremental re-index via mtime comparison. |
| **DependencyGraph** | `core/coding/dependency_graph.py` | Builds on indexer: resolves relative and dotted imports to indexed paths. Computes fan-in, fan-out, centrality (fraction of nodes reachable via reverse traversal). Finds circular dependencies via DFS. Exports Graphviz DOT format. |
| **ArchitectureMapper** | `core/coding/architecture_map.py` | Assigns every file to a layer (controllers/services/models/repositories/config/utils/tests) based on directory conventions. Detects architectural pattern (layered, MVC, hexagonal, microservices, monolith). Reports cross-layer dependency edges and violations. |
| **ImpactAnalyzer** | `core/coding/impact_analyzer.py` | Given a changed file, finds all directly and transitively affected files via dependency graph reverse traversal. Computes risk score from fan-in (30%), transitive impact (25%), centrality (15%), layer risk (20%), and test coverage bonus (-10%). Suggests relevant test files. |

### Key Design Decisions

1. **Single database**: `data/repo_index.db` — independent from `data/workflow.db` to avoid coupling with activity/research tables.
2. **Deterministic language parsers**: No LLM — pure regex-based import/export extraction for Python, JS/TS, Java, Kotlin, Rust, Go.
3. **Path normalization**: All paths normalized to forward slashes for cross-platform consistency.
4. **Pipeline**: `RepositoryIndexer → DependencyGraph → ArchitectureMapper → ImpactAnalyzer` — each builds on the previous.

### Tests

31 tests in `tests/unit/test_coding.py`: indexing (9), dependency graph (8), architecture mapping (6), impact analysis (8 coverage).

### Phase 8.1 Overall

> **Coding Intelligence:** 7/10 → **8.5/10** (+1.5)

## Phase 8.4 — Architecture Reasoning (June 22, 2026)

`core/coding/architecture_reasoning.py` — deterministic architecture analysis across 4 components.

| Component | Purpose |
|-----------|---------|
| **ArchitectureScorer** | Quantifies coupling (avg fan-out), cohesion (module-exclusive exports ratio), maintainability (inverse of complexity score), stability (1 - fan_out/(fan_in+fan_out)), layer discipline (allowed cross-layer edge ratio). Overall = average. |
| **DesignAnalyzer** | Detects 5 weakness categories: god files (>=5 exports + >=5 dependents), hub modules (fan-in >=75th percentile), fragile files (fan-out >=75th percentile), circular dependency groups, layer violations. Produces DesignReport with score, weaknesses, migration suggestions, summary. |
| **TradeoffEngine** | Compares current pattern against 5 alternatives (hexagonal, mvc, monolith, layered, modular_monolith). Uses 6 weighted dimensions with hardcoded pattern profiles (maintainability 0.25, coupling 0.20, cohesion 0.20, complexity 0.15, stability 0.10, scalability 0.10). Returns TradeoffComparison with scored alternatives, recommended pattern, rationale. |
| **MigrationPlanner** | Converts StepSuggestion objects from DesignAnalyzer.migration_suggestions into ChangePlan via ChangePlanner. Multi-step migration plans ordered by safety. |

### Tests

20 tests in `tests/unit/test_coding_architecture.py`: scoring (3), design analysis (6), tradeoff (6), migration (3), dataclass roundtrips (2).

### Phase 8.4 Overall

> **Coding Intelligence:** 8.5/10 → **9/10** (+0.5)

The Phase 8 pipeline now spans 4 layers:

```
RepositoryIndexer (8.1) → DependencyGraph (8.1) → ArchitectureMapper (8.1) → ImpactAnalyzer (8.1)
    → ChangePlanner (8.2) → RefactorSafetyEngine (8.2) → ChangeSimulation (8.2)
    → RefactoringEngine (8.3) → ArchitectureScorer (8.4) → DesignAnalyzer (8.4)
    → TradeoffEngine (8.4) → MigrationPlanner (8.4)
```

**104 total coding tests + 40 memory tests + 39 improvement tests + 29 research tests + 44 generalization tests = 256 total passing.**

**Key finding:** The gap has shifted from editing files to design reasoning. JARVIS can now answer "Should this be microservices?", "Where should this feature live?", and "What architecture minimizes future risk?" — all deterministically, without LLM dependency.

## Phase 9 — Long-Term Memory & Knowledge Consolidation (June 22, 2026)

`core/long_term_memory/` — 6 files, bridges the 4 disjoint memory systems into a durable knowledge layer.

### Architecture

```
Activity Graph
        │
        ▼
ExperienceExtractor
        │  (compresses completed activity DAGs into ExperienceSummary)
        ▼
KnowledgeSynthesizer
        │  (cross-activity pattern detection: domain patterns, tool patterns,
        │   failure patterns, principles)
        ▼
KnowledgeStore (SQLite — extends workflow.db)
        │
        ▼
BehaviorAdapter
        │
        ├──→ Planner (for_planner)
        ├──→ Research (for_research)
        └──→ Coding (for_coding)
```

### Four-Layer Condensation

| Layer | What | Count |
|-------|------|-------|
| **Activities** | Raw DAG nodes in activity graph | 1000 |
| **Experiences** | Compressed activity summaries (ExperienceSummary) | 100 |
| **Knowledge Items** | Structured knowledge (KnowledgeItem) | 50 |
| **Principles** | Highest-confidence generalizations | 10 |

### Components

| Component | File | Purpose |
|-----------|------|---------|
| **KnowledgeStore** | `core/long_term_memory/store.py` | SQLite-backed CRUD for KnowledgeItem + ExperienceSummary. Lives in same DB as activity graph and research facts. Tables: `knowledge_items`, `experience_summaries`. |
| **ExperienceExtractor** | `core/long_term_memory/extractor.py` | Walks completed ActivityGraph trees, counts nodes/tools/agents/errors, infers domain from goal+tool keywords, computes outcome quality. |
| **KnowledgeSynthesizer** | `core/long_term_memory/synthesizer.py` | Cross-activity synthesis: domain success-rate patterns, tool-success heuristics, failure-mode warnings (including PatternFailureMemory merge), overall principles. Requires MIN_EVIDENCE_FOR_PATTERN=2, MIN_EVIDENCE_FOR_PRINCIPLE=3. |
| **BehaviorAdapter** | `core/long_term_memory/adapter.py` | Three query points: `for_planner(goal, domain)` → patterns+warnings+heuristics for prompt injection; `for_research(question)` → known claims + confidence gaps; `for_coding(file, type)` → risk modifiers. |
| **Consolidator** | `core/long_term_memory/consolidator.py` | Periodic background loop (default 300s). Each cycle: extract new experiences → run synthesis → prune stale low-confidence items (90 days, <0.4 confidence). |

### Data Flow

```
Consolidator (every 5 min)
         │
         ▼
ExperienceExtractor.extract_all_completed()
    → inserts new ExperienceSummary rows
         │
         ▼
KnowledgeSynthesizer.synthesize_from_experiences()
    → inserts new KnowledgeItem rows
         │
         ▼
KnowledgeStore.prune_stale()
    → deletes unvalidated low-confidence items >90 days old
```

### KnowledgeItem Schema

| Field | Type | Description |
|-------|------|-------------|
| `knowledge_id` | TEXT PK | UUID-based |
| `category` | TEXT | pattern, principle, heuristic, factoid, warning |
| `claim` | TEXT | What was learned |
| `confidence` | REAL | 0.0–1.0 statistical confidence |
| `evidence_count` | INT | Number of supporting experiences |
| `source_activity_ids` | JSON | Activity IDs that contributed |
| `source_pattern_keys` | JSON | PatternFailureMemory keys |
| `tags` | JSON | For filtering (domain, tool, etc.) |
| `last_validated` | TEXT | Most recent confirmation timestamp |

### Integration Points

- **Planner**: `BehaviorAdapter.for_planner()` returns domain patterns + failure warnings → injected into planner prompt
- **Research**: `BehaviorAdapter.for_research()` returns known claims + confidence gaps → can short-circuit research if sufficient confidence
- **Coding**: `BehaviorAdapter.for_coding()` returns risk modifiers → can augment ImpactAnalyzer scores

### Tests

40 tests in `tests/unit/test_long_term_memory.py`: models (4), store (13), extractor (7), synthesizer (5), adapter (5), consolidator (6).

### Phase 9 Overall

> **Memory:** 4/10 → **7.5/10** (+3.5)
> **Learning:** 3/10 → **5.5/10** (+2.5)

Phase 9 is the foundation for self-improvement (Phase 10). Knowledge consolidation bridges the gap between raw activity history and behavior-influencing knowledge, but does not yet close the loop to automatic behavior change.

## Phase 10 — Adaptive Behavior System (June 22, 2026)

`core/improvement/` — 6 files, closes the loop from accumulated knowledge to measurable behavior change.

### Architecture

```
KnowledgeStore (Phase 9)
        │
        ▼
ImprovementDetector
        │  (scans for patterns: "domain X has low success rate",
        │   "errors correlate with failures", "tool Y is risky")
        ▼
ImprovementProposal
        │
        ▼
ProposalEngine
        │  (converts proposals to concrete KnobChange objects)
        ▼
ExperimentRunner
        │  (A/B test: control vs candidate, measures metrics)
        ▼
SafePromotion
        │
   ┌────┴────┐
   ▼         ▼
Promote    Reject
   │         │
   ▼         ▼
Apply to   Discard
KnobStore
```

### Components

| Component | File | Purpose |
|-----------|------|---------|
| **Models** | `core/improvement/models.py` | BehaviorKnob (typed, ranged, auditable parameter), ImprovementProposal, Experiment, KnobChange, MetricComparison, ExperimentResult. KNOB_REGISTRY with 11 pre-defined knobs. |
| **KnobStore** | `core/improvement/knob_store.py` | JSON-backed persistent knob storage with clamping, bounds enforcement, snapshot/rollback, and persistence across restarts. Uses RLock for thread safety. |
| **ImprovementDetector** | `core/improvement/detector.py` | Reads KnowledgeStore for domain warnings, failure patterns, tool risks, and high-confidence principles. Produces ImprovementProposal objects with confidence scores. |
| **ProposalEngine** | `core/improvement/proposals.py` | Maps proposal categories to concrete knob changes. Configurable _RESOLUTION_MAP decides which knobs to adjust and by how much. |
| **ExperimentRunner** | `core/improvement/experiment.py` | Full A/B test lifecycle: create → start (snapshot + apply changes) → complete (measure + rollback). All experiments stored in `workflow.db` experiments table. |
| **SafePromotion** | `core/improvement/promoter.py` | Safety-gated keep/revert. Rejects if no improvement, critical regressions (>5% per metric), or no metrics. Promoted changes survive restarts. |

### Behavior Knobs (11 pre-defined)

| Knob | Category | Default | Range | Purpose |
|------|----------|---------|-------|---------|
| `research.min_sources` | RESEARCH | 2 | 1–10 | Minimum sources per research task |
| `coding.simulation_required` | CODING | False | bool | Gate refactors behind ChangeSimulation |
| `coding.safety_threshold` | CODING | 0.7 | 0.0–1.0 | Risk threshold for safety gate |
| `planner.inject_domain_patterns` | PLANNER | True | bool | Inject Phase 9 domain patterns into planner |
| `planner.inject_failure_warnings` | PLANNER | True | bool | Inject Phase 9 failure warnings into planner |
| `synthesizer.min_evidence_pattern` | SYNTHESIZER | 2 | 1–10 | Min evidence for pattern knowledge |
| `synthesizer.min_evidence_principle` | SYNTHESIZER | 3 | 2–20 | Min evidence for principle knowledge |
| `synthesizer.high_confidence_threshold` | SYNTHESIZER | 0.8 | 0.5–1.0 | Success rate for positive pattern detection |
| `scheduler.urgency_bonus` | SCHEDULER | 30 | 0–100 | Priority bonus for pending/running |
| `scheduler.retry_bonus` | SCHEDULER | 50 | 0–100 | Priority bonus for failed activities |
| `scheduler.waiting_bonus_per_minute` | SCHEDULER | 2 | 0–20 | Per-minute waiting time bonus |

### Data Flow

```
Consolidator (Phase 9, every 5 min)
    │
    ▼
KnowledgeStore (patterns, warnings, principles)
    │
    ▼
ImprovementDetector.detect_all()
    │  (on each scheduler tick or manual trigger)
    ▼
ProposalEngine.evaluate_all(proposals)
    │
    ▼
ExperimentRunner.create() + start()
    │  (snapshot current knobs, apply candidate changes)
    │
    ├── Control workflows run with old values
    └── Candidate workflows run with new values
    │
    ▼
ExperimentRunner.complete()
    │  (rollback candidate values, compute metrics)
    ▼
SafePromotion.evaluate(result)
    │
    ├── Accepted → promote() (re-apply candidate values permanently)
    └── Rejected → reject() (candidate already rolled back)
```

### Safety Guarantees

1. **No source code modification** — only configuration-level knob values
2. **Automatic rollback** — ExperimentRunner always rolls back after measurement
3. **Critical regression gate** — SafePromotion rejects if any metric regresses >5%
4. **Evidence requirement** — only promotes when overall improvement is proven
5. **Snapshot recovery** — KnobStore supports full-state restore
6. **Experiments table** — all experiments persisted in workflow.db for audit

### Tests

39 tests in `tests/unit/test_improvement.py`: models (5), knob store (12), detection (5), proposals (4), experiment (6), promotion (7).

### Phase 10 Overall

> **Learning:** 5.5/10 → **8.5/10** (+3.0)
> **Memory:** 7.5/10 → **8.5/10** (+1.0)
> **Coding:** 9.1/10 → **9.3/10** (+0.2)
> **Research:** 9.1/10 → **9.3/10** (+0.2)

Phase 10 closes the loop that Phase 9 opened. JARVIS now not only accumulates knowledge — it can test whether that knowledge improves behavior, and permanently adopt changes that work. The system still cannot modify its own source code, but it can adjust 11 tuneable parameters based on measured outcomes.

## Phase 14.0 — Principle Discovery (June 23, 2026)

`core/generalization/` — 5 files, extracts causal principles from experimental evidence.

### Three-Layer Architecture

**Layer 1 — Structural Property Registry** (`registry.py`): Stores tool→properties mappings. 9 built-in properties (5 static: `retry_capable`, `repair_capable`, `verification_builtin`, `stateful`, `has_failure_memory`; 4 derived: `avg_retry_count`, `avg_repair_count`, `artifact_count`, etc.). Supports hybrid static+derived model so the system can discover properties humans didn't label. Default profiles for `build_project` (all False) and `automated_build` (all True).

**Layer 2 — Principle Extractor** (`extractor.py`): Consumes experimental data points (properties + outcomes) and finds correlations. Uses discrimination formula: `P(success|property=True) - P(success|property=False)`. Only produces candidates for properties that actually vary (both True and False exist in dataset). Supports boolean properties directly and numeric properties via median-split.

**Layer 3 — Principle Validator** (`validator.py`): Gates candidate principles through 5 thresholds before acceptance:
- `sample_size >= 10` — enough experiments
- `domains >= 3` — applies across contexts
- `support_rate >= 0.70` — property-true group succeeds consistently
- `discrimination >= 0.20` — meaningful separation from control group
- `confidence >= 0.80` — statistical confidence (computed from sample size, discrimination strength, domain diversity)

### Key Design Decisions

1. **Discrimination over correlation**: The validator doesn't ask "do successful systems have property X?" It asks "does property X meaningfully separate successful and unsuccessful systems?" This prevents weak correlations from becoming false principles.
2. **No LLM**: Pure statistical analysis — the extractor and validator are deterministic functions with no AI dependency.
3. **Hybrid properties**: Static (declared by developers) + Derived (computed from ActivityGraph data). Derived properties enable discovery without human labels.
4. **save_candidate_as_principle**: Promotion is an explicit action — candidates persist as their own record type until validated.

### Expected Output

After enough benchmark runs:
```
Principle P-001
  Property: verification_builtin
  Support:  91%  Control: 58%  Discrimination: 33%
  Domains:  build  Evidence: 24 experiments  Confidence: 0.89

Principle P-002
  Property: retry_capable
  Support:  87%  Control: 52%  Discrimination: 35%
  Domains:  build  Evidence: 24 experiments  Confidence: 0.92
```

The system no longer says "automated_build won." It says "verification and retry behavior predict success."

### Phase 14.1 (Next)

- Proposal engine that consumes accepted principles to suggest architectural changes (e.g., "browser_tool lacks retry → propose browser_tool_v2")
- Cross-domain validation (principles discovered in build domain tested in browser/research domains)
- Multi-sample statistical rigor before principle acceptance

### Tests

44 tests in `tests/unit/test_generalization.py`: models (8), registry (9), extractor (7), validator (10), store (7), integration (3).

## Phase 6 — Activity Scheduler (June 22, 2026)

The biggest remaining architectural gap: JARVIS can resume a single activity but cannot manage multiple
concurrent activities with scheduling priorities.

### Architecture

```
                 Scheduler
                      │
                      ▼
             PriorityPolicy
                      │
                      ▼
            ResumeEngine
                      │
                      ▼
         PlannerStateMachine
                      │
                      ▼
                Agent Graph
                      │
                      ▼
              Workflow Engine
                      │
                      ▼
              Activity Graph
```

### Design Decision

The scheduler is deliberately narrow. It only decides WHAT to run next.
The HOW is delegated entirely to existing infrastructure:

```python
while running:
    activities = activity_manager.get_active_activities()
    ranked = priority_policy.rank(activities)
    next_activity = ranked[0]
    resume_engine.resume(next_activity.id)
    await asyncio.sleep(tick_interval)
```

### Key Features

1. **Activity Registry** — list of all activities with status, priority, dependencies
2. **Priority Policy** — deterministic scoring (priority, urgency, retry, waiting time, user bonus)
3. **Dependency Resolution** — defer activities until their artifact dependencies are met
4. **Autonomous Continuation** — system decides WHEN to resume, not just HOW

### Priority Engine

Deterministic scoring (no AI):

```
score = priority_weight + urgency_weight + retry_weight
        + waiting_time_bonus + user_requested_bonus
```

| Factor | Weight | Purpose |
|--------|--------|---------|
| Priority (0-5) | 0, 20, 40, 60, 80, 100 | Manual priority level |
| Urgency | +30 | Ready/running gets boost |
| Retry (failed) | +50 | Failed attempts get retry priority |
| Waiting time | +2/min | Stale activities rise over time |
| User requested | +80 | User goals over subgoals |

### Files

| File | Purpose |
|------|---------|
| `core/scheduler/models.py` | `ScheduledActivity` dataclass |
| `core/scheduler/policies.py` | `PriorityPolicy` — deterministic scoring |
| `core/scheduler/queue.py` | `SchedulerQueue` — dependency-aware loading |
| `core/scheduler/scheduler.py` | `Scheduler` — async tick loop |
| `core/scheduler/worker.py` | `SchedulerWorker` — resume → planner bridge |
| `core/scheduler/metrics.py` | `SchedulerMetrics` — telemetry |

### Acceptance Criteria (all passing)

1. Submit 3 activities — scheduler executes highest-scored first
2. Activity with unmet dependency stays BLOCKED
3. Completed/failed activities are excluded from the ready list
4. Scheduler runs as background asyncio task with configurable tick interval
5. Resume engine finds correct resume point automatically
6. No new planner, router, or workflow engine created

## Phase 8.2 — Change Planning (June 22, 2026)

Three files in `core/coding/` that build on Phase 8.1 to plan, validate, and simulate code changes before any file is touched.

| Component | File | Purpose |
|-----------|------|---------|
| **ChangePlanner** | `core/coding/change_planner.py` | Takes file-level change decisions (create/modify/delete/rename) and produces a structured ChangePlan with ordered execution phases, per-step risk scores, affected file sets, breaking change warnings, and test recommendations. Groups changes into 5 phases: scaffold → low-impact modify → high-impact modify → delete → rename. |
| **RefactorSafetyEngine** | `core/coding/refactor_safety.py` | Pre-edit safety evaluation. Checks 5 gates: file existence consistency, layer risk weight, dependency graph centrality + fan-in blast radius, architecture violation detection, and suggests alternatives for unsafe changes (e.g., deprecation cycles instead of deletion). |
| **ChangeSimulation** | `core/coding/change_simulation.py` | Simulates a ChangePlan against the live dependency graph. Predicts breakages per change type (delete → import chain breaks, modify → transitive impact, rename → broken imports, create → overwrite risk). Detects step conflicts (same file in 2+ steps). Outputs unchanged-affected files for test selection. |

### Data Flow

```
Agent decides file changes
  │
  ▼
ChangePlanner.plan(request, file_changes)
  │  • validates against index + dependency graph
  │  • groups into execution phases
  │  • scores risk per step
  │  • detects breaking changes
  ▼
RefactorSafetyEngine.evaluate_change(file, type)
  │  • 5 safety gates
  │  • architecture violation check
  │  • suggests alternatives
  ▼
ChangeSimulation.simulate(plan)
  │  • predicts breakages per file
  │  • detects step conflicts
  │  • selects relevant tests
  ▼
Agent executes (with risk awareness)
```

### Tests

28 tests in `tests/unit/test_coding_planning.py`: planning (10), safety (8), simulation (10).

## Phase 8.3 — Safe Refactoring (June 22, 2026)

Single file in `core/coding/` that converts ChangePlans into validated code patches with automatic import fixing, dependency-safe rename/move/delete, and full rollback support.

| Component | File | Purpose |
|-----------|------|---------|
| **RefactoringEngine** | `core/coding/refactoring_engine.py` | Patch generation (4 recipes: rename_file, rename_symbol, delete_file_safe, move_exports), import path fixing, snapshot/rollback, patch validation against dependency graph |

### Recipes

| Recipe | Input | Output |
|--------|-------|--------|
| `rename_file` | old_path → new_path | Import-update patches for all dependents |
| `rename_symbol` | old_name → new_name in file | Reference-update patches for all importers |
| `delete_file_safe` | file path | Snapshot for rollback + patch if no dependents |
| `move_exports` | src → dst file | Remove exports from src, create dst, update imports |

### Pipeline

```
ChangePlan
  │
  ▼
RefactoringEngine.generate_patches(plan, recipe)
  │  • generates CodePatch objects with old/new content
  │  • automatically updates imports for rename/move
  ▼
RefactoringEngine.validate_patches(patches)
  │  • checks no broken import chains
  │  • warns about missing import-update patches
  ▼
RefactoringEngine.apply_patches(patches, dry_run=True)
  │  • dry_run: builds RollbackSnapshots without writing
  │  • apply: writes patches, returns snapshots for undo
  ▼
RefactoringEngine.rollback(snapshots)  (if needed)
```

### Tests

25 tests in `tests/unit/test_coding_refactoring.py`: recipes (2), patch generation (8), validation (5), apply/rollback (3), quick validate (7).

## Current Status
- **Infrastructure: 9/10** — All subsystems stable and tested
- **Planner: 9.5/10** — Templates, decomposition, routing, verification, enforcement proven
- **Activity Graph: 8.5/10** — Persistence, lineage, resume, recording all working
- **Scheduler: 8.5/10** — Core loop, policy, queue, worker all implemented and tested
- **Multi-Agent Collaboration: 8.5/10** — CollaborationCoordinator, ConsensusEngine, ArtifactReviewer, NegotiationEngine (34 tests, 5 files, wired produce→review→negotiate→consensus→revise/complete)
- **Coding Intelligence: 9.3/10** — Repository indexer, dependency graph, architecture mapper, impact analyzer, change planner, refactor safety, change simulation, refactoring engine, architecture scorer, design analyzer, tradeoff engine, migration planner, improvement-driven safety
- **Research: 9.3/10** — Fact extraction, knowledge graph, reasoning, synthesis, improvement-driven quality
- **Memory: 9/10** — KnowledgeStore, ExperienceExtractor, KnowledgeSynthesizer, BehaviorAdapter, Consolidator all working
- **Learning: 9/10** — ImprovementDetector, ProposalEngine, ExperimentRunner, SafePromotion, KnobStore — closed-loop adaptation
- **Strategic Reasoning: 7.5/10** — StrategyGenerator, OutcomePredictor, StrategyEvaluator, StrategySelector, MemoryAdapter, SimilarityScorer (105 tests, 8 files in core/strategy/)
- **Automated Build: 8/10** — do_automated_build with ActivityGraph + Calibration + KnowledgeStore feedback (30 tests)
- **Build Benchmark: 7/10** — Comparison framework + promotion decisions fully wired, no multi-sample statistics yet (25 tests)
- **Principle Discovery: 7/10** — Registry + extractor + validator + store proven, no cross-domain proposal engine yet (44 tests in core/generalization/)
- **Generalization Pipeline: 9.2/10** — Proposal engine, prioritizer, causal filter, derived properties, proposal executor — full evidence → principle → proposal → experiment → outcome loop (101 tests in core/generalization/)
- **Strategic Reasoning v2: 8.5/10** — StrategyCandidate, TradeoffEngine, OutcomePredictor, StrategicSelector, **StrategyExecutor** (bridges decision → ProposalExecutor → experiment → outcome data point), **PortfolioOptimizer** (budget-aware knapsack selection, selected + deferred allocation), **Future Option Value** (dependency-aware option value scoring, enables strategies that unlock future improvements to score higher) (73 tests, 9 files in core/strategy_v2/)
- **Opportunity Forecasting: 8/10** — ForecastingEngine with trend analysis, velocity estimation, bottleneck pressure, unlock value, horizon classification (60 tests in core/opportunity/forecasting.py)
- **Opportunity Management: 9/10** — Full pipeline: discover (17) → calibrate (17.1) → graph (19) → mine (20) → forecast (21) → bottleneck (22) → roadmap (23) (280+ tests total)