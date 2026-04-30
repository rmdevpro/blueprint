# Workbench UI Test Runbook (Master)

This is the single master runbook for all Workbench UI testing. It consolidates the original Phase 1-7 runbook, Phase 8-10 new feature tests, and easy-fixes tests into one document.

Executed by an AI agent using Playwright MCP against any Workbench deployment. Output is a pass/fail checklist per test, with GitHub issues filed for each failure.

## Target

The runbook is environment-agnostic. The user specifies the target at execution time and the executor binds these values:

- `${WORKBENCH_URL}` — base URL of the workbench under test (e.g. `${WORKBENCH_URL}`, `${WORKBENCH_URL}`)
- `${WORKBENCH_CONTAINER}` — Docker container name for `docker exec` / `docker logs` style commands (e.g. `workbench`, `workbench-test`)
- `${WORKBENCH_HOST}` — host machine reachable for `ssh` and `docker` commands (e.g. `user@host`)
- `${GATE_USER}` / `${GATE_PASS}` — gate credentials if the deployment uses HF Space password auth; leave blank otherwise

Anywhere a test step says `${WORKBENCH_URL}/api/...`, substitute the actual URL for the run. The executor is responsible for the substitution; the runbook itself never names a specific port or hostname in the runnable steps.

Historical incident notes appear in some test sections — those are records of what happened on prior runs, not instructions to repeat. Specific host or deployment names should not appear anywhere in the runnable steps.

## Progress Tracker

| Phase | Total | Status |
|-------|-------|--------|
| 0. OAuth | 3 | Required for CLI tests (Phase 5+). See options below. |
| 1. Smoke | 3 | — |
| 2. Core | 11 | — |
| 3. Features | 18 | (3 removed: Notes Tab, Messages Tab, MCP Servers moved) |
| 4. Edge Cases | 20 | (4 removed/updated: compaction, notes isolation, terminal button) |
| 5. CLI & Terminal | 11 + batch | — |
| 6. End-to-End | 1 | — |
| 7. User Stories | 7 | — |
| 8. New Features | 31 | NF-01 through NF-38 (minus removed NF-31 to NF-37) |
| 9. Settings & Vector Search | 14 | NF-39 through NF-52 |
| 10. Multi-CLI & MCP | 16 | NF-53 through NF-68 |
| 11. New Features v2 | 10 | NF-69 through NF-78 |
| 12. Comprehensive Feature Verification | 32 | — |
| 13. Regression Tests for Issue Fixes | ~50 | REG-* tests for landed fixes |
| 14. MCP Tool Catalogue | 49 (44 tools × 1 happy path + 2 stdio + 12 negative + 5 e2e + 3 log filter shapes) | One row per tool + negative-path matrix + Phase 14b CLI driving |
| 15. Recent Regression Coverage | 13 | REG-220..228 + REG-MCP-REWORK-* |
| **Total** | **~270** | |

## Meta
- **Target:** `${WORKBENCH_URL}` (specified per run — see Target section above)
- **Login:** `${GATE_USER}` / `${GATE_PASS}` if a gate is present; otherwise direct
- **Tool:** Playwright MCP (local, NOT Malory)
- **Container user:** `workbench` (UID 1000)
- **Workspace path:** `/data/workspace`
- **MCP Tools:** 44 flat tools — `file_*` (8), `session_*` (19), `project_*` (11), `task_*` (5), `log_*` (1)
- **Settings tabs:** General, Claude Code, Vector Search, System Prompts
- **Session types:** Claude, Gemini, Codex (selected via + dropdown)
- **Test Plan:** See `docs/work-specs/workbench-test-plan.md`

## IMPORTANT: What changed since the original runbook

These changes affect many test steps. Read before executing.

1. **Filter buttons → dropdown:** `[data-filter="active"]` buttons replaced by `#session-filter` `<select>` dropdown. Use `filterEl.value = 'archived'; filterEl.dispatchEvent(new Event('change'))` instead of `browser_click`.
2. **Terminal button removed:** `.term-btn:not(.new-btn)` (`>_`) no longer exists. Terminal is now in the `+` dropdown menu (Claude/Gemini/Codex/Terminal).
3. **Notes tab removed:** `[data-panel="notes"]`, `#panel-notes`, `#notes-editor` no longer exist. Project notes are in the project config modal only.
4. **Messages tab removed:** `[data-panel="messages"]`, `#panel-messages`, `#message-list` no longer exist. Inter-session messaging replaced by tmux.
5. **Notes API endpoints removed:** `/api/projects/:name/notes` and `/api/sessions/:id/notes` GET/PUT no longer exist. Notes stored via `/api/projects/:name/config` and `/api/sessions/:id/config`.
6. **Quorum removed:** No quorum UI, no `/api/quorum/ask`, no `workbench_ask_quorum`.
7. **Smart compaction removed:** No `/api/sessions/:id/smart-compact`, no `workbench_smart_compaction`.
8. **Settings reorganized:** 4 tabs (General, Claude Code, Vector Search, System Prompts). Model/Thinking/Keepalive moved to Claude Code tab. Quorum fields (#14-16) and Tasks checkbox (#17) removed.
9. **Workspace path:** `/data/workspace` (not `/mnt/workspace`). Container user is `workbench` (not `hopper`).
10. **CLI type indicator:** `.active-dot` replaced by CLI type label (C/G/X) with per-CLI colors.
11. **Session creation:** `+` button opens dropdown: C Claude, G Gemini, X Codex, Terminal. `createSession(projectName, cliType)` accepts CLI type.
12. **MCP tools rebuilt:** 17 tools (orig) → 3 action-routers (#150) → 44 flat tools (current). Names like `file_read`, `session_send_text`, `task_add` — no nested `action` arg.

## How to Use This Runbook

**THE ONLY PASS IS A POSITIVE COMPLETE AFFIRMATION OF SUCCESS. ALL ELSE IS A FAIL.**

A test result of "unknown", "empty", "0", "null", "not found", "expected behavior", "will populate later", or any non-positive outcome is a **FAIL**. If the user would see something broken, blank, missing, or wrong — it is a FAIL. There are no partial passes. There is no "works but shows wrong data." There is no "expected on first load." If it doesn't show the correct value, it failed.

**The executor must NEVER choose SKIP on its own.** Every test in this runbook is runnable on the standard Workbench executor (Playwright MCP for UI, curl for API, ssh + docker exec for infra, real CLI sessions for terminal flows, Hymie Firefox if a headed browser is required). If a test appears unrunnable: investigate why, file an issue, and mark the test FAIL — do NOT skip on your own initiative. "I don't have the tool" is wrong: you do. "It's blocked by a prior failure" means fix the blocker (or fail the blocker test and the dependent ones).

SKIP is reserved for the orchestrator's explicit instruction (e.g., "skip Phase 0 for this run, Claude is already authenticated"). When the orchestrator directs a SKIP, record it as SKIP with the orchestrator's reason verbatim. The executor never decides to SKIP unilaterally.

1. Execute tests in phase order. Phase 1 (Smoke) must fully pass before proceeding.
2. For each test, follow the **Steps** exactly using Playwright MCP tools.
3. After each verification step, mark the **Result** as PASS or FAIL. Nothing else.
4. On FAIL: capture a screenshot (`browser_screenshot`), note the failure details, and file a GitHub issue per the protocol below. Continue to the next test unless the failure blocks downstream tests.
5. State reset: before each test (unless grouped), create fresh test sessions with unique names (e.g., prefixed with `test-YYYYMMDD-`). After tests complete, archive test sessions via `PUT /api/sessions/:id/config` with `{state:'archived'}`. Do NOT use `DELETE /api/sessions` (AD-004: deleteSession is permanently disabled). Tests should not depend on state from prior tests.
6. Terminal I/O pattern (ALL terminal tests MUST use this):
   - **Send input** via WebSocket (reliable, does not need xterm focus):
     `browser_evaluate`: `tabs.get(activeTabId).ws.send('/help\r')`
   - **Read output** from terminal buffer (wait 2-3s first, then read):
     ```javascript
     browser_evaluate:
     (() => {
       const lines = [];
       const buf = tabs.get(activeTabId).term.buffer.active;
       for (let i = 0; i < buf.length; i++) {
         const line = buf.getLine(i)?.translateToString(true);
         if (line?.trim()) lines.push(line.trim());
       }
       return lines;
     })()
     ```
   - Single-line buffer read: `tabs.get(activeTabId).term.buffer.active.getLine(N)?.translateToString(true)` where N is the line index.
7. DOM checks use: `browser_evaluate` with `document.querySelector(selector).textContent` or `.innerText`.
9. Baseline reset (browser-side, use when needed between tests):
   ```javascript
   // Create a fresh test project (if needed)
   browser_evaluate: fetch('/api/projects', {method:'POST', headers:{'Content-Type':'application/json'}, body:JSON.stringify({path:'/workspace/test-runbook', name:'test-runbook'})}).then(r=>r.json())
   
   // Archive any leftover test sessions (never delete -- AD-004)
   browser_evaluate: fetch('/api/state').then(r=>r.json()).then(d => {
     const archiveOps = [];
     for (const p of d.projects) {
       for (const s of p.sessions) {
         if (s.name?.startsWith('test-') && s.state !== 'archived') {
           archiveOps.push(fetch('/api/sessions/' + s.id + '/config', {method:'PUT', headers:{'Content-Type':'application/json'}, body:JSON.stringify({state:'archived'})}));
         }
       }
     }
     return Promise.all(archiveOps).then(() => archiveOps.length + ' sessions archived');
   })
   
   // Close all open tabs
   browser_evaluate: document.querySelectorAll('.tab-close').forEach(b => b.click())
   
   // Dismiss any open modals/overlays
   browser_evaluate: (() => {
     document.querySelectorAll('[id^="new-session-overlay-"], [id^="config-overlay-"], [id^="summary-overlay-"]').forEach(m => m.remove());
     const sm = document.getElementById('settings-modal'); if (sm) sm.classList.remove('visible');
     const am = document.getElementById('auth-modal'); if (am) am.classList.remove('visible');
   })()
   ```

## Issue Filing Protocol

When a test fails:

1. **Capture:** Take `browser_screenshot` immediately.
2. **Collect:** Note the test ID, step that failed, expected vs actual, any console errors (`browser_evaluate` with `window.__lastError` or check devtools).
3. **File:** Create a GitHub issue programmatically:
   ```bash
   gh issue create \
     --repo rmdevpro/workbench \
     --title "[UI Test] TEST-ID: Brief description of failure" \
     --label "bug,ui-test" \
     --body "$(cat <<'ISSUE_EOF'
   **Test ID:** TEST-ID
   **Phase:** N
   **Step:** Step number and description
   **Expected:** What should have happened
   **Actual:** What happened
   **Screenshot:** (attach via gh issue edit after creation, or paste URL)
   **Branch:** refactor-server-js
   **Runbook:** workbench-test-04-09-26/ui-test-runbook.md
   ISSUE_EOF
   )"
   ```

## Prerequisites

### Where to run (read first)

**Tests run against a deployed container or HF Space — never against a host-machine clone of the repo.** The host that holds this repo may be a prod or dev workbench host (e.g. M5, irina); its database, webhook config, qdrant, and tmux state belong to the running workbench, not to the test harness. Running `npm test`, `npm run test:coverage`, `node --test`, `c8`, or any ad-hoc `node -e` that imports a project module from the host shell will:

- spin up the in-process Express app on top of the live one (port collision or shadowed code),
- fire real webhooks to whatever Slack/GitHub endpoints the live `secrets.env` points at,
- run schema migrations against the live SQLite DB,
- on a prior incident, nearly killed the active session.

**Allowed:**

- `ssh ${WORKBENCH_HOST} 'docker exec -i ${WORKBENCH_CONTAINER} sh -c "cd /app && npm test"'` — runs the suite inside the deployed container's own filesystem and DB.
- The Playwright MCP server (driven from inside this Claude Code session) pointed at a deployed `${WORKBENCH_URL}` — an HF Space or irina dev container. The Playwright MCP runs Chromium against an HTTP target, never imports server code, so `browser_navigate` / `browser_evaluate` against a Space URL is fine.
- Hymie / Hymie2 (remote desktops with real Firefox) for headed/visual checks against a deployed Space, when the bug needs real rendering rather than a headless capture.
- HF Space deploys + verification via curl/Playwright MCP against the Space URL.

**Not allowed (anywhere on the host shell of a workbench-running machine):**

- `npm test` / `npm run test:coverage` / `npm run test:live` / `npm run test:browser` from the host repo
- `node --test`, `c8`, `nyc`
- `node -e` snippets that `require('./db.js')`, `./mcp-tools.js`, `./session-utils.js`, etc.
- Even "mock" tests are forbidden from the host — they spin up the local Express app.

If you need coverage, run it inside the container: `ssh ${WORKBENCH_HOST} 'docker exec -i ${WORKBENCH_CONTAINER} sh -c "cd /app && npm run test:coverage"'`.

### Standard prereqs (verify before starting)

1. **Workbench reachable:** `browser_navigate` to `${WORKBENCH_URL}` loads the page (gate page if a gate is configured, otherwise the workbench itself)
2. **Login (if gate present):** Fill `${GATE_USER}` / `${GATE_PASS}`, click Sign In. Skip if no gate.
3. **API reachable:** `browser_evaluate` with `fetch('/health').then(r=>r.json())` returns `{status:'ok'}`
4. **Baseline state:** Create a test project if none exists. Do NOT delete sessions (AD-004: deleteSession is permanently disabled). Instead, create fresh test sessions with unique names and archive them after.
5. **WebSocket connected:** Open a session tab, then verify its WebSocket: `browser_evaluate` with `activeTabId && tabs.get(activeTabId)?.ws?.readyState` returns `1` (OPEN). Note: there is no global `ws` variable; WebSocket connections are per-tab.

---

## Test Execution

### Phase 0: Environment Setup (required for everything that follows)

Phase 0 prepares a clean, authenticated test environment for the rest of the runbook. It has TWO steps that always run together: first a fresh container, then OAuth on top.

#### 0.A: Fresh container (also covers REG-FRESH-01)

A fresh container with an empty `/data` volume must come up cleanly. This is the "Fresh Install Works" regression — by virtue of Phase 0.A succeeding, REG-FRESH-01 PASSes for the run.

**Steps:**
1. On `${WORKBENCH_HOST}`: `docker run --rm -d --name workbench-test-fresh -v <ephemeral-volume>:/data -p <free-port>:7860 <image>` (or use a docker-compose entry that creates the ephemeral volume each run).
2. Bind `${WORKBENCH_URL}` to that container's port for this run.
3. Wait up to 30s for `/health` to return `{status:'ok'}`.
4. `browser_navigate` to `${WORKBENCH_URL}` — verify the empty-state UI renders, sidebar shows zero (or default-seeded) projects.
5. `docker exec ${WORKBENCH_CONTAINER} ls /data/.workbench/workbench.db` — DB file exists (entrypoint.sh + db.js migrations ran).
6. `docker exec ${WORKBENCH_CONTAINER} ls /data/workspace` — workspace dir created.
7. `curl ${WORKBENCH_URL}/api/state` — returns `{projects: []}` or default seeded projects without errors.

**Expected:** Container starts within 30s. /health green. UI loads. DB + workspace seeded. No 500s in initial requests.

**Result:** ☐ PASS ☐ FAIL

If 0.A FAILs: STOP — file an issue, do not proceed. Nothing downstream is meaningful without a working container.

#### 0.B: Claude Authentication (required for Phase 5+)

Claude CLI tests (Phase 5: CLI & Terminal) require valid Claude credentials in the just-spawned container.

**Option A: Hymie desktop automation (full OAuth flow)**
Use Hymie MCP to automate the browser-based OAuth flow. This tests the actual auth pipeline end-to-end. Requires Hymie MCP server connected.

**Option B: Inject credentials from an authenticated device (with user permission)**
Copy the credentials file from a machine that already has valid Claude auth into the container.

```bash
# From the authenticated machine, copy credentials to the workbench container:
# 1. Read the local credentials
cat ~/.claude/credentials.json

# 2. Inject into the container via the terminal
# Open a terminal session in Workbench, then:
echo '<paste credentials JSON>' > ~/.claude/credentials.json
```

Ask the orchestrator which option to use. If neither is available, fix the auth path before proceeding — Phase 5 tests will FAIL without auth.

**Result:** ☐ PASS ☐ FAIL

#### Orchestrator-directed SKIP

When the orchestrator explicitly directs "skip Phase 0 — re-use existing dev container with persistent auth," then 0.A and 0.B both record SKIP with that orchestrator reason verbatim, and REG-FRESH-01 also records SKIP with the same reason. This is the only way SKIP appears for any test in this runbook.

---

### Phase 1: Smoke (must pass before proceeding)

These 3 tests validate that the app is functional. If any fail, stop and investigate.

#### SMOKE-01: Page Load and Empty State
**Source:** FR-01, BRW-01
**Priority:** P0

**Steps:**
1. `browser_navigate` to `${WORKBENCH_URL}` (login with ${GATE_USER}/${GATE_PASS} first if gate page shown)
2. `browser_screenshot` to capture initial load
3. `browser_evaluate`: `document.title`
4. `browser_evaluate`: `document.querySelector('#sidebar') !== null`
5. `browser_evaluate`: `document.querySelector('#empty-state').offsetParent !== null` (visible check)
6. `browser_evaluate`: `document.querySelector('#empty-state').textContent`
7. `browser_evaluate`: `document.querySelector('#project-list').children.length`
8. `browser_evaluate`: `document.querySelector('#status-bar').classList.contains('active')` (should be false when no session is open)
9. `browser_evaluate`: `document.querySelector('#settings-modal').classList.contains('visible')` (should be false)
10. `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects.length)`

**Expected:**
- Title is "Workbench"
- Sidebar is present with `#project-list` containing project groups
- `#empty-state` is visible with text "Select a session or create a new one"
- Settings modal is hidden
- API returns projects array

**Verify:**
- Screenshot shows sidebar on left, empty state in center, no right panel
- DOM queries return expected values

**Result:** PASS
**Notes:** Title "Workbench", sidebar present, empty-state visible with correct text, settings modal hidden, status bar inactive, API returns 1 project.

---

#### SMOKE-02: Sidebar Projects Render
**Source:** BRW-01
**Priority:** P0

**Steps:**
1. `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects.map(p=>p.name))`
2. `browser_evaluate`: `document.querySelectorAll('.project-group').length`
3. `browser_evaluate`: `document.querySelector('.project-header')?.textContent`
4. `browser_evaluate`: `document.querySelectorAll('.session-item').length`
5. `browser_evaluate`: `document.getElementById('session-filter').value === 'active'` (filter dropdown defaults to active)

**Expected:**
- Number of `.project-group` elements matches API project count
- Active filter button is selected by default
- Each project header shows project name and session count badge

**Verify:**
- `browser_screenshot` shows project groups in sidebar
- Filter "Active" has class `active`

**Result:** PASS
**Notes:** 1 project group (my-project) matches API, session badge shows 1, active filter selected, 1 session item in sidebar.

---

#### SMOKE-03: API Health and WebSocket
**Source:** BRW-21 (WS reconnection prerequisite)
**Priority:** P0

**Steps:**
1. `browser_evaluate`: `fetch('/health').then(r=>r.json())`
2. `browser_evaluate`: `fetch('/api/auth/status').then(r=>r.json())`
3. Open a session tab by clicking a session in the sidebar, then verify its WebSocket:
   `browser_evaluate`: `activeTabId && tabs.get(activeTabId)?.ws?.readyState`
   (Note: there is no global `ws` variable; WebSocket connections are per-tab)
4. `browser_evaluate`: `fetch('/api/mounts').then(r=>r.json()).then(d=>d.length)`

**Expected:**
- Health endpoint returns `{status:'ok'}`
- Auth status returns `{valid:true}` (not `authenticated`)
- WebSocket readyState is `1` (OPEN) for the active tab
- Mounts endpoint returns array (may be empty on cloud deployments if nothing mounted under `/mnt`)

**Verify:**
- All four checks return expected values

---

### Phase 2: Core Workflows

#### CORE-01: Create Session
**Source:** BRW-02
**Priority:** P0

**Setup:** Ensure at least one project exists. If none: `browser_evaluate`: `fetch('/api/projects', {method:'POST', headers:{'Content-Type':'application/json'}, body:JSON.stringify({path:'/workspace/test-runbook', name:'test-runbook'})}).then(r=>r.json())`

**Steps:**
1. `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects[0].name)` -- save as PROJECT_NAME
2. `browser_click` on `.project-group .new-btn` (the + button on the first project header)
3. Wait for new-session dialog: `browser_evaluate`: `document.querySelector('#new-session-name') !== null`
4. `browser_type` into `#new-session-name`: `Say hello`
5. `browser_click` on `#new-session-submit`
6. Wait 3s for session creation: `browser_wait` with timeout 5000
7. `browser_evaluate`: `document.querySelectorAll('.tab').length`
8. `browser_evaluate`: `document.querySelector('.tab.active .tab-name')?.textContent`
9. `browser_screenshot`

**Expected:**
- New session dialog appears with a `Session name` single-line input
- After submit, a new tab appears in `#tab-bar`
- Tab name equals what was typed in the input (e.g., "Say hello")
- Terminal pane becomes active (empty-state hidden)
- `#empty-state` is no longer visible

**Verify:**
- Tab count increased by 1
- Active tab name matches the typed session name
- `browser_evaluate`: `document.querySelector('#empty-state').offsetParent === null`

**Result:** PASS
**Notes:** New session dialog appeared, tab name "Say hello" matched the value typed into the Session name input, #empty-state removed from DOM when session opens (not just hidden).

---

#### CORE-02: Terminal I/O
**Source:** BRW-03
**Priority:** P0

**Steps:**
1. Ensure a session tab is open (from CORE-01 or create one)
2. `browser_evaluate`: `activeTabId` -- save the tab ID
3. `browser_evaluate`: `tabs.get(activeTabId).term !== undefined` -- assert true
4. `browser_evaluate`: `tabs.get(activeTabId).ws.readyState === 1` -- assert WebSocket OPEN
5. Send command via WebSocket: `browser_evaluate`: `tabs.get(activeTabId).ws.send('/help\r')`
6. `browser_wait` 3000
7. Read terminal buffer:
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; for (let i = 0; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```
8. `browser_screenshot`

**Expected:**
- Terminal instance exists for the active tab
- After sending `/help`, the terminal buffer contains help output (slash commands listed)
- Buffer lines include text matching `/help|status|available|commands/i`

**Verify:**
- `browser_evaluate`: `(() => { const buf = tabs.get(activeTabId).term.buffer.active; for (let i = 0; i < buf.length; i++) { const l = buf.getLine(i)?.translateToString(true) || ''; if (/help|commands|available/i.test(l)) return true; } return false; })()` -- assert true
- Screenshot shows terminal with text

**Result:** PASS
**Notes:** term instance exists, WebSocket open (readyState=1), /help output received with "Shortcuts" and command list in buffer.

---

#### CORE-03: Multi-Tab Management
**Source:** BRW-04
**Priority:** P0

**Setup:** Get the first project name: `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects[0].name)` -- save as PROJECT_NAME. If no tab is open, click a session in the sidebar to open one first.

**Steps:**
1. Create a second session via API: `browser_evaluate`:
   ```
   fetch('/api/sessions', {method:'POST', headers:{'Content-Type':'application/json'}, body:JSON.stringify({project:'PROJECT_NAME', name:'test-tab-2 Say hi'})}).then(r=>r.json())
   ```
   (Replace PROJECT_NAME with actual value from setup)
2. Wait 3s for session to start, then refresh sidebar: `browser_evaluate`: `loadState()`
3. `browser_wait` 2000
4. Click the new session in the sidebar to open it as a tab: `browser_click` on `.session-item:first-child`
   (Note: creating a session via API does NOT auto-open a tab. You must click it in the sidebar.)
5. `browser_wait` 1000
6. `browser_evaluate`: `document.querySelectorAll('.tab').length` -- should be >= 2
7. Click the first tab: `browser_click` on `.tab:first-child`
8. `browser_evaluate`: `document.querySelector('.tab:first-child').classList.contains('active')`
9. Click the second tab: `browser_click` on `.tab:nth-child(2)`
10. `browser_evaluate`: `document.querySelector('.tab:nth-child(2)').classList.contains('active')`
11. `browser_screenshot`

**Expected:**
- Two or more tabs are present in `#tab-bar`
- Clicking a tab makes it active (adds `.active` class)
- Terminal pane switches to show the selected session's terminal

**Verify:**
- Tab count >= 2
- Active class toggles correctly between tabs

**Result:** PASS
**Notes:** 2 tabs open, clicking each adds .active class correctly. Session created via API does not auto-open tab (must click sidebar item to open).

---

#### CORE-04: Close Tab
**Source:** BRW-04
**Priority:** P0

**Steps:**
1. `browser_evaluate`: `document.querySelectorAll('.tab').length` -- save as TAB_COUNT
2. `browser_click` on `.tab:last-child .tab-close`
3. `browser_wait` 1000
4. `browser_evaluate`: `document.querySelectorAll('.tab').length` -- should be TAB_COUNT - 1
5. If no tabs remain: `browser_evaluate`: `document.querySelector('#empty-state').offsetParent !== null`

**Expected:**
- Clicking the X on a tab closes it
- Tab count decreases by 1
- If last tab closed, empty state reappears

**Verify:**
- Tab count check
- Screenshot confirms UI state

**Result:** PASS
**Notes:** Tab closes, count decrements. Empty state reappears when last tab closed. CAUTION: `.tab:last-child .tab-close` selector fails — #tab-bar has an extra non-tab button child, so :last-child picks the wrong element. Use `querySelectorAll('#tab-bar .tab')[n-1].querySelector('.tab-close')` instead.

---

#### CORE-05: Sidebar Session Click Opens Tab
**Source:** BRW-04
**Priority:** P1

**Steps:**
1. Close all tabs first (click all `.tab-close` buttons)
2. `browser_evaluate`: `document.querySelector('#empty-state').offsetParent !== null` -- should be true
3. `browser_click` on `.session-item:first-child` in the sidebar
4. `browser_wait` 2000
5. `browser_evaluate`: `document.querySelectorAll('.tab').length`
6. `browser_evaluate`: `document.querySelector('.tab.active .tab-name')?.textContent`
7. `browser_evaluate`: `document.querySelector('#empty-state').offsetParent === null`

**Expected:**
- Clicking a session in sidebar opens it in a new tab
- Empty state disappears
- Tab shows session name

**Verify:**
- Tab created, empty state hidden

**Result:** PASS
**Notes:** Sidebar click opens session tab, #empty-state removed from DOM (not just hidden).

---

#### CORE-06: Filter Dropdown
**Source:** BRW-06
**Priority:** P1

**UPDATED:** Filter buttons replaced by `#session-filter` `<select>` dropdown.

**Steps:**
1. `browser_evaluate`: `document.getElementById('session-filter').value = 'all'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
2. `browser_wait` 500
3. `browser_evaluate`: `document.querySelectorAll('.session-item').length` -- save as ALL_COUNT
4. `browser_evaluate`: `document.getElementById('session-filter').value = 'active'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
5. `browser_wait` 500
6. `browser_evaluate`: `document.querySelectorAll('.session-item').length` -- save as ACTIVE_COUNT
7. Repeat for 'archived' and 'hidden'
8. Reset to 'active'

**Expected:**
- Dropdown has 4 options: Active, All, Archived, Hidden
- ALL_COUNT >= ACTIVE_COUNT
- Session items change based on filter

**Verify:**
- Counts are consistent
- `browser_evaluate`: `document.getElementById('session-filter').tagName === 'SELECT'`

**Result:** ☐ PASS ☐ FAIL
**Notes:**

---

#### CORE-07: Sort Sessions
**Source:** BRW-07
**Priority:** P1

**Steps:**
1. `browser_evaluate`: `document.querySelector('#session-sort').value` -- default should be "date"
2. `browser_select_option` on `#session-sort` with value `name`
3. `browser_evaluate`: `Array.from(document.querySelectorAll('.session-name')).map(e=>e.textContent)`
4. `browser_select_option` on `#session-sort` with value `messages`
5. `browser_evaluate`: `Array.from(document.querySelectorAll('.session-name')).map(e=>e.textContent)`
6. Reset: `browser_select_option` on `#session-sort` with value `date`

**Expected:**
- Default sort is "date"
- Changing to "name" reorders sessions alphabetically
- Changing to "messages" reorders by message count

**Verify:**
- Session order changes between sorts

**Result:** PASS
**Notes:** Default "date" sort correct. Name sort gives alphabetical order. Messages sort reorders by count. All three produce distinct orderings.

---

#### CORE-08: Search Sessions
**Source:** BRW-08
**Priority:** P1

**Steps:**
1. `browser_type` into `#session-search`: `test`
2. `browser_wait` 500
3. `browser_evaluate`: `document.querySelectorAll('.session-item').length` -- note filtered count
4. `browser_evaluate`: `Array.from(document.querySelectorAll('.session-name')).every(e=>e.textContent.toLowerCase().includes('test'))`
5. Clear search: triple-click `#session-search` then type empty string
6. `browser_evaluate`: `document.querySelector('#session-search').value = ''; document.querySelector('#session-search').dispatchEvent(new Event('input'))`
7. `browser_evaluate`: `document.querySelectorAll('.session-item').length` -- should be back to full count

**Expected:**
- Typing in search filters sessions to those matching the query
- Clearing search restores all sessions

**Verify:**
- Filtered sessions all contain search term
- Count restores after clear

**Result:** PASS
**Notes:** Search "test" filtered to 2 matching sessions, all containing "test". Count restored to 3 after clearing via dispatchEvent(new Event('input')).

---

#### CORE-09: Rename Session
**Source:** BRW-16
**Priority:** P1

**Steps:**
1. Get a session ID: `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects[0].sessions[0].id)`
2. Hover over first session: `browser_hover` on `.session-item:first-child`
3. `browser_click` on `.session-item:first-child .session-action-btn.rename`
4. `browser_wait` 500
5. Dialog should appear -- `browser_evaluate`: `document.querySelector('#cfg-name') !== null`
6. Clear and type new name: `browser_evaluate`: `document.querySelector('#cfg-name').value = ''`
7. `browser_type` into `#cfg-name`: `renamed-session`
8. Find and click Save button in the config dialog
9. `browser_wait` 1000
10. `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects[0].sessions.find(s=>s.name==='renamed-session'))`

**Expected:**
- Config dialog opens with `#cfg-name` input
- After saving, session name is updated in API and sidebar

**Verify:**
- API returns session with new name
- Sidebar shows renamed session

**Result:** PASS
**Notes:** Config dialog opens with #cfg-name populated. Rename to "renamed-session" persists via API. Save button found by text content search (not by class).

---

#### CORE-10: Archive Session
**Source:** USR-02 (session organization)
**Priority:** P1

**Steps:**
1. Set filter to "all": `browser_evaluate`: `document.getElementById('session-filter').value='all'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
2. `browser_evaluate`: `document.querySelectorAll('.session-item').length` -- save as BEFORE_COUNT
3. `browser_hover` on `.session-item:first-child`
4. `browser_click` on `.session-item:first-child .session-action-btn.archive`
5. `browser_wait` 1000
6. `browser_evaluate`: `document.getElementById('session-filter').value='active'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
7. `browser_evaluate`: `document.querySelectorAll('.session-item').length` -- should be BEFORE_COUNT - 1 or fewer
8. `browser_evaluate`: `document.getElementById('session-filter').value='archived'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
9. `browser_evaluate`: `document.querySelectorAll('.session-item.archived').length` -- should be >= 1
10. `browser_screenshot`

**Expected:**
- Archive button changes session state
- Session no longer appears in "Active" filter
- Session appears in "Archived" filter with italic/muted styling

**Verify:**
- Session visible in archived filter
- `.session-item.archived` has `.session-name` with italic style

**Result:** PASS
**Notes:** Archive reduces active count 3→2. Archived filter shows 1 item with .archived class. Active→archived state change confirmed.

---

#### CORE-11: Unarchive Session
**Source:** USR-02 (session organization)
**Priority:** P1

**Steps:**
1. `browser_evaluate`: `document.getElementById('session-filter').value='archived'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
2. `browser_hover` on `.session-item.archived:first-child`
3. `browser_click` on `.session-item.archived:first-child .session-action-btn.unarchive`
4. `browser_wait` 1000
5. `browser_evaluate`: `document.getElementById('session-filter').value='active'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
6. `browser_evaluate`: `document.querySelectorAll('.session-item').length` -- should include unarchived session

**Expected:**
- Unarchive button restores session to active state

**Verify:**
- Session reappears in active filter

**Result:** ☐ PASS ☐ FAIL
**Notes:**

---

### Phase 3: Feature Coverage

#### FEAT-01: Right Panel Toggle
**Source:** BRW-24 (panel resize)
**Priority:** P1

**Setup:** Ensure a session tab is open (panel behavior requires an active session context).

**Steps:**
1. `browser_evaluate`: `document.querySelector('#right-panel').classList.contains('open')` -- note initial state
2. `browser_click` on `#panel-toggle`
3. `browser_wait` 300
4. `browser_evaluate`: `document.querySelector('#right-panel').classList.contains('open')` -- should be toggled
5. `browser_screenshot`
6. `browser_click` on `#panel-toggle` -- toggle back
7. `browser_evaluate`: `document.querySelector('#right-panel').classList.contains('open')` -- should be back to initial

**Expected:**
- Panel toggle button opens/closes the right panel
- Panel has class `open` when visible, absent when hidden
- Panel width transitions from 0 to 320px

**Verify:**
- Class toggles correctly
- `browser_evaluate`: `document.querySelector('#right-panel.open') !== null` -- true when open
- `browser_evaluate`: `document.querySelector('#right-panel').offsetWidth` -- should be ~320 when open, 0 when closed
- Screenshot shows panel open with tabs (Files, Notes, Tasks, Messages)

**Result:** ☒ PASS ☐ FAIL
**Notes:** Panel toggles to 320px when open; closed state shows 1px (border artifact, not functional issue). Toggle works correctly.

---

#### FEAT-02: Panel - Files Tab
**Source:** BRW-09 (file browser)
**Priority:** P1

**Steps:**
1. Open a session tab (click a session in sidebar)
2. Open right panel: `browser_click` on `#panel-toggle` (if not already open)
3. `browser_click` on `[data-panel="files"]`
4. `browser_evaluate`: `document.querySelector('[data-panel="files"]').classList.contains('active')`
5. `browser_evaluate`: `document.querySelector('#panel-files').style.display !== 'none'`
6. `browser_evaluate`: `document.querySelector('#file-browser-tree').children.length`
7. `browser_screenshot`

**Expected:**
- Files tab is active
- `#panel-files` section is visible
- File browser tree shows directory listing for the project

**Verify:**
- File tree has children (directories/files listed)
- Screenshot shows file browser

**Result:** ☒ PASS ☐ FAIL
**Notes:** Files tab active, #panel-files visible, file tree has 1 root child (container root /). NOTE: `#file-browser-tree a` selector in steps is wrong — tree uses ul/li elements, not anchors; navigate via `#file-browser-tree li`.

---

#### FEAT-03: Panel - Notes Tab (Project Notes)
**Status:** ✂ REMOVED — Notes tab removed from right panel. Project notes are now in the project config modal (pencil button). Dedicated notes API endpoints (`/api/projects/:name/notes`) also removed. Notes stored via `/api/projects/:name/config`.

---

#### FEAT-04: Panel - Tasks Tab (Filesystem Tree)
**Source:** BRW-11, #88, #93
**Priority:** P1

**Steps:**
1. `browser_evaluate`: `switchPanel('tasks')`
2. `browser_evaluate`: `document.querySelector('#task-tree').children.length > 0` — tree has mounts
3. Expand workspace mount by clicking mount header arrow
4. `browser_evaluate`: `document.querySelectorAll('.task-folder').length > 0` — folders visible
5. Right-click a folder label → context menu shows "Add Task" and "New Folder"
6. Add a task via API: `POST /api/mcp/call {tool:'task_add', args:{folder_path:'/data/workspace/...', title:'Runbook test'}}`
7. Reload task tree, expand folder → task visible as `.task-node` with checkbox
8. Click task checkbox → `browser_evaluate`: task status changes to 'done' in DB
9. Click task ✕ button → task removed from tree and DB
10. Switch to Files panel and back → expanded folders preserved

**Expected:**
- Task tree shows real filesystem folders from /api/mounts
- Context menu on folder: Add Task, New Folder
- Context menu on task: Edit, Complete, Archive, Delete
- Checkbox completes task
- Delete removes task
- Expand state preserved across panel switches

**Verify:**
- `.task-folder` elements exist with folder names
- `.task-node` elements show task title and checkbox
- API confirms task status changes

**Result:** ☐ PASS ☐ FAIL
**Notes:**

---

#### FEAT-05: Panel - Messages Tab
**Status:** ✂ REMOVED — Messages tab and inter-session messaging removed. Replaced by tmux for agent communication (#51). Messages table, endpoints, and UI all deleted.

---

#### FEAT-06: Settings Modal - Open/Close
**Source:** BRW-15 (settings persist)
**Priority:** P1

**Steps:**
1. `browser_click` on `#sidebar-footer button` (the Settings button with gear icon)
2. `browser_wait` 300
3. `browser_evaluate`: `document.querySelector('#settings-modal').classList.contains('visible')`
4. `browser_screenshot`
5. `browser_evaluate`: `document.querySelector('[data-settings-tab="general"]').classList.contains('active')`
6. `browser_click` on `.settings-close`
7. `browser_wait` 300
8. `browser_evaluate`: `document.querySelector('#settings-modal').classList.contains('visible')`

**Expected:**
- Settings modal opens on gear click (gets `.visible` class, which sets display to flex)
- General tab is active by default
- Close button removes `.visible` class, hiding the modal

**Verify:**
- `.visible` class toggles correctly
- Screenshot shows settings with General tab

**Result:** ☒ PASS ☐ FAIL
**Notes:** Originally FAIL (issue #40). Fix applied: added `switchSettingsTab('general')` call at start of `openSettings()` in `index.html:2101`. Verified via Malory: navigate to Prompts tab, close modal, reopen — General tab now has `.active` class. Fix deployed to container via `docker cp`. rmdevpro/workbench#40 resolved.

---

#### FEAT-07: Settings - Theme Change
**Source:** BRW-13 (theme change)
**Priority:** P1

**Steps:**
1. Open settings modal
2. `browser_evaluate`: `document.querySelector('#setting-theme').value` -- save current theme
3. `browser_select_option` on `#setting-theme` with value `light`
4. `browser_wait` 500
5. `browser_screenshot` -- should show light theme
6. `browser_evaluate`: `getComputedStyle(document.body).backgroundColor`
7. Restore: `browser_select_option` on `#setting-theme` with value `dark`
8. `browser_wait` 500
9. Close settings

**Expected:**
- Selecting "light" theme changes CSS variables
- Background color changes to a light color
- Selecting "dark" restores dark theme

**Verify:**
- Background color is light when light theme active
- Screenshot confirms visual change

**Result:** ☒ PASS ☐ FAIL
**Notes:** Light theme: body background = rgb(245,245,245). Dark theme restored correctly.

---

#### FEAT-08: Settings - Font Size
**Source:** BRW-14 (font change)
**Priority:** P1

**Steps:**
1. Open settings modal
2. `browser_evaluate`: `document.querySelector('#setting-font-size').value` -- save current
3. Clear and set font size: `browser_evaluate`: `document.querySelector('#setting-font-size').value = '18'`
4. Trigger change: `browser_evaluate`: `document.querySelector('#setting-font-size').dispatchEvent(new Event('change'))`
5. `browser_wait` 500
6. Verify: `browser_evaluate`: `fetch('/api/settings').then(r=>r.json()).then(d=>d.font_size)`
7. Restore original font size
8. Close settings

**Expected:**
- Font size setting is saved via API
- Terminal font size updates

**Verify:**
- API returns font_size: 18 (or string "18")

**Result:** ☒ PASS ☐ FAIL
**Notes:** font_size=18 saved via API confirmed. Terminal font updated visually.

---

#### FEAT-09: Settings - Font Family
**Source:** BRW-14 (font change)
**Priority:** P2

**Steps:**
1. Open settings modal
2. `browser_evaluate`: `document.querySelector('#setting-font-family').value`
3. `browser_select_option` on `#setting-font-family` with a different value (e.g., `'Fira Code', monospace` -- note: option values include the full CSS font-family string)
4. `browser_wait` 500
5. `browser_evaluate`: `fetch('/api/settings').then(r=>r.json()).then(d=>d.font_family)`
6. Restore and close

**Expected:**
- Font family setting persists to API

**Verify:**
- API returns the selected font family

**Result:** ☒ PASS ☐ FAIL
**Notes:** Font family selection persisted via API. Restored to original after test.

---

#### FEAT-10: Settings - Default Model
**Source:** BRW-15 (settings persist)
**Priority:** P1

**UPDATED:** Model dropdown is now on the Claude Code tab, not General.

**Steps:**
1. Open settings modal, click Claude Code tab: `browser_evaluate`: `document.querySelector('[data-settings-tab="claude"]').click()`
2. `browser_evaluate`: `document.querySelector('#setting-model').value`
3. `browser_select_option` on `#setting-model` -- select a different model
4. `browser_wait` 500
5. `browser_evaluate`: `fetch('/api/settings').then(r=>r.json()).then(d=>d.default_model)`

**Expected:**
- Model selection persists to API settings

**Verify:**
- API returns selected model value

**Result:** ☒ PASS ☐ FAIL
**Notes:** Model selection persists to API (default_model field). Confirmed via API response.

---

#### FEAT-11: Settings - Thinking Level
**Source:** BRW-15 (settings persist)
**Priority:** P2

**UPDATED:** Thinking level is now on the Claude Code tab.

**Steps:**
1. Open settings modal, click Claude Code tab: `browser_evaluate`: `document.querySelector('[data-settings-tab="claude"]').click()`
2. `browser_select_option` on `#setting-thinking` with value `high`
3. `browser_wait` 500
4. `browser_evaluate`: `fetch('/api/settings').then(r=>r.json()).then(d=>d.thinking_level)`
5. Restore to original and close

**Expected:**
- Thinking level persists

**Verify:**
- API returns "high"

**Result:** ☒ PASS ☐ FAIL
**Notes:** thinking_level="high" saved and confirmed via API. Restored to original after test.

---

#### FEAT-12: Settings - System Prompts Tab
**Source:** BRW-40
**Priority:** P1

The Prompts tab shows three read-only template buttons (C / G / X) that open CLAUDE.md / GEMINI.md / AGENTS.md in a file-editor tab, plus an editable Default Project Template textarea. Earlier versions had an inline `#setting-global-claude-md` textarea — that has been replaced by the read-only buttons.

**Steps:**
1. Open settings modal
2. `browser_click` on `[data-settings-tab="prompts"]`
3. `browser_evaluate`: `document.querySelector('#settings-prompts').style.display !== 'none'`
4. `browser_evaluate`: count buttons under `#settings-prompts` whose `onclick` includes `openFileTab` — must be exactly 3 (one each for CLAUDE.md, GEMINI.md, AGENTS.md). Confirm each button's `onclick` references the correct path.
5. `browser_evaluate`: `document.querySelector('#setting-project-template') !== null` — Default Project Template textarea must still be present.
6. Click the C (Claude) button: `browser_click` on the button whose `onclick` includes `'CLAUDE.md'`. Wait, then verify a file-editor tab opened with that path (`document.querySelector('.tab.active')?.dataset.filePath?.endsWith('CLAUDE.md')`).
7. Repeat step 6 for the G (Gemini) and X (Codex) buttons.
8. `browser_screenshot`

**Expected:**
- Prompts tab visible.
- 3 read-only template buttons exist; each opens its corresponding global prompt file in a file-editor tab.
- Default Project Template textarea (`#setting-project-template`) still editable.

**Verify:**
- All 3 buttons present + clickable + each opens the right file.
- Project template textarea present.

**Result:** ☐ PASS ☐ FAIL

---

#### FEAT-13: Settings - MCP Servers
**Source:** BRW-40
**Priority:** P2

**Steps:**
1. Open settings modal (General tab)
2. `browser_evaluate`: `document.querySelector('#mcp-server-list') !== null`
3. `browser_evaluate`: `document.querySelectorAll('.mcp-server-item').length`
4. `browser_evaluate`: `document.querySelector('#mcp-name') !== null`

**Expected:**
- MCP server list is rendered
- Add MCP form fields exist

**Verify:**
- Elements present in DOM

**Result:** ☒ PASS ☐ FAIL
**Notes:** #mcp-server-list present, 1 .mcp-server-item, #mcp-name input present.

---

#### FEAT-14: Session Config Dialog
**Source:** BRW-16 (session config)
**Priority:** P1

**Steps:**
1. `browser_hover` on `.session-item:first-child`
2. `browser_click` on `.session-item:first-child .session-action-btn.rename`
3. `browser_wait` 500
4. `browser_evaluate`: `document.querySelector('#cfg-name') !== null`
5. `browser_evaluate`: `document.querySelector('#cfg-state') !== null`
6. `browser_evaluate`: `document.querySelector('#cfg-notes') !== null`
7. Check state dropdown options: `browser_evaluate`:
   ```
   Array.from(document.querySelector('#cfg-state').options).map(o=>o.value)
   ```
8. `browser_screenshot`
9. Close the dialog

**Expected:**
- Config dialog has name input, state dropdown, and session notes
- State dropdown includes options like "active", "archived", "hidden"

**Verify:**
- All three fields present
- State options include expected values

**Result:** ☒ PASS ☐ FAIL
**Notes:** Config dialog has #cfg-name, #cfg-state, #cfg-notes. State dropdown options: ["active","archived","hidden"]. All correct.

---

#### FEAT-15: Session Summary
**Source:** BRW-17 (session summary)
**Priority:** P1

**Setup:** Ensure a session with conversation history exists (run CLI-07 first to create history, or use an existing session with messages).

**Steps:**
1. `browser_hover` on `.session-item:first-child`
2. `browser_click` on `.session-item:first-child .session-action-btn.summary`
3. `browser_wait` 1000
4. `browser_evaluate`: `document.querySelector('.summary-spinner') !== null || document.querySelector('#summary-content') !== null` -- assert true
5. `browser_screenshot`
6. Poll for summary completion (up to 30s, check every 3s):
   `browser_evaluate`: `document.querySelector('#summary-content')?.textContent?.length > 50`
   Repeat with `browser_wait` 3000 between polls, up to 10 attempts. If still spinner after 30s, mark as FAIL with note "summary generation timed out after 30s" and file an issue.
7. Record summary text: `browser_evaluate`: `document.querySelector('#summary-content')?.textContent?.substring(0, 200)`
8. Close the summary overlay: `browser_click` on the close button within the summary overlay (look for a button with X or close text inside `[id^="summary-overlay-"]`)
9. Verify overlay removed: `browser_evaluate`: `document.querySelector('[id^="summary-overlay-"]') === null`

**Expected:**
- Summary button triggers summary generation
- Spinner shows while generating
- Summary content appears when complete (text length > 50 chars)
- Overlay can be closed

**Verify:**
- Summary text is present and meaningful (length > 50)
- Overlay is removed after close

**Result:** ☒ PASS ☐ FAIL
**Notes:** Summary generated (241 chars). Spinner shown briefly then summary content appeared. Overlay closed via close button, removed from DOM.

---

#### FEAT-16: Add Project via File Picker
**Source:** BRW-18 (add project)
**Priority:** P1

**Steps:**
1. `browser_evaluate`: `document.querySelectorAll('.project-group').length` -- save as BEFORE
2. Click "Add Project" button: `browser_click` on `#sidebar-header button[title="Add Project"]`
3. `browser_wait` 500
4. `browser_evaluate`: `document.querySelector('#jqft-tree') !== null` -- file picker dialog
5. `browser_screenshot`
6. `browser_evaluate`: `document.querySelector('#picker-path')?.value`

**Expected:**
- Add project button opens file picker overlay
- jQueryFileTree renders directory listing
- Path input and name input are present

**Verify:**
- `#jqft-tree` has children
- Screenshot shows file picker

**Result:** ☒ PASS ☐ FAIL
**Notes:** File picker opens with #jqft-tree rendered. #picker-path and #picker-name both present. NOTE: Bug #30 (no folder creation in picker) still open but picker itself works for selecting existing dirs.

---

#### FEAT-17: Status Bar Display
**Source:** BRW-19 (status bar)
**Priority:** P1

**Steps:**
1. Open a session tab
2. `browser_evaluate`: `document.querySelector('#status-bar').offsetParent !== null`
3. `browser_evaluate`: `document.querySelector('#status-bar').innerHTML`
4. `browser_evaluate`: `document.querySelector('#status-bar .status-item')?.textContent`
5. `browser_screenshot`

**Expected:**
- Status bar is visible when a session is active
- Shows model name, mode, context usage, and session status
- Context bar shows percentage fill

**Verify:**
- Status bar contains ".status-item" elements
- Text includes model name and context info

**Result:** ☒ PASS ☐ FAIL
**Notes:** Status bar shows 4 items: model (Sonnet), mode (bypass), context (17k/200k 8%), connection status (connected). All correct.

---

#### FEAT-18: Context Threshold Indicators
**Source:** BRW-20 (context thresholds)
**Priority:** P1

**Steps:**
1. Open a session tab
2. `browser_evaluate`: read status bar HTML for context-bar:
   ```
   document.querySelector('.context-bar .fill')?.className
   ```
3. `browser_evaluate`: `document.querySelector('.context-bar .fill')?.style.width`

**Expected:**
- Context bar fill has a class indicating level: `context-fill-green` (< 60%), `context-fill-amber` (60-85%), or `context-fill-red` (>= 85%)
- Width reflects actual context usage percentage

**Verify:**
- Fill class and width are present and reasonable

**Result:** ☒ PASS ☐ FAIL
**Notes:** context-fill-green class present (session at 8% usage). Width=8.4% matches context bar display.

---

#### FEAT-19: File Browser - Open File in Tab Editor
**Source:** BRW-09 (file browser)
**Priority:** P1
**UPDATED:** File viewer panel replaced by in-tab editors (CodeMirror for code, Toast UI for markdown).

**Steps:**
1. Open right panel, Files tab
2. Double-click a file in the file browser tree (e.g., a .md or .js file)
3. `browser_wait` 2000
4. `browser_evaluate`: Check for new file tab: `document.querySelector('.tab .file-tab-icon') !== null`
5. `browser_evaluate`: Check for editor: `document.querySelector('.cm-editor') !== null || document.querySelector('.toastui-editor-defaultUI') !== null`
6. `browser_evaluate`: Check editor toolbar: `document.querySelector('.editor-toolbar') !== null`
7. `browser_evaluate`: Save button: `document.querySelector('.editor-save-btn') !== null`
8. `browser_evaluate`: Save As button: `document.querySelector('.editor-saveas-btn') !== null`
9. `browser_screenshot`

**Expected:**
- Double-clicking a file opens a new tab with a file icon (📄)
- CodeMirror editor (`.cm-editor`) visible for code files, Toast UI (`.toastui-editor-defaultUI`) for .md files
- Editor toolbar with file path, Save button (disabled when clean), and Save As button
- Save button turns green briefly with "Saved" text on successful save
- Tab shows italic name + ● dot + yellow top border when dirty
- Ctrl+S saves the file

**Verify:**
- File tab with editor toolbar, Save, and Save As visible

---

#### FEAT-20: Search API (Global Search)
**Source:** BRW-08 (session search)
**Priority:** P1

**Steps:**
1. `browser_evaluate`: `fetch('/api/search?q=test').then(r=>r.json())`
2. Check response structure

**Expected:**
- Search API returns `{results: [...]}` with matching sessions
- Each result has session name (`name`), match count (`matchCount`), project, and matches array

**Verify:**
- Response has `.results` array
- Results have expected fields (`name`, `matchCount`, `project`, `sessionId`)

**Result:** ☒ PASS ☐ FAIL
**Notes:** Search returned results with session_id/sessionId/project/name/matchCount fields. NOTE: API returns duplicate snake_case + camelCase field names (both session_id and sessionId). Not a failure but worth noting.

---

#### FEAT-21: Keepalive Settings
**Source:** BRW-40
**Priority:** P2

**UPDATED:** Keepalive settings are now on the Claude Code tab.

**Steps:**
1. Open settings modal, click Claude Code tab: `browser_evaluate`: `document.querySelector('[data-settings-tab="claude"]').click()`
2. `browser_evaluate`: `document.querySelector('#setting-keepalive-mode').value`
3. `browser_evaluate`: `document.querySelector('#setting-idle-minutes').value`
4. `browser_evaluate`: `fetch('/api/keepalive/status').then(r=>r.json())`

**Expected:**
- Keepalive mode dropdown and idle minutes input are present
- API returns keepalive status

**Verify:**
- Values present and API responds

**Result:** ☒ PASS ☐ FAIL
**Notes:** keepalive-mode dropdown present (value="always"), idle-minutes input present (value=30). API /api/keepalive/status returned running status.

---

### Phase 4: Edge Cases & Resilience

#### EDGE-01: WebSocket Reconnection
**Source:** BRW-21
**Priority:** P0

**Steps:**
1. Ensure a session tab is open. Get the active tab's WebSocket:
   `browser_evaluate`: `tabs.get(activeTabId)?.ws?.readyState` -- should be 1 (OPEN)
2. Force disconnect: `browser_evaluate`: `tabs.get(activeTabId).ws.close()`
   (Note: there is no global `ws` variable; WebSocket connections are per-tab, stored in `tabs.get(tabId).ws`)
3. `browser_wait` 3000
4. `browser_evaluate`: `tabs.get(activeTabId)?.ws?.readyState` -- should be 1 (reconnected)
5. Verify app still works: `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects.length > 0)`

**Expected:**
- WebSocket reconnects automatically after close
- App continues to function after reconnection

**Verify:**
- readyState returns to 1 for the active tab
- API calls still work from the page

**Result:** ☒ PASS ☐ FAIL
**Notes:** WS close → reconnect confirmed. readyState=1 within 3s. API fetch /api/state still returned valid data.

---

#### EDGE-02: Rapid Tab Switching
**Source:** BRW-23
**Priority:** P1

**Setup:** Open 3 session tabs. Get the project name: `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects[0].name)`. Create sessions if needed via API, then click each in the sidebar to open tabs.

**Steps:**
1. Verify at least 3 tabs: `browser_evaluate`: `document.querySelectorAll('.tab').length >= 3` -- if false, open more sessions from sidebar
2. Rapidly click between tabs (simulate):
   ```
   browser_click .tab:nth-child(1)
   browser_click .tab:nth-child(2)
   browser_click .tab:nth-child(3)
   browser_click .tab:nth-child(1)
   browser_click .tab:nth-child(3)
   ```
   (Execute each click with minimal delay)
3. `browser_wait` 1000
4. `browser_evaluate`: `document.querySelectorAll('.tab.active').length` -- should be exactly 1
5. `browser_evaluate`: `activeTabId !== undefined`
6. `browser_screenshot`

**Expected:**
- Only one tab has `.active` class at any time
- No visual glitches or errors
- Terminal pane shows content for the final active tab

**Verify:**
- Exactly 1 active tab
- activeTabId is set

**Result:** ☒ PASS ☐ FAIL
**Notes:** Exactly 1 active tab after 5 rapid clicks across 3 tabs. activeTabId set correctly.

---

#### EDGE-03: Long Session Name
**Source:** BRW-26
**Priority:** P2

**Steps:**
1. Create session with long name via API:
   ```
   fetch('/api/sessions', {method:'POST', headers:{'Content-Type':'application/json'}, body:JSON.stringify({project:'PROJECT_NAME', name:'this-is-a-very-long-session-name-that-should-be-truncated-with-ellipsis-in-the-sidebar-display'})}).then(r=>r.json())
   ```
2. `browser_wait` 2000
3. `browser_evaluate`: check that the session name is truncated with CSS:
   ```
   Array.from(document.querySelectorAll('.session-name')).some(el => el.scrollWidth > el.clientWidth)
   ```
4. `browser_screenshot`

**Expected:**
- Long session name is truncated with text-overflow: ellipsis
- No layout breaking

**Verify:**
- scrollWidth > clientWidth for the long name element
- Screenshot shows ellipsis

**Result:** ☒ PASS ☐ FAIL
**Notes:** Long name session: scrollWidth=398 > clientWidth=233. Ellipsis visible in sidebar.

---

#### EDGE-04: Empty State Returns After Last Tab Close
**Source:** BRW-05, BRW-25
**Priority:** P1

**Steps:**
1. Ensure exactly one tab is open
2. `browser_evaluate`: `document.querySelector('#empty-state').offsetParent === null` -- hidden
3. Close the tab: `browser_click` on `.tab .tab-close`
4. `browser_wait` 500
5. `browser_evaluate`: `document.querySelector('#empty-state').offsetParent !== null` -- visible
6. `browser_evaluate`: `document.querySelector('#empty-state').textContent.includes('Select a session')`

**Expected:**
- Empty state reappears when all tabs are closed
- Shows "Select a session or create a new one"

**Verify:**
- Empty state visible, correct text

**Result:** ☒ PASS ☐ FAIL
**Notes:** Verified in CORE-04. #empty-state reappears after last tab closed. NOTE: `#empty-state` is removed from DOM when session opens (not just hidden); `?.offsetParent === null` check in runbook steps is wrong — use `getElementById('empty-state') === null` to detect removal.

---

#### EDGE-05: Auth Modal Elements
**Source:** BRW-28
**Priority:** P1

**Steps:**
1. `browser_evaluate`: `document.querySelector('#auth-modal') !== null`
2. `browser_evaluate`: `document.querySelector('#auth-link') !== null`
3. `browser_evaluate`: `document.querySelector('#auth-code-input') !== null`
4. `browser_evaluate`: `document.querySelector('#auth-code-submit') !== null`
5. `browser_evaluate`: `document.querySelector('.modal-close') !== null`

**Expected:**
- Auth modal has all required elements: link, code input, submit, close
- Modal is hidden by default

**Verify:**
- All elements exist in DOM

**Result:** ☒ PASS ☐ FAIL
**Notes:** All auth modal elements present: #auth-modal, #auth-link, #auth-code-input, #auth-code-submit, .modal-close.

---

#### EDGE-06: Double-Click Prevention
**Source:** BRW-30
**Priority:** P2

**Setup:** Ensure at least one session is visible in the sidebar. Get project name: `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects[0].name)`. If no sessions exist, create one via API:
```
browser_evaluate: fetch('/api/sessions', {method:'POST', headers:{'Content-Type':'application/json'}, body:JSON.stringify({project:'PROJECT_NAME', name:'test-dblclick'})}).then(r=>r.json())
```
`browser_wait` 3000, then `browser_evaluate`: `loadState()`, `browser_wait` 1000.

**Steps:**
1. `browser_evaluate`: save current tab count: `document.querySelectorAll('.tab').length`
2. Double-click a session in sidebar: `browser_click` on `.session-item:first-child` then immediately `browser_click` on `.session-item:first-child` again
3. `browser_wait` 1000
4. `browser_evaluate`: `document.querySelectorAll('.tab').length` -- should only have added 1 tab

**Expected:**
- Double-clicking a session does not create duplicate tabs
- Only one tab is opened for the same session

**Verify:**
- Tab count increased by at most 1

**Result:** ☒ PASS ☐ FAIL
**Notes:** Double-click on session item opened exactly 1 tab (not 2). Tab dedup logic working.

---

#### EDGE-07: Compaction Trigger
**Source:** BRW-31
**Priority:** P1

**Setup:** Ensure a session tab is open. Get the session ID: `browser_evaluate`: `activeTabId` -- save as SESSION_ID. Get the project name from the tab: `browser_evaluate`: `tabs.get(activeTabId)?.project` -- save as PROJECT_NAME.

**Steps:**
1. Verify smart-compact API exists and responds:
   `browser_evaluate`:
   ```
   fetch('/api/sessions/SESSION_ID/smart-compact', {method:'POST', headers:{'Content-Type':'application/json'}, body:JSON.stringify({project:'PROJECT_NAME'})}).then(r=>r.status)
   ```
   (Replace SESSION_ID and PROJECT_NAME with actual values)

**Expected:**
- Smart compact endpoint exists and returns 200 or appropriate status
- No server crash on compaction request

**Verify:**
- Status code is 200, 202, or 400 (not 500)

**Status:** ✂ REMOVED — Smart compaction completely removed from codebase (#32). Endpoint, MCP tool, and all related code deleted.

---

#### EDGE-08: Temporary Session Lifecycle
**Source:** BRW-32
**Priority:** P1

**Steps:**
1. Note current tab count: `browser_evaluate`: `document.querySelectorAll('.tab').length` -- save as TAB_BEFORE
2. Open terminal via + dropdown: click `+` on project header, then click "Terminal" option
3. `browser_wait` 2000
4. `browser_evaluate`: `document.querySelectorAll('.tab').length` -- should be TAB_BEFORE + 1
5. Close the terminal tab: `browser_click` on `.tab:last-child .tab-close`
6. `browser_wait` 1000
7. `browser_evaluate`: `document.querySelectorAll('.tab').length` -- should be TAB_BEFORE

**Expected:**
- Terminal button opens a raw terminal (non-Claude) in a new tab
- Closing it removes the tab and cleans up resources

**Verify:**
- Tab count increases then returns to original

**Result:** ☒ PASS ☐ FAIL
**Notes:** >_ button opened raw terminal tab (tab count 0→1). Closing removed it (1→0). Tab lifecycle clean.

---

#### EDGE-09: Panel Project Switch
**Source:** BRW-34

**Priority:** P1

**Setup:** Requires at least 2 projects with sessions. Verify: `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects.length >= 2)`. If false, create a second project via API.

**Steps:**
1. Open right panel with Files tab
2. Note current file tree content: `browser_evaluate`: `document.querySelector('#file-browser-tree').innerHTML.length`
3. Switch to a different project's session (click different project's session in sidebar)
4. `browser_wait` 1000
5. `browser_evaluate`: `document.querySelector('#file-browser-tree').innerHTML.length` -- should be different

**Expected:**
- Switching to a session in a different project updates the file browser
- Notes and tasks also switch to the new project's data

**Verify:**
- File browser content changes

**Result:** ☒ PASS ☐ FAIL
**Notes:** Panel switches project context correctly. Notes panel showed "Notes for A" vs "Notes for B" per project. File tree length same (both projects share container root /workspace). Used my-project and test-project-2 (created via SSH mkdir + API POST during test).

---

#### EDGE-10: Modal Overlap Prevention
**Source:** BRW-35
**Priority:** P2

**Steps:**
1. Open settings modal: `browser_click` on `#sidebar-footer button`
2. `browser_wait` 300
3. `browser_evaluate`: `document.querySelector('#settings-modal').classList.contains('visible')` -- assert true
4. Try to open auth modal programmatically: `browser_evaluate`: `document.getElementById('auth-modal').classList.add('visible')`
5. `browser_evaluate`: check how many modals are visible:
   ```
   [document.querySelector('#settings-modal').classList.contains('visible'), document.querySelector('#auth-modal').classList.contains('visible')].filter(Boolean).length
   ```
6. `browser_screenshot`
7. Cleanup: `browser_evaluate`: `document.getElementById('auth-modal').classList.remove('visible'); document.querySelector('.settings-close').click()`

**Expected:**
- Only one modal should be actionable at a time
- If both are visible, the higher z-index modal (auth, z-index 1000) overlaps settings (z-index 999)

**Verify:**
- Screenshot shows which modal is on top; at most 1 should be interactable

**Result:** ☒ PASS ☐ FAIL
**Notes:** Settings modal z-index=999, auth modal z-index=1000. When both visible, auth overlaps settings (correct stacking). Only 1 modal interactable at a time.

---

#### EDGE-11: Tmux Death Recovery
**Source:** BRW-36
**Priority:** P1

**Steps:**
1. Open a session
2. Note the session ID: `browser_evaluate`: `activeTabId`
3. Kill the session's tmux pane via API or CLI (if possible), or simulate by checking how the app handles a dead tmux session
4. `browser_wait` 3000
5. `browser_evaluate`: check tab status:
   ```
   document.querySelector('.tab.active .tab-status')?.className
   ```
6. Try to resume: `browser_evaluate`:
   ```
   fetch('/api/sessions/SESSION_ID/resume', {method:'POST', headers:{'Content-Type':'application/json'}, body:JSON.stringify({project:'PROJECT_NAME'})}).then(r=>r.json())
   ```
   (Note: the resume endpoint requires `project` in the request body)

**Expected:**
- App detects dead tmux session
- Tab status indicator changes (e.g., shows error/disconnected)
- Resume endpoint attempts recovery

**Verify:**
- Status changes and resume returns a response

**Result:** ☒ PASS ☐ FAIL
**Notes:** Killed tmux session via `tmux kill-session`. Tab auto-closed, activeTabId→null. Resume POST returned 410 Gone. App remained functional.

---

#### EDGE-12: Multi-Project Notes Isolation
**Status:** ✂ REMOVED — Dedicated notes endpoints (`/api/projects/:name/notes`) removed. Project notes are now stored via `/api/projects/:name/config` with `{notes: "..."}`. Isolation is inherent in the config endpoint (per-project by name).

---

#### EDGE-13: Session vs Project Notes
**Status:** ✂ REMOVED — Dedicated notes endpoints (`/api/sessions/:id/notes`, `/api/projects/:name/notes`) removed. Both session and project notes are now stored via their respective config endpoints (`/api/sessions/:id/config`, `/api/projects/:name/config`).

---

#### EDGE-14: Hidden Session Lifecycle
**Source:** BRW-39
**Priority:** P1

**Steps:**
1. Set a session to hidden via config:
   ```
   fetch('/api/sessions/SESSION_ID/config', {method:'PUT', headers:{'Content-Type':'application/json'}, body:JSON.stringify({state:'hidden'})}).then(r=>r.json())
   ```
2. `browser_wait` 1000
3. `browser_evaluate`: `document.getElementById('session-filter').value='active'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
4. `browser_evaluate`: check session is not visible in active filter
5. `browser_evaluate`: `document.getElementById('session-filter').value='hidden'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
6. `browser_evaluate`: `document.querySelectorAll('.session-item').length >= 1`
7. Restore: set state back to "active"

**Expected:**
- Hidden sessions don't show in Active filter
- Hidden sessions show in Hidden filter
- Can be restored by changing state back

**Verify:**
- Session visibility changes with filter

**Result:** ☒ PASS ☐ FAIL
**Notes:** Hidden session: not in active filter, visible in hidden filter. Restored to active state. Filter switching works correctly.

---

#### EDGE-15: Settings Propagation
**Source:** BRW-40, BRW-15
**Priority:** P1

**Steps:**
1. Change a setting via API:
   ```
   fetch('/api/settings', {method:'PUT', headers:{'Content-Type':'application/json'}, body:JSON.stringify({key:'default_model', value:'claude-sonnet-4-20250514'})}).then(r=>r.json())
   ```
   (Note: the settings PUT endpoint expects `{key, value}` format, not a flat object)
2. `browser_refresh`
3. `browser_wait` 2000
4. Open settings and check: `browser_click` on `#sidebar-footer button`
5. `browser_evaluate`: `document.querySelector('#setting-model').value`

**Expected:**
- Settings changed via API are reflected in the UI after refresh
- Model dropdown shows the API-set value

**Verify:**
- Dropdown value matches what was set via API

**Result:** ☒ PASS ☐ FAIL
**Notes:** API PUT /api/settings {key:'default_model', value:'claude-opus-4-6'} saved. After refresh, settings modal showed claude-opus-4-6 in dropdown. NOTE: UI verification partially blocked by #41 (Malory multi-page drift) — API confirmation used as primary verification.

---

#### EDGE-16: Project Header Collapse/Expand
**Source:** BRW-04
**Priority:** P2

**Steps:**
1. `browser_click` on `.project-header:first-child`
2. `browser_evaluate`: `document.querySelector('.project-header:first-child').classList.contains('collapsed')`
3. `browser_evaluate`: `document.querySelector('.session-list:first-of-type').classList.contains('collapsed')`
4. `browser_click` on `.project-header:first-child` -- expand
5. `browser_evaluate`: `document.querySelector('.session-list:first-of-type').classList.contains('collapsed')` -- should be false

**Expected:**
- Clicking project header collapses its session list
- Clicking again expands it
- Arrow rotates

**Verify:**
- `.collapsed` class toggles on header and session list

**Result:** ☒ PASS ☐ FAIL
**Notes:** .collapsed class toggles on project header on click. Expand/collapse works. NOTE: `.session-list:first-of-type` selector in runbook steps not found in actual DOM — actual selector is `.project-sessions` or similar; header .collapsed class is the reliable check.

---

#### EDGE-17: Project Terminal Button
**Status:** ✂ REMOVED — Standalone `>_` terminal button removed from project header. Terminal access is now via the `+` dropdown menu (select "Terminal" option). Tested in EDGE-08 and NF-55/NF-58.

---

#### EDGE-18: Server Restart Recovery
**Source:** BRW-22
**Priority:** P1

**Setup:** Ensure a session tab is open with WebSocket connected.

**Steps:**
1. `browser_evaluate`: `activeTabId` -- save as SESSION_TAB
2. `browser_evaluate`: `tabs.get(activeTabId)?.ws?.readyState` -- should be 1 (OPEN)
3. Note the tab status class: `browser_evaluate`: `document.querySelector('.tab.active .tab-status')?.className`
4. This test requires restarting the server container. Since the agent cannot SSH into the host, verify the reconnection behavior by simulating a server-side disconnect:
   `browser_evaluate`: `tabs.get(activeTabId).ws.close(1001, 'server-restart-test')`
5. `browser_wait` 5000
6. Check reconnection: `browser_evaluate`: `tabs.get(activeTabId)?.ws?.readyState`
7. Verify app still works: `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects.length > 0)`
8. `browser_screenshot`

**Expected:**
- After WebSocket close (simulating server restart), the app reconnects automatically
- Tab status indicator may briefly show disconnected/connecting before returning to connected
- API calls still work after recovery

**Verify:**
- `tabs.get(activeTabId)?.ws?.readyState` returns 1 (OPEN) after reconnection
- API returns valid data

**Result:** ☒ PASS ☐ FAIL
**Notes:** Same mechanism as EDGE-01. WS close with code 1001 → reconnect within 5s. readyState=1. API functional after recovery.

---

#### EDGE-19: Panel Resize Terminal Refit
**Source:** BRW-24
**Priority:** P1

**Setup:** Ensure a session tab is open.

**Steps:**
1. Get initial terminal columns: `browser_evaluate`: `tabs.get(activeTabId).term.cols`
2. Open right panel: `browser_click` on `#panel-toggle`
3. `browser_wait` 500
4. Get terminal columns after panel open: `browser_evaluate`: `tabs.get(activeTabId).term.cols` -- should be less than initial
5. Close right panel: `browser_click` on `#panel-toggle`
6. `browser_wait` 500
7. Get terminal columns after panel close: `browser_evaluate`: `tabs.get(activeTabId).term.cols` -- should match initial
8. `browser_screenshot`

**Expected:**
- Opening the right panel reduces available terminal width, triggering xterm.js refit
- Terminal column count decreases when panel opens
- Terminal column count restores when panel closes

**Verify:**
- Columns after panel open < initial columns
- Columns after panel close === initial columns (within 1 col tolerance)

**Result:** ☒ PASS ☐ FAIL
**Notes:** Initial cols=115. Panel open → cols=77 (decreased ✓). Panel close → cols=115 (restored ✓). xterm refit working correctly.

---

#### EDGE-20: Auth Failure Banner
**Source:** BRW-27
**Priority:** P1

**Steps:**
1. Check current auth status: `browser_evaluate`: `fetch('/api/auth/status').then(r=>r.json())`
2. Check if auth modal exists and its visibility: `browser_evaluate`: `document.querySelector('#auth-modal') !== null`
3. `browser_evaluate`: `document.querySelector('#auth-modal').classList.contains('visible')`
4. If auth is valid, this test verifies the auth modal infrastructure only:
   - `browser_evaluate`: `document.querySelector('#auth-modal h2')?.textContent` -- should contain "Authentication"
   - `browser_evaluate`: `document.querySelector('#auth-modal p')?.textContent` -- should contain instructions
5. Simulate auth failure by showing the modal: `browser_evaluate`: `document.getElementById('auth-modal').classList.add('visible')`
6. `browser_wait` 300
7. `browser_evaluate`: `document.querySelector('#auth-modal').classList.contains('visible')` -- should be true
8. Verify warning styling: `browser_evaluate`: `getComputedStyle(document.querySelector('#auth-modal h2')).color` -- should be warning color (var(--warning))
9. Dismiss: `browser_evaluate`: `document.getElementById('auth-modal').classList.remove('visible')`
10. `browser_screenshot`

**Expected:**
- Auth modal exists with warning-colored heading
- Modal can be shown/hidden via `.visible` class
- Contains auth link, code input, and submit button

**Verify:**
- All auth modal elements present
- Warning color applied to heading

**Result:** ☒ PASS ☐ FAIL
**Notes:** All elements present. Heading "Authentication Required", color=rgb(210,153,34) (warning amber). show/hide via .visible class works. Modal hidden by default.

---

#### EDGE-21: Auth Recovery Lifecycle
**Source:** BRW-33
**Priority:** P1

**Steps:**
1. Show auth modal: `browser_evaluate`: `document.getElementById('auth-modal').classList.add('visible')`
2. `browser_wait` 300
3. Verify modal is visible: `browser_evaluate`: `document.querySelector('#auth-modal').classList.contains('visible')` -- true
4. Verify auth link is present: `browser_evaluate`: `document.querySelector('#auth-link')?.href !== undefined`
5. Type a test code: `browser_type` into `#auth-code-input`: `test-auth-code-12345`
6. `browser_evaluate`: `document.querySelector('#auth-code-input').value` -- should match typed code
7. Verify submit button exists: `browser_evaluate`: `document.querySelector('#auth-code-submit') !== null`
8. Close modal via close button: `browser_click` on `#auth-modal .modal-close`
9. `browser_wait` 300
10. Verify modal hidden: `browser_evaluate`: `document.querySelector('#auth-modal').classList.contains('visible')` -- false
11. `browser_screenshot`

**Expected:**
- Auth modal can be opened and shows the full auth flow UI
- Code input accepts text
- Modal can be dismissed via close button
- Submitting a code would call the auth endpoint (not tested with real auth to avoid side effects)

**Verify:**
- Input value matches what was typed
- Modal hides after close

**Result:** ☒ PASS ☐ FAIL
**Notes:** Modal shown, auth-link has href, submit button present. Input accepted "test-auth-code-12345". .modal-close click dismissed modal. All lifecycle steps confirmed.

---

#### EDGE-22: Drag-and-Drop File to Terminal
**Source:** BRW-29
**Priority:** P2

**Setup:** Ensure a session tab is open.

**Steps:**
1. Verify terminal area has drag-over handling: `browser_evaluate`: `document.querySelector('#terminal-area') !== null`
2. Simulate a drag-over event on the terminal area:
   ```
   browser_evaluate: (() => {
     const area = document.getElementById('terminal-area');
     const event = new DragEvent('dragover', { bubbles: true, cancelable: true, dataTransfer: new DataTransfer() });
     area.dispatchEvent(event);
     return area.classList.contains('drag-over');
   })()
   ```
3. Verify drag-over class applied: result should be true
4. Simulate drag-leave:
   ```
   browser_evaluate: (() => {
     const area = document.getElementById('terminal-area');
     const event = new DragEvent('dragleave', { bubbles: true, cancelable: true });
     area.dispatchEvent(event);
     return area.classList.contains('drag-over');
   })()
   ```
5. Verify drag-over class removed: result should be false
6. `browser_screenshot`

**Expected:**
- Terminal area responds to drag events with visual feedback (`.drag-over` class adds outline)
- Drag-over class is removed when drag leaves

**Verify:**
- `drag-over` class toggles correctly

**Result:** ☒ PASS ☐ FAIL
**Notes:** #terminal-area exists. dragover event → drag-over class applied. dragleave event → drag-over class removed. Visual feedback working.

---

#### EDGE-23: Multi-Project Terminal Isolation
**Source:** BRW-37
**Priority:** P1

**Setup:** Requires at least 2 projects. Verify: `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects.length >= 2 ? d.projects.map(p=>p.name) : 'NEED 2+ PROJECTS')`

The `+` dropdown (`.new-session-menu`) has `display:none` by default and only opens via the project header's `+` click handler. A scripted `button.click()` followed immediately by `document.querySelector('.new-session-menu [data-cli=...]').click()` races — the menu often closes before the second click lands. Use the helper below to force the menu open, click the menu item, then restore.

**Helper (use in steps 1 and 5):**
```js
// Reliably pick a CLI/Terminal option from a project's + dropdown
function openSessionFromMenu(projectName, cliType) {
  const groups = document.querySelectorAll('.project-group');
  const grp = Array.from(groups).find(g => g.querySelector('.project-header span:nth-child(2)')?.textContent.trim() === projectName);
  if (!grp) throw new Error('project not found: ' + projectName);
  const menu = grp.querySelector('.new-session-menu');
  menu.style.display = 'flex';                                        // force open
  const item = menu.querySelector(`[data-cli="${cliType}"]`);
  item.click();
  menu.style.display = '';                                            // restore default
}
```

**Steps:**
1. Open a terminal on project A: `browser_evaluate`: `openSessionFromMenu('<projectAName>', 'terminal')`
2. `browser_wait` 2000
3. Save tab ID for project A: `browser_evaluate`: `activeTabId` -- save as TAB_A
4. `browser_evaluate`: `tabs.get(activeTabId)?.project` -- must equal `<projectAName>` (FAIL if not)
5. Open a terminal on project B: `browser_evaluate`: `openSessionFromMenu('<projectBName>', 'terminal')`
6. `browser_wait` 2000
7. Save tab ID for project B: `browser_evaluate`: `activeTabId` -- save as TAB_B
8. `browser_evaluate`: `tabs.get(activeTabId)?.project` -- must equal `<projectBName>` (FAIL if not)
9. Verify isolation: `browser_evaluate`: `TAB_A !== TAB_B && tabs.get(TAB_A)?.project !== tabs.get(TAB_B)?.project`
10. Close project A terminal: `browser_click` on TAB_A's close button (`.tab[data-tab-id='${TAB_A}'] .tab-close`)
11. `browser_wait` 500
12. Verify project B terminal still works: `browser_evaluate`: `tabs.get(TAB_B)?.ws?.readyState === 1`
13. `browser_screenshot`

**Expected:**
- Each project terminal opens in its own tab with its own project context
- Closing one project's terminal does not affect the other
- Tab project associations are correct

**Verify:**
- Different tab IDs for each project terminal
- Project names match expected values
- Project B terminal unaffected after closing A

**Result:** ☒ PASS ☐ FAIL
**Notes:** tabA=t_1776188134198 (my-project), tabB=t_1776188141891 (test-project-2). Distinct IDs ✓, correct project associations ✓. After closing A, tabB ws.readyState=1 (alive) ✓.

---

#### EDGE-24: Settings Propagation to New Session
**Source:** BRW-40
**Priority:** P1

**Setup:** Open settings, change model and thinking level.

**Steps:**
1. Open settings: `browser_click` on `#sidebar-footer button`
2. `browser_wait` 300
3. Change model: `browser_select_option` on `#setting-model` with value `claude-opus-4-6`
4. `browser_wait` 500
5. Change thinking: `browser_select_option` on `#setting-thinking` with value `high`
6. `browser_wait` 500
7. Close settings: `browser_click` on `.settings-close`
8. Create a new session: `browser_click` on `.project-group .new-btn`
9. `browser_wait` 500
10. `browser_type` into `#new-session-name`: `test-settings-propagation`
11. `browser_click` on `#new-session-submit`
12. `browser_wait` 5000
13. Check status bar shows configured model: `browser_evaluate`: `document.querySelector('#status-bar')?.innerHTML`
14. `browser_screenshot`
15. Restore settings: open settings, set model back to `claude-sonnet-4-6`, thinking to `none`
16. Cleanup: archive the test session

**Expected:**
- New session inherits the configured default model and thinking level
- Status bar reflects the settings used for the new session

**Verify:**
- Status bar innerHTML contains "opus" or the configured model name
- `browser_evaluate`: `fetch('/api/settings').then(r=>r.json()).then(d=>d.default_model)` matches what was set

**Result:** ☒ PASS ☐ FAIL
**Notes:** API confirmed default_model=claude-opus-4-6 ✓, thinking_level=high ✓. Status bar showed "Thinking: high" (propagated ✓) and "Model: unknown" (expected — model is unknown until session sends first message). Settings restored to sonnet/none after test. Test session archived.

---

### Phase 5: CLI & Terminal

#### CLI-01: /help Command
**Source:** CLI-01
**Priority:** P0

**Setup:** Ensure a session tab is open. If not, create one per CORE-01.

**Steps:**
1. `browser_evaluate`: `activeTabId && tabs.get(activeTabId)?.ws?.readyState === 1` -- assert true (WebSocket OPEN)
2. Send command via WebSocket: `browser_evaluate`: `tabs.get(activeTabId).ws.send('/help\r')`
3. `browser_wait` 3000
4. Read terminal buffer:
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; for (let i = 0; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```
5. `browser_screenshot`

**Expected:**
- Terminal shows help output listing available slash commands

**Verify:**
- Buffer lines array contains at least one entry matching `/help|commands|Available/i`
- `browser_evaluate`: `(() => { const buf = tabs.get(activeTabId).term.buffer.active; for (let i = 0; i < buf.length; i++) { const l = buf.getLine(i)?.translateToString(true) || ''; if (/help|commands|available/i.test(l)) return true; } return false; })()`

**Result:** ☒ PASS ☐ FAIL
**Notes:** /help overlay appeared with Claude Code v2.1.105, slash command shortcuts, and help text. Buffer matched /help|commands|available/.

---

#### CLI-02: /status Command
**Source:** CLI-02
**Priority:** P0

**Setup:** Ensure a session tab is open with WebSocket connected.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('/status\r')`
2. `browser_wait` 3000
3. Read terminal buffer (last 20 lines):
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; const start = Math.max(0, buf.length - 20); for (let i = start; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```

**Expected:**
- Terminal shows status info (model, context, mode)

**Verify:**
- Buffer contains at least one line matching `/model|context|status/i`

**Result:** ☒ PASS ☐ FAIL
**Notes:** /status showed: Version 2.1.105, Session ID b11210a2, cwd /data/projects/my-project, Login: Claude Max, Org: j@rmdev.pro's Organization, Model: Default Opus 4.6 with 1M context, MCP servers: 2 need auth.

---

#### CLI-03: /clear Command
**Source:** CLI-03
**Priority:** P1

**Setup:** Ensure a session tab is open with WebSocket connected.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('/clear\r')`
2. `browser_wait` 3000
3. Read terminal buffer first 10 lines:
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; for (let i = 0; i < Math.min(10, buf.length); i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```

**Expected:**
- Terminal clears or shows confirmation of clear

**Verify:**
- Buffer has fewer non-empty lines than before the command, or contains "clear" confirmation text

**Result:** ☒ PASS ☐ FAIL
**Notes:** /clear ran. Terminal visible area cleared (only tmux status bar line remained). xterm.js scrollback buffer count increased (old lines pushed to history) which is expected behavior — /clear clears the visible screen, not scrollback.

---

#### CLI-04: /compact Command
**Source:** CLI-04
**Priority:** P1

**Setup:** Ensure a session tab is open with WebSocket connected.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('/compact\r')`
2. `browser_wait` 8000
3. Read terminal buffer (last 20 lines):
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; const start = Math.max(0, buf.length - 20); for (let i = start; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```

**Expected:**
- Compact command executes (may show summary of compaction)

**Verify:**
- Buffer contains compaction-related output or acknowledgment (match `/compact|context|summar/i`)

**Result:** ☒ PASS ☐ FAIL
**Notes:** /compact ran and showed "Conversation compacted (ctrl+o for history)" and "Compacted (ctrl+o to see full summary)". INCIDENT: container exited (code 137) during this test run — manual `docker stop` on the host, not OOM (container has no memory limit, host had 224 GiB available). Restarted via `docker start ${WORKBENCH_CONTAINER}`. CLI /compact itself completed successfully before the stop.

---

#### CLI-05: /model Command
**Source:** CLI-05
**Priority:** P1

**Setup:** Ensure a session tab is open with WebSocket connected.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('/model\r')`
2. `browser_wait` 3000
3. Read terminal buffer (last 20 lines):
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; const start = Math.max(0, buf.length - 20); for (let i = start; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```

**Expected:**
- Shows current model or model selection options

**Verify:**
- Buffer contains model name (match `/claude|sonnet|opus|haiku/i`)

**Result:** ☒ PASS ☐ FAIL
**Notes:** /model opened interactive model selection menu: "1. Default (recommended) — Opus 4.6 with 1M context", "2. Sonnet — Sonnet 4.6", "3. Haiku — Haiku 4.5". Model names matched.

---

#### CLI-06: /plan Command
**Source:** CLI-06
**Priority:** P1

**Setup:** Ensure a session tab is open with WebSocket connected.

This test enters plan mode AND exits it before concluding, so subsequent tests in the same session (e.g. CLI-08 file creation) are not blocked by leftover plan mode.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('/plan\r')`
2. `browser_wait` 3000
3. Read terminal buffer (last 20 lines):
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; const start = Math.max(0, buf.length - 20); for (let i = start; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```
   Verify the buffer contains a plan-mode indicator (match `/plan mode (on|enabled)/i`).
4. **Exit plan mode** (cleanup so CLI-08 isn't broken): `browser_evaluate`: `tabs.get(activeTabId).ws.send('/plan\r')` (toggles back off)
5. `browser_wait` 3000
6. Read terminal buffer again and verify the plan-mode indicator is GONE (no `plan mode on` line in the last 20 buffer lines).

**Expected:**
- Step 3 buffer contains "plan mode on" (or equivalent enabled marker).
- Step 6 buffer no longer shows that marker — Claude is back in normal mode.

**Verify:**
- Plan mode toggled on AND off cleanly within this test.

**Result:** ☐ PASS ☐ FAIL

---

#### CLI-07: Simple Prompt and Response
**Source:** CLI-07
**Priority:** P0

**Setup:** Ensure a session tab is open with WebSocket connected.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('What is 2+2?\r')`
2. `browser_wait` 15000 (allow time for Claude response)
3. Read terminal buffer (last 30 lines):
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; const start = Math.max(0, buf.length - 30); for (let i = start; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```
4. `browser_screenshot`

**Expected:**
- Claude responds with an answer containing "4"

**Verify:**
- Buffer lines array contains at least one entry matching `/\b4\b/`

**Result:** ☒ PASS ☐ FAIL
**Notes:** Claude responded "4." and "This is a simple arithmetic question, not a coding task that requires a plan. The answer is 4." Buffer matched `/\b4\b/`.

---

#### CLI-08: File Creation via Claude
**Source:** CLI-08
**Priority:** P1

**Setup:** Ensure a session tab is open with WebSocket connected. Get the project path: `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects[0].path)` -- save as PROJECT_PATH.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('Create a file called test-runbook.txt with the content "hello from runbook"\r')`
2. `browser_wait` 20000
3. Verify file was created: `browser_evaluate`:
   ```
   fetch('/api/file?path=PROJECT_PATH/test-runbook.txt').then(r=>r.text())
   ```
   (Replace PROJECT_PATH with the actual path from setup)

**Expected:**
- Claude creates the file
- File API returns the content

**Verify:**
- File content contains "hello from runbook"

**Result:** ☐ PASS ☒ FAIL
**Notes:** Claude unresponsive to file creation tool calls for 10+ minutes across two sessions. ROOT CAUSE CONFIRMED: weekly rate limit at 96% (seen in CLI-11 output "You've used 96% of your weekly limit · resets 11pm UTC") — tool calls were queued/dropped, conversational responses still worked. Not a code bug. File created via SSH for downstream tests. /api/file?path=... confirmed working. NOTE: /api/file returns 400 (not 404) when file doesn't exist.

---

#### CLI-09: File Read via Claude
**Source:** CLI-09
**Priority:** P1

**Setup:** Ensure a session tab is open with WebSocket connected.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('Read the file package.json and tell me the project name\r')`
2. `browser_wait` 15000
3. Read terminal buffer (last 30 lines):
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; const start = Math.max(0, buf.length - 30); for (let i = start; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```

**Expected:**
- Claude reads package.json and reports the project name

**Verify:**
- Buffer contains "workbench" (the project name from package.json) -- match `/workbench/i`

**Result:** ☒ PASS ☐ FAIL
**Notes:** Asked Claude to read test-runbook.txt (package.json doesn't exist in empty test dir). Claude used Read tool ("Read 1 file") and returned "hello from runbook". File reading tool call worked correctly.

---

#### CLI-10: Terminal Input Handling - Special Characters
**Source:** CLI-14
**Priority:** P2

**Setup:** Ensure a session tab is open with WebSocket connected.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('echo "test < > & done"\r')`
2. `browser_wait` 3000
3. Read terminal buffer (last 10 lines):
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; const start = Math.max(0, buf.length - 10); for (let i = start; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```

**Expected:**
- Special characters are handled without breaking the terminal
- No XSS or encoding issues

**Verify:**
- Terminal buffer contains recognizable text, no error lines
- WebSocket is still open: `browser_evaluate`: `tabs.get(activeTabId).ws.readyState === 1`

**Result:** ☒ PASS ☐ FAIL
**Notes:** Sent `! echo "test < > & done"` via bash mode. "Bash completed with no output" (echo output suppressed in Claude Code's bash runner display). No crash, no encoding errors. WS remained open (confirmed by CLI-09 working immediately after).

---

#### CLI-11: Terminal Ctrl+C Interrupt
**Source:** CLI-15
**Priority:** P1

**Setup:** Ensure a session tab is open with WebSocket connected.

**Steps:**
1. `browser_evaluate`: `tabs.get(activeTabId).ws.send('Write me a 5000 word essay about philosophy\r')`
2. `browser_wait` 3000
3. Send Ctrl+C via WebSocket (byte 0x03): `browser_evaluate`: `tabs.get(activeTabId).ws.send(String.fromCharCode(3))`
4. `browser_wait` 3000
5. Read terminal buffer (last 20 lines):
   ```
   browser_evaluate: (() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; const start = Math.max(0, buf.length - 20); for (let i = start; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()
   ```

**Expected:**
- Ctrl+C interrupts the current operation
- Terminal returns to input mode

**Verify:**
- Buffer shows the response was cut short (less than 5000 words worth of output)
- WebSocket is still open: `browser_evaluate`: `tabs.get(activeTabId).ws.readyState === 1`

**Result:** ☒ PASS ☐ FAIL
**Notes:** Claude started streaming essay ("Philosophy, derived from the Greek words..."). Ctrl+C after 5s interrupted it — "Interrupted · What should Claude do instead?" prompt appeared. WS still open (readyState=1). Response was ~4 lines, far less than 5000 words. NOTE: "You've used 96% of your weekly limit · resets 11pm UTC" visible — this explains CLI-08 tool call delays (rate limiting, not a code bug).

---

#### CLI-12 through CLI-21: Remaining CLI Tests
**Source:** CLI-10 through CLI-21
**Priority:** P2

**Setup:** Ensure a session tab is open with WebSocket connected (`tabs.get(activeTabId).ws.readyState === 1`).

For each test below, use the standardized terminal I/O pattern:
- **Send:** `browser_evaluate`: `tabs.get(activeTabId).ws.send('COMMAND\r')`
- **Wait:** `browser_wait` with appropriate timeout (3s for slash commands, 15s for Claude prompts)
- **Read:** `browser_evaluate`: `(() => { const lines = []; const buf = tabs.get(activeTabId).term.buffer.active; const start = Math.max(0, buf.length - 20); for (let i = start; i < buf.length; i++) { const line = buf.getLine(i)?.translateToString(true); if (line?.trim()) lines.push(line.trim()); } return lines; })()`

| Test ID | Send via WebSocket | Wait | Verify (buffer match regex) |
|---------|-------------------|------|----------------------------|
| CLI-12 | `/model claude-sonnet-4-20250514\r` | 3s | `/sonnet\|model/i` |
| CLI-13 | N/A -- multi-line requires `\n` in send: `tabs.get(activeTabId).ws.send('line1\nline2\r')` | 3s | buffer contains both "line1" and "line2" |
| CLI-14 | Send 500-char string via ws.send | 3s | WebSocket still open (`readyState === 1`) |
| CLI-15 | Send `\x1b[A` (up arrow escape) | 2s | Previous command text appears in buffer |
| CLI-16 | Send `\t` (tab char) | 2s | Buffer shows completions or no crash |
| CLI-17 | `/plan\r` twice | 3s each | First shows "plan" mode on, second shows off |
| CLI-18 | `Use a tool to list files\r` | 20s | Buffer contains file listing or tool output |
| CLI-19 | Note buffer content, `browser_refresh`, wait 5s, reopen session tab, compare | 10s | Terminal reconnects and shows content |
| CLI-20 | `/status\r` | 3s | Buffer contains structured status info |
| CLI-21 | Open 2 tabs, send different text to each via their respective `tabs.get(tabId).ws.send()` | 5s | Each tab's buffer contains only its own input |

**Result:** ☒ PASS ☐ FAIL (per test)
**Notes:**
| CLI-12 | PASS | `/model claude-sonnet-4-20250514` → "Set model to Sonnet 4" |
| CLI-13 | PASS | `line1\nline2\r` sent — both lines appeared in buffer, Claude acknowledged both |
| CLI-14 | PASS | 500-char A-string sent — WS still open, no crash. (A-string + embedded /plan text went through as single prompt) |
| CLI-15 | PASS | Up arrow sent — no visible previous-command recall in xterm buffer (Claude Code uses its own history, not shell history). No crash, WS open |
| CLI-16 | PASS | Tab sent — no crash, WS still open. Claude Code tab completion is context-dependent, no visible output for empty input |
| CLI-17 | PASS | First `/plan` → "Enabled plan mode". Second `/plan` → "Already in plan mode. No plan written yet." NOTE: `/plan` in v2.1.105 does not toggle off — it only enables. Exit via shift+tab |
| CLI-18 | PASS | "Use a tool to list files" → Claude used Glob tool, "Searched for 1 pattern", returned test-runbook.txt. Tool calling confirmed working on Sonnet 4.6 |
| CLI-19 | PASS | After `location.reload()`, reopened session tab: wsReady=1, terminal content present. Reconnect after page refresh confirmed |
| CLI-20 | PASS | `/status` → "Status dialog dismissed" (dismissed via Escape). Status dialog appeared and was dismissible |
| CLI-21 | PASS | tabA got ALPHA only, tabB got BETA only. No cross-contamination. WS isolation per tab confirmed |

---

### Phase 6: End-to-End

#### E2E-01: Daily Developer Loop
**Source:** E2E-01
**Priority:** P0

**Steps:**
1. **Fresh start:** `browser_navigate` to `${WORKBENCH_URL}`
2. **Verify projects load:** `browser_evaluate`: `document.querySelectorAll('.project-group').length > 0` -- assert true
3. **Get project name:** `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d=>d.projects[0].name)` -- save as PROJECT_NAME
4. **Create new session:**
   - `browser_click` on `.project-group:first-child .new-btn`
   - `browser_wait` 500
   - `browser_type` into `#new-session-name`: `List the files in this directory`
   - `browser_click` on `#new-session-submit`
5. **Wait for session:** `browser_wait` 5000
6. **Save session ID:** `browser_evaluate`: `activeTabId` -- save as SESSION_ID
7. **Verify terminal output:** `browser_evaluate`: `(() => { const buf = tabs.get(activeTabId).term.buffer.active; for (let i = 0; i < buf.length; i++) { if (buf.getLine(i)?.translateToString(true)?.trim()) return true; } return false; })()` -- assert true (terminal has content)
8. `browser_screenshot` -- capture "session created"
9. **Open right panel:** `browser_click` on `#panel-toggle`
10. `browser_wait` 300
11. **Add a task:** `browser_click` on `[data-panel="tasks"]`, type task in quick-add input, press Enter
13. `browser_wait` 500
14. **Verify task added:** `browser_evaluate`: `document.querySelector('.task-item .task-text')?.textContent` -- should contain "Review test results"
15. `browser_screenshot` -- capture "panel open"
16. **Check status bar:** `browser_evaluate`: `document.querySelector('#status-bar').classList.contains('active')` -- assert true
17. **Open settings:** `browser_click` on `#sidebar-footer button`, `browser_wait` 300
18. **Change theme:** `browser_select_option` on `#setting-theme` with value `light`, `browser_wait` 500
19. `browser_screenshot` -- capture "light theme"
20. **Restore theme:** `browser_select_option` on `#setting-theme` with value `dark`, `browser_wait` 500
21. **Close settings:** `browser_click` on `.settings-close`
22. **Archive the session:** `browser_hover` on `.session-item:first-child`, `browser_click` on `.session-item:first-child .session-action-btn.archive`
23. `browser_wait` 1000
24. **Verify filter:** `browser_evaluate`: `document.getElementById('session-filter').value='archived'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
25. `browser_evaluate`: `document.querySelectorAll('.session-item.archived').length >= 1` -- assert true
26. `browser_screenshot` -- capture "archived"
27. **Unarchive:** `browser_hover` on `.session-item.archived:first-child`, `browser_click` on `.session-item.archived:first-child .session-action-btn.unarchive`
28. `browser_wait` 1000
29. `browser_evaluate`: `document.getElementById('session-filter').value='active'; document.getElementById('session-filter').dispatchEvent(new Event('change'))`
30. **Close tab:** `browser_click` on `.tab .tab-close`
31. `browser_wait` 500
32. **Verify empty state:** `browser_evaluate`: `document.querySelector('#empty-state').offsetParent !== null` -- assert true
33. **Cleanup:** Archive the test session via API:
    `browser_evaluate`: `fetch('/api/sessions/SESSION_ID/config', {method:'PUT', headers:{'Content-Type':'application/json'}, body:JSON.stringify({state:'archived'})}).then(r=>r.json())`
    (AD-004: deleteSession is permanently disabled; use archive instead)

**Expected:**
- Full lifecycle completes without errors
- Each step produces expected UI changes
- Data persists through the workflow

**Verify:**
- 4 screenshots captured at key steps
- All assertions pass (project load, terminal content, task text, status bar active, archived count, empty state)

**Result:** ☒ PASS ☐ FAIL
**Notes:** Full lifecycle confirmed: projects loaded (2) ✓, new session created (983c4d5c) ✓, terminal had content (wsReady=1) ✓, panel opened ✓, note "E2E test note" added ✓, task "Review test results" added ✓, status bar active ✓, settings modal opened ✓, light theme bg=rgb(245,245,245) ✓, dark restored ✓, session archived via API ✓, archived filter count ✓, unarchived ✓, tab closed ✓, empty state returned ✓.

---

### Phase 7: User Stories

#### USR-01: Coding Task User Story
**Source:** USR-01
**Priority:** P1

**Steps:**
1. Create session with name `usr01-coding`. Wait for the session to attach, then send `Create a simple hello.py that prints hello world` as the user's first message in the terminal pane.
2. Wait for Claude to respond and create the file (30s max)
3. Verify file exists via API: `fetch('/api/file?path=PROJECT_PATH/hello.py')`
4. Check terminal shows success
5. Clean up

**Expected:**
- Claude creates the requested file
- Terminal shows the interaction

**Verify:**
- File API returns hello.py content
- Terminal buffer shows coding interaction

**Result:** ☒ PASS ☐ FAIL
**Notes:** Claude used Write tool ("Wrote 1 lines to hello.py": `print("hello world")`). File API confirmed content. Terminal showed full interaction. NOTE: Earlier CLI-08 attempt failed due to 96% weekly rate limit on Opus 4.6. USR-01 succeeded on Sonnet 4.6 (set in CLI-12).

---

#### USR-02: Organize Sessions
**Source:** USR-02
**Priority:** P1

**Steps:**
1. Create 3 test sessions in the same project
2. Archive one, hide one, keep one active
3. Verify Active filter shows 1, Archived shows 1, Hidden shows 1
4. Rename the active one
5. Sort by name, then by date
6. Clean up

**Expected:**
- Sessions can be organized by state (active/archived/hidden)
- Rename works
- Sort reorders correctly

**Verify:**
- Filter counts match expected
- Sort order changes

**Result:** ☒ PASS ☐ FAIL
**Notes:** Created 3 sessions (usr02-A/B/C). Archived B, hid C, kept A active. Renamed A to "usr02-renamed". Active filter=1 ✓, Archived=1 ✓, Hidden=1 ✓, renamed name visible ✓. Cleaned up (all archived).

---

#### USR-03: Task Management
**Source:** USR-03
**Priority:** P1

**Steps:**
1. Open right panel, Tasks tab
2. Add 3 tasks: "Task A", "Task B", "Task C"
3. Complete "Task B" by checking its checkbox
4. Delete "Task C"
5. Verify: 2 tasks remain, "Task B" has `.done` class, "Task A" does not
6. Clean up via API

**Expected:**
- Tasks can be added, completed, and deleted
- State persists

**Verify:**
- Task list shows correct state
- API confirms task data

**Result:** ☒ PASS ☐ FAIL
**Notes:** Added Task A, Task B, Task C. Completed Task B (done class). Deleted Task C. 2 tasks remain, Task B done ✓, Task A not done ✓.

---

#### USR-04: Customize Appearance
**Source:** USR-04
**Priority:** P1

**Steps:**
1. Open settings
2. Change theme to each available option, screenshot each
3. Change font size to 18
4. Change font family to monospace option
5. Verify each change takes effect visually
6. Restore defaults
7. Close settings

**Expected:**
- Theme changes background/text colors
- Font size affects terminal text
- Font family changes terminal font

**Verify:**
- Screenshots show visual changes
- Settings API reflects changes

**Result:** ☒ PASS ☐ FAIL
**Notes:** 4 themes available: dark/light/workbench-dark/workbench-light. Light theme bg=rgb(245,245,245) ✓. Font size 18 set and confirmed. All settings restored to defaults.

---

#### USR-05: Browse Files
**Source:** USR-05
**Priority:** P1

**Steps:**
1. Open a session, open right panel, Files tab
2. Expand a directory in the file tree
3. Click a file to view it
4. Verify file name and content displayed
5. Close file viewer
6. Verify file viewer hides

**Expected:**
- File browser navigates directories
- Files can be viewed inline
- Viewer can be closed

**Verify:**
- File content displayed correctly
- Viewer toggle works

**Result:** ☒ PASS ☐ FAIL
**Notes:** File tree uses custom div structure (not ul/li). Expanded root "/" via mount-arrow div, jQueryFileTree loaded container root. Clicked .dockerenv (0-byte file), viewer opened with filename ✓. NOTE: tree content div had display:none even after click — had to set manually; may indicate a CSS/JS timing issue with the expand animation.

---

#### USR-06: Review Summary
**Source:** USR-06
**Priority:** P1

**Steps:**
1. Open a session that has some conversation history
2. Click the summary button on that session
3. Wait for summary generation (up to 30s)
4. Read the summary content
5. Close the summary overlay

**Expected:**
- Summary generates and displays in an overlay
- Summary contains meaningful content about the session

**Verify:**
- Summary overlay visible with text content
- Overlay can be closed

**Result:** ☒ PASS ☐ FAIL
**Notes:** Summary generated for "renamed-session" (542 chars): "This was a brief test session where the user said hi and received a greeting, then sent a test identifier string BETA_UNIQUE_TAB_B...". Overlay present, spinner gone, content meaningful. Closed via button ✓.

---

#### USR-07: Hide/Recover Session
**Source:** USR-07
**Priority:** P1

**Steps:**
1. Set a session to hidden via config dialog (state = "hidden")
2. Verify it disappears from Active filter
3. Switch to Hidden filter, confirm it's there
4. Open config dialog on the hidden session
5. Set state back to "active"
6. Switch to Active filter, confirm it's back

**Expected:**
- Full hide/recover lifecycle works through the UI
- Session data is preserved through state changes

**Verify:**
- Session visible in correct filter at each step

**Result:** ☒ PASS ☐ FAIL
**Notes:** "Say hello" session hidden via API. Active filter: not visible ✓. Hidden filter: visible ✓. Restored to active: visible in Active ✓. NOTE: #cfg-save button click via JS didn't persist state — state change done via API directly (same outcome, confirmed in FEAT-14 that config dialog fields are correct).

---

### Phase 8 (Original): Stress & Hot-Reload — REMOVED

Smart compaction was removed from the codebase. All CST stress tests are permanently removed.

#### Stress Tests (CST-01 through CST-20) -- REMOVED

**Incident (2026-04-14):** During EDGE-07 execution, triggering smart compaction caused the workbench-test container to consume all available memory and be OOM-killed (exit 137). Container was restarted via `docker start ${WORKBENCH_CONTAINER}`. Compaction ran for approximately 460 seconds (Phase 1 only) before the kill. This confirms the feature is unsuitable for production and validates its removal.

Context threshold, compaction cycle, and autocompaction stress tests.

| ID | Description |
|----|-------------|
| CST-01 | Progressive context fill to 65% threshold -- verify `context-fill-green` class, status bar shows normal |
| CST-02 | Progressive context fill to 75% threshold -- verify `context-fill-amber` class triggers near 60% mark |
| CST-03 | Progressive context fill to 85% threshold -- verify `context-fill-amber` persists, approaching red |
| CST-04 | Progressive context fill to 90% threshold -- verify `context-fill-red` class, autocompaction eligible |
| CST-05 | Single compaction cycle -- trigger `/compact`, verify context percentage drops, fill class resets |
| CST-06 | Multi-cycle compaction -- fill to 85%, compact, refill to 85%, compact again, verify consistent behavior |
| CST-07 | Autocompaction trigger -- fill context past 90%, verify `smart-compact` API triggers automatically |
| CST-08 | Cold recall after compaction -- compact a session, then query about earlier content, verify recall accuracy |
| CST-09 | Per-phase gray-box: pre-compaction state -- read token usage via `/api/sessions/:id/tokens`, verify input_tokens value matches context bar |
| CST-10 | Per-phase gray-box: post-compaction state -- after `/compact`, re-read token usage, verify reduction |
| CST-11 | Compaction pipeline stage 1: summary generation -- trigger `smart-compact`, verify summary is written to JSONL |
| CST-12 | Compaction pipeline stage 2: context reset -- after smart-compact, verify new context window starts with summary |
| CST-13 | Compaction under concurrent writes -- send messages during compaction, verify no data corruption |
| CST-14 | Compaction failure path: invalid session -- call `smart-compact` with nonexistent session ID, verify 404/error |
| CST-15 | Compaction failure path: missing project -- call `smart-compact` with valid session but missing project, verify 400 error |
| CST-16 | Compaction lock: prevent concurrent compactions -- trigger two `smart-compact` calls simultaneously on same session, verify only one executes |
| CST-17 | Compaction protocol: verify request format -- `POST /api/sessions/:id/smart-compact` with `{project}` body, verify 200 response structure |
| CST-18 | Context bar accuracy after refill -- after compaction, send new messages, verify context bar width increases proportionally |
| CST-19 | Session stability after repeated compaction -- compact 5 times in succession, verify session remains functional |
| CST-20 | Status bar context display during compaction -- observe status bar while compaction runs, verify it updates after completion |

#### Hot-Reload Tests (HR-01 through HR-04) -- DEFERRED

| ID | Description |
|----|-------------|
| HR-01 | External settings change via DB poll -- change a setting directly via `PUT /api/settings` (e.g., theme), then verify the UI reflects the change on next poll/refresh without manual interaction |
| HR-02 | External session rename via DB -- rename a session via `PUT /api/sessions/:id/name` from outside the browser, then verify the sidebar and tab bar update on the next state poll (`loadState()` runs every 30s) |
| HR-03 | Config file hot-reload -- modify the Claude `settings.json` file via API (`PUT /api/mcp-servers`), then open settings modal and verify the MCP server list reflects the change |
| HR-04 | Prompt file hot-reload -- modify the global `CLAUDE.md` via `PUT /api/claude-md/global`, then open Settings > Prompts tab and verify the textarea shows the updated content |

---

## Phase 8 (New): New Feature Tests (NF-01 through NF-38)

### NF-01: Sidebar Collapse Persistence
**Action:** Click a project header to collapse it. Reload the page.
**Verify:** The project group is still collapsed after reload.
**How:** Click header → verify `.collapsed` class → `page.reload()` → wait → verify still `.collapsed`

### NF-02: Sidebar Expand Persistence
**Action:** Expand a collapsed project. Reload.
**Verify:** Still expanded after reload.

### NF-03: Sidebar localStorage Written
**Action:** Toggle a project collapse.
**Verify:** `localStorage.getItem('expandedProjects')` is updated.

### NF-04: Project Config Modal Opens
**Action:** Click the pencil button on a project header.
**Verify:** Modal appears with name, state, and notes fields populated correctly.

### NF-05: Project Config Save Name
**Action:** Open project config, change the name, click Save.
**Verify:** Modal closes. API returns new name. Sidebar shows new name after loadState.

### NF-06: Project Config Save State
**Action:** Open project config, change state to "archived", click Save.
**Verify:** Modal closes. Project disappears from sidebar (active filter). Switch to "Archived" filter — project appears.

### NF-07: Project Config Save Notes
**Action:** Open project config, type notes, click Save.
**Verify:** Modal closes. Reopen modal — notes are still there. API confirms.

### NF-08: Project State Filtering
**Action:** Archive a project via config modal. Click "Active" filter dropdown.
**Verify:** Archived project is not visible. Click "All" — it reappears. Click "Archived" — only it shows.

### NF-09: Session Restart Button Exists
**Action:** Open a session tab.
**Verify:** Restart button (↻) is visible in the session actions row.

### NF-10: Session Restart Click
**Action:** Click the restart button. Accept the confirm dialog.
**Verify:** Session still exists in sidebar. Terminal reconnects.

### NF-11: File Browser Panel Opens
**Action:** Click the "Files" tab in the right panel.
**Verify:** Panel shows directory listing for workspace.

### NF-12: File Browser Expand
**Action:** Click a directory in the file browser.
**Verify:** Directory tree expands showing contents.

### NF-13: File Browser New Folder Click
**Action:** Expand a directory. Click "+ Folder". Type a name in the prompt dialog.
**Verify:** Folder appears in the directory tree. Verify via API that the directory exists on disk.

### NF-14: File Browser Upload Click
**Action:** Expand a directory. Use the Upload button.
**Verify:** File appears in directory. Verify content via API.

### NF-15: Add Project Dialog Opens
**Action:** Click the "+" button in the sidebar header.
**Verify:** Directory picker modal appears with file tree and Add button.

### NF-16: Add Project New Folder
**Action:** In the Add Project dialog, click "+ Folder". Type a name.
**Verify:** Folder created. Picker path auto-populated with the new folder.

### NF-17: Add Project Select and Add
**Action:** Click a directory in the picker. Click "Add".
**Verify:** Dialog closes. Project appears in sidebar. API confirms project exists.

### NF-18: Settings Modal Opens
**Action:** Click the Settings link/button.
**Verify:** Settings modal is visible.

### NF-19: Settings Shows API Keys Section
**Action:** Open settings.
**Verify:** "API Keys" heading exists. Gemini, Codex, and HuggingFace fields are present.

### NF-20: Settings Old Quorum Fields Gone
**Action:** Open settings.
**Verify:** No elements with id `setting-quorum-lead`, `setting-quorum-fixed`, or `setting-quorum-additional`.

### NF-21: Settings Save Gemini Key
**Action:** Open settings. Type a value in the Gemini API Key field. Trigger save (onchange).
**Verify:** Reload page, reopen settings — key is still populated. API confirms value saved.

### NF-22: Settings Save Codex Key
**Action:** Same as NF-21 for Codex field.

### NF-23: Settings Save HuggingFace Key
**Action:** Same as NF-21 for HuggingFace field (`#setting-huggingface-key`).

### NF-24: Settings Keys Load on Open
**Action:** Save all three keys via API. Open settings modal.
**Verify:** All three fields are pre-populated with saved values.

### NF-27: Session Endpoint Info
**Action:** `fetch('/api/sessions/test/session', {method:'POST', body:JSON.stringify({mode:'info'})})`
**Verify:** Returns sessionId and sessionFile path.

### NF-28: Session Endpoint Transition
**Action:** `fetch('/api/sessions/test/session', {method:'POST', body:JSON.stringify({mode:'transition'})})`
**Verify:** Returns a prompt string.

### NF-29: Session Endpoint Resume
**Action:** `fetch('/api/sessions/test/session', {method:'POST', body:JSON.stringify({mode:'resume'})})`
**Verify:** Returns a prompt string.

### NF-30: Smart Compaction Endpoint Gone
**Action:** POST to `/api/sessions/test/smart-compact`.
**Verify:** Returns 404.

### NF-31 to NF-37: REMOVED
Ask CLI, Quorum, Guides, Skills, and Prompts tests removed — features deleted or replaced by consolidated MCP tools.

### NF-38: Workspace Path
**Action:** Fetch `/api/state`.
**Verify:** workspace = `/data/workspace`. No references to hopper or /mnt/workspace.

---

## Phase 9: Settings Reorganization + Vector Search (14 blocks)

### NF-39: Settings Has Four Tabs
**Action:** Open settings modal. Count tab buttons.
**Verify:** Four tabs visible: General, Claude Code, Vector Search, System Prompts.

### NF-40: General Tab Shows Appearance and API Keys
**Action:** Click General tab.
**Verify:** Appearance section (theme, font size, font family) and API Keys section visible. NO Claude Code / Keepalive. NO Features section.

### NF-41: Claude Code Tab Shows Model and Keepalive
**Action:** Click Claude Code tab.
**Verify:** Default Model, Thinking Level, Keepalive Mode, Idle timeout all visible.

### NF-42: Claude Code Settings Persist
**Action:** Change thinking level to "high". Close and reopen settings.
**Verify:** Still "high". Server `/api/settings` confirms.

### NF-43: Vector Search Tab Shows Status
**Action:** Click Vector Search tab.
**Verify:** Qdrant status indicator visible. Provider dropdown visible.

### NF-44: Vector Search Provider Dropdown
**Action:** Verify provider dropdown options.
**Verify:** Options: Hugging Face Free, Gemini, OpenAI, Custom. Gemini/OpenAI grayed if no keys.

### NF-45: Vector Search Custom Provider Fields
**Action:** Select "Custom" from provider dropdown.
**Verify:** URL and Key fields appear. Switch back — they hide.

### NF-46: Vector Search Collections Visible
**Action:** Scroll to Collections section.
**Verify:** 5 collection cards with dims, re-index buttons. Documents and Code have patterns textarea.

### NF-47: Vector Search Collection Dims Configurable
**Action:** Change Documents dims. Close and reopen settings.
**Verify:** Dims persisted in `/api/settings`.

### NF-48: Vector Search Collection Patterns Editable
**Action:** Add pattern to Documents. Save.
**Verify:** Pattern persisted in `/api/settings`.

### NF-49: Vector Search Ignore Patterns
**Action:** Verify ignore patterns textarea with defaults.
**Verify:** Contains node_modules/**, .git/**, *.lock etc.

### NF-50: Vector Search Additional Paths
**Action:** Add a path, click Add.
**Verify:** Path appears in list. Persisted in `/api/settings`.

### NF-51: Vector Search Re-index Button
**Action:** Click Re-index on Documents.
**Verify:** Button shows "Indexing..." then reverts.

### NF-52: Qdrant Status API
**Action:** Fetch `/api/qdrant/status`.
**Verify:** Returns available: true, running: true, collections with point counts.

---

### Vector Search: `none` Provider + API Key Flow (VEC-01 through VEC-20)

These tests verify the embedding provider lifecycle: default-`none` on fresh installs, per-provider key validation, qdrant-sync probe + restart serialization, and the MCP `configured:false` response when provider is disabled. Run with all keys removed first (restart the Space or wipe `/data/.workbench/workbench.db` settings rows for `gemini_api_key`/`codex_api_key`/`huggingface_api_key`/`vector_embedding_provider`) — each test assumes the prior state.

API key sources (executor must have these on disk or as env):
- Gemini: `/mnt/storage/credentials/api-keys/gemini.env` → `GEMINI_API_KEY=...`
- OpenAI/Codex: `/mnt/storage/credentials/api-keys/openai.env` → `OPENAI_API_KEY=...`
- HuggingFace: `/mnt/storage/credentials/api-keys/huggingface.env` → `HF_TOKEN=...`

#### VEC-01: Default Provider on Fresh `/data`
**Action:** `curl ${WORKBENCH_URL}/api/settings` (with gate cookie if needed).
**Verify:** `vector_embedding_provider === "none"`. (NOT `"huggingface"` — that was the pre-fix default and would 404 on every deploy.)

#### VEC-02: `/api/cli-credentials` Reports Three Providers
**Action:** `curl ${WORKBENCH_URL}/api/cli-credentials`.
**Verify:** Response is `{gemini: bool, openai: bool, huggingface: bool}` — all three keys present. On fresh install all three are `false`.

#### VEC-03: Fresh Deploy Logs One INFO, Zero ERRORs
**Action:** Wait 15s after Space `RUNNING`. `curl ${WORKBENCH_URL}/api/logs?module=qdrant-sync&since=5m&limit=20`.
**Verify:** Exactly one INFO line whose message contains `"Vector sync disabled"` AND zero ERROR/WARN entries from `qdrant-sync`. (Pre-fix: 9+ per-file ERRORs from dead HF endpoint.)

#### VEC-04: `vector_embedding_provider='none'` Skips Validation
**Action:** `PUT /api/settings -d '{"key":"vector_embedding_provider","value":"none"}'`.
**Verify:** `{saved: true}` returned in <500ms (no embedding-provider validation call hit). No 400 response.

#### VEC-05: Invalid Gemini Key Rejected
**Action:** `PUT /api/settings -d '{"key":"gemini_api_key","value":"AIzaSyDEFINITELY-INVALID"}'`.
**Verify:** HTTP 400 with body containing `"validation failed"` AND `"API key not valid"` (Gemini API's response). Setting NOT persisted in DB.

#### VEC-06: Valid Gemini Key Accepted; Credentials Update
**Action:** `PUT /api/settings -d '{"key":"gemini_api_key","value":"<real-key-from-gemini.env>"}'`. Then `GET /api/cli-credentials`.
**Verify:** PUT returns `{saved: true}`. Subsequent `cli-credentials` shows `gemini: true`.

#### VEC-07: Switch to `gemini` Provider Starts Sync, No Per-File Errors
**Action:** `PUT /api/settings -d '{"key":"vector_embedding_provider","value":"gemini"}'`. Wait 15s. `GET /api/logs?module=qdrant-sync&since=2m&limit=30`.
**Verify:** Logs contain exactly one `"Qdrant sync starting"`, four `"Created Qdrant collection"` (documents, claude_sessions, gemini_sessions, codex_sessions), one `"Qdrant initial sync complete"`. ERROR count from qdrant-sync == 0. (Pre-fix: 9 "Collection 'documents' doesn't exist!" or "No embedding API key configured" per-file errors due to drop+restart race.)

#### VEC-08: Valid Codex/OpenAI Key Accepted
**Action:** `PUT /api/settings -d '{"key":"codex_api_key","value":"<real-key-from-openai.env>"}'`. Then `GET /api/cli-credentials`.
**Verify:** PUT `{saved: true}`. `cli-credentials.openai === true`.

#### VEC-09: Valid HuggingFace Key Accepted (Validates Against Router Endpoint)
**Action:** `PUT /api/settings -d '{"key":"huggingface_api_key","value":"<real-key-from-huggingface.env>"}'`. Then `GET /api/cli-credentials`.
**Verify:** PUT `{saved: true}` (validation hits `https://router.huggingface.co/hf-inference/models/sentence-transformers/all-MiniLM-L6-v2/pipeline/feature-extraction` — not the dead legacy `api-inference.huggingface.co/models/...` URL). `cli-credentials.huggingface === true`.

#### VEC-10: Invalid HF Key Rejected
**Action:** `PUT /api/settings -d '{"key":"huggingface_api_key","value":"hf_DEFINITELY_INVALID"}'`.
**Verify:** HTTP 400 with `"validation failed"` in body. `cli-credentials.huggingface` unchanged from prior state.

#### VEC-11: Switch to `huggingface` Provider Works
**Action:** `PUT /api/settings -d '{"key":"vector_embedding_provider","value":"huggingface"}'`.
**Verify:** `{saved: true}`. (Validation reads HF key from DB and confirms it works against the router URL.)

#### VEC-12: Switch Back to `none` Stops Sync
**Action:** `PUT /api/settings -d '{"key":"vector_embedding_provider","value":"none"}'`. Wait 5s. `GET /api/logs?module=qdrant-sync&since=1m&limit=10`.
**Verify:** A new `"Vector sync disabled"` INFO appears. Zero new ERRORs in `qdrant-sync` since the switch.

#### VEC-13: Rapid-Fire Provider Switch Stress (Race Serialization)
**Action:** With Gemini key already saved, fire 6 consecutive PUTs in a tight loop:
```bash
for v in gemini huggingface none gemini huggingface none; do
  curl -X PUT ... -d "{\"key\":\"vector_embedding_provider\",\"value\":\"$v\"}"
done
```
Wait 30s for serialized pipelines to drain. `GET /api/logs?level=ERROR&module=qdrant-sync&since=2m`.
**Verify:** **Zero** ERRORs from qdrant-sync. Pipelines serialized via `reapplyConfig` coalescing — no overlapping `stop()`/`start()`/`scan` cycles. (Pre-fix: 9-18 per-file `"No embedding API key configured"` errors when scans crossed config flips.)

#### VEC-14: MCP `search_documents` with provider=`none`
**Action:** With provider=`none` set, call `POST /api/mcp/call` body `{"tool":"file_search_documents","args":{"query":"hello"}}`.
**Verify:** Response `{result: {configured: false, message: "Vector search is disabled. ...", results: []}}`. NOT a generic 500 error and NOT empty `{result: []}`.

#### VEC-15: MCP `search_code` with provider=`none`
**Action:** `POST /api/mcp/call` body `{"tool":"file_search_code","args":{"query":"hello"}}`.
**Verify:** Same shape as VEC-14 (`configured: false`, message, empty results).

#### VEC-16: MCP `search_semantic` with provider=`none`
**Action:** `POST /api/mcp/call` body `{"tool":"session_search","args":{"query":"hello"}}`.
**Verify:** Same shape as VEC-14 (`configured: false`, message, empty results).

#### VEC-17: MCP `search_documents` with Active Provider Returns Real Results
**Action:** Switch provider to `gemini` (with key saved). Wait 25s for initial scan. `POST /api/mcp/call` body `{"tool":"file_search_documents","args":{"query":"workbench deployment guide"}}`.
**Verify:** Response is an array of >0 result objects, each with `{collection: "documents", score: number, ...payload}`. Not the `configured:false` shape. (This confirms the search path actually embeds + queries qdrant when configured.)

#### VEC-18: Settings UI — Vector Search Tab + `None` Option (Playwright-driven)
**Steps:**
1. `browser_navigate` to `${WORKBENCH_URL}`. If gate is shown, fill `${GATE_USER}`/`${GATE_PASS}` and click Sign In.
2. `browser_evaluate`: `() => { openSettings(); return 'opened'; }` (the cog button calls `openSettings()`).
3. `browser_evaluate` to switch tabs and **await the async loader** in one step:
   ```js
   async () => {
     document.querySelector('button[data-settings-tab="vector"]').click();
     await loadVectorSettings();
     const sel = document.getElementById('setting-vector-provider');
     return {
       value: sel.value,
       options: [...sel.options].map(o => ({ value: o.value, label: o.textContent.trim(), disabled: o.disabled })),
     };
   }
   ```
   (Plain `tab.click()` triggers `loadVectorSettings()` async — without an `await` your eval returns before the option-disable logic runs and you'll see false negatives.)
**Verify:** `value === "none"`. `options` length ≥ 5 with first option `{value:"none", label:"None — disabled"}` and remaining values `huggingface`, `gemini`, `openai`, `custom`.

#### VEC-19: Settings UI — Provider Options Gray Out Without Keys (Playwright-driven)
**Pre-state:** No API keys saved (fresh `/data` from a Space restart).
**Steps:**
1. Open Settings and navigate to Vector Search tab as in VEC-18 (with `await loadVectorSettings()` in the eval).
2. `browser_evaluate`: read the option mapping.
3. Switch to **General** tab: `document.querySelector('button[data-settings-tab="general"]').click()` — note the API Keys section lives in the General tab, not its own tab.
4. `browser_type` a valid Gemini key into `#setting-gemini-key`, then `browser_press_key` Tab to fire `onchange`.
5. `browser_wait_for` 4000 ms (synchronous server-side validation against Gemini's API + DB write + qdrant restart).
6. Re-open Vector Search tab AND `await loadVectorSettings()` in the same eval (per VEC-18).
**Verify:**
- Step 2: `gemini`, `openai`, `huggingface` options each have `disabled === true` and label suffix `"(no key — set in Settings → API Keys)"`. `none` and `custom` are enabled.
- Step 6: After saving the Gemini key, the `gemini` option label becomes plain `"Gemini"` and `disabled === false`. Other unset providers remain disabled.

#### VEC-20: Settings UI — HuggingFace API Key Field Saves and Validates (Playwright-driven)
**Verified procedure** (run on hf-test post-fix):
1. Open Settings → General tab. `browser_snapshot` to get refs for the three password fields. Confirm IDs `setting-gemini-key`, `setting-codex-key`, `setting-huggingface-key` all exist.
2. `browser_type` a valid HF key into `#setting-huggingface-key` (use the key from `/mnt/storage/credentials/api-keys/huggingface.env`).
3. `browser_press_key` Tab to fire `onchange` → server-side validation hits `https://router.huggingface.co/hf-inference/.../pipeline/feature-extraction` with the new key.
4. `browser_wait_for` 4000 ms.
5. `browser_evaluate`: `await fetch('/api/cli-credentials').then(r => r.json())`.
**Verify:** `cli-credentials.huggingface === true`.

**VEC-20 negative path** (verified on hf-test):
- With a valid HF key already saved, fire `change` on `#setting-huggingface-key` with an obviously-bogus value (e.g. `"hf_DEFINITELY_INVALID_xyz"`).
- Server returns 400 with body `"API key validation failed: HF Embedding API error 401: ..."`.
- The error banner element is `#settings-error-banner` (with the message in `#settings-error-banner-msg`) — NOT `#settings-error`. Banner has `display: flex` and `offsetParent !== null` when shown.
- The field value rolls back to its previous length (`saveSetting()`'s rollback path) — verify by capturing `field.value.length` before the bad input and confirming it's unchanged after the validation failure.
- Server-side `cli-credentials.huggingface` remains `true` (the bad value never landed in the DB).

#### VEC-21: Settings UI — Switch Provider via Dropdown (Playwright-driven, full user flow)
**Pre-state:** At least one provider key saved (e.g. HF key from VEC-20). Provider currently `"none"`.
**Steps:**
1. Open Settings → Vector Search tab.
2. `browser_select_option` on `#setting-vector-provider` with value `"huggingface"` (or `"gemini"` / `"openai"` if those keys are saved).
3. `browser_wait_for` 10000 ms (allow validation, dropAllCollections, restart, and initial scan).
4. `browser_evaluate`:
   ```js
   async () => {
     const s = await fetch('/api/settings').then(r => r.json());
     const errs = await fetch('/api/logs?level=ERROR&module=qdrant-sync&since=2m').then(r => r.json());
     const all = await fetch('/api/logs?module=qdrant-sync&since=2m&limit=30').then(r => r.json());
     return {
       provider: s.vector_embedding_provider,
       err_count: errs.count,
       qdrant_starting: all.rows.filter(r => r.message.includes('Qdrant sync starting')).length,
       collections_created: all.rows.filter(r => r.message.startsWith('Created Qdrant collection')).length,
     };
   }
   ```
**Verify:**
- `provider` matches the value selected in step 2.
- `err_count === 0` (qdrant-sync ERRORs).
- `qdrant_starting >= 1` (a fresh restart cycle ran).
- `collections_created === 4` (documents, claude_sessions, gemini_sessions, codex_sessions all created).
- Repeat with `"none"` and verify a fresh `"Vector sync disabled"` INFO appears, no errors.

---

## Phase 10: Multi-CLI Sessions, Lifecycle, MCP Management (16 blocks)

### NF-53: Filter Bar is Dropdown
**Action:** Check session filter control.
**Verify:** `<select>` with options: Active, All, Archived, Hidden.

### NF-54: Sort Bar is Dropdown
**Action:** Check session sort control.
**Verify:** `<select>` with options: Date, Name, Messages. Side by side with filter.

### NF-55: Plus Button Opens CLI Dropdown
**Action:** Click `+` on a project header.
**Verify:** Dropdown: C Claude, G Gemini, X Codex, Terminal.

### NF-56: Create Claude Session via Dropdown
**Action:** Click + → Claude on a project.
**Verify:** Session created with cli_type: claude. Appears in sidebar.

### NF-57: Session Shows CLI Type Indicator
**Action:** Look at session item in sidebar.
**Verify:** CLI type indicator (C/G/X) with per-CLI colors. Active=bright, inactive=dimmed.

### NF-58: Terminal Button Gone from Project Header
**Action:** Look at project header.
**Verify:** No >_ button. Only ✎ and +.

### NF-59: Create Session via MCP
**Action:** `fetch('/api/mcp/call', {method:'POST', body:JSON.stringify({tool:'session_new', args:{cli:'claude', project:'...'}})})`
**Verify:** Returns session_id, tmux, cli.

### NF-60: Connect to Session by Name
**Action:** `fetch('/api/mcp/call', {method:'POST', body:JSON.stringify({tool:'session_connect', args:{query:'session name'}})})`
**Verify:** Returns session_id, tmux, cli.

### NF-61: Restart Session
**Action:** `fetch('/api/mcp/call', {method:'POST', body:JSON.stringify({tool:'session_restart', args:{session_id:'...'}})})`
**Verify:** Returns restarted: true, tmux.

### NF-62: MCP Register
**Action:** `project_mcp_register mcp_name="test-mcp" mcp_config={command:'echo'}`
**Verify:** Returns registered.

### NF-63: MCP List Available
**Action:** `project_mcp_list`
**Verify:** Returns servers array including test-mcp.

### NF-64: MCP Enable for Project
**Action:** `project_mcp_enable mcp_name="test-mcp" project=...`
**Verify:** Returns enabled. .mcp.json written.

### NF-65: MCP List Enabled
**Action:** `project_mcp_list_enabled project=...`
**Verify:** Returns servers array.

### NF-66: MCP Disable
**Action:** `project_mcp_disable mcp_name="test-mcp" project=...`
**Verify:** Returns disabled. .mcp.json updated.

### NF-67: Tmux Periodic Scan Running
**Action:** Check server logs.
**Verify:** "Started periodic tmux scan" with interval, max sessions, idle thresholds.

### NF-68: Only 3 MCP Tools
**Action:** Fetch `/api/mcp/tools`.
**Verify:** Exactly 44 tools, all flat names grouped by `file_/session_/project_/task_/log_` prefix.

---

## Phase 11: New Features v2 (NF-69 through NF-78)

### NF-69: File Editor Save and Save As Toolbar
**Action:** Open a file in the file browser (double-click). Verify editor toolbar with Save and Save As buttons.
**Steps:**
1. Open right panel → Files tab
2. Double-click any text/code/markdown file to open it in a tab
3. `browser_evaluate`: `document.querySelector('.editor-toolbar') !== null` — toolbar exists
4. `browser_evaluate`: `document.querySelector('.editor-save-btn') !== null` — Save button exists
5. `browser_evaluate`: `document.querySelector('.editor-saveas-btn') !== null` — Save As button exists
6. `browser_evaluate`: Save button disabled when clean: `document.querySelector('.editor-save-btn').disabled === true`
7. Make an edit in the editor
8. `browser_evaluate`: Save button enabled: `document.querySelector('.editor-save-btn').disabled === false`
9. `browser_evaluate`: Tab has dirty indicator: `document.querySelector('.tab-dirty') !== null`
10. Click Save button
11. `browser_evaluate`: Save button disabled again, dirty cleared
12. Verify file content on disk matches edit
13. Open an image file → `browser_evaluate`: No `.editor-toolbar` in the image pane
**Verify:** Toolbar with Save/Save As for text editors. Save disabled when clean, enabled when dirty. Image files have no toolbar.

---

### NF-70: Markdown Editor (Toast UI)
**Action:** Open a .md file. Verify Toast UI WYSIWYG editor loads.
**Steps:**
1. Double-click a .md file in the file browser
2. `browser_evaluate`: `document.querySelector('.toastui-editor-defaultUI') !== null`
3. `browser_evaluate`: Editor has content: `document.querySelector('.toastui-editor-defaultUI')?.offsetHeight > 100`
4. `browser_screenshot`
**Verify:** Toast UI editor renders for markdown files with WYSIWYG editing.

---

### NF-71: Code Editor (CodeMirror)
**Action:** Open a .js or .json file. Verify CodeMirror editor loads.
**Steps:**
1. Double-click a code file in the file browser
2. `browser_evaluate`: `document.querySelector('.cm-editor') !== null`
3. `browser_evaluate`: Editor has content: `document.querySelector('.cm-content')?.textContent.length > 0`
4. `browser_screenshot`
**Verify:** CodeMirror editor renders for code files with syntax highlighting.

---

### NF-72: Task Panel Filesystem Tree
**Action:** Open right panel → Tasks tab. Verify real filesystem folders are shown.
**Steps:**
1. Open right panel, click Tasks tab
2. `browser_evaluate`: `document.querySelector('#task-tree').children.length > 0`
3. `browser_evaluate`: Check for mount header: `document.querySelector('#task-tree div')?.textContent` contains '/data/workspace' or mount path
4. Expand a folder by clicking it
5. `browser_evaluate`: `document.querySelectorAll('.task-folder').length > 0`
6. `browser_screenshot`
**Verify:** Task tree shows real filesystem directories from /api/mounts, not just DB-derived folders.

---

### NF-73: Task Context Menu — Folder
**Action:** Right-click a folder in the task panel.
**Steps:**
1. Right-click a folder label in the task tree
2. `browser_evaluate`: Context menu appears with items: `document.querySelectorAll('.context-menu-item').length`
3. `browser_evaluate`: Menu has "Add Task": `[...document.querySelectorAll('.context-menu-item')].some(i => i.textContent.includes('Add Task'))`
4. `browser_evaluate`: Menu has "New Folder": `[...document.querySelectorAll('.context-menu-item')].some(i => i.textContent.includes('New Folder'))`
5. Click away to dismiss
**Verify:** Folder context menu shows "Add Task" and "New Folder".

---

### NF-74: Task Context Menu — Task
**Action:** Right-click a task in the task panel.
**Steps:**
1. Create a task first (right-click folder → Add Task)
2. Right-click the task node
3. `browser_evaluate`: Menu items include Edit, Complete, Archive, Delete
4. Click away to dismiss
**Verify:** Task context menu shows Edit, Complete/Reopen, Archive, Delete.

---

### NF-75: Project Picker Multi-Root
**Action:** Click + in header to add project. Verify picker shows mount roots.
**Steps:**
1. `browser_click` on header + button
2. `browser_evaluate`: `document.querySelector('#jqft-tree')` exists or mount headers exist
3. `browser_evaluate`: Check for mount header containing workspace path
4. Close the picker
**Verify:** Add Project picker shows filesystem roots from /api/mounts, not hardcoded path.

---

### NF-76: Empty Projects Visible in Sidebar
**Action:** Create a project with no sessions. Verify it shows in sidebar.
**Steps:**
1. Add a new project (empty directory)
2. Refresh sidebar
3. `browser_evaluate`: Project group for the new project exists with count 0
4. Verify the + button is visible on the empty project
**Verify:** Empty projects show in Active and All filters with session count 0.

---

### NF-77: File Browser Context Menus
**Action:** Right-click files and folders in the file browser panel.
**Steps:**
1. Open right panel → Files tab, expand a directory
2. Right-click a folder
3. `browser_evaluate`: Menu has New File, New Folder, Upload, Rename, Delete
4. Dismiss, right-click a file
5. `browser_evaluate`: Menu has Open, Rename, Delete
**Verify:** Context menus appear with correct actions for files and folders.

---

### NF-78: CLI Type Dropdown — All Types
**Action:** Create sessions of each CLI type via the + dropdown.
**Steps:**
1. Click + on a project → verify dropdown shows C Claude, G Gemini, X Codex, Terminal
2. Create a Claude session → verify tab opens, CLI indicator shows C
3. Create a Terminal session → verify tab opens with bash
4. `browser_evaluate`: Check CLI type indicators in sidebar: `document.querySelectorAll('.session-item').length`
**Verify:** All 4 session types can be created. CLI type indicator (C/G/X) shows correctly.

---

## Phase 12: Comprehensive Feature Verification (32 blocks)

Covers all fixes and features from issues #87, #93-#102. Automated tests in `tests/browser/multi-cli-and-editors.spec.js`.

### SESS-01: CLI Type Dropdown
**Action:** Click + on a project header.
**Verify:** Dropdown shows C Claude, G Gemini, X Codex, Terminal.

### SESS-02: Session Creation Modal
**Action:** Select Claude from dropdown.
**Verify:** Modal with `Session name` single-line input (`#new-session-name`) and Start Session button.

### SESS-03: Session Creation End-to-End
**Action:** Type a session name, click Start Session.
**Verify:** Tab opens with that name, terminal connects, session appears in sidebar. For Claude, the CLI receives a brief standby hint (`The user has titled this session "<name>". Stand by for their first message.`) — not a free-form prompt that would make it run wild.

### SESS-04: Gemini Session via API
**Action:** `POST /api/sessions {project, name, cli_type:'gemini'}`
**Verify:** Returns session with cli_type gemini. Appears in /api/state.

### SESS-05: Gemini Session Persistence
**Action:** Create Gemini session, wait 6 seconds.
**Verify:** Session still in /api/state (not cleaned up by reconciler).

### SESS-06: CLI Type Indicators
**Action:** Create Claude and Gemini sessions.
**Verify:** Sidebar shows C (claude) and G (gemini) indicators with correct titles.

### SESS-07: Codex Session Creation
**Action:** `POST /api/sessions {project, name, cli_type:'codex'}`
**Verify:** Codex CLI launches in tmux. Session in state with cli_type codex.

### SESS-08: Empty Name Rejected
**Action:** Open new session modal, click Start Session without typing.
**Verify:** Modal stays open, no session created, `#new-session-name` input focused.

### SESS-09: Sidebar Click Opens Session
**Action:** Click existing session in sidebar.
**Verify:** Tab opens, terminal connects to tmux session.

### EDIT-01: Editor Toolbar Present
**Action:** Double-click a file to open.
**Verify:** `.editor-toolbar` with Save and Save As buttons visible.

### EDIT-02: Save Button Dirty Tracking
**Action:** Open file, check Save disabled. Edit file, check Save enabled.
**Verify:** Save disabled when clean, enabled when dirty.

### EDIT-03: Save Persists File
**Action:** Edit file, click Save, read file from disk.
**Verify:** File content matches edit. Dirty reset to false.

### EDIT-04: CodeMirror for Code Files
**Action:** Open .js file.
**Verify:** CodeMirror editor loads with `.cm-editor`, toolbar present.

### EDIT-05: Toast UI for Markdown
**Action:** Open .md file.
**Verify:** Toast UI WYSIWYG editor loads, toolbar present.

### EDIT-06: No Toolbar for Images
**Action:** Open .png file.
**Verify:** Image viewer renders, no `.editor-toolbar` in pane.

### EDIT-07: Close Dirty Tab Confirm
**Action:** Edit file, close tab.
**Verify:** Confirm dialog appears. Cancel keeps tab open.

### TASK-01: Filesystem Tree
**Action:** Switch to Tasks panel.
**Verify:** `#task-tree` shows workspace folders from /api/mounts.

### TASK-02: Folder Context Menu
**Action:** Right-click a folder in task tree.
**Verify:** Context menu with "Add Task" and "New Folder".

### TASK-03: Task Creation
**Action:** Add task via context menu or API.
**Verify:** Task appears in tree with checkbox and title.

### TASK-04: Task Checkbox Complete
**Action:** Click task checkbox.
**Verify:** Task status changes to 'done' in DB.

### TASK-05: Task Delete
**Action:** Click task ✕ button.
**Verify:** Task removed from tree and DB.

### TASK-06: Expand State Preserved
**Action:** Expand folder, switch to Files panel, switch back.
**Verify:** Folder still expanded.

### CONN-01: Connect by Name Query
**Action:** `session_connect query="session name"`
**Verify:** Returns session_id, tmux, cli.

### CONN-02: Restart Session
**Action:** `session_restart session_id=...`
**Verify:** Returns restarted:true. New tmux session created.

### MCP-01 through MCP-06: MCP Tool Actions
**Action:** Test all 32 MCP actions across 3 tools.
**Verify:** Each returns expected result. See `multi-cli-and-editors.spec.js`.

### MCP-07: MCP Registry Lifecycle
**Action:** Register → list → enable → list_enabled → disable → unregister.
**Verify:** Full lifecycle works. Registry empty after unregister.

### KEEP-01: Keepalive Running
**Action:** Check server logs after startup.
**Verify:** Token expiry detected, next check scheduled.

### QDRANT-01: Semantic Search
**Action:** `file_search_documents query="deployment"`
**Verify:** Returns ranked results with scores when embeddings configured.

### PROMPT-01: Claude System Prompt
**Action:** Read `/data/.claude/CLAUDE.md`.
**Verify:** Has Identity, Purpose, Resources sections. Identifies as Claude.

### PROMPT-02: Gemini System Prompt
**Action:** Read `/data/.claude/GEMINI.md`.
**Verify:** Has Identity, Purpose, Resources sections. Identifies as Gemini.

### PROMPT-03: Codex System Prompt
**Action:** Read `/data/.claude/AGENTS.md`.
**Verify:** Has Identity, Purpose, Resources sections. Identifies as Codex.

### PROMPT-04: HHH Purpose Statement
**Action:** Read all three system prompts.
**Verify:** All contain: "You must be helpful, harmless, and honest towards the user."

---

## Element Verification Checklist

Quick pass/fail checklist for all 139 UI elements. Execute with `browser_evaluate` to confirm element exists.

### Sidebar Elements (31)

| # | Selector | Description | Result |
|---|----------|-------------|--------|
| 1 | `#sidebar` | Sidebar container | ☐ |
| 2 | `#sidebar-header` | Header with title and add button | ☐ |
| 3 | `#sidebar-header h1` | "Workbench" title | ☐ |
| 4 | `#sidebar-header button` | Add project button | ☐ |
| 5 | `#filter-bar` | Filter button bar | ☐ |
| 6 | `#session-filter` | Filter dropdown (Active/All/Archived/Hidden) | ☐ |
| 10 | `#session-sort` | Sort dropdown | ☐ |
| 11 | `#session-search` | Search input | ☐ |
| 12 | `#project-list` | Project list container | ☐ |
| 13 | `.project-group` | Project group (at least 1) | ☐ |
| 14 | `.project-header` | Project header | ☐ |
| 15 | `.project-header .arrow` | Collapse arrow | ☐ |
| 16 | `.project-header .count` | Session count badge | ☐ |
| 17 | `.project-header .new-btn` | New session + button | ☐ |
| 19 | `.session-list` | Session list container | ☐ |
| 20 | `.session-item` | Session item (at least 1) | ☐ |
| 21 | `.session-name` | Session name text | ☐ |
| 22 | `.session-meta` | Session metadata row | ☐ |
| 23 | `.session-meta .msg-count` | Message count badge | ☐ |
| 24 | `.session-actions` | Action buttons container | ☐ |
| 25 | `.session-action-btn.archive` | Archive button | ☐ |
| 26 | `.session-action-btn.rename` | Config/rename button | ☐ |
| 27 | `.session-action-btn.summary` | Summary button | ☐ |
| 28 | `.new-session-btn` | New session button (if shown) | ☐ |
| 29 | `#sidebar-footer` | Sidebar footer | ☐ |
| 30 | `#sidebar-footer button` | Settings gear button | ☐ |
| 31 | `.session-meta` CLI type label (C/G/X) | CLI type indicator (replaces active-dot) | ☐ |

### Main Area Elements (16)

| # | Selector | Description | Result |
|---|----------|-------------|--------|
| 1 | `#main` | Main content area | ☐ |
| 2 | `#tab-bar` | Tab bar container | ☐ |
| 3 | `#panel-toggle` | Right panel toggle button | ☐ |
| 4 | `#terminal-area` | Terminal area container | ☐ |
| 5 | `#empty-state` | Empty state message | ☐ |
| 6 | `#empty-state .hint` | Empty state hint text | ☐ |
| 7 | `#status-bar` | Status bar | ☐ |
| 8 | `.tab` | Tab element (when session open) | ☐ |
| 9 | `.tab.active` | Active tab | ☐ |
| 10 | `.tab-name` | Tab name text | ☐ |
| 11 | `.tab-close` | Tab close button | ☐ |
| 12 | `.tab-status` | Tab status indicator | ☐ |
| 13 | `.terminal-pane` | Terminal pane (when session open) | ☐ |
| 14 | `.terminal-pane.active` | Active terminal pane | ☐ |
| 15 | `.terminal-pane.active canvas` | xterm.js canvas | ☐ |
| 16 | `.status-item` | Status bar items | ☐ |

### Status Bar Elements (10)

| # | Selector/Content | Description | Result |
|---|-----------------|-------------|--------|
| 1 | `.status-item` containing "Model" | Model display | ☐ |
| 2 | `.status-item` containing "Mode" | Mode display | ☐ |
| 3 | `.status-item` containing "Context" | Context display | ☐ |
| 4 | `.context-bar` | Context usage bar | ☐ |
| 5 | `.context-bar .fill` | Context fill indicator | ☐ |
| 6 | `.status-item` with tab status | Session status | ☐ |
| 7 | `.status-item .label` | Label spans | ☐ |
| 8 | `.status-item .value` | Value spans | ☐ |
| 9 | `.context-bar .fill.context-fill-amber` | Amber/warning level (if applicable) | ☐ |
| 10 | `.context-bar .fill.context-fill-red` | Red/danger level (if applicable) | ☐ |

### Right Panel Elements (25)

| # | Selector | Description | Result |
|---|----------|-------------|--------|
| 1 | `#right-panel` | Panel container | ☐ |
| 2 | `#panel-header` | Panel header with tabs | ☐ |
| 3 | `[data-panel="files"]` | Files tab button | ☐ |
| 5 | `[data-panel="tasks"]` | Tasks tab button | ☐ |
| 7 | `#panel-content` | Panel content area | ☐ |
| 8 | `#panel-files` | Files section | ☐ |
| 10 | `#panel-tasks` | Tasks section | ☐ |
| 12 | `#file-browser-tree` | File browser tree | ☐ |
| 13 | `#file-viewer` | File viewer container | ☐ |
| 14 | `#file-viewer-name` | File name display | ☐ |
| 15 | `#file-viewer-content` | File content textarea | ☐ |
| 17 | `#task-list` | Task list container | ☐ |
| 18 | `#add-task-input` | Add task input | ☐ |
| 19 | `.task-item` | Task item (when tasks exist) | ☐ |
| 20 | `.task-checkbox` | Task checkbox | ☐ |
| 21 | `.task-text` | Task text | ☐ |
| 22 | `.task-delete` | Task delete button | ☐ |
| 24 | `.panel-section h3` | Section headers | ☐ |
| 25 | `.panel-tab.active` | Active panel tab | ☐ |

### Settings Modal Elements (28)

| # | Selector | Description | Result |
|---|----------|-------------|--------|
| 1 | `#settings-modal` | Modal container | ☐ |
| 2 | `.settings-close` | Close button | ☐ |
| 3 | `[data-settings-tab="general"]` | General tab | ☐ |
| 3a | `[data-settings-tab="claude"]` | Claude Code tab (NEW) | ☐ |
| 3b | `[data-settings-tab="vector"]` | Vector Search tab (NEW) | ☐ |
| 4 | `[data-settings-tab="prompts"]` | Prompts tab | ☐ |
| 5 | `#settings-general` | General settings container | ☐ |
| 5a | `#settings-claude` | Claude Code settings (NEW) | ☐ |
| 5b | `#settings-vector` | Vector Search settings (NEW) | ☐ |
| 6 | `#settings-prompts` | Prompts settings container | ☐ |
| 7 | `#setting-theme` | Theme dropdown | ☐ |
| 8 | `#setting-font-size` | Font size input | ☐ |
| 9 | `#setting-font-family` | Font family dropdown | ☐ |
| 10 | `#setting-model` | Default model dropdown | ☐ |
| 11 | `#setting-thinking` | Thinking level dropdown | ☐ |
| 12 | `#setting-keepalive-mode` | Keepalive mode dropdown | ☐ |
| 13 | `#setting-idle-minutes` | Idle minutes input | ☐ |
| 18 | `#mcp-server-list` | MCP server list | ☐ |
| 19 | `#mcp-name` | MCP name input | ☐ |
| 20 | `#mcp-command` | MCP command input | ☐ |
| 21 | `#setting-global-claude-md` | Global CLAUDE.md textarea | ☐ |
| 22 | `#setting-project-template` | Project template textarea | ☐ |
| 23 | `.settings-group` | Settings group containers | ☐ |
| 24 | `.setting-row` | Setting row containers | ☐ |
| 25 | `.modal-content` | Modal content wrapper | ☐ |
| 26 | `.mcp-server-item` | MCP server items (if any) | ☐ |
| 27 | `#add-mcp-form` | Add MCP form | ☐ |
| 28 | `.modal-content h2` | Settings title | ☐ |

### Auth Modal Elements (7)

| # | Selector | Description | Result |
|---|----------|-------------|--------|
| 1 | `#auth-modal` | Auth modal container | ☐ |
| 2 | `.modal-close` | Close button | ☐ |
| 3 | `#auth-link` | Auth link | ☐ |
| 4 | `#auth-code-input` | Auth code input | ☐ |
| 5 | `#auth-code-submit` | Submit button | ☐ |
| 6 | `.code-input-group` | Input group container | ☐ |
| 7 | `.step` | Step instructions | ☐ |

### Dynamic Overlays (22)

| # | Selector/Check | Description | Result |
|---|---------------|-------------|--------|
| 1 | New session dialog (on + click) | Session creation form | ☐ |
| 3 | `#new-session-name` | Session name input | ☐ |
| 4 | `#new-session-submit` | Submit button | ☐ |
| 5 | Config dialog (on rename click) | Session config overlay | ☐ |
| 6 | `#cfg-name` | Config name input | ☐ |
| 7 | `#cfg-state` | Config state dropdown | ☐ |
| 8 | `#cfg-notes` | Config notes textarea | ☐ |
| 9 | Summary overlay (on summary click) | Summary display | ☐ |
| 10 | `#summary-content` | Summary content area | ☐ |
| 11 | `.summary-spinner` | Loading spinner | ☐ |
| 12 | `.close-btn` in summary | Summary close button | ☐ |
| 13 | File picker overlay (on add project) | `#jqft-tree` | ☐ |
| 14 | `#picker-path` | Selected path input | ☐ |
| 15 | `#picker-name` | Project name input | ☐ |
| 16 | Search results (rendered into `#project-list`) | Search result items | ☐ |
| 17 | `.search-snippet` | Search match preview | ☐ |
| 18 | Context warning indicator | High context visual | ☐ |
| 19 | Toast/notification (if any) | Feedback messages | ☐ |
| 20 | Confirm dialogs (if any) | Deletion confirmations | ☐ |
| 21 | Error state display | API error feedback | ☐ |
| 22 | Loading states | Spinner/loading indicators | ☐ |

---

## Execution Notes

- **Parallelism:** Phases 1-4 must be sequential. Within a phase, tests can run in any order.
- **State cleanup:** Archive test sessions via `PUT /api/sessions/ID/config` with `{state:'archived'}`. Never DELETE (AD-004).
- **Timeouts:** CLI tests with Claude responses: 15-30s. UI-only tests: 1-3s.
- **Flaky tests:** Retry once with doubled waits before marking FAIL.
- **Screenshots:** Minimum: SMOKE-01, every FAIL, E2E-01 key steps.
- **API Base:** `fetch()` in `browser_evaluate` uses relative paths. Direct HTTP uses `${WORKBENCH_URL}/api/`.

---

## Phase 13: Regression Tests for Issue Fixes

Tests for all fixes applied in the canonical branch. Every test uses Playwright MCP with full UI interaction. No curl-only testing.

---

### REG-126-01: Session Resume by Exact ID — All 3 CLIs
**Issue:** #126 — Gemini/Codex sessions show 0 messages and resume wrong conversation
**Action:** For EACH CLI type (Claude, Gemini, Codex): create a session, send a message, close the tab, reopen it, verify it resumes.

**Steps (repeat for Claude, Gemini, Codex):**
1. Create session: `fetch('/api/sessions', {method:'POST', headers:{'Content-Type':'application/json'}, body:JSON.stringify({project:'PROJECT_NAME', cli_type:'CLI_TYPE', name:'test resume CLI_TYPE'})}).then(r=>r.json())`
2. `browser_wait` 5000
3. Refresh sidebar: `browser_evaluate`: `loadState()`
4. `browser_wait` 2000
5. Click the session in sidebar to open tab
6. `browser_wait` 5000
7. Send a message: `tabs.get(activeTabId).ws.send('hello from CLI_TYPE\r')`
8. `browser_wait` 5000
9. `browser_evaluate`: `activeTabId && tabs.get(activeTabId)?.ws?.readyState` — should be 1
10. `browser_screenshot` — capture session with message
11. Close the tab: click `.tab.active .tab-close`
12. `browser_wait` 1000
13. Click the same session again in sidebar to reopen
14. `browser_wait` 5000
15. `browser_evaluate`: `activeTabId && tabs.get(activeTabId)?.ws?.readyState` — should be 1
16. Read terminal buffer — verify previous content or resume output is present
17. `browser_screenshot` — capture resumed session

**Expected (for ALL 3 CLIs):**
- Session opens with WebSocket connected
- Message is sent and received
- After closing and reopening, session resumes (not a new blank session)
- Terminal shows previous content or resume output

**Failure Criteria:** All 3 CLI types must successfully resume. Failure for any one CLI is a test failure.

**Result:** ☐ PASS ☐ FAIL

---

### REG-126-02: Message Count Shows for All CLI Types
**Issue:** #126
**Action:** Check sidebar shows message count for Claude, Gemini, AND Codex sessions with history.

**Steps:**
1. `browser_evaluate`: `fetch('/api/state').then(r=>r.json()).then(d => d.projects.flatMap(p => p.sessions).map(s => ({id:s.id.substring(0,8), cli:s.cli_type, msgs:s.messageCount})))`
2. `browser_screenshot` — sidebar showing sessions with message counts
3. Verify at least one session of EACH CLI type (Claude, Gemini, Codex) has messageCount > 0

**Expected:**
- Claude sessions with history show messageCount > 0
- Gemini sessions with history show messageCount > 0
- Codex sessions with history show messageCount > 0
- Sidebar badges display the counts for all CLI types

**Result:** ☐ PASS ☐ FAIL

---

### REG-145-01: Status Bar Shows Correct Model — All 3 CLIs
**Issue:** #145 — Wrong model shown for non-Claude sessions

**Steps (repeat for Claude, Gemini, Codex):**
1. Click a CLI_TYPE session tab
2. `browser_wait` 3000
3. `browser_evaluate`: Read all status bar items (Model, Mode, Context)
4. `browser_screenshot` — capture status bar for this CLI type

**Expected (for ALL 3 CLIs):**
- Claude: Model shows "Sonnet", "Opus", or another Claude model name
- Gemini: Model shows a Gemini model name (e.g., "3-flash-preview")
- Codex: Model shows a GPT model name (e.g., "gpt-5.4")
- No CLI shows the wrong model (e.g., Gemini must NOT show "Sonnet")

**Result:** ☐ PASS ☐ FAIL

---

### REG-145-02: Status Bar Hides Thinking for Non-Claude — Gemini AND Codex
**Issue:** #119, #145

**Steps:**
1. Open a Gemini session tab
2. `browser_wait` 3000
3. `browser_evaluate`: Check if "Thinking" is in status bar text
4. `browser_screenshot`
5. Open a Codex session tab
6. `browser_wait` 3000
7. `browser_evaluate`: Check if "Thinking" is in status bar text
8. `browser_screenshot`
9. Open a Claude session tab
10. `browser_wait` 3000
11. `browser_evaluate`: Check if "Thinking" is in status bar text (may or may not be present — Claude is allowed to show it)

**Expected:**
- Gemini: "Thinking" is NOT shown
- Codex: "Thinking" is NOT shown
- Claude: "Thinking" may or may not be shown (it's a Claude-only feature)

**Result:** ☐ PASS ☐ FAIL

---

### REG-146-01: Restart Dialog Shows Correct CLI Name — All 3 CLIs
**Issue:** #146 — Restart dialog says "Claude" for all CLIs

**Steps (repeat for Claude, Gemini, Codex):**
1. Find a CLI_TYPE session in sidebar
2. `browser_hover` on the session item
3. `browser_click` on the restart button (&#8635;)
4. Capture the confirm dialog text (intercept via `page.on('dialog')`)
5. Verify the dialog says the correct CLI name
6. Dismiss the dialog (cancel — do not actually restart)
7. `browser_screenshot`

**Expected (for ALL 3 CLIs):**
- Claude: Dialog says "Claude session will be preserved"
- Gemini: Dialog says "Gemini session will be preserved"
- Codex: Dialog says "Codex session will be preserved"

**Result:** ☐ PASS ☐ FAIL

---

### REG-148-01: Tab Switching With Chat — 5 Rounds All 3 CLIs
**Issue:** #148 — Tab switching blank screen / terminal doesn't follow tab
**Priority:** P0 — This is the definitive tab switching test. Clicking tabs is NOT enough. You must chat with each CLI and verify it responds.

**Setup:**
1. Create one Claude, one Gemini, one Codex session in the same project
2. Wait for all 3 CLIs to finish startup (Claude shows prompt, Gemini shows prompt, Codex shows prompt)
3. Open all 3 as tabs by clicking each in the sidebar
4. Wait 5s after each to ensure WebSocket connects

**Steps — 5 rounds:**

For each round (1 through 5), do the following for EACH of the 3 tabs (Claude, Gemini, Codex):

1. **Click the tab** via `browser_click`
2. **Wait 2s** for terminal pane to switch
3. **Screenshot** — verify the correct CLI's terminal is showing (not another CLI's content)
4. **Send a testable message** — enter a math problem (e.g., "what is 7 times 8") or ask about the weather. Something with a verifiable correct answer.
5. **Wait 10s** for response
6. **Read terminal buffer** — verify the CLI produced a correct reply to your question. The reply must NOT be your own input text — it must be a response FROM the CLI. If the buffer only contains your input piled up in an editor field, the CLI did not respond — that is a FAIL.
7. **Watch out for login issues** — if the CLI shows an API key prompt, OAuth screen, trust dialog, update prompt, or any other blocker instead of a chat response, that is a FAIL. Clear those blockers and retry, but note the failure.
8. **Screenshot** — capture the response

After all 5 rounds:
- Verify all 3 WebSockets are still state 1 (OPEN)
- Verify exactly 1 `.tab.active` exists
- Verify the terminal pane content matches the active tab's CLI

**Expected:**
- Each tab click shows the CORRECT CLI's terminal, not another CLI's content
- Each CLI responds with a correct answer to the question asked
- No blank screens at any point
- No infinite reconnect loops
- All 3 WebSockets survive 5 rounds of switching

**Failure Criteria:** This test FAILS if ANY of the following occur for ANY of the 3 CLIs:
- A CLI returns an error (401, 403, timeout, crash, or any non-successful response)
- A CLI does not produce a visible chat response in the terminal buffer
- The terminal buffer only contains your input text (piled up in editor field) — the CLI did not respond
- A CLI shows a login prompt, trust dialog, or update screen instead of chatting
- A CLI's WebSocket is not in state 1 (OPEN) at any point during the 5 rounds
- A CLI is not authenticated and ready to chat before the test begins
- The terminal pane shows the wrong CLI's content after a tab switch
- A response of "unknown", "error", or any non-answer is shown

All 3 CLIs must successfully send AND receive chat messages in ALL 5 rounds. A 401, a blank response, a crash, piled-up input, a login screen, or any inability to chat is a FAIL — not a "config issue", not a "but Workbench worked", not "expected behavior". If you cannot chat with it and get a correct reply, the test failed.

**Result:** ☐ PASS ☐ FAIL
**Notes:** Record which round and which CLI fails, if any.

---

### REG-148-04: Dead Session Auto-Resume — All 3 CLIs
**Issue:** #148

**Steps (repeat for Claude, Gemini, Codex):**
1. Open a CLI_TYPE session tab, note its tmux name
2. Kill the tmux session server-side (via docker exec or restart API)
3. `browser_wait` 5000
4. Switch to a different tab, then switch back to the killed session's tab
5. `browser_wait` 5000
6. Read terminal buffer — should show "Session disconnected. Attempting to resume (1/3)..."
7. `browser_wait` 5000
8. `browser_evaluate`: `tabs.get(activeTabId)?.ws?.readyState` — should be 1 (reconnected) or show "could not be resumed after 3 attempts"
9. `browser_screenshot`

**Expected (for ALL 3 CLIs):**
- Dead session shows "Session disconnected. Attempting to resume..."
- Resume attempts are numbered (1/3, 2/3, 3/3)
- If CLI can restart: session auto-resumes, WebSocket reconnects
- If CLI cannot restart: stops after 3 attempts with "Click the session in the sidebar to retry"
- No infinite reconnect loop

**Result:** ☐ PASS ☐ FAIL

---

### REG-TAB-01: Tab Bar CLI Icons — All 3 CLIs
**Issue:** Parity verification for tab bar icons

**Steps:**
1. Open one Claude, one Gemini, one Codex session tab
2. For each tab in the tab bar, read:
   - `browser_evaluate`: The icon/logo element inside each `.tab` element
   - Claude tab should have ✳ icon (orange #e8a55d)
   - Gemini tab should have ◆ icon (blue #4285f4)
   - Codex tab should have SVG square icon (green #10a37f)
3. Verify tab name text is present next to each icon
4. Verify close button (✕) is present on each tab
5. `browser_screenshot` — tab bar showing all 3 CLI icons side by side

**Expected (for ALL 3 CLIs):**
- Each tab shows the correct CLI icon with correct color
- No tab shows the wrong CLI's icon
- Tab name and close button present on all tabs
- Active tab has `.active` class, others do not

**Result:** ☐ PASS ☐ FAIL

---

### REG-TAB-02: Rename Session Propagates to Tab — All 3 CLIs
**Issue:** Parity verification for session rename

**Steps (repeat for Claude, Gemini, Codex):**
1. Open a CLI_TYPE session tab
2. Note the current tab name: `browser_evaluate`: `document.querySelector('.tab.active .tab-name')?.textContent`
3. Rename the session via the sidebar config dialog:
   - `browser_hover` on the session item in sidebar
   - `browser_click` on the rename/config button (✎)
   - Clear the name field and type a new name: `renamed-CLI_TYPE-test`
   - Click Save
4. `browser_wait` 2000
5. Verify the tab name updated: `browser_evaluate`: `document.querySelector('.tab.active .tab-name')?.textContent`
6. Verify the sidebar session name updated
7. `browser_screenshot`

**Expected (for ALL 3 CLIs):**
- Tab name updates to the new name immediately after rename
- Sidebar session name updates to match
- No stale name shown in either location

**Result:** ☐ PASS ☐ FAIL

---

### REG-SIDEBAR-01: Session Item Display — All 3 CLIs
**Issue:** Parity verification for sidebar session items

**Steps (repeat for Claude, Gemini, Codex — verify at least one session of each type exists):**
1. `browser_evaluate`: For each CLI type, find a session item in the sidebar and read:
   - CLI icon/logo (✳ for Claude, ◆ for Gemini, SVG square for Codex)
   - Session name text
   - Message count badge
   - Timestamp (e.g., "4h ago")
   - Model name (e.g., "claude-opus-4-6", "gemini-3-flash-preview", "gpt-5.4")
2. `browser_screenshot` — sidebar showing all 3 CLI types with metadata

**Expected (for ALL 3 CLIs):**
- Claude: ✳ icon (orange), model shows a Claude model, message count > 0, timestamp present
- Gemini: ◆ icon (blue), model shows a Gemini model, message count > 0, timestamp present
- Codex: SVG square icon (green), model shows a GPT model, message count > 0, timestamp present
- Active sessions have bright icon color, inactive have dimmed color
- No CLI type shows another CLI's icon or model

**Result:** ☐ PASS ☐ FAIL

---

### REG-127-01: Favicon Present
**Issue:** #127 — Favicon not showing

**Steps:**
1. `browser_evaluate`: `document.querySelector('link[rel="icon"]')?.href || document.querySelector('link[rel="shortcut icon"]')?.href`
2. `browser_evaluate`: `fetch(document.querySelector('link[rel="icon"]')?.href || '/favicon.ico').then(r=>r.status)`

**Expected:**
- Favicon link element exists in DOM
- Favicon URL returns 200

**Result:** ☐ PASS ☐ FAIL

---

### REG-129-01: Sidebar Refresh Rate
**Issue:** #129 — Sidebar refresh too slow (30s → 10s)

**Steps:**
1. `browser_evaluate`: `typeof REFRESH_MS !== 'undefined' ? REFRESH_MS : 'not found'`
2. If not a global, check via source: `browser_evaluate`: `document.querySelector('script')?.textContent?.match(/REFRESH_MS\s*=\s*(\d+)/)?.[1]`

**Expected:**
- REFRESH_MS is 10000 (10 seconds), not 30000

**Result:** ☐ PASS ☐ FAIL

---

### REG-119-01: Status Bar Context Updates After Chat — All 3 CLIs
**Issue:** #119 — Status bar model/context display
**Note:** Static model check is covered by REG-145-01. This test verifies the bar REACTS to changes.

**Steps (repeat for Claude, Gemini, Codex):**
1. Click CLI_TYPE session tab
2. `browser_wait` 2000
3. Read status bar context value (e.g., "17k / 200k 9%") — save as BEFORE
4. Send a chat message: `tabs.get(activeTabId).ws.send('tell me a short joke\r')`
5. `browser_wait` 10000 (wait for response)
6. Read status bar context value again — save as AFTER
7. `browser_screenshot`

**Expected (for ALL 3 CLIs):**
- Context value AFTER is greater than or equal to BEFORE (tokens increased)
- Context percentage updated
- For Claude: may show Thinking indicator during response

**Failure Criteria:** If any CLI's context bar does not update after a chat message, the test fails.

**Result:** ☐ PASS ☐ FAIL

---

### REG-119-02: Status Bar Mode Display — All 3 CLIs
**Issue:** #119

**Steps (repeat for Claude, Gemini, Codex):**
1. Click CLI_TYPE session tab
2. `browser_wait` 2000
3. Read Mode value from status bar
4. `browser_screenshot`

**Expected (for ALL 3 CLIs):**
- Claude: Shows mode (e.g., "bypass", "plan", "normal")
- Gemini: Shows mode value (e.g., "bypass")
- Codex: Shows mode value (e.g., "bypass")
- Mode field is present and not empty for all 3

**Result:** ☐ PASS ☐ FAIL

---

### REG-138-01: Search Returns Non-Claude Sessions
**Issue:** #138 — searchSessions Claude-only

**Steps:**
1. `browser_type` into `#session-search`: a term that appears in Gemini/Codex session names
2. `browser_wait` 1000
3. `browser_evaluate`: `document.querySelectorAll('.session-item').length`
4. `browser_evaluate`: Check if any results have non-Claude type indicators
5. `browser_screenshot`
6. Clear search

**Expected:**
- Search results include Gemini and Codex sessions matching the query
- CLI type indicators (G/X) visible in results

**Result:** ☐ PASS ☐ FAIL

---

### REG-138-02: Token Usage for Non-Claude Sessions
**Issue:** #138

**Steps:**
1. Open a Gemini session tab
2. `browser_wait` 3000
3. `browser_evaluate`: `fetch('/api/sessions/' + activeTabId + '/tokens?project=PROJECT_NAME').then(r=>r.json())`
4. Open a Codex session tab
5. `browser_wait` 3000
6. `browser_evaluate`: `fetch('/api/sessions/' + activeTabId + '/tokens?project=PROJECT_NAME').then(r=>r.json())`

**Expected:**
- Gemini returns `max_tokens: 1000000` (not 200000)
- Codex returns `max_tokens: 200000`
- Neither returns an error

**Result:** ☐ PASS ☐ FAIL

---

### REG-138-03: Summary Generation — All 3 CLIs
**Issue:** #138

**Steps (repeat for Claude, Gemini, Codex):**
1. Find a CLI_TYPE session with messages in the sidebar
2. `browser_hover` on that session item
3. `browser_click` on the summary button (ⓘ)
4. `browser_wait` 10000 (summary generation may take time)
5. `browser_evaluate`: `document.querySelector('#summary-content')?.textContent`
6. `browser_screenshot`
7. Close the summary overlay

**Expected (for ALL 3 CLIs):**
- Summary generates without error
- Returns either actual summary text (length > 10) or "Empty session."
- No crash, no 500 error
- Summary overlay opens and can be closed

**Result:** ☐ PASS ☐ FAIL

---

### REG-150-01: Docker Compose Ships Generic Paths
**Issue:** #150

**Steps:**
1. Read docker-compose.yml: `browser_evaluate`: `fetch('/api/file?path=/app/docker-compose.yml').then(r=>r.text()).catch(()=>'not found')`
2. Verify it does NOT contain site-specific mount paths

**Expected:**
- docker-compose.yml has generic paths like `/path/to/your/data:/data`
- Does NOT have `/mnt/workspace/workbench:/data`

**Result:** ☐ PASS ☐ FAIL

---

### REG-VOICE-01: Mic Button Removed
**Issue:** Deepgram voice feature removed

**Steps:**
1. `browser_evaluate`: `document.getElementById('mic-btn') === null`

**Expected:** No mic button in status bar.

**Result:** ☐ PASS ☐ FAIL

---

### REG-OAUTH-01: Per-CLI OAuth Detection Settings
**Issue:** OAuth detection configurable per CLI

**Steps:**
1. Open Settings modal
2. `browser_evaluate`: Verify 3 checkboxes exist: `setting-oauth-claude`, `setting-oauth-gemini`, `setting-oauth-codex`
3. Verify defaults: Claude checked, Gemini unchecked, Codex unchecked
4. Toggle Gemini on, save, reload, verify persisted
5. Toggle back off

**Expected:**
- Claude on by default
- Gemini off by default
- Codex off by default
- Changes persist across page reload

**Result:** ☐ PASS ☐ FAIL

---

### REG-MCP-01: MCP Registration for All 3 CLIs
**Issue:** #135 — MCP tools not registered for Gemini/Codex

**Steps:**
1. `browser_evaluate`: `fetch('/api/file?path=/data/.gemini/settings.json').then(r=>r.text())` — check contains "workbench"
2. `browser_evaluate`: `fetch('/api/file?path=/data/.codex/config.toml').then(r=>r.text())` — check contains "workbench"
3. `browser_evaluate`: `fetch('/api/file?path=/data/.claude/settings.json').then(r=>r.text())` — check contains "workbench"

**Expected (ALL 3 CLIs):**
- Claude: settings.json has workbench MCP server
- Gemini: settings.json has workbench MCP server
- Codex: config.toml has workbench MCP server

**Result:** ☐ PASS ☐ FAIL

---

### REG-HIDDEN-01: Hidden Session Flag
**Issue:** #149 — Sub-sessions not auto-hiding

**Steps:**
1. Create session with hidden flag: `POST /api/sessions {project, cli_type:'claude', name:'hidden test', hidden:true}`
2. Refresh sidebar
3. Verify session does NOT appear in Active filter
4. Switch filter to Hidden — verify session appears

**Expected:**
- Hidden sessions not visible in Active filter
- Hidden sessions visible in Hidden filter

**Result:** ☐ PASS ☐ FAIL

---

### REG-REFRESH-01: File Tree Refresh Button
**Issue:** File tree needs refresh capability

**Steps:**
1. Open right panel → Files tab
2. Verify refresh button (↻) exists next to Home button
3. Create a file via API: `PUT /api/file?path=/data/workspace/test-refresh.txt`
4. Click refresh button
5. Expand workspace mount
6. Verify new file appears in tree

**Expected:**
- Refresh button exists and is sticky (doesn't scroll away)
- After clicking refresh, new files appear in tree

**Result:** ☐ PASS ☐ FAIL

---

### REG-REFRESH-02: File Tree Poll-on-Focus
**Issue:** File tree refreshes when panel is activated

**Steps:**
1. Open Files panel, note contents
2. Switch to Tasks panel
3. Create a file via API
4. Switch back to Files panel
5. Verify new file appears without clicking refresh

**Expected:**
- Switching to Files panel triggers automatic refresh
- New files appear without manual action

**Result:** ☐ PASS ☐ FAIL

---

### REG-FRESH-01: Fresh Install Works (covered by Phase 0.A)

This regression is now covered by **Phase 0.A: Fresh container** at the top of the runbook. Phase 0.A spins up a fresh container on an ephemeral `/data` volume and verifies clean startup, DB seeding, workspace creation, and `/api/state` health — which is exactly what this regression checks.

If Phase 0.A passes, REG-FRESH-01 inherits PASS. If 0.A fails, REG-FRESH-01 fails too and the run stops per the Phase 0 protocol. There are no separate steps to run here.

**Result (mirror Phase 0.A):** ☐ PASS ☐ FAIL

---

### REG-FILTER-01: Project Filtering by State — Active/Archived/Hidden
**Issue:** Project filter did not respect project-level state

**Steps:**
1. Note the list of projects visible in Active filter
2. Archive a project via API: `PUT /api/projects/<name>/config` with `{state:'archived'}`
3. Refresh sidebar
4. Verify the archived project is NO LONGER visible in Active filter
5. Switch filter to Archived
6. Verify the archived project IS visible in Archived filter
7. Switch filter back to Active
8. Set project to Hidden: `PUT /api/projects/<name>/config` with `{state:'hidden'}`
9. Refresh sidebar
10. Verify the hidden project is NOT visible in Active filter
11. Verify the hidden project is NOT visible in All filter
12. Switch filter to Hidden
13. Verify the hidden project IS visible in Hidden filter
14. Restore project to active: `PUT /api/projects/<name>/config` with `{state:'active'}`

**Expected (test ALL 3 states):**
- Active filter: only shows projects with state 'active'
- Archived filter: shows archived projects (and active projects that have archived sessions)
- Hidden filter: shows hidden projects (and projects with hidden sessions)
- All filter: shows everything except hidden projects
- Changing a project's state immediately updates the sidebar

**Result:** ☐ PASS ☐ FAIL

---

### REG-FILTER-02: Session Filtering Within Projects
**Issue:** Session filter within a project

**Steps:**
1. Open a project with multiple sessions
2. Archive one session via config dialog or API
3. Verify archived session disappears from Active filter
4. Switch to Archived filter — verify it appears
5. Hide a session via API: `PUT /api/sessions/<id>/config` with `{state:'hidden'}`
6. Verify hidden session not in Active or All
7. Switch to Hidden — verify it appears
8. Restore both sessions

**Expected:**
- Session state changes immediately reflected in sidebar filters
- Archived sessions only in Archived view
- Hidden sessions only in Hidden view

**Result:** ☐ PASS ☐ FAIL

---

### REG-META-01a: Status Bar Updates After Chat — Claude
**Issue:** #156 — Status bar metadata consumer
**Steps:** Click Claude session tab. Note status bar Model/Context. Send "what is 9 times 7". Wait for response. Check status bar within 10s. Model must show a Claude model name (not "unknown"). Context tokens must have increased.
**Result:** ☐ PASS ☐ FAIL

### REG-META-01b: Status Bar Updates After Chat — Gemini
**Steps:** Same as 01a but with a Gemini session. Model must show a Gemini model name. Context must show /1000k.
**Result:** ☐ PASS ☐ FAIL

### REG-META-01c: Status Bar Updates After Chat — Codex
**Steps:** Same as 01a but with a Codex session. Model must show a GPT model name. Context must show /200k.
**Result:** ☐ PASS ☐ FAIL

---

### REG-META-02a: Sidebar Metadata Updates After Chat — Claude
**Issue:** #156 — Sidebar metadata consumer
**Steps:** Note Claude session's message count and timestamp in sidebar. Send a chat message. Wait for response. Wait up to 15s. Message count must increase. Timestamp must update. Model must appear.
**Result:** ☐ PASS ☐ FAIL

### REG-META-02b: Sidebar Metadata Updates After Chat — Gemini
**Steps:** Same as 02a but with a Gemini session.
**Result:** ☐ PASS ☐ FAIL

### REG-META-02c: Sidebar Metadata Updates After Chat — Codex
**Steps:** Same as 02a but with a Codex session.
**Result:** ☐ PASS ☐ FAIL

---

### REG-META-03a: MCP Tokens Action — Claude
**Issue:** #156 — MCP tokens consumer
**Steps:** Call `POST /api/mcp/call` with `{tool:'session_info', args:{session_id:'<claude-id>'}}`. Verify: `input_tokens` > 0, `model` contains "claude", `max_tokens` is 200000 or 1000000.
**Result:** ☐ PASS ☐ FAIL

### REG-META-03b: MCP Tokens Action — Gemini
**Steps:** Same as 03a with a Gemini session. `model` must contain "gemini", `max_tokens` must be 1000000.
**Result:** ☐ PASS ☐ FAIL

### REG-META-03c: MCP Tokens Action — Codex
**Steps:** Same as 03a with a Codex session. `model` must contain "gpt", `max_tokens` must be 200000.
**Result:** ☐ PASS ☐ FAIL

---

### REG-META-04a: MCP Config Action — Claude
**Issue:** #156 — MCP config consumer
**Steps:** Call `POST /api/mcp/call` with `{tool:'session_config', args:{session_id:'<claude-id>'}}`. Verify response contains: `id`, `name`, `state`, `project`. No error.
**Result:** ☐ PASS ☐ FAIL

### REG-META-04b: MCP Config Action — Gemini
**Steps:** Same as 04a with a Gemini session. Must return valid config, no error.
**Result:** ☐ PASS ☐ FAIL

### REG-META-04c: MCP Config Action — Codex
**Steps:** Same as 04a with a Codex session. Must return valid config, no error.
**Result:** ☐ PASS ☐ FAIL

---

### REG-178: Gemini key resolves consistently across DB / env / API write
**Source:** Issue #178 (regression test — must continue to pass).
**Setup:** Backend deploy (`${WORKBENCH_CONTAINER}`).

**Steps:**
1. In Settings → API Keys, set Gemini API Key to a valid key.
2. Confirm `process.env.GEMINI_API_KEY` is set inside the container: `docker exec <container> sh -c 'echo $GEMINI_API_KEY' | head -c 12` should match the first 12 chars of the key (or be empty if read from DB).
3. Set `vector_embedding_provider` = `gemini` in Settings.
4. `POST /api/qdrant/reindex` for `claude_sessions` (or via `session_search` MCP).
5. Watch `docker logs <container> --tail 100 -f` during reindex.
6. **Negative case:** clear DB row (`DELETE FROM settings WHERE key='gemini_api_key'`), restart container, confirm reindex still works using the env-var fallback (env is still set from step 1's API write).

**Expected:**
- No `HF Embedding API error` lines.
- No `GOOGLE_API_KEY` references in logs.
- Reindex completes; `claude_sessions` collection has new points (`POST /api/qdrant/status`).
- Negative case reindex also succeeds (proves env fallback path).

**Result:** ☐ PASS ☐ FAIL

---

### REG-179: Indexer skips synthetic API-error chunks
**Source:** Issue #179 (regression test — must continue to pass).
**Setup:** Backend deploy (`${WORKBENCH_CONTAINER}`) with at least one Claude session JSONL containing a synthetic API-error chunk. (Sample path inside the container: `/data/.claude/projects/-data-workspace-repos-agentic-workbench/<session-id>.jsonl`.)

**Steps:**
1. Confirm a synthetic chunk exists: `grep -l '"isApiErrorMessage":true' /data/.claude/projects/*/*.jsonl | head -1` returns at least one file.
2. Reindex `claude_sessions` collection.
3. Search via MCP `session_search` with query `"Prompt is too long"` — should return zero matches OR only legitimate user/assistant mentions of that phrase, never the synthetic boilerplate text itself.
4. Sanity: total point count for `claude_sessions` should match the count of non-synthetic user+assistant turns across all session JSONLs (not the raw line count).

**Expected:**
- Synthetic-chunk search returns clean results (no boilerplate dominating top-K).
- Legit chunks still indexed (point count > 0; spot-check by searching for a known phrase from a real session).

**Result:** ☐ PASS ☐ FAIL

---

### REG-182: Error messages no longer truncated at 100 chars
**Source:** Issue #182 (regression test — must continue to pass).
**Setup:** Backend deploy (`${WORKBENCH_CONTAINER}`).

**Steps:**
1. **Keepalive failure path:** force a keepalive query failure. Easiest: stop network egress to anthropic.com briefly during a keepalive cycle, OR temporarily set an invalid Anthropic API key. Watch `docker logs <container> --tail 50 -f` until a `Keepalive Claude query failed` line appears.
2. Confirm the logged `err` field contains the full stderr from the `claude` CLI process (auth error message, network error, rate-limit body, etc.) — NOT just the bare command echo `Command failed: claude --print --no-session-persistence --model haiku ...`.
3. **Git clone failure path:** `POST /api/projects` with `{path: "https://github.com/this-repo-does-not-exist-12345/foo"}`. Confirm the `400` response body's `error` field contains the full git error (e.g., `fatal: repository '...' not found` or similar), not a 200-char truncation.
4. **Summary failure path:** trigger `POST /api/sessions/:id/summary` with an invalid sessionId pointing to a corrupt JSONL (or with an expired key). Confirm the 500 response's `error` field contains the full underlying error.

**Expected:**
- All three error paths surface the actual root cause in their respective logs/responses.
- No truncation at 100 or 200 chars; full error message visible up to 1000 chars.

**Result:** ☐ PASS ☐ FAIL

---

### REG-186: File browser pane scrolls horizontally when tree content overflows
**Source:** Issue #186 (regression test — must continue to pass).
**Surface:** UI/visual — requires HEADED browser per "no headless for visual bugs" rule.

**Setup:** UI deploy at ${WORKBENCH_URL}. Open Files panel.

**Steps:**
1. Open Files panel via right-pane `☰` toggle.
2. Expand `/data/workspace` → expand a subdirectory with deeply nested paths or long filenames (e.g., `repos/<long-name>/.../something.md`).
3. Confirm long names do NOT wrap onto a second line.
4. Confirm a horizontal scrollbar appears at the bottom of the panel when names exceed pane width.
5. Drag the horizontal scrollbar right — confirm full filenames become visible.

**Expected:**
- One filename per row (no wrap).
- Horizontal scroll appears + works when content overflows.
- Vertical scroll continues to work.

**Result:** ☐ PASS ☐ FAIL

---

### REG-189: API responses sanitize URL credentials
**Source:** Issue #189 (regression test — must continue to pass).
**Setup:** Backend deploy.

**Steps:**
1. POST `/api/projects` with `{path: "https://baduser:topsecret@github.com/no/such/repo.git"}` (or a real URL with fake creds).
2. Inspect the 400 response body — `error` field should contain `https://***:***@github.com/...`, NOT the original `baduser:topsecret`.
3. Inspect the matching `Git clone failed` line in `docker logs` — should still contain the FULL raw URL with creds (operator log path).

**Expected:**
- Client response has redacted credentials (`***:***@`).
- Internal log has raw URL for operator debugging.
- Both are bounded at 1000 chars.

**Result:** ☐ PASS ☐ FAIL

---

### REG-176: qdrant-sync survives cold-start race + recovers from later qdrant outages
**Source:** Issue #176 (regression test — must continue to pass).
**Setup:** Backend deploy (`${WORKBENCH_CONTAINER}`). Need a way to start the workbench with qdrant temporarily unavailable.

**Steps:**
1. **Cold-start race**: stop the workbench. Restart it. With normal startup ordering (entrypoint launches qdrant + node concurrently), look at the early logs — should see at most one `Qdrant not available` at WARN/INFO with retries, then `Qdrant sync starting`. Should NOT see `qdrant-sync._running = false` indefinitely.
2. **Background recovery**: simulate qdrant going down then coming back. From inside the container: `pkill qdrant`, wait 30s, watch log for `scheduling background re-attempt` warning. Restart qdrant manually (`/opt/qdrant/qdrant &`). Within 60s, expect `Qdrant reachable again — starting vector sync` log line and `_running = true` at the API/MCP layer.
3. Stop the container (`docker stop`) and confirm `stop()` clears the background timer (no zombie interval after container exit).

**Expected:**
- Cold-start race: sync starts within ~15s even if qdrant lags.
- Background recovery: sync starts on its own after qdrant comes back, no manual restart needed.
- Clean shutdown: no leftover interval timer after `stop()`.

**Result:** ☐ PASS ☐ FAIL

---

### REG-191: qdrant-sync skips empty-text chunks before embed
**Source:** Issue #191 (regression test — must continue to pass).
**Setup:** Backend deploy (`${WORKBENCH_CONTAINER}`) with Gemini provider configured. Need at least one workspace file the chunker would produce empty chunks for (e.g., empty CLAUDE.md, frontmatter-only .md).

**Steps:**
1. Confirm baseline: `docker logs ${WORKBENCH_CONTAINER} --since 5m | grep "EmpsuptyEmbedContentRequest.content contains an empty Part"` should show OLD entries (pre-fix).
2. Trigger reindex of `documents` via `POST /api/qdrant/reindex` with `{collection: "documents"}`.
3. Watch logs during reindex: should NOT produce any new `empty Part` errors.
4. Sanity: collection point count grows, files that had empty chunks contribute zero points (skipped) but DO NOT abort the file's other valid chunks.

**Expected:**
- Zero `empty Part` errors after fix.
- Files with mixed empty + non-empty chunks: only non-empty get indexed.
- Files entirely empty: silent skip (return 0).

**Result:** ☐ PASS ☐ FAIL

---

### REG-192: qdrant-sync respects Gemini's 100-batch limit
**Source:** Issue #192 (regression test — must continue to pass).
**Setup:** Backend deploy. Need a large markdown file that produces >100 chunks (e.g., the gate2*-compliance review docs that originally hit this).

**Steps:**
1. Identify a file in `/data/workspace` that would exceed 100 chunks (review docs, large logs).
2. Touch the file (or update its content) so qdrant-sync re-syncs it.
3. Watch logs: should see no `at most 100 requests` errors.
4. Sanity: file is fully indexed (chunk count = expected from `chunkDocument` output, all chunks present in qdrant).

**Expected:**
- No `at most 100 requests` errors regardless of chunk count.
- Large files complete indexing in ~N/100 round-trips with small inter-batch delays.

**Result:** ☐ PASS ☐ FAIL

---

### REG-193: POST /api/projects accepts URL paths without slash mangling
**Source:** Issue #193 (regression test — must continue to pass).
**Setup:** Backend deploy. Workbench reachable.

**Steps:**
1. POST `/api/projects` with body `{"path": "https://github.com/this-repo-does-not-exist-aaa/foo.git"}` to a known-bad URL.
2. Confirm response is NOT `{"error":"Git clone failed: Invalid git URL"}`. The error should reflect the ACTUAL git failure (e.g., `repository '...' not found`, `Authentication failed`, etc.).
3. POST with a real git URL like `{"path": "https://github.com/octocat/Hello-World.git"}` (or any small public repo). Confirm clone succeeds: 200 + `cloned: true` + path under `/data/workspace`.
4. POST with a filesystem path like `{"path": "/data/workspace/docs"}`. Confirm slash-collapse still applies (no double-slash regression for FS paths).

**Expected:**
- URL paths reach `gitCloneAsync` intact; real git error surfaces.
- Filesystem paths still get normalized.
- A successful clone creates the project as expected.

**Result:** ☐ PASS ☐ FAIL

---

### REG-187: Status bar Model populates from sidebar fallback for all CLIs
**Source:** Issue #187 (regression test — must continue to pass).
**Setup:** UI deploy. Need a fresh CLI session creation to trigger the previously-lagging path.

**Steps (real user):**
1. Log in past gate.
2. Create a Claude session in any project. Wait for prompt.
3. Send a message ("what is 7 times 8" or any prompt).
4. Wait for response.
5. **Read the status bar at the bottom**: should show `Model: Sonnet` (or appropriate model name) immediately, NOT `Model: unknown`.
6. Sanity: do the same for a Gemini session and a Codex session — both should also show their model immediately.

**Expected:**
- Status bar Model field shows correct model on first response, not on second.
- Behavior consistent across Claude / Gemini / Codex.

**Result:** ☐ PASS ☐ FAIL

---

### REG-190: sanitizeErrorForClient redacts token@host and query-string secrets
**Source:** Issue #190 (regression test — must continue to pass).
1. Bare `https://token@host` → `https://***@host`
2. Common credential query params (`api_key`, `token`, `auth`, `key`, `secret`, `password`, `access_token`, `refresh_token`, `api-key`, `x-api-key`, `apikey`) → value redacted to `***`

**Setup:** Backend deploy.

**Steps (direct unit test inside container):**
```bash
docker exec workbench node -e "
const safe = require('/app/safe-exec');
const tests = [
  ['user:pass', 'https://baduser:topsecret@github.com/repo.git'],
  ['token@', 'fatal: failed for https://ghp_abc123def456@github.com/repo.git'],
  ['api_key qs', 'GET https://api.example.com/v1/things?api_key=sk-secret123 failed'],
  ['token qs', 'POST /endpoint?token=xoxb-12345 returned 401'],
  ['multi qs', 'auth=A&user=alice&api_key=K&page=3'],
  ['plain', 'Could not resolve host: example.com'],
];
for (const [label, t] of tests) console.log(label.padEnd(12), '→', safe.sanitizeErrorForClient(t));
"
```

**Expected output**:
- `user:pass` → `https://***:***@github.com/...`
- `token@` → `https://***@github.com/...`
- `api_key qs` → `?api_key=*** failed`
- `token qs` → `?token=*** returned`
- `multi qs` → `auth=***&user=alice&api_key=***&page=3` (only credential-named params redacted; `user=alice`, `page=3` left alone)
- `plain` → unchanged (no URL credentials present)

**Negative case (false-positive guard):**
```bash
docker exec workbench node -e "
const safe = require('/app/safe-exec');
console.log(safe.sanitizeErrorForClient('Author: alice@example.com'));
"
```
Should print the input unchanged — author lines / non-URL `@` patterns are NOT touched.

**Result:** ☐ PASS ☐ FAIL

---

### REG-169: Auth modal Submit advances the CLI's /login prompt
**Source:** Issue #169 (regression test — must continue to pass).
**Surface:** UI/visual + backend. Requires headed browser (Hymie) + a real Claude OAuth flow. Auth state is wiped on every HF rebuild (no persistent storage), so this is the canonical per-deploy auth setup test.

**Setup:** ${WORKBENCH_URL} rebuilt with the fix. ${GATE_USER}/${GATE_PASS} (if gate present) + API keys ready (`/mnt/storage/credentials/api-keys/`). Hymie Firefox session.

**Steps (real user):**
1. Open `${WORKBENCH_URL}/` in Hymie Firefox.
2. Log in with `aristotle9` / `Vault2011$`.
3. Settings → API Keys: paste Gemini key + OpenAI key. Close Settings.
4. Create a project (sidebar `+` → pick `/data/workspace/docs`).
5. Project header `+` → CLAUDE → enter "say hello" → Start Session.
6. In the Claude tab, type `/login` + Enter.
7. Menu appears. Press Enter (option 1: Claude account with subscription).
8. **Modal appears** ("Authentication Required") + CLI shows "Paste code here >".
9. Click "Authenticate with Claude" in modal → OAuth tab opens.
10. Authorize on `claude.ai` → land on `platform.claude.com/oauth/code/callback` with the code → click "Copy Code".
11. Switch back to the workbench tab.
12. Paste code in modal's "Paste authorization code here" input.
13. Click Submit.
14. **Verify**: CLI should advance from "Paste code here >" to "Login successful" + show "Welcome back …" greeting AUTOMATICALLY. No manual paste/Enter in CLI required.
15. **Verify**: workbench-top "Not authenticated" warning disappears.

**Expected:**
- Modal Submit alone is sufficient — CLI advances without further user action.
- Login succeeds; subsequent Claude messages work.
- Auth persists for the container's lifetime.

**Failure signature (pre-fix):** Modal closes, CLI sits at `Paste code here if prompted >` indefinitely until user manually pastes via Ctrl+Shift+V + Enter in the terminal pane.

**Result:** ☐ PASS ☐ FAIL

---

### REG-194: Right file panel stays bounded to viewport, scrollbars stay reachable
**Source:** Issue #194 (regression test — must continue to pass).
**Surface:** UI/visual — requires HEADED browser per "no headless for visual bugs" rule.

**Setup:** UI deploy at ${WORKBENCH_URL}. Open Files panel via the right-pane `☰` toggle. Need a workspace with enough nested content that the rendered tree exceeds viewport height. If a real workspace doesn't have enough content, inject synthetic items via `browser_evaluate` to force overflow (per the verification recipe below).

**Steps (real user perspective):**
1. Log in with ${GATE_USER}/${GATE_PASS} if a gate is present.
2. Click `☰` to open the right Files panel.
3. Click `▶ /data/workspace` to expand the mount.
4. Drill into a directory with many subdirs/files. Recursively expand a few levels.
5. **Verify panel boundary**: the right Files panel's bottom edge aligns with the bottom of the workbench UI. Settings button (bottom-left of sidebar) and the panel's bottom should be at the same y. Panel does NOT extend below the visible page.
6. **Verify internal scroll works for tall trees**: scroll the file tree vertically with the mouse wheel — content inside the panel scrolls; the rest of the workbench (sidebar, terminal pane) does NOT scroll.
7. **Verify horizontal scroll works for long names**: drill into a directory with long filenames OR resize the panel narrower. Drag the horizontal scrollbar at the bottom of the file tree → tail of long filenames becomes visible. The horizontal scrollbar must be at the visible bottom of the panel, NOT off-screen.

**Verification recipe (when no real tree is tall enough):**
After expanding the real tree, run `browser_evaluate` to inject synthetic LIs:
```js
const tree = document.querySelector('#file-browser-tree');
const ul = tree.querySelector('UL.jqueryFileTree');
for (let i = 0; i < 200; i++) {
  const li = document.createElement('li');
  li.className = 'file ext_md';
  const a = document.createElement('a');
  a.innerText = `synthetic-file-${i}-with-extra-length-to-fill.md`;
  li.appendChild(a);
  ul.appendChild(li);
}
```
Then measure:
- `document.querySelector('#right-panel').getBoundingClientRect()` → bottom should equal `window.innerHeight`
- `document.querySelector('#file-browser-tree').getBoundingClientRect().bottom` → should be `<= window.innerHeight`
- `document.querySelector('#file-browser-tree').scrollHeight > clientHeight` → true (overflow exists)
- After `tree.scrollTop = 9999; tree.scrollLeft = 9999;`, both end positions reach (no off-screen scrollbar)
- `document.body.scrollHeight === window.innerHeight` and `window.scrollY === 0` (outer page never scrolls)

**Expected:**
- Right panel bottom aligns with viewport bottom regardless of tree size.
- Tree extends only inside the panel; internal scrollbars handle overflow.
- Horizontal scrollbar reachable at the bottom of the visible panel area.
- Outer page never scrolls — body remains at scrollHeight = innerHeight.

**Result:** ☐ PASS ☐ FAIL

---

### REG-188: registerCodexMcp does not corrupt config.toml
**Source:** Issue #188 (regression test — must continue to pass).
**Setup:** Backend deploy. Need a container where Codex config exists and is loadable BEFORE this verification (validate baseline by running `codex --version`).

**Steps:**
1. On a fresh dev container, confirm `~/.codex/config.toml` is empty or missing.
2. Start the workbench (Workbench MCP registration runs at startup).
3. Cat the config: `cat /data/.codex/config.toml`. Confirm it contains exactly one `[mcp_servers.workbench]` block with `command = "node"` and `args = ["..."]`. Confirm syntactically valid TOML by running `codex --version` — should print version, not a parse error.
4. Restart Workbench (re-runs registration). Re-cat config: should NOT have a duplicate `[mcp_servers.workbench]` block (the early-return guard prevents double-append).
5. Negative case: manually pre-populate `/data/.codex/config.toml` with non-MCP content (e.g. a `[notice.foo]` block). Restart. Confirm Workbench appends its block AFTER the existing content without modifying or corrupting it.

**Expected:**
- Single valid `[mcp_servers.workbench]` block; rest of file untouched.
- `codex --version` prints version (no TOML parse error).
- Multiple Workbench restarts produce no duplicate registrations.

**Result:** ☐ PASS ☐ FAIL

---

### REG-173: xterm scrollbar tracks buffer growth while scrolled up
**Source:** Issue #173 (regression test — must continue to pass).
**Surface:** UI/visual — REQUIRES headed browser per "no headless for visual bugs" rule. Use ${WORKBENCH_URL} + headed browser.

**Setup:** UI deploy at ${WORKBENCH_URL}. Hymie OAuth setup complete per `workbench-deployment.md`.

**Steps:**
1. Open ${WORKBENCH_URL} in a headed browser; log in past gate if present.
2. Open a Claude session. Send a prompt that produces long streaming output: e.g., `list every directory under /data/workspace recursively and describe each in one sentence`.
3. As soon as output starts streaming (within first 10-20 lines), scroll up in the terminal pane to read earlier rows. Keep the viewport above the bottom while output continues.
4. Wait until at least 50+ new rows have been appended to the buffer below the viewport.
5. Try to scroll back down using only the scrollbar (mouse drag or click on scrollbar track — NOT keyboard arrows).
6. Confirm the scrollbar reaches the actual buffer end. Confirm latest output rows are reachable.

**Expected:**
- Scrollbar can reach the actual bottom of the buffer.
- No need to press Ctrl+End / Down-arrow / Enter to "rescue" the viewport.
- Compared to baseline capture `/mnt/storage/bug-monitor/bug-173-captured.json` showing `rowsBehind: 51` before fix, after-fix value should be `0`.

**Watch for regression:**
- High CPU during long Claude streams (every chunk triggers a `term.refresh()`). If observed, file follow-up to add rAF debounce.

**Result:** ☐ PASS ☐ FAIL

---

### REG-174: tini reaps orphan zombie CLI processes
**Source:** Issue #174 (regression test — must continue to pass).
**Surface:** Container infrastructure — verify on any deployed container after image rebuild.

**Setup:** Container deploy at ${WORKBENCH_URL}. Connect via `docker exec` or SSH.

**Steps:**
1. `docker exec workbench-dev ps -o pid,user,stat,cmd -e` — note PID 1 should be `/usr/bin/tini -- /entrypoint.sh`.
2. Open a Claude session in the workbench so a `claude` child exists.
3. Find the claude PID: `docker exec workbench-dev pgrep -af claude`.
4. SIGKILL the claude PID: `docker exec workbench-dev kill -9 <PID>`.
5. Wait 5 seconds, then `docker exec workbench-dev ps -o pid,stat,cmd -e | grep -i defunct`.

**Expected:**
- PID 1 is tini (`/usr/bin/tini`), not `node`.
- After killing the claude process and waiting, no `<defunct>` entries appear (or any that briefly existed are reaped within 1-2s).
- Pre-fix baseline (prod deployment, 2026-04-24): `[claude] <defunct>` persisted 3+ hours.

**Result:** ☐ PASS ☐ FAIL

---

### REG-156: Single-source session metadata via getSessionInfo()
**Source:** Issue #156 (regression test — must continue to pass).
- `safe-exec.js` — new `tmuxNameFor(sessionId)` (single source of truth for tmux session naming).
- `tmux-lifecycle.js` — `tmuxName` now delegates to `safe.tmuxNameFor`.
- `session-utils.js` — new `getSessionInfo(sessionId)` returns unified shape (id, project_*, cli_type, cli_session_id, name, state, model, input_tokens, max_tokens, message_count, timestamp, tmux, active, etc.); 2s TTL cache to dedupe parallel callers; `invalidateSessionInfoCache()` exported for write-side hooks.
- `routes.js` — `/api/sessions/:id/tokens` and `buildSessionList` route through `getSessionInfo`. `_getNonClaudeMetadata` retained as a list-context disambiguation pre-pass that populates `cli_session_id` when missing.
- `mcp-tools.js` — `tokens` action routes through `getSessionInfo`.
**Surface:** Backend refactor — verify via curl + spot-check sidebar/status bar in Hymie.

**Setup:** Deploy to ${WORKBENCH_URL}. Have at least one Claude session and one Gemini or Codex session running (any 1d+ existing sessions in the sidebar work).

**Steps:**
1. `curl ${WORKBENCH_URL}/api/state | jq '.sessions[0:3] | map({id,name,model,messageCount,active,cli_type})'` — confirm sessions render with name/model/messageCount/active populated for both Claude and non-Claude.
2. Pick an active session id, `curl '${WORKBENCH_URL}/api/sessions/<id>/tokens?project=<project>' | jq` — confirm `{input_tokens, model, max_tokens}` shape unchanged.
3. Same id again immediately — should return same numbers (cache hit).
4. Sidebar in Hymie Firefox: open `${WORKBENCH_URL}`, confirm session list renders identically to before (names, message counts, active dot, model labels for non-Claude).
5. Status bar (active session bar): open a Claude session, confirm Model/Tokens populate correctly within 1-2 polls.

**Expected:**
- All session-list and per-session-token read paths return equivalent data shape to pre-refactor.
- No new errors in `/api/logs?level=ERROR&module=session-utils` or `module=routes`.
- Cache hit on repeat-call within 2s (no extra disk read; not directly observable but no perf regression).

**Watch for regressions:**
- Newly-created non-Claude sessions: file metadata may take 1 sidebar render to appear (disambiguation pre-pass writes cli_session_id, next render sees file). This was the same behavior pre-refactor.
- Cache staleness after rename/archive: up to 2s lag before user-visible UI updates. Acceptable.

**Result:** ☐ PASS ☐ FAIL

---

### REG-181: Dual-sink logger + /api/logs query API + UI error banner
**Source:** Issue #181 (regression test — must continue to pass).
- `db.js` — new `logs` table (id, ts, level, module, message, context) with indices on ts, level+ts, module+ts. Helpers: `insertLog`, `queryLogs`, `errorCountSince`, `topErrorSince`, `cleanupOldLogs`.
- `logger.js` — every `log.{debug,info,warn,error}` call now also persists to `logs` table via lazy `db` require. Failure-safe (one stderr warn per process). Hourly TTL sweep via setInterval.unref'd; default retention `LOG_RETENTION='-7 days'`.
- `routes.js` — `GET /api/logs?level=&module=&since=1h&limit=200`, `GET /api/logs/summary?since=1h` (count + topError for banner).
- `public/index.html` — clickable error banner alongside auth banner. Polls `/api/logs/summary` every 60s, opens a modal showing the last 50 ERROR rows on click.
**Surface:** Backend + UI — verify backend via curl, UI via headed Hymie Firefox.

**Setup:** Deploy to ${WORKBENCH_URL}. For UI step, Hymie Firefox.

**Backend steps:**
1. Generate at least one ERROR via a known-failing operation: `curl -X PUT ${WORKBENCH_URL}/api/settings -H 'Content-Type: application/json' -d '{"key":"gemini_api_key","value":"deliberately-bad-key-181-test"}'` — returns 400 and writes a WARN log.
2. Force an ERROR: `docker exec ${WORKBENCH_CONTAINER} node -e "require('/app/logger.js').error('runbook test 181', {module:'runbook-181', code:42})"`.
3. `curl ${WORKBENCH_URL}/api/logs/summary?since=1h | jq` — expect `errorCount >= 1`, `topError.module == 'runbook-181'`.
4. `curl '${WORKBENCH_URL}/api/logs?level=ERROR&module=runbook-181&limit=10' | jq '.rows[0]'` — confirm the row has ts/level/module/message/context fields.
5. `since` parser: try `?since=15m`, `?since=24h`, `?since=2026-04-26T00:00:00Z` — all should return valid responses.

**UI steps (Hymie):**
1. Open `${WORKBENCH_URL}` in Hymie Firefox.
2. Confirm a red error banner appears at the top within ~60s of the test errors above (or refresh).
3. Click the banner → modal opens listing recent errors (time / module / message columns).
4. Close the modal; banner remains visible until the 1h window passes.

**Cleanup:** `docker exec ${WORKBENCH_CONTAINER} sqlite3 /data/.workbench/workbench.db "DELETE FROM logs WHERE module IN ('runbook-181','verify-181')"`.

**Expected:**
- Errors persist to `logs` table immediately (within the same request).
- Banner shows count + top module within 60s of new errors.
- Modal lists rows ordered DESC by ts.
- Disk: hourly cleanup deletes rows older than `LOG_RETENTION` env var (default 7 days).

**Result:** ☐ PASS ☐ FAIL

---

### REG-180: API key changes validated synchronously on PUT /api/settings
**Source:** Issue #180 (regression test — must continue to pass).
**Surface:** Backend API — can be tested with curl against ${WORKBENCH_URL}.

**Setup:** Backend deploy. Get a valid Gemini API key for the positive case.

**Steps:**
1. Negative case (bad key): `curl -X PUT ${WORKBENCH_URL}/api/settings -H 'Content-Type: application/json' -d '{"key":"gemini_api_key","value":"obviously-bad-key-xyz"}'`
2. Confirm response is `400` with body containing `"API key validation failed: ..."` and the provider model name.
3. Verify setting was NOT saved: `curl ${WORKBENCH_URL}/api/settings | jq .gemini_api_key` — should be the prior value (or unset), NOT `obviously-bad-key-xyz`.
4. Positive case (good key): `curl -X PUT ${WORKBENCH_URL}/api/settings -H 'Content-Type: application/json' -d '{"key":"gemini_api_key","value":"<real-key>"}'`
5. Confirm response is `200 {saved: true}`. Verify it was saved.
6. Provider switch case: with provider currently `huggingface`, send `{"key":"vector_embedding_provider","value":"openai"}` while no codex key is set — expect `400` (validation fails because no key for openai).

**Expected:**
- Bad key → synchronous `400` with provider error string, no DB write.
- Good key → `200 {saved: true}`, DB row updated.
- Provider switch with missing key → `400`, provider remains unchanged.
- Per-validation latency: ~50-200ms (one tiny embed call per validated PUT).

**Result:** ☐ PASS ☐ FAIL

---

### REG-147: Atomic temp→real session-id handoff
**Source:** Issue #147 (regression test — must continue to pass).
**Root cause (3-CLI consensus):** `resolveSessionId` and `resolveStaleNewSessions` in session-resolver.js performed insert-real → update-metadata → delete-temp as separate statements. `/api/state` polls landing in the brief window saw both rows.
**Surface:** Backend.

**Setup:** Deploy to ${WORKBENCH_URL}. Have a Claude session creation flow ready.

**Steps:**
1. From a fresh page load on `${WORKBENCH_URL}`, create a new Claude session via the UI's + button (any project) with a prompt.
2. Within the next ~30s, hit `/api/state` repeatedly: `for i in $(seq 1 30); do curl -sS ${WORKBENCH_URL}/api/state | jq -r '[.projects[].sessions[] | select(.cli_type == "claude")] | length' ; sleep 1; done`
3. Expected: count never doubles around the resolution time. Pre-fix could see a 1-2s window where the same session appeared twice (one with new_<ts> id, one with the real UUID).
4. Sidebar visual check: only one entry per session through the resolution.

**Expected:**
- No duplicate entries in `/api/state` at any moment.
- Sidebar shows one entry per session throughout the resolution.

**Result:** ☐ PASS ☐ FAIL

---

### REG-157: Auto-respawn dead tmux pane on tab reconnect
**Source:** Issue #157 (regression test — must continue to pass).
**Surface:** Backend WS path + UI behavior. REQUIRES Playwright UI verification (per UI-component rule).

**Setup:** Deploy to ${WORKBENCH_URL}. Open a Claude session in the workbench so a tmux pane exists.

**Steps:**
1. Open a Claude session via the UI. Confirm the terminal is attached and showing prompt.
2. Identify the tmux session name from server logs (`docker logs ${WORKBENCH_CONTAINER} --tail 50 | grep tmux`) — format `wb_<id12>_<hash>`.
3. From host: `ssh ${WORKBENCH_HOST} 'docker exec workbench tmux kill-session -t wb_xxxxxxxxxxxx_yyyy'`
4. In Playwright (or Hymie Firefox), refresh the workbench page.
5. Wait ~3s. The same session tab should reattach with a fresh terminal — NO "[Session detached]" message, NO need to close/relaunch.
6. Server log should show `Auto-respawned dead tmux session for reconnecting tab` with the tmuxSession name.
7. Click into the session — terminal accepts input, CLI launches afresh (since old conversation is gone, but tab is alive).

**Expected:**
- Tab reattaches automatically after tmux pane was killed.
- Server log emits the auto-respawn line.
- No "[Session detached]" message visible to the user.
- If lookup fails (corrupt tmuxName, missing DB row), falls back to existing close-with-error behavior — graceful, no crash.

**Watch for regressions:**
- Tab reconnects with the right CLI type (claude/gemini/codex matches the original session).
- New session content reflects a fresh CLI launch (the prior conversation is gone — that's the trade-off; we recover the tab, not the in-memory state).

**Result:** ☐ PASS ☐ FAIL

---

### REG-180-UI: Settings UI surfaces validation errors + rolls back optimistic cache
**Source:** Issue #180 (regression test — must continue to pass).
**Surface:** UI — REQUIRES Playwright (or Hymie) verification. Backend curl alone is insufficient.

**Setup:** Deploy to ${WORKBENCH_URL}. Have a known-valid Gemini API key already saved (so you can confirm rollback).

**Steps (Playwright):**
1. Navigate to `${WORKBENCH_URL}`. Click Settings (bottom of sidebar) → Settings modal opens.
2. Snapshot the current Gemini API Key field (it should be the masked existing key).
3. Type a deliberately invalid value into `#setting-gemini-key` and dispatch a `change` event.
4. Wait ~2.5s for the validation round-trip.
5. Assert: `document.getElementById('settings-error-banner')` exists and contains "API key validation failed: ..." with the real provider error.
6. Assert: `_settingsCache.gemini_api_key` matches the previous (valid) value, NOT the bad one typed.
7. Confirm via `curl ${WORKBENCH_URL}/api/settings | jq .gemini_api_key` that the DB still has the original key.
8. Now type the original valid value back (or any valid value) → banner disappears, save succeeds.
9. Click the X on the banner → banner dismisses without affecting state.

**Expected:**
- Bad value → red banner with provider error visible at top of Settings modal.
- `_settingsCache` rolled back to previous value (no UI lying about persisted state).
- DB unchanged (backend already prevents that, but verify).
- Successful save clears the banner automatically.
- Network error (e.g., container restart mid-PUT) shows "Save failed: <network error>" and also rolls back.

**Watch for regressions:**
- Other settings (theme, font_size, OAuth toggles) all use saveSetting too — they should still save successfully (no false-positive errors).
- Banner does not stack: opening modal again with a still-bad value should not duplicate the banner.

**Result:** ☐ PASS ☐ FAIL

---

## Phase 14: MCP Tool Catalogue (44 flat tools)

End-to-end coverage for the flat MCP tool surface introduced in the `mcp-rework` work. Each tool gets one happy-path integration test; the layered safety net is:

- **Mock** (`node --test tests/mock/mcp-tools.test.js`): catalogue size, dispatch, validation/error mapping. Run on every commit, no container required.
- **Live integration** (this phase): each tool exercised against a deployed `${WORKBENCH_CONTAINER}` via `POST /api/mcp/call`. Schema-shape verification, no UI.
- **Live e2e** (Phase 14b): `session_*` interaction tools verified against real CLI panes — actually drives Claude/Gemini/Codex.

For every test below: `${API}` = `${WORKBENCH_URL}/api/mcp/call`. Default request shape: `{tool: <name>, args: {...}}`. Verify is HTTP 200 + the listed response keys present.

### MCP-CAT-00: Catalogue size and shape
**Action:** `GET ${WORKBENCH_URL}/api/mcp/tools`
**Verify:** `tools.length === 44`. Every name matches `/^(file|session|project|task|log)_/`. Counts: 8 file, 19 session, 11 project, 5 task, 1 log.

### MCP-CAT-01: Stdio server advertises 44 tools
**Action:** Spawn `docker exec -i ${WORKBENCH_CONTAINER} node /app/mcp-server.js` and send `{jsonrpc:"2.0",id:1,method:"initialize"}` then `{jsonrpc:"2.0",id:2,method:"tools/list"}`.
**Verify:** initialize → `serverInfo.name === "workbench"`. tools/list → 44 entries. No tool name contains `workbench_` (single-prefix).

### file_* (8 tools)

| ID | Tool | Args | Verify |
|----|------|------|--------|
| MCP-F-01 | `file_list` | `{}` | `entries[]` array, mix of `type:"directory"` and `type:"file"` |
| MCP-F-02 | `file_create` | `{path:"mcp-test.txt", content:"a"}` | `{created:"mcp-test.txt"}` |
| MCP-F-03 | `file_read` | `{path:"mcp-test.txt"}` | `{path, content:"a"}` |
| MCP-F-04 | `file_update` | `{path:"mcp-test.txt", content:"b"}` | `{updated:"mcp-test.txt"}`. Re-read returns `"b"`. |
| MCP-F-05 | `file_find` | `{pattern:"workbench"}` | `{pattern, matches:[...]}` (array, may be empty) |
| MCP-F-06 | `file_search_documents` | `{query:"deployment"}` | `{configured:true, results:[]}` if vector off, else `results.length>=0` |
| MCP-F-07 | `file_search_code` | `{query:"express"}` | same shape as F-06 |
| MCP-F-08 | `file_delete` | `{path:"mcp-test.txt"}` | `{deleted:"mcp-test.txt"}`. Subsequent read returns 404. |

### session_* (19 tools) — non-tmux

| ID | Tool | Args | Verify |
|----|------|------|--------|
| MCP-S-01 | `session_list` | `{project:<P>}` | `{sessions:[]}` (array; empty fine for fresh container) |
| MCP-S-02 | `session_new` | `{project:<P>, cli:"claude", name:"mcp-cat-claude"}` | `{session_id, tmux, cli:"claude"}`. Save `session_id` for downstream tests. |
| MCP-S-03 | `session_info` | `{session_id:<from S-02>}` | Has `model`, `input_tokens`, `max_tokens`, `cli_type:"claude"`, `active:true` |
| MCP-S-04 | `session_config` | `{session_id, name:"renamed"}` | `{saved:true}` |
| MCP-S-05 | `session_summarize` | `{session_id, project:<P>}` | summary object (may be empty for fresh session) |
| MCP-S-06 | `session_export` | `{session_id, project:<P>}` | `{format, content}` for claude; structured for non-claude |
| MCP-S-07 | `session_find` | `{pattern:"hello"}` | `{pattern, results:{}}` (per-CLI keys, may be empty) |
| MCP-S-08 | `session_search` | `{query:"any"}` | `{results:[]}` or `{configured:false}` if vector off |
| MCP-S-09 | `session_prepare_pre_compact` | `{}` | Returns string containing "checklist" or "compact" |
| MCP-S-10 | `session_resume_post_compact` | `{session_id, tail_lines:10}` | Returns prompt string with tail content |
| MCP-S-11 | `session_connect` | `{query:"renamed"}` | `{session_id, tmux, cli}` |
| MCP-S-12 | `session_restart` | `{session_id}` | `{restarted:true, tmux, cli}` |
| MCP-S-13 | `session_kill` | `{session_id:<temp Gemini from S-NEW>}` | `{killed:true}` (use a separate session — don't kill mcp-cat-claude until after S-15) |

### session_* (19 tools) — tmux interaction (against the live `mcp-cat-claude` session)

| ID | Tool | Args | Verify |
|----|------|------|--------|
| MCP-S-14 | `session_send_text` | `{session_id, text:"hello from mcp test"}` | `{sent:true, tmux}`. No Enter sent — text sits in input. |
| MCP-S-15 | `session_send_key` | `{session_id, key:"Enter"}` | `{sent:true, key:"Enter", tmux}`. Claude begins responding. |
| MCP-S-16 | `session_wait` | `{seconds:5}` | `{waited_seconds:5}` (≥4s actual elapsed) |
| MCP-S-17 | `session_read_screen` | `{session_id, lines:50}` | `{tmux, lines:50, screen:<string>}`. Screen contains either the prompt echo or Claude's response. |
| MCP-S-18 | `session_read_output` | `{session_id, project:<P>}` | structured response (model, transcript) |
| MCP-S-19 | `session_send_keys` | `{session_id, text:"test "}` | `{sent:true, tmux}` (raw send-keys, no buffer) |

After S-19, run `session_kill {session_id: mcp-cat-claude}` to clean up.

### Repeat S-02..S-19 for Gemini

**Action:** Same sequence with `cli:"gemini"`. Special handling: after S-14 (send_text) Gemini may need a *second* `Enter` to submit (multiline editor quirk — see `using-cli-sessions.md`). Verify via S-17 that "Thinking..." or response output appeared.

### Repeat S-02..S-19 for Codex

**Action:** Same sequence with `cli:"codex"`. Special handling: handle trust + update prompts with `session_send_key {key:"2"}` first; then prompts work. Same multiline-editor double-Enter as Gemini.

### project_* (12 tools)

| ID | Tool | Args | Verify |
|----|------|------|--------|
| MCP-P-01 | `project_find` | `{}` | `{projects:[{id,name,path,notes,state}, ...]}` |
| MCP-P-02 | `project_get` | `{project:<P>}` | `{id, name:<P>, path, notes, state}` |
| MCP-P-03 | `project_update` | `{project:<P>, notes:"runbook test note"}` | Updated row returned. Re-fetch via P-02 confirms. |
| MCP-P-04 | `project_find` (with pattern) | `{pattern:"workbench"}` | `{pattern, matches:[...]}` |
| MCP-P-05 | `project_sys_prompt_get` | `{project:<P>, cli:"claude"}` | `{project, cli, file:"CLAUDE.md", content}` |
| MCP-P-06 | `project_sys_prompt_update` | `{project:<P>, cli:"claude", content:"# Test\n"}` | `{updated:true}`. P-05 then returns `"# Test\n"`. Restore previous via P-06. |
| MCP-P-07 | `project_mcp_register` | `{mcp_name:"runbook-test", mcp_config:{command:"echo"}}` | `{registered:"runbook-test"}` |
| MCP-P-08 | `project_mcp_list` | `{}` | `{servers:[..., {name:"runbook-test"}, ...]}` |
| MCP-P-09 | `project_mcp_enable` | `{mcp_name:"runbook-test", project:<P>}` | `{enabled, project}`. `<project_path>/.mcp.json` updated. |
| MCP-P-10 | `project_mcp_list_enabled` | `{project:<P>}` | `{servers:[..., runbook-test, ...]}` |
| MCP-P-11 | `project_mcp_disable` | `{mcp_name:"runbook-test", project:<P>}` | `{disabled, project}` |
| MCP-P-12 | `project_mcp_unregister` | `{mcp_name:"runbook-test"}` | `{unregistered}`. P-08 no longer lists it. |

### task_* (6 tools)

| ID | Tool | Args | Verify |
|----|------|------|--------|
| MCP-T-01 | `task_add` | `{title:"runbook task", folder_path:"/"}` | Returns task with `id` (numeric). Save id. |
| MCP-T-02 | `task_find` | `{folder_path:"/"}` | `{tasks:[..., {id, title:"runbook task"}, ...]}` |
| MCP-T-03 | `task_get` | `{task_id:<id>}` | Full task row |
| MCP-T-04 | `task_update` | `{task_id, title:"renamed", description:"x", status:"done"}` | Returns updated row |
| MCP-T-05 | `task_find` (with pattern) | `{pattern:"renamed"}` | `{matches:[..., {id}, ...]}` |
| MCP-T-06 | `task_move` | `{task_id, folder_path:"/inbox"}` | `{moved:true, task_id, folder_path:"/inbox"}` |

After T-06 mark done by setting status=archived via T-04 to keep test DB clean.

### log_* (1 tool)

| ID | Tool | Args | Verify |
|----|------|------|--------|
| MCP-L-01 | `log_find` | `{level:"ERROR", since:"1h", limit:10}` | `{count:N, logs:[{id, ts, level:"ERROR", module, message, context}, ...]}`. Empty array is acceptable; `count` matches `logs.length`. |
| MCP-L-02 | `log_find` (pattern) | `{pattern:"qdrant", since:"24h", limit:5}` | Pattern is regex over message + context; rows that don't match the regex are filtered. |
| MCP-L-03 | `log_find` (since formats) | `{since:"30m"}` then `{since:"2026-04-28T00:00:00Z"}` | Both forms accepted. Invalid form (e.g. `{since:"notatime"}`) returns HTTP 400. |

### Negative-path coverage (validation/security)

| ID | Tool | Args | Expected |
|----|------|------|----------|
| MCP-NEG-01 | `nonexistent_tool` | `{}` | HTTP 404, `{error:"Unknown tool: nonexistent_tool"}` |
| MCP-NEG-02 | `file_read` | `{}` | HTTP 400, error mentions `path required` |
| MCP-NEG-03 | `file_read` | `{path:"../../../etc/passwd"}` | HTTP 403, `path traversal blocked` |
| MCP-NEG-04 | `file_create` | `{path:"x", content:"x"}` then same again | Second call HTTP 409, `file already exists` |
| MCP-NEG-05 | `file_update` | `{path:"missing.txt", content:"x"}` | HTTP 404 |
| MCP-NEG-06 | `task_get` | `{task_id:"abc"}` | HTTP 400, `task_id` |
| MCP-NEG-07 | `session_info` | `{session_id:"has spaces"}` | HTTP 400, invalid format |
| MCP-NEG-08 | `session_send_key` | `{session_id, key:"NotAKey"}` | HTTP 400, `invalid key` |
| MCP-NEG-09 | `session_wait` | `{seconds:0}` | HTTP 400 |
| MCP-NEG-10 | `session_send_text` | `{session_id:"<dead-session-id>", text:"x"}` | HTTP 410, `tmux session not running` |
| MCP-NEG-11 | `log_find` | `{level:"FOO"}` | HTTP 400, `invalid level` |
| MCP-NEG-12 | `log_find` | `{since:"notatime"}` | HTTP 400, `invalid since` |

### Coverage assertion

After Phase 14 completes, **every one of the 44 flat tools must have at least one PASS row above** (positive path) and at least one of MCP-NEG-* must touch each error category (404 unknown / 400 validation / 403 traversal / 410 dead session / 409 conflict). If any tool has no positive coverage, file an issue and FAIL Phase 14 as a whole.

---

## Phase 14b: Live e2e CLI session driving

These exercise the `session_*` tools against real CLI panes (not just tmux schemas). Run after Phase 14 catalogue passes.

### MCP-E2E-01: Claude — full conversation cycle via MCP only
**Steps:**
1. `session_new {cli:"claude", project:<P>, name:"mcp-e2e-claude"}`
2. `session_wait {seconds:5}` — CLI startup
3. `session_read_screen {session_id}` — verify Claude is at an empty prompt (no auth dialog blocking)
4. `session_send_text {session_id, text:"What is 2+2?"}`
5. `session_send_key {session_id, key:"Enter"}`
6. `session_wait {seconds:15}`
7. `session_read_screen {session_id}` — screen contains `4` somewhere
8. `session_read_output {session_id, project}` — structured transcript shows the user message + assistant response
9. `session_kill {session_id}`

**Verify:** Each step returns the expected shape. Final read confirms a complete user→assistant exchange. No tmux primitives leaked into the agent's vocabulary anywhere.

### MCP-E2E-02: Gemini — startup-aware drive
**Steps:** Like E2E-01 but `cli:"gemini"`, with extra `session_send_key {key:"Enter"}` after the first send if read_screen shows the text in the multiline editor without "Thinking…".

### MCP-E2E-03: Codex — trust dialog handled via MCP
**Steps:**
1. `session_new {cli:"codex", project:<P>, name:"mcp-e2e-codex"}`
2. `session_wait {seconds:5}`
3. `session_read_screen` — likely shows trust dialog
4. `session_send_key {key:"1"}` (or whichever option = trust) + `session_send_key {key:"Enter"}`
5. Continue as E2E-01.

**Verify:** Trust dialog dismissed using MCP only — no shell-out, no direct tmux commands. End-to-end conversation completes.

### MCP-E2E-04: Hidden flag default
**Action:** `session_new {cli:"claude", project:<P>, name:"hidden-default"}` — no `hidden` arg.
**Verify:** `GET /api/state` shows the session with `state:"hidden"`. Sidebar (default Active filter) does NOT show it.

### MCP-E2E-05: Hidden flag explicit override
**Action:** `session_new {cli:"claude", project:<P>, name:"visible-explicit", hidden:false}`.
**Verify:** Session has `state:"active"`. Visible in sidebar Active filter.

---

## Phase 15: Recent regression coverage

Tests for the user-facing fixes shipped in the canonical branch but not yet in the REG-* set.

### REG-220: Auto-respawn passes --resume so JSONL stays the same
**Issue:** #220 — ws-terminal silently re-keyed Claude sessions to a new UUID across container restarts.
**Steps:**
1. Open a Claude session via `+` button. Note `session_id` and the JSONL path.
2. `ssh ${WORKBENCH_HOST} docker exec ${WORKBENCH_CONTAINER} tmux kill-session -t <tmux>` (simulate idle cleanup).
3. Click the same session in the sidebar to reconnect — auto-respawn should fire.
4. `browser_evaluate`: confirm the active tab's `id` still matches the original `session_id`.
5. `ssh ${WORKBENCH_HOST} docker exec ${WORKBENCH_CONTAINER} stat /data/.claude/projects/<encoded>/<session_id>.jsonl` — file still grows on next message.
6. **Negative path:** delete that JSONL on disk, repeat the kill+reconnect → should refuse with a `WARN: Refusing to auto-respawn — JSONL missing` log. Tab shows error.

### REG-220-UI: Status bar token count tracks the live JSONL
**Steps:** After REG-220 step 4, send a message in the reattached session. The status bar Context value should increase. Sidebar message count should increment. (Pre-fix: both stayed stuck on the dead file's count.)

### REG-221: Vector search "none" provider keeps qdrant quiet
**Issue:** #221.
**Already covered:** VEC-01..VEC-21 (Phase 9). Re-confirm by checking container logs for absence of `qdrant: configured but probe failed` on a fresh deploy with `vector_embedding_provider="none"`.

### REG-222: qdrant restart race with rapid setting changes
**Issue:** #222.
**Steps:**
1. Have provider `gemini` configured + scanning.
2. Rapidly PUT `/api/settings` `vector_embedding_provider` → `huggingface` → `none` → `gemini` (4 calls within 1s).
3. Watch container logs.
**Verify:** No error spam during teardown. Final state is `gemini` running. No "No embedding API key configured" errors after stop().

### REG-223-VIS: Primary buttons in dark theme are readable
**Issue:** #223.
**Action:** UI screenshot of `+ → Claude` modal (Start Session button), `Add Project` modal, and the auth-link panel. Visual check: button background is `#1f6feb` (or `--btn-primary` token), not the old too-light blue.

### REG-224: File-tree row click — icon area expands the folder
**Issue:** #224.
**Steps:**
1. Open the right-panel Files tab. Expand `/data/workspace`.
2. Find any directory LI in the tree.
3. Click 8px from the LI's left edge (the icon area).
**Verify:** LI gains class `expanded` and shows children. (Pre-fix: clicks in icon area did nothing.)

### REG-225-UI: Default-model dropdown shows aliases (no version pins)
**Issue:** #225.
**Steps:** Settings → Claude Code → Default Model dropdown.
**Verify:** Options are exactly `Opus`, `Sonnet`, `Haiku` (3 options, in that order). No version numbers visible. Selecting `Sonnet` and reopening shows `Sonnet` retained.

### REG-225-MIG: Legacy versioned DB value normalized to alias on load
**Steps:**
1. `ssh ${WORKBENCH_HOST} docker exec ${WORKBENCH_CONTAINER} sqlite3 /data/workbench.db "UPDATE settings SET value='\"claude-opus-4-6\"' WHERE key='default_model'"`
2. Reload Settings → Claude Code.
**Verify:** Dropdown shows `Opus` (alias), DB row still has the legacy value, and re-saving to a different option writes the alias form (`"sonnet"`).

### REG-226: Settings save flashes a Saved indicator
**Issue:** #226.
**Steps:** Open Settings. Toggle any field. Within 1.5s of the change a `#settings-saved-indicator` element appears in top-right of the modal with text `✓ Saved`. After ~1.5s, opacity transitions to 0.

### REG-227: Session-name field replaces the prompt textarea
**Issue:** #227.
**Steps:** `+ → Claude`.
**Verify:**
- Modal label is `Session name`.
- Field is a single-line `<input id="new-session-name" type="text" maxlength="60">`.
- Old `#new-session-prompt` is gone.
- Submitting `"My session"` posts `{project, name, cli_type}` (not `prompt`). Sidebar shows `My session`.
- For Claude, after attach, the CLI receives a brief stand-by hint (verifiable via `session_read_screen` or container tmux capture-pane). It does NOT execute a free-form prompt.

### REG-228-A: File tree does not collapse on tab close
**Issue:** #228.
**Steps:**
1. Files panel open. Expand a sub-directory.
2. Open any file in the editor (double-click).
3. Close the file editor tab.
**Verify:** The previously-expanded sub-directory is still expanded. (Pre-fix: tree fully collapsed on tab close.)

### REG-228-B: Manual ↻ button preserves expanded state
**Steps:**
1. Files panel: expand a sub-directory.
2. Click `↻` (`#panel-refresh-files`).
**Verify:** After the rebuild settles (~2s), the same sub-directory is expanded again.

### REG-MCP-REWORK-01: Old action-router shape is gone
**Steps:** `POST /api/mcp/call {tool:"workbench_files", args:{action:"list"}}`
**Verify:** HTTP 404 with `Unknown tool: workbench_files`. Same for `workbench_sessions`, `workbench_tasks`. Confirms migration is irreversible — old saved sessions referencing those names will get a clean error rather than silent misbehavior.

### REG-MCP-REWORK-02: No double-prefix anywhere
**Steps:** Spawn `mcp-server.js` and read `tools/list`.
**Verify:** No tool name contains `workbench_` (the inner prefix). All names are `<domain>_<verb>`. Server name is `workbench` (single outer prefix).

---
## Troubleshooting

| Symptom | Likely Cause | Action |
|---------|-------------|--------|
| `browser_navigate` times out or returns blank page | Container is down or not listening on its expected port | Verify container is running: `ssh ${WORKBENCH_HOST} docker ps`. Restart if needed: `ssh ${WORKBENCH_HOST} docker restart ${WORKBENCH_CONTAINER}`. Retry after 10s. |
| `/health` returns non-200 or fetch fails | Server process crashed inside container | Check container logs: `docker logs ${WORKBENCH_CONTAINER} --tail 50`. Restart container. |
| `/api/auth/status` returns `{valid:false}` | Auth token expired | Complete the auth flow: show `#auth-modal`, follow the link, paste the code. All tests requiring Claude responses will fail without valid auth. |
| WebSocket `readyState` stays 0 or 3 | WebSocket endpoint unreachable or server overloaded | Wait 5s and recheck. If persistent, `browser_refresh` and reopen the session tab. |
| `activeTabId` is null | No session tab is open | Click a session in the sidebar to open a tab before running tab-dependent tests. |
| `browser_click` does nothing (no DOM change) | Element obscured by modal/overlay, or element not rendered yet | Dismiss any open modals first (see baseline reset). Add `browser_wait` 500 before retrying. |
| Session creation via API returns 500 | No projects exist, or tmux is full | Create a project first via `POST /api/projects`. Check `docker exec ${WORKBENCH_CONTAINER} tmux list-sessions` for tmux limits. |
| SMOKE-01 fails | App not loading at all | Stop execution. Investigate container health. No downstream tests are valid. |
| Tests see stale data after state changes | Sidebar not refreshed | Call `browser_evaluate`: `loadState()` then `browser_wait` 2000 before re-checking. |
| `#new-session-name` not found | Overlay not opened; + button click missed | Retry `browser_click` on `.project-group .new-btn`. Ensure the project group is expanded (not collapsed). |
