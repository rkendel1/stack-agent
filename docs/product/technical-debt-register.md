# Technical-debt register

Every TODO-like finding in the repository, classified. The goal is **zero unclassified debt**, which
is different from zero debt: the register lists known limitations and what happens to each. Real
work lives in [`coding-agent-production-roadmap.md`](coding-agent-production-roadmap.md); this file
points there rather than duplicating it.

Dated 2026-10-09; rows D-10, D-15, D-16, D-18, D-20 updated and D-33 to D-38 added on 2026-10-17 (stack-agent "harden runtime contracts" change; evidence in `../known-issues.md`). Rows D-05, D-06, D-08 and D-09 updated on 2026-10-20 (security findings: path policy, confinement, project lock, redaction, prompt-injection corpus), and D-19 the same day (durable work events through FeltDB). Method and counts are in section 1 so the audit can be repeated.

Dispositions: **1 Resolved now** (fixed in the change that introduced this file); **2 Production
defect** (a correctness, safety, reliability or data-integrity problem needing its own change);
**3 Deferred capability** (legitimate work not yet implemented; backlog item named); **4 Intentional
limitation** (explicitly accepted or a documented non-goal).

## 1. What was searched and what it found

Search: `TODO|FIXME|XXX|HACK|todo!(|unimplemented!(|placeholder|for now|temporary|workaround|stub|not
yet implemented|not implemented` over `*.rs`, `*.sh`, `*.yml`, `*.toml`, `*.md`; plus `#[ignore]`;
plus "not yet / future work / out of scope / known limitation / unverified / deferred / not supported /
intentionally" over docs and source comments (about 150 hits, read in context); plus a path and link
check of every repository path named in `README.md`, `AGENTS.md`, `docs/**` and crate READMEs; plus
`cargo clippy --workspace --all-targets` and `cargo check --workspace --all-targets`.

| Marker | Occurrences | Finding |
| --- | --- | --- |
| `TODO` / `FIXME` / `XXX` / `HACK` in code or docs | 2, both test data | `chip-project/tests/navigation.rs:33,255`: a `// TODO: gamma` line in a fixture file that the search test must find. Not debt |
| `todo!(` / `unimplemented!(` | 0 | none |
| `placeholder` | 1 | `chip-reasoning-corpus/src/corpus.rs:105`: documented design (every case carries the same placeholder graph state because the corpus has no architecture). Intentional, experiment crate |
| `stub` | 2 | `chip-cli/src/native.rs:337,347`: a `Stub` `LocalReasoner` inside `#[cfg(test)]`. Test double |
| `temporary` / `mktemp` | many | temp-file implementation details (`chip-project` atomic write, scripts). Not debt |
| `not implemented` | 2 | `README.md` (stale; see D-21, resolved) and `project-observation-boundary.md:184` (Decision Frontier; D-22) |
| `#[ignore]` | 2 | `chip-local-decision-train/tests/training.rs:190` (slow grid search, run in release) and `chip-laya-reasoner/tests/synthetic.rs:266` (a utility that writes a checkpoint). Both documented; neither hides a failing test |

The repository carries its debt as prose limitations, not TODO comments, so the substantive audit is
section 2.

## 2. Register

| ID | Finding | Location | Impact | Disposition | Follow-up |
| --- | --- | --- | --- | --- | --- |
| D-01 | Experiment and proof crates are linked unconditionally into the shipped `chip` binary, and its experiment/proof subcommands ship | `chip-cli/Cargo.toml`, `src/main.rs`; `crates.md` sections 5.1, 8 | The product binary carries unproven code and surface; larger binary; unclear support promise | 3 Deferred: making them opt-in features changes the CLI and needs approval | roadmap P2-D1 |
| D-02 | Duplicate experiments: `chip-wasm-reasoner` vs `chip-wasm-decision` pair; `chip-local-ml` vs `chip-laya-reasoner` | `crates/` | Maintenance cost; no recorded result separates them | 3 Deferred: remove once nobody needs the benchmark commands | roadmap P3-06 |
| D-03 | Product code renders the measurement through a demo module | `software_work.rs`, `verify.rs` -> `work_demo::measurement_json` | A product path depends on proof code; pinned as the only such coupling by `product_path.rs` | 3 Deferred: moving it is a refactor with no behaviour change | roadmap P2-D1 |
| D-04 | `ModelDecisionBoundary` tolerates one code fence around the whole reply | `chip-core/src/model_decision.rs`; `AGENTS.md` Invariant 6 | A narrow exception to "no repair" | 4 Intentional (documented, tested) | none |
| D-05 | A crash between temp file and rename can leave `.chip-write-*.tmp` | `chip-project/src/lib.rs` header | Stray file in the project after a crash | **Resolved 2026-10-20**: a work holds `ProjectLock` on the directory, and since only a lock holder writes temporary files, acquiring it removes every `.chip-write-*.tmp` (outside `.git`, `target`, `node_modules`; bounded at 50,000 entries) and `work` reports their paths on stderr (`chip-project/tests/lock.rs`) | roadmap P0-08 |
| D-06 | Path checks and the operation are not one atomic step (a root rewritten concurrently can race) | `chip-project/src/lib.rs` header | Time-of-check/time-of-use on a project another process mutates | **Resolved 2026-10-20 on Unix**: every operation is relative to directory descriptors opened with `O_NOFOLLOW` (`chip-project/src/confine.rs`), so the check and the use are one step; FIFOs and devices are refused on the open descriptor, hard-linked files are not read. The race tests in `chip-project/tests/confinement.rs` escape the root against the previous implementation and not against this one. Other platforms keep the path-based check (4 Intentional, single owner) | roadmap P0-06 |
| D-07 | Project tooling is not sandboxed: `project.write` + `pax.test` is code execution | `capabilities.md` G6; test `write_plus_test_is_code_execution_through_the_projects_own_tooling` | Hostile project or model-written code runs with the operator's permissions | 2 Production defect for any untrusted/hosted use; accepted for a local trusted developer | roadmap P0-06 (blocked on an isolating provider) |
| D-08 | File contents go to the provider; only `.git` and `.env*` are withheld | `chip-project` path rules; `capabilities.md` G8 | Secrets in other files can reach a hosted model | **Partially resolved 2026-10-20**: a default, case-folded deny-list of credential stores and files (`chip_project::policy::withheld`, fixtures in `chip-project/tests/fixtures/path-policy.json`) is withheld from every capability. Remaining **2 Production defect**: the list is not configurable, and a secret inside an ordinary source file still reaches the provider | roadmap P0-06 |
| D-09 | Repository content is untrusted input to the model; no document or test addresses prompt injection | docs (absence) | A file can try to steer the model; the decision boundary still refuses invalid decisions but nothing is claimed beyond that | **Partially resolved 2026-10-20**: the threat model is stated (`stack-agent/tests/prompt_injection.rs`: content is not filtered; obeying it gains nothing), protected execution and instruction surfaces are never written (`chip_project::policy::protected`), and an 18-case corpus (`tests/fixtures/prompt-injection.json`) pins that a scripted model obeying each injection executes nothing beyond its read. Remaining **3 Deferred**: no real model's susceptibility is measured | roadmap P0-06 |
| D-10 | Test tampering is invisible to the runtime | `coding-agent-evaluation.md` limit 2 | A green run achieved by weakening tests verifies | **Partially resolved 2026-10-17**: at acceptance (`WorkRuntime::run`, local environment), a passing run is refused if the work replaced a test file Git tracks (`tampered_test_files`; any replaced test file outside Git), or if the project changed outside any observed write after the run (`stale_test_evidence`). Remaining **2 Production defect**: tests inline in source files (`#[cfg(test)]`), weakened test configuration, and changes made and undone between run and acceptance are not detected | roadmap P1-V2 |
| D-11 | Completion cannot express feature acceptance | `coding-agent-evaluation.md` limit 1 | Work completes on the first fixed defect | 2 Production defect | roadmap P0-01 |
| D-12 | `inspect` answers are grounded, never verified | `capabilities.md` G1b | Exit 1 by design; no independent predicate exists | 3 Deferred | roadmap P2-C5 |
| D-13 | No repair budget, tier or human channel in `chip work`; an escalated run cannot resume | `coding-agent-evaluation.md` limit 3 | Hard tasks end at the first tier | 3 Deferred | roadmap P1-02, P1-04, P1-07 |
| D-14 | The handoff does not fit the 2,000-byte goal and is test-only | `coding-agent-evaluation.md` limit 4; `tests/coding_agent/packet.rs` | Escalation context is weaker in the product than in the harness | 3 Deferred | roadmap P1-03, P1-08 |
| D-15 | PAX counts are partial when `cargo test` is red | `coding-agent-evaluation.md` limit 7 | Misleading totals; not a verdict error | **Resolved 2026-10-17 on Chip's side**: the report marks counts `complete: false` unless the run passed, and a `passed` result whose counts show a failure or no passed test (skipped only) is not passing evidence (`PaxExecutionResult::is_passing_evidence`). PAX's own partial counting is unchanged (owner: PAX) | roadmap P1-V2 |
| D-16 | Cancellation of running work does not interrupt an execution in flight; no whole-work wall-clock limit | `service.rs`; `crates.md` section 5.2 | A stuck execution is not interrupted (a model call in flight is abandoned through FX since compute#90) | **Deadline resolved 2026-10-17** (`--deadline-secs`, `serve --work-deadline-secs`, checked before every model call and execution); CLI cancellation added (Ctrl-C/SIGTERM). Not interrupting an execution in flight stays **4 Intentional** (cooperative stop at the execution boundary; no thread abort); an execution with no timeout of its own can still outlive the deadline | roadmap P0-04 |
| D-17 | A request for a nonexistent capability exits in the same class as a safety-invariant violation | `capabilities.md` section 2 | Operators cannot tell a bad decision from a broken invariant | 3 Deferred: exit codes are a public interface | roadmap P0-04 |
| D-18 | Events are available only when a work ends; no streaming | `service.rs`; `crates.md` section 8 | Clients cannot observe progress | **Resolved 2026-10-17 for `serve`**: `GET /v1/work/{id}/events[?after=N]` returns the events recorded so far while the work runs (polling; nothing pushed, nothing replayed after exit). The CLI still prints one report at the end (3 Deferred) | roadmap P1-O3 |
| D-19 | No persistence, authentication or remote exposure in `chip serve` | README; `crates.md` section 10 | Restart forgets all work; local trusted clients only | **Persistence resolved 2026-10-20**: every `serve` work is a FeltDB task with its events and verdict, and a restarted service answers earlier ids from it (`docs/product/agent-state.md`). Authentication and remote exposure stay **4 Intentional** (local trusted clients only) | roadmap P3-01, P0-08 |
| D-20 | Tests return early when PAX, Compute, git or a model is absent, so a green run on a bare machine proves less | `crates.md` section 8 ("Skips look like passes") | False confidence | 3 Deferred: print a summary of skipped tests / require them in the release gate. Partly reduced 2026-10-17: CI installs PAX and sets `FX_REQUIRE_TLS_TESTS=1`; the new product, cancellation, exit-code and Wasm conformance tests use stand-ins and fail rather than skip | roadmap P2-D5 |
| D-21 | `README.md` said the project-observation boundary "is not implemented" although `project.observe` is | `README.md` | Contradicted `capabilities.md` | **1 Resolved now** | none |
| D-22 | The "Decision Frontier" is described as a direction but implemented nowhere | `project-observation-boundary.md` section 8 | A reader could assume it exists | 3 Deferred (the document says so explicitly) | roadmap P2-04 |
| D-23 | `project-observation-boundary.md` links `observe-benchmark.md`, which exists only on `origin/pax-observe-consumer` | `project-observation-boundary.md` section 10 | Dangling link; the keep/narrow/remove gate for `project.observe` has no result in this branch | **1 Resolved now** (link replaced by an accurate statement); the gate itself is 3 Deferred | roadmap P1-V5 |
| D-24 | No real-model run of `chip work`/`serve`/`verify` is recorded; the opt-in tests are not in CI | `capabilities.md` G10; `crates.md` section 8 | Effectiveness with a real model is unmeasured | 3 Deferred | roadmap P2-05 |
| D-25 | One release target (Linux x86_64), no signing, no evidence of a consumed release | `crates.md` sections 7, 8 | Distribution unverified | 3 Deferred | roadmap P1-O5, P2-D5 |
| D-26 | Escalated works are never evicted from `chip serve`, so that class is unbounded | `service.rs`; README "Retention of finished work" | Memory grows with unresolved escalations | 3 Deferred: needs a resolution mechanism (the service cannot tell resolved from pending) | roadmap P1-O1, P0-03 |
| D-27 | Evidence for an evicted work is gone (410 `work_expired`); evidence does not outlive retention | `service.rs` | A client that polls late loses the explanation | 4 Intentional (documented trade-off of bounded retention) | roadmap P1-V4 |
| D-28 | Adding `max_retained` to the public `Capacity` struct breaks struct-literal construction by embedders (`serve_in`); it broke `chip-cli/benches/baseline.rs`, which `cargo check --workspace` does not compile (only `--all-targets`/`cargo bench` do) | `chip-cli/src/service.rs`; `benches/baseline.rs` | CI's bench step would have failed; an embedder constructing `Capacity { .. }` must add a field or use `..Capacity::default()` | **1 Resolved now** for the in-repo caller (the bench); the compatibility change for external embedders is **4 Intentional** and recorded here | roadmap P2-D5 (API-compat note per release) |
| D-29 | Frozen `decision_state.rs` residue in `chip-core` (nothing in `Agent`/`run_work` reads it) | `chip-core/src/decision_state.rs` | Dead weight kept for experiment goldens | 4 Intentional (pinned by a test that the work loop does not use it) | none |
| D-30 | `chip-compute` is a legacy adapter, not an `EnvironmentProvider`; live runs need a real `compute` | `crates.md` | Frozen integration | 4 Intentional (FROZEN) | none |
| D-31 | Clippy reports about 50 style warnings across the workspace (lints such as `collapsible_if`, `clone` to slice, `assert_eq!` with a literal bool, `is_multiple_of`); none is a correctness lint | listed in section 3 | Noise; no behaviour impact | 3 Deferred: not suppressed and not mass-refactored here; one test-only unused import in `chip-core` and one needless `mut` in the retention bench were fixed | none (mechanical, fix per crate when touched) |
| D-33 | Exit codes differed by command (the one-shot prompt exited 1 for every error; `work` called any first-call model failure "unavailable") | `main.rs`, `software_work.rs`, `verify.rs` | Callers could not rely on one meaning per code | **Resolved 2026-10-17**: one mapping (`verify::exit_code`) for `work`, `verify`, the per-work `exit_status` of `serve` and the one-shot prompt; "unavailable" (3) is decided from the typed FX failure kind, not text (`tests/exit_codes.rs`) | none |
| D-34 | The native provider classified a body-read timeout by searching the error text for "timeout" | `fx-native-provider/src/provider.rs` | A reset connection whose message mentioned "timeout" was reported as a timeout | **Resolved 2026-10-17**: typed (`ureq::Error::Timeout` or `io::ErrorKind::TimedOut`) | none |
| D-35 | An HTTP error response was reported `possibly_sent`, contradicting FX's definition of `confirmed_response` ("a response from the provider was observed") | `fx-native-provider/src/provider.rs` | Delivery certainty was less precise than the contract | **Resolved 2026-10-17**: non-2xx and non-stream 2xx responses are `confirmed_response` (still failures); tests updated with the contract | none |
| D-36 | A cancelled model call's remote state (FX `RemoteCancellation`) was dropped by the Chip adapter | `chip-fx/src/mapping.rs` | Callers could not see that a stop was unconfirmed | **Resolved 2026-10-17**: carried as `remote_cancellation` into `WorkOutcome::Cancelled` and the `WorkCancelled` event | none |
| D-37 | The `fx-host` and `chip-wasm-host` Wasm modules were compiled but never executed in this repository | `crates.md`; `known-issues.md` (G) | The Wasm ABI was unverified here | **Resolved 2026-10-17 for the Rust/`wasmi` host with a host-played provider** (`chip-wasm-host/tests/wasmi_conformance.rs`); WASI, Wasmtime, Node/V8 and an in-Wasm provider bridge stay unsupported (3 Deferred) | none |
| D-38 | No host-defined feature-acceptance predicate can be supplied to `work`/`serve` | `software_work.rs` (`GoalKind`); D-11 | The same as D-11, recorded separately as an API decision | 3 Deferred: needs a product decision on how a host supplies and validates acceptance criteria (a new request field and its validation); not invented here | roadmap P0-01 |
| D-32 | The experiment crate's own limits: Journal payload files carry no checksum; the `durability` crate's lock file and resume-flush behaviour; redb default durability; one machine, synthetic workload, SIGKILL not power loss | `session-store-comparison.md` sections 3, 5, 9 | Only matters if a store is ever adopted | 4 Intentional (experiment findings, recorded) | roadmap P3-01 |

## 3. Clippy warnings, by location (D-31)

Counts from `cargo clippy --workspace --all-targets` on 2026-10-09 (not suppressed; lint names are
clippy's):
`chip-core/src/work.rs` 3x `collapsible_if`; `chip-core/tests/capability_surface.rs` 8x
`unnecessary clone` and 1x `collapsible_if`; `chip-core/src/decision_state.rs` 1x
`wrong_self_convention`; `chip-core/tests/*` 4 more (literal-bool assert, `expect` with a call,
`MutexGuard` held across await in `work_measurement.rs`, a `collapsible_if`); `chip-cli/src/main.rs`
2, `software_work.rs` 1, `work_demo.rs` 2, `horizon.rs` 2, `benches/baseline.rs` 2,
`tests/real_model_work.rs` 1; `chip-compute/tests` 3; `chip-project/src/lib.rs` 1; `chip-remote-env`
2; `chip-pax/tests` 1; `chip-graph/src/analyze.rs` 1; `chip-decision-corpus` 2;
`chip-local-decision-train` 3; `chip-wasm-reasoner/tests` 1; `chip-local-ml/tests` 1;
`chip-session-memory` 8 (experiment). The one with possible runtime meaning is the `MutexGuard` held
across an `.await` in `chip-core/tests/work_measurement.rs` (a test; tracked by D-31 until the test is
next touched).

## 4. What was resolved in the change that introduced this file

* D-21 README contradiction fixed; D-23 dangling link replaced; D-28 baseline bench repaired.
* Stale references corrected: `README.md` named another repository's paths
  (`crates/compute-rust-chip`, `docs/rust-chip.md`) without saying they are not in this one;
  `session-memory-experiment.md` named `crates/feltdb` (FeltDB's repository) as if local;
  the experiment documents did not say they were superseded or label their claims.
* `scripts/audit-dependencies.sh` now also enforces that no product crate reaches an experimental
  storage engine and that nothing depends on `chip-session-memory`.
* No TODO was deleted to reach a count; there were none to delete.

## 5. Verification snapshot (2026-10-09, Linux x86_64, sandbox VM)

Environment notes that affect what these results mean: PAX v0.4.1 built from source and placed on
`PATH` (without it, 4 `chip-cli` tests and the baseline bench's process section fail, and many tests
return early); the `wasm32-unknown-unknown` target was **not** installed at the start, so the first
full run had 10 failures, all in `chip-wasm-decision-host` (`cargo test` there reports "target may not
be installed"); after `rustup target add wasm32-unknown-unknown` the same tests passed. No real
model, no real `compute` binary and no network service were used, so everything that needs one was
not run.

| Check | Command | Result |
| --- | --- | --- |
| Formatting | `cargo fmt --all -- --check` | pass |
| Compilation incl. benches and tests | `cargo check --workspace --all-targets` | pass (it **failed** before this change set: the baseline bench did not compile after `Capacity` gained a field; fixed, D-28) |
| Lint | `cargo clippy --workspace --all-targets` | 0 errors, about 50 style warnings, none suppressed (D-31) |
| Wasm builds (as CI) | `cargo check -p chip-core --target wasm32-unknown-unknown`; `cargo build -p chip-wasm-decision --target wasm32-unknown-unknown --profile wasm-decision` | pass |
| Workspace tests | `cargo test --workspace --no-fail-fast` (PAX on `PATH`, wasm target installed) | **1139 passed, 0 failed, 1 ignored**. Tests that print `SKIPPED` (real `compute`, live model) count as passed |
| Dependency and boundary audit | `scripts/audit-dependencies.sh` | pass, including the new storage-engine checks |
| Crate inventory vs workspace | `cargo test -p chip-cli --test inventory` | pass |
| CI extras | `cargo run -p chip-cli -- --test`; `cargo run -p chip-decision-corpus --bin chip-decision-corpus -- verify`; `cargo bench -p chip-cli --bench baseline -- --quick` | pass |
| Packaging | `scripts/package-release.sh`, `scripts/smoke-test.sh` on the produced archive | pass ("SMOKE PASSED") |
| Placeholder search | the pattern in section 1 | no unclassified finding |
| Doc paths and links | script checking every repository path named in `README.md`, `AGENTS.md`, `docs/**` | the only unresolved paths are the other-repository references that the text now labels as such |

Not run, and why: manual live workflows (`live-compute.yml`, `live-model.yml`, `laya.yml`,
`local-ml.yml`) need a real `compute`, a real model or local model weights; the opt-in real-model
tests (`CHIP_TEST_REAL_MODEL=1`); the session-store benchmarks (unchanged by this change; their
recorded results are dated in their documents); the Windows/macOS builds (never run here).
Remaining uncertainty: effectiveness with any real model (roadmap P2-05), behaviour of the packaged
binary on any other platform, and whether the cleaned documentation matches what an external
embedder sees.
