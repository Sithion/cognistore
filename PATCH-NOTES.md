# Patch Notes

## v2.6.0 (unreleased)

**Performance and knowledge curation.** Work in progress on `release/2.6` — see `documentation/plans/2026-11-performance-e-curadoria.md`.

### Improvements
- **The sidecar now measures itself.** Every 5 minutes it logs event-loop delay (p50/p99/max) and a summary of database calls: how many took 100 ms or more, how many of those were writes (usually a lock wait behind another process), how many failed with `SQLITE_BUSY`, and the slowest statements of the interval. Bound values are never logged, only the SQL text. The summary goes to `~/.cognistore/cognistore.log` with asynchronous I/O. This is the baseline for the "app freezes on large databases" work.
- **Opening Settings no longer scans the whole base for duplicates.** The Knowledge Health panel used to run duplicate detection every time Settings opened — 41 s of a frozen sidecar on a 10,000-entry base. It now runs only when you click **Check for duplicates**, and the result is cached until an entry is added, edited or deleted (or the base is re-embedded), so checking again on an unchanged base is instant.
- **Duplicate detection no longer freezes the app, and is ~11× faster.** It used to load every entry's full text and run one nearest-neighbour query per entry on the sidecar's only thread: 41 s of a frozen dashboard on a 10,000-entry base, whether it came from the Settings button or the periodic cleanup report. It now reads only titles and metadata, reads each stored vector once, and compares them in small slices that hand control back to the app every ~15 ms. On the same base, the full scan takes 3.6 s and the app never stalls for more than ~30 ms. It also remembers what it found. The next check compares only entries added or edited since then (83 ms after one edit), and re-embedding starts it over. Results are the same groups as before on the test bases. The new search is exact: it no longer misses members of a very large cluster of near-identical entries.
- **Searches no longer write to the database on the way back.** Every search used to insert into the activity log and, for agent lookups, update the read counters of its hits: two synchronous writes on the read path of a database shared by the dashboard and every agent session. Both are now counted in memory and written in one transaction: activity every 30 seconds, read marks every 10 seconds (and on shutdown). Every flush waits at most 250 ms for a busy database instead of stalling for up to 5 seconds: activity counts are then kept for the next flush, read marks are dropped. The Activity chart and stats show the same numbers as before, up to 30 seconds late for other sessions' activity.
- **Faster, lighter database connections.** Every connection (dashboard and agent sessions) now uses `synchronous=NORMAL` (safe with WAL), a 32 MB page cache, 256 MB of memory-mapped reads, in-memory temp tables and a 64 MB cap on the WAL after checkpoints. `PRAGMA optimize` runs on close and in the 6-hour maintenance.
- **Token usage scan does less work.** Session logs are read with asynchronous I/O, scan positions are loaded once and saved in one transaction per pass, session files without any usage lines are no longer re-read from the start on every pass, a read error mid-file no longer skips the unread rest of it, and the scan runs every 5 minutes only while new usage keeps arriving — every 30 minutes once a pass finds nothing (the Scan button still scans immediately).
- **An ignored cleanup report is retired even with cleanup turned off.** A report left open before the cycle was disabled stayed open forever; it is now auto-closed after twice the interval, as it is when the cycle is on.
- **Agent sessions can report their own performance.** With `COGNISTORE_PERF=1` in the MCP server's environment, it writes the same `[perf]` lines as the dashboard (event-loop delay, slow and busy database calls) to stderr, and to `COGNISTORE_PERF_LOG` if set. See `documentation/mcp-server.md`.

### Fixes
- **The Stop hook no longer says "no knowledge captured" right after you captured some.** The script that records a capture (`post-add-knowledge-marker.sh`) was installed but never registered for `addKnowledge`, so the end-of-session check could never see it and blocked or nagged anyway. It is now registered; existing installs pick it up with the automatic hook re-deploy on update.
- **Fresh installs deny the destructive tools from the start.** When `~/.claude/settings.json` did not exist yet, setup wrote only the server-wide allow rule, so `deleteKnowledge` and `deletePlanTask` were auto-approved until the first update re-ran the permission merge. The deny entries are now written with the file.
- **Re-running setup or an update no longer grows your instruction files.** Each run added a blank line after the CogniStore block in `CLAUDE.md`, the Copilot instructions and OpenCode's `AGENTS.md`. Blank lines added by earlier versions are left as they are.
- **Uninstall leaves no empty scaffolding behind.** It used to leave `"mcp": {}` in `opencode.json` and, on a machine that had no `~/.claude/settings.json` before, a `settings.json` holding only empty permission lists. Setup now records which of those two files it created (`createdConfigFiles` in `~/.cognistore/settings.json`); uninstall deletes such a file only when it is on that record and nothing but setup's own keys are left. A file that was yours — even one holding only `$schema` or `{}` — is kept. Installs set up before 2.6 have no record, so their files are cleaned but never deleted.
- **Databases created by v0.8.0 open again.** Since 2.3.2 such a database failed to open with `no such table: operations_log`. Every runner since 0.9.0 recorded the 0.8.0 base schema as applied without running it, and v0.8.0 itself never created that table. The base schema is now re-checked on every open, also on databases an older version has already upgraded. It only creates what is missing, and when nothing is missing it takes no write lock.

- **Imports without `source` work.** The import format makes `source` optional, but every such entry failed (`NOT NULL constraint failed: knowledge_entries.source`) while the import still reported success with `imported: 0`. They are now imported with `source: "import"`.
- **Bad input to the API is a 400, not a 500.** Input the SDK rejects (for example `POST /api/knowledge` without `source`) went to the server-error path, and so did a search without a query. Both are now a 400 with the validation message.
- **Unknown API paths are a 404.** Any `/api/...` path that does not exist was answered with the dashboard's `index.html` and a 200, so a typo or a route a newer client expected looked like success and failed later as a JSON parse error. It is now a JSON 404. Page routes still fall back to the dashboard.

### Maintenance
- Removed leftover Stryker mutation-testing output (`packages/core/packages/`, `packages/core/reports/`) and added it to `.gitignore`.
- The per-platform agent instructions committed under `apps/dashboard/templates/configs/` are regenerated from their base template. They still said every CogniStore tool is pre-approved, which stopped being true when the destructive tools started to prompt. Release builds recompile them, so installed apps already had the right text. The new `sidecar-bundle` CI job now fails when the committed copies drift.

### Tests
- **Performance suite on a realistic large base.** A seeded generator builds a 10,000-entry database (0.5–10 KB contents, real embeddings shape, 5% near-duplicate clusters) with 200,000 token-usage rows and 50,000 operation-log rows, plus Claude Code–style JSONL session logs. The same seed always produces the same file, and it is cached between runs. `pnpm --filter @cognistore/tests test:perf` (on demand, one worker; not part of the default `pnpm test`) times hybrid search, paginated listing, stats, token aggregates, duplicate detection and the token scan against budgets of 4× the recorded baseline (`packages/tests/src/performance/baseline.json`), and prints a `PERF <case> <ms>` line for each. A contention harness runs three agent-session processes and the sidecar's periodic work against one database and records lock waits and `SQLITE_BUSY` errors. Baseline highlights: duplicate detection 41 s and the 180-day token aggregates 1.7 s — the first targets of phases 1–2.
- **The test package is type-checked.** `packages/tests` now has a `type-check` script and runs in `pnpm type-check` (and the CI `type-check` job). Its tsconfig spans the repo (the tests import sidecar modules) and includes DOM types for `page.evaluate` bodies and `fetch().json()`.
- **The upgrade e2e no longer depends on the real home.** It compared the mtimes of the developer's own `~/.claude.json` & co. before and after, which failed whenever a running Claude Code touched them. It now proves the HOME override held by finding every artifact the upgrade writes under the sandbox HOME.
- **Setup, re-setup, update and uninstall are tested end to end for all three platforms.** The real sidecar runs in a sandboxed HOME, once pre-filled with a user's own Claude/Copilot/OpenCode config and once empty: setup must inject every artifact of the symmetry table, a second setup and a version update must change nothing, and uninstall must return the home to exactly its initial files (only the `*.bak.*` rollback copies stay, by design). A fake `ollama` on `PATH` proves only the pulled models are removed.
- **The Claude Code hooks are run for real.** A test fires the deployed scripts the way Claude Code does (matcher, JSON on stdin, per-session markers) and checks that a capture satisfies the Stop hook, that it does not leak into another session, and that every hook script shipped is registered and every registered command exists.
- **The MCP tool surface is frozen in a test.** Tool names, input schemas and annotations must equal a snapshot generated from the published v2.5.4 server, and every one of the 18 tools is called once: each response must keep every field (and type) the snapshot recorded. New optional parameters or response fields need a deliberate snapshot update (`UPDATE_MCP_CONTRACT=1`). The new `compat` test project holds this and the coming compatibility suites.
- **Upgrade matrix over every published schema.** One small database per schema version (0.8.0, also as left by v2.1.0 after opening it, 0.9.0, 1.3.0 and the legacy 1.3.0 `.deb` layout with `consumption_*` tables, 2.0.0, 2.1.0, 2.3.x, 2.4.0, 2.4.1, 2.5.4) is written by that release's own SDK, checked out from its git tag, with varied entries, plans, tasks, token usage and a deletion. Each one is opened with the current code: no row may be lost, every entry must stay byte-identical, the full-text index and the embeddings must cover every entry (0.x's 384-dimension vectors are re-embedded), search must find a seeded entry, and migrations run twice, from the `.sql` files and from the copy bundled in the MCP server, must leave the same database. This found the v0.8.0 bug above. Regenerate with `node packages/tests/scripts/gen-upgrade-fixtures.mjs` (about 220 KB gzipped in total).
- **Mixed MCP versions on one database are tested.** Agents run whatever server build npx resolved, all against the database the app upgrades. The new matrix runs the published 2.5.3 and 2.5.4 servers (real `npx`, with a sandboxed npm cache and HOME) on a 2.6 database, the 2.6 server on a 2.5.4 database, and the 2.5.4 server again after that. It also runs the 2.6 app (the real sidecar) writing at the same time as both 2.5.x servers. Each one runs the smoke (`addKnowledge`, `getKnowledge`, `createPlan`, `updatePlanTask`), and every write must be readable by the other version, with every call succeeding and no `SQLITE_BUSY` in the app's log. Needs the network for npx; offline it skips locally and fails in CI.
- **Every sidecar route is inventoried and tested.** The test asks Fastify itself for the route list (`COGNISTORE_ROUTE_MANIFEST`), and it fails when an `/api` route has no test, listing the method and path. Each route is checked for the token and Origin (CSRF): every route except the `/api/health` liveness check refuses a missing token, and all of them refuse a foreign Origin. Also covered: malformed and invalid input (4xx), the error handler (5xx with a `ref`), the 1 MiB body limit, and the 1–200 limit and offset clamps of the listings. The 29 routes no suite called before now have a test: metrics, scopes, tag merge and suggestions, plan relations, bulk delete, the provider edit/secret/test/OAuth paths, and the setup steps, which run in a sandbox with a fake `ollama` so they install nothing. This found the three API fixes above.
- **Unit layer for core.** Vitest unit tests (`packages/core/test/`, `pnpm --filter @cognistore/core test`) cover the repositories, the knowledge and plan services, cleanup merging, plan lineage, duplicate detection, the token scanner and its adapters, the migration runner and the perf instrumentation. They run in CI before the Playwright suites, against a real temporary SQLite + sqlite-vec database with a deterministic stub embedder, so no Ollama is needed. Core is at 94% of lines and 77% of branches (goal: 85% / 75%). The sidecar's pure modules (`auth.ts`, `settings.ts`) have their own (`apps/dashboard/server/test/`, 90% / 88%).
- **The packaged sidecar is built and smoke-tested on every PR.** A new CI job builds the bundle the desktop app ships (single-file server, frontend, templates, and `better-sqlite3`/`sqlite-vec` for Node 24) and starts it the way the app does, in an isolated directory with a sandboxed HOME. It must report ready, open the database, and find an added entry by semantic search, which only works when sqlite-vec loads from the bundle. Before, the bundle was only built at release time.
- **Coverage is measured and gated in CI.** Both layers run under V8 coverage: Vitest for the unit layer, and `c8` around the Playwright suites, which also measures the sidecar and MCP processes they spawn. `pnpm coverage` runs both and prints lines and branches per package; CI puts the table in the job summary and uploads the reports as an artifact. The build fails when a package drops more than 1 pt below `coverage-baseline.json`, which records the numbers at the end of this round.

### CI
- **New `rust` job:** `cargo check --locked` and `cargo test --locked` for the Tauri shell on every PR (`ubuntu-24.04`, the same Linux deps as the release build). Until now Rust only compiled in `publish.yml`, after a merge to `main`. The toolchain is pinned in `apps/dashboard/src-tauri/rust-toolchain.toml` (1.97.0).
- **New `perf` job (report only):** runs the `@perf` suite on the cached 10k-entry fixture with budgets ×3 for the shared runner and posts the `PERF` lines to the job summary. It never fails the PR.
- **`pnpm verify`: one command, used by CI and before every push.** It runs lint, type-check, build, the unit layer and the integration suites (API inventory, MCP contract, MCP × database matrix, upgrade matrix) and stops at the first failure. With `--coverage` it also runs the coverage gate. CI's `build-and-test` job runs `pnpm verify --coverage`, and a new `pre-push` hook runs `pnpm verify` for pushes that send commits (skip one with `git push --no-verify`). The project has no linter or knip configured yet, so those steps currently do nothing.
- **A cached build no longer drops the sidecar.** `turbo.json` now lists `dist-server/**` as a build output. Before, a cache hit restored the dashboard's `dist/` but not the compiled sidecar, so the suites that spawn it failed with "Cannot find module .../dist-server/index.js".
- **Release failures raise an issue.** When a Publish run fails on `main`, a new `alert-on-failure` job opens an issue, or comments on the open one, linking the run.
- **CI hygiene.** Linux jobs are pinned to `ubuntu-24.04` instead of `ubuntu-latest`. The exception is the release AppImage/deb build, which stays on `ubuntu-22.04` for glibc compatibility. `pnpm/action-setup` moved from v4 to v6.1.0, pinned by SHA. `osv-scanner.toml` dropped 17 ignores that no longer match: the 10 GTK "unmaintained" advisories, which OSV withdrew; `rand` 0.7, `fxhash` and the `unic-*` crates, which are no longer in the tree; and react-router, which is fixed in the version we ship. Each of the 9 that remain has a `reason`. The `npm publish --dry-run` check no longer fails just because the unbumped version is already on npm, which is `version-check`'s job. It used to abort without printing why.
- **The coverage gate no longer fails at random outside CI.** Depending only on process ids, `pnpm verify --coverage` could report `core` and `shared` as a single line per file and fail (seen on a clean clone; green in CI by luck). Cause: the Playwright processes load the packages' `dist` through a transforming loader, and c8 keeps the source-map data of whichever dump it reads last. The report now drops those transformed-source entries before c8 maps the numbers (`scripts/coverage-normalize.mjs`, tested with `pnpm test:scripts`), so the result no longer depends on the machine. Details in `documentation/ci-cd.md#coverage`.

## v2.5.4

**Security maintenance release: two advisories published after 2.5.3.** Caught by the weekly OSV scan on the v2.6 draft PR the same day they appeared.

### Security
- **`zip` 9.0.0 → 9.1.3 (GHSA-m665-v7pm-7grj, critical).** A parser differential between the central directory and local file headers ("zip cloaking") can make an extracted file land somewhere other than where the archive index says. `zip` is used by the Tauri updater to unpack downloaded updates (which are also signature-checked). `libc` moves to 0.2.191, required by the fixed `zip`.
- **`@hono/node-server` → 2.1.5 (GHSA-rmxm-3fg6-px4f, moderate).** `serveStatic` decoded the request path twice, letting a crafted path skip middleware on static prefixes. Pulled in through the MCP SDK; the override in `package.json` is raised from `>=2.0.5` to `>=2.1.3`.

## v2.5.3

**Security maintenance release: the weekly dependency scan had been failing since September 7.** New advisories were published against transitive dependencies after v2.5.2 shipped; the scheduled OSV scan caught them every Monday, but a failing scheduled run notifies nobody, so eight weeks went by unnoticed. This release clears them and makes the next one impossible to miss.

### Security
- **npm:** `fastify` 5.8.5 → 5.12.x, `@fastify/cors`/`@fastify/static` patch bumps, `@modelcontextprotocol/sdk` 1.27.1 → 1.32.x (MCP server, providers, tests), `react-router-dom`/`react-router` → 7.18.5. Transitive fixes via `pnpm.overrides`: `vite` (6.4.4+, still 6.x), `qs`, `body-parser`, `proxy-addr`, `fast-uri`, `hono`, `ip-address`, `brace-expansion`, `shell-quote`, `source-map-js`, `browserslist`, `baseline-browser-mapping`. Includes two critical (`proxy-addr`, `shell-quote`) and the high-severity MCP SDK advisories.
- **`zod` 3.25 → 4.6.6+ with the v3 API kept.** The MCP SDK validates every JSON-RPC message with `zod/v4`, which in `zod@3.25` ships the array-validation memory-exhaustion bug (GHSA-mrhx-c7xc-m3w5). Our own schemas now import `zod/v3` from the zod 4 package, so their behaviour — and the MCP tools' published input schemas, verified byte-identical — does not change.
- **Rust (Tauri shell):** `rustls` 0.23.46, `rustls-webpki` 0.103.16, `webpki-root-certs` 1.0.11, `tokio` 1.54 (RUSTSEC-2026-0386), `tauri-plugin-updater` 2.14 (drops `zip` 4.x, RUSTSEC-2026-0367/0368/0369) and `tauri-plugin-process` 2.4, which bring `tauri` to 2.12. `@tauri-apps/*` npm packages bumped to the matching minors.
- `osv-scanner.toml`: `block-buffer` 0.10 (GHSA-qwgh-2vcv-g2f7, CVSS 6.3) ignored with justification — fixed only in the 0.12 line (digest 0.11), which Tauri and `keyring` don't use yet, and it needs a panic caught inside a hash compression callback, which nothing here does. Also three new "unmaintained" informational advisories (`zvariant`, `zvariant_derive`, `zbus_names`, merged into zbus 6) ignored with justification — they arrive through `keyring` 3's Linux Secret Service backend and have no patched version.

### CI
- **A failing scheduled scan now opens (or comments on) a GitHub issue** "Weekly dependency scan (OSV) is failing", so it can no longer fail silently.
- `scripts/bump-version.sh` now works on Linux too (it used BSD-only `sed -i ''` for `Cargo.toml`).
- **npm publishing moved to trusted publishing (OIDC).** The first 2.5.3 publish failed with a 404 because the long-lived `NPM_TOKEN` had expired (the same failure as v1.0.10–v1.0.12). `publish-mcp` no longer uses a token at all: GitHub's OIDC identity for `publish.yml` is trusted by npm directly, so there is no secret to expire or leak.

## v2.5.2

**The sidecar has been crashing on every single launch since 2.5.0, and this release fixes it.** After the readiness handshake moved onto the child process's own stdout pipe in 2.5.0 (see below), the Tauri shell read that pipe only until it saw the ready marker, then dropped the reader — closing the pipe's read end. The sidecar's very next `console.log` (its access logger fires on nearly every request, and startup alone logs several lines) then hit `EPIPE`. Node does not install a signal handler for that on piped, non-TTY stdio, so the write failure surfaces as an unhandled `'error'` event, which is fatal: the process exits with an uncaught exception a few dozen milliseconds after saying it was ready. The window has already been told to navigate to `http://localhost:<port>` by the time this happens, so the visible symptom was a blank white window that never loaded — on some machines the app kept restarting the sidecar in a loop trying to reconnect, which is what a separately investigated freeze after upgrading to 2.5.0 turned out to be riding on top of.

> If you're on 2.5.0 or 2.5.1, this is why the app hasn't been loading. Update and relaunch — that fixes the crash.
> **If your vector index had been emptied by the bug below, read the note under Fixes about duplicate
> entries before you assume nothing else needs attention.**

### Fixes
- **The sidecar no longer crashes on launch.** The readiness reader now keeps draining (and discarding) the sidecar's stdout for the life of the process instead of returning ownership of it to be dropped — reproduced directly (close the pipe's read end the old way and the sidecar dies with `Error: write EPIPE` on its next log line every time) and verified fixed the same way.
- **Sidecar stderr is now drained too**, and logged with a `[sidecar stderr]` prefix in the app's console output. It was never read at all before — harmless until the OS pipe buffer filled, at which point the sidecar's own stderr writes would start blocking. This is also what would have made the EPIPE crash visible immediately instead of silent.
- **The embedding-integrity resync no longer corrupts itself over time.** The check compared a raw count of *all* knowledge entries against the count of embedding rows, but the rebuild it triggered re-embedded only *non-system* entries — so the two numbers could never agree, and every upgrade run concluded the index was short, dropped the entire vector index and re-embedded from scratch. If that run was ever interrupted (the crash above interrupted plenty), the index came back empty. Two independent fixes: the embedding writers are now upsert-safe (an update that matches no row falls through to an insert, instead of silently doing nothing), and a new incremental, resumable backfill (`embedMissing`) embeds only the ids that are actually missing — found with a symmetric query that counts system entries on both sides — rather than dropping and rebuilding everything. Nothing calls the old drop-and-rebuild-everything path from the integrity check anymore.
- **The backfill no longer runs when Ollama can't embed.** The upgrade now probes Ollama before starting, exactly as the model-migration step already did, and records the step as *skipped* rather than *error*. Without the probe, an Ollama that was down or stalled made every missing entry burn its full retry budget (3 attempts × 30s each), so a few thousand of them would have held the upgrade open for hours behind a spinner — and marking it an error would have refused to write `.version`, re-running the whole upgrade on every launch forever. A partially-completed backfill now counts as progress for the same reason: it leaves the index strictly better than it found it, and the next run resumes from there.
- **Coverage is measured the same way the repair is.** "How many embeddings are missing" is a `LEFT JOIN`, not a subtraction of two counts, so a leftover vector whose entry was deleted (possible any time the process died between the two deletes — which it did, on every launch) can't cancel out a genuinely missing one and make an incomplete index report as complete.
- **New `scripts/repair-embeddings.mjs`** for repairing a knowledge base whose vector index fell behind or was wiped by the bug above, without needing to launch the app. Prints progress as counts only, never entry content. It refuses to run against a database outside `~/.cognistore` or with an inherited `EMBEDDING_DIMENSIONS` — that last one would make the SDK's dimension migration drop the very index the script was run to repair. It also refuses while a CogniStore sidecar is running, **on macOS only** — the running-process check doesn't yet recognize the Linux packaging; quit CogniStore from the tray first regardless of platform. Usage and safety rails: [documentation/recovery.md](./documentation/recovery.md).

**If you were affected — duplicate entries may exist and this release does not merge them.** Deduplication is embedding-based: `addKnowledge`/`createPlan` decide "update the existing entry" vs. "create a new one" purely by vector similarity search. While your index was empty (dropped by the old integrity check, then left empty by any run the crash above interrupted — which, on a machine hit by both bugs, was most of them), that search always returned nothing, so every write that should have updated an existing entry created a duplicate instead. This release restores dedup for *new* writes going forward, and repairs the index so search works again — it does **not** retroactively merge duplicates created while it was down. A report-only duplicate audit is planned for a later release; until then, if something looks doubled, it probably is.

## v2.5.1

**`nanoid`, pulled in transitively through `postcss`, was pinned at a vulnerable `3.3.16`.** A pnpm override now bounds it to `>=3.3.18 <4`, closing the gap without jumping to the ESM-only `nanoid@6` that an unbounded override would otherwise resolve — `postcss` consumes `nanoid` as CJS.

### Security
- **`nanoid` bumped 3.3.16 → 3.3.18 (GHSA-2v37-7h3g-55p8, CVSS 8.2).** Fixed via a root `package.json` `pnpm.overrides` entry, bounded `>=3.3.18 <4` to match the repo's convention for other overrides (e.g. `react-router`) and to keep `postcss`'s CJS `require('nanoid')` working.

## v2.5.0

**The dashboard API had no authentication, and that turned out to matter more than it sounds.** The sidecar binds `127.0.0.1`, which was treated as sufficient — but loopback is not a trust boundary: every other process on the machine, and every page served by any other local HTTP server, sits inside it. Of 76 routes, 7 had an Origin check, and that check allowed a *missing* Origin outright. `POST /api/uninstall` takes no body, so a body-less `fetch(url, {method:'POST', mode:'no-cors'})` from any web page was a CORS-simple request — no preflight, nothing to block — that ran the whole teardown: `~/.cognistore` deleted, Ollama uninstalled, the app removed from `/Applications`. The port range is small enough to loop through. `GET /api/export` hands over the entire knowledge base through the same hole.

A `SIDECAR_TOKEN` already existed. It was generated, injected, and never required — and `GET /api/health` gave it to anyone who asked.

This release closes that, and the rest of what a full audit of the codebase turned up: a local-root hole on Linux, arbitrary local command execution by provider configuration, keychain reads reachable from any localhost origin, command execution through a hook's edit counter, and a dead pnpm overrides block that would have silently rolled back six CVE fixes on the next pnpm major.

> Requires a rebuild and a full app restart, plus the MCP config refresh to `@cognistore/mcp-server@2.5.0`. **An out-of-date client will fail authentication.**

### Security
- **The sidecar API authenticates every request.** Deny by default, with only static assets and the SPA shell exempt. Three checks: the `x-cognistore-token` header must match; a present `Origin` must be this server's *exact* origin (the old check accepted any localhost port, so a dev server or another app's webview qualified); and the `Host` must be ours, which defeats DNS rebinding. A missing `Origin` is accepted only alongside a valid token — a browser cannot forge that header cross-origin, which is what closes the drive-by case.
- **The token is no longer published.** `GET /api/health` used to return it, because the desktop shell proved the server on the port was the one it spawned by matching the echoed value. That handshake now runs over the child process's own stdout — a channel nothing else can write to — so identity is proven without publishing anything. The token reaches the webview through a Tauri initialization script, never through the served HTML.
- **Local root on Linux (setup).** The Ollama installer script was written to a fixed path in a world-writable `/tmp` and then run under `pkexec`; another user could pre-create or symlink that path and have their content executed as root. It now uses a 0700 `mkdtemp` directory, refuses to follow an existing file, and is executed without a shell.
- **Arbitrary local command execution by configuration.** A provider entry with `transport: 'stdio'` carries a command, args and env handed straight to a spawn — reachable by anything that can write `providers.json`, including a prompt-injected agent with no shell access. It now requires an explicit installation opt-in, as does `auth.allowInsecure`, which switches the SSRF guard off entirely. `env` keys that alter process code loading (`LD_PRELOAD`, `DYLD_*`, `NODE_OPTIONS`, …) are refused outright.
- **Provider secrets were being written to disk in plaintext.** The generated MCP config copied every keychain-held provider credential into four agent config files, three of them world-readable, so a subprocess CogniStore does not even spawn could read them. It no longer does; `providers.json` is written `0600`.
- **Keychain reads were reachable from any local origin.** The Tauri capability granted IPC to `http://localhost:*`, including the command that reads OAuth tokens out of the OS keychain. It is pinned to the port range the shell actually uses, and the keychain commands additionally require the sidecar token, checked in Rust.
- **A hook could be made to execute commands.** Two hooks read an edit counter from a predictable file in a shared `/tmp` and fed it into shell arithmetic, where `a[$(…)]` runs. Counters are sanitised, marker writes refuse symlinks, and the whole marker namespace moved to a per-user `0700` directory.
- **The SSRF guard** now covers all of `127/8` rather than `127.0.0.1` alone, `169.254/16` where the cloud metadata endpoint lives, `0.0.0.0`, `::`, CGNAT, and the decimal/hex/octal IPv4 spellings that reach the same address while matching no dotted-quad pattern — plus a check *after* DNS resolution, since a public name can still answer with an internal address.
- **`~/.cognistore` is no longer an allow-listed root for plan-file reads.** A plan's `planFilePath` is only validated as a non-empty string, so anything able to create a plan could aim it at `oauth-tokens.json` and read the file back.
- **Destructive MCP tools are no longer pre-approved.** `deleteKnowledge` and `deletePlanTask` now prompt; deleting your knowledge is your call. Everything else stays frictionless.
- **A dead `overrides` block in `pnpm-workspace.yaml`** pinned strictly older versions of six packages the live overrides pin for CVE reasons. pnpm 9 ignores it; pnpm 10 does not. Removed.
- Error responses no longer echo command lines, absolute paths and provider URLs; a real CSP is sent on the origin the UI actually runs on; `javascript:` URLs from external providers are not rendered as links; the free-text knowledge fields have upper bounds; and CI no longer interpolates a PR-controlled version string into a shell.

### Fixes
- **Uninstall no longer removes Ollama unless you say so.** It used to delete the binary, `~/.ollama` and the brew formula unconditionally — a dependency you may have installed yourself and may be using for something else. It is now opt-in, and only offered when CogniStore installed it. Installs upgraded from 2.4.1 or earlier carry no such record, so the answer there is to leave it alone.
- **Uninstall no longer deletes your config backups.** The `*.bak.*` copies under `~/.claude` and `~/.copilot` are the rollback path to a pre-CogniStore config; they are kept.
- **Uninstall stops the `ollama serve` it started**, rather than `pkill`-ing every process whose command line matches — including yours.
- Migrating an old instruction-marker block left two stray characters in `CLAUDE.md`; a hook of your own under `~/.cognistore/` could be misclassified as ours and deleted; and a trailing comma in `settings.json` threw out of the middle of a deploy instead of skipping that file.

### Improvements
- **The plan status filter combines instead of replacing.** The chips above the plan list (`Draft`, `Active`, `Completed`, `Archived`) are now a multi-select toggle group: click two and you get both, click one again to drop it. The `All` chip is gone because it no longer means anything — with nothing selected the list already shows everything. The filter is applied server-side (`GET /api/plans?status=draft,active`), so it still composes with the scope dropdown and still pages correctly on scroll. A single `?status=active` behaves exactly as before, and the MCP `listPlans` tool is unchanged. One contract change if you script against the endpoint: an unrecognised `status` value now returns `400` instead of an empty `200`.
- **The plan status vocabulary has one definition.** `draft` / `active` / `completed` / `archived` lived as separate hardcoded copies in the MCP server and the dashboard; both now import `PLAN_STATUS_VALUES` from `@cognistore/shared`, which mirrors the `plans` table's `CHECK` constraint. The repository rejects any status outside it, and `GET /api/plans` answers `400` rather than silently returning an empty list.

## v2.4.1

**The first launch after an update looked like a hang.** The app ran the whole upgrade — database re-init, re-embedding, artifact redeploy — behind a static "Loading…" screen with no indication that anything was happening. On a large knowledge base that is minutes of a frozen-looking brain emoji, and the natural reaction is to force-quit it. The upgrade now runs on a screen that shows what it is doing, step by step, as it happens.

### Features
- **The upgrade shows its work.** The update screen is no longer reached only when something failed: an upgrade always runs there, listing each step as it completes and marking the one in progress. The step list comes from the sidecar (new `GET /api/upgrade/progress`, polled while the upgrade runs) rather than from a hardcoded copy in the UI that had drifted to six entries while the server emitted up to eleven — including the long ones, `Re-embedding knowledge` and `Embedding integrity check`, which are exactly the steps that used to look like a freeze. Skipped and warning outcomes render as themselves instead of appearing stuck. On success the dashboard opens on its own, as before.
- **The plain loading screen says what it is waiting on** — `Checking setup…`, then `Checking version…` — instead of a bare "Loading…".
- **Delete a plan's tasks from the dashboard.** Task rows in the plan detail view now have a delete button. The confirmation names the task being removed, and the plan, its progress and the list counts refresh afterwards. The read-only task lists on the active-plan cards are unchanged.
- **See where a plan came from.** A plan that continues another one now carries a `↳ Continuation` chip on its card in both plan lists, and its detail view opens with an **Origin** line naming the parent plan — both jump straight to it. Previously this was only inferable from the chain diagram further down the page, which is hidden entirely for a plan whose chain was cut short. The chain card now also says when it is showing only part of a longer chain.

### Fixes
- **A second upgrade request re-ran the entire upgrade.** `POST /api/upgrade/run` waits for an in-flight deploy rather than rejecting — but once that finished, the waiting request went on to run the whole thing again: database re-init, the re-embed probe, a full artifact redeploy and an npx cache wipe. It now returns the completed run's result instead of repeating it, and reports an explicit no-op when the app was already up to date. A run that did *not* complete cleanly is never replayed from that cache — retrying really retries it.

### Notes
- `GET /api/upgrade/progress` publishes step names and statuses only. Step *messages* are deliberately withheld from it — they embed raw filesystem errors, and with them absolute paths — and remain in the upgrade response the app itself consumes.

## v2.4.0

**The knowledge base never shrank.** Nothing expired, nothing was ever retired, and near-duplicates could only be found manually in Settings — so a base that grows by a few hundred entries a month only ever got noisier. This introduces a periodic **cleanup report**, designed to run every 10 days and propose what could go — entries tagged `deprecated`, entries nobody has retrieved in six months, and groups of near-duplicates to consolidate into their newest member. **Nothing is deleted automatically.** The report is a proposal; you approve each item.

> Requires a rebuild and a full app restart, plus the MCP config refresh to `@cognistore/mcp-server@2.4.0` — an older MCP server records no reads, which unread detection guards against explicitly (see below).

### Features
- **Per-entry read tracking.** New `last_read_at` / `read_count` columns record when an entry is actually retrieved. Tracking is **opt-in per call**: agent retrieval through the MCP `getKnowledge` tool and explicit dashboard searches count; browsing, internal scans and re-embeds deliberately do not, or the signal would say everything is in use. Marking never touches `updated_at` or `version` — a read is not an edit.
- **Cleanup detection.** Deprecated (tag `deprecated`), unread (180-day window, tunable in `~/.cognistore/settings.json`, with tag `keep` as an escape hatch), and near-duplicate groups above a deliberately high similarity threshold (0.92, since the non-survivors get deleted).
- **Consolidation merge via a local model.** Duplicate groups are merged by a small Ollama chat model (`llama3.2:3b`, pulled on demand), with a deterministic concatenation fallback that loses no information when Ollama is unavailable. The model only ever proposes a title and body — **it never chooses tags**, which are recomputed server-side.
- **Review and approve in Settings.** The new *Cleanup Report* section lists what the cycle proposes, grouped by reason. Removals are approved per item or per group; a consolidation shows its members with the survivor starred and **cannot be applied until its merged text has been previewed** — approving unseen text would delete the others on the strength of it. A banner on the home page appears when proposals are waiting.
- **Configurable.** Interval, unread window, similarity threshold and merge model are all settings, changed through `settings.json` or `PUT /api/settings` — this release ships no editor for them in the UI, only the read-only values the report renders. Values are clamped on both read and write, so a hand-edited `settings.json` cannot turn the whole base into deletion candidates.
- **Plans now form chains.** A plan created without a reference is the **ORIGINAL** of an effort; every plan created afterwards for the same effort passes `parentPlanId`, so nothing is orphaned — including plans a subagent creates on its own, which is exactly where the lineage used to disappear. The new `getPlanChain` tool (and `GET /api/plans/:id/chain`) answers from any member of a chain and returns the original first, and the dashboard's plan detail view shows the chain indented by depth. `listPlans` marks which plans are originals; `updatePlan` can link a plan after the fact, or unlink it with `parentPlanId: null`.
- **The agent is told which id to pass.** The Claude Code hooks suggest the current effort's plan id as `parentPlanId` before each `createPlan`, and inject it when a subagent is dispatched, so the id reaches the subagent's prompt even though it does not share the parent session's markers. Entering plan mode clears the cursor — a new plan-mode cycle is a new effort, not a branch of the last one. The cursor is its own marker, so clearing it never disturbs the task-tracking reminders for a plan that is still running.

### Fixes
- **The `-active-plan` hook marker was never written by `createPlan`.** A plan id lives in the MCP tool *response*, which arrives as an escaped JSON string, and the extractor only matched bare quotes — so it silently returned nothing and the marker was only ever created later, by the `updatePlan` hook. Task-sync reminders therefore started one call late and, in a create-only session, not at all. The hooks now read escaped responses, and ids are dropped unless they are UUID-shaped before being written to a marker or injected back into the agent's context.

### Notes on safety
- **Unread detection stays silent for its first six months.** The migration starts every existing entry's clock at install time (there is no read history to mine), so the window only becomes meaningful once tracking has existed that long. The report says so explicitly instead of showing a misleading empty bucket.
- It also suppresses itself if no read has been recorded recently — an outdated MCP server records nothing, and without this guard every heavily-used entry would look abandoned.
- Approving re-checks the entry still qualifies, so un-tagging or re-reading something after the report was generated is honoured rather than overridden by the stale queue.
- Each deleted entry is snapshotted into the candidate record *before* deletion. That snapshot is the only copy of an irreversibly deleted entry, so a terminal candidate can no longer be overwritten by a second click. Recovering from it currently means querying the database by hand — a restore button is not in this release.
- A candidate is claimed with a conditional update, so two dashboard windows cannot both apply the same one, and a late write cannot land on an already-closed report.
- A report left open for more than twice the interval closes itself on the next cycle: only one report may be open at a time, so an ignored one would otherwise block the cycle forever.

### Security
- **Dependency refresh clearing outstanding advisories.** `brace-expansion` **5.0.8 → 5.0.9**, `fast-uri` **4.1.1 → 4.1.2** and `hono` **4.12.32 → 4.13.0** resolve upward through the `>=` security overrides added in v2.3.6; `event-listener` **5.4.1 → 5.4.2** on the Rust side. No direct dependency or override range changed — this is a lockfile-only update.
- **`express-rate-limit` 8.3.1 → 8.6.2 finally moves `ip-address` off 10.1.0 (now 10.4.0).** This is the transitive bump `osv-scanner.toml` had recorded as unreachable, on a premise that turned out to be wrong: the ignore entry for `GHSA-v2v4-37r5-5v8g` claimed the fix "requires an MCP SDK release that bumps `express-rate-limit`", but `@modelcontextprotocol/sdk` is unchanged at 1.27.1 and its `^8.2.1` range always permitted 8.6.2 — a plain lockfile re-resolution was enough the whole time. (The entry also mislabelled the advisory as an SSRF bypass; it is an XSS in `Address6`'s HTML-emitting methods, fixed in 10.1.1.) A scan with the CI-pinned OSV-Scanner confirms the advisory is cleared (it reported the suppression as an unused ignore), so that entry has been removed from `osv-scanner.toml` rather than left to mask a future regression.

### Internal
- Migration `2.4.0` (in both `migrations/2.4.0.sql` and the embedded copy) adds the read-tracking columns, a `cleanup_meta` table and the `cleanup_reports` / `cleanup_candidates` queue. A unique partial index enforces one open report at a time.
- Merge policy lives in `packages/core/src/services/cleanup-merge.ts` and is re-applied at apply time, so a hand-made request cannot bypass rules enforced only on the producing side.
- The Ollama chat client lives in `@cognistore/embeddings` (the product's single Ollama boundary) rather than in the sidecar, reusing the existing model-pull logic.
- 69 new tests across `cleanup-report`, `cleanup-merge`, `cleanup-settings`, `cleanup-routes`, `read-tracking` and `migration-parity`. The parity test locks the two copies of every migration (the `.sql` files the sidecar runs and the strings the bundled MCP server runs) to the same statements, since a drift would give one machine two different schemas under one `schema_version`.
- The sidecar's settings file location is now overridable with `COGNISTORE_HOME`. `SQLITE_PATH` only ever moved the database — `settings.json` still resolved from the home directory, so any test hitting a route that persists a setting rewrote the developer's own `~/.cognistore/settings.json`. The override is scoped to `server/settings.ts`; the rest of the sidecar still resolves its install directory from `homedir()`. Production never sets it.
- Uninstall now removes Ollama models with an argument array instead of a shell string, and covers the merge model as well as the embedding one.
- Migration `2.4.1` adds `parent_plan_id` / `root_plan_id` to `plans` plus their indices. The number is ahead of the app version on purpose: migration versions are independent of app versions, and `2.4.0` was already applied on this branch. `root_plan_id` is denormalized so a chain is one indexed lookup; there is no foreign key (SQLite cannot add one via `ALTER TABLE`), so parents may dangle and cycles may exist — every traversal lives in `packages/core/src/services/plan-lineage.ts` and is bounded by a visited set, depth 64 and 500 entries. A synchronous unbounded walk would hang the sidecar and every MCP server sharing the database.
- Lineage is validated in `KnowledgeService`, the one choke point the MCP server, the SDK and the dashboard's `PUT` route share (`sdk.updatePlan` runs no schema of its own). Deleting a plan repairs the chain around it in a single transaction; `importPlans` strips lineage, since ids are regenerated on import and a foreign id would graft onto an unrelated local chain.
- The "never call createPlan from a subagent" rule is replaced everywhere it was stated (base instructions, the Claude Code skill, the seeded system knowledge) with: a subagent that owns an implementation slice may create a plan, but must pass the main effort's `parentPlanId`; review-only subagents still must not.

## v2.3.6

> Never released standalone — this fix ships as part of v2.4.0 (PR #101 was superseded by PR #102, which contains all of it).

**The app stopped upgrading itself — silently — and agents ended up talking to a years-old MCP server.** Every installed build reported its version as `0.0.0`, which made the upgrade check permanently answer "nothing to do", so hooks, skills, agent instructions and MCP configs were frozen at whatever first shipped. Meanwhile the generated MCP config used an *unversioned* `npx -y @cognistore/mcp-server`, which `npm exec` happily satisfied from a stale globally-installed copy on `PATH` instead of the registry. Together those produced an unsolvable deadlock: a hook from one release demanding a `planFilePath` argument that an old server's `createPlan` schema rejected, leaving agents unable to leave plan mode at all.

### Fixes
- **The app knows its own version again.** The version was read at runtime from a `package.json` next to the bundle, but the packaged sidecar runs from `Resources/dist-server/` and `package.json` was never copied there — so the `catch` branch silently returned `0.0.0` forever, and `needsUpgrade` (`compareSemver('0.0.0','0.0.0') > 0`) was always false. It is now **inlined at build time** by tsup (`__APP_VERSION__`, matching what the frontend already did), read behind a `typeof` guard so the separate `tsc` build still works, and `package.json` is bundled into `Resources/` as a fallback. If the version still can't be resolved, the app now says so loudly in the log instead of pretending to be `0.0.0`.
- **A failed or unknown version is never written to disk.** `~/.cognistore/.version` holding `0.0.0` is unrecoverable — it disables upgrades permanently — whereas a *missing* marker simply reads as a first install. The marker is now only written for a known version, and only when no deploy step failed (previously a half-finished upgrade was recorded as complete).
- **Artifacts self-heal on launch.** Re-deploying hooks/skills/configs used to require opening the dashboard so the UI could call `/api/upgrade/run`; an app that was never opened stayed stale indefinitely. The sidecar now re-deploys them at startup when the on-disk artifacts lag the running version. It is gated to app-launched sidecars only, skips first installs (that is the setup wizard's job), and tracks its own `.artifacts-version` marker so it does not interfere with the embedding re-embed and integrity steps that `/api/upgrade/run` owns.
- **MCP configs are pinned to a real version.** Generated entries now use `@cognistore/mcp-server@<version>` (falling back to `@latest` when that version isn't published yet, e.g. for source builds), so a stale global install can no longer shadow it. Setup and upgrade also **warn** when they spot a divergent global install, naming the `npm uninstall -g @cognistore/mcp-server` fix — the app never touches your global npm itself.
- **Works with a hardened `~/.npmrc`.** Pinning the version forces a fresh `npx` install, which must compile `better-sqlite3`. With `ignore-scripts=true` set globally that build is skipped and the server starts but can't open the database (`Could not locate the bindings file`). The generated entry now sets `npm_config_ignore_scripts=false` for that subprocess only.
- **OpenCode configs no longer lose the pinned paths.** `setupOpenCodeMcp()` hardcoded `['npx','-y','@cognistore/mcp-server']`, discarding both the pinned Node `npx` path and the package version its caller had resolved. It now derives the command from the entry it is given.
- **A concurrent deploy no longer looks like a failed upgrade.** The in-progress flag was only cleared on the success path, so one thrown error wedged it and every later upgrade returned `409` forever; it is now released in a `finally`, shared by all three deploy paths, and `/api/upgrade/run` waits for an in-flight deploy instead of rejecting. `/api/upgrade/run` also reports the correct `fromVersion` (it previously read the marker *after* overwriting it).

### Security
- **Dependency updates clearing 20 known advisories** (1 Cargo, 19 npm). `@fastify/static` **9 → 10.1.2** (path-traversal and redirect issues) and `react-router-dom` → **7.18.1** are direct upgrades; `hono`, `@hono/node-server`, `body-parser`, `brace-expansion`, `fast-uri`, `find-my-way`, `postcss` and `shell-quote` are pinned transitively via `pnpm.overrides`; `serde_with` **3.18.0 → 3.21.0** on the Rust side. Note the previous `hono` override pinned an *exact* version, which is what had been holding it at the vulnerable release — security pins should be `>=` ranges.
- **One advisory is knowingly not fixed and now documented in `osv-scanner.toml`.** `GHSA-qwww-vcr4-c8h2` (React Router RSC-mode CSRF) is fixed only in react-router **8.3.0**, which is unreachable while `react-router-dom@7.18.1` pins react-router to 7.18.1 exactly — reaching it means migrating off `react-router-dom` entirely (v8 merged the packages). The advisory is specific to RSC mode; the dashboard is a client-only SPA using just the declarative router, with no RSC, data-router actions or loaders.

### Internal
- `buildMcpEntry()` and the version-marker helpers moved to `apps/dashboard/server/mcp-entry.ts` so they can be unit-tested — importing `server/index.ts` boots a listening server.
- The three deploy paths (`/api/upgrade/run`, `/api/redeploy`, startup) now share one `redeployArtifacts()` covering instructions, MCP configs, skills and global hooks. Database work, seeding, re-embedding and the version write deliberately stay with `/api/upgrade/run`. As a side effect, `/api/redeploy` now reports missing templates as errors instead of silently succeeding.
- New `packages/tests/src/e2e/mcp-entry-pinning.test.ts` (17 tests) covers spec resolution, the `ignore-scripts` override, marker write refusals, shadow detection and the OpenCode command. `plan-gate-hooks.test.ts` gains an end-to-end check that a `createPlan()` **without** `planFilePath` really does let `ExitPlanMode` through.
- The sidecar is launched with `COGNISTORE_MANAGED=1`, which gates the startup re-deploy. Without it the e2e suite — which spawns the real sidecar against the developer's actual `HOME` — would rewrite their own `~/.claude` config on every test run.

## v2.3.5

**Leaving plan mode no longer gets stuck re-running `createPlan()`.** The Claude Code hook that gates `ExitPlanMode` only recognised a plan persisted via `createPlan()` *with* a `planFilePath`, so once a plan already existed, calling `updatePlan()` (even to add that path) couldn't satisfy the gate — the agent was forced to re-run `createPlan()`, which dedups into the draft and produced duplicate/churned plans and deny loops. The gate now accepts **`createPlan()` OR `updatePlan()`**. The fix redeploys automatically on the next app upgrade — no manual action needed.

### Fixes
- **`updatePlan()` now satisfies the ExitPlanMode gate.** `post-update-plan-cleanup.sh` opens the plan-persistence gate on any successful `updatePlan` (a `updatePlan` always targets an existing plan), and `post-create-plan-marker.sh` now opens it whether or not a `planFilePath` was recorded — recording the path is recommended for local-file linkage but no longer required to leave plan mode.
- **The gate no longer re-blocks on retry.** `pre-exit-plan-check.sh` used to consume (`rm -f`) its marker on success, so when a second `ExitPlanMode` denier (the review gate) forced a retry, the marker was gone and the agent had to persist again. The marker is now left in place; it is still reset per plan-mode cycle by `pre-enter-plan-check.sh`, so entering a new plan afresh correctly re-requires a persist.

### Internal
- New behavioral test `packages/tests/src/e2e/plan-gate-hooks.test.ts` exercises the marker handshake against the real hook scripts (deny → `updatePlan` opens the gate → allow without consuming → per-cycle reset → `createPlan` without `planFilePath` still opens).

## v2.3.4

**Release-pipeline reliability — no application changes** (the app is identical to v2.3.3). Fixes the automated verification that was meant to gate v2.3.3 but couldn't run.

### Fixes
- **`verify-release` can now read the draft release it verifies.** The job that checks a release's `latest.json` is complete before promoting it ran with `contents: read`, but a *draft* release is only visible to a token with push access — so it failed with 403 and v2.3.3 got stuck as an unpublished draft (it was promoted manually). It now uses `contents: write`.
- **Re-running a publish no longer disturbs an already-shipped release.** `create-release` detects a published (non-draft) version and skips the build/verify/promote jobs (and the stale-asset cleanup), so a workflow re-run can't momentarily delete a live release's `latest.json`/updater assets. A new version or an incomplete draft still builds normally.

## v2.3.3

**macOS auto-update is reliable again, and the release pipeline can no longer ship a half-built update.** The v2.3.2 release went out missing its macOS updater manifest, so in-app updates from 2.3.1 silently found nothing. The publish workflow now builds each release as a **draft**, **verifies** the updater manifest is complete, and only then **promotes** it to public — and it produces that manifest deterministically instead of racing.

### Fixes
- **Auto-update no longer breaks on release.** Two independent races in the multi-platform publish could leave `latest.json` (the updater manifest) and the macOS `.app.tar.gz` missing or incomplete: a per-job "clean stale assets" step let one platform's job delete another platform's updater artifacts, and the two platform jobs wrote `latest.json` concurrently (last-writer-wins, dropping a platform). The cleanup now runs **once** before the builds, and the platform builds run **serially** (`max-parallel: 1`) so the manifest accumulates every platform deterministically. A new **verify-release** job asserts `latest.json` contains every expected platform + signature (and all installers exist) while the release is still a **draft**; a **promote-release** job publishes it only after that passes — so updater clients never see a partial release.
- **Stuck Intel job no longer stalls every release.** The macOS Intel (`macos-13`) build hung in "queued" and got cancelled after ~24h on every recent release. `publish-tauri` now has a `timeout-minutes` and the Intel target is removed (see below).

### Removed
- **macOS is now Apple Silicon only.** The Intel (`x86_64-apple-darwin`) build is dropped. This is a documentation correction as much as a change: the Intel job never completed, so **no Intel `.dmg` has ever actually shipped** — the download tables just implied one existed. Apple Silicon (M1/M2/M3/M4) is unaffected.

### Notes
- **"App is damaged" on first install is expected** — the app isn't signed with an Apple Developer certificate, so macOS Gatekeeper blocks a freshly downloaded `.dmg`. Right-click the app → **Open** (or **System Settings → Privacy & Security → Open Anyway**), or run `xattr -dr com.apple.quarantine "/Applications/CogniStore.app"`. This is a **one-time** step for the initial install; **in-app updates need no workaround** (they replace the app without a download quarantine flag).
- The auto-update reliability applies **from v2.3.3 forward**. If you're on v2.3.2, do the one-time un-quarantine to install v2.3.3; after that, updates arrive in-app automatically.

## v2.3.2

The dashboard **Activity chart no longer loses history** when the operations log is pruned. Daily read/write counts are now kept in a permanent, never-pruned rollup — the same keep-forever model as token usage — so a historical day can never silently drop to zero again. The schema migration runs automatically on app upgrade; no manual action needed.

### Fixes
- **Activity-chart data no longer vanishes.** The chart aggregated the raw `operations_log` table, which is hard-`DELETE`-pruned by a 6-hour maintenance job. Because the chart zero-fills every day in view, a pruned day rendered as **Total 0** instead of disappearing — so an older point (e.g. one exactly at the retention edge) could show 305 one day and 0 the next. Raising retention to 800 days (v2.3.0) only pushed the cliff out; it didn't remove it, and the value that actually prunes lives in the **running sidecar binary** — a process launched from an older build kept pruning at the old window regardless of the source fix. The chart now reads a new permanent `operations_daily` rollup that pruning the raw log can never affect. **Note:** days already deleted before this release are unrecoverable from the app itself (a pre-prune `~/.cognistore/knowledge.db` backup can be restored manually); durable history accrues from this release forward, and taking effect still requires rebuilding and fully restarting the app so the old pruning process is replaced.

### Internal
- **Migration `2.3.2`** creates `operations_daily(date PK, reads, writes)` and backfills it from the still-surviving `operations_log` rows, in both the disk and embedded migration paths (bundled MCP server stays in sync). `logOperation`/`logOperationBatch` now upsert the rollup (`reads = reads + excluded.reads`) atomically in the same transaction as the raw insert; `getOperationsByDay` reads the rollup with a date-only cutoff (a full-ISO cutoff sorted past a bare `YYYY-MM-DD` key and dropped the boundary day) and pure-UTC zero-fill stepping (DST-safe `length === days`; same hardening applied to `getPlansByDay`). A new `reconcileOperationsDaily()` **MAX-merges** the retained raw window into the rollup on the maintenance tick **before** pruning, self-healing any gap left by a stale/other-process writer without ever reducing an accumulated count. Retention stays at 800 days. Tests cover rollup upsert, prune-survival regression, migration backfill idempotency (disk + embedded), and the `730`-bucket boundary.

## v2.3.1

Claude Code no longer prompts you tool-by-tool to approve CogniStore. Setup now injects a single **server-scope** permission rule that pre-approves every CogniStore MCP tool at once, and it migrates existing installs automatically on upgrade — no manual action needed.

### Fixes
- **No more per-tool permission prompts in Claude Code.** Setup used to inject a hardcoded list of 13 individual tool-allow rules into `~/.claude/settings.json`, but the CogniStore MCP server exposes 17 tools — so `listPlans`, `archivePlan`, `deletePlanTask`, and `getTokenUsage` still prompted on first use for every user, and any newly-added tool would prompt again. The setup now injects the single server-scope rule `mcp__cognistore`, which pre-approves **all** CogniStore tools, current and future. On upgrade/redeploy the old per-tool rules (`mcp__cognistore__*`) are stripped and replaced automatically; your own permission rules and your `permissions.deny`/`permissions.ask` entries are left untouched, and re-runs make no change once migrated (no `settings.json.bak` accumulation). Uninstall removes the rule plus any legacy leftovers.
  - **Behavior change to be aware of:** the server-scope rule widens auto-approval to every tool the server exposes now and in the future — including the destructive `deleteKnowledge` / `deletePlanTask` (the former was already auto-approved before this change) — without a per-tool prompt. Also note that upgrade/redeploy re-injects this rule, so if you deliberately narrow CogniStore's permissions by hand, the full rule is restored on the next app update.

### Internal
- `ConfigManager.COGNISTORE_AUTO_ALLOW_TOOLS` is now the single `['mcp__cognistore']` rule; legacy per-tool rules are identified by the `mcp__cognistore__` prefix (`COGNISTORE_LEGACY_ALLOW_PREFIX`). `injectPermissions` strips those on re-inject and stays idempotent (skips — no backup — when there is nothing to add and nothing to strip); `removePermissions` clears the server-scope rule plus any `mcp__cognistore__*` leftovers. New `packages/tests/src/e2e/config-permissions.test.ts` covers fresh inject, migration, idempotency/backup-count, deny/ask preservation, hyphen-lookalike safety, and uninstall — the first tests for these two methods.

## v2.3.0

Provenance tracking — every knowledge entry and plan now records **which platform** and **which agent** created it, with new dashboard charts and filters. The schema migration, MCP-config re-injection, and instruction/template updates all redeploy automatically on app upgrade — no manual action needed.

### Features
- **Agent & platform provenance.** Each entry/plan now carries a `platform` (the host app — Claude Code / Copilot / OpenCode, auto-detected) and an `agent` (the calling agent's own name, e.g. a custom `documentation` agent). The platform is detected automatically: the app injects a per-platform `COGNISTORE_PLATFORM` env var into each MCP config, with the MCP `clientInfo` handshake as a fallback (anything unrecognized → `unknown`). The agent is whatever a named/custom agent passes as `agentId` on `addKnowledge`/`createPlan` (left `unspecified` when not provided) — the injected instructions now remind custom agents to set it so their discoveries can be summarized per agent.
- **Two new Stats charts: "Knowledge by Agent" and "Knowledge by Platform".** Both follow the global date range. The bars are clickable and deep-link to the knowledge list filtered by that agent/platform.
- **Agent & platform filters on the knowledge list.** Browse mode now filters by `agent`/`platform` (via `?agent=`/`?platform=` deep-links from the charts), shown as removable filter chips.
- **Dashboard now keeps and shows up to 2 years of history.** Activity records were vanishing after ~1 month: the operations log was pruned at 30 days and the metrics API clamped any range to 365 days. Retention is now **800 days** (the 730-day view window + margin) and the API clamp is **730 days**, with a new **`2Y`** preset in the date-range picker. Long-range charts thin their X-axis automatically and switch to `YYYY-MM` labels past a year so 730 daily points stay readable. Note: operations already deleted by the old 30-day pruning are unrecoverable — the 2-year history fills in from this release forward.
- **The "Plans Activity" chart now follows the global date-range picker.** It was hardcoded to the last 15 days; it now honors the selected range (including `2Y`), backed by a new `getPlansByDay()` SQL aggregation instead of an in-memory scan of every plan. Completed/archived plan embeddings are now kept **730 days** (was 30) before dropping out of semantic search.

### Internal
- **Migration `2.3.0`** adds `platform` to `knowledge_entries` and `agent_id` + `platform` to `plans` (plus indexes), in both the disk and embedded migration paths so the bundled MCP server and the dashboard stay in sync. New repository aggregations `countByAgent`/`countByPlatform` `COALESCE` NULL into a single `unspecified`/`unknown` bucket; the list filters round-trip those sentinels back to `IS NULL`.
- New API endpoints `GET /api/metrics/by-agent` and `GET /api/metrics/by-platform`; `/api/knowledge/recent` accepts `agent`/`platform` query params.
- **2-year history is constants-only — no schema migration.** `OPERATIONS_RETENTION_DAYS` 30→800 and the `daysBetween` clamp 365→730 (the retention comment cites the clamp as the binding constraint: retention must exceed the largest requestable window). `getPlansByDay(days)` mirrors `getOperationsByDay`'s zero-fill (repository → service → SDK); `GET /api/metrics/plans` gained optional `from`/`to` (legacy 15-day fallback when absent, so the summary widgets that call it unparameterized are unaffected). New shared `dateAxisProps()` chart helper. Tests: the operations-retention test now asserts an ~400-day row survives (not just that >800-day rows are deleted) plus a 730-bucket zero-fill check; new `getPlansByDay` service test; three ranged `/api/metrics/*` HTTP tests.

### Fixes
- **Custom date-range calendar is now legible on the dark theme.** The `react-day-picker` (v9) popover shipped its default light stylesheet, so day numbers were washed out and the selected range rendered as a light-lavender block on the dark background. Added a scoped `.rdp-dark` theme (accent-colored selection, translucent range highlight, `--text-primary`/`--text-secondary` day and weekday text, themed nav chevrons and today marker).
- **`osv-scan` CI is green again.** Four npm advisories with available fixes were failing the scan (`vite` 6.4.2→6.4.3, `hono` 4.12.24→4.12.25, `esbuild` 0.27.7→0.28.1, `@babel/core` 7.29.0→7.29.6). Root cause: the version pins lived in `pnpm-workspace.yaml`, whose `overrides:` block is **inert under pnpm 9** (a pnpm-10 feature) — so they never applied. The fixes now live in `package.json` `pnpm.overrides` where pnpm 9 reads them; the `esbuild` bump is a selective `esbuild@0.27.7` override so the drizzle-kit `0.18` loader is left untouched. Also bumped the Rust crate `anyhow` 1.0.102→1.0.103 (RUSTSEC-2026-0190).

## v2.2.3

A meticulous three-reviewer (code / security / quality) hardening pass over the whole app. No new features; fixes + robustness + test coverage. All artifacts redeploy automatically on app upgrade — no manual action needed.

### Fixes
- **Copilot's `[COGNISTORE-PROTOCOL]` injection was silently dropped on macOS.** `copilot/user-prompt-check.sh` escaped the DB-sourced protocol with the GNU-only `sed ':a;N;$!ba;s/\n/\\n/g'` idiom, which errors on macOS/BSD `sed` (`unused label 'a'`) → a literal newline landed inside the JSON string → Copilot CLI received invalid JSON and dropped the protocol for **every macOS Copilot user**. Replaced with a single portable `awk` pass (escapes `\`, `"`, folds newlines to `\n`) — no jq/perl/python dependency. Regression test added.
- **The dashboard frontend was never type-checked — three real bugs were shipping.** `vite`/esbuild strips types from `.tsx`, and the frontend `tsconfig` (inheriting the root `lib:["ES2022"]` without DOM) emitted ~142 false DOM errors, so nobody ran `tsc` on it. With the `lib`/`types` fixed, the genuine errors surfaced: (1) `SetupPage` read `nodeReady` from a `catch` fallback that omitted it (failed status check → `undefined`); (2) the Plans list computed progress from detail-view state that's null in list view, so the **mini progress bar never rendered**; (3) `archivePlan` in the MCP server passed a bare `'archived'` string instead of the `KnowledgeStatus` enum. All fixed, plus two React-19 `useRef` arg fixes.

### Security / robustness
- **`POST /api/import` now validates its body.** It was the only write endpoint with zero validation (`request.body as any` straight into the importer). A bounded zod schema now gates it (type enum, content ≤ 500 KB, ≤ 200 tags, ≤ 50 000 items, unknown keys stripped) → **400** on a bad payload; the existing system→pattern rewrite stays as a second guard so a privileged `system` entry can never be imported.
- **Plan-file read closed a TOCTOU window.** `GET /api/plans/:id/file` validated the (DB-stored, allow-listed) path, then re-resolved it for `existsSync`/`statSync`/`readFileSync` — a local symlink-swap race between check and read could leak 256 KB of another file. It now opens the fd **once** (`O_RDONLY|O_NOFOLLOW`) and `fstat`s + reads from that fd, so the resolved file can't be swapped out from under it.
- **Upgrade re-embed no longer drops data when Ollama is down.** On a dimension-change upgrade the server dropped the vec tables then re-embedded; if Ollama was unavailable, semantic search was degraded until a later successful re-embed. It now pre-flights an embed probe and **skips the drop** (keeping existing embeddings) when Ollama can't embed.
- **Ollama and frontend fetches are now time-bounded.** `@cognistore/embeddings` had no request timeout — a stalled Ollama socket could hang SDK init and every search. Added `AbortSignal.timeout` (30 s embed, 10 s health, 30 s connect + 120 s idle-guard on the model-pull stream). The dashboard API client gained a 30 s default request timeout (30 min for setup/upgrade/uninstall) so a stalled call surfaces an error instead of an infinite spinner.

### i18n
- **SettingsPage maintenance strings now translate.** The redeploy/cleanup result messages and two button tooltips were hardcoded English; moved to `t()` keys in en/es/pt (with i18next plurals for the orphan-count and failed-step messages).

### Tests / internal
- **New HTTP-endpoint test harness.** Boots the real dashboard sidecar against a temp DB + an in-test mock Ollama and exercises the route handlers the service-level tests can't reach: the `/api/import` zod gate (invalid/oversized/empty → 400, valid strips unknown keys, `system`→`pattern`), the plan-file allow-list + fd read (404 / 403 / missing / real read), and CRUD error shapes. Runs on CI with no Ollama installed.
- **CI now type-checks the frontend + MCP server.** New `type-check` job runs `pnpm type-check` (dashboard frontend, server, MCP server, and each package's `tsc`).
- **Server hygiene (mechanical, behavior-preserving):** a typed `getRawSqlite()` accessor centralizing the raw-handle casts, and a `sendError()` helper collapsing the repeated `reply.code(n); return { error }` pattern.

## v2.2.2

### Fixes
- **Copilot CLI / OpenCode agents no longer told to call tools by the wrong name.** A Copilot user hit *"Tool 'mcp__cognistore__getKnowledge' does not exist"*: every injected artifact (instructions, hooks, skills, and the system-knowledge protocol injected into every session) hardcoded the **Claude Code** tool naming (`mcp__cognistore__<tool>`), but Copilot CLI exposes the tools as **`cognistore-<tool>`** and OpenCode as **`cognistore_<tool>`** (verified against real session logs). The instruction compiler now rewrites tool names per platform; the system-knowledge seed uses bare names with an explicit per-platform prefix note; Copilot hook texts and SKILL.md files use `cognistore-*`; OpenCode skills and the plan-enforcement plugin use `cognistore_*` (old names kept as compat matches).
- **Copilot's "queried" marker never fired.** `post-tool-marker.sh` matched only the Claude-style name — which never occurs in Copilot — so the knowledge-query reminder never went quiet (this had fed the v2.2.0 no-op-loop incident). It now recognizes `cognistore-getKnowledge` / `cognistore-addKnowledge`.
- **Copilot-created plan files now preview and open.** Plans created by Copilot CLI store their plan file under `~/.copilot/session-state/…`, which was outside the dashboard's read allow-list — the preview showed a misleading *"File not found."* and **Open in editor** silently failed even though the file existed. `~/.copilot/session-state` is now an allowed root (the symlink-escape check and bounded read are unchanged), and the UI distinguishes a genuinely missing file from a path outside the allowed folders.
- **Stale skill `hooks/` directories are cleaned on upgrade.** Skill deployment copies over the destination but never deleted files removed from newer templates, so machines upgraded from older versions kept serving outdated hook scripts (with the wrong tool names). Deploy now removes a destination `hooks/` dir when the current template doesn't ship one.

All artifacts redeploy automatically on app upgrade (instructions re-injected, hooks redeployed, skills re-copied, seed updated at startup) — no manual action needed.

## v2.2.1

### Fixes
- **Tag Suggestions "Select all" no longer dead-ends on conflicts.** In v2.2.0, selecting all suggestions could hit *"Conflicting selections — '«tag»' cannot be merged in two directions"* with no practical way out: one tag appearing in several pairs received contradictory default keepers, and fixing dozens of rows by hand was unrealistic (field report with 49 suggestions). Overlapping pairs are now **clustered into groups** (`ui-pattern ↔ ui-patterns ↔ uipattern` renders as one row): one **Keep:** selector per group (default = most-used tag, usage counts shown), and every merge targets that group's keeper — conflicting directions are impossible by construction, so "select all → Apply" always works. Batches larger than the endpoint's 50-merge cap are sent in chunks automatically. The server-side CONFLICT guard remains as a backstop.

## v2.2.0

### Features
- **Batch tag merge.** Tag Suggestions (Settings) now supports selecting multiple pairs and applying them all at once: checkbox per pair with select-all, a per-pair "keeper" selector (defaults to the more-used tag — usage counts are shown), and one **Apply N merges** action. Conflicting selections (the same tag merged in two directions, or a circular chain) are detected client-side and block Apply with a warning; plain chains (`a→b, b→c`) are allowed and collapse to their final target. The whole batch is ONE request — entries touched by several merges are **re-embedded only once** (bounded concurrency against Ollama), and the list refreshes a single time at the end. New `POST /api/tags/merge-batch` endpoint + `mergeTagsBatch` SDK method.
- **Duplicate groups with one-click resolve.** The "Possible duplicates" panel (Settings → Knowledge Health) no longer lists raw pairs — N near-identical entries used to render as up to N·(N−1)/2 rows repeating the same title at 100%. Duplicates are now clustered into **group cards** (union-find over the KNN pair graph, wider K so big clusters stay intact): each card shows every member with scope · type · version · date, a radio to pick which entry to **keep** (defaults to the highest version), and a **"Keep selected, delete N"** action backed by the existing bulk delete (system entries remain protected; per-entry failures are surfaced). `GET /api/health/duplicates` now returns groups.

### Fixes
- **Agent no-op-loop hardening (field incident).** A user's Copilot CLI agent emitted hundreds of placeholder SQL calls trying to appease the cognistore protocol reminder. The Copilot `preToolUse` hook now only fires for edit/exec tools (unknown/third-party tools such as a `sql` MCP tool proceed silently), reminds at most **2×** per session, and the Claude Code deny hook **fails open after 3 denies** so a session can never be permanently wedged when the cognistore MCP server isn't connected (e.g. Ollama down). Hook messages and the injected agent instructions gain an explicit escape hatch: *if `mcp__cognistore__getKnowledge` is not among your available tools, skip the protocol — never substitute other tools to simulate compliance.* Hooks redeploy automatically on upgrade.
- **Destructive actions no longer fail silently.** Deleting/archiving a plan, deleting knowledge (single or bulk), saving a new entry, creating a plan, and updating tasks now surface failures — confirm modals stay open with an inline error instead of pretending success (previously the UI cleared state even when the server call failed). Background polls remain silent by design (documented rule).
- **Plan endpoints validate input.** `PUT /api/plans/:id`, `POST /api/plans/:id/tasks` and `PUT /api/plans/tasks/:taskId` now validate bodies with the shared zod schemas and return **400** with a clear message instead of passing raw payloads to the SDK.
- **Atomic knowledge writes.** `create()` commits the entry row and its embedding in a single SQLite transaction — a failed embedding insert can no longer leave an orphan entry invisible to semantic search.

### Improvements
- **Token Consumption and Providers pages auto-refresh** (5s change-detection poll, same pattern as the Knowledge/Plans lists). The token poll pauses during a manual rescan; the providers poll never touches an open edit form.
- **Accessibility:** modals are real dialogs (`role="dialog"`, `aria-modal`, labelled titles) with a focus trap — Tab cycles inside, Esc closes, focus returns to the trigger.
- **Anti double-submit:** provider row buttons disable while a request for that provider is in flight.
- **i18n:** provider-form placeholders translated; heatmap weekday labels are now locale-aware (`Intl.DateTimeFormat`); the language picker shows native self-names (English / Español / Português).
- **Uninstall completion screen** is now React state instead of a raw `document.body.innerHTML` swap.
- Tag suggestions API now includes per-tag usage counts (`countA`/`countB`).

### Notes
- New endpoint: `POST /api/tags/merge-batch` (1–50 merges per call). `GET /api/health/duplicates` response changed from pairs to groups (its only consumer is the dashboard health panel). No DB schema changes — no migration needed. All release-driving versions bumped to **2.2.0**.

## v2.1.3

### Security
- **`shell-quote` bumped 1.8.3 → 1.8.4 (GHSA-w7jw-789q-3m8p, CVSS 9.2 critical).** A newly-published advisory failed the gating `osv-scan` CI job. The package is a transitive dependency of `@cognistore/core`; pinned via a root `package.json` `pnpm.overrides` (the override mechanism honored by the repo's pinned pnpm 9.15 — `pnpm-workspace.yaml` `overrides` are not read until pnpm 10).

### Docs
- **New dashboard screenshot + README accuracy pass.** Replaced the hero screenshot with the current Knowledge Base view and corrected drift between the README and the shipping app: the MCP **Available Tools** table now lists all **17** tools (added `getTokenUsage`, `listPlans`, `deletePlanTask`, `archivePlan`); the **Dashboard** section reflects the real **seven** pages (added Token Consumption, Providers, Widgets, and the Plans stats sub-page); the **Stats** section drops the removed contribution heatmap and tag cloud and documents the current Top Tags chart; and the stale `scripts/test-agents.sh` / Docker references were replaced with the actual `pnpm test` (Playwright test runner, `packages/tests`) testing story for this Docker-free project. Also corrected leftover **BSL 1.1** license references (README badge + footer, `bump-version.sh`, `documentation/ci-cd.md`) to **MIT** — the project's actual license (the `LICENSE` file and `@cognistore/mcp-server` were already MIT).

## v2.1.2

### Fixes
- **CI `osv-scan` gate failed on 10 fixable npm advisories.** The scheduled security scan flagged two packages in `pnpm-lock.yaml`: **hono** 4.12.18 (4 advisories, fixed in 4.12.21) and **react-router** 7.13.1 (6 advisories, the highest fix being 7.15.0 — incl. the 8.1/8.0 highs `GHSA-49rj-9fvp-4h2h` and `GHSA-8646-j5j9-6r62`). The `hono` version was being held back by an explicit `4.12.18` pin in the `pnpm-workspace.yaml` `overrides` block — bumped that pin to **4.12.24**. `react-router` was transitive via `react-router-dom`, whose direct dependency in `apps/dashboard` was bumped `^7.13.1 → ^7.15.0`, resolving **react-router / react-router-dom 7.17.0**. All 10 advisories cleared (dependency manifests + lockfile only).
- **Plans list didn't refresh on out-of-band changes.** The dashboard Plans screen left its list stale whenever plans were created/updated/completed by another process (the MCP server, OpenCode, a second window) — it only refreshed when you navigated away and back, re-clicked the nav link, or changed a filter (the main infinite-scroll list was deliberately not polled, to avoid resetting scroll). It now runs the same 5s **snapshot poll** the Knowledge Base list uses: it watches the cheap `/api/metrics/plans` aggregate (plan status counts + task stats) and refreshes the list **only when something actually changed**, so external changes appear within ~5s without thrashing your scroll position.

## v2.1.1

### Fixes
- **Desktop publish failed on `ReleaseAsset already_exists` (macOS).** The release matrix declared an Intel build on `macos-14`, but `macos-14`/`macos-latest` are Apple-Silicon runners — so the "x86_64" job actually built **aarch64** and uploaded the same `CogniStore_aarch64.app.tar.gz` updater asset as the arm64 job, colliding and failing the Publish workflow. (The npm `@cognistore/mcp-server@2.1.0` published fine; only the desktop GitHub-release assets were affected.) The Intel build now runs on the **`macos-13`** Intel runner, producing distinct `_x64` artifacts (and a genuinely Intel-native binary + native module). Re-released as **2.1.1**.

## v2.1.0

### Features
- **Hybrid search (semantic + keyword/BM25)**: `getKnowledge` now blends the existing sqlite-vec semantic ranking with an FTS5 full-text index over title/content/tags. A new `knowledge_fts` virtual table (migration `2.1.0.sql`, created idempotently and backfilled at startup) powers BM25 retrieval; results from both paths are unioned and re-ranked as `0.7·semantic + 0.3·sigmoid(bm25)`, so exact-term matches that rank low semantically now surface. The `SearchResult` shape and the MCP `getKnowledge` signature are unchanged. FTS query text is sanitized into quoted phrase literals (no `fts5: syntax error` on punctuation like `c++`), and the whole keyword path is wrapped so search falls back to pure semantic if FTS5 is unavailable.
- **Tag normalization + merge**: tags are normalized on write (trim + lowercase + dedup, order-preserving — no token rewriting). A new **Tag Suggestions** panel in Settings surfaces near-duplicate tags (e.g. `nest.js` ↔ `nestjs`, `redis` ↔ `Redis`) via Levenshtein + token-set similarity, and a confirmed **Merge** rewrites the tag across all entries (`json_group_array(DISTINCT …)`), then re-embeds and re-indexes the affected entries.
- **Knowledge Health**: a new Settings panel lists **stale** entries (not updated in 90d, expired, or low-confidence) and **possible duplicates** (per-entry KNN over embeddings, ≥0.9 similarity). Entries link straight to their editor. Endpoints return summary fields only (no full content) with a result cap.

### Fixes
- **Sidecar Node bumped to v24 — fixes the `better-sqlite3` ABI crash on "Finishing setup"**: the app now pins **Node 24** (macOS + Linux) instead of Node 20 across the Rust sidecar (`find_node`), the setup wizard/`/api/setup/node`, the bundler, and CI. The bundled `better-sqlite3` is an ABI-specific native addon, so a Node-20 runtime loading a Node-24-built binary (or vice-versa) failed with `NODE_MODULE_VERSION` mismatch and the DB never opened. The app **reuses** an existing Node 24 if present and only installs via nvm when none is found. The sidecar bundler now resolves Node via `process.execPath` (so CI's `actions/setup-node`, which has no nvm, rebuilds correctly) and **fails the build loudly** if no Node 24 is available — preventing an ABI-mismatched bundle from ever shipping. The `@cognistore/mcp-server` npm package keeps its `node20` build target for broad `npx` compatibility (its `better-sqlite3` is rebuilt per-runtime by npx). Launch timeout raised to 120s to absorb a cold nvm Node install on upgrade.

### Improvements
- **Knowledge Base & Plans: server-side filtering + infinite scroll.** The KB list now browses the **entire** base (not just the recent 50) with **server-side** type/scope/tag filtering and lazy infinite scroll, so clicking a tag (e.g. from Stats `/?tag=…`) now shows **all** matching entries instead of an empty list when the tag wasn't in the recent window. Typing in the search box switches to semantic search (filters still apply); the external/providers section is unchanged. The Plans list gains a **scope filter** and the same infinite scroll. New `created_at` indexes are created idempotently at startup for fast paging.
- **Plan file: inline preview + open in editor.** In a plan's detail, the file-path chip is now clickable to toggle a **collapsible Markdown preview** of the plan file, with an **"Open in editor"** button (opens it in the OS default text editor — macOS/Linux) and a copy-path action. Reads are confined to an allow-list (`~/.claude/plans`, `~/.cognistore`), size-capped, and the open action uses a no-shell spawn.
- **Security:** CORS is now restricted to local origins (localhost/127.0.0.1/webview) instead of reflecting any origin — external websites can no longer reach local API endpoints.
- **Stats page cleanup**: removed the broken Contributions heatmap (incorrect month labels) and the Tag Cloud. **Top Tags** is now full-width with a **median reference line** and a **distinct-tag count** badge, and each bar/row is **clickable** — it opens the knowledge listing filtered by that tag (`/?tag=…`). Removed the now-dead `/api/metrics/contributions` route, its client method, and the `heatmap` field from `/api/metrics`.

### Notes
- New endpoints: `GET /api/tags/suggestions`, `POST /api/tags/merge`, `GET /api/health/stale`, `GET /api/health/duplicates` (all behind the standard `ensureReady` guard).
- DB migration `2.1.0.sql` (also in `EMBEDDED_MIGRATIONS` for the bundled MCP) adds `knowledge_fts`. It lives inside `knowledge.db`, so no uninstall change is needed. All release-driving versions bumped to **2.1.0**.

## v2.0.3

### Fixes
- **Publish failure caught at PR time instead of post-merge** (`ReleaseAsset already_exists`): the desktop publish derives its release tag from `apps/dashboard/package.json` and builds the binary from `Cargo.toml`, but the existing CI `version-check` only compared the **root** `package.json`. A version could be bumped in root while `apps/dashboard/package.json` / `Cargo.toml` lagged behind — the publish would then rebuild an already-released version and fail uploading its (version-less updater) assets, discovered only **after** merge. This shipped in v2.0.2 (root/mcp-server at 2.0.2, dashboard/Cargo.toml left at 2.0.1).
  - New `scripts/check-release-version.mjs` (`pnpm check:version`) asserts the four release-driving version sources agree: root + `apps/dashboard/package.json` + `apps/mcp-server/package.json` + `Cargo.toml`.
  - New CI job **`release-version-guard`** (PR-only) runs that script **and** queries the GitHub Releases API to fail when the target tag already has a published release — failing closed on any non-200/404 response. Complements (does not replace) `version-check`.
  - Re-synced all release-driving versions (and the `cognistore-dashboard` `Cargo.lock` entry) to **2.0.3**.

## v2.0.2

### Features
- **Agents now have full control over their plan**: three MCP tools let an agent fix and retire its own plans instead of being stuck once a task is wrong or a plan goes stale.
  - **`deletePlanTask(taskId)`** (destructive) — removes a task. If the remaining tasks are all completed (and at least one remains), the plan **auto-completes**; an emptied plan is **not** auto-completed. Returns the updated plan context (`status`, `progress`, `autoActions`).
  - **`archivePlan(planId)`** — takes a plan out of active circulation (`status` → `archived`) **without deleting it**. Reversible via `updatePlan({ status: "active" })` and preserves the plan's linked knowledge. Preferred over deletion. (This reverses the previous "archiving is dashboard-only" guidance — agents may now archive.)
  - **Reorder tasks** — `updatePlanTask` now accepts a `position` parameter to move a task within the plan (tasks are listed by `position` ascending).
  - Agent instruction templates (`_base-instructions.md`) and the `cognistore-plan` skills (Claude Code / Copilot / opencode) document the new capabilities; the MCP server reference (`documentation/mcp-server.md`) adds the new tools and the `destructiveHint` for `deletePlanTask`.
  - No DB migration: `archived` was already a valid `plans.status` value and task deletion already cascades. `@cognistore/mcp-server` is published at **2.0.2**.

### Fixes
- **Dependency vulnerability (`tar` crate)**: bumped the transitive `tar` crate from `0.4.45` → `0.4.46` in `apps/dashboard/src-tauri/Cargo.lock` to clear OSV advisory `GHSA-3pv8-6f4r-ffg2` flagged by the CI dependency scan.

## v2.0.1

### Fixes
- **`@cognistore/mcp-server` failed to install via `npx` / `npm install`**: the v2.0.0 tarball carried `workspace:*` markers in `devDependencies` pointing at private `@cognistore/*` packages that are never published to npm, so `npm install` rejected the package with `EUNSUPPORTEDPROTOCOL`. The bundled SDK/shared/core/embeddings/providers code is already inlined into `dist/index.js` by tsup (`noExternal`), so those workspace entries only existed for local IDE/build resolution and had no business being in the published tarball. The publish workflow now:
  - (a) runs `apps/mcp-server/scripts/strip-workspace-deps.mjs` before pack to remove `@cognistore/sdk` and `@cognistore/shared` from `devDependencies` (pnpm v9 does **not** run `prepack` / `prepublishOnly` lifecycle scripts during `pack` / `publish`, so this is invoked directly from CI, not via an npm hook);
  - (b) packs the tarball with `pnpm pack` and greps `package/package.json` inside it — failing the build if any `workspace:` token or private `@cognistore/(sdk|shared|core|embeddings|providers)` reference survives;
  - (c) publishes via `pnpm publish --provenance --access public --no-git-checks` so any residual `workspace:` ranges added in the future are rewritten as a second safety net;
  - (d) restores the working-copy `package.json` after publish via `scripts/restore-workspace-deps.mjs` (`if: always()`, idempotent).

  Consumers should pin `@cognistore/mcp-server@>=2.0.1`; v2.0.0 will be unpublished from npm.

## v2.0.0

Major release: **External Knowledge Providers (MCP)**. CogniStore can now augment its local semantic search by also querying external **MCP servers** you connect. Search runs **local-first** and, when external search is active, **also** queries enabled providers — returning everything **sectioned by source**. External search is **opt-in and disabled by default**, so existing behavior is unchanged unless you turn it on.

### Features
- **MCP-only connectors**: connect any MCP server as a knowledge source — a local **stdio** subprocess or a **remote** Streamable HTTP server — in `tool` or `resources` mode. (CogniStore acts as an MCP client; this aligns with the standard the broader ecosystem converged on, so one connector works everywhere.) A `@cognistore/providers` package implements the federation layer (`ProviderManager` fan-out with per-provider failure isolation, per-provider timeout, and abort).
- **Auth that fits MCP**: **stdio** servers receive their secret as an env var the subprocess reads (keychain-backed). **Remote** servers authenticate at the connection with **OAuth 2.1 + PKCE** (browser consent via a loopback redirect, with automatic token refresh) or a **static `Authorization` header**. CogniStore reuses the MCP SDK's built-in OAuth client (discovery, PKCE, Dynamic Client Registration, token exchange/refresh).
- **Sectioned results**: external results are returned in **separate, source-labeled sections** (one per provider) alongside the local section — never merged or cross-ranked. Provider `score` values are not comparable to local cosine similarity, so sections stay distinct.
- **Opt-in, two ways**: per query via the `includeExternal` / `providers` parameters (on the MCP `getKnowledge` tool and `POST /api/knowledge/search`), or globally via the **`alwaysSearchExternalProviders`** setting (default `false`). `getKnowledge` with no flag returns a byte-identical local result — full backward compatibility.
- **Dashboard provider manager** (**Settings → External Knowledge Providers**): list / add / edit / enable-disable / **test** connectors, with **stdio** and **remote** forms, a **Connect** button that runs the OAuth browser flow, an **always-on** toggle, and a secret field that writes to the OS keychain. The Home search view renders an additive, provenance-labeled **"External provider results"** area with an *external · untrusted* badge and per-section timing/error states. Localized in **en/es/pt**.
- **Plans link their source file**: a plan authored from a local plan file (e.g. plan mode) now records that file's **absolute path** (`planFilePath`) on the CogniStore plan — surfaced as a copyable path in the dashboard and **mandatory** in the agent protocol/skills/hook. New nullable `plans.plan_file_path` column (folded into the `2.0.0` migration). The plan-mode hook now **gates `ExitPlanMode`** until the plan is persisted *with* a `planFilePath`, so any agent reopening the plan always finds the original local file.
- **Global enforcement hooks (Claude Code + Copilot CLI)**: CogniStore now installs **real, always-on hooks**. Previously the hook scripts were copied into skill directories (`~/.claude/skills/*/hooks/`), which Claude Code never registers — so they never fired. The hooks are now injected into `~/.claude/settings.json` (the only place global hooks run) and `~/.copilot/hooks/hooks.json`, with scripts living in `~/.cognistore/hooks/`. They use the current hook schema (`hookSpecificOutput.permissionDecision` for `PreToolUse` denials; `additionalContext`/`systemMessage` for reminders) and enforce the full workflow: **query first** (deny edits until `getKnowledge()`), **persist plan** (deny `ExitPlanMode` until `createPlan()` with a `planFilePath`), **track tasks**, and **capture at end** (the `Stop` hook blocks once when work was done but nothing was captured). Markers are **keyed by `session_id`** so concurrent sessions don't race. Everything **fails open**: any error or a missing DB allows the action, and `COGNISTORE_DISABLE_HOOKS=1` (or `~/.cognistore/hooks-disabled`) bypasses all hooks. Copilot hooks are reminder-only (the Copilot CLI has no block/deny output).

### Improvements
- **Smarter plan dedup**: `createPlan()` no longer over-merges. The merge threshold was raised from `0.5` to **`0.7`**, and appending into an already-**active** plan now requires **`0.8`** — so genuinely different work in the same project becomes its own plan instead of being force-merged into whatever was open. When a related-but-distinct plan exists, the response includes `dedupSkipped`, `nearestPlanId`, `nearestSimilarity`, and a hint pointing at `updatePlan()` if it really is the same effort.
- **Plan-augmented retrieval**: `getKnowledge()` now also mines knowledge **linked to semantically similar plans** (both `input` = consulted and `output` = produced) and surfaces it with a `provenance` label, ranked **after** all direct hits and capped to a small budget. This raises the chance of returning relevant prior knowledge. On by default for the MCP tool; off by default at the SDK/service layer (existing callers and the federated path are unchanged).

### Security
- **stdio secrets in the OS keychain**: stored via Tauri `keyring` commands (macOS Keychain, Windows Credential Manager, Linux Secret Service) — **never** in `providers.json`, logs, or query strings (`providers.json` holds only a `secretRef`). The Rust sidecar reads the keychain and injects `COGNISTORE_PROVIDER_SECRET__*` env vars that the MCP subprocess / `EnvSecretStore` resolve at request time.
- **OAuth tokens**: persisted by the always-running sidecar in `~/.cognistore/oauth-tokens.json` (mode `0600`, atomic writes) so refresh works even with the window closed, with an optional OS-keychain mirror (`cognistore-oauth`). Uninstall and per-provider delete remove the token file and keychain entries (setup/uninstall symmetry).
- **Untrusted external content / indirect prompt injection**: external results are treated as untrusted reference data, never instructions — provenance-labeled sections (`externalNote` warning in the MCP response, *untrusted* badge in the dashboard), size-capped (~8 KB/result, ~64 KB/section), links open with `rel=noreferrer`.
- **Network egress controls**: remote MCP URLs are **HTTPS-only** with an SSRF guard that rejects loopback/private hosts (IPv4 + IPv6 incl. unique-local, link-local, and IPv4-mapped forms) unless `allowInsecure` (dev). Each provider runs under a per-provider timeout (default 5 s) with abort. The sidecar identity token uses a CSPRNG (`getrandom`).

### Documentation
- New `documentation/providers/`: [Plug in MCP](documentation/providers/plug-mcp.md) (stdio + remote OAuth/header), the [config reference](documentation/providers/providers-config.md) (schema v2), and the [security model](documentation/providers/security.md). Updated `architecture.md`, `mcp-server.md` (`getKnowledge` params + sectioned response), `api-reference.md` (`/api/providers*` + federated search), `setup-uninstall.md` (keychain + token-file teardown), and the README index.

### Infrastructure
- New `@cognistore/providers` workspace package (depends only on `@cognistore/shared`); `core` receives a `FederatedProviderSource` by injection, avoiding a `core ↔ providers` cycle. Provider config is validated with zod (`providersConfigSchema`, **v2**); a v1 `providers.json` is migrated to v2 on first load (legacy HTTP providers become disabled stubs to re-add as MCP). DB: a nullable `plan_file_path` column folded into the `2.0.0` migration (idempotent `ALTER`).

### Fixes
- **`scan_state` / `token_usage` tables missing after upgrade from old .deb**: installs that had `1.3.0` recorded in `schema_version` (with the original `consumption_samples` / `consumption_ingest_state` schema) never got the real tables, so the token scanner logged *"no such table: scan_state"* every 5 min. The `2.0.0` migration creates both with `IF NOT EXISTS` (idempotent).
- **`McpKnowledgeProvider.dispose()` race leaked a live client**: a `dispose()` during `getClient()` mid-connect left a connected `Client` alive. A `disposed` flag is checked on entry (throws) and after `connect()` (closes and throws), and `dispose()` nulls `this.connecting`.
- **Malformed `providers.json` was silently swallowed**: parse/validation errors in `loadProviders()` / `reloadProviders()` were discarded; both now log to stderr.

### Linux fixes
- **Floating widgets failed to open**: `always_on_top` + `skip_taskbar` + borderless windows are unreliable on WebKitGTK/X11 at creation time; they are now gated off Linux and always-on-top is applied after the window maps. Widget-open failures are logged instead of silently swallowed by the tray path. (Also: `WEBKIT_DISABLE_DMABUF_RENDERER=1` is set process-wide to prevent an `EGL_NOT_INITIALIZED` crash on some GPU/driver stacks.)
- **Dropdowns were near-invisible**: WebKitGTK ignores `background-color` on native `<select>` widgets, so the dark theme didn't apply (light text on a near-white box). A global rule (`appearance:none` + dark background + custom arrow + styled `option`s) fixes every dropdown.

### Tests
- Provider test suite reworked for the MCP-only model: v1→v2 config migration + v2 schema validation, fan-out isolation/timeout/abort, MCP tool/resources modes + dispose-race, and OAuth (`OAuthClientProvider` + file/memory token store round-trip, `invalidateCredentials`).

## v1.4.6

### Fixes
- **Floating widgets were invisible (nothing appeared) in release builds**: the widget windows were created with `transparent(true)`, and on macOS transparent webview windows render blank in bundled/DMG builds (a known upstream Tauri/wry issue — [tauri#13415](https://github.com/tauri-apps/tauri/issues/13415), [wry#1524](https://github.com/tauri-apps/tauri/issues/1524)) that the Tauri 2.11 / wry 0.55 bump in v1.4.5 exposed. The window was created and reported visible, but painted nothing, so widgets appeared not to open. Widget windows are now **opaque** with a solid dark background (`widget.css`), which renders reliably in release; the only visual change is square outer corners and no see-through. Widget-open failures (previously swallowed by the tray path) are now logged to `cognistore.log`.

## v1.4.5

### Infrastructure
- **CI no longer re-runs on merge to `main`**: `ci.yml` dropped `main` from its `push` trigger. A merge to `main` now triggers only the `Publish` release workflow, instead of also re-running the full CI (which had been redundantly rebuilding the app on top of the pull-request run that already validated it). Pull requests still run the complete CI — including `osv-scan`, which remains the required status check — and the weekly Monday cron keeps scanning `main` for new advisories.

## v1.4.4

### Fixes
- **Release build was broken by a Tauri version mismatch**: v1.4.2 bumped the Rust `tauri` crate to 2.11.1 (security fix) but left the JS `@tauri-apps/api` at 2.10.1; Tauri requires both on the same major/minor, so `tauri build` (release) failed its preflight check — which CI's `pnpm build` never runs. Aligned the JS packages to 2.11 (`@tauri-apps/api` 2.11.0, `@tauri-apps/cli` 2.11.2). Verified with a local `tauri build` (full Rust release compile succeeds).
- **Automatic updates never started**: `UpdateChecker` armed its 30-minute check from a synchronous cache that is `false` at mount and only hydrates from `settings.json` a moment later, so the periodic check was never scheduled even with auto-update enabled (only the manual button worked). It now reacts to the hydrated preference (React state) and re-arms when the setting loads or is toggled, and all hook instances stay in sync so toggling in Settings takes effect immediately.

### Infrastructure
- **Renovate runs once a week, Mondays**: `renovate.json` now schedules the single combined update PR for **Mondays 9am–12pm (America/Sao_Paulo)** with `prConcurrentLimit: 1`, instead of the earlier Sunday-night UTC window.

## v1.4.3

### Infrastructure
- **One CI pipeline**: The standalone `security.yml` workflow was folded into `ci.yml`, so a single "CI" workflow now runs every pull-request check together — `version-check`, `validate-dependencies`, `build-and-test`, and `osv-scan`. The `osv-scan` job id is unchanged, so it remains the required status check on `main`. The weekly full vulnerability scan stays (only `osv-scan` runs on the schedule; the other jobs are skipped). The release workflow (`publish.yml`) is unchanged.
- **Switched dependency updates from Dependabot to Renovate**: `dependabot.yml` is removed and replaced by `renovate.json`, which groups all three ecosystems — npm/pnpm, Cargo, and GitHub Actions — into a **single combined update PR** (weekly, `separateMajorMinor: false`, one concurrent PR) instead of one PR per ecosystem. Requires installing the Renovate GitHub App on the repository.

## v1.4.2

### Features
- **Platform column in the Token Consumption tables**: Top Projects and Top Sessions now show which AI tool each row came from — a colored `Claude` / `Copilot` badge derived from `token_usage.source`. A session maps to a single platform; a project that was worked on with both tools shows both badges side by side. The aggregations gained `GROUP_CONCAT(DISTINCT source)` (per project) and `MAX(source)` (per session); the additions are backward-compatible (the `getTokenUsage` MCP tool simply returns the extra fields). Labels are translated in en/es/pt.

### Security
- **Free dependency vulnerability scanning in CI**: New `.github/workflows/security.yml` runs [OSV-Scanner](https://google.github.io/osv-scanner/) (Google, OSS, backed by osv.dev) over the whole repo, covering both dependency ecosystems in a single pass — npm (`pnpm-lock.yaml`) and Cargo (`apps/dashboard/src-tauri/Cargo.lock`) — on pull requests, pushes to `main`, and weekly (Mondays 06:00 UTC). The check fails when a known vulnerability is found. To respect the repo's curated Actions allowlist, the workflow is self-contained: it uses only `actions/checkout` plus the official OSV-Scanner release binary, version-pinned (v2.3.8) and SHA256 checksum-verified — no third-party Action. This gives Snyk/Aqua-equivalent coverage at no cost.
- **Dependabot enabled**: New `.github/dependabot.yml` opens weekly update PRs for three ecosystems — npm/pnpm (root workspace), Cargo (Tauri shell), and GitHub Actions (keeps the workflow SHA pins current) — with minor/patch updates grouped to reduce PR noise. OSV-Scanner gates on known vulnerabilities; Dependabot opens the bump PRs that resolve them.
- **Cleared all fixable advisories from the first scan**: The initial scan flagged 63 known advisories; every one with an available fix is resolved so the gate is green and meaningful. npm fixes are pinned via `pnpm.overrides` in the root `package.json` (turbo 2.9.14 — fixes the lone Critical, vite 6.4.2, esbuild 0.25.0, lodash 4.18.0, fastify 5.8.5, `@fastify/static` 9.1.1, hono 4.12.18, `@hono/node-server` 1.19.13, fast-uri 3.1.2, brace-expansion 5.0.6, ip-address 10.1.1, path-to-regexp 8.4.0, picomatch 4.0.4, postcss 8.5.10, qs 6.15.2, drizzle-orm 0.45.2). Cargo fixes are pinned in `Cargo.lock` (tauri 2.11.1, rustls-webpki 0.103.13, tar 0.4.45, rand 0.8.6). Build + full test suite + `cargo check` all pass.
- **Documented ignore list for unfixable advisories**: New root `osv-scanner.toml` (applied via `--config`) ignores only advisories with no reachable fix — the "unmaintained" RUSTSEC entries from Tauri 2.x's Linux GTK stack (`gtk`/`gdk`/`atk`/`unic-*`/`proc-macro-error`/`fxhash`), plus `glib` 0.18 (pinned by that stack) and a transitive `rand` 0.7.3 — each with a rationale to revisit when Tauri upgrades. With the gate now green, `osv-scan` is a required status check on `main`.

## v1.4.1

### Features
- **Filter Token Consumption by provider**: Both the Token Consumption page and the floating widget gain an `All / Claude / Copilot` filter. `All` shows the combined total of both supported tools (the previous behavior); `Claude` scopes everything to the Claude Code adapter (`source = 'claude-code'`) and `Copilot` to the GitHub Copilot CLI adapter (`source = 'copilot-cli'`). On the page the filter sits next to the date-range picker and drives every section (totals, activity chart, models, cache gauge, time-of-day heatmap, top projects and top sessions); on the widget it's a compact segmented toggle under the title. The backend already supported `source` filtering end-to-end (`token_usage.source` column indexed via `idx_token_usage_source_model`, threaded through every aggregation and the `/api/token-usage` endpoint), so this is a UI change plus one persisted setting.
- **Provider choice persists**: The selection is stored in `~/.cognistore/settings.json` as `tokenProviderFilter`, alongside the date-range preference, so it is shared between the page and the widget and survives app restarts and upgrades. Defaults to `All`.

## v1.4.0

### Features
- **GitHub Copilot CLI token consumption**: A second token adapter joins the existing Claude Code adapter and reads from `~/.copilot/session-state/<sessionId>/events.jsonl` (Copilot CLI v1.x). Sessions with a `session.shutdown` event emit one record per model used (Opus / Sonnet / Haiku / GPT-x) with input / output / cache-read / cache-creation tokens, plus the project decoded from `session.start.data.context.cwd`. Live verification on a real `~/.copilot` directory: 247 records across 25+ projects, all five models attributed correctly. Sessions still active when scanned are skipped until they shut down; no extra config required.
- **All distribution cards on Stats follow the date range picker**: Knowledge by Type, Knowledge by Scope, Top Tags, and Tag Cloud were always-time totals — useless once the user had picked a 1-week window for everything else. They now refetch on range change via the new `/api/metrics/by-type`, `/api/metrics/by-scope`, and the existing top-tags + tags endpoints (both now accept optional `from`/`to`). Card titles get a small `(this period)` suffix in en/es/pt so the source is obvious. Total Entries remains range-independent.
- **Range-aware Consulted / Written cards on Stats**: Brings back the at-a-glance Consulted and Written counters that were removed in v1.3.0, but now they reflect the period chosen by the global date-range picker (1D / 1W / 1M / 1Y / custom) instead of the old fixed 1h / 24h windows.
- **Scrollable Stats cards**: `WidgetCard` gains an optional `maxBodyHeight` prop. Knowledge by Type / Scope / Top Tags / Tag Cloud now cap at 380px with internal vertical scroll, so a user with 30+ workspaces no longer sees one card push everything else off-screen.

### Security
- **Drop unused `@tanstack/react-query` dependency**: The package was declared in `apps/dashboard/package.json` but never imported anywhere in the codebase. Removing it eliminates the transitive attack surface from a dependency that was providing zero functional value. Verified: zero `@tanstack/*` packages in the lockfile post-install.

### Infrastructure
- **Repository range overloads**: `countByType`, `countByScope`, `topTags`, and `listTags` in `knowledge.repository.ts` accept optional `{ from, to }` ISO date params. When both are present, queries filter `created_at >= from AND created_at < to` (closed-open, matching the existing contributions endpoint). When omitted, behavior is identical to today so the Knowledge Stats widget, MCP server, and any other no-range caller keep working unchanged.
- **Adapter pattern proven**: `TokenSourceAdapter.scan()` now allows `record === null` so adapters can mark a file as "seen at this size, nothing to store yet" (used by Copilot for in-progress sessions). The scanner still advances `scan_state` so the next pass skips it until more bytes arrive.

## v1.3.0

### Features
- **Token Consumption page**: New top-level `/tokens` view that tracks how many input / output / cache-read / cache-write tokens you spend in AI coding tools. Includes a stacked daily activity area chart, a model ranking, a cache-efficiency gauge (`cache_read / (input + cache_read + cache_write)`), a 7×24 time-of-day heatmap, and top-projects + top-sessions tables. v1.3.0 ships a Claude Code adapter that parses `~/.claude/projects/<cwd>/<session>.jsonl` incrementally; adapters for Copilot (OTel) and Cursor can be added later without schema or UI changes.
- **Token Consumption widget**: Compact floating widget showing the four 7-day totals; click the header to open the full page. Available from the Widgets page and the tray submenu, with position persistence.
- **Global date-range picker**: New picker (1D / 1W / 1M / 1Y / custom calendar via `react-day-picker` v9) at the top of the Stats and Token Consumption pages. The chosen range drives Activity, Contributions, and the entire Token Consumption page, replacing the previous fixed 15-day and 90-day windows.
- **`getTokenUsage` MCP tool**: Read-only tool that returns the same aggregations as the dashboard for a given date range, optionally filtered by source / model / project.

### Fixes
- **Auto-update preference now survives upgrades**: The toggle previously lived in `localStorage`, which the Tauri webview can wipe across app re-installs and major upgrades, silently flipping the preference back to OFF. It now lives in `~/.cognistore/settings.json` (next to `widgets.json`, which is already known to survive upgrades) and is migrated from the legacy localStorage key on first launch.

### Improvements
- **Dashboard redesign**: The Stats page drops the always-confusing hourly/daily op counters (Consulted/Written 1h/24h) and the duplicated `Last 24h` / `Last 7d` / `Database Size` cards. Only `Total Entries` and the two range-driven charts remain. `Database Size` moves to Settings next to the other infrastructure cards.

### Infrastructure
- **`@cognistore/core` build is now idempotent**: previously `cp -r src/db/migrations dist/db/migrations` (and the matching `seeds` line) would *nest* the source folder inside the existing target on every rebuild after the first one — a BSD-`cp` gotcha. The result: any migration added after the dist had been built once (e.g. `1.3.0.sql`) silently landed at `dist/db/migrations/migrations/1.3.0.sql` and was never picked up by the loader. The build now `rm -rf`s those two folders before copying, so repeated `pnpm build` invocations produce the same layout the first one did.
- **`token_usage` + `scan_state` tables** (migration `1.3.0.sql`, also mirrored to `migrate.ts`'s `EMBEDDED_MIGRATIONS` so the bundled sidecar and the bundled MCP server get the schema without an on-disk migrations directory).
- **Background token scan**: 5-minute incremental scan loop in the Fastify sidecar, plus a one-shot scan on SDK ready. `INSERT OR IGNORE` with a deterministic id (sha256 of `source|sessionId|messageId|occurredAt`) keeps re-scans idempotent; per-file `scan_state.last_offset` keeps them cheap.
- **New endpoints**: `GET /api/token-usage`, `POST /api/token-usage/scan`, `GET /api/metrics/activity?from&to`, `GET /api/metrics/contributions?from&to`, `GET /api/settings`, `PUT /api/settings`. The existing `/api/metrics` is preserved unchanged so the Knowledge Stats widget keeps working.

## v1.2.2

### Fixes
- **Dashboard "Database Size" stuck value**: The Stats page reported only the size of `knowledge.db` and ignored its SQLite sidecars (`knowledge.db-wal`, `knowledge.db-shm`). Between WAL checkpoints the main file barely grows, so the displayed size could appear frozen for days while writes piled up in the WAL. The `/api/metrics` endpoint now sums all three files, so the reported size reflects real on-disk usage and updates promptly after every write.
- **Activity (Last 15 Days) chart leading zeros**: The chart queries the last 15 days from `operations_log`, but the background maintenance job pruned anything older than 7 days, so the first ~8 days of the window always rendered as zero even for daily users. Retention is now aligned to the chart window via a single `OPERATIONS_RETENTION_DAYS = 30` constant in `packages/core/src/repositories/knowledge.repository.ts`, giving the chart full visibility plus a safety margin.

## v1.2.1

### Improvements
- **MIT license**: Changed project license from BUSL-1.1 (Business Source License) to MIT.

### Fixes
- **Linux Ollama install via graphical sudo**: On Linux, the Ollama install script requires root. The setup wizard now tries `pkexec` first (graphical password prompt on GNOME/KDE/XFCE), falls back to non-sudo attempt, then shows clear terminal instructions with the exact command to run. Error messages in the setup page now render multiline text correctly.

## v1.2.0

### Features
- **Multiple floating widgets**: Three draggable widget types — Knowledge Stats (total entries, reads/writes), Plan Stats (plan status breakdown, task completion %), and Active Plans (scrollable list with progress bars). Each widget auto-refreshes every 10 seconds.
- **Widgets page**: New `/widgets` page in the sidebar (Tauri only) to manage all widget types. Cards show widget status with green indicator dot. Open/close buttons for each widget type.
- **Widget position persistence**: Widget positions are saved to `~/.cognistore/widgets.json`. On app restart, all widgets that were open are restored at their last positions.
- **Plan navigation from widget**: Clicking an active plan in the Active Plans widget navigates the main app to the Plans page with focus on that plan.
- **System tray with Widgets submenu**: System tray icon with "Show CogniStore", "Widgets" submenu (Knowledge Stats, Plan Stats, Active Plans), and "Quit". Create new widget instances directly from the tray.
- **Widget actions**: Active Plans widget rows show a delete button on hover. Click to delete the plan directly from the widget.
- **Dynamic Active Plans widget**: Widget height adjusts automatically based on content (up to configurable max, default 5 slots). Scrollbar appears when content exceeds max. Max visible setting available on the Widgets page.
- **Task visibility in Active Plans widget**: In-progress tasks are shown inline under each plan with blue status dots. Click the expand arrow to see all tasks (pending, in-progress, completed with strikethrough). Widget resizes dynamically when expanding/collapsing.

### Fixes
- **Widget close button**: Fixed close button not working — was using `window.close()` which doesn't work in Tauri webviews. Now uses Tauri window API with `core:window:allow-close` permission.
- **Ollama download 404 on Linux/macOS**: Ollama v0.19.0 changed release format from standalone binaries to `.tar.zst` archives, breaking fallback download URLs. Removed broken binary download fallbacks; both platforms now use install script with clear manual install instructions if it fails.
- **Active Plans widget progress**: The `/api/plans` endpoint now enriches plans with `taskCount` and `completedTasks` (matching MCP server behavior). Progress bars in the Active Plans widget now show correct task completion.

### Improvements
- **Application logging**: Logs written to `~/.cognistore/cognistore.log` with automatic rotation (500 lines max). New log viewer in Settings page (collapsible, auto-refresh, color-coded by level). New `/api/logs` endpoint.
- **Friendly launcher errors**: Setup/server errors now show a branded error page with details toggle and retry button instead of raw technical messages.
- **macOS dock behavior**: Closing the main window hides it instead of quitting. Click the dock icon to reopen. Only "Quit" in tray actually exits.
- **Stats page label rework**: Renamed technical labels "Reads/Writes" to user-friendly "Consulted/Written" across all 3 languages (English, Spanish, Portuguese). Sub-labels changed from "searches/mutations" to "knowledge consulted/knowledge written".
- **CogniStore CLI adherence**: Improved hook enforcement for Claude Code — query hook now uses `decision: "block"` instead of `systemMessage` (advisory), with state-aware marker (`/tmp/.cognistore-queried`) so it only blocks until the first query. Plan task sync reduced noise (every 5th edit) with escalation to block after 15+ edits without tracking. Capture nudge starts earlier (5th edit instead of 10th).

### Infrastructure
- **Tauri multi-window support**: New Rust modules (`widgets.rs`, `widget_config.rs`, `tray.rs`) for widget window management, position persistence, and system tray. Widget windows use `WebviewWindowBuilder` with `always_on_top`, `transparent`, `decorations(false)`.
- **Vite multi-page build**: Three widget entry points (stats, plans, active-plans) alongside the main dashboard.
- **Dependency validation CI**: New `validate-dependencies` job in CI pipeline checks that external URLs (Ollama install script, GitHub Releases API) are reachable before merge.

## v1.1.0

### Fixes
- **Fix Ollama "input length exceeds context length" error**: The `/api/embeddings` request did not pass `options.num_ctx`, so Ollama used the model's default context window — which varies by Ollama version and could be too small for some inputs. Fix: explicitly pass `options: { num_ctx: 8192 }` in every embedding request (nomic-embed-text supports 8192 tokens).
- **Auto-resync embeddings on upgrade**: The upgrade endpoint only resynced vec tables when embedding dimensions changed. If entries existed without embeddings (e.g., from a previous failed embedding call), they were silently left orphaned. Added an integrity check (Step 1c) that compares `knowledge_entries` count vs `knowledge_embeddings` count — if any entries are missing embeddings, the upgrade drops vec tables and re-embeds all entries automatically.

### Features
- **`listPlans` MCP tool**: Agents can now browse and filter plans by status (`draft`, `active`, `completed`, `archived`) and scope. Each plan is enriched with task progress (`taskCount`/`completedTasks`). Response includes a hint when abandoned plans with incomplete tasks are detected, steering agents to resume existing plans instead of creating duplicates.
- **Auto-update toggle in Settings**: Added a checkbox to the Updates section (default: OFF). When disabled, the app will not automatically check for or download updates in the background. Manual "Check for updates" button remains always available. Preference is persisted in localStorage.

## v1.0.15

### Fixes
- **Serialize publish pipeline to eliminate race conditions**: `publish-mcp`, `create-release`, and `build-web` jobs ran in parallel with no dependency chain, causing intermittent pipeline failures. Added `needs` directives to create serial chain: `publish-mcp → create-release → build-web → publish-tauri`. Each job still handles its own setup (fast via pnpm/Turbo cache). npm publish runs first so failures stop the pipeline before creating releases or building desktop apps unnecessarily.
- **Fix embedding dimension mismatch (768→256)**: `sidecar.rs` hardcoded `EMBEDDING_DIMENSIONS=768`, which propagated to all MCP configs via `buildMcpEntry()`. The MCP server generated 768-dim embeddings while vec tables expected 256 (after Matryoshka migration in v1.0.12). Root cause chain: `sidecar.rs (768)` → Fastify `process.env` → `buildMcpEntry()` → `mcp-config.json (768)` → MCP server. Fixed by changing sidecar.rs to `256`. Existing user configs will be corrected on next upgrade run (re-writes all MCP configs).
- **Fix "Failed to start server" on fresh installs**: `sdk.initialize()` blocked the Fastify server from calling `app.listen()` — on first launch, `ensureModel()` streams the entire Ollama model download, which can take minutes. The Rust sidecar health check timed out after 15 seconds, showing an error screen. Fix: moved SDK initialization to a background async task after `app.listen()`, so the server binds the port immediately and the frontend loads with the setup wizard. Also increased health check timeout from 15s to 30s as safety net.
- **Fix upgrade screen showing after Tauri auto-update**: After Tauri auto-updates the binary, `~/.cognistore/.version` still contains the old version (Tauri only replaces the app bundle, not user data). On next launch, the version mismatch triggered the full upgrade screen. Fix: `App.tsx` now silently runs the upgrade in the background when a version mismatch is detected, going straight to the dashboard on success. Falls back to the visible upgrade screen with retry only if the silent upgrade fails.
- **Fix publish pipeline failing on re-run (asset conflict)**: `tauri-action` failed with "already_exists" when re-running the pipeline because updater artifacts (`.tar.gz`, `.tar.gz.sig`, `latest.json`) don't have versions in their filenames. Added a cleanup step before `tauri-action` that deletes stale updater assets from the release via `gh api`, making the pipeline idempotent.

### Security
- **Harden GitHub repo**: Enforce admins on branch protection (no direct push to main), dismiss stale reviews, require last push approval, require CODEOWNERS review. Pin all 8 external GitHub Actions to commit SHA hashes. Restrict Actions to GitHub-owned + verified creators + 4 explicit third-party patterns. Create `production` environment with required reviewer.

### Improvements
- **Mid-session knowledge capture enforcement**: Agents were only reminded to capture knowledge at session end (Stop/sessionEnd hook), making it easy to skip. Added PostToolUse hooks that nudge agents during work — after 10+ edits without calling `addKnowledge()`, a prescriptive reminder fires every 5th edit. Positive reinforcement: calling `addKnowledge()` sets a marker that silences all nudges. Stop/sessionEnd hooks are now context-aware: lighter reminder if knowledge was captured, very insistent if not. Applied to both Claude Code and Copilot skill templates.

## v1.0.13

- Version bump to recover npm publish pipeline (v1.0.10–v1.0.12 failed to publish due to expired NPM_TOKEN)
- Includes all v1.0.12 fixes and improvements below

## v1.0.12

### Improvements
- **Reduce embedding storage via Matryoshka truncation (768→256 dims)**: nomic-embed-text supports Matryoshka Representation Learning — the first 256 dimensions retain ~95% of semantic accuracy. Embeddings are now truncated to 256 dims + L2-normalized after Ollama returns the native 768-dim vector. Each embedding drops from 3 KB to 1 KB (67% reduction). Auto-migration detects dimension mismatch on startup and re-embeds all entries. Input text size (8192 token context window) is unchanged.
- **Periodic WAL checkpoint**: Added `walCheckpoint()` (PASSIVE mode) to the 6-hour maintenance interval alongside `cleanupOldOperations()`. Keeps the WAL file compact without blocking readers/writers.
- **Auto-cleanup completed plan embeddings**: Plans with status completed/archived older than 30 days have their embeddings deleted automatically. Semantic search only queries draft/active plans, so this has zero functional impact.
- **Encourage pattern storage in agent instructions**: Added Pattern Checklist (5 concrete questions) to all 3 capture skills (claude-code, copilot, opencode). Enhanced `addKnowledge` tool description to emphasize patterns with global scope. Added pattern prompt to stop-reminder hooks. Added pattern bullet to CHECKPOINT 3 in base instructions.

### Fixes
- **Fix plan detail markdown table rendering**: Added `remark-gfm` plugin to `react-markdown` in `PlansPage.tsx` and `KnowledgeCard.tsx`. Tables were rendering as raw text because `react-markdown` only supports CommonMark by default — GFM tables require the `remark-gfm` plugin. CSS styles for tables already existed in `styles.css`.
- **Fix MCP server stdout pollution breaking protocol handshake**: `packages/core/src/db/migrate.ts` had 4 `console.log()` calls that wrote migration status messages to stdout. Since the MCP server uses stdio transport (stdin/stdout for JSON-RPC), any non-JSON output on stdout corrupts the protocol handshake and causes Claude Code / Copilot to fail connecting. Changed all `console.log` → `console.error` in migrate.ts so diagnostic output goes to stderr instead
- **Fix plan task tracking enforcement**: Agents created plans via `createPlan()` but never called `updatePlanTask()` during execution — all tasks stayed "pending". Three root causes fixed:
  1. `SubagentStop`, `PostCompact`, `TaskCompleted` hooks were unsupported event types that never fired — removed dead hooks
  2. `PostToolUse` only fired on `ExitPlanMode`, not during Edit/Write/Bash where actual work happens — added state-aware PostToolUse hooks on execution tools
  3. Hook messages used advisory language ("sync CogniStore plan") instead of prescriptive ("STOP. Call X NOW") — rewrote all messages with exact function signatures
- **State-aware hook system**: New `/tmp` marker file mechanism tracks active planId across hooks. `post-create-plan-marker.sh` sets the marker after `createPlan()`, `post-edit-task-sync.sh` checks it before reminding, `post-task-update-marker.sh` resets the counter on compliance (positive reinforcement), `post-update-plan-cleanup.sh` cleans up on plan completion
- **Throttled reminders**: PostToolUse hook on Edit/Write/Bash fires every 3rd edit instead of every time, reducing noise while maintaining enforcement. Counter resets when agent calls `updatePlanTask()` — compliant agents get fewer reminders
- **Switch embedding model from all-minilm to nomic-embed-text**: `all-minilm` has a 256-token context window causing `createPlan()` to fail with large content. `nomic-embed-text` supports 8192 tokens (32x more) with 768 dimensions. Upgrade automatically detects dimension mismatch, pulls new model, drops/recreates vec tables, and re-embeds all existing entries and plans. `maxInputChars` raised from 500 to 2000.
- **Fix auto-update system (3 root causes)**: The entire auto-update pipeline was broken:
  1. `window.__TAURI__` was undefined because the WebView loads from `http://localhost:{port}` (Node.js sidecar) without IPC access configured — added `remote.urls` to `capabilities/default.json`
  2. `createUpdaterArtifacts` was missing from `tauri.conf.json` — no `.tar.gz`/`.sig` files were generated, so `latest.json` was never uploaded (confirmed 404 on all releases v1.0.7–v1.0.11)
  3. Non-Tauri fallback path skipped auto-checks on launch and "Update Now" silently did nothing when `__pendingUpdate` was null
- **Fix isTauri detection**: Now checks both `__TAURI_INTERNALS__` (Tauri v2) and `__TAURI__` (legacy) for reliable environment detection
- **Add CSP for GitHub CDN**: Added `objects.githubusercontent.com` to `connect-src` for update artifact downloads
- **Improve update error handling**: Tauri updater failures now fall back to GitHub API check instead of silently failing; all errors logged with `[UpdateChecker]` prefix
- **Fix "Update Now" button in Settings**: When native Tauri update is unavailable, button now opens GitHub release page instead of doing nothing
- **Fix plan dedup KNN saturation**: rewrote `findSimilarActivePlans()` to use pre-filter approach — query `plans` table for draft/active IDs first, then compute cosine similarity in JS. The old KNN approach returned from ALL plans (including completed), saturating results and hiding active duplicates. Now works correctly even with 15+ completed plans
- **Fix knowledge embedding quality**: embeddings were generated from tags only (`tags.join(' ')`), making semantic search unreliable. Now uses full text: `${title} ${content} ${tags.join(' ')}`
- **Fix dashboard read count undercount**: `logOp('read')` was called once per `getKnowledge` call regardless of results returned — a search returning 10 entries counted as 1 read. Now logs N reads for N results, consistent with how writes are counted (1 per entry). Uses a batched SQLite transaction for efficiency
- **Fix `createEmbeddingsTable` hardcoded 768 default**: the function parameter default was `768` instead of `DEFAULT_EMBEDDING_DIMENSIONS` (256). This caused the vec0 table to be created with 768 dims when the env var was absent, conflicting with the Matryoshka 256-dim config and breaking all searches with a dimension mismatch error
- **Scope-filter activePlan hint in getKnowledge**: the `activePlan` returned by `getKnowledge` now filters by the caller's `scope` parameter, preventing cross-workspace plan hints
- **Add tasks to createPlan MCP tool schema**: the `tasks` property was missing from the MCP tool's input schema, causing inline tasks passed by agents to be silently dropped
- **Refactor listPlans**: replaced 4-branch if/else with single dynamic parameterized query supporting status, scope, or both filters
- **Fix Ollama embedding context overflow**: `all-minilm` has a 256-token context window but text was sent without truncation, causing `createPlan()` and `addKnowledge()` to fail with large content. Now truncates at 800 chars (word-boundary aware) in `OllamaEmbeddingClient.embed()`, protecting all callers. Limit is configurable via `maxInputChars`
- **Block ExitPlanMode without createPlan()**: Added PreToolUse hook on `ExitPlanMode` that uses a marker file gate (`/tmp/.cognistore-plan-persisted`). `EnterPlanMode` resets the marker, `createPlan()` sets it, and `ExitPlanMode` is **blocked** if it's missing. Previous enforcement was non-blocking (post-hook reminder arrived too late)

### Improvements
- **Prescriptive instruction language**: "Track each task" section in all agent instructions (Claude Code, Copilot, OpenCode) now uses mandatory language with PostToolUse enforcement notes
- **Removed dead hook scripts**: Cleaned up `subagent-stop-reconcile.sh`, `post-compact-reinject.sh`, `task-completed-check.sh` from both Claude Code and Copilot templates — these were registered under unsupported event types and never executed
- **Removed dead MCP tool files**: Deleted `apps/mcp-server/src/tools/` directory (9 files). All tools were rewritten inline in `server.ts` — the old files were never imported

### Features
- **Auto-archive stale draft plans**: `createPlan()` now runs `archiveStaleDrafts(24)` with 1-hour throttle, automatically archiving draft plans older than 24 hours
- **Scope parameter for listPlans**: `listPlans()` now accepts an optional `scope` parameter across repository, service, and SDK layers
- **Knowledge semantic dedup**: `addKnowledge()` checks for similar entries in the same scope+type (threshold 0.85). If a match is found, updates the existing entry instead of creating a duplicate. Response includes `deduplicated: true`
- **Scope regex validation**: scope field now enforced as `"global"` or `"workspace:<project-name>"` (alphanumeric, dots, hyphens, underscores) via Zod schema across all create/update/search schemas
- **Structured plan content requirement**: all plan skill templates (Claude Code, Copilot, OpenCode) now require `content` to include Context, Approach, Files to Modify, and Verification sections. New `pre-create-plan-check.sh` hook enforces this before `createPlan()` calls
- **Global knowledge encouragement**: capture skill templates and base instructions now actively encourage `scope: "global"` for language/framework/tool insights that apply beyond the current project
- **Plan card timestamps**: plan card dates in the dashboard now show full date+time (hours, minutes, seconds) instead of date-only

### Tests
- **KNN saturation test**: creates 15+ completed plans then verifies dedup still finds a draft in the same scope
- **archiveStaleDrafts edge cases**: verifies active/completed plans are not archived, returns 0 on empty database
- **listPlans backward compat**: undefined scope returns all plans
- **Knowledge dedup**: validates dedup merges similar entries in same scope+type, keeps entries separate across different scopes
- **Global scope knowledge**: validates knowledge creation with `scope: "global"`

## v1.0.11

### Fixes
- **Fix npm publish repository.url format**: corrected `repository.url` to use `git+https://...git` format, preventing npm auto-correction that breaks provenance attestation

### CI
- **Fail CI on npm publish warnings**: `npm publish --dry-run` in both CI and publish workflows now captures output and fails if any `npm warn publish` messages are detected, catching manifest issues before merge
- **Package.json validation tests**: new Playwright test validates bin paths start with `./`, repository URL has correct `git+https` format, required fields exist, and package is correctly scoped

## v1.0.10

### Features
- **Automatic plan deduplication**: `createPlan()` now uses semantic search (via sqlite-vec embeddings) to detect existing plans before creating new ones. If an active plan exists in the same scope, new tasks are added to it. If a semantically similar draft exists, it is updated instead of duplicated. Response includes `deduplicated: true` flag when an existing plan was reused
- **Enriched activePlan in getKnowledge**: the `activePlan` object now includes `scope`, `taskCount`, `completedTasks`, and a dedup-aware hint guiding the agent to use updatePlan instead of creating duplicates

### Improvements
- **Centralized plan embedding operations**: refactored inline SQL for plan embeddings into dedicated functions (`insertPlanEmbedding`, `updatePlanEmbedding`, `deletePlanEmbedding`, `searchPlansKnn`) in sqlite-vec.ts, consistent with knowledge embedding pattern
- **Updated agent instructions**: added dedup note to CHECKPOINT 2 in all platform instructions and "Automatic Deduplication" section to plan SKILL.md (Claude Code + Copilot)

## v1.0.9

### Improvements
- **Auto-approve all CogniStore tools**: expanded permission injection from 4 read-only tools to all 13 tools (read + write), so agents can call `createPlan()`, `addKnowledge()`, `updatePlanTask()`, etc. without prompting the user for permission. This removes friction that was breaking the automatic workflow
- **Reinforced agent instructions**: added CRITICAL section at the top of all platform instructions (Claude Code, Copilot, OpenCode) with a concise 1-line summary of the mandatory workflow. Added rule about tools being pre-approved
- **Prescriptive hooks**: rewrote all hook scripts across Claude Code and Copilot to use direct action commands (e.g., "STOP. Call getKnowledge() NOW") instead of passive reminders (e.g., "Have you queried?"). Hooks now include exact function signatures for easy copy-paste by the agent

## v1.0.8

### Fixes
- **Prevent upgrade on downgrade**: upgrade check now uses semver comparison instead of string inequality, so the upgrade flow only triggers when the running app version is strictly greater than the deployed version — never on downgrades

## v1.0.7

### Improvements
- **Auto-download on manual update check**: clicking "Check for updates" in Settings now auto-downloads and installs when an update is found (same as automatic background checks). Added "Update now" button and download progress directly in the Settings page

## v1.0.6

### Fixes
- **MCP server Node.js version mismatch**: setup/upgrade/reinstall now write the absolute path to the nvm Node 20 `npx` binary in MCP configs and prepend its bin dir to `PATH`, preventing `NODE_MODULE_VERSION` errors when the system Node is a different version. Stale npx caches are also cleared to force recompilation of native modules. Uninstall cleans up the npx cache as well

### Improvements
- **Remove edit button from knowledge cards**: clicking the card already opens the edit modal; the amber pencil button was redundant

## v1.0.5

### Improvements
- **Simplified search screen**: removed export button from the Knowledge page; replaced broken ☐ Unicode with SVG checkbox icon for bulk select
- **Icon buttons on knowledge cards**: replaced text Edit/Delete buttons with colored icon buttons (pencil on amber, trash on red)
- **Unified export/import**: replaced 5 separate buttons in Settings with 2 modal-based flows (Export and Import) supporting selective knowledge and plans in a single JSON file
- **Background auto-update**: in Tauri, updates download and install automatically in background with a restart prompt; outside Tauri, checks GitHub Releases API and shows download link
- **Documentation refresh**: expanded README Settings and Knowledge sections, added packages/tests to architecture tree, fixed version references

### Fixes
- **Export version**: export files now include the actual app version instead of hardcoded "0.9.5"
- **CLAUDE.md version**: updated architecture section version from v0.6.0 to v1.0.4

### Removed
- Old separate export endpoints (GET /api/export/knowledge, GET /api/export/plans)
- Old separate import endpoints (POST /api/import/knowledge, POST /api/import/plans)
- CSV export/import support (JSON-only now)
- "Only available in desktop app" update checker message

## v1.0.4

### Fixes
- **Node.js version mismatch crash**: removed unsafe fallback in `find_node()` that picked the latest nvm-installed Node regardless of major version. When Node 20 was missing, the app would use e.g. Node 23, causing a `NODE_MODULE_VERSION` mismatch with the bundled `better-sqlite3` native module. The fallback now skips incompatible versions and auto-installs Node 20 via nvm instead

## v1.0.3

### Improvements
- **Unified `addKnowledge` tool**: merged `addKnowledgeBatch` into `addKnowledge` — now accepts a single entry object or an array of entries. One tool, no ambiguity. `addKnowledgeBatch` is removed.
- **Updated date on cards**: knowledge and plan cards now show "updated" date when it differs from the created date
- **Scrollable plan tasks**: plan detail task list and active plans grid task list are now scrollable, supporting plans with many tasks
- **README cleanup**: removed hardcoded version below logo since npm and release badges already show the version

## v1.0.2

### Fixes
- **Crash on launch (SIGABRT)**: app crashed on machines without Node.js v20 due to setup errors propagating through the macOS FFI boundary (`panic_cannot_unwind` in `did_finish_launching`). Setup errors are now caught and displayed in the webview instead of panicking
- **Auto-install Node.js v20**: when Node.js v20 is not found, the app now automatically installs nvm and Node.js v20 before spawning the sidecar, removing the need for users to pre-install Node
- **Window destroy handler**: use `try_state()` instead of `state()` to avoid panic if sidecar was never managed (e.g., setup failed)

## v1.0.1

### Fixes
- **Plan stats donut charts**: fix visual gap in single-segment donuts (`paddingAngle` now conditional), add center label showing total count

## v1.0.0

### Milestone
First stable release. All features validated across Claude Code, Copilot, and OpenCode via automated test battery (5/5 scores).

### Features
- **Single-source config compiler**: new `_base-instructions.md` as the single source of truth for agent instructions, compiled to 3 platform-specific files (`claude-code-instructions.md`, `copilot-instructions.md`, `opencode-instructions.md`) via `compile-instructions.mjs` using `<!-- IF:platform -->...<!-- ENDIF -->` conditionals. Generated files are now gitignored
- **OpenCode enforcement**: 3 new SKILL.md templates (`cognistore-query`, `cognistore-plan`, `cognistore-capture`) deployed to `~/.config/opencode/skills/cognistore-*/`. New plugin at `~/.config/opencode/plugins/` with 3 event handlers (`tool.execute.after`, `session.end`, `experimental.session.compacting`)
- **Batch MCP tools**: `addKnowledgeBatch` (create multiple knowledge entries at once with optional planId for auto-linking) and `updatePlanTasks` (update multiple plan tasks at once)
- **Plan status guards**: auto-activate plan when any task moves to `in_progress`, auto-complete all tasks when plan is set to `completed`, reactivate plan if a task is updated on a `completed` plan
- **New hooks**: `SubagentStop` (fires when subagent completes, reminds to reconcile plan tasks), `PostCompact` (experimental, fires after context compaction, reminds to reload plan state), `TaskCompleted` (fires after updatePlanTask, reminds to start next task). All hooks now output standardized JSON `{"systemMessage": "..."}` format

### Improvements
- **MCP tool annotations**: `readOnlyHint: true` on read tools, `destructiveHint: true` on delete tools
- **MCP Resources**: `cognistore://context/{scope}` exports recent entries + active plans + tags
- **createPlan response**: includes planId reminder ("Your active plan ID is X. Pass planId to addKnowledge calls.")
- **updatePlan(active) response**: includes same planId reminder
- **getKnowledge response**: includes active plan detection ("You have an active plan: X")
- **addKnowledge with planId**: auto-creates output relation (non-system entries only)
- **listPlanTasks response**: includes planId reminder
- **Instruction compilation in build pipeline**: `bundle-sidecar.mjs` runs compiler before copying templates to sidecar bundle
- **All 3 platforms**: now have CHECKPOINT language, similarity scores, batch tools, Rules section

### Fixes
- **Confidence score step**: changed from 0.1 to 0.01 in AddKnowledgeModal and KnowledgeModal for finer granularity
- **Destructive actions**: all use ConfirmModal (portal-based, Escape key, backdrop blur, loading state)

## v0.9.16

### Features
- **System knowledge type** (`type='system'`): mandatory entries seeded during setup/upgrade, injected into agent context via UserPromptSubmit hook. Contains the CogniStore workflow protocol (query-first, plan lifecycle, capture-after)
- **System knowledge guards**: system entries cannot be deleted (single, bulk, or MCP), type cannot be changed via update, stripped from imports, excluded from dashboard, stats, search, and export
- **Archive button**: completed plans can now be archived from the dashboard via a new "Archive" button with confirmation modal
- **Active plans grid**: active plans section uses responsive CSS grid layout with blue left accent border and scope badge
- **Hook-based protocol injection**: UserPromptSubmit hooks read system knowledge from DB and inject as `[COGNISTORE-PROTOCOL]` system message, with hardcoded fallback if sqlite3 unavailable

### Fixes
- **Plan lifecycle enforcement**: SKILL.md templates now explicitly state `archived` status is dashboard-only — agents must never set it
- **Import sanitization**: CSV and JSON imports with `type='system'` are automatically downgraded to `type='pattern'`

## v0.9.15

### Features
- **Reusable ConfirmModal component**: new portal-based modal (`ConfirmModal.tsx`) with backdrop blur, Escape key, loading state, and i18n support — used as the standard for all destructive confirmations
- **Knowledge delete via modal**: replaced inline confirm/cancel buttons in KnowledgeCard with a proper confirmation modal
- **Bulk delete confirmation**: bulk delete now shows a modal with entry count before executing (previously had no confirmation)
- **Uninstall via modals**: converted the inline multi-step uninstall flow to a 2-step modal confirmation sequence

### Fixes
- **KnowledgeCard simplified**: removed `confirmingDelete` and `onCancelDelete` props — delete button now delegates to parent modal
- **PlansPage refactored**: plan delete now uses the shared ConfirmModal instead of an inline implementation

## v0.9.14

### Features
- **Input-based plan detection**: CHECKPOINT 3 now has dual triggers — INPUT (user message contains 3+ action steps) and OUTPUT (agent produced 2+ ordered steps). Previously only OUTPUT was detected, missing multi-step user requests
- **MCP tool annotations**: Read-only tools marked with `readOnlyHint: true` (getKnowledge, listTags, healthCheck, listPlanTasks). Future-proofing for when clients respect annotations in plan mode
- **MCP Resource `cognistore://context/{scope}`**: Exposes scope-aware KB context as auto-loaded resource with recent entries, active plans, and tags. Prepares for future resource support in plan mode
- **Permission config injection**: Read-only CogniStore tools auto-allowed in Claude Code's dontAsk mode via `~/.claude/settings.json` permission rules
- **Graceful degradation notice**: Agents warn when they cannot save plans to KB (tools blocked in plan mode)

### Fixes
- **Plan mode persistence**: createPlan() is now called BEFORE ExitPlanMode (not after). Fixes race condition where agent's turn ended before persisting the plan
- **OpenCode execution tracking**: Full Execution Tracking Protocol added to AGENTS.md (updatePlanTask lifecycle that Claude/Copilot get from SKILL.md Phase 2)
- **UserPromptSubmit hook**: INPUT detection added to cognistore-query hooks to detect multi-step tasks at the earliest point
- **Subagent plan leak**: Explicit instruction added to prevent subagents from calling createPlan() — "When launching a subagent, include 'Do NOT call createPlan()' in the prompt"

### Known assumptions
- **MCP tools in plan mode**: The plan mode persistence fix relies on MCP tools (createPlan, getKnowledge) being callable during Claude Code's plan mode. This was empirically confirmed (2026-03-20) but is not guaranteed by the spec — Anthropic could restrict MCP calls in plan mode in a future release. The `post-plan-check.sh` hook serves as a fallback if this assumption breaks.

## v0.9.13

### Fixes
- **Output-based plan detection**: CHECKPOINT 3 in all instruction templates (Claude Code, Copilot, OpenCode) now triggers based on OUTPUT — "if you produced 2+ ordered implementation steps, call createPlan()" — instead of intent ("any time you plan work"). This fixes plan mode ignoring createPlan() because the agent didn't identify itself as "planning work"
- **Consistent language across all templates**: all 3 instruction templates + both user-prompt-check.sh hooks use the same output-based detection rule

## v0.9.12

### Features
- **OpenCode AGENTS.md instructions**: new instruction template injected into `~/.config/opencode/AGENTS.md` during setup — OpenCode now gets the same knowledge-first protocol as Claude Code and Copilot (query → plan → track → capture)
- **OpenCode setup/upgrade/uninstall symmetry**: AGENTS.md is injected on setup, re-injected on upgrade/redeploy, and cleaned up on uninstall

### Fixes
- **Skill/hook rewrite — full lifecycle coverage**: skills and hooks now cover the entire plan lifecycle (creation + execution tracking), not just plan mode events. Previously hooks only fired on EnterPlanMode/ExitPlanMode, missing execution-phase tracking entirely
- **Claude Code plan mode compatibility**: `pre-plan-file-check.sh` now detects `.claude/plans/` directory paths (plan mode generates random slugs like `sorted-jumping-whistle.md` that the previous filename-only check missed)
- **Claude Code SKILL.md conflict**: changed approach from "NEVER write local files" to "write local AND ALSO call createPlan()" — works WITH plan mode instead of against it, resolving instruction priority conflict where system-level plan mode instructions overrode skill-level instructions
- **Claude Code `post-plan-check.sh`**: shortened verbose 8-line message to 1 direct instruction — reduces likelihood of model ignoring the hook after "finishing" planning
- **Copilot execution tracking**: restructured SKILL.md with Two-Phase Workflow (Planning + Execution) at the top, added execution tracking callout and task tracking reference table
- **Copilot hook fatigue**: shortened hook messages; `post-plan-check` now includes execution tracking reminder instead of only planning reminder
- **`user-prompt-check.sh` (both agents)**: updated to include execution tracking reminders on every user message, not just plan creation
- **Instruction templates**: claude-code-instructions.md and copilot-instructions.md updated with consistent plan tracking language
- **Renamed "AI Knowledge" to "CogniStore"**: all SKILL.md titles now use "CogniStore Plan" instead of "AI Knowledge Plan"

## v0.9.11

## v0.9.5

### Features
- **Export/Import**: export knowledge entries (JSON/CSV) and plans (JSON) for backup or migration; import with duplicate detection (hash-based) and automatic embedding regeneration
- **Scope Autocomplete**: replaced free-text scope input with dropdown autocomplete showing existing scopes across knowledge and plans; custom values still allowed
- **Bulk Delete**: checkbox selection mode on knowledge entries with bulk action bar (select all, deselect all, delete selected)
- **Plan Templates**: 4 predefined plan structures (Bug Fix, Feature, Refactoring, Investigation) with pre-filled title patterns, markdown content, default tags, and task lists
- **Inline Task Editing**: click-to-edit task descriptions, priority dropdown, editable notes, and status cycling (click status icon) directly in plan detail view

### Improvements
- **Data Management section in Settings**: centralized export/import UI with buttons for JSON/CSV knowledge export, plans JSON export, and file picker for imports with progress indicator
- **Export buttons on pages**: quick-access export buttons on Knowledge and Plans pages
- **New API endpoints**: `GET /api/scopes`, `DELETE /api/knowledge/bulk`, `GET /api/export/knowledge`, `GET /api/export/plans`, `POST /api/import/knowledge`, `POST /api/import/plans`

### Fixes
- **Duplicate plan prevention**: subagents (Agent tool) are now explicitly blocked from calling `createPlan()` — only the main conversation agent creates plans, preventing duplicate entries in the knowledge base

## v0.9.4

### Features
- **Create Plan from Dashboard**: users can now create draft plans directly from the Plans page with title, description, tags, scope, and tasks — then ask an agent to refine and execute the plan
- **POST /api/plans endpoint**: new server endpoint for creating plans from the dashboard UI

### Improvements
- **Markdown rendering**: plan detail view and card previews (both Plans and Knowledge) now render content as formatted markdown (headings, lists, code blocks, tables, blockquotes)
- **Unified UI pattern**: both Knowledge and Plans pages now use floating action button (FAB) + full-page form view instead of modal overlay
- **Unified 5s polling**: all pages now auto-refresh every 5 seconds; removed manual refresh interval selector from Stats page
- **Activity chart**: replaced single-line area chart with 3-line chart (Total, Reads, Writes) with color legend

### Fixes
- **Copilot instructions template**: rewrote `copilot-instructions.md` template to explicitly reference all 3 mandatory skills (`cognistore-query`, `cognistore-capture`, `cognistore-plan`) by name — fixes issue where Copilot treated skills as optional and wrote plans to local files instead of using `createPlan()`
- **Copilot [PLAN] mode**: updated `cognistore-plan` skill to explicitly state it applies in `[PLAN]` mode — plan mode changes HOW you plan, NOT WHERE you store it (always `createPlan()`)

## v0.9.3

### Improvements
- **Plan enforcement**: createPlan() now mandatory for ALL tasks (removed "3+ steps" threshold)
- **Override clause**: plan skill explicitly overrides all other planning rules (EnterPlanMode, TodoWrite, local files)
- **Knowledge linking**: mandatory relatedKnowledgeIds on create + addPlanRelation during execution
- **Plans list auto-refresh**: 10s polling on plans list view (not just detail view)
- **CI version check**: new `version-check` job blocks PRs to main that forget version bumps

## v0.9.2

### Fixes
- **PlansPage**: removed plan status change buttons from dashboard — plan status can only be changed by agents via MCP

### Improvements
- **Copilot skills**: converted from flat `.md` files to directory format (`SKILL.md` + hooks) matching Claude Code structure
- **Copilot hooks**: added `preToolUse`, `sessionEnd`, and `postToolUse` hooks (parity with Claude Code)
- **Instruction templates**: stronger enforcement language with CHECKPOINT-based flow for both Claude Code and Copilot
- **Skill descriptions**: rewritten with MANDATORY/BLOCKING REQUIREMENT language for better auto-triggering
- **UserPromptSubmit hook**: new earliest-possible hook fires when user sends a message, BEFORE any tool use — reminds to query knowledge base and use createPlan() for multi-step tasks
- **Plan enforcement**: added CHECKPOINT 3 to instruction templates — 3+ steps = mandatory createPlan()
- **Plan file guard hook**: new PreToolUse hook on Write/Edit detects plan-like filenames (plan.md, TODO.md, etc.) and warns to use createPlan() instead
- **Plan skill rewrite**: explicit FORBIDDEN section listing banned patterns (local files, task-list-only, chat-only plans)
- **PostToolUse hook strengthened**: ExitPlanMode hook now explicitly forbids local file plans and task-list substitutes
- **Re-deploy button**: new "Re-deploy configurations" in Settings → Maintenance re-deploys skills, hooks, instructions, and MCP configs without losing data
- **Plan detail auto-refresh**: 5s polling on plan detail view + new `GET /api/plans/:id` endpoint
- **Upgrade cleanup**: old flat Copilot skill files (`.md`) are automatically removed during upgrade

## v0.9.1

### Upgrade System (New)
- App detects version changes on startup and shows upgrade screen (`vOLD → vNEW`)
- Re-deploys: database migrations, agent instructions, MCP configs, skills/hooks
- Visual progress with step-by-step status indicators

### Bug Fixes
- **Embedded migrations**: MCP server now works via npx (SQL embedded in code, not external files)
- **UpdateChecker**: distinguish manual vs automatic checks — errors only shown when user clicks "Check for updates"
- **UpdateChecker**: new states `upToDate`, `error`, `unavailable` with proper SettingsPage feedback
- **Plan creation**: rollback plan if task creation fails (no more orphaned plans)
- **HTTP status codes**: 404 returned for missing resources (was 200 with error body)
- **Upgrade race condition**: concurrent upgrade requests blocked with 409 Conflict
- **PlansPage**: shows error message instead of infinite loading on API failure
- **Version tracking**: `.version` file saved on setup completion (not via fragile hook)

### Other
- **CI:** no longer triggers on push to `main` (only PRs + feature branches)
- **PATCH-NOTES.md** added and linked from README
- **CLAUDE.md**: development rules (upgrade scripts, patch notes, testing) for all contributors

## v0.9.0

### Plans (New Feature)
- Plans are now a **separate entity** with their own `plans` table and embedding
- Plan tasks (`plan_tasks`) with status (pending/in_progress/completed), priority (low/medium/high), notes, and position ordering
- Plan relations (`plan_relations`) link plans to knowledge entries as input (consulted) or output (produced)
- 6 new MCP tools: `createPlan`, `updatePlan`, `addPlanRelation`, `addPlanTask`, `updatePlanTask`, `listPlanTasks`
- New `/plans` dashboard page with active plans section, task icons (spinner/check), progress bars, and priority indicators
- Plan analytics on StatsPage: metric cards, status distribution chart, task completion chart, activity chart

### Migration System
- Versioned SQL migrations (`schema_version` table + `.sql` files per version)
- Bootstrap detection for existing databases (automatically marks v0.8.0 as applied)
- Seeds directory for initial data on fresh installs

### Upgrade System (New)
- App detects version changes on startup and shows upgrade screen
- Re-deploys: database migrations, agent instructions, MCP configs, skills/hooks
- Visual progress with `vOLD → vNEW` header and step-by-step status

### Knowledge Improvements
- `title` field added to all knowledge entries (mandatory, shown on cards)
- `addKnowledge` MCP tool now requires `title` parameter
- `PLAN` removed from KnowledgeType (plans are separate)

### Dashboard
- Cleanup orphan embeddings moved from Stats to Settings > Maintenance
- New `cognistore-plan` skill with PostToolUse hook on ExitPlanMode
- Plan completion protocol: agents must verify all tasks completed before closing plan

### Auto-Update
- Removed redundant `generate-updater` CI job (tauri-action handles `latest.json`)

### Testing
- 69 automated tests in `packages/tests` (E2E, load, performance)
- CI workflow runs on PRs and feature branch pushes
- Pre-commit security hook scans for leaked secrets

### Documentation
- README and all 9 documentation files updated for v0.9.0

---

## v0.8.1

- Operations stats: read/write counters (last hour + last day)
- Settings page (renamed from Monitoring): infrastructure, updates, language, maintenance
- Heatmap color scheme (GitHub-style green)
- Browser language auto-detection
- UI improvements: chart tooltips, cleanup button as trash icon

## v0.8.0

- Mandatory skills with hooks (PreToolUse, Stop)
- Monitoring page with health checks
- UI improvements

## v0.7.x

- Bug fixes, CI improvements, search fixes, tag input redesign
