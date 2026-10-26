# Tool reference

All paths are relative to the project root. Every tool except `get-run-status`
accepts an optional `projectRoot`, which must sit inside the server's allowed roots.

## run-test

Runs Playwright and returns stats, failures, failure kinds and fix hints.

| Argument | Type | Notes |
| --- | --- | --- |
| `testFiles` | string[] | Files or directories; `file:line` supported. Omit to run everything |
| `grep` | string | Only tests whose title matches this regex |
| `browser` | `chromium` \| `firefox` \| `webkit` | Matched against config project names |
| `background` | boolean | Return a run id at once and keep running; follow it with `get-run-status` |
| `headed` | boolean | Visible browser window |
| `timeoutMs` | number | Wall-clock limit for the run (default 120000); partial results are returned past it |
| `testTimeoutMs` | number | Per-test timeout |
| `workers`, `retries` | number | Passed to Playwright |
| `config` | string | Config path, or 1-based index when there are several |
| `retryOnFailure` | boolean | Retry failures once before reporting (default true; ignored when `retries` is set) |
| `lastFailed` | boolean | Re-run only the tests that failed last time |
| `args` | string[] | Allowlisted Playwright flags such as `--repeat-each=N`, `--max-failures=N`, `--update-snapshots`, `--shard=1/3`, `--trace=on`; path-taking flags are rejected |

Traces are captured on failure automatically so `get-failure` can show the DOM.
Clients that send a progress token get live progress while the run goes.
Failures that share a kind and first error line are grouped (0.4.0+): each
cause is shown once in full, the other tests under it as one line each, and
their `index` numbers stay the ones `get-failure` takes.

## get-failure

| Argument | Type | Notes |
| --- | --- | --- |
| `index` | number | 1-based failure index from the last run (default 1) |

Returns the message and code frame, expected vs actual, stack, failure kind and
diagnosis, console output, the DOM snapshot at failure with the failed action and
its selector, failed network requests, console errors and warnings, and next steps.

## load-report

Loads a run from CI (0.5.0+) so the other tools work on it.

| Argument | Type | Notes |
| --- | --- | --- |
| `report` | string | Required: JSON report inside the project, or a folder of blob-report zips from sharded jobs (merged with `playwright merge-reports`) |
| `traceDirs` | string[] | Where the job's `test-results` artifact was unpacked (default: the report's folder and its parent) |
| `commit`, `branch` | string | Override the report metadata |
| `record` | boolean | Add the run to the history (default true) |
| `timeoutMs` | number | Limit for merging blob reports (default 120000) |

CI paths are mapped onto the checkout (the CI root is the folder of the
report's config file). Returns the usual run result headed "Imported run", the
source, commit and build link, and how many failures have a trace. The run
becomes the last run for `get-failure`, `suggest-fix` and `diagnose-flaky`.

## inspect-page

| Argument | Type | Notes |
| --- | --- | --- |
| `url` | string | Required, full http(s) URL |
| `selector` | string | Inspect only matches of this CSS selector |
| `waitFor` | string | Wait for a selector (CSS or `text=...`) first |
| `waitUntil` | `load` \| `domcontentloaded` \| `networkidle` | Navigation wait |
| `includeHtml` | boolean | Include rendered HTML (capped by `maxHtmlChars`, default 20000) |
| `timeoutMs` | number | Default 45000 |
| `view` | `elements` \| `locators` \| `aria` | `locators`: compact map of interactive elements with verified locators; `aria` (0.5.0+): accessibility snapshot of the page or of `selector`, with a `toMatchAriaSnapshot` assertion |
| `storageState` | string | Playwright storageState JSON inside the project (signed-in session); defaults to `PW_MCP_STORAGE_STATE` |
| `headers` | object | Extra HTTP headers |
| `actions` | array | Up to 20 steps after load: `{ type: click\|dblclick\|fill\|press\|check\|uncheck\|select\|hover\|wait\|goto, locator?, value?, url?, ms? }` |
| `routes` | array | Up to 20 network mocks before load, first match wins: `{ url (glob), method?, status?, json? \| body?, contentType?, headers?, abort?, delayMs? }` (0.5.0+). The result reports hits per mock |
| `har` | object | `{ path, mode?: replay\|record, url?, notFound?: abort\|fallback }` (0.5.0+): replay requests from a HAR inside the project, or record the traffic to one. `routes` still win |
| `browser` | `chromium` \| `firefox` \| `webkit` | Engine (0.5.0+, default chromium); must be installed |
| `viewport` | object | `{ width, height }` |

Returns each element's Playwright locators proven unique on the page (role +
name first), unique CSS selector, tag, visibility, box, text and attributes,
plus console messages. `validate-selector`, `compare-visual-state`,
`audit-accessibility` and `audit-performance` take the same `storageState`,
`headers`, `actions`, `routes`, `har`, `browser` and `viewport`
(`audit-performance` is Chromium-only).

## validate-selector

| Argument | Type | Notes |
| --- | --- | --- |
| `url` | string | Required |
| `selector` | string | Required: CSS, a Playwright selector, or a locator such as `getByRole('button', { name: 'Save' })` |
| `timeoutMs` | number | Default 45000 |

Verdicts: `✅ VALID — N matches` with samples and a unique locator for each,
a strict-mode warning when more than one matches, `✅ VALID — 0 matches` with
advice, or `❌ INVALID` with the parse error.

## list-tests

| Argument | Type | Notes |
| --- | --- | --- |
| `config` | string | Config path or index |
| `testDir` | string | Restrict to a directory |
| `filter` | string | Case-insensitive substring of `file › title` |
| `limit` | number | Default 500 |

Falls back to a source scan when Playwright cannot list (broken install or spec).

## generate-e2e-test

| Argument | Type | Notes |
| --- | --- | --- |
| `description` | string | Required: what the test should cover |
| `pageUrl` | string | Start page (default: `baseURL` / `webServer.url`) |
| `testDir`, `file` | string | Where to write; `file` must end in `.spec.*` or `.test.*` |
| `write` | boolean | Write to disk (default true) |
| `overwrite` | boolean | Replace a spec this tool generated earlier |
| `liveInspect` | boolean | Cross-check selectors on the live page |
| `steps` | array | Walk the flow (0.5.0+): up to 30 steps in the `actions` format, run on the live page first |
| `assertScope` | string | With `steps`: CSS scope of the end-state aria snapshot (default `body`) |
| `storageState` | string | With `steps`: session for the walk, also set in the spec with `test.use` |
| `verify`, `project`, `timeoutMs` | | With `steps`: run the written spec once (default true) |
| `config` | string | As above |

With `steps`, a step that fails on the live page stops the walk and nothing is
written. Otherwise the spec replays the steps and asserts the URL path and the
aria snapshot where the flow landed (its headings when it is over 60 lines),
then runs once; a failing first run keeps the file and shows the error.

## compare-visual-state

| Argument | Type | Notes |
| --- | --- | --- |
| `url` | string | Required |
| `name` | string | Baseline id, e.g. `checkout-page` |
| `action` | `compare` \| `baseline` | Default `compare`; `baseline` re-captures the reference |
| `selector` | string | Capture one element |
| `fullPage` | boolean | Full scrollable page |
| `tolerance` | number | Percent of pixels allowed to differ (default 0.1) |
| `pixelThreshold` | number | Per-pixel channel delta (default 60) |
| `waitUntil`, `waitFor`, `timeoutMs` | | As `inspect-page` |

Baselines live in `.pw-mcp/visual/`.

## diagnose-flaky

| Argument | Type | Notes |
| --- | --- | --- |
| `testFiles` | string[] | Default: tests that failed in the last run |
| `runs` | number | 2 to 10 (default 3) |
| `isolate` | boolean | Repeat fully parallel (`workers` default 4), then repeat the failing tests with one worker (0.3.0+) |
| `order` | boolean | Run the target files in `runs` random orders with one worker (`--shuffle`, Playwright 1.64+), replay a failing order, and name the test it relies on or is broken by (0.4.0+) |
| `separateProcesses` | boolean | One Playwright process per run instead of one `--repeat-each` process; slower (0.3.0+) |
| `browser`, `headed`, `workers`, `config` | | As `run-test` |
| `timeoutMs` | number | Per run (default 120000); the single `--repeat-each` process gets this × `runs` |

Runs with retries disabled and returns, per test, passes, failures, duration
spread, first error and `CONSISTENTLY FAILING`, `FLAKY` or `NOT REPRODUCING`,
plus the verdict block for the worst test. With `isolate`, a second table reads
each failing test as "fails only in parallel", "flaky even alone" or "fails
alone too". With `order`, a third section reads each test as "order
dependent", "flaky regardless of order" or "fails in every order", with the
`--shuffle=<seed>` command that reproduces it. `PW_MCP_SHUFFLE_SEEDS=1,2,3`
on the server replays given seeds instead of random ones. Versions before 0.3.0 return one run-level verdict and a per-run
table instead.

## audit-accessibility

Runs axe-core (0.4.0+) on a live page and returns WCAG violations, worst first.

| Argument | Type | Notes |
| --- | --- | --- |
| `url` | string | Required |
| `standard` | `wcag2a` \| `wcag2aa` \| `wcag21aa` \| `wcag22aa` \| `best-practice` \| `all` | Default `wcag22aa` (WCAG 2.0 to 2.2, A and AA) |
| `minImpact` | `critical` \| `serious` \| `moderate` \| `minor` | Hide violations below this impact |
| `selector` | string | Audit only this part of the page |
| `storageState`, `headers`, `actions`, `routes`, `viewport` | | As `inspect-page` |
| `waitFor`, `waitUntil`, `timeoutMs` | | `waitUntil` default `load`; `timeoutMs` default 60000 |

Each violation has its rule id, impact, WCAG criteria, a help link, up to three
offending elements as verified locators with what to change, and the count of
the rest. The result ends with an `@axe-core/playwright` check to paste into
the spec.

## audit-performance

Measures lab Web Vitals (0.5.0+) in headless Chromium.

| Argument | Type | Notes |
| --- | --- | --- |
| `url` | string | Required |
| `throttle` | `none` \| `mobile` | `mobile`: 412×823 touch viewport, 4x CPU slowdown, slow 4G (Lighthouse's mobile preset) |
| `cpuSlowdown` | number | Override the CPU factor, 1 to 20 |
| `runs` | number | 1 to 5 loads, median reported (default 1) |
| `budgets` | object | `{ lcpMs, cls, inpMs, tbtMs, fcpMs, ttfbMs, transferKb, requests }`; turns the verdict into pass/fail |
| `settleMs` | number | Observe this long after load (default 1500) |
| `storageState`, `headers`, `actions`, `routes`, `viewport` | | As `inspect-page`; clicks and key presses in `actions` are measured as INP |
| `waitFor`, `waitUntil`, `timeoutMs` | | `waitUntil` default `load`; `timeoutMs` per run, default 60000 |

Returns a table of LCP, CLS, INP (only when `actions` ran), TBT, FCP and TTFB
rated good / needs improvement / poor (or against the budgets), what to fix
(the LCP element and the shifted elements as verified locators, long tasks,
render-blocking requests), transfer size by type, the heaviest requests and
third-party weight, and a Playwright test asserting LCP and CLS budgets.

## suggest-fix

| Argument | Type | Notes |
| --- | --- | --- |
| `index` | number | 1-based failure index from the last run (default 1) |
| `apply` | boolean | Write the fix (default false: diff only) |
| `verify` | boolean | After applying, re-run and revert if still failing (default true) |
| `allowExpectationUpdate` | boolean | Allow applying a changed expected text (default false) |
| `candidate` | number | Strict mode violation: which listed match the test meant (0.5.0+) |
| `url`, `storageState`, `headers` | | Heal against a live page instead of the trace snapshot |
| `config`, `timeoutMs` | | As `run-test` |

For a strict mode violation (0.5.0+) it uses the unique locator Playwright
printed for the intended match: the exact-name match with `high` confidence, or
the `candidate` you pass with `medium`; with equal matches and no `candidate`
it lists them and changes nothing.

Returns a unified diff: a locator fix rated `high` or `medium` confidence, or an
expectation update rated `low` that is applied only with
`allowExpectationUpdate: true`. Otherwise it refuses and says the element is most
likely missing.

## get-run-status

| Argument | Type | Notes |
| --- | --- | --- |
| `runId` | string | From `run-test` with `background: true` (default: latest) |
| `waitSeconds` | number | Wait up to this long (max 55) |
| `cancel` | boolean | Stop the run |

## analyze-history

| Argument | Type | Notes |
| --- | --- | --- |
| `view` | `flaky` \| `patterns` \| `slow` \| `trend` \| `commits` \| `test` | Default `flaky`. `slow`, `trend` and `commits` are 0.5.0+ |
| `test` | string | Substring of a test's file or title |
| `lastRuns` | number | Default 30 |
| `limit` | number | Default 15 |

Reads `.playwright-e2e-mcp/history.jsonl`, written by every run
(`PW_MCP_HISTORY=0` disables it). `slow` lists tests by median duration in
passing runs and flags ones that got slower; `trend` shows failed and flaky
executions per day; `commits` names, per failing or flaky test, the first bad
commit after its last passing streak and the last good one.

## audit-tests (0.6.0+)

| Argument | Type | Notes |
| --- | --- | --- |
| `testDir` / `filter` | string | Narrow the files |
| `minSeverity` | `low` \| `medium` \| `high` | Default `low` |
| `historyRuns` | number | Default 50 |
| `limit` | number | Findings listed, default 50 |
| `fix` | boolean | Rewrite mechanical findings, re-run touched files, revert on failure |
| `verify` | boolean | Default true |

Rules: `hard-wait`, `sleep`, `non-retrying-assertion`, `missing-await`,
`focused-test` (high); `force-action`, `networkidle`, `element-handle`,
`fragile-selector`, `no-timeout` (medium); `hardcoded-url`, `serial-mode` (low).
Only `non-retrying-assertion`, `missing-await` and `focused-test` are fixed
mechanically. Files rank by findings weighted by their flaky rate in the history.

## bisect-failure (0.6.0+)

| Argument | Type | Notes |
| --- | --- | --- |
| `test` | string | Spec file (required) |
| `grep` | string | Test title; better than `:line` across commits |
| `good` / `bad` | string | Commits or refs; `good` defaults to the newest passing commit in the history, `bad` to HEAD |
| `repeat` | number | Runs per commit (1–10) for intermittent failures |
| `maxSteps` | number | Default 12 |
| `stepTimeoutMs` | number | Default 180000 |

Runs in a temporary git worktree with the current `node_modules` linked in;
untestable commits are skipped. `status` is `found`, `ambiguous`, `max-steps`,
`not-failing` (passes at bad) or `good-fails`.
