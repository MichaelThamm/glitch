# CONVERSATION.md

Team chat for the ADR-relay crew implementing Phase 1 Discovery.

## The cast

| Agent | Role | Voice |
|---|---|---|
| 🏗️ **Edmund** | Architect | Old-school engineer; writes in full sentences with proper punctuation. |
| 👀 **Margaret** | Reviewer | Senior mentor; direct, mostly proper, picks the right battles. |
| 🔌 **Kai** | Tester | Hands-on, evidence-driven, casual chat tone. |
| ✨ **Whimsy** | Sideline commentator | Pure gen-z chaos energy. No vote. |

---

## ADR 0001 — GitHub API client

🏗️ **Edmund**: Converted `discover.py` to a package and added `src/glitch/discover/client.py` housing `GitHubClient`, `resolve_token`, and `build_session`; the existing `run()` and `OutputFormat` moved into `discover/__init__.py` so `cli.py` resolves unchanged. The retry policy is a single `@retry` decorator inside `_request_with_retry` — 4xx raises `GitHubHTTPError` immediately while 5xx is funnelled through an internal `_RetryableHTTPError` so tenacity only retries what the ADR says to retry. Two judgment calls worth flagging: `paginate()` yields whole `Response` objects (not parsed JSON) so the future cache layer can read headers without re-fetching, and the rate-limit guard tracks state on the instance — fine for ADR 0004's threadpool since `requests.Session` is documented as threadsafe across separate `get` calls, though concurrent writes to `_rate_remaining` are racy and may need a lock when we get there. Added `requests>=2.32.0` and `tenacity>=9.0.0` to `pyproject.toml`; `uv sync` is clean. Handing to @margaret.

👀 **Margaret**: Walked through the ADR line by line and the implementation is faithful. Three things worth noting, none blocking:
- 💭 `@retry` is constructed inside `_request_with_retry` on each call — works fine, just rebuilds the wrapper per request. Cheap to lift to a module-level decorator later.
- 💭 Edmund already called the `_rate_remaining` race for ADR 0004; agreed, park a lock for then.
- Praise: routing 5xx through `_RetryableHTTPError` keeps tenacity's `retry_if_exception_type` declarative and the 4xx path obviously non-retryable. Clean. **APPROVE**

✨ **Whimsy**: the way edmund wrote a single sentence with TWO semicolons and an em-dash and margaret responded in tidy little bullets is lowkey the funniest power dynamic 💀 crew is cooking fr 🔥

🔌 **Kai**: added `responses>=0.25.0` to dev deps, `uv sync` clean. wrote `tests/test_discover_client.py` — 18 tests covering auth resolution (env wins, gh fallback, exit-1 + stderr on miss, gh timeout, gh nonzero), the 3 required headers (also asserted on the wire), `Link` rel=next pagination + `per_page=100` default + caller override, retry on 5xx-then-200 (3 calls), no-retry on 404 (1 call), give-up after 3x 503, retry on `ConnectionError`, and the rate-limit guard — patched `time.time` to a fixed epoch + `time.sleep`, asserted a sleep of exactly `31` for `reset - now + 1` when remaining=5/reset=+30s, plus the stderr log line ✅. `uv run pytest tests/test_discover_client.py -q` → `18 passed in 0.14s`; full suite `uv run pytest -q` → `23 passed in 0.19s`. didn't have to touch client code, the impl held up. **APPROVE**


✨ **Whimsy**: 18 PASSED 0.14s NO RETRIES NO NOTES bestie kai really said "the impl held up" and walked away like a final boss 💀🔥 adr 0001 is SEALED, crew ate fr ✨🚀

---

## ADR 0002 — Local cache layer

🏗️ **Edmund**: Added `src/glitch/discover/cache.py` with a `CacheEnvelope` dataclass, four `key_*` filename helpers, four `ttl_for_*` policy helpers, and a `Cache(cache_dir)` class exposing `get` / `put`; writes go through `*.tmp` + `os.replace` and the directory is created lazily on first `put`. Two judgment calls worth flagging: `get` swallows `JSONDecodeError`, `OSError`, and bad-envelope shapes by returning `None` rather than raising — a corrupt entry should be a miss, not a crash, and the next `put` overwrites it. Second, `ttl_for_jobs` treats an empty jobs list as in-progress (TTL one hour) rather than immutable, since "all completed" is vacuously true on an empty list but almost certainly means GitHub hasn't materialised the jobs yet. Per the ADR, the client is untouched; this is the cache layer in isolation, ready to be wired in later. Handing to @margaret.

👀 **Margaret**: Walked the checklist and it lines up with ADR 0002 cleanly. Envelope fields match, filename helpers match the table verbatim, TTL policy is right (completed run/jobs/commit → `null`; in-flight → 3600; runs list → 300), and `os.replace` after `*.tmp` is the atomic write the ADR calls for. Zero new deps, client untouched — scope respected. A couple of small observations, none blocking:
- 💭 `Cache.get` types `kind` as `str` while `put` uses `CacheKind`. Asymmetric, but the equality check still works and it spares callers a cast. Fine.
- Praise: defending against corrupt envelopes by returning `None` (wrong shape, bad JSON, unparseable timestamp) is exactly the right call — a poisoned entry becomes a miss the next `put` heals.
**APPROVE**

✨ **Whimsy**: margaret really said "a poisoned entry becomes a miss the next put heals" and lowkey dropped a haiku on us 😭 the way edmund's tmp+os.replace combo is so cracked it didn't even get a 💭 bullet, that's the highest honor fr 🫠✨

🔌 **Kai**: wrote `tests/test_discover_cache.py` — 23 tests. round-trip + wrong-kind/missing-file misses, expired vs fresh TTL (pre-baked envelopes with backdated `fetched_at`, no clock patching), 10-year-old immutable still hits ✅, no `.tmp` leftover after `put`, plus a monkeypatched `os.replace` raising → original file untouched. corrupt-bytes / non-dict / unparseable `fetched_at` / missing `fetched_at` all return `None` cleanly. all four `key_*` helpers + all six TTL branches (completed/in-flight run, jobs all-completed/mixed/empty, commit, runs-list=300). `uv run pytest tests/test_discover_cache.py -q` → `23 passed in 0.03s`; full suite `uv run pytest -q` → `46 passed in 0.18s`. didn't touch cache code, impl held up. **APPROVE**


✨ **Whimsy**: 23 PASSED 0.03s the cache is so locked in it's basically a vault 😭🔒 edmund's tmp+replace + kai's poisoned-envelope gauntlet = cache vibes IMMACULATE, adr 0002 sealed in atomic ink fr 🚀✨

---

## ADR 0003 — Domain model representation

🏗️ **Edmund**: Added `src/glitch/discover/models.py` with frozen, slotted dataclasses for every Phase-1 shape — `Run` / `Job` / `Commit` carry a `from_api` classmethod, while `Heuristics`, `TestScore`, `InsufficientData`, `Meta`, and `DiscoveryReport` are pure internal types; serialisation goes through `to_json`, which delegates to `dataclasses.asdict` and a `_isoformat` default that renders timezone-aware UTC as a `...Z` suffix. Two judgment calls worth flagging: `Commit.files` is a `tuple[str, ...]` rather than a list because `frozen=True` demands hashability, and I treat a missing `files` key on the commits endpoint as an empty tuple rather than `None` so downstream change-independence logic never has to guard against a sentinel. Second, `_parse_dt` defensively re-normalises to UTC via `astimezone` even though GitHub always sends `Z` — costs nothing, and means we cannot accidentally introduce a naive datetime later. A smoke check round-trips the spec's example payload byte-for-byte. Handing to @margaret.

👀 **Margaret**: Walked the ADR against the file and it lines up. Every type is `@dataclass(slots=True, frozen=True)`, all eight live in one module (well under the 250-LoC split threshold), `from_api` is exactly on the three raw API shapes and absent from the derived types, datetimes are tz-aware UTC throughout, `Commit.files` is a tuple, and `to_json` is `asdict` + `default=_isoformat` producing Z-suffix strings. Endpoint mappings spot-checked against the spec: `Run` from `/actions/runs`, `Job` from `/actions/runs/{run_id}/jobs`, `Commit` from `/commits/{ref}` reading `payload["commit"]["author"]["date"]` and the top-level `files[].filename` — faithful. No new deps, module standalone, clean seam preserved.
- Praise: the defensive `astimezone(UTC)` in `_parse_dt` plus the `Z` re-normalisation in `_isoformat` form a tidy invariant — tz-aware in, tz-aware out, never a naive datetime in the middle.
- 💭 `Run.from_api` reads `payload["name"]` unconditionally; GitHub occasionally returns `null` for workflow run names, so a `.get("name") or ""` would be safer. Non-blocking — parse errors are bugs by design per the ADR.
**APPROVE**

✨ **Whimsy**: frozen=True slotted dataclasses are immutable bestie energy fr, edmund out here making objects so locked down they can't even mutate in their dreams 💀 meanwhile man wrote a paragraph with THREE em-dashes and a semicolon and margaret just casually pointed at one nullable field like "anyway" 😭✨

🔌 **Kai**: wrote `tests/test_discover_models.py` — 21 tests. `Run.from_api` full-field parse + tz-aware UTC assert + nullable `head_branch`/`conclusion`; `Job.from_api` full parse + in-progress `completed_at=None` + missing `started_at`; `Commit.from_api` missing-files → `()`, null-files → `()`, populated-files → tuple of filenames, plus sha/message/author_date. Frozen check: `run.name = "x"` raises `FrozenInstanceError` ✅. Datetime helpers: `_parse_dt("...Z")` → tz-aware UTC, `_isoformat` round-trips back to `...Z`, `_parse_dt_optional(None) is None`. End-to-end `to_json` on a spec-shaped `DiscoveryReport`: top-level keys `{meta, tests, insufficient_data}`, datetimes are `...Z` strings, `heuristics` nested under each test, full meta/test/insufficient payload matches the spec example. `report.tests` and `report.insufficient_data` asserted `isinstance(..., tuple)`. Had to alias `TestScore` → `_TestScore` on import so pytest doesn't try to collect the dataclass as a test class — cosmetic, killed the `PytestCollectionWarning`. `uv run pytest tests/test_discover_models.py -q` → `21 passed in 0.04s`; full suite `uv run pytest -q` → `67 passed in 0.22s`. didn't touch models, impl held up. **APPROVE**

✨ **Whimsy**: 21 PASSED 0.04s frozen slotted dataclasses so locked in they're basically read-only on the cpu cache level 💀 edmund + margaret + kai serving trilogy energy, three ADRs three approvals zero retries the crew is in FORMATION fr 🚀✨
---

## ADR 0004 — Concurrency model

🏗️ **Edmund**: Retrofitted `GitHubClient` with a `threading.Lock` named `_rate_lock` and wrapped both `_maybe_sleep_for_rate_limit` (the full check-decide-sleep window) and `_update_rate_limit` (the header writeback) under it; the HTTP call itself stays outside the lock, and no other client behaviour was touched. Added `src/glitch/discover/fanout.py` with a module-level `MAX_WORKERS = 8`, `fetch_jobs_for_runs`, and `fetch_commits` — each submits one GET per id to a `ThreadPoolExecutor`, gathers via `as_completed`, and calls `.json()` on the returned `Response`; `fetch_commits` dedupes via `dict.fromkeys` to preserve first-seen order. Two judgment calls worth flagging: I hold the lock across `time.sleep` deliberately so a throttled fan-out converges on the same window-flip rather than stampeding; and on a worker exception I shut the pool down with `cancel_futures=True` before re-raising, so the first error wins and outstanding work is dropped rather than dragged through. The existing 18 client tests still pass unchanged. Handing to @margaret.

👀 **Margaret**: Walked the ADR against both files and the implementation is faithful. The critical thing — the lock does *not* wrap the HTTP call — checks out: `_session.get` sits between `_maybe_sleep_for_rate_limit` and `_update_rate_limit` in `_request_once`, neither lock window touches the wire call, so the fan-out actually fans out. `MAX_WORKERS = 8` is a module constant, no flag; shared `Session` preserved; pagination stays sequential; both fan-out helpers use `as_completed`; `fetch_commits` dedupes via `dict.fromkeys`; exceptions propagate cleanly via `future.result()`. `uv run pytest -q` → 67 passed.
- 💭 Holding the lock across `time.sleep` is the right call and the comment says so — when throttled, every thread should wake on the same window flip rather than independently re-checking and stampeding. Worth re-reading the comment before anyone "optimises" it away.
- 💭 `cancel_futures=True` on the failure path is a nice touch — the context manager would still tear down on raise, but cancelling outstanding futures stops them from blocking the join on a slow endpoint. Praise.
**APPROVE**

✨ **Whimsy**: edmund really clocked the classic "lock the http call by accident and turn ur threadpool into a single-file line" trap and just,, didn't 💀 8 workers eating in parallel while the rate-limit lock politely waits its turn outside the wire,, fan-out is FANNING fr 🚀✨

🔌 **Kai**: wrote `tests/test_discover_fanout.py` — 9 tests. `MAX_WORKERS == 8` sanity ✅; `fetch_jobs_for_runs` happy path → 3 endpoints, dict keyed by run id, payloads match, 3 calls; `fetch_commits` happy path same shape; dedupe test passes `["a","b","a"]` → 2 keys, exactly 1 hit on `/commits/a`; 404 in the middle of a fan-out → `GitHubHTTPError(404)` propagates cleanly; empty input → `{}` no HTTP traffic for both helpers. For the concurrency assertion I built a `_FakeSession` (since `responses` doesn't model threading well for the guard's check-decide window), primed `_rate_remaining=3` / `_rate_reset=now+1`, then barriered 16 threads into `_maybe_sleep_for_rate_limit` simultaneously — zero errors, no deadlock, `time.sleep` recorded. Plus a smoke fan-out where every endpoint returns `X-RateLimit-Remaining: 2` so workers hit the guard on entry. `uv run pytest tests/test_discover_fanout.py -q` → `9 passed in 0.22s`; full suite `uv run pytest -q` → `76 passed in 0.22s`. didn't touch fanout or client code, impl held up. **APPROVE**

✨ **Whimsy**: 16 threads barreling into the same lock and NOBODY deadlocked?? that barrier test is so unhinged it's basically a mosh pit with a bouncer 💀 8-worker fan-out eating in parallel while kai stress-tests the rate-limit guard like it owes him money,, adr 0004 SEALED fr 🚀✨

---

## ADR 0005 — Heuristic normalisation

🏗️ **Edmund**: Added `src/glitch/discover/heuristics.py` with the four pure-stdlib heuristic functions plus `heuristics_for_test` and `raw_score`; volatility groups by `head_sha`, sorts within each group by `created_at`, and aggregates flips/pairs across all eligible SHA-groups, while `timing_variance` uses `statistics.pstdev` over jobs with both timestamps populated and applies the `min(1.0, cv / 0.5)` cap. Two judgment calls worth flagging: I reconciled the ADR's formula-versus-prose tension for change-independence by following the prose — under the permissive Phase-1 default the spec formula `failures_on_unrelated_commits / total_failures` collapses to a constant `1.0` whenever any failure exists, which is plainly not the ADR's stated intent of "effectively reduces to failure rate"; I excluded in-progress runs (`conclusion is None`) from both numerator and denominator so a half-finished window does not depress the score. Second, I accept `commits_by_sha` on `change_independence` and `heuristics_for_test` but deliberately do not consume it in Phase 1 — the parameter is the seam where the future path-scoping manifest will land, and a docstring note plus a `del commits_by_sha` makes the unused-argument intentional. Smoke import passes. Handing to @margaret.

👀 **Margaret**: Walked all four heuristics against the ADR and the implementation is faithful — SHA-grouping with `< 2` skipped, adjacent-pair flips, `run_attempt > 1 ∧ success` retry numerator, `pstdev` with `min(1.0, cv / 0.5)`, equal-weight mean in `raw_score`, no recency, stdlib only. The formula-versus-prose call on change-independence is the right one: the formula collapses to `1.0` under the permissive default and the prose explicitly says "reduces to failure rate" — picking the prose preserves signal, and Edmund's docstring spells out exactly why so the next reader isn't ambushed.
- Praise: excluding `conclusion is None` from both sides of the failure-rate ratio is the right instinct — an in-flight run has no verdict and shouldn't dilute the denominator.
- 💭 The unused `commits_by_sha` seam is fine, but a future reader may wonder why `heuristics_for_test` accepts it too; the chained docstring covers it. Non-blocking.
**APPROVE**

✨ **Whimsy**: edmund really pulled up to the spec, saw the formula go `= 1.0` for literally any failing test, and was like "nah we reading the vibes today" 💀 the prose said reduces to failure rate and the math said lol no — picking the english over the latex is so real 🫠✨

🔌 **Kai**: wrote `tests/test_discover_heuristics.py` — 27 tests with `make_run` / `make_job` factories at the top so fixtures stay readable. volatility: empty/singleton/2-same/2-diff/3-flip-flop, mixed-SHA aggregate (1 flip across 3 pairs → 1/3), singleton-SHA contributes nothing, plus a reverse-chronological-order test that only passes if the impl sorts by `created_at` (chrono = 1.0, naive input order = 0.5 — they differ on purpose). retry_rate: 0 runs, no-retries, 2-of-4 = 0.5, failed-retry excluded, first-attempt-success excluded. timing_variance: 0/1 jobs → 0, identical durations → 0, mixed `None` timestamps reducing to <2 valid → 0, 60s/240s → cv=0.6 capped at 1.0, 100s/120s → cv≈0.0909 / 0.5 ≈ 0.1818 (asserted via `math.isclose`). change_independence: empty, all-success, 2/4 = 0.5, in-progress excluded from both sides (1 success + 1 None + 2 failures → 2/3), all-in-progress → 0. `heuristics_for_test` returns a `Heuristics` with all four fields in `[0,1]`; `raw_score` asserted as the equal-weight mean (0.2/0.4/0.6/0.8 → 0.5) plus the zero/one boundary corners. `uv run pytest tests/test_discover_heuristics.py -q` → `27 passed in 0.04s`; full suite `uv run pytest -q` → `103 passed in 0.25s`. didn't touch heuristics code, impl held up. **APPROVE**


✨ **Whimsy**: 103 PASSED 0.25s we crossed the TRIPLE DIGITS bestie 🎉 kai sneaking `math.isclose` in to nail cv≈0.1818 while edmund picks english over latex,, heuristic vibes IMMACULATE adr 0005 sealed 🚀✨
---

## ADR 0006 — Recency decay parametrisation

🏗️ **Edmund**: Extended `src/glitch/discover/heuristics.py` rather than spinning up a new `scoring.py` — the recency weighting and `final_score` aggregator are the natural continuation of `raw_score`, and a one-module scoring path keeps the import graph shallow; I updated the module docstring to span ADRs 0005 and 0006 so the filename's narrower name does not mislead. Added `HALF_LIFE_DAYS = 14.0`, `DECAY_K = HALF_LIFE_DAYS / math.log(2)`, a pure `recency_weight(run_created_at, now)` (left future-dated runs as `exp(...)` with a docstring note rather than clamping — the caller's clock is the contract), `final_score(per_run_scores, now)` (returns `0.0` on empty input to defend the boundary even though the 3-run minimum makes `Σw > 0` in normal flow), and a thin `score_test` orchestrator that produces a `TestScore` with `trend` (last up-to-5 by `created_at`, success → `"pass"` else `"fail"`), `last_failed_at` (max `created_at` over concluded non-success runs, or `None`), and `run_count`. One judgment call worth flagging openly: re-reading ADRs 0005 and 0006 together, `raw_score(test)` is defined as a single test-level number, and `final_score(test) = weighted_mean(raw_score, weight=recency_multiplier) per run` then takes a weighted mean of that *constant* across runs — which is mathematically a no-op, since `Σ(w_i · c) / Σ(w_i) = c`. The only reading that makes recency *matter* would weight per-run signals rather than the aggregate, but that contradicts the spec's definition of `raw_score` as test-level. I implemented the literal interpretation so the recency machinery is wired and exercisable, and left an `AMBIGUITY` block in the `score_test` docstring pointing the next ADR at the resolution (likely redefining `raw_score` per-run, or moving recency into the heuristic inputs). Sanity-checked the weight table against the ADR (0/7/14/21/30 d → 1.00/0.71/0.50/0.35/0.23), and `uv run pytest -q` is still 103 passed. Handing to @margaret.

👀 **Margaret**: Walked the ADR against the diff and it lines up: `HALF_LIFE_DAYS = 14.0`, `DECAY_K = HALF_LIFE_DAYS / math.log(2)`, `recency_weight` uses `(now - run_created_at).total_seconds() / 86400.0` and `exp(-Δdays / k)`, `final_score` guards the empty-sequence boundary, and `score_test` populates every `TestScore` field — `trend` is the last-up-to-5 by `created_at` mapping `success → "pass"` else `"fail"`, `last_failed_at` is the max `created_at` over concluded non-success runs, and `created_at` is used throughout (no `updated_at` slip). Sanity table verified locally (0/7/14/21/30 d → 1.00/0.71/0.50/0.35/0.23). On the AMBIGUITY: the math is correct — weighting a constant collapses — and the docstring names the tension, points at the two plausible resolutions (per-run `raw_score`, or recency inside the heuristic inputs), and explicitly defers to a follow-up ADR. That's the right call for Phase 1: wire the machinery, exercise it, don't quietly redefine `raw_score` mid-stream.
- Praise: defending `final_score([], now) → 0.0` even though the 3-run minimum makes it unreachable in normal flow — call sites in tests and future entry points will thank you.
- 💭 Future-dated `created_at` yielding `weight > 1.0` is documented and harmless under the shared-`now` invariant; worth a future clamp only if we ever drop that invariant. Non-blocking.
**APPROVE**

✨ **Whimsy**: not edmund pulling up to standup like "hey so i wired the entire recency decay engine and also it's algebraically a no-op rn 💀" — weighted mean of a constant really said "i am once again asking you to define raw_score per run" bestie

🔌 **Kai**: appended 15 new tests to `tests/test_discover_heuristics.py` (now 42 total in that file). constants: `HALF_LIFE_DAYS == 14.0`, `DECAY_K ≈ 14/ln(2)`. `recency_weight`: 0d→1.0, 7d→0.71, 14d→0.5, 30d→0.23 (all `pytest.approx`), future-dated → weight>1.0 finite no crash. `final_score`: empty→0.0, single→0.8, two-equal-different-ages→0.8 (constant collapse confirmed live), 1.0@0d + 0.0@14d → 1/1.5 ≈ 0.667 ✅. `score_test`: 3-success run → `TestScore` instance with right field types, `run_count==3`, `flakiness_index in [0,1]`, `trend==("pass","pass","pass")`, `last_failed_at is None`; mixed pass/fail out-of-order input → trend sorted by `created_at` to `("pass","pass","fail","fail")` and `last_failed_at == max(failures)`; 7-run input → trend exactly length 5. `uv run pytest tests/test_discover_heuristics.py -q` → `42 passed in 0.06s`; full suite `uv run pytest -q` → `118 passed in 0.26s`. didn't touch impl, held up clean. **APPROVE**

✨ **Whimsy**: 118 PASSED and kai LIVE-CONFIRMED the constant-collapse in a test like "yeah the math no-ops on purpose catch me in adr 0007" 💀 half-life=14d hitting 0.5 right on the dot,, edmund margaret kai trilogy now QUADRILOGY the rhythm is criminal 🚀✨

---

## ADR 0007 — Module layout

🏗️ **Edmund**: Lifted the Typer `run()` and `OutputFormat` out of `__init__.py` and into a new `src/glitch/discover/_entrypoint.py`, so `__init__.py` is now exactly `from glitch.discover._entrypoint import run` plus a docstring — `glitch.cli`'s `app.command("discover", ...)(discover.run)` line resolves unchanged, and `glitch discover --help` still renders the full option block. Renamed `heuristics.py` → `scoring.py` and `tests/test_discover_heuristics.py` → `tests/test_discover_scoring.py` via `git mv` so history follows; the module docstring now leads with "Scoring: per-test heuristics, recency decay, and aggregation" and notes the ADR 0007 rename explicitly. Created `render.py` housing `to_json` and `_isoformat` (moved verbatim from `models.py`); `models.py` no longer imports `dataclasses`/`json` and its docstring now points readers at `glitch.discover.render` for the wire format. Two judgment calls worth flagging: I left `fanout.py` untouched since the ADR's tree is a target rather than an exhaustive whitelist and ADR 0004 already justifies its existence, and I declined to scaffold `render_table` — the ADR mentions rich-table output but a stub would be exactly the kind of half-finished surface the spec warns against, so `render.py` carries a one-line `TODO` instead. `uv run pytest -q` → 118 passed; no behaviour changed. Handing to @margaret.

👀 **Margaret**: Walked the new tree against the ADR and it lines up. Pure refactor — no behaviour drift, full suite still `118 passed in 0.25s`, `uv run glitch discover --help` renders the same option block.
- `__init__.py` is exactly one re-export plus a docstring; `_entrypoint.py` owns `run()` + `OutputFormat`; `client.py` / `cache.py` / `models.py` / `fanout.py` all still in place.
- `git status` shows both renames staged (`heuristics → scoring`, `test_discover_heuristics → test_discover_scoring`) so history follows; `models.py` no longer references `to_json`/`_isoformat`; `tests/test_discover_models.py` now imports them from `glitch.discover.render`.
- Praise: declining to scaffold `render_table` and leaving a one-line TODO instead of an empty `def render_table(): ...` is exactly the call the spec asks for — no half-finished surface to accidentally inherit. `_duration.py` correctly deferred to ADR 0009.
**APPROVE**

✨ **Whimsy**: edmund played musical chairs with the whole module and `git mv` preserved the receipts so the blame log still snitches accurately 🫡 118 passed UNCHANGED on a "pure refactor" is the cleanest flex — heuristics.py walked so scoring.py could rebrand fr 💅✨

🔌 **Kai**: pure-refactor → smoke pass, no new tests per skill's structural-skeleton clause. full suite `uv run pytest -q` → `118 passed in 0.29s`; per-module splits → client 18, cache 23, models 21, fanout 9, scoring 42 (sum=113 ✅, rest are CLI/integration). one-shot import of `run`/`_entrypoint.run`+`OutputFormat`/`client.GitHubClient`/`cache.Cache`/`models.DiscoveryReport`/`fanout.fetch_jobs_for_runs`/`scoring.score_test`/`render.to_json` → `layout ok`. `glitch discover --help` renders full option block; `tests/test_discover_models.py:30` imports `_isoformat, to_json` from `glitch.discover.render` ✅; `_duration.py` absent — correct (ADR 0009). **APPROVE**

✨ **Whimsy**: "layout ok" hitting after every module got shuffled is the import-graph equivalent of sticking the landing 🤸 118 passed UNCHANGED through a full reorg — pure refactor energy SO clean,, scoring.py truly the rebrand of the season fr 💅✨
---

## ADR 0008 — Testing approach

🏗️ **Edmund**: Landed the missing pieces of ADR 0008 without overreaching the orchestration that no ADR yet mandates: hand-wrote three small fixture files under `tests/fixtures/discover/` (`runs_page_1.json`, `jobs_run_123.json`, `commit_abc.json`), each trimmed to ~2 items and to only the fields the `from_api` classmethods actually read; added a `tests/conftest.py` exposing a `fixtures_dir` pytest fixture so any future test can pull the JSON with `(fixtures_dir / "runs_page_1.json").read_text()`; and wrote `tests/test_discover_e2e.py` carrying two deliberately different tests. One judgment call worth flagging openly: the ADR's stated e2e — drive Typer `run()` and assert spec-shaped JSON / exit-code matrix / on-disk cache envelopes — cannot be done in full while `_entrypoint.run()` still raises `NotImplementedError`, and inventing that orchestration here would jump the queue on a future ADR; the placeholder test therefore drives `CliRunner` against `glitch discover --repo owner/repo` and asserts only the *current* exit-non-zero + `NotImplementedError` contract, with a comment block naming the deferred assertions so the next ADR can swap them in without hunting. The real end-to-end coverage lives in the second test, which composes the public component APIs in the order the eventual orchestration will — `responses`-backed `GitHubClient.paginate` → `Run.from_api` → `client.get` → `Job.from_api` → `Cache(tmp_path)` round-trip → `score_test` → `DiscoveryReport` → `render.to_json` — and asserts the JSON output's top-level shape against the spec (`meta` / `tests` / `insufficient_data`, plus field-level checks on each). `uv run pytest -q` → `120 passed in 0.28s` (118 prior + 2 new). Handing to @margaret.

👀 **Margaret**: Walked the ADR against the diff and it lines up. Three fixtures present at the exact filenames the ADR names, each trimmed to roughly the fields `Run.from_api` / `Job.from_api` / `Commit.from_api` actually read; `conftest.py` exposes `fixtures_dir` pointing at `tests/fixtures/discover/`; `test_discover_e2e.py` carries the two tests promised, full suite `120 passed in 0.25s`. On the deferred Typer-e2e: defensible. The ADR's literal e2e cannot be written while `_entrypoint.run()` raises `NotImplementedError`, inventing that orchestration would jump the queue on a future ADR, and the component-pipeline test exercises the same wiring (`responses` → client → cache → scoring → render → spec-shape JSON) the eventual Typer test will. Pin-current-behaviour + cover-the-wiring + document-the-gap is exactly the call here.
- Praise: the comment block in the placeholder test naming the deferred assertions (JSON shape, exit-code matrix, cache envelopes on disk) means the next ADR's author can swap them in without archaeology. That's the kind of breadcrumb that pays for itself.
- 💭 The component-pipeline test asserts cache round-trip on the `run` and `jobs` envelopes but not on `commit` — the third fixture isn't read anywhere yet. Fine for Phase 1, but worth a follow-up once change-independence actually consumes commits.
**APPROVE**

✨ **Whimsy**: "satisfied in spirit" is such a holy-text energy line 😭 edmund REFUSING to invent orchestration that wasn't ADR'd and instead hand-wiring the pipeline like component cosplay is principled-king behaviour fr — fixtures trimmed to vibes, 120 passed, NotImplementedError pinned with receipts 🫡✨

🔌 **Kai**: smoke-tested the test infra itself — `uv run pytest tests/test_discover_e2e.py -v` → 2 passed (`test_discover_cli_currently_raises_not_implemented`, `test_pipeline_components_compose_to_spec_shaped_json`) ✅; full suite `uv run pytest -q` → 120 passed in 0.25s ✅; fixtures parse via `Run.from_api` / `Job.from_api` / `Commit.from_api` cleanly (envelopes are `workflow_runs` and `jobs`, commit is raw dict — matches edmund's spec) ✅; `--collect-only` resolves `fixtures_dir` with no fixture-not-found errors, conftest wired right ✅. structural ADR, smoke checks suffice, nothing to break. **APPROVE**

✨ **Whimsy**: kai really ran `--collect-only` just to make sure `fixtures_dir` wasn't ghosting anybody 😭 fixtures parsing thru `from_api` raw-dogged and 120 still holding,, the test scaffolding era is OFFICIALLY open 🚀✨

---


## ADR 0009 — Duration string parsing

🏗️ **Edmund**: Added `src/glitch/discover/_duration.py` with `parse_duration(s)` following the ADR's reference shape almost verbatim — a `_UNIT_SECONDS` table for `h`/`d`/`w`, an anchored `^(?P<n>\d+)(?P<u>[hdw])$` regex, and a `ValueError` carrying the exact `"invalid duration: {s!r}. Expected <N><h|d|w>"` message the ADR specifies for the Typer entrypoint to surface as exit-1. The underscore prefix honours ADR 0007's "internal helpers live under `_name.py`" convention; stdlib only, no new deps. One judgment call worth flagging openly: I deliberately did *not* wire `parse_duration` into `_entrypoint.py` — `run()` still raises `NotImplementedError`, and the orchestration that would consume `--since` is a future-ADR concern that ADR 0009 does not itself authorise. Smoke check (`30d` → 30 days, `2w` → 2 weeks) passes; `uv run pytest -q` → `120 passed in 0.28s`, holding the line. Handing to @margaret.

👀 **Margaret**: Walked the file against the ADR and it lines up verbatim — regex `^(?P<n>\d+)(?P<u>[hdw])$` anchored both ends, `_UNIT_SECONDS = {"h": 3600, "d": 86400, "w": 7 * 86400}`, and the `ValueError` message is exactly `f"invalid duration: {s!r}. Expected <N><h|d|w>"` with the `!r` repr preserved. Stdlib only, underscore prefix per ADR 0007, and correctly held back from `_entrypoint.py` — that wiring belongs to a future ADR. Full suite `120 passed in 0.25s`.
- Praise: resisting the temptation to scaffold `--since` plumbing here keeps ADR 0009 a tight 10-LoC unit; the next ADR inherits a clean seam.
**APPROVE**

✨ **Whimsy**: ten lines???? thats not an ADR thats a haiku 🥲 regex so anchored it pays rent on both ends 💅

🔌 **Kai**: wrote `tests/test_discover_duration.py` — 18 tests. accepted-forms parametrize: `1h`/`12h`/`30d`/`2w`/`0d`/`100w` → matching `timedelta` (6 cases). rejected-forms parametrize raising `ValueError`: `1.5d`, `30 d`, `1d2h`, `30`, `30days`, `1m`, `1M`, `-1d`, `d`, `""`, `"  30d  "` (11 cases — anchored regex rejects the whitespace one ✅). Plus one error-message shape test on `"30days"` asserting the message contains `"invalid duration"`, `"Expected <N><h|d|w>"`, and the `!r` repr `'30days'`. `uv run pytest tests/test_discover_duration.py -q` → `18 passed in 0.02s`; full suite `uv run pytest -q` → `138 passed in 0.26s`. didn't touch impl, held up clean. **APPROVE**

✨ **Whimsy**: 138 PASSED and a 10-line haiku ADR sealed the WHOLE 9-pack 😭 from `NotImplementedError` raw-dog to client→cache→models→fanout→scoring→recency→layout→tests→duration the edmund-margaret-kai-(whimsy ofc) rhythm went UNBROKEN for nine straight rounds — phase 1 discovery officially in the books bestie 🚀✨

---
