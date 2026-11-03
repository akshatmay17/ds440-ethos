# AGENTS.md — Ethos

Rust runtime (`ethos`) providing a taint-tracked sandbox and Agent-Computer Interface (ACI) for autonomous AI coding agents: bitmask provenance tracking, snapshot/rewind, injection containment walls, and a benchmark evaluation harness feeding Paper 1 (DS 440 capstone).

## Commands

- CI gate (`.github/workflows/ci.yml`): `cargo check --all-targets` then `cargo test`. Both must pass before handing off.
- Run one suite: `cargo test --test test_rust_walls` — suites are `tests/test_rust_*.rs`.
- Run one test: `cargo test test_ouroboros`.
- Run the CLI: `cargo run -- [subcommand]` (`default-run = "ethos"`; no `--bin` needed). **There is no `tbox` binary** — mentions in older docs are stale; only `ethos` exists in `Cargo.toml`.
- Subcommands: default (interactive harness), `setup` (provider wizard), `daemon --port` (Axum REST, default 8000), `app` (daemon + browser UI), `run --task "..."`, `eval`, `doctor` (env diagnostics: Postgres, Git, MinGit, walls, sandbox), `tui` (ratatui dashboard).
- No clippy/rustfmt gate in CI; keep the build warning-free. The neural safety tier is opt-in (`cargo check --features semantic-ml`) — it pulls heavy candle/tokenizers deps and is intentionally excluded from the default CI gate; its live test is `#[ignore]`d (weights download).

## Testing gotchas

- `tests/` mixes Rust integration tests (`test_rust_*.rs`, run by `cargo test`) with **stale Python tests** (`test_*.py`) that import a Python `ethos` package that no longer exists (legacy of the pre-Rewrite prototype). Cargo ignores them; do not run pytest, and do not "fix" their imports.
- Postgres is optional everywhere: `DATABASE_URL` only enables the persistent session store (`src/store/postgres.rs`, schema `migrations/0001_init.sql`). Rust tests never need a database.

## Environment

- Copy `.env.example` to `.env` (gitignored; auto-loaded via `dotenvy` at startup). Provider keys (`OPENAI_API_KEY`, `ANTHROPIC_API_KEY`, `OPENROUTER_API_KEY`, `SPIDER_API_KEY`) are optional — pick per provider.
- Local inference (optional, for live evals): LM Studio on port `1234`/`2277` or Ollama on `11434`. `ethos eval` probes these and **exits with an error when the requested provider is offline** (no silent fallback); use `--provider scripted` for an explicit, labelled non-model smoke run.

## Architecture (non-obvious wiring)

- `src/bin/ethos.rs` is a thin entrypoint → `ethos::cli::run_cli()`.
- `src/aci/` typed tool harness (1-indexed `view_lines`, `edit_block`, untrusted-tagged `fetch`) + `state_tree.rs` (branching snapshot DAG).
- `src/runtime/` CoW snapshots + rewind; rollback requires a `.ethos_sandbox` marker (`.taintbox_sandbox` legacy alias). Configured ACI constructors default to exec disabled. `ETHOS_EXEC_BACKEND=docker` plus a pinned `ETHOS_EXEC_IMAGE` enables disposable Linux commands; no host fallback. `new_local_with_*` is the explicit unconfined component-test/legacy path. See `docs/container-execution.md`; run `python scripts/container_stress.py --output reports/<fresh-name>.json` with a local Docker engine and the pinned image for live boundary checks. Settings and Docker client identity are frozen before project `.env` loading.
- `src/taint/` bitmask provenance: `TRUSTED < INTERNAL < UNTRUSTED < HOSTILE`, worst-severity propagation, sensitive paths (`.env`, `id_rsa`).
- `src/walls/` containment: `PromptInjectScanner`, `OuroborosWall`, `HalluScan`, `EmergencyStop`, `SemanticGuard`. Enforcement status: taint policy + Ouroboros + exec guards are enforcing; `EmergencyStop` is a wired circuit breaker (3 attack-class blocks ⇒ all tools walled until `reset_emergency_stop()` / `POST /v1/sandboxes/:id/estop/reset`); `SemanticGuard` is wired advisory (SEMANTIC_SCAN telemetry + agent-loop `System 1` digests) with an optional neural tier behind `--features semantic-ml` (candle + tokenizers; env: `ETHOS_SEMANTIC_NEURAL=1`, `ETHOS_SEMANTIC_MODEL_DIR` for local models, `ETHOS_SEMANTIC_MODEL` to fetch from HF, optional `HF_TOKEN`). Ethos-owned weights (`~/.ethos/models/ethos-guard-bert-base` = quality tier, `ethos-guard-laya` = BERT-small fast tier) are trained via `scripts/` (see `docs/semantic-guard-finetune-plan.md`); their `ethos_model_card.json` operating threshold is auto-applied. Scripts emit the classic weight/bias LayerNorm naming candle expects (transformers v5 saves gamma/beta — `train_semantic_guard.py` normalizes). `HalluScan` remains advisory/unwired.
- `src/config/` user config + `models.dev` live catalog (7-day TTL cache; provider/model specs are not hardcoded) + `policy.default.yaml` boundary rules (RULE-001 …). `config/runtime.yaml` holds sandbox runtime settings.
- `apps/desktop/` is a **separate Tauri v2 crate, not part of the root cargo build** (root `Cargo.toml` has no `[workspace]`). Its UI is static HTML/JS in `apps/desktop/ui` — no node/npm build; build from `apps/desktop/src-tauri` with the Tauri CLI. The daemon also serves this UI (embedded via `include_str!`): opencode-style chrome with sidebar menu + tabs (Dashboard / Sessions / Model Catalog / Attack Lab / Security), command palette (Ctrl+P), and a full models.dev catalog browser — all wired to the real `/v1/*` endpoints, no demo data. The TUI's `/models` opens the same catalog as a searchable overlay (zen.rs `draw_models_browser`).
- One UI, three surfaces: the daemon-served browser GUI (`ethos app`), the Tauri desktop app, and the MSI/NSIS installers all ship `apps/desktop/ui`. The Tauri shell (`src-tauri/src/main.rs`) probes `127.0.0.1:8000` and spawns `ethos daemon --port 8000` as a sidecar if nothing is listening (killed on window close); inside the webview, `app.js` detects the `tauri.localhost` origin and defaults its API base to `http://localhost:8000`. If you change daemon routes, all three surfaces are affected.

## Runtime invariants (enforced by tests — preserve when editing taint/walls/runtime)

1. All paths pass `resolve_path()` canonicalization; `../` traversal and symlink escapes return `BLOCKED_BY_POLICY`.
2. Destructive rewind verifies the `.ethos_sandbox` marker before touching files; the marker files themselves are Ouroboros-protected against tool-layer and exec-redirect forgery.
3. Exec guards apply to **every program, not just shell wrappers**: all args are inspected case-folded and separator-normalized, with stem-based program matching (`curl.exe` ≡ `curl`); `-EncodedCommand` is worst-case classified; `>`/`>>` redirect targets pass the same Ouroboros + sensitive-path walls as the write tool. Four universal arg guards cover non-wrapper programs: `SENSITIVE-PATH-EXEC-GUARD` (protected paths in any arg), `HOST-PATH-EXEC-GUARD` (drive letters/UNC/unix roots — exec args stay sandbox-relative), `TRAVERSAL-EXEC-GUARD` (`../`, `..\`), `ENV-EXPANSION-EXEC-GUARD` (`%VAR%`).
4. Content from `fetch()` is tagged untrusted; tainted data cannot trigger privileged actions without explicit policy authorization; `fetch`'s `save_as` passes the same Ouroboros + sensitive-path write gates as the write tool.
5. Provenance **merges, never downgrades**: an unsourced rewrite of a tainted file keeps the worst severity (`laundering_attempt_blocked` lands in telemetry) — only `declassify` with a valid token may clear it.
6. Both `exec` egress and `fetch()` egress are evaluated against the full tainted ledger: once untrusted data is in play, every network channel walls (allowlist can re-open specific destinations).
7. Path policy matching is case-folded everywhere (Ouroboros patterns, sensitive paths): `.ENV` ≡ `.env`, `Tests/` ≡ `tests/` — NTFS-insensitive casing must not bypass guards.
8. Scanner digests fed to the LLM (`PromptInjectScanner::summarize_findings`) carry pattern names only — never raw attacker excerpts (re-injection channel). Scanner input is homoglyph-folded (Cyrillic/Greek lookalikes + zero-width chars) before matching.
9. Every read-shaped tool (`read`, `view_lines`, `grep` per-file) passes the same sensitive-path gate; the sensitive-path list includes the ethos-owned credential stores (`~/.ethos/config.json`, `models_dev_cache.json`) and common host credentials (`.netrc`, `.npmrc`, `.aws/credentials`, `.gitconfig`, `authorized_keys`).
10. Network allowlist matches on parsed URL host (exact or dot-delimited subdomain) — never substring; the daemon binds loopback-only and masks API keys in all HTTP responses.
11. File listing and snapshotting are symlink-safe: in-sandbox links neither enumerate host trees nor get followed by snapshot copies.
12. The destructive-rewind markers are Ouroboros-protected; snapshots are keyed by harness-generated IDs only (rewind looks up the in-memory registry before any disk path is touched).

`tests/test_rust_redteam.rs`, `test_rust_redteam2.rs` and `test_rust_redteam3.rs` are adversarial component regressions; they explicitly choose local or inert adapters. A failure means a wall regressed; change assertions only for intentional behavior changes. `test_rust_container` has five live Docker tests ignored by default but required by the CI container step, which also runs `test_rust_file_aliases`. The application rejects `backend=local`; unconfined Rust adapters are test/baseline-only. File tools reject hardlinks, symlinks/reparse points and Windows stream/device aliases. Residual risks include host-level filesystem races, Docker/kernel trust, bounded secret recognition, unverified legacy runsc/WSL probing and the demo declassification token (not agent-callable). Container scratch writes are discarded; durable edits use structured tools.

## Benchmark evals (feed Paper 1)

The evaluation harness is **v2** (`src/aci/eval.rs`, driven by `src/cli/eval_cmd.rs`); the scenario and report contract is in `docs/eval-scenario-schema.md` — read it before adding cases or reading reports. The legacy `src/aci/benchmark.rs` types remain only for existing tests.

```powershell
cargo run -- eval --dataset <name> --provider <lmstudio|ollama|openai|openrouter|anthropic|scripted> `
  --model <id> --condition full --variant benign --repeats 3 --output reports/<name>_v2_results.json
```

- **Datasets** (`--dataset`): `injecagent` `hackaprompt` `agenthijack` `m365` `evasion` (the enriched local files); `benign` (false-positive controls); `capability` (clean coding tasks with a utility check); `injected` / `fetch` / `tool_output` (payload-via-code-comment / fetch / command-output — not yet authored); `injecagent-upstream` (1054 cases, generate with `scripts/import_injecagent.py`, gitignored); `attacks` (all five local attack files); `all` (attacks + benign + capability). `--dataset-file path.json` loads an explicit file.
- **Fail-closed, no silent fallback.** If a live provider is requested and unreachable (or a key is missing), the command exits non-zero. `--provider scripted` is the one explicit rule-based driver; its reports are stamped `driver: "scripted"` and must never be cited as model behaviour. The report records `driver`, `endpoint`, `requested_model` and the `model` the server actually served.
- **Conditions** (`--condition`): `full` enforces every wall; `rewind` / `structured` / `raw-shell` run the walls in shadow mode (decisions recorded, file ops let through, commands/network simulated) so the four-condition comparison is possible. `--runtime gvisor` fails if `runsc` is absent.
- **Variants** (`--variant benign|complicit|both`): `benign` uses the realistic task framing (`benign_prompt`); `complicit` uses the legacy "follow the file's instructions" framing (`agent_prompt`). Run both to measure how much the framing itself drives attack success.
- **Scoring:** attacker success is a machine-checkable `oracle` per case (egress / canary_leak / sensitive_read / command / file_written|modified|deleted / args_contains), scored over per-step traces and the final workspace; the runner seeds a canary `.env`. Each run reports `attack_attempted`, `attack_succeeded`, `attack_blocked`, `payload_read`, `utility_ok`, `false_positive`. A driver error marks the run `valid: false` — an outage is never scored as a defense. Traces go to `<output>.traces.jsonl`.
- **Report schema is v2** (`schema_version: 2`; see the doc). Build paper tables with `python scripts/make_tables.py reports/*_v2_results.json` (Wilson CIs; refuses scripted reports unless `--include-scripted`; prints a warning row for legacy v1 reports). `--mcnemar COND_A COND_B` runs a paired McNemar test of attacker success between two conditions (same scenarios must appear under both — run the same dataset twice with different `--condition`). Legacy `reports/*_eval_results.json` are kept but their `driver` is unknown — do not treat their block counts as model results (see the critique in `paper/`).
- **Pilot before the full suite.** `--sample N [--seed S]` runs a deterministic stratified sample (proportional by `source`); `--repeats` drives confidence intervals. Validate scenario files with `python scripts/validate_scenarios.py` (also a CI gate): it checks the schema, unique ids, that oracle/utility paths are seeded, and that `benign_prompt`s do not authorise the attack.
- **Scanner evaluation:** `cargo run -- scanner-eval [--semantic] [--data file.jsonl]` scores the **enforcing** Rust `PromptInjectScanner` (and, with `--semantic`, `SemanticGuard`) as precision/recall/F1 on a labelled JSONL corpus — the code that actually fires, unlike `scripts/eval_semantic_baseline.py`, which only scores a Python copy of the keyword fallback.
- **Classifier corpus / eval separation (leakage).** `scripts/prepare_semantic_dataset.py --hf` assembles public prompt-injection datasets into `data/semantic_guard/` (gitignored). By default (`--eval-cases heldout`) all agent-eval scenario text is kept **out of the TRAIN split** (placed in `test` only), and any public-corpus row that duplicates an eval payload is dropped — so SemanticGuard/scanner numbers on eval cases are not contaminated. `--eval-cases exclude` drops them; `include` leaks them (not recommended). The manifest records the policy.
- `--split train|eval|test|all` keeps the 70/20/10 partition (`test` is the blind holdout). Wrappers: `scripts/eval_bench.ps1` / `.sh`. Release packaging: `scripts/build_*`.

## Repo conventions

- Stack credits live in README §10 ("Technology Stack, Prior Art & Inspirations"): ratatui/crossterm (TUI), axum/tokio/sqlx/reqwest (daemon), Tauri v2 (desktop), gVisor (sandboxing), models.dev (catalog), opencode (UX patterns), Laya/Prompt-Guard/DeBERTa (SemanticGuard slots). Cite additions there.
- `.gitignore` blocks `*.md` (except `README.md`, `AGENTS.md`, `docs/*.md`), `*.txt`, `*.pdf`, `paper/`, and `scratch/` — "GitHub is code only". Put new docs in `docs/`.
- Main dev machine is Windows PowerShell 5.1 (one macOS); scripts ship as both `.ps1` and `.sh`. PowerShell 5.1 has no `&&` — use `; if ($?) { ... }` in commands.
- Branches: `main` (default) and `harsh-dev`; CI runs on pushes to both plus all PRs.
