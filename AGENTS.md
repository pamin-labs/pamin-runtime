# Repository Instructions

This repository holds `pamin-runtime`, the open-source compute crate shared by Pamin modules that run models locally: instruction-set kernel dispatch, inference devices over ONNX Runtime, per-call thread budgets and the prepared-model cache. It is published to crates.io and used by pamin-memory and other modules.

## Source of truth

- Specification, decisions and plans live in the private InternalDocs repository under `pamin-runtime/` (start with its `README.md`), plus the shared extension architecture in `pamin-platform/decisions/`. InternalDocs is a sibling clone at `$PAMIN_LABS_DEV_INTERNAL_DOCS` (default `../InternalDocs`); pull it before reading. Read the relevant documents before changing behaviour.
- When a design or decision changes, update InternalDocs in a PR there; cite it from here with SHA permalinks.
- This repository is public. Keep private planning, pricing, strategy and anything about paid or closed modules out of it; that lives in InternalDocs.

## Rules

- Everything committed is English: code, comments, logs, commit messages, PR titles and bodies, documents.
- Conventional Commits with a required scope for commits and PR titles (`fix(engine): ...`), one logical change per commit, each building and passing on its own. A commit's first line and a PR title are at most 72 characters, scope included: the pamin-labs-dev hook refuses a longer commit and CI fails a longer title, and a pushed commit is not rewritten without the owner, so count before committing.
- Coordinate through pamin-labs-dev before editing. With the plugin, its hooks and the `protocol` skill guide you. Without it, declare an intent with the `pamin-labs-dev` CLI first (`pamin-labs-dev intent declare ...`), work on its branch `<type>/i-<number>-<slug>` (no person or tool names), and put `Intent: I-<number>` in the PR description; CI rejects PRs without a live intent for their branch. Intents of the products this one uses appear in the session briefing; check them before changing code that depends on them.
- Keep PRs focused on one concern and reviewable in one sitting; split large work into a stack of PRs, each mergeable on its own. PR descriptions have a summary, the changes, what it reused, how it was verified, and any risk or follow-up.
- Commits and PRs carry no agent attribution: no `Co-Authored-By` trailers, no session URLs, no "Generated with" footers. Some tools append such a footer when they create or edit a PR, so read the description back after every such call and remove it.
- The commit author is always the engineer's own git identity; never invent one. If it is missing, stop and ask, then save it as `GIT_AUTHOR_NAME` and `GIT_AUTHOR_EMAIL` in the environment settings.
- Never squash-merge; keep every commit.
- **A PR merges only when its final commit is proven** (owner, 2026-11-05): GitHub reports it clean, every check has passed (a failed or pending check blocks it, however small the change), its tests pass, and, when it changes a service or binary that is deployed or shipped, an end-to-end check has passed on that same final commit: a local acceptance run or staging, never a run from before the last review fix.
- Work found and not done (a review's follow-ups, an audit's findings, a flaky test) goes into the maintainers' roadmap in InternalDocs in the same session, and a decision the owner makes goes into a decision record there before or with the change, so nothing lives only in a conversation.
- Never write tokens, keys or credentials to files, commits or logs.
- Prefer `rtk <command>` for shell commands when `rtk` is available.

## Code

The bar is high performance, low resource use, fast builds, and clean, DRY, decoupled code that is easy to maintain and extend. The `pamin-engineering` skill says how to meet it; follow it for every change.

- One implementation per concern: search for an existing one before adding logic, and extend it through its interface.
- Do not reinvent what exists: the repository's own implementation of the concern, then the official SDK of a service, then the standard library, then the platform, then a dependency already in the tree, then a maintained, widely used dependency; write your own only when none of them meets the need. A PR's "Reused" section names what it searched for, what it reused, and why anything was written by hand; hand-written code where one of those already covers the need is a defect, and review sends it back. This crate is a library: require dependencies with caret minimums and let lock files pin exact versions; pin exactly only with a stated reason, as for `ort` (InternalDocs `pamin-platform/decisions/2026-11-01-library-dependency-requirements.md`).
- No speculative abstractions, options or layers; add them when a second real use appears.
- **Model external data with types.** Parse external JSON (the plan cache's files, model metadata) into typed structs and enums that ignore unknown fields, and serialize requests from typed structs. No hand-built JSON strings, no chains of untyped lookups, no searching payloads for substrings. A value stays opaque only when a protocol requires it to be echoed back unchanged, and the code says so.
- **Tests meet the same bar as code.** A test builds requests from typed values, decodes an answer into the API's own types and compares JSON by decoding it, never as strings, and names a value owned elsewhere from its owner, like any code.
- **No deferral inside a PR's own code.** A written rule that code the PR adds or touches breaks is fixed in that PR, in its own commit; a follow-up is only work outside the PR's concern.
- **Comments claim only what the code guarantees.** A guarantee that waits on later work is named as not yet given.
- Before adding a dependency, check its maintenance, its licence and what it adds to build time and binary size, and record that in the PR.
- Measure before and after any change that claims a speed-up or a smaller footprint, and put the numbers in the PR.
- **No hard-coded value in more than one place.** Every port, address, URL, id, version, limit, price, file name and default is defined once, in the crate or file that owns it, and everything else reads it from there or is checked against it by a test or a generator. A literal that names a value owned elsewhere is a bug, in code, config, scripts, tests and docs alike.
- **No hidden defaults.** The crate deploys nothing, so it reads few settings; each environment variable it reads and each default it falls back to (a device selection, a thread budget, a cache directory) is named once, as a constant in the module that owns it, and documented there.
- **Built files are never committed:** `target/`, binaries, benchmark outputs and generated caches are git-ignored; only generated files a gate checks are committed.
- **Extensibility check before every PR:** adding one more of something the code already has (a kernel, a device, an execution provider, a prepared-model rewrite) touches its one definition plus its tests and docs. If the change needed more places, fold them into one source in the same PR.
- Nothing here knows about MCP, HTTP, tenants or any module; it changes only when hardware or inference back ends change.
- Every kernel path is tested on its own hardware (x86-64, Linux aarch64, Apple silicon); AVX-512 stays out until a measurement beats AVX2.

## Layout

The crate is one project in one language, so this file holds all its rules. **A directory says what its code is:** this list names every module and folder by its path, with what it owns, and a new one is described here in the PR that adds it, never placed beside them without a line; no test reads this list yet, so review checks it.

- `src/lib.rs`: the crate's documentation, its modules and its public re-exports.
- `src/error.rs`: the crate's one error type and `Result`.
- `src/kernels.rs`: vector math dispatched by instruction set at run time (the exact-rescoring dot product); `src/kernels/f16.rs`: IEEE 754 half-precision encoding and decoding.
- `src/onnx.rs`: small ONNX wire helpers the graph rewrites share, leaving unknown fields unchanged.
- `src/activity.rs`: what model loads in this process fetched and prepared, as counters.
- `src/device.rs`: which ONNX Runtime execution providers a machine can run, and what a session was actually given.
- `src/winml.rs`: Windows ML's certified vendor catalog, on Windows only.
- `src/budget.rs`: how much of the machine one forward pass may use, and the session options every model is built with.
- `src/session.rs`: ONNX Runtime sessions over a model's file, and the Core ML compiled cache for static shapes.
- `src/resident.rs`: handing a model's mapped weights back to the page cache while it is idle.
- `src/plan.rs`: which device a model runs on, chosen by measuring it and kept per machine.
- `src/prepared/`: a prepared, memory-mapped copy of a model: `mod.rs` builds and loads it, `key.rs` keys it to the runtime and CPU that wrote it, and `attention.rs`, `word_embeddings.rs` and `native.rs` are its graph rewrites.
- `build.rs`: carries the Windows ML catalog with an installed executable.
- `tests/`: integration tests through the public API, with ONNX fixtures in `tests/fixtures/`.

## Layers, domains and decoupling

These rules are shared word for word by every Pamin Labs repository. Each came from a defect found in an audit of Tala's server on 2026-11-03, and each stops that defect from coming back. Each project's `AGENTS.md` names its own layers and the tests that check them.

- **Layers point one way.** Code is layered by concern: entry, wiring, transport, domain, then store and integrations, then values. Dependencies point only from left to right, and nothing points back up. A test fails when one does:
  - in a Rust workspace, a test that reads `cargo metadata`;
  - in a single crate, a test over its modules' `use` paths;
  - in Go, the import test.

  A new module or crate goes in its layer's directory, never beside the layers.
- **Transport only translates.** A handler, middleware or CLI command does three things: it parses the request into types, calls one domain function, and shapes that function's result as the API's own types. A business rule in transport is a bug, and that includes refusals, quotas, limits, metering decisions and checks of any kind. A middleware may read the request, but it calls the function that decides, and that function declares the error.
- **Transport never reaches the store.** It uses no call, type or error from it. Even a domain function that only passes a call through is worth having, so that a rule added later has one place to go.
- **Each layer converts at its edge.** Row types never leave the store. The store returns its own plain read types, the domain converts them to its own types, and the API converts the domain's types to its own wire types. A schema change then fails to compile at a conversion instead of silently changing the API. A domain's public functions and fields take and return the domain's own types, never store or row types; the only store type a domain shows is the store handle it is built with. A type several domains and the store share is a value, not a store type.
- **Errors are declared once, with their kind and code, in the domain that owns them.** Transport answers any declared error by its kind, with no table that lists every domain's errors. A store error that transport must act on is mapped by the domain to its own error, so transport never names the store's errors.
- **A domain owns its data.** A domain calls another domain's service, never that domain's queries or tables, and the caller's domain orchestrates cross-domain work, not the store. Each store function is called from one domain only, and a test fails otherwise.
- **A domain module holds its service, its types, its errors and its rules.** It depends only on the store, on integrations through traits or interfaces it declares, and on other domains' services. It never imports an HTTP framework, MCP transport code or the API layer.
- **Wiring is in one place.** The entry point or app module builds each service once and hands each transport the services it uses. Every background task is domain code run on a schedule, under the same rules, and it is owned by the wiring that awaits it at shutdown.
- **Each handler group sees only its own services.** An API is not one handler holding every dependency. Each business area registers its own operations in its own file and receives only its own service and the caller's identity.
- **Traits and interfaces are declared by their consumer,** with only the methods it calls. Functions return concrete types.
- **One definition per concern.** Each rule, constant, limit, price, page size, setting name, header, path or schema has one definition, in the module that owns it, and everything else imports it. Before adding a helper, search for one. A second copy of a loop over an SDK is a bug: put one helper per repeated SDK flow in its integration module.
- **A rule is computed in one function,** and another domain calls that function rather than restating the rule. What a client must do first is that function's answer, not a set of flags the client has to order.
- **A counter and its refusal come from one function.** What a caller is told it has left must agree with what is refused. The "left" figure asks the same function that refuses, and a test checks that the two agree.
- **A closed set of values is one named type with one list.** Wire enums and schemas are built from that list, never written again in a tag or a string, and a test checks the list against the database's check constraint. A store value is never a wire name.
- **Modules are named for what they hold.** Names like `utils`, `common`, `models` and `helpers` are not allowed. Each module covers one concern with a small public surface and is private by default. A file covers one business area, not one type. Within a file the order is:
  1. imports;
  2. constants and statics;
  3. types;
  4. constructors;
  5. methods grouped by type, public first;
  6. plain helpers, in rough call order.

  A type is declared before the code that uses it.
- **Writes are safe to repeat.** A write that a client or a retry may send twice is idempotent: a repeat returns what the first one stored and changes nothing more. A write that also reaches another service calls that service outside the transaction, and is safe to try again, with that service's "not found" counting as done. Steps are ordered so that a failure part way leaves no gap.
- **Per-transaction state only.** A deployed PostgreSQL may sit behind a transaction-pooling proxy such as PlanetScale's PgBouncer, so a connection belongs to the code for one transaction only. Use `set local` or `set_config(name, value, true)`, and protocol-level prepared statements. Never use:
  - a session `set`, or `set_config(..., false)`, meant to outlast its transaction;
  - session advisory locks (use `pg_advisory_xact_lock` instead);
  - `LISTEN`/`NOTIFY`;
  - temporary tables;
  - SQL `PREPARE`;
  - cursors held across transactions.

  Test fixtures may use these.
- **State kept per user, tenant or key beyond a request is bounded,** like a rate limiter's buckets or a cache. Use a bounded structure with eviction, never a map pruned by hand. Per-user work that must be serialised is serialised in the database (a lease or row lock), not in one instance's memory, so instances stay stateless.
- **Hot paths keep their database round trips flat.** A request's round trips do not grow with the size of a user's data: no `count(*)`, `offset` or `max()` over a growing set per request. Keep counters, use keyset pagination with indexes that match each query, and batch independent reads.
- **Parse once.** Large values such as manifests, schemas, prompts and models are parsed once and cached by version in a bounded cache, never copied per request. Answers are streamed rather than buffered when they can be.

### Layers here

pamin-runtime is a compute library: it has no entry point, wiring or transport (its caller builds and serves), and no database, so the rules about those have no subject here. Its modules under "Layout" above still layer one way by their `use` paths:

- **Domain:** `prepared` (the prepared copy and its rewrites) and `plan` (choosing a device by measuring).
- **Integrations:** `session`, `budget`, `device`, `winml` and `resident`, the modules that configure ONNX Runtime, the platforms' accelerator catalogs and the page cache.
- **Values:** `error`, `kernels`, `onnx` and `activity`, which import no other module of the crate but `error`.

`prepared` and `plan` → `session` → `budget` and `resident` → `device` → `winml` → values. Two edges point back up today: `budget` reads `prepared::LEVEL` and `session` calls `prepared::source_digest`; new code adds none, and moving them down is its own change. The test over the modules' `use` paths that fails when a layer points back up is not yet written; on the roadmap.

## Rust

These rules are the same in every Pamin Labs Rust repository; change them in all of them together.

- **Toolchain and lints.** The edition and toolchain are pinned in `rust-toolchain.toml` and upgraded as their own change; code is `rustfmt`-clean and `clippy`-clean with warnings denied. A lint beyond clippy's defaults (a `clippy::pedantic` lint, `missing_docs`) is enabled in `[lints]` only after its findings on the current tree have been counted and found few and worth fixing, and the PR that enables it fixes them all.
- **Errors.** A library declares typed errors with `thiserror`, one enum per boundary with variants a caller can act on; `anyhow` or a boxed error only in binaries and tests. Errors travel with `?`, each layer adding what it was doing (a variant's field, or `.context(...)` in a binary), and are handled once: returned or logged, never both.
- **No panic reachable from input.** `unwrap`, `expect`, `panic!`, `unreachable!`, indexing or slicing that can go out of bounds, and arithmetic that can overflow stay out of every path a request, a file or another service's answer reaches. They are allowed in tests, at start-up before serving, and where an invariant rules the failure out, with an `expect` message that states the invariant.
- **`unsafe`** only where no safe API gives the result (FFI, a measured SIMD kernel), in the smallest block, with a `// SAFETY:` comment naming every invariant it relies on and a test that exercises it. A new crate that needs none starts with `#![forbid(unsafe_code)]`.
- **Borrow before cloning.** A `.clone()` added to satisfy the borrow checker on a hot path is a defect: restructure, borrow, or share an `Arc` and say why. Parameters take `&str`, `&[T]` or `impl AsRef<_>`; functions return owned values.
- **Types over strings and integers.** Ids, units and amounts are newtypes or standard types (`struct TenantId(Uuid)`, `Duration`), never a bare `String`, `i64` or `u64`; a closed set of values is an enum, never a string compared in code. Input is parsed into these types at the boundary (`serde`, `FromStr`, `TryFrom`), so inner code only sees valid values.
- **Typed JSON.** Bodies are `serde` types; walking a `serde_json::Value` by hand, `json!` for a body whose shape is known and `format!` building JSON are defects. A value a protocol requires to be echoed unchanged is a `Box<RawValue>`, and the code says why.
- **Published crates** (one another repository depends on) keep semver: a public struct or enum that may grow is `#[non_exhaustive]` or has private fields and a constructor, and a breaking change is called out in the PR and released as one. Features are additive: enabling one never removes or changes what another relies on, and the default features are the smallest set a typical user needs.
- **Dependency features.** Each dependency is declared once (in `[workspace.dependencies]` where there is a workspace) with only the features the code calls; `tokio`, `axum` and other large crates never take `full` or unused defaults. A new dependency's added clean build time (`cargo build --timings`) and release binary size are measured and recorded in the PR.
- **No blocking in async.** No blocking file or network call, `std::thread::sleep`, long CPU-bound loop or contended `std::sync` lock on an async task: use the async API, `spawn_blocking` or a dedicated thread. No lock guard is held across `.await` (clippy's `await_holding_lock` stays on); a `tokio::sync` lock only when the guard must cross one.
- **Everything queued is bounded.** Channels, queues, caches and per-key maps have a bound named once as a constant or a setting, and the code says what happens when it is reached (wait, refuse or evict); an unbounded channel is a defect outside tests.
- **Tasks are owned.** Every spawned task's `JoinHandle` is kept (or the task lives in a `JoinSet` or a `TaskTracker`) and awaited or aborted by its owner, so its panic or error is seen. Every branch of a `tokio::select!` is cancellation-safe, or a comment says why the lost work does not matter. A long-running service shuts down gracefully on SIGTERM: it stops accepting, finishes or hands over work in flight within a deadline, flushes what it buffers, then exits.
- **Shared state** is `Send + Sync`, owned by one type that keeps each lock next to the fields it guards; on a hot path prefer atomics or message passing to a lock, and never take two locks in different orders.
- **Logs** go through `tracing` with structured fields: ids, counts and durations, never a secret, a token, a request body or user content. A type that holds a secret redacts it in `Debug`.
- **SQL** (`sqlx`) binds every value (`$1`, `.bind`); a query built with `format!` from input is a defect, and what cannot be bound (an identifier) comes from a closed list in code. Migrations are append-only: a merged migration is never edited, renamed or removed; a change is a new migration.
- **Tests.** Unit tests sit beside the code in `#[cfg(test)] mod tests`; tests of a crate's behaviour through its public API go in its `tests/` directory. Tests are deterministic and independent: no `sleep` to wait for something (await the event, poll with a deadline, or pause tokio's clock), no dependence on test order, the wall clock, the network or state another test left; anything random uses a fixed seed. A fix comes with a test that fails without it.

## Performance

- **Hot paths allocate once.** Reuse buffers (`clear()` and refill, `with_capacity` from a known size); no `collect()` into a `Vec` only to iterate it once; no `to_string()` or `format!` for a value that is only compared or written out.
- **Static dispatch on hot paths** (generics, `impl Trait`); `dyn` at boundaries crossed once per request or less.
- **Connections:** a database pool's size is set explicitly, and a transaction holds its connection only for SQL, never across a call to another service.
- **Start-up** does not wait on other services: connect, fetch keys and load what can wait on first use or in the background, unless the program can answer nothing without it.

## Review before every PR

Before a PR opens, go through its whole diff, tests included, against each rule of every `AGENTS.md` the change touches and the `pamin-engineering` skill, and fix what misses in new commits; then run the `pamin-labs-dev:peer-review` skill and put its verdict and findings under the PR's verification. Work an agent delegated is reviewed the same way: the agent that opens the PR reads its diff and tests itself and never accepts them on the delegate's report alone.

## Gates before every push

`cargo fmt --all --check`, `cargo clippy --all-targets -- -D warnings`, `cargo test`, `cargo deny check`.

## Skills

Longer guidance lives in `.agents/skills/`, one directory per skill; `.claude/skills/` links to the same directories.

| Skill | Use it when |
| --- | --- |
| `pamin-engineering` | Writing or changing code, adding a dependency, claiming a speed-up, reviewing |
