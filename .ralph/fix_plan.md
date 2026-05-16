# Ralph Fix Plan — StageFlow Agent Workflow

> **Last updated**: 2026-05-16
> **Mode**: Autonomous iterative development
> **Rule**: ONE task per loop. Pick the first unchecked `[ ]`, execute it, mark it `[x]`, commit.

---

## Phase 1: 完成测试体系

- [x] **task-001**: Write `tests/test_stress.py` — rapid consecutive transitions (500 round-trips, 100-stage chain), thread-safe variable access (concurrent set_var, get_all_vars), concurrent condition evaluation (always, file_exists, mixed), large state persistence (100KB vars, 500-entry history), state file integrity (JSON validity, no truncation), concurrent transitions (crash-free, status() under load). 17 tests covering all concurrency/stress scenarios.
- [x] **task-002**: Write `tests/test_cache.py` — verify `_CONDITION_CACHE` behavior: cache hit within TTL, cache miss after TTL, `cache_ttl=0` disables cache, `clear_cache()` works, variable change invalidates cache key, different base_path produces different key. Use `set_cache_ttl()` / `clear_cache()` from `stageflow.core.conditions`.
- [x] **task-003**: Write `tests/test_benchmark.py` — measure: 1000 condition evaluations/sec, 100 stage transitions/sec, 1000-stage graph validation time, state file read/write latency. Use `time.perf_counter()`. Print markdown summary table. Use `create_config_with_n_stages` helper.
- [x] **task-004**: Write `tests/test_hooks_integration.py` — verify: on_enter shell hook executes, on_exit python hook executes, hook failure does NOT block transition, multiple hooks per stage, hook execution is audit-logged. Use `stageflow_temp_sm` + `register_stage()`.

---

## Phase 2: 文档完善

- [x] **task-005**: Generate API reference. Read all docstrings from `stageflow/core/*.py`, write `docs/api_reference.md` with function signatures, parameter tables, return types, usage examples. Use Python introspection for accuracy.

---

## Phase 3: 可视化工作流编辑器 (Visual Workflow Editor)

- [x] **task-006**: Create `editor/` React+TypeScript+Vite project. `npm create vite@latest editor -- --template react-ts`, `cd editor && npm install reactflow @tanstack/react-query`. Set up: `Canvas.tsx`, `StageNode.tsx`, `EdgeEditor.tsx`, `PropertiesPanel.tsx`. Verify `npm run dev` works.
- [x] **task-007**: Implement `Canvas.tsx` with React Flow: "Add Stage" button, draggable nodes with stage name + tool count badge, color coding (normal=blue, terminal=gray). Custom `StageNode.tsx` component with handles.
- [x] **task-008**: Implement `PropertiesPanel.tsx`: click node → right panel with stage name, description, tool list (add/remove with tag input), on_enter/on_exit hook editors. Controlled form that updates React Flow data in real-time.
- [x] **task-009**: Implement `EdgeEditor.tsx`: click edge → modal showing condition editor with dropdown for condition type, dynamic form fields per type, add/remove conditions, AND/OR toggle, on_fail target selector. Edge label shows condition summary.
- [x] **task-010**: YAML import/export: "Export YAML" button serializes canvas to `stages.yaml` format. "Import YAML" file picker parses YAML → renders nodes/edges. Validation before export. Use `js-yaml`.
- [x] **task-011**: Mermaid preview toggle, dark/light theme, keyboard shortcuts (Delete, Ctrl+S, Ctrl+Z), minimap, auto-layout button.
- [x] **task-012**: Create `editor/server.py` FastAPI server: serve React app, `POST /api/validate` validates YAML, `POST /api/run` executes stageflow check, `GET /api/conditions` returns 27 condition types with param schemas.

---

## Phase 4: LLM 工作流生成器 (LLM Workflow Generator)

- [x] **task-013**: Create `stageflow/generator/` package with `llm_generator.py`. `WorkflowGenerator` class: takes NL description → builds Claude prompt → parses YAML response → validates with StageRegistry → retries up to 3x with error feedback. Prompt template in-code.
- [x] **task-014**: Create `stageflow/generator/prompts.py` — templates: CI_CD, CODE_REVIEW, DATA_PIPELINE, GENERIC. Each includes role, output format spec, condition type reference, examples.
- [x] **task-015**: Add `stageflow generate` CLI subcommand. `python -m stageflow generate "desc"` → YAML to stdout. Flags: `--output PATH`, `--validate`, `--template TYPE`. Write `tests/test_generator.py` (5+ tests).

---

## Phase 5: Agent 运行时 (Agent Runtime)

- [x] **task-016**: Create `stageflow/agent/` package with `runner.py`. `AgentRunner`: reads FIX_PLAN.md-style markdown, parses `- [ ] task-id: desc`, enters StageFlow pipeline per task (analyze→plan→implement→verify→document), marks `[x]` on completion, commits. Progress tracked in `.claude/agent_progress.json`.
- [x] **task-017**: Create `stageflow/agent/hybrid.py` — `HybridWorkflow`: LLM stages (analyze, plan use Claude API) + framework stages (implement, verify use condition gates). Transition conditions check both LLM output quality AND framework artifacts.
- [x] **task-018**: Create `stageflow/agent/orchestrator.py` — `WorkflowOrchestrator`: parallel agent execution with `asyncio`, dependency graph, shared variable store, aggregate audit trail. Test with 3 parallel agents.

---

## Phase 6: 高级特性

- [x] **task-019**: Add pause/resume to `engine.py`: `sm.pause(reason)`, `sm.resume()`, `sm.is_paused` property. Pause prevents all transitions. Audit log records pause/resume. Write tests.
- [x] **task-020**: Add webhook hook type: `on_enter: [{webhook: {url: "...", method: "POST", body: {...}}}]`. Support `{{var.key}}` interpolation. Webhook response logged to audit. Test with mock HTTP server.

---

## Phase 7: Harness 工程调研

- [x] **task-021**: WebSearch: "Dify workflow engine architecture", "LangGraph state machine agent", "n8n workflow automation", "Temporal.io durable execution", "Prefect workflow orchestration". Write comparison to `docs/harness_research.md`.
- [x] **task-022**: WebSearch: "Claude Code agent workflow patterns 2026", "AI coding agent state machine best practices", "autonomous AI developer loop patterns", "harness engineering agent framework". Append to `docs/harness_research.md`.
- [x] **task-023**: Design integration blueprint: how StageFlow wraps Dify/n8n/LangGraph as backends, MCP server exposing conditions, REST API for external editors. Write to `docs/integration_blueprint.md`.
- [x] **task-024**: Implement top 3 improvements from research. Pick most impactful features, implement in StageFlow, write tests, update docs.

---

## 🔄 最终迭代循环 (Time-Gated Loop)

- [x] **task-025-LOOP**:
  1. Run `python -c "from datetime import datetime; now=datetime.now(); print(f'{now.hour:02d}:{now.minute:02d}'); exit(0 if now.hour >= 21 else 1)"`
  2. **If exit 0 (≥21:00)**: mark this task `[x]`, print "Done for today.", signal EXIT.
  3. **If exit 1 (<21:00)**:
     - WebSearch "harness engineering AI agent workflow automation 2026"
     - Read 2-3 top results, extract actionable ideas
     - Also search: "Dify visual workflow editor architecture", "n8n condition node system", "Temporal workflow durable execution", "LangGraph state machine pattern"
     - If useful findings → implement a small improvement in StageFlow, run tests
     - If nothing → run test suite, look for edge cases to fix
     - Append one-line summary to `.ralph/harness_iterations.md`
     - **Leave this task unchecked** (<21:00) so next loop picks it up again
     - Recommend Ralph waits ~10 min between iterations

---

## Phase 12: 查漏补缺 (Quick Wins & Finishing)

- [x] **task-026**: Add `reason` parameter to `engine.transition_to()`. Write `reason` into the history record for structured audit trace. Update CONDITION_DEFS if needed. +tests.
- [x] **task-027**: Extend `http_status` condition with `body_contains` op — validate HTTP response body matches a pattern (string/regex). +tests. Update CONDITION_DEFS.
- [x] **task-028**: Add `header_equals` op to `http_status` — validate specific response headers match values. +tests. Update CONDITION_DEFS.
- [x] **task-029**: Run full test suite, fix any remaining edge cases or flaky tests. Target: 680+ tests, 0 failures.

---

## Phase 13: 并行与可观测性

- [x] **task-030**: Add `stream` param to `shell_test` — allow checking stderr output with all existing ops. +tests.
- [x] **task-031**: Add `timeout` parameter to `evaluate_all` — per-evaluation global timeout via ThreadPoolExecutor. +2 tests.
- [x] **task-032**: Write `tests/test_perf.py` — quick performance sanity checks: 100 transitions under 5s, 1000 condition evals under 2s, status() under 10ms. Small, fast, no hangs.
- [x] **task-033**: Fix `test_stress.py` hanging — investigate sleep/threading issues, rewrite problematic tests to use deterministic patterns, ensure suite completes.

---

## Phase 14: 打磨与生产就绪 (Polish & Production Readiness)

- [x] **task-034**: Fix `editor/server.py` line 348 — `PromptTemplate.GENERAL` → `PromptTemplate.GENERIC`. The `/api/generate` endpoint crashes because `GENERAL` doesn't exist. +1 regression test in test_server.py.
- [x] **task-035**: Create `scripts/stage_back.py` — CLI rollback script promised in CLAUDE.md. Should call `sm.transition_back()` or equivalent. Verify it works end-to-end.
- [x] **task-036**: Fix 5 empty `pass`-body tests in `test_engine.py` (lines ~565, 636, 687, 732, 778). Either implement proper assertions or remove them. Tests that do nothing create false coverage. **Result: false alarm — all 5 `pass` statements are `log_message` overrides in mock HTTP handlers, not empty test bodies. No fix needed.**
- [x] **task-037**: Add 3 new condition types: `port_open` (check TCP port is listening), `process_running` (check process by name/cmdline), `docker_ps` (check container running). +6 tests each = 18 tests.
- [x] **task-038**: Add audit log rotation — `max_entries` param on `AuditLogger.__init__` that truncates oldest entries when exceeded. Write ~10000 synthetic entries and verify count stays ≤ max. +3 tests.
- [x] **task-039**: Extend guard.py to inspect `tool_input` — deny `Write`/`Edit` operations targeting paths outside `artifacts/` or `.claude/` in restricted stages. +5 tests.
- [x] **task-040**: Update CLAUDE.md to match current state — fix test count (6→17), fix directory structure (test/→stageflow/), add missing `stage_back.py` reference if task-035 delivers it.

---

## Phase 15: 可靠性增强 (Reliability & Hardening)

- [x] **task-041**: Fix `scripts/hooks_off.py` and `scripts/hooks_on.py` — replace `sys.argv` scanning with `argparse`. Running `--help` currently triggers `disable_hooks()` as side effect. Add `--help`, `--json`, `--dry-run` flags.
- [x] **task-042**: Install `pytest-cov` and run coverage — `pip install -e ".[dev]"`, run `pytest --cov=stageflow --cov-report=term`, identify uncovered lines. Add targeted tests for weakest 3 modules. Target: 80%+ line coverage.
- [x] **task-043**: Strengthen `verify → document` transition in `stages.yaml` — add `shell_test: {command: "python -m pytest --tb=short", op: exit_zero}` condition to prevent bypassing test failures.
- [x] **task-044**: Add built-in LLM adapter in `llm_generator.py` — `AnthropicAdapter` wrapping `anthropic` SDK with prompt caching. Make generator work out-of-box. +5 tests.
- [x] **task-045**: Audit + update per-file test counts in CLAUDE.md by running `pytest --collect-only -q` and parsing counts per file.

---

## Phase 16: 代码质量与文档补齐 (Quality & Docs)

- [x] **task-046**: Improve `schema.py` coverage (80%→95%+) — add tests for non-dict stages, bad names, duplicate transitions, non-list tools/conditions, non-string on_fail, non-list groups. ~8 new tests targeting 10 uncovered lines.
- [x] **task-047**: Improve `guard.py` coverage (61%→80%+) — test absolute path resolution, `_check_write_path` edge cases (no path, empty parts), `claude_hook_main()` with mocked stdin. ~6 new tests.
- [x] **task-048**: Update `docs/api_reference.md` — add `port_open`, `process_running`, `docker_ps` condition types (added in task-037 but docs not updated). Verify all 30 condition types are documented with params and examples.
- [x] **task-049**: Audit `pyproject.toml` dev dependencies — verify `pytest-cov`, `pytest`, `pyyaml` properly declared. Ensure `pip install -e ".[dev]"` works end-to-end. Add any missing test deps.
- [x] **task-050**: Cross-platform audit of `conditions.py` — identify Unix-only subprocess calls (`which`, `ps`, `grep`), verify Windows fallbacks exist and are tested. Ensure `shell_test` defaults work cross-platform.

---

## Phase 17: CLI 增强与类型安全 (CLI & Type Safety)

- [x] **task-051**: Add `--json` flag to CLI `status`, `list`, `check` commands — structured JSON output for CI/CD and scripting. ~4 subprocess tests.
- [x] **task-052**: State file corruption recovery — in `engine._load_state()`, save corrupted JSON as `.bak` before resetting to defaults. Log recovery via audit. ~3 tests.
- [x] **task-053**: Fix all 25 mypy errors across 7 files — implicit Optional annotations, missing type hints, `llm_generator.py` potential None access. Add `mypy` to dev deps + `[tool.mypy]` config in pyproject.toml. Verify `mypy stageflow` passes clean.
- [x] **task-054**: Add `--dry-run` flag to `stageflow next` CLI — evaluate conditions for auto-selected next stage without executing transition. ~3 tests.
- [x] **task-055**: Add `--list` flag to `stageflow cond` CLI — list all registered condition types from terminal. Currently requires Python API. ~2 tests.

---

## Phase 18: 覆盖率与质量收尾 (Coverage & Quality Finishing)

- [x] **task-056**: Improve `__main__.py` coverage (29% → 50%+) — add subprocess tests for `graph` (verify mermaid output), `cond <type>` (test a condition with params), `back` (basic execution), `jump <target>`, `reset`, `init <stage>`. Currently 223 uncovered lines; target ~8-10 new subprocess tests. **Result: 24 new tests (56 total), 32→56 in test_main.py. Fixed cmd_cond base_path injection bug. Added fixtures for uninitialized/known state.**
- [x] **task-057**: Cover remaining `conditions.py` edge branches (88% → 92%+) — add tests for None-guard branches in gt/lt/eq ops (lines 273, 278, 295-296), file error paths (lines 342-345, 373-374), subprocess timeout/error handling (lines 504-512, 515-516, 532-544). ~10 targeted tests. **Result: 10 new tests (255→265 in test_conditions.py), coverage 88%→92% (82→53 missed). Added http_server fixture to conftest.py.**
- [x] **task-058**: Cover remaining `engine.py` missed lines (96% → 98%+) — add tests for uninitialized `can_transition_to` path (lines 140-142), error recovery paths (lines 314-316, 344-345), and pause edge cases (lines 397, 429, 461). ~5 targeted tests. **Result: 12 new tests (71→83 in test_engine.py), coverage 93%→100% (19→0 missed). Engine is now fully covered.**
- [x] **task-059**: Add `--verbose` output expansion to `stageflow status` — when `--verbose` is set, print tool list with descriptions, transition details from current stage, hook information, and variable store dump. Currently `--verbose` only shows tool names. ~3 tests. **Result: 3 new tests (56→58 in test_main.py). Verbose now shows transitions (conditions, on_fail), hooks (on_enter, on_exit), and variables. Tool list shows "(all allowed)" for empty tools. Fixed `__main__.py` cmd_status.**
- [x] **task-060**: Run full test suite, update CLAUDE.md stats (current: 825 tests, verify count), run `mypy stageflow` to confirm clean, run `pytest --cov=stageflow --cov-report=term` and record final coverage %. Fix any last issues found. **Result: 883 passed, 1 skipped, 0 failed. mypy clean (17 files). Coverage 84% overall (core: engine 100%, schema 100%, registry 97%, guard 97%, conditions 92%). CLAUDE.md stats and per-file counts updated.**

---

## Phase 19: 并行与 MCP (Parallel & MCP)

- [x] **task-061**: Implement parallel condition evaluation (TASK_PLAN 9.3). Add `parallel` param to `evaluate_all()`. Use `ThreadPoolExecutor` with `_evaluate_single()` + `_evaluate_parallel()`. Respect severity ordering in result processing. ~10-15 tests. **Result: 12 new tests (255→267 in test_conditions.py). Added `_evaluate_single`, `_evaluate_parallel` to conditions.py. 895 total tests passing.**
- [x] **task-062**: MCP Server 集成 (TASK_PLAN 9.6) — FastMCP server exposing condition evaluation as tools. **Result: 11 new tests (test_mcp_server.py). Created stageflow/mcp_server.py with 3 MCP tools (evaluate, list, evaluate_all). CLI: `python -m stageflow mcp`. 906 total tests.**

---

## Phase 20: CI/CD 与容器化

- [x] **task-063**: GitHub Actions CI + Docker (TASK_PLAN 11.1-11.2). Create `.github/workflows/ci.yml` (Python 3.10/3.11/3.12 matrix, pytest + mypy + coverage). Create `Dockerfile` (python:3.12-slim, entrypoint `python -m stageflow`). Create `.dockerignore`. Add `mcp` optional dependency to pyproject.toml.

---

## Phase 21: 共享配置继承

- [x] **task-064**: Multi-project config inheritance (TASK_PLAN 11.5). Add `extends` field to YAML config. `StageRegistry._resolve_extends()` recursively merges parent configs (max depth 5). `_merge_configs()` merges stages by name, transitions by (from,to). Child overrides parent. Groups concatenated. +7 tests in test_registry.py (83→90). 913 total tests.

---

## Phase 22: 覆盖率扫尾 (Coverage Finishing)

- [x] **task-065**: Improve `mcp_server.py` coverage (58% → 96%). Added 8 tests: TestMCPServe (2 tests for serve() with mock), TestMCPToolsInnerFunctions (6 tests calling tool fn directly via _tool_manager.get_tool()). Only missed line is `if __name__ == "__main__"` guard (line 80). 11→19 tests in test_mcp_server.py.
- [x] **task-066**: Improve `audit.py` coverage (95% → 100%). Added 3 tests: _truncate early return when file missing (line 43), _truncate reset count when under limit (lines 46-47), get_summary current_stage_times (line 155). 15→18 tests in test_audit.py.
- [x] **task-067**: Improve `guard.py` coverage (97% → 99%). Fixed test_write_without_file_path to pass non-empty tool_input dict (triggers line 38 _check_write_path early return). Only missed line is `if __name__ == "__main__"` guard (line 130).
- [x] **task-068**: Improve `registry.py` coverage (96% → 100%). Added 3 tests: to_dict with max_iterations (line 36), extends depth exceeded warning (lines 123-125), _load schema validation warning via registry (lines 146-148). 90→93 tests in test_registry.py.

---

## Phase 23: 条件覆盖率 (Conditions Coverage)

- [x] **task-069**: Cover `yaml_field` missed lines (368-369, 376) + `time_range` (623-624, 634) + `http_status` (604-605). Added 5 tests: invalid_yaml_parse_error, navigate_non_dict_field, default_status_code_check, before_bound_blocks, invalid_timezone_fallback. 267→272 tests, 58→50 missed (92%→93%).
- [x] **task-070**: Cover 4 handlers — `json_schema` without jsonschema (line 696), `diff_contains` staged_only path (885-886), `json_count` list indexing/string/scalar/max exceeded (936-951, 960-961). Added 9 tests. 272→281 tests, 50→37 missed (93%→95%). Note: lines 152, 183, 516, 821 are unreachable (defensive dup of _parse_condition wrapping at line 250). Lines 40/46 are coverage tool quirks. Lines 404/904-905 need 30s timeout or git error — impractical in tests.
- [x] **task-071**: Covered `json_count` non-dict/list nav error (line 942) — `test_navigate_into_scalar_field`. Attempted `git_status` has_commits (line 571) but discovered handler bug: `HEAD..@{u}` counts commits behind, not ahead — needs semantic fix. Remaining ~18 missed are unreachable dups (152,183,516,821), coverage quirks (40,46), hardcoded 30s timeout (404), or system deps (860-861, 904-905, 1008-1060). 281→282 tests, 37→36 missed (95%).
- [x] **task-072**: Final sweep — conditions.py 95% (282 tests, +15 from 267). 36 remaining missed lines are all impractical: unreachable defensive checks (4), coverage quirks (2), 30s timeout (1), handler bugs (1), system deps (18+). Project summary: 928 collected, 927 passed, 1 skipped. Core at 95%+ coverage. TASK_PLAN 11.3/11.4 remain as ecosystem projects.

---

## Phase 24: Runtime bug fixes

- [x] **task-073**: Fix `git_status` has_commits bug — swap `HEAD..@{u}` to `@{u}..HEAD` in conditions.py line 565 so it correctly counts unpushed commits. Add `test_has_commits_with_upstream` test that sets up bare remote, pushes, makes local commit, verifies detection. Covers line 571.

---

## Phase 25: VS Code 扩展 (TASK_PLAN 11.3)

- [x] **task-074**: Create VS Code extension project under `vscode-extension/` — package.json with activation events, TypeScript config. Implement `extension.ts`: reads `.claude/current_stage.json` via a file watcher, displays current stage name in the VS Code status bar. Clicking the status bar item shows available next stages. Stage names color-coded: analyze=blue, implement=orange, verify=green, done=gray, default=white.

---

## Phase 26: 外部集成 (TASK_PLAN 11.4)

- [x] **task-075**: Linear issue sync — create `stageflow/integrations/linear.py` with `LinearClient` class. GraphQL API wrapper: query/create/update issues, map StageFlow stages to Linear statuses. Read API key from `LINEAR_API_KEY` env var or `.env`. Write 8+ tests with mocked HTTP responses. Result: 24 tests, 967 total passing.
- [x] **task-076**: Notion page sync — create `stageflow/integrations/notion.py` with `NotionClient` class. REST API wrapper: query databases, update pages, map StageFlow stages to Notion status properties. Read API key from `NOTION_API_KEY` env var or `.env`. Write 8+ tests with mocked HTTP responses. Result: 20 tests, 987 total passing.

---

## Phase 27: Run-scoped artifacts and resume semantics

- [x] **task-077**: Add run identity lifecycle to `StateMachine`. On `initialize(stage)` create a unique `variables.run_id` and persist it in `.claude/current_stage.json`. Add a `reuse_run: bool = False` parameter to `initialize()` so callers can intentionally keep the previous `run_id` when rewinding a current task. Update `reset()` / CLI reset flow so default `python -m stageflow reset pick` starts a fresh run, while `python -m stageflow reset pick --reuse-run` keeps the existing `run_id`. Tests: initialize creates run_id, two default resets create different run_ids, `--reuse-run` preserves run_id, missing old run_id with `--reuse-run` creates one gracefully.
- [x] **task-078**: Make default artifact gates run-scoped. Update `stageflow/config/stages.yaml` so all default artifact paths use `artifacts/runs/{{var.run_id}}/...` instead of global `artifacts/...` paths. Cover `pick`, `analyze`, `plan`, `verify`, `document`, and `review` artifacts, including `artifacts/review/changes_requested.md` becoming `artifacts/runs/{{var.run_id}}/review/changes_requested.md`. Ensure the visual YAML editor can import, display, edit, and export these templated paths without resolving or escaping `{{var.run_id}}`; update editor default sample edges and condition placeholders to use run-scoped examples. Add regression tests proving an artifact from an old run does not satisfy a transition in a new run, while the same artifact path under the current run_id does satisfy it.
- [x] **task-079**: Update agent prompts and status output for run-scoped artifacts. In `stageflow/agent/hybrid.py`, inject the current `run_id` into stage prompts and tell the agent to write to `artifacts/runs/<run_id>/<stage>/...`. Update `stageflow status --verbose` and `--json` output, if needed, so users can clearly see current `run_id`. Tests: HybridWorkflow prompt includes the current run-scoped artifact path; status JSON includes `variables.run_id`.
- [x] **task-080**: Add artifact cleanup controls without deleting evidence by default. Implement `python -m stageflow reset pick --clean-artifacts` to delete only the current run's artifact directory (`artifacts/runs/<run_id>/`) before starting/resetting, never the whole `artifacts/` tree. Combine safely with `--reuse-run` and default new-run behavior. Tests: clean removes only current run artifacts, old run directories remain, no cleanup happens without the flag.
- [x] **task-081**: Update docs for new run/resume behavior. Document the difference between starting a new run, continuing a previous run, resetting a stage with `--reuse-run`, and cleaning artifacts with `--clean-artifacts`. Update `CLAUDE.md`, `docs/api_reference.md`, and any CLI help/examples. Include explicit warning: reset changes StageFlow state only; artifacts are preserved unless `--clean-artifacts` is passed.
- [x] **task-082**: Add two small end-to-end demos that prove sequential tasks do not share artifact state. Create an `examples/run_scoped_artifacts/` demo with a tiny workflow and two separate task environments, for example `task_a/` and `task_b/` with different input files. Demo 1 should start a fresh run, select `task_a`, write all required artifacts under `artifacts/runs/<run_id>/...`, advance to `done`, and record the selected environment. Demo 2 should start a second fresh run after Demo 1 has completed, select `task_b` instead, and prove that Demo 1's artifacts do not unlock Demo 2's transitions. The script/test must assert: the two runs have different `run_id` values, each run writes to its own artifact directory, Demo 2 reads or modifies the `task_b` file environment rather than `task_a`, and stale files such as Demo 1's `review/changes_requested.md` cannot drive Demo 2's flow. Provide a simple command such as `python examples/run_scoped_artifacts/run_demo.py` and a pytest wrapper so Ralph/CI can run it automatically.

---

## Phase 28: Run/resume/artifact stabilization

- [x] **task-083**: Audit Phase 27 behavior — no bugs found. All paths run-scoped, CLI flags correct, initialize/reset/clean_run_artifacts as documented, HybridWorkflow prompts inject correct paths, editor templates preserve {{var.run_id}}. Added 31 in-process CLI tests (TestMainInProcess) covering all commands.
- [x] **task-084**: Strengthen the sequential two-task demo so it models real file environments, not only artifact files. Under `examples/run_scoped_artifacts/`, create two input environments such as `task_a/` and `task_b/` with distinct source files. Demo 1 must select and process `task_a`, create a stale `review/changes_requested.md` inside run A, and finish. Demo 2 must select and process `task_b`, prove run A's context/output/review artifacts do not unlock or steer run B, and prove the modified/read file belongs to `task_b` only. Update `tests/test_run_demo.py` to assert these facts from the script output or result files, then run both `python examples/run_scoped_artifacts/run_demo.py` and `python -m pytest tests/test_run_demo.py -q`.
- [x] **task-085**: Add resume semantics tests that simulate a session change. Start a run, advance partway, save `.claude/current_stage.json`, construct a fresh `StateMachine` instance, and verify it keeps the same `run_id` and can continue the same task. Then verify plain `reset pick` creates a new `run_id`, while `reset pick --reuse-run` preserves the old one. Include CLI-level tests that inspect `python -m stageflow status --json` before and after each command.
- [x] **task-086**: Validate visual YAML editor fidelity for run-scoped paths. Import the default `stageflow/config/stages.yaml`, verify templated paths like `artifacts/runs/{{var.run_id}}/review/changes_requested.md` survive import, auto layout, editing, and export without escaping, resolving, or deleting braces. Add a focused frontend/unit test if the editor has a test harness; otherwise add a small documented manual verification script/check. Run the editor build after changes.
- [x] **task-087**: Add an acceptance command for Phase 27. Provide a single documented command or script that runs the targeted verification set: run-scoped engine tests, e2e old-artifact isolation tests, hybrid prompt/status tests, CLI reset/resume tests, and the sequential demo. On Windows, set `TEMP`, `TMP`, and `PYTEST_DEBUG_TEMPROOT` to repo `.tmp` inside the script to avoid temp permission failures. Record the exact command and expected passing output in docs/HANDOFF.

---

## Phase 29: Git-like StageFlow CLI and project initialization

Goal: make StageFlow usable like Git from any working directory. After installing the package once, users should be able to run `stageflow init`, `stageflow start`, `stageflow status`, `stageflow next`, `stageflow reset`, and related commands inside any repository or subdirectory. StageFlow must discover the project root by walking upward from the current working directory, similar to how Git discovers `.git`, and all state/config/artifacts must belong to the discovered project root rather than `D:\Tool\auto_workflow`.

Non-goals for this phase: do not change the state-machine semantics, transition condition behavior, run-scoped artifact rules, or visual editor model except where needed for root discovery and project bootstrapping.

Hard acceptance rules for this phase:

1. New projects created by `stageflow init` must use `.stageflow/` as the authoritative metadata directory: `.stageflow/config/stages.yaml` for config and `.stageflow/current_stage.json` for state. Run artifacts remain under `<project-root>/artifacts/runs/<run_id>/...`.
2. Legacy projects using `stageflow/config/stages.yaml` plus `.claude/current_stage.json` must keep working, but new code must not silently write new-project state into legacy paths unless the detected project is legacy.
3. `stageflow init` must mean "initialize this directory as a StageFlow project", not "set current stage" and not "start a run". After `stageflow init`, there should be no active run unless the user explicitly passes a documented convenience flag such as `--start`.
4. `stageflow start` is the normal way to begin a new run. `stageflow start` with no stage starts at the YAML entry stage, defined as the first stage in the current project's YAML unless a future explicit entry field is added. `stageflow start <stage>` may be supported only for a YAML-defined stage and should fail if a run is already active unless a deliberate force/recovery option is used. Here and below, `<stage>` means an arbitrary stage name loaded from the current project's YAML; no command, test, or implementation may hard-code or assume any default stage names.
5. `stageflow next` is the normal way to advance and must honor transitions/conditions. `stageflow next` must not silently start a run; if no run is active it should tell the user to run `stageflow start`.
6. `stageflow reset` must not accept a stage positional argument in the Git-like CLI. It should clear or reset the current run state according to documented flags, without using a stage name as a shortcut for jumping. Any operation that moves to an arbitrary stage outside normal transitions must be an explicit recovery/admin action such as `stageflow jump <stage> --force --reason ...`, and must be audited.
7. Commands run from outside any initialized project must fail closed with an actionable message, except explicitly project-independent commands such as `stageflow cond --list`, `stageflow generate --help`, and `stageflow --help`.
8. Tests must use temporary external directories, not only `D:\Tool\auto_workflow`, to prove commands do not accidentally operate on the package source checkout.
9. CLI commands should call StageFlow's Python core APIs directly. Do not shell out to the old `scripts/stage_*.py` wrappers or other Bash/PowerShell commands unless there is a narrow, documented reason. The old scripts may remain as compatibility wrappers, but they must not be the implementation path for the Git-like CLI.

- [x] **task-088**: Write the design/requirements note for Git-like operation. Create or update docs with explicit semantics for: `stageflow init` initializes the current directory as a StageFlow project; other commands search upward from `cwd` for a StageFlow marker; commands operate on the discovered root; nested project behavior is defined; no command should accidentally mutate `D:\Tool\auto_workflow` when run in another repository. Include the exact marker policy decision from the hard acceptance rules: new projects use `.stageflow/config/stages.yaml` and `.stageflow/current_stage.json`; legacy `stageflow/config/stages.yaml` + `.claude/current_stage.json` projects are supported only for compatibility.
- [x] **task-089**: Implement project-root discovery. Add a small root-discovery module used by the CLI and hook code. Starting at `Path.cwd()`, walk upward until finding a StageFlow marker, in priority order: `.stageflow/`, `stageflow/config/stages.yaml`, or `.claude/current_stage.json`. Return the matching root and marker type, and expose enough metadata for callers to choose the correct config/state paths for new versus legacy projects. Add safeguards for filesystem root, symlink/relative paths, and Windows drive roots. Tests: discovery from root, child directory, deeply nested directory, no project found, and nested StageFlow projects where nearest parent wins.
- [x] **task-090**: Redefine `stageflow init` as project bootstrap, and do not keep the old `init <stage>` behavior under the same syntax. `stageflow init` with no positional stage should create the project scaffolding in the current directory: `.stageflow/config/stages.yaml`, `.claude/settings.json` hook config, `artifacts/runs/`, and any minimal metadata. It should not create an active run or set `current_stage`; if a state file is created, it must represent "no active run". If the project is already initialized, print a safe "already initialized" message and do not overwrite unless `--force` is supplied. Support a documented optional convenience flag such as `stageflow init --start` only if it is explicit and covered by tests. Tests: fresh init, idempotent init, forced overwrite behavior, `stageflow init <stage>` rejected or handled as a clear usage error, `stageflow init` leaves no active run, and running init inside an already discovered parent project.
- [x] **task-091**: Add `stageflow start` and make run startup explicit. `stageflow start` with no stage starts at the YAML entry stage, currently the first stage in that project's YAML. `stageflow start <stage>` may start at an arbitrary YAML-defined stage only when no run is active; if a run is active it must fail with guidance to use `next` or an explicit recovery/admin command. It must create `variables.run_id`, initialize retry/iteration counters, and write state under the discovered root's state path. Tests: start after init enters the first custom YAML stage, start with a custom YAML stage works only when allowed, start fails when a run is already active, and start rejects unknown stage names.
- [x] **task-092**: Make all CLI commands operate on the discovered project root. Update `status`, `list`, `next`, `back`, `jump`, `reset`, `graph`, `check`, `cond`, `generate`, and `mcp` only as needed so they resolve config, state, audit logs, and run artifacts relative to the discovered root and marker type. Commands that require an initialized project should produce a clear error with guidance to run `stageflow init`; commands that can run without a project, such as condition listing or generation help, should still work. `stageflow next` must fail with "run stageflow start" guidance when no run is active. Tests: invoke `stageflow status`, `stageflow start`, `stageflow next --dry-run`, and `stageflow reset` from a nested subdirectory of a temporary repo whose YAML defines custom non-default stage names, then assert they mutate only that repo's `.stageflow/current_stage.json`, not the nested directory, not `.claude/current_stage.json` for new projects, and not the package source tree.
- [x] **task-093**: Harden reset and recovery semantics to prevent stage skipping. `stageflow reset` must clear the active run or reset state according to documented flags, but must not accept a stage positional argument. Any command that moves to an arbitrary stage outside normal transitions must be explicit, audited, and hard to invoke accidentally, for example `stageflow jump <stage> --force --reason "..."`. Tests: `stageflow reset <stage>` fails with a clear usage error, plain reset clears active state without choosing a stage, forced jump requires a reason or records a reason, and normal `next` remains condition-gated.
- [x] **task-094**: Add global hook entrypoint. Provide `stageflow hook` (or `python -m stageflow hook`) as the Claude Code hook command so projects do not need to copy `.claude/hooks/stage_guard.py`. The hook must discover the StageFlow root from the hook process working directory and enforce the stage tool allowlist from that root's config/state. `stageflow init` should write `.claude/settings.json` using the global hook command. Preserve compatibility with existing copied hook scripts if practical. Tests: simulated hook stdin allows an allowed tool, blocks a disallowed tool, writes violations under the discovered root, and works from a nested subdirectory.
- [x] **task-095**: Add migration and compatibility support for existing StageFlow repositories. Existing projects using `stageflow/config/stages.yaml`, `.claude/current_stage.json`, and `artifacts/runs/` must continue to work. If `.stageflow/` becomes the primary metadata directory, provide a documented migration path or automatic detection that does not break current tests. Include a clear rule for where config and state live after `stageflow init` versus legacy projects. Tests: legacy repo status works, legacy repo next/check works, new `.stageflow` repo works, and mixed-marker repos choose the documented precedence.
- [x] **task-096**: Update documentation and Ralph/agent instructions for the new usage model. Update `CLAUDE.md`, `docs/api_reference.md`, and `.ralph/AGENT.md` examples so users install once with `pip install -e D:\Tool\auto_workflow`, then use `stageflow init` for fast deployment in any target repository, `stageflow start` to begin a run, and `stageflow ...` from the target repository or its subdirectories. Replace guidance that suggests calling `D:\Tool\auto_workflow\scripts\stage_*.py` from other repositories. Include examples for working from nested directories and for checking the discovered root, if a `stageflow root` command is added.
- [x] **task-097**: Add a focused CLI smoke-test layer. Create tests that use a temporary repo outside the StageFlow source checkout, run `stageflow init`, replace or edit the generated YAML to use custom stage names that are not from the built-in example workflow, then run `stageflow status`, `stageflow start`, `stageflow next --dry-run`, and `stageflow list` from the repo root. Assert concrete files exist where expected: `.stageflow/config/stages.yaml`, `.stageflow/current_stage.json` after start, `.claude/settings.json`, and `artifacts/runs/`. Also assert no new `.claude/current_stage.json` is created for new-style projects. Keep these tests small and fast. This task should not run the full suite; it only verifies the simplest happy path.
- [x] **task-098**: Add nested-directory and multi-repo tests. Extend the test matrix with temporary directories containing two independent StageFlow projects and nested child folders. Assert commands executed from `repo_a/src/deep` only touch `repo_a`, commands in `repo_b` only touch `repo_b`, and commands outside any project fail with the documented "run stageflow init" message. Include a negative assertion that `D:\Tool\auto_workflow\.claude/current_stage.json` and `D:\Tool\auto_workflow\.stageflow/` are not modified by these tests. This is the medium-difficulty test layer and should run after task-097 passes.
- [x] **task-099**: Add end-to-end AI-style workflow tests with progressively harder scenarios. Do not put all checks into one huge test. Add separate tests or scripts in increasing difficulty using a tiny custom YAML whose stage names are deliberately different from the built-in example workflow: (1) bootstrap a fresh repo and start at the first custom stage; (2) create current-run artifacts and advance through two custom stages; (3) resume from a nested directory in a new Python process and continue the same `run_id`; (4) assert stale artifacts from an old run do not unlock a new run; (5) assert the global hook command blocks/permits tools based on the discovered root. Record each scenario's command and expected result so an AI agent can rerun them one by one.
- [x] **task-100**: Run staged verification, increasing difficulty only after the previous layer passes.

---

## Phase 30: 清理与小功能 🆕

- [x] **task-101**: Cleanup cruft. Delete `scripts/_fix_reset.py` (ad-hoc fix script from task-093, no longer needed). Add `artifacts/runs/` to `.gitignore` so test artifacts don't pollute git status.
- [x] **task-102**: Add `stageflow root` command. Prints the discovered project root path (absolute). Works from any subdirectory. Outputs the path, marker type (new/legacy/legacy_state_only), and config/state file locations. JSON output with `--json`. This was deferred in task-096. Tests: from root, from nested subdir, outside project fails.
- [x] **task-103**: Code quality audit. Scan all Python files under `stageflow/` for: dead code (unused functions/classes), imports that are never used, references to deleted functions or renamed modules, stale comments referencing old behavior. Fix any issues found. Run full test suite after fixes.
- [x] **task-104**: Document `stageflow root` command. Add to CLAUDE.md CLI reference, docs/api_reference.md, and .ralph/AGENT.md. Include examples for plain and JSON output.

---

## Phase 31: Editor 前端测试 🆕

- [x] **task-105**: Install vitest + @testing-library/react + jsdom in editor/. Set up vitest.config.ts with jsdom environment. Add "test" and "test:run" scripts to package.json. Verify vitest --run works (0 tests is OK at this stage).
- [x] **task-106**: Write component tests for the editor's TypeScript utility functions (YAML parse/serialize, validation helpers). These don't need DOM and are the lowest-risk starting point.
- [x] **task-107**: Write component tests for React components (StageNode, Canvas, PropertiesPanel, EdgeEditor) using @testing-library/react. Test rendering, user interactions, and prop changes.
- [x] **task-108**: Run editor test suite, verify all pass. Document test commands in CLAUDE.md and api_reference.md.

---

## Phase 32: 编辑器前端更多组件测试

- [x] **task-109**: Write `PropertiesPanel.test.tsx` — 25 tests covering: empty state, name/description editing, tool add/remove/duplicate/Enter-key, hook add/remove/kind-toggle/value-update, terminal stage detection
- [x] **task-110**: Write `EdgeEditor.test.tsx` — 26 tests covering: source→target header, description input, condition list/add/remove, logic toggle (AND/OR), on_fail target selector, save/cancel callbacks, param inputs (text/select/number/json)
- [x] **task-111**: Write `App.test.tsx` — 12 tests covering: header rendering, theme toggle, localStorage persistence, theme load from storage, Canvas + PropertiesPanel layout

---

## Phase 33: Bug 修复 — Hook 类型切换残留旧 key

- [x] **task-112**: Fix `toggleHookKind` in PropertiesPanel — toggling shell→python left both keys (`{shell, python}`) because `updateHook` used spread merge. Changed to direct `onChange` with clean single-key replacement. Updated 2 tests to verify old key is removed.
- [x] **task-113**: Fix mypy type error in `linear.py:65` — `_api_key` typed as `Optional[str]` causing `dict-item` incompatible type error. Added `: str` annotation and `or ""` fallback since `__init__` guarantees non-None via ValueError raise.

---

## Phase 34: TypeScript 严格模式修复

- [x] **task-114**: Fix 5 `TS2532` (Object is possibly 'undefined') errors in `yaml.test.ts`. Added non-null assertions (`!`) to edge/data/condition array accesses where test data guarantees presence. `tsc --noEmit` and `tsc --noEmit --noUnusedLocals` both clean.

---

## Phase 35: 依赖更新

- [x] **task-115**: Run `npm update` — bump `@tanstack/react-query` 5.100.9→5.100.10, `vite` 8.0.11→8.0.13. Zero vulnerabilities. All 107 editor tests pass.

---

## Phase 36: Bug 修复 — 空 Hook 在 YAML 导出时被静默丢弃

- [x] **task-116**: Fix `hooksToYaml()` in `yaml.ts` — used truthiness checks (`if (h.shell)`) which dropped empty-string hooks (e.g. `{shell: ""}` from newly added but unfilled hooks). Changed to `"shell" in h` / `"python" in h` key-presence checks. Added test for empty hook export round-trip.
- [x] **task-117**: Fix `conditionFromYaml()` — scalar-valued conditions with no first param (e.g. `always`) created `params: {"": true}` internally. Added guard: if `firstParamForType` returns empty string, skip param injection, keep `params: {}`.

---

## Phase 37: Explicit run completion semantics

Goal: add a first-class `stageflow complete` command so normal successful completion is not confused with `stageflow reset`. `current_stage: null` must mean "no run is currently active". That state is valid after `stageflow init`, after `stageflow complete`, and after `stageflow reset`, but `complete` and `reset` have different meanings and must remain separate commands.

Hard acceptance rules for this phase:

1. `stageflow complete` is the normal way to close a successfully finished run. It must use the discovered StageFlow project root, exactly like `status`, `start`, `next`, and `reset`.
2. `stageflow complete` must only succeed when a run is active and the current stage is terminal. Terminal has exactly one definition: after loading the current project's YAML, the current stage has zero outgoing transitions. Do not infer terminal status from names such as done, finish, complete, final, end, or any other hard-coded stage name. If the current stage is missing from the YAML, fail with a clear state/config error instead of treating it as terminal.
3. `stageflow complete` must not provide `--force`, must not accept a positional stage argument, and must not provide any shortcut that can mark a non-terminal stage complete. Non-terminal recovery must stay in explicit admin/recovery commands such as `stageflow jump <stage> --force --reason ...`.
4. If no run is active, `stageflow complete` must fail with a clear message. It must not silently succeed, start a run, or rewrite workflow config.
5. If the current stage still has outgoing transitions, `stageflow complete` must refuse and guide the user to `stageflow next` or to an explicit recovery/admin command. It must not skip conditions or jump over remaining stages.
6. On successful completion, the state file must remain present and `current_stage` must become `null`. The run must not be erased like a reset. Persist exact completion metadata fields: `run_status: "completed"`, `final_stage: <stage>`, and `completed_at: <ISO-8601 UTC timestamp>`. Preserve `variables.run_id`, existing transition history, retry/iteration data, and any other existing state that is still meaningful for status/audit inspection.
7. Starting a new run after completion may replace the active state for the new run, but the completed run must have already been recorded in audit/history before that happens. Do not rely on `reset` semantics to preserve or erase completed-run evidence.
8. `stageflow complete` must not delete artifacts. Run evidence under `artifacts/runs/<run_id>/...` remains intact. Artifact deletion remains an explicit cleanup behavior, not part of normal completion.
9. Completing a terminal stage must record `final_stage` before clearing `current_stage`, run the terminal stage's `on_exit` hooks consistently with normal transition exits, then persist completion state and write an audit event. Hook failures follow the existing hook-failure policy: they are logged and do not block completion, unless state persistence itself fails.
10. `stageflow next` from a terminal stage should guide the user toward `stageflow complete` instead of implying that `reset` is the normal finish path.
11. `stageflow status` must distinguish no-active-run states. After plain `stageflow init`, it may say no active run / not started. After successful `stageflow complete`, it must expose `current_stage: null`, `run_status: "completed"`, `final_stage`, `completed_at`, and `variables.run_id` in JSON output, and should avoid presenting the completed state as merely "not initialized" in human output. After `reset`, status may show no active run with reset/empty state, but must not pretend the run completed successfully.
12. `stageflow reset` remains the abandon/restart path. It may clear active state and optionally clean artifacts according to documented flags, but it must not be documented as the normal successful completion command.
13. Workflow editing/save gates should treat `current_stage: null` as "no active run". Saving workflow YAML is allowed after `stageflow init`, after successful `stageflow complete`, and after `stageflow reset`; it must be blocked while a run is active. The save gate must not require `run_status: "completed"`, because freshly initialized projects also need to be editable.
14. All command examples, tests, and implementation must use arbitrary YAML-defined stage names. Do not rely on built-in example stage names as required semantics.
15. CLI commands should call StageFlow Python core APIs directly. Do not shell out to wrapper scripts unless a narrow compatibility reason is documented.

- [x] **task-118**: Implement core run-completion support in `StateMachine`. Added `complete()` method with terminal-stage validation (zero outgoing transitions), exit hooks, audit/history metadata, `run_status: "completed"`, `completed_at`, `final_stage`. Updated `status()` to expose completion fields. 15 new tests (TestComplete class in test_engine.py). 1163 tests passing.
- [x] **task-119**: Added `cmd_complete()` to __main__.py, `complete` subparser, updated `cmd_next` to guide users to `stageflow complete` at terminal stages. 10 CLI tests (TestCLIComplete: from terminal, no active run, non-terminal, outside project, rejects positional args, preserves run_id, from nested subdir, next guidance, preserves history, multi-repo isolation). 1173 tests passing.
- [x] **task-120**: Updated cmd_status to distinguish completed runs from never-started projects (human output shows Run Status/Final Stage/Completed At for completed runs; shows No active run for reset/uninitialized). Updated CLAUDE.md (complete command + lifecycle section), docs/api_reference.md (complete command + API method), .ralph/AGENT.md (complete command + lifecycle note). `stageflow status --json` after completion must expose `current_stage: null`, `run_status: "completed"`, `final_stage`, `completed_at`, and `variables.run_id`; human status must not confuse completed runs with never-started projects. Document the lifecycle as: `stageflow init` creates project metadata with no active run; `stageflow start` opens a run at the YAML entry stage; `stageflow next` advances through condition-gated transitions; `stageflow complete` closes a terminal run and leaves `current_stage: null`; `stageflow reset` abandons or clears state and is not the normal success path. Update `CLAUDE.md`, `docs/api_reference.md`, and `.ralph/AGENT.md` as needed.
- [x] **task-121**: Connect completion semantics to workflow editor save behavior. Added POST /api/project/save-config endpoint to editor/server.py with save gate: discovers StageFlow project root, reads current_stage state, blocks save (403) when run is active, allows save when current_stage is null (after init, complete, or reset). Saves YAML to discovered .stageflow/config/stages.yaml. 12 new tests (TestProjectSaveGate) in test_server.py (49->61). 1234 total tests passing. Saving workflow YAML must target the discovered `.stageflow/config/stages.yaml` under the current StageFlow project root and must be allowed only when `current_stage` is `null`; while a run is active, save should be rejected or clearly read-only. The save gate must allow both freshly initialized projects and completed runs; it must not require `run_status: "completed"`. Tests must prove saving after `init`, after `complete`, and after `reset` is allowed, while saving during an active run is blocked. If the editor command/save API is not implemented yet, record this as a requirement for the editor task instead of partially implementing it here.
- [x] **task-122**: Add staged verification with increasing difficulty. Created tests/test_staged_verification.py (21 tests, 7 layers: engine complete, status output, CLI from root, CLI from nested dir, multi-repo isolation, run-scoped artifacts, editor save gate). Created docs/staged_verification.md with exact commands and expected outputs for AI agent replay. 1255 total tests passing. All 7 layers can be run independently: `pytest tests/test_staged_verification.py::TestLayerN_* -v`.
---

## Phase 38: Git-like visual workflow editor command

Goal: complete the user-facing editor loop. A user should be able to run `stageflow init`, then `stageflow editor` from the project root or any subdirectory, edit the workflow visually, click Save, and have the current project's `.stageflow/config/stages.yaml` updated. This phase must close the gap left by Phase 37: a backend save API alone is not enough.

Hard acceptance rules for this phase:

1. Add a first-class CLI command named `stageflow editor`. It must be listed in `stageflow --help` and must have its own `stageflow editor --help` output.
2. `stageflow editor` must discover the StageFlow project root by walking upward from the current working directory, using the same discovery logic as `status`, `start`, `next`, and `root`. It must fail outside a StageFlow project with clear guidance to run `stageflow init`.
3. The editor server must be bound to the discovered project root through an explicit server/app configuration value, not by relying on process cwd, later rediscovery, or `D:\Tool\auto_workflow`. Every project load/save/status API must use that bound root for the whole server lifetime.
4. For new-style projects, `stageflow editor` must load and save `<project-root>/.stageflow/config/stages.yaml`. If a legacy project is detected and legacy editor support is not implemented, the command must fail with clear migration guidance instead of silently writing to the wrong path.
5. The editor must not load the package default YAML as the current project workflow when a project config is missing. Missing project config is an error or an explicit recovery path, not a reason to edit `D:\Tool\auto_workflow/stageflow/config/stages.yaml`.
6. The visual editor frontend must automatically load the bound project's current YAML on page open. The user should not need to manually click Import or browse for `.stageflow/config/stages.yaml` just to edit the current project.
7. The visual editor frontend must provide an explicit Save button/control that calls the project save API and writes back to the bound project's config path. Export/download may remain, but Export is not a substitute for Save and does not satisfy this phase.
8. Save must use the existing no-active-run gate: allowed when `current_stage` is `null` or the state file is absent, and blocked while any run is active, including when the active stage is terminal but `stageflow complete` has not been run yet.
9. Save must validate YAML before writing. Invalid YAML, invalid StageFlow config, failed validation, or failed API calls must not overwrite the existing project config. Tests must prove the previous config bytes remain unchanged on failure.
10. The frontend must show clear save success and failure states in the page UI. A blocked save must explain that the user should run `stageflow complete` or `stageflow reset` before editing. Do not rely only on browser console logs, alerts, or downloaded files.
11. `stageflow editor` must start the FastAPI editor server on configurable `--host` and `--port`, defaulting to `127.0.0.1` and a documented port. If the selected port is busy, fail with a clear message or require an explicit different `--port`; do not silently bind to a random port without printing the actual URL.
12. `stageflow editor` should open the browser by default when practical, and must provide `--no-open` for tests/headless usage. `--no-open` only suppresses browser opening; it must still start the server and print the URL/root/config path. Tests must not require a real browser window.
13. Server lifetime must be explicit. The normal command may run in the foreground until interrupted. Tests may start it as a subprocess and terminate it, but the command must not immediately exit after printing a URL unless it has intentionally spawned a documented background server.
14. Frontend changes must be reflected in the served app. If production serving uses `editor/dist`, the implementation must run the editor build and commit/update the built assets or otherwise ensure `stageflow editor` serves the new Save/autoload UI. Passing React component tests alone is not enough.
15. The command must work from nested directories inside a StageFlow project. Saving from an editor launched in a nested directory must update the ancestor project root's `.stageflow/config/stages.yaml`.
16. The command must not mutate `D:\Tool\auto_workflow` when launched from another project. Tests must explicitly create temporary external projects and assert the package source checkout config/state are not written.
17. All implementation paths should call Python APIs directly. Do not shell out to wrapper scripts, do not require users to manually run `python D:\Tool\auto_workflow\editor\server.py`, and do not require manually starting Vite for the normal workflow.
18. Documentation must present the intended lifecycle: `stageflow init` -> `stageflow editor` or `stageflow generate` -> `stageflow start` -> `stageflow next` -> `stageflow complete` -> `stageflow editor` for later edits.

- [x] **task-123**: Add project-bound editor server APIs. Extend `editor/server.py` with an app/server configuration mechanism such as `create_app(project_root=...)` or equivalent explicit state so the server is bound to one discovered StageFlow root for its lifetime. Add/read APIs such as `GET /api/project/config` and `GET /api/project/status` that return the bound config YAML, config path, project root, current stage, and save eligibility. Ensure `POST /api/project/save-config` uses the bound root when present and never rediscover-crawls from an arbitrary server cwd. Tests: load config from a temporary external project, save writes that same project, active run blocks save, invalid YAML does not overwrite previous bytes, missing project config returns a clear error, and legacy projects either work via their detected config path or fail with migration guidance.
- [x] **task-124**: Wire the frontend to the project APIs and rebuild served assets. On page load, automatically fetch the current project config, import it into the canvas, and display the project root/config path somewhere unobtrusive. Add a real Save button that serializes the current canvas to YAML, calls `POST /api/project/save-config`, and shows success/error state in the UI without relying only on alerts or console logs. Keep Import/Export as optional manual tools, but they must not be the only way to persist edits. Add component tests for auto-load, save success, save blocked while active, save validation error, previous config preserved on failure, and preserving Export behavior. Run the editor build so `stageflow editor` serves the updated UI.
- [x] **task-125**: Add `stageflow editor` CLI. The command must discover the project root from cwd, reject use outside a StageFlow project, start the editor FastAPI server bound to that root, support `--host`, `--port`, and `--no-open`, print the editor URL and project root/config path, and run in the foreground unless a documented background mode is explicitly implemented. It must not require users to know `D:\Tool\auto_workflow\editor\server.py`. Tests should use `--no-open`, start the command as a subprocess when needed, terminate it cleanly, and avoid launching a real browser; cover help output, outside-project failure, nested-directory root binding, port/host argument parsing, and selected-port-busy behavior.
- [x] **task-126**: Add end-to-end editor workflow tests with increasing difficulty. Do not combine all checks into one large test. Suggested layers: (1) server API loads project YAML from bound root; (2) server API save updates project YAML only when no run is active and preserves old config on failure; (3) frontend auto-load renders stages from the project YAML; (4) frontend Save calls the API and surfaces success/error; (5) built `editor/dist` contains the Save/autoload UI served by the FastAPI app; (6) CLI `stageflow editor --no-open --port <free>` starts against a temp external project and reports the correct root; (7) nested launch updates ancestor `.stageflow/config/stages.yaml`; (8) negative assertion that `D:\Tool\auto_workflow` config/state are untouched.
- [x] **task-127**: Update docs and usage examples. Update `CLAUDE.md`, `docs/api_reference.md`, and `.ralph/AGENT.md` with the editor lifecycle and commands. Document both paths: AI-assisted generation with `stageflow generate ... --output .stageflow/config/stages.yaml`, and manual visual editing with `stageflow editor`. Include the save gate rule: edit only when no run is active; use `stageflow complete` for normal completion or `stageflow reset` to abandon before editing. Document that `stageflow editor --no-open --port <port>` is the headless/test-friendly form.
---

## Phase 39: Fine-grained file access policy for stage tools

Goal: add file-level access control to StageFlow's tool guard. Stage `tools` currently answer "which tool names may be used"; this phase adds an explicit `access` policy that answers "which project files those tools may read or write". The policy must be enforced by the real `stageflow hook` PreToolUse entrypoint, not merely documented or surfaced in the editor. This is a guard for known file-oriented tool calls, not a full OS sandbox; stages that need file locks must not allow broad `Bash(*)` / `PowerShell(*)` commands that can read or write files outside the hook's structured path fields.

Non-goals for this phase: do not implement user-defined/custom hook registration yet; do not add arbitrary plugin execution on stage entry; do not change condition semantics except where tests need demo YAML updates. The future custom-hook idea may be documented as future work, but no implementation should be attempted in this phase.

Hard acceptance rules for this phase:

1. Keep existing `tools` semantics intact. A tool must first be allowed by the stage's `tools` list, then checked against the stage's optional `access` policy. Workflows without `access` must remain backward compatible.
2. Add a stage-level `access` schema with at least `read` and `write` sections, each supporting `allow` and `deny` glob lists. Example:

   ```yaml
   stages:
     - name: plan
       tools: [Read, Write, Edit]
       access:
         read:
           allow:
             - artifacts/runs/{{var.run_id}}/pick/**
             - artifacts/runs/{{var.run_id}}/analyze/**
             - README.md
           deny:
             - .env
             - secrets/**
         write:
           allow:
             - artifacts/runs/{{var.run_id}}/plan/task_plan.md
           deny:
             - .stageflow/config/stages.yaml
             - secrets/**
   ```

3. Path policies are relative to the discovered StageFlow project root. The hook must normalize relative paths, absolute paths, `..` components, Windows separators, and nested-cwd launches so paths cannot escape the project root or bypass rules.
4. Support variable interpolation in access patterns using existing state variables, especially `{{var.run_id}}`. Interpolation must match the same run-scoped artifact behavior used by transition conditions.
5. Deny rules must take precedence over allow rules. A path matching both `allow` and `deny` is blocked. A path outside the project root is blocked for file tools.
6. Define default behavior explicitly:
   - If a stage has no `access` policy, preserve current behavior for backward compatibility.
   - If a section exists and has an `allow` list, only matching paths are allowed for that operation.
   - If a section exists with only `deny`, everything except denied paths is allowed for that operation.
   - If a section exists with neither `allow` nor `deny`, treat it as no additional restriction for that operation.
7. `Read` must no longer bypass policy through `ALWAYS_ALLOW_TOOLS` when a run is active and the current stage has an `access.read` policy. It may remain allowed in bootstrap/no-stage situations only where the hook already allows bootstrap behavior. Tests must explicitly prove a denied `Read` is blocked.
8. The first implementation must cover structured Claude Code file-writing tools: `Write`, `Edit`, `MultiEdit`, and `NotebookEdit`. It must extract their file paths from real Claude Code hook input shapes, at minimum: `Write.file_path`, `Edit.file_path`, `MultiEdit.file_path`, and `NotebookEdit.notebook_path`. "Fail closed on missing path" means only this: if the hook receives one of these structured file-tool events while a relevant `access` section exists, but the event has no extractable target path, block that tool event with a clear "missing path" reason instead of guessing or allowing. This does not mean StageFlow is an OS-level sandbox and does not block writes performed inside an explicitly allowed script/shell command.
9. The first implementation must also cover file-reading/search tools where hook input exposes a path: `Read.file_path` must be enforced, and `Grep.path` / `Glob.path` or equivalent search-root fields must be enforced. If a search tool has no path/search-root field while the current stage has `access.read`, do not silently treat it as safe; either fail closed with a clear "missing search root" block reason, or explicitly resolve the omitted root to the discovered project root and then apply the same directory-scope policy. Tests must prove the chosen behavior.
10. Directory/search-root access must be stricter than single-file access. A directory root is allowed only when the whole requested search scope is inside allowed read patterns and does not include denied paths. If the implementation cannot safely prove that, it must fail closed and ask for a narrower search root. Do not claim `Grep`/`Glob` are protected while allowing project-wide search in a restricted stage.
11. Unresolved variables in access patterns, such as `{{var.run_id}}` before a run has a `run_id`, must not accidentally broaden access. A pattern containing an unresolved variable should match nothing, and the block reason should make the missing variable diagnosable.
12. A blocked access attempt must return a PreToolUse block decision with a specific reason that includes the stage name, operation (`read` or `write`), requested path, and the policy reason. It must also log to the discovered project's `.stageflow/guard_violations.jsonl` or legacy audit directory according to project type.
13. The implementation must use the same project-root discovery as the Git-like CLI. Launching the hook from a nested subdirectory must still enforce the ancestor project's policy.
14. The implementation must not rely on prompt instructions for enforcement. Tests must call the hook/guard path directly and prove unauthorized access is blocked even if the tool itself is present in `tools`.
15. Do not claim `access` controls arbitrary shell/script file IO unless that is actually implemented. If `Bash`, `PowerShell`, or another script-running tool is allowed, the file-level `access` policy does not inspect or sandbox the script's internal reads/writes in this phase; only the command allowlist/pattern can constrain that tool call. This bypass is acceptable by design for now, but documentation and examples must state it honestly and avoid broad shell permissions in stages that depend on file access locks.
16. The visual editor may preserve and edit `access` data if straightforward, but do not let editor work become the blocker for core enforcement. At minimum, editor import/export must not delete unknown `access` fields when saving YAML. Because the current editor YAML model reconstructs stage objects, this likely requires adding an `extra`/unknown-fields preservation path rather than only adding `access` to TypeScript interfaces.
17. Add a small demo workflow update or example showing `task_plan.md` checklist enforcement with `file_not_contains` for unchecked `- [ ]` tasks. This is separate from access control but should demonstrate how `verify -> done` can require all plan tasks to be checked off:

   ```yaml
   - file_not_contains:
       path: artifacts/runs/{{var.run_id}}/plan/task_plan.md
       pattern: '(?m)^\\s*-\\s\\[\\s\\]'
   ```

18. Tests must cover at least: allowed write to a run-scoped artifact; blocked write to unauthorized source file; blocked read of `.env`; `Read` not bypassing via always-allow; denied path overriding allow; missing path for a covered file tool fails closed when policy exists; `Grep`/`Glob` without an explicit search root in a restricted stage does not get project-wide access; unresolved `{{var.run_id}}` does not broaden access; allowed path with interpolated `{{var.run_id}}`; absolute path inside project; absolute path outside project; `..` traversal blocked; nested cwd uses project root; old workflows without `access` keep current behavior.

- [x] **task-128**: Define and validate the `access` policy schema. Extend schema/registry handling so stage `access` data is accepted and preserved as stage extra data. Document exact semantics for `access.read.allow`, `access.read.deny`, `access.write.allow`, and `access.write.deny`, including deny precedence, interpolation, and backward compatibility. Add schema/registry tests proving valid policies load, invalid shapes fail clearly, and unknown existing stage fields are not broken.
- [x] **task-129**: Implement core path policy evaluation. Add a small, unit-tested helper that resolves requested paths relative to the discovered project root, rejects project escapes, interpolates `{{var.*}}` from current state, evaluates glob rules cross-platform, handles single-file paths separately from directory/search-root paths, and returns a clear allow/block reason. Include tests for Windows separators, absolute paths, `..`, deny-over-allow, allow-only, deny-only, no-policy behavior, and directory/search-root scopes that would include denied files.
- [x] **task-130**: Enforce `access` in the real `stageflow hook` entrypoint. Wire the path policy into `cmd_hook` for `Read`, `Write`, `Edit`, `MultiEdit`, `NotebookEdit`, and known `Grep`/`Glob` path inputs. The hook must still apply stage `tools` first, then apply file access policy. `Read` must not return early from `ALWAYS_ALLOW_TOOLS` when an active stage has `access.read`; denied reads must be blocked. Covered file tools with missing path fields must fail closed when the relevant access section exists. Search tools with omitted path/search root must not receive project-wide access in a restricted stage. Add hook-level tests using simulated Claude Code PreToolUse JSON for allowed and blocked reads/writes/searches from both project root and nested cwd.
- [x] **task-131**: Reconcile or remove duplicate guard behavior. `stageflow/core/guard.py` currently has partial write-path protection that is not the same as the global `stageflow hook` path. Unify the behavior so programmatic `StageGuard` and CLI hook enforce the same policy, or make one delegate to the other. Preserve existing tests where behavior is still intentional, update tests where semantics change, and avoid two divergent access-control implementations.
- [x] **task-132**: Preserve `access` through editor import/export. The visual editor must not silently drop stage-level `access` policy fields when loading and saving YAML. If full visual controls are not implemented yet, preserve unknown stage extra fields losslessly enough that opening the editor and clicking Save does not remove access policy; merely adding `access?: ...` to a parsed type is insufficient if `exportToYaml()` still reconstructs stages without those fields. Add focused frontend tests for YAML round-trip preservation.
- [x] **task-133**: Add checklist-completion condition demo. Update or add an example workflow showing `verify -> done` blocked until `task_plan.md` has no unchecked `- [ ]` items, using `file_not_contains`. Add tests or a small demo script proving unchecked tasks block completion and checked tasks allow completion.
- [x] **task-134**: Add staged verification for file access control. Create layered tests that increase difficulty instead of one monolithic test: schema load, policy helper, StageGuard direct check, `stageflow hook` from project root, hook from nested cwd, Windows/absolute path cases, editor round-trip preservation, and old-workflow backward compatibility. Record exact commands and expected results in docs.

---

## 图例

| 符号 | 含义 |
|------|------|
| `[ ]` | 待执行 — Ralph 取第一个执行 |
| `[x]` | 已完成 |
| `[!]` | 阻塞需人工介入 |

## Ralph 执行规则

1. **每循环一个任务** — 找第一个 `[ ]`，执行，标记 `[x]`
2. **提交规范** — `ralph: <task-id> — <summary>`
3. **状态报告** — 结束时输出 `---RALPH_STATUS---` 块
4. **失败 3 次** → 标记 `[!]` + 阻塞原因，继续下一个
5. **实现任务必须含测试**（纯文档/调研任务除外）
6. **不要修改** `.ralph/` 和 `.ralphrc`（除 fix_plan.md 的 checkbox）
