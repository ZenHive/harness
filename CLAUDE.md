# harness — CLAUDE.md

**Repo:** [github.com/ZenHive/harness](https://github.com/ZenHive/harness) (public, default branch `development`).

## Always-on includes (core only)

@~/.claude/includes/critical-rules.md
@~/.claude/includes/code-style.md
@~/.claude/includes/rmap.md

> **Trimmed 2026-05-30.** The previous version `@`-imported 14 includes + the 43 KB harness-driver SKILL (~44k tokens always-on), which drove compulsive re-reading on Opus 4.8. The eager floor is now the three above — `critical-rules` (guardrails), `code-style` (KPIs), `rmap` (roadmap decision layer, used every session). `response-conventions` is inherited from `~/.claude/CLAUDE.md`, not re-imported here. Everything else is **load-on-demand** — pull it only when the trigger matches.

## Load-on-demand (don't auto-load — read the file or invoke the skill when the trigger hits)

| When you need… | Load |
|---|---|
| `mix test.json` flags / jq recipes | Skill `elixir:ex-unit-json` |
| `mix dialyzer.json` flags / fix_hints | Skill `elixir:dialyzer-json` |
| `mix` / `ex_dna` / `ex_ast` command surface | Skill `elixir:development-commands` |
| rmap CLI: status/score/new/render/delegate | Skill `task-driver:rmap` |
| D/B/U scoring, ceremony floor, task-writing | Skill `elixir:roadmap-planning` + `@~/.claude/includes/task-writing.md` |
| Session-per-phase / batched-execution / evaluator-separation rules | `@~/.claude/includes/workflow-philosophy.md` |
| Worktree-per-branch workflow | `@~/.claude/includes/worktree-workflow.md` |
| Driving harness as a consumer (dispatch patterns, result shapes) | `@skills/harness-driver/SKILL.md` |
| Phoenix project setup / gen.auth | Skill `phoenix:phoenix-setup` |
| The "message across instances" (philosophical anchor) | `@~/.claude/includes/across-instances.md` |

**Situational skills** (invoke via Skill tool when trigger matches; don't auto-load): `elixir:reach` (PDG/SDG, `mix reach.otp`), `elixir:web-command` (browser/dashboard work), `elixir:agent-economy` (descripex surface), `elixir:elixir-setup` (dep-stack / alias edits).

## Elixir methodology (the non-obvious mandates — compressed from development-philosophy.md)

The full include is verbose and mostly restates mainstream Elixir. These are the bits the model would otherwise get wrong:

- **`@spec` on every function — `def` AND `defp`.** Not the community publics-only default. Configure `{Credo.Check.Readability.Specs, [include_defp: true]}`. Suppress macro-generated `defp` per-callsite, don't drop the check.
- **Doctests are documentation, not tests.** Happy-path / API-shape examples only. Edge cases, boundaries, unions, error paths → ExUnit `describe` blocks. A second doctest "to cover the empty case" is the failure mode — write an assertion instead.
- **`TODO:` prefix for all temporary code / "for now" / "in production" notes** so Credo tracks the debt. No prefix = invisible debt.
- **No IO in `@doc` examples.** `@doc` demonstrates API usage, not console output.
- **Library-first / precedent-first (anti-hedging).** Before calling a cost a real trade-off (case-conversion, option validation, wire-format friction) → check hex.pm. Before objecting a macro/DSL "could grow knobs" → name the specific Elixir precedent that fails the same way (Phoenix.Router, Ecto.Schema, NimbleOptions, Ash) or accept it. Generic FUD without a named failure pattern is hedging.
- **Internal-API markers:** `defp` first; `@doc false` for must-be-public-but-internal; `@moduledoc false` on a whole `MyLib.Internal` module; `@opaque` for tokens/handles whose structure is implementation detail.

## rmap is ours

The `rmap` CLI (the roadmap substrate `roadmap/tasks.toml` uses) is a sibling Rust project we own at `../rmap/` (`/Users/efries/_DATA/code/rmap/`). If the roadmap workflow needs a CLI change — new field, query, render, or `delegate --to` target — edit it there; don't work around a gap in harness. The `task-driver:rmap` skill is the usage contract; `../rmap/` is the source.

**AI driver surface (canonical for orchestrators):** `@skills/harness-driver/SKILL.md` — **load on demand** when driving harness as a consumer. Stable contract for delegation patterns, non-delegatable handling, result interpretation, sharp edges. Any change to public driver surfaces must update it.

## Commands

Toolchain pinned by `.tool-versions`: **Elixir 1.18.4-otp-27** (asdf). Postgres required for the Oban dispatch layer.

| Task | Command |
|---|---|
| Run the node | `iex -S mix` — boots the app, Oban (Postgres), and the dashboard on `http://localhost:4018` (routes `/harness`, `/harness/oban`, `/harness/mcp`, `/tidewave/mcp`). **Long-lived; the user starts it manually — don't boot it yourself.** |
| First-time DB | `mix ecto.create && mix ecto.migrate` (one migration: the Oban jobs table). DB name/user overridable via `HARNESS_DB_NAME` / `HARNESS_DB_USER` (defaults `harness_dev`, `$USER`). |
| Tests | `mix test.json` — AI-friendly JSON output; **use over bare `mix test`** (load `elixir:ex-unit-json` for flags/jq). `:integration` tests (real agent CLIs, live DB) are **excluded by default** — add `--include integration`. |
| Single test | `mix test.json test/harness/run_test.exs:42` · re-run only failures: `mix test.json --failed` · coverage: `--cover`. |
| Fast gate | `mix check.fast` — `format --check-formatted` + `compile --warnings-as-errors` + `credo --strict`. |
| Pre-commit gate | `mix precommit` — adds `doctor --raise`, `test.json --cover --cover-threshold 80 --exclude integration`, `sobelow`. Hook-bound (180s); **dialyzer is deliberately not here** (cold-PLT timeout). |
| Before PR / handoff | `mix precommit.full` — `precommit` + `dialyzer.json`. CI mirror (`.github/workflows/harness.yml`). |

**Per-edit hooks already run this stack** (`format`, `compile`, `test.json`, `credo`, `dialyzer.json`, `sobelow`, `doctor`) on every touched file — don't re-run a check the hook just graded. Full-suite `precommit.full` earns its cost only before a PR/merge, after `mix deps.get`, or on a branch switch (see global CLAUDE.md § "Don't Re-Run Hook-Driven Checks").

## What This Is

`harness` is an OTP-native Elixir engine an **AI orchestrator drives end to end**: pull a task from the rmap roadmap → dispatch to a **headless coding agent** (Claude Code, Cursor, Codex, Grok, Antigravity, Pi) in an isolated git worktree → run the target project's own check stack against the result → report a *verified* outcome. Consumer surfaces: Elixir API (IEx / tidewave / another BEAM process), the Phoenix LiveView dashboard, and an MCP server. It is a long-running OTP node that orchestrates **N registered target projects** (Elixir, Rust, anything with a shell-driven check stack) concurrently.

**Primary user is an AI agent, not a human** — harness is the OTP-native automation of the delegate → verify → repair loop this repo runs by hand via the `cloud-delegation` skills.

**Not a wrapper around one agent.** The `AgentAdapter` behaviour (Task 3) is a deliberately thin contract: *invoke* an agent, *capture its raw output*, declare capabilities — nothing more. **No normalized event model**: the consumer is an AI that reads each agent's raw JSON natively; harness decides "did the job succeed?" from its **own verification stack**, never from the agent's self-reported result.

## Architecture

- **Elixir / OTP, not TypeScript.** harness *is* N concurrent supervised agent runs needing crash isolation, timeouts, retries, observable state. One run = one supervised `gen_statem`; one batch = a `DynamicSupervisor`.
- **Core loop.** rmap task → dispatch to headless agent in isolated worktree → run target's check stack → green ⇒ done, red ⇒ repair-or-report. The verification stack (not the agent) is the grader — implementer/evaluator separation.
- **Thin adapter pattern.** One adapter per agent: invocation + raw capture + capability declaration. Behaviour `Harness.AgentAdapter` — required callbacks `capabilities/0` + `rule_channel/0` + `build_command/1`; `classify_message/2` + `terminate/1` default via `use Harness.AgentAdapter` + defoverridable. `AgentAdapter.invoke/2` does the generic Port spawn. `build_command/1` threads caller-controlled env (`Invocation.env`, set/scrub pairs → Port, Task 25). Harness-owned rules delivered ahead of `build_command/1` by `AgentAdapter.attach_rules/2` (Task 39), dispatching on `c:rule_channel/0`: `:system_prompt_file` (Claude), `:codex_ephemeral_file` (Codex/Pi), `:cursor_ephemeral_file` (Cursor), `:prompt_preamble` (Grok/Antigravity), `:none` (test doubles). Every adapter must pass `Harness.AgentAdapter.ConformanceCase` **unchanged** — a leak gets fixed in the behaviour, not patched in the adapter.
- **No agent-output parsing.** Raw passthrough is simpler *and* more robust — agents ship 40+ releases; a JSON-format change is absorbed by the AI reading the transcript, not by breaking a normalization layer.
- **Path discipline:** raw-output capture is hot-path-adjacent (allocation-light); run/batch lifecycle is warm-path OTP state; dashboard / MCP is cold-path.
- **Multi-project federation (shipped, v0_5).** `%Harness.Project{}` (Task 46) carries `source` (`{:local, dir}` or `{:github, url}` — Task 47), `check_stacks` (list of declarative `%Harness.CheckStack{}` — Task 44; Elixir + Rust presets, Tasks 44/45), `roadmap_path`, `concurrency_cap`. **Multi-language monorepos** (Task 92): worktree is always repo-root-granular, so each stack has a `workdir` (relative to worktree root); `Harness.Verification.run/2` runs each stack's checks in its own subdir and flattens to one verdict (green iff all green). Single-language = one stack with `workdir: ""`; singular `preset:`/`check_stack:` still works via back-compat. `Harness.ProjectRegistry` GenServer holds them. **Merge-bar reconciliation (Task 97):** a green `:elixir` preset verdict can still be unmergeable under the project's own `mix precommit` (the Task 94 gap: coverage 80 gate vs measured 75.92%). The `:elixir_precommit` preset mirrors that mergeable bar — adds `format --check-formatted`, `compile --warnings-as-errors`, a coverage threshold on `test`, and `doctor --raise` — so a project opts into "verdict ⇒ mergeable" via `preset: {:elixir_precommit, cover_threshold: 80, exclude: [:integration]}`. The harness self-project registers against it; `:elixir` stays the lighter default.
- **Oban = dispatch layer** (Task 48): queue-per-project gives per-project concurrency caps + restart resilience (jobs survive BEAM death in Postgres). `Oban.Plugins.Cron` (Task 51) enables autonomous roadmap polling. Dashboard (Task 50): `Harness.Dashboard.Endpoint` standalone Bandit on **4018** (conditional behind `:dashboard, :enabled` + `Code.ensure_loaded?(Bandit)` so mountable consumers aren't forced into a 2nd HTTP server), Oban Web at `/harness/oban`, MCP at `/harness/mcp`, Tidewave MCP in dev — all on the one port.

## Orchestration Library — Build a Thin Core (settled, Task 2)

Core is textbook OTP (Port per run, `gen_statem` per run, `DynamicSupervisor` for batches). Adopting a niche orchestration lib adds risk, not leverage. Evaluated `opal`, `gen_agent(_ensemble)`, `altar_ai`, `ex_mcp`, and SDKs `claude_code`/`codex_sdk` — **outcome: build thin core, adopt none, uniform Ports.** Full rationale: `docs/orchestration-library-evaluation.md`.

- **None of the orchestration libs spawns/supervises an external OS process** — no Port in any of them; they coordinate *in-process* LLM agents, harness orchestrates *external* headless CLIs.
- **`claude_code` / `codex_sdk` are CLI wrappers**, not native reimplementations. An SDK's headline value is a normalized event model, which harness's raw-passthrough design deliberately discards. So **uniform Ports for every adapter**.
- **Cold-path surface = dashboard + Oban Web + MCP, all on one Bandit.** Mountable into a consumer Phoenix endpoint or standalone. MCP (`Harness.Dashboard.MCPServer`, on `anubis_mcp`) exposes the descripex-`api()`-annotated driver surface (`Harness.Manifest`) as MCP JSON-RPC 2.0 over Streamable HTTP at `/harness/mcp`. `Harness.Chat.Tools` is the single source of truth for both the in-process chat dispatcher (`Harness.Chat.Session`) and the MCP surface. `Harness.Roadmap.list/2` + `next_bundle/1` let the orchestrator browse a registered project's roadmap as structured data. `Harness.Playbooks` layers orchestration recipes as compile-time-embedded `priv/playbooks/*.md`.
- **Oban = queue + persistence + cron, NOT a worker engine.** It *wraps* `Harness.Run` gen_statem: `Harness.Run.Worker` takes `{project_name, item_id, adapter_module}`, spawns the gen_statem, threads terminal state into Oban's contract. gen_statem stays load-bearing (runs are minutes-to-hours with rich live state).
- **Dispatch retry vs in-run retry — keep separate.** Oban owns dispatch-level persistence/retry (quota/transient → `{:snooze,_}`). The Task-10 retry policy inside `Harness.Run` owns the repair loop after a red verdict. Open-source Oban has no cross-queue global cap; effective ceiling = sum of `project_<name>` queue limits.
- **`Harness.AgentRegistry` is a soft hint, not a contract** (Task 40, option (b)). Unavailability lives in GenServer state only — no persistence/TTL; restart clears it **by design**. It's a *latency optimization*; *correctness* lives in Oban. Rationale: `lib/harness/agent_registry.ex` `@moduledoc`.

## Agent Headless Entry Points (domain reference)

| Agent | Headless invocation | Raw output format |
|---|---|---|
| Claude Code | `claude -p` | `--output-format stream-json` |
| Cursor | `cursor-agent -p` | `--output-format stream-json` |
| Codex | `codex exec` | `--json` |
| Grok | `grok -p` / `agent` subcommand | `--output-format streaming-json` |
| Antigravity | `agy -p` | none (plain text) |
| Pi (pi.dev) | `pi -p` | `--mode json` |

All six driven over OTP Ports — uniform, no per-agent SDK. harness captures raw, never parses/normalizes. **Exit code is unreliable**: derive *termination* from Port close + timeout guard; derive *success* from the verification stack — never `$?`, never the agent's self-report.

**Two-axis adapter contract** (don't conflate):
- **Renderable vs executable**: `rmap delegate --to` now renders a native prompt for all six adapters (`claude`/`codex`/`cursor`/`grok`/`antigravity`/`pi`), so each is a first-class `Roadmap.ingest(agent: …)` target dispatched directly on its own adapter — the old non-delegatable two-step is gone. rmap can also render `droid`, but harness has **no Droid adapter**, so `:droid` is rejected at the ingest/dispatch boundary (`{:invalid_agent, :droid}` / `{:unknown_adapter, "droid"}`). Adding an executor is two-sided: an rmap-lib `--to` target (the rmap binary is ours, `../rmap/` — already done for `droid`) **plus** a harness `AgentAdapter` listed in `Roadmap`'s `@valid_agents`.
- **Worktree isolation**: only `Antigravity` declares `worktree_isolation: false` (`agy` resolves workspace via git-common-dir, ignoring Port `cwd` — Task 32); the `Harness.Worktree.Isolation` guard refuses worktree-isolated dispatch on a non-isolating adapter and snapshots the checkout porcelain mid-run to trap pollution. Codex's equivalent regression (Task 41) is resolved (`codex exec --cd`).

## Reach Is in the Dep Stack

Core is OTP-dense. `mix reach.otp` (state-machine analysis, dead replies, missing handlers, supervision topology) and `Reach.independent?` are on-point. Reach is a dev/test dep (`runtime: false`); invoke the `elixir:reach` skill for OTP introspection / static analysis here.

## Status

**ROADMAP.md (rendered from `roadmap/tasks.toml` by `rmap`) is the live source of truth — start every session with `rmap next`.** High-level snapshot, not a changelog; per-task history lives in `tasks.toml` and `.remember/`.

- **Bootstrap (hand-built):** Tasks 1–8, 23, 24.
- **Phases 1–4 (dogfooded):** all 6 adapters, conformance suite (12), resilience bundle (9/10/11), caller-controlled env (25), non-delegatable contract (31), rule injection (39), capability/availability registry (16/40), StatusView (18), structured logging (19), AuditReview grader (58).
- **Phase 7 / v0_5 (multi-project + dashboard, hand-built):** CheckStack + presets (44/45), Project + ProjectRegistry (46), GitHub sources (47), template (49), Oban dispatch (48), Cron poller (51), dashboard + Oban Web on 4018 (50).
- **Phase 9 / v0_7 (chat orchestrator):** Manifest (75), Chat.Session (76), MCP server on anubis_mcp (79), Chat.Claude subscription-OAuth backend (82), ChatLive + tokens (78). Task 77 (hand-rolled Anthropic client) **deleted as superseded** — violated "Claude subscription, not API" + library-first. **Library-first rule reasserted.**
- **In progress (v0_8/v0_9):** dashboard LiveViews, flat `dispatch__task`, run kill button (94), per-stack `workdir` (92), chat persistence (93), autonomous merge-train lander (100). Confirm specifics via `rmap next` — this list drifts.

## Dogfooding — harness Builds harness

From the core loop onward, harness is developed *by* harness. **Once bootstrap is `done`, every remaining pending task is delivered by dispatching it through harness.** Hand-build only what harness cannot yet do for itself. Runbook: `docs/dogfooding-workflow.md`. Driver reference: `@skills/harness-driver/SKILL.md` (load on demand; changes to `AgentAdapter.*` / `Run.Supervisor` / `Batch` / `Roadmap` / Invocation/result shapes must update it).

- **Roadmap = harness's own test corpus.** A task harness fails to deliver is a harness bug, filed via `rmap new`, not worked around by hand-building.
- **Verification stays separate.** Dispatched agent = implementer; harness's check stack = grader. Done = verification green, never the agent's self-report.
- **Repair loop landed (9/10/11).** Red verdict isn't stop-the-line: harness resumes the agent with failing checks fed back, re-grades up to `:max_repair_attempts`.
- **Hand-built exceptions:**
  - *Scaffolding that reshapes harness's own runtime* (supervision tree, dep stack, Endpoint) **while the verification stack itself is in flux**. A new phase that only adds features on stable surfaces does **not** earn a hand-build window.
  - *Tiny tasks* — ALL of (a) D≤2, (b) ≤30 LOC across ≤3 files, (c) no harness-surface change. Fail any → dispatch. When in doubt, dispatch.
  - *UI / LiveView / heex / CSS work* — hand-build via tidewave + browser, not headless dispatch (headless agents idle-timeout with no visual reward signal).
- **Multi-project autonomy (46/48/51):** dogfooding extends to N registered projects, each with its own check stack + `roadmap_path`; with cron enabled it runs unattended.
