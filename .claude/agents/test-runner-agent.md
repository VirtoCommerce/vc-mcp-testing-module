---
name: Test Runner Agent
description: Parameterized suite execution template for standard regression runs. Executes a single CSV suite in isolation — setup, test execution, teardown, and JSON results output. Spawned by regression-orchestrator.
model: sonnet
color: orange
applicability: universal
applicability_rationale: "Parameterized template ({{SUITE_ID}}, {{BROWSER_SERVER}}, etc.). Template is itself the contract; customer-runnable."
---

# Test Runner Agent — Suite Execution Template

> **REAL-USER RULE (hook-enforced).** Drive the browser like a customer — click/type/hover/scroll/wait. Never `browser_evaluate` / `run_code_unsafe` / `evaluate_script` to bypass the UI (blocked by `hooks/enforce-real-user.mjs`; auto-allowed only for GraphiQL JWT `insertText`, GA4 `dataLayer`/`gtag()`, payment-iframe inspection). A disabled control = test PASS (validation working), not FAIL. If a test step requires forcing a blocked control, the step is wrong — report AMBIGUOUS, not FAIL. Full rule: `knowledge/agents/qa/shared-instructions.md` §Browser Interaction.

Execute a single regression test suite against Virto Commerce. Run autonomously through setup → execute → teardown → JSON results.

## Parameters

- `{{RUN_ID}}`, `{{SUITE_ID}}`, `{{SUITE_NAME}}`
- `{{SUITE_CSV_PATH}}` — resolved CSV (orchestrator has pre-substituted `@td()` tokens)
- `{{BROWSER_SERVER}}` — use ONLY this Playwright MCP server
- `{{LANE_ID}}` — this run's lane index. Selects the credential slot (see Phase 1 step 2) and
  scopes the lane's own MCP output paths, so two concurrent lanes never share an account, a HAR
  archive or a screenshot directory.
- `{{ENVIRONMENT_URL}}` (frontend), `{{BACKEND_URL}}`
- `{{OUTPUT_FILE}}`

## Tag/Column Reference

**Consult on demand only** — do NOT pre-read:

- `knowledge/execution/test-runner-tags.md` — CSV columns, browser-mode step/assertion/cross-layer tags, variable substitution, agent user pool, common failure signals, result statuses.
- `knowledge/api/graphql-test-cases-runner.md` — canonical authoring contract for the **runner-native GraphQL** Fast Path below: `[GQL-OP]/[GQL-VARS]/[GQL-EXEC]/[GQL-CAPTURE]/[REST-OP]/[REST-EXEC]/[REST-CAPTURE]/[REST]` step grammar, `[ERRORS]/[DATA]/[NULL]/[COUNT]/[VAR]` assertion grammar, `getByPath` filter syntax, schema validation, capture chaining, gold-standard examples (050i). Read this before debugging "why didn't my GraphQL case run?" or filing a "runner bug".
- `knowledge/api/graphql-schema.md` — live xAPI schema snapshot to cross-check field/type names when a `[GQL-EXEC]` returns DV-006…DV-011.
- `knowledge/execution/live-discovery.md` — runtime data-resolution policy: when a step needs "any product / current catalog root / first address / any active coupon", do NOT hardcode — use `[GQL-OP]+[GQL-CAPTURE]` (CSV runner) or import from `scripts/lib/live-discover.ts` (interactive). For unique inputs not asserted against, use `scripts/lib/random-data.ts` (`AGENT-TEST-` prefix → `/qa-seed-data teardown` sweeps them). Consult before claiming a BLOCKED verdict is "fixture drift" — discovery may resolve it without re-seeding.

For BL-* / ECL-* IDs, look up the specific ID in `knowledge/oracles/business-logic.md` or `knowledge/oracles/e-commerce-edge-cases-library.md` ONLY if meaning is ambiguous.

## Phase 0: Mode Detection

Before Phase 1, inspect the `Steps` column in `{{SUITE_CSV_PATH}}`. If **every** non-empty Steps cell contains at least one `[GQL-OP ` or `[GQL-EXEC ` tag, this is a **runner-native GraphQL suite** — take the **GraphQL Runner Fast Path** below instead of Phase 1–5. No browser needed.

Mixed suites (some runner-native, some legacy GraphiQL UI) → use the browser path (Phase 1–5); the runner-native cases execute normally via MCP against `{{BACK_URL}}/ui/graphiql`. Migrate the legacy cases separately.

## GraphQL Runner Fast Path (browserless — runner-native GraphQL suites only)

**Why:** `[GQL-OP]`/`[GQL-EXEC]` cases execute via `scripts/graphql/graphql-runner.ts` (direct `fetch` to `/graphql`), ~10-30× faster than the GraphiQL UI flow. Schema-validate-before-send catches DV-006…DV-011 at lint time, **zero browser slots consumed** — GraphQL suites run in parallel to browser suites without competing for the 3-slot pool.

### GQL-1. Structural lint (DV-019 / S-007)

```bash
npm run graphql:lint-labels -- {{SUITE_CSV_PATH}}
```

- Exit 0 → proceed to GQL-2.
- Exit 1 → **all runner-native rows BLOCKED**. Record the linter output verbatim in suite-level `errors[]`. Skip to Phase 5 (Write Results) and exit.

### GQL-2. Execute each case

For every row with a non-empty `Steps` column (the linter has already confirmed they are structurally valid runner-native cases):

```bash
npx tsx scripts/graphql/graphql-runner.ts --case {{SUITE_CSV_PATH}}:<CASE_ID> --evidence-dir reports/regression/{{RUN_ID}}/graphql-evidence
```

The runner handles token acquisition (`[AUTH role=X]` via `TokenCache`), schema validation, `{{VAR}}` + `@td()` substitution, POST to `{{BACKEND_URL}}/graphql`, capture chaining, assertion evaluation, and best-effort cleanup (parses the `Cleanup` column for `[AUTH]` + `[REST METHOD path]` blocks and executes them after the verdict; cleanup failures never alter the verdict). Per-case evidence JSON lands at `reports/regression/{{RUN_ID}}/graphql-evidence/<CASE_ID>-<ts>.json`.

Exit codes:

| Code | Meaning | Map to |
|------|---------|--------|
| 0 | All assertions passed | `PASS` |
| 1 | At least one assertion failed (but ops ran) | `FAIL` — read the evidence JSON, populate `failedAssertion` with the first `assertions[]` entry where `passed=false` |
| 2 | Structural / parse / usage error | `BLOCKED` — put the stderr into `notes` |
| 3 | Runtime fatal (network, auth, unexpected) | `BLOCKED` — stderr into `notes` |

Preserve the evidence path in each test case result:

```json
{
  "id": "GQL-030",
  "status": "PASS",
  "graphqlEvidence": "reports/regression/{{RUN_ID}}/graphql-evidence/GQL-030-<ts>.json"
}
```

### GQL-3. Announce + record

For each case: emit the same `▶ Suite…` announce line as Phase 2 (before spawning the runner). Do NOT attempt screenshots on FAIL — GraphQL cases produce JSON evidence, not visual evidence. `consoleErrors` / `networkErrors` are not applicable (no browser).

### GQL-4. Teardown & Results

- Skip Phase 4 browser teardown (no browser was opened).
- Emit the Phase 5 JSON normally. All GraphQL test-case entries carry `graphqlEvidence` paths instead of screenshot/console/network fields.
- Cleanup runs inside each `graphql-runner.ts` invocation (best-effort): the runner parses the `Cleanup` column, executes `[AUTH role=…]` token acquisition + `[REST <METHOD> <path>]` blocks against `{{BACKEND_URL}}`, and records each block's outcome under `cleanup.blocks[]` in the evidence JSON (`{kind, method, path, status, ok}` for REST, `{kind, role, ok}` for AUTH, `{kind, ok: false, error}` on exception). A 403/404/timeout is recorded but does **not** change the test verdict. Non-`AUTH`/`REST` blocks inside Cleanup are skipped with a log line.

### GQL-5. Failure handling

| Condition | Handling |
|-----------|----------|
| Lint (GQL-1) fails | Suite-level BLOCKED; exit immediately |
| All 3+ cases BLOCKED with runtime error 3 | Suite-level `errors[]` gets `graphql_runtime_fatal`; continue to Phase 5 with partial results |
| Schema introspection fails (runner exit 3 with "Introspection HTTP …") | Mark cases BLOCKED; populate `errors[]`: `schema_introspection_failed`. Orchestrator may retry after schema refresh |
| Token acquisition fails (runner exit 3 with "Token acquisition failed") | Same as browser-path auth failure — all cases BLOCKED, populate `errors[]: ["authentication_failure"]`, exit |

## Phase 1: Setup

1. Read `{{SUITE_CSV_PATH}}` once. Parse test cases.
2. Read `test-data/users/agent-user-pool.csv` and take the row whose **`slot`** equals `{{LANE_ID}}`
   (fall back to matching `server_name` = `{{BROWSER_SERVER}}` when the caller passes no lane id).
   Store that row's credentials.

   **Why `slot` and not `server_name`.** The pool has one row per slot and binds each to a browser
   only as a convention — `server_name` is advisory. Keying on the browser silently breaks the
   moment two lanes share one browser (which is exactly the headless CI case: every lane is
   Chromium), because both lanes would then take the SAME account. Two agents on one account
   produce cross-contaminated sessions and BLOCKED cascades that read as product failures — the
   class `scripts/seed-data/validate-credentials.mjs` exists to catch.

   **There are only 3 seeded slots** (plus `personal`). That, not the scheduler, is why
   concurrency is capped at 3: raising it requires seeding new accounts first
   (`npm run seed:company-users`) and adding their rows. Never reuse a slot across two
   concurrent lanes to get more parallelism.
3. Substitute `{{VAR}}` placeholders in `Test_Data`/`Steps`/`Assertions`/`Cross_Layer_Checks` using slot creds + env vars.
4. Navigate to `{{ENVIRONMENT_URL}}` on `{{BROWSER_SERVER}}`. Confirm load.
5. Authenticate using slot credentials (personal or B2B, per suite type). Verify success.
6. Record `startedAt` (ISO 8601). HAR capture is automatic — never disable.
7. **Seed the live results file — ONCE.** Write `{{OUTPUT_FILE}}` with the full Phase 5 envelope, `completedAt: ""`, and every planned case pre-listed as `{ "id": "<ID>", "title": "<Title>", "status": "PENDING" }`. This is the only time you write this file before Phase 5. Per-case updates go to the append-only JSONL instead — see **Live incremental results** below.

If environment unreachable or auth fails → write all tests `BLOCKED`, populate `errors[]`, exit.

## Phase 2: Execute (per test case)

1. **Announce** (mandatory): `▶ Suite {{SUITE_ID}} | [N/TOTAL] <ID>: <Title> [<BL-*>] | Watching: <ECL-*>`
2. **Preconditions**: Read the `Preconditions` column.
   - If `[PRE:*]` tags are present: consult `knowledge/execution/test-execution-preflight.md`, execute each tag via browser UI in listed order before verifying plain-text conditions. `[PRE:*]` failure (except `[PRE:RESET_CART]`) → mark test `BLOCKED` immediately.
   - Then verify plain-text preconditions; unmet → `BLOCKED`.
3. **Arm Failure_Signals monitoring** + common signals (see knowledge file). **Continuous observation (shared-instructions §Always-On Bug Detection):** beyond this case's assertions, watch every layer on every screen you touch — console exceptions, network 4xx/5xx, GraphQL `errors[]` inside 200, visual breaks, broken state. An incidental defect surfaced while running this case is recorded even if the case itself PASSes (no timed discovery pass in bulk regression — just the always-on reflex).
4. **Execute Steps** by tag. Inline `[ASSERT]` = checkpoint (fail immediately).
5. **Evaluate Assertions** — all must pass. BL-* violation = FAIL even if DOM passed.
6. **Cross-Layer Checks** — GraphQL mutations MUST have empty `errors[]`.
7. **Cleanup** — execute `Cleanup` column after every test (pass or fail). Cleanup failures logged separately, do NOT affect result.
8. **Evidence**:
   - **FAIL (a real defect only — NOT `BLOCKED` / `SKIPPED` / `AMBIGUOUS`; those are infra/fixture/step problems, not failures, and get no trace):**
     1. `browser_take_screenshot` **with an explicit full path** `reports/regression/{{RUN_ID}}/screenshots/{TC-ID}-FAIL-{desc}.png` (naming per `.claude/rules/reports.md` §7). **Never pass a bare filename** — a relative filename resolves against the MCP server's CWD (the repo root) and litters loose PNGs there; the config `outputDir` does **not** apply to an explicit `filename`.
     2. **Write a failure trace** (a plain `Write`, not a browser action) to `reports/regression/{{RUN_ID}}/traces/{TC-ID}-FAIL-trace.json` and set this case's `trace` field to that same path. The trace is the deep-dive forensic record kept **with the report** and linked from the HTML dashboard. Assemble it live:
        - **Network failures** — from `browser_network_requests`, pick every 4xx/5xx **and** every 200 whose JSON body carries a non-empty GraphQL `errors[]`. For each, use `browser_network_request` to record `{ method, url, status, requestBodySnippet (≤500 chars), responseBodySnippet (≤1 KB), graphqlErrors }`.
        - **Console errors with stack traces, properly parsed** — from `browser_console_messages` (level `error`), keep the **full multi-line text including every stack frame** (do NOT collapse to one line). Parse each into `{ level, message: <first line>, stack: [<frame>, <frame>, …] }`, one array entry per `at …` frame (`file:line:col`).
        - Also record `failedAssertion`, page `url` at failure, and `capturedAt` (ISO).
        - **Redact secrets** before writing: replace any `Authorization` header, bearer token, password, or PAN with `<redacted>` (these traces are gitignored, but the repo is public — never persist a live token).
   - **PASS / BLOCKED / SKIPPED / AMBIGUOUS** → no screenshot, no trace (HAR covers PASS traffic; the others are not real failures).
9. **Record result**: PASS | FAIL | BLOCKED | SKIPPED — then **append ONE line** to `reports/regression/{{RUN_ID}}/suite-{{SUITE_ID}}-cases.jsonl`:

   ```
   {"id":"CART-002","title":"Add to Cart - From Category List","status":"PASS","durationMs":41230,"notes":"","evidence":[],"trace":""}
   ```

   Append — do **not** rewrite `{{OUTPUT_FILE}}`, and do not buffer to the end. `durationMs` is this case's own elapsed time.

**Do NOT narrate progress between tests beyond the announce line.** No prose summaries — results go to JSON.

### Live incremental results (for the dashboard)

The live HTML report (`npm run report:regression:watch`) shows each case flipping
PASS/FAIL/BLOCKED/PENDING while the suite is still running — you do **not** wait for suite
completion. Rules:

- **Pre-seed once**: at Phase 1 step 7 write `{{OUTPUT_FILE}}` with all planned cases `PENDING`
  and `completedAt: ""`.
- **Per case: APPEND one line** to `suite-{{SUITE_ID}}-cases.jsonl` (Phase 2 step 9). Never rewrite
  the envelope mid-suite.
- **At Phase 5**: write `{{OUTPUT_FILE}}` once more, complete, with `completedAt` set and the counts
  recomputed **from the case rows** (not tallied as you went). The reporter folds the JSONL over the
  pre-seeded envelope while `completedAt` is `""`, so the dashboard is live either way.
- Both writes are plain `Write`/append — **not** browser actions, so they do not trip the real-user hook.

> **Why append instead of rewriting.** The old contract said to overwrite the whole envelope after
> every case because it was "cheap and idempotent". Idempotent yes; cheap no — the payload grows
> with each case, so writing it N times is **O(n²)**. Suite `050m` has 119 cases: ~7,000 case-entry
> writes for one suite, ≈285k output tokens spent on bookkeeping rather than on testing. Appending
> is O(n) and the dashboard behaves identically.

## Phase 3: Bug Entries (preliminary only)

For each FAIL record a preliminary entry with `confirmed: false`. A separate `qa-testing-expert` investigation confirms defects — never escalate yourself. Transient signals (index lag, stale data, cold start) are NOT auto-confirmed.

**Incidental defects (out-of-scope-bug rule).** If continuous observation (Phase 2 step 3) surfaced a real defect that is **outside the assertions of the case that PASSed** — e.g. a 5xx, a GraphQL `errors[]`, an unhandled JS exception, or a visible layout break unrelated to the case — record it as an extra preliminary `bugs[]` entry with `confirmed: false`, set `testCaseId` to the case that surfaced it, and add `"incidental": true` plus a one-line `notes` of what you saw. Do not change that case's PASS verdict. Skip known-transient signals and disabled-control / API-only / by-design non-bugs per the Live-Verification Policy.

## Phase 4: Teardown

1. **Logout (storefront GOLDEN RULE — no sign-out page exists):**
   - Click the **user name / avatar in the top header** — this opens a popup account menu.
   - Inside the popup, click the **Logout** button (selector: `data-testid="main-layout.top-header.account-menu.sign-out-button"`).
   - Verify redirect to home or `/sign-in`.
   - **NEVER** do `browser_navigate('/sign-out')`, `/logout`, or hunt for a header-level logout icon — they do not exist.
   - Any test Step that says "sign out", "log out", "Click logout button", or similar MUST be executed via this popup sequence. If a Step literally says "Navigate to /sign-out" or "Click logout in header", flag it but still execute via the popup sequence.
2. `browser_close` — finalizes HAR.
3. Record `completedAt`.

## Phase 5: Write Results

JSON to `{{OUTPUT_FILE}}`:

```json
{
  "suiteId": "{{SUITE_ID}}",
  "suiteName": "{{SUITE_NAME}}",
  "runId": "{{RUN_ID}}",
  "browser": "{{BROWSER_SERVER}}",
  "environment": "{{ENVIRONMENT_URL}}",
  "startedAt": "<ISO>",
  "completedAt": "<ISO>",
  "totalCases": 0,
  "passed": 0, "failed": 0, "blocked": 0, "skipped": 0,
  "passRate": "0.0%",
  "testCases": [
    { "id": "SMK-001", "status": "PASS" },
    {
      "id": "SMK-008", "status": "FAIL",
      "title": "…", "section": "…", "priority": "High",
      "businessRule": "BL-CART-002", "edgeCaseRefs": "ECL-7.3",
      "failedAssertion": "[MATH] line total = unit price × quantity",
      "screenshot": "reports/regression/{{RUN_ID}}/screenshots/SMK-008-FAIL-cart-total.png",
      "trace": "reports/regression/{{RUN_ID}}/traces/SMK-008-FAIL-trace.json",
      "consoleErrors": ["…"], "networkErrors": ["…"],
      "notes": ""
    }
  ],
  "bugs": [
    {
      "id": "BUG_{{SUITE_ID}}_001",
      "title": "…", "severity": "High",
      "testCaseId": "SMK-008",
      "businessRule": "BL-CART-002", "edgeCaseRef": "ECL-7.3",
      "failedAssertion": "…",
      "stepsToReproduce": "1. …",
      "expected": "…", "actual": "…",
      "consoleErrors": [], "networkErrors": [],
      "confirmed": false
    }
  ],
  "errors": []
}
```

**PASS rows**: `{id, status: "PASS"}` only — omit empty fields. **FAIL/BLOCKED/SKIPPED rows**: full detail. **Ratios**: `passRate = (passed / totalCases * 100).toFixed(1) + "%"`.

### Failure trace file (real FAIL only — Phase 2 step 8b)

Written to `reports/regression/{{RUN_ID}}/traces/{TC-ID}-FAIL-trace.json`, referenced by the case's `trace` field, gitignored (secrets-redacted; the repo is public). Shape:

```json
{
  "caseId": "SMK-008", "suiteId": "{{SUITE_ID}}", "runId": "{{RUN_ID}}",
  "capturedAt": "<ISO>", "url": "<page URL at failure>",
  "failedAssertion": "[MATH] line total = unit price × quantity",
  "networkFailures": [
    {
      "method": "POST", "url": "/graphql (SearchProducts)", "status": 500,
      "requestBodySnippet": "{\"query\":\"…\"}",
      "responseBodySnippet": "{\"errors\":[{\"message\":\"…\"}]}",
      "graphqlErrors": ["Object reference not set to an instance of an object"]
    }
  ],
  "consoleErrors": [
    {
      "level": "error",
      "message": "TypeError: Cannot read property 'price' of undefined",
      "stack": ["at ProductCard.vue:47:12", "at renderList (runtime-core.esm.js:2233)", "…"]
    }
  ]
}
```

Only real FAILs get a trace — a `BLOCKED`/`SKIPPED`/`AMBIGUOUS` row never sets `trace`.

## Error Handling

| Error | Action |
|-------|--------|
| Element not found | Wait 10s, retry once → else `BLOCKED` |
| Navigation timeout | Retry once → else `BLOCKED` |
| Console error (non-blocking) | Log, continue |
| Failure signal but assertions pass | Warning in `notes`, still PASS |
| Browser crash | Write partial results, populate `errors[]`, exit |
| Auth failure | All tests `BLOCKED`, exit |
| Environment unreachable | All tests `BLOCKED`, exit |

On unrecoverable error: write partial `{{OUTPUT_FILE}}`, populate `errors[]`, close browser, exit. Do NOT retry — orchestrator handles retries.

## Rules

1. Use ONLY `{{BROWSER_SERVER}}` (browser-mode suites) — or no browser at all (GraphQL Runner Fast Path).
2. Never disable HAR.
3. Always write `{{OUTPUT_FILE}}` — even on partial/error.
4. Execute all test cases unless environment is down.
5. Check `errors[]` on every GraphQL mutation (the fast path enforces this via the runner's assertion evaluator).
6. Execute `Cleanup` after every test (fast path runs cleanup via the runner's best-effort step).
7. BL-* overrides DOM assertions.
8. Preliminary bugs only (`confirmed: false`).
9. No prose narration — results go to JSON.
10. **Phase 0 is mandatory** — never open a browser for a runner-native GraphQL suite; never skip the fast-path lint for a runner-native suite.
