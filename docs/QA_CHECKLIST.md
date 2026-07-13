# Brok's Forge — Manual QA Checklist

A professional, release-oriented manual test plan. Work top to bottom before a release, or run the
relevant section after a targeted change. Each case is independent and written so anyone on the team
can execute it without tribal knowledge.

## How to use

- Duplicate this file per release (e.g. `QA_CHECKLIST_v1.1.0.md`) and fill it in, or track results in a sheet.
- Set the **Status** cell to exactly one outcome.
- Record what you actually saw in **Actual**; add environment/repro details in **Notes**.

**Status legend** — mark one per row: `✅ PASS` · `❌ FAIL` · `⛔ BLOCKED` · `⬜ NOT TESTED`.

**Environment under test:** `docker compose up --build` → frontend `http://localhost:3000`, backend
`http://localhost:8080`, Swagger `http://localhost:8080/swagger-ui.html`.

---

## Automated verification status (2026-07-07)

A **Feature Validation** pass verified CRUD and core behaviour **automatically** against real
infrastructure. Rows below whose behaviour is covered by that automation are marked `✅ PASS` with the
evidence source in **Notes**; rows that are purely visual/interactive (or need a live third-party key)
were **not** executed here and remain `⬜ NOT TESTED`.

- **AIT** — backend integration test (JUnit 5 + MockMvc + **Testcontainers PostgreSQL 16**, real Flyway
  + `ddl-validate` + security). Full suite: **225 tests, 0 failures**.
- **E2E** — Playwright against the live stack (`http://localhost:3000` + `:8080`). **32 tests, 0 failures**.
- **UT** — pure unit test (no Spring context).

Result: **0 product bugs** found or introduced. All CRUD across every module (create / read / update /
soft-delete / slug generation & reuse / duplicate handling / validation / pagination / filtering /
search / tenant isolation / permissions / DB & Flyway integrity) is green. Every failure encountered
during the pass was a test-expectation/test-code bug and was fixed in the test code only. Note: there
is **no "restore" of a soft-deleted aggregate by design** — the lifecycle is soft-delete (one-way) plus
archive/unarchive (status); rows referencing "restore" are interpreted as the archive/unarchive toggle.

---

## 1. Registration

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| REG-001 | Register a new account | Go to `/register` → fill first/last/email/valid password → Create account | Account created, redirected to `/dashboard`, success toast | Register via UI lands on `/dashboard` | ✅ PASS | E2E `auth.spec` |
| REG-002 | Password strength meter | Type increasingly strong passwords | Meter updates weak→strong live | | ⬜ NOT TESTED | Visual — not automated |
| REG-003 | Weak password rejected | Enter `weak` as password → submit | Inline validation error; no account created | Server rejects weak password (400) | ✅ PASS | AIT `AuthControllerIntegrationTest` (validation) |
| REG-004 | Invalid email rejected | Enter `not-an-email` → submit | Inline "valid email" error | Server rejects malformed email (400) | ✅ PASS | AIT `AuthControllerIntegrationTest` |
| REG-005 | Duplicate email | Register with an already-registered email | 409 error toast; no duplicate account | Duplicate register → 409 | ✅ PASS | AIT `AuthControllerIntegrationTest` |
| REG-006 | Caps-lock warning | Focus password, enable Caps Lock | Caps-lock hint shown | | ⬜ NOT TESTED | Visual — not automated |
| REG-007 | Show/hide password | Click the eye toggle | Password text toggles visibility | | ⬜ NOT TESTED | Visual — not automated |

## 2. Email Verification

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| EMV-001 | Verification email sent on register | Register → check backend logs (dev LoggingEmailService) | A verification link is logged | | ⬜ NOT TESTED | Not in this pass |
| EMV-002 | Verify with valid token | POST `/api/v1/auth/verify-email` with the token | 200; email marked verified | | ⬜ NOT TESTED | Not in this pass |
| EMV-003 | Verify with invalid/expired token | Use a garbage token | 401 invalid/expired | | ⬜ NOT TESTED | Not in this pass |
| EMV-004 | Resend verification | POST `/api/v1/auth/resend-verification` | Always 200 (no account enumeration) | | ⬜ NOT TESTED | Not in this pass |

## 3. Forgot Password

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| FGP-001 | Request reset for existing email | `/forgot-password` → submit registered email | Generic "if an account exists…" message; reset link logged | Generic confirmation shown | ✅ PASS | E2E `auth.spec` (generic confirmation) |
| FGP-002 | Request reset for unknown email | Submit an unregistered email | Same generic message (no enumeration) | Same generic message (no enumeration) | ✅ PASS | E2E `auth.spec` |
| FGP-003 | Contact Developer link present | View the page footer | "Need help? Contact Developer" → https://gokul.quest (new tab) | | ⬜ NOT TESTED | Visual — not automated |

## 4. Password Reset

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| RSP-001 | Reset with valid token | Open `/reset-password?token=…` → set a strong new password | Success; can log in with the new password | | ⬜ NOT TESTED | Needs a live token — not automated |
| RSP-002 | Reset with invalid token | Use a garbage token | Error (invalid/expired) | Invalid token surfaces an error | ✅ PASS | E2E `auth.spec` |
| RSP-003 | Old sessions revoked | Reset password, then reuse an old refresh token | Old token rejected | | ⬜ NOT TESTED | Not in this pass |

## 5. OTP Verification (Password Change — ADR 0017)

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| OTP-001 | Request code | Settings → enter current password → request code | 200; 6-digit code emailed (logged in dev); wizard moves to code step | Requesting a code advances the wizard to code entry | ✅ PASS | E2E `otp-password-change.spec` |
| OTP-002 | Wrong current password | Enter an incorrect current password | 401; no code sent | | ⬜ NOT TESTED | Not automated in this pass |
| OTP-003 | Verify correct code | Enter the emailed code | 200; single-use ticket issued; wizard moves to new-password step | | ⬜ NOT TESTED | Needs the emailed code — not automated |
| OTP-004 | Verify wrong code | Enter an incorrect code | 400; attempts counter increments | | ⬜ NOT TESTED | Not automated in this pass |
| OTP-005 | Attempt lockout | Enter wrong code 5× | 429 locked; must request a new code | | ⬜ NOT TESTED | Not automated in this pass |
| OTP-006 | Code expiry | Wait > 5 minutes, then verify | Code rejected as expired | | ⬜ NOT TESTED | Time-based — not automated |
| OTP-007 | Generation rate limit | Request codes repeatedly | Throttled after the limit (429) | | ⬜ NOT TESTED | Rate-limit disabled in test profile |

## 6. Password Change (completion)

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| PWC-001 | Complete change with ticket | Enter a strong new password with a valid ticket | 200; all sessions revoked; must sign in again | | ⬜ NOT TESTED | Needs a live OTP ticket — not automated |
| PWC-002 | Ticket single-use | Reuse a consumed ticket | Rejected | | ⬜ NOT TESTED | Not automated in this pass |
| PWC-003 | Weak new password | Submit a weak new password | Validation error | | ⬜ NOT TESTED | Not automated in this pass |
| PWC-004 | Confirmation email | Complete a change | "Password changed" email logged/sent | | ⬜ NOT TESTED | Not automated in this pass |

## 7. Idle Timeout (FIX 3)

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| IDLE-001 | Activity resets timer | Interact (mouse/keys/scroll) periodically | No logout while active | | ⬜ NOT TESTED | Time-based — not automated |
| IDLE-002 | Warning modal before logout | Stay idle until ~60s before timeout | "Your session is about to expire" modal with countdown | | ⬜ NOT TESTED | Time-based — not automated |
| IDLE-003 | Stay signed in | Click "Stay signed in" in the modal | Modal closes; timer resets; stays logged in | | ⬜ NOT TESTED | Time-based — not automated |
| IDLE-004 | Auto logout | Stay fully idle past the timeout | Logged out → `/login?reason=session-expired` with banner | Session-expired banner renders on `/login` | ✅ PASS | E2E `session-timeout.spec` (banner); timer itself is manual |

## 8. Login & Logout

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| LOGIN-001 | Valid login | Enter valid credentials | Redirect to `/dashboard`; welcome toast | Login lands on `/dashboard` | ✅ PASS | E2E `auth.spec` |
| LOGIN-002 | Wrong password | Enter a wrong password | Stays on `/login`; error toast; no token | Stays on `/login` with an error | ✅ PASS | E2E `auth.spec` |
| LOGIN-003 | Unknown email | Log in with an unregistered email | 401 generic error | Invalid credentials → 401 | ✅ PASS | AIT `AuthControllerIntegrationTest` |
| LOGIN-004 | Session-expired banner | Visit `/login?reason=session-expired` | Inactivity banner shown | Banner shown | ✅ PASS | E2E `session-timeout.spec` |
| LOGOUT-001 | Logout | Avatar menu → Log out | Redirect to `/login`; token cleared; back button cannot re-enter | Logout returns to `/login` | ✅ PASS | E2E `auth.spec` |

## 9. Refresh Token

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| REF-001 | Access token refresh | Let the access token expire; make a request | Refresh rotates the pair; request succeeds | | ⬜ NOT TESTED | Not automated in this pass |
| REF-002 | Rotation invalidates old | Reuse a rotated refresh token | Rejected (401) | | ⬜ NOT TESTED | Not automated in this pass |
| REF-003 | Logout revokes refresh | Log out, then use the refresh token | Rejected | | ⬜ NOT TESTED | Not automated in this pass |

## 10. Organizations

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| ORG-001 | Create organization | Create with a valid name | 201; appears in list; creator is OWNER | 201; slug generated; creator OWNER; memberCount 1 | ✅ PASS | AIT `OrganizationCrudIntegrationTest` |
| ORG-002 | Blank name rejected | Submit an empty name | 400 validation | Blank/short name → 400 | ✅ PASS | AIT `OrganizationCrudIntegrationTest` |
| ORG-003 | Slug uniqueness (live) | Create two orgs with the same name | Second slug auto-suffixed; no error | Second slug `…-2`; explicit dup slug → 409 | ✅ PASS | AIT `OrganizationCrudIntegrationTest` |
| ORG-004 | Reuse slug after delete | Delete an org, recreate with the same name | Succeeds (partial-unique index, V30) | Slug freed after soft-delete; recreate OK | ✅ PASS | AIT `OrganizationCrudIntegrationTest` |
| ORG-005 | Cross-tenant isolation | Access an org id you are not a member of, or a foreign project/agent id | Non-member org → **403** (membership checked first); foreign project/agent/dataset id → **404**. No existence leak either way | Non-member → 403; foreign resource → 404 | ✅ PASS | AIT `OrganizationCrudIntegrationTest`, `ProjectCrudIntegrationTest` (deny-by-default) |
| ORG-006 | Members & roles | Add a member; change role | Role updates; permissions reflect | Add/list members; role change; last-owner & OWNER-grant guards | ✅ PASS | AIT `OrganizationCrudIntegrationTest` |

## 11. Projects

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| PROJ-001 | Create project | Create under an org | 201; appears under the org | 201; linked to org; listed | ✅ PASS | AIT `ProjectCrudIntegrationTest` |
| PROJ-002 | Unique slug per org | Two projects, same name | Second auto-suffixed | Second `…-2`; same slug OK in another org | ✅ PASS | AIT `ProjectCrudIntegrationTest` |
| PROJ-003 | Reuse slug after delete | Delete then recreate same name | Succeeds (V30) | Slug freed after soft-delete | ✅ PASS | AIT `ProjectCrudIntegrationTest` |
| PROJ-004 | Archive / restore | Archive a project (status), then set active again | Status toggles; lists filter correctly | Archive via PATCH status; delete requires ADMIN | ✅ PASS | AIT `ProjectCrudIntegrationTest` |

## 12. Agents

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| AGENT-001 | Register (Custom REST / Python / API Key) | Register with the Groq endpoint scenario | 201; redirected to onboarding on the Credentials tab | 201; API-key agent registers as not-yet-credentialed | ✅ PASS | AIT `AgentRegistrationIntegrationTest`; E2E `agents.spec` |
| AGENT-002 | Register (auth = None) | Register a NONE-auth agent | 201; no onboarding; usable immediately | 201; `credentialConfigured=true` | ✅ PASS | AIT `AgentCrudIntegrationTest` |
| AGENT-003 | Reuse slug after delete | Register "X", delete it, register "X" again | Succeeds (V30 fix; previously 409 "data constraint") | Slug reused after soft-delete | ✅ PASS | AIT `AgentRegistrationIntegrationTest` |
| AGENT-004 | Live duplicate name | Register "X" twice without deleting | Second slug auto-suffixed `-2` | Second slug `…-2` | ✅ PASS | AIT `AgentRegistrationIntegrationTest` |
| AGENT-005 | All frameworks | Register one agent per framework (Spring AI…Custom REST, Other) | All persist | | ⬜ NOT TESTED | Enum matrix not exhaustively automated |
| AGENT-006 | All languages | Register per language (Java…Rust, Other) | All persist | | ⬜ NOT TESTED | Enum matrix not exhaustively automated |
| AGENT-007 | All capabilities | Toggle each capability combo | Persist and display correctly | Capabilities persist (sampled) | ✅ PASS | AIT `AgentRegistrationIntegrationTest` (representative set) |
| AGENT-008 | Setup-required badge | View an auth agent without a credential in `/agents` | "Setup required" badge shown | Badge shown for uncredentialed API-key agent | ✅ PASS | E2E `agents.spec` |
| AGENT-009 | Edit agent | Change name/description/visibility | Saved; reflected in list | Update saved; invalid endpoint → 400; archived → 409 | ✅ PASS | AIT `AgentCrudIntegrationTest` |
| AGENT-010 | Delete agent | Soft-delete an agent | Removed from lists; slug freed | Soft-delete → 404 on read; MEMBER cannot delete | ✅ PASS | AIT `AgentCrudIntegrationTest` |

## 13. Credentials (FIX 1)

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| CRED-001 | Set API-Key credential | Configure name/header/prefix/secret | Saved; credential status shows configured | Saved; `credentialConfigured=true`; masked hint | ✅ PASS | AIT `AgentCredentialCrudIntegrationTest` |
| CRED-002 | Secret never returned | Inspect the credentials API response | Only masked hint; no plaintext/ciphertext | Secret absent from all responses; only `secretHint` | ✅ PASS | AIT `AgentCredentialCrudIntegrationTest`, `AgentRegistrationIntegrationTest` |
| CRED-003 | Test connection (valid key) | Configure a valid Groq key → Test Connection | Success (probes `GET …/openai/v1/models`) | | ⬜ NOT TESTED | Needs a live Groq key; probe strategy covered by UT `HealthProbePlannerTest` |
| CRED-004 | Test connection (bad key) | Use an invalid key → Test Connection | "Authentication rejected (HTTP 401)" | | ⬜ NOT TESTED | Needs live network; dry-run path covered by CRED-005 |
| CRED-005 | Test before save | Test a draft credential before saving | Dry-run result without persisting | Dry-run returns a result; nothing persisted | ✅ PASS | AIT `AgentCredentialCrudIntegrationTest` (fast-fail endpoint) |
| CRED-006 | Update (keep secret) | Edit label, leave secret blank | Existing secret retained | Blank secret keeps stored hint | ✅ PASS | AIT `AgentCredentialCrudIntegrationTest` |
| CRED-007 | Replace secret | Save a new secret | Rotates; hint updates | New secret rotates; hint changes | ✅ PASS | AIT `AgentCredentialCrudIntegrationTest` |
| CRED-008 | Delete credential | Delete the active credential | Removed; agent shows "setup required" again | Deleted; `credentialConfigured=false` | ✅ PASS | AIT `AgentCredentialCrudIntegrationTest` |
| CRED-009 | Auth types | Configure API Key / Bearer / Basic / Custom Header | Each saves and builds the correct header | Per-type field validation enforced | ✅ PASS | AIT `AgentCredentialCrudIntegrationTest` |
| CRED-010 | Non-admin restricted | View/manage credentials as a MEMBER | Restricted (admin-only) | MEMBER → 403 | ✅ PASS | AIT `AgentCredentialCrudIntegrationTest` |
| CRED-011 | Native Ollama — test connection | Configure a native Ollama provider (`host.docker.internal`/`localhost`/`127.0.0.1`) → Test Connection | Success; probes `GET /api/tags`; no `BROKSFORGE_MODEL_ALLOW_PRIVATE_TARGETS` needed | Trusted without the env var; probe shows `GET_MODELS · …/api/tags` | ✅ PASS | Verified live against a real Ollama instance |
| CRED-012 | Native Ollama — refresh models | On a configured Ollama provider, click Refresh Models | Model list populates from the live Ollama instance | | ⬜ NOT TESTED | Not exercised as a standalone case this pass — covered indirectly by CRED-011 |
| CRED-013 | Custom REST on localhost still blocked (regression) | Configure a Custom REST provider pointed at `localhost`/`127.0.0.1` → Test Connection | Blocked by `OutboundUrlGuard` (SSRF) — the Ollama trust bypass must **not** leak to Custom REST | Custom REST on localhost still rejected | ✅ PASS | UT `OutboundUrlGuardTest` (remote providers/Custom REST unaffected by the Ollama bypass) |
| CRED-014 | Google AI Studio — test connection | Configure a Google AI Studio (Gemini) provider with a valid key → Test Connection | Success; probe strategy/URL shown | | ⬜ NOT TESTED | Needs a live Google AI Studio key |
| CRED-015 | Google AI Studio — refresh models | On a configured Google AI Studio provider, click Refresh Models | Model list populates | | ⬜ NOT TESTED | Needs a live Google AI Studio key |
| CRED-016 | Groq/OpenAI-compatible — auth-failure handling | Configure a Groq/OpenAI-compatible provider with a bad key → Test Connection | "Authentication rejected (HTTP 401)" surfaced clearly, not a generic error | | ⬜ NOT TESTED | Needs live network; dry-run auth-failure path not exercised as a distinct case this pass |

## 14. Health Checks (FIX 9 / provider-aware)

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| HEALTH-001 | Groq agent probe | Run check on a Groq chat/completions agent | Probes `GET …/models` (GET_MODELS); not 404 | Groq/OpenAI-compat → GET_MODELS strategy | ✅ PASS | UT `HealthProbePlannerTest` |
| HEALTH-002 | Spring AI agent | Run check on a Spring AI agent | Probes `/actuator/health` | Spring AI → actuator health strategy | ✅ PASS | UT `HealthProbePlannerTest` |
| HEALTH-003 | FastAPI/LangGraph agent | Run check | Probes `/health` | Python frameworks → `/health` strategy | ✅ PASS | UT `HealthProbePlannerTest` |
| HEALTH-004 | Healthy status | Probe returns 2xx | Status HEALTHY; latency shown | | ⬜ NOT TESTED | Needs a reachable 2xx endpoint |
| HEALTH-005 | Unhealthy status | Probe returns 5xx / unreachable | Status UNHEALTHY; failure reason shown | Unreachable endpoint → not HEALTHY; success=false | ✅ PASS | AIT `AgentHealthIntegrationTest` |
| HEALTH-006 | History + availability | Run several checks | Availability % + recent history correct | Empty summary; history paginates; totals update | ✅ PASS | AIT `AgentHealthIntegrationTest` |
| HEALTH-007 | No probe during registration | Register an agent | No health check runs at registration time | New agent `healthStatus=UNKNOWN`, 0 checks | ✅ PASS | AIT `AgentCrudIntegrationTest`, `AgentHealthIntegrationTest` |
| HEALTH-008 | Probe strategy recorded | Inspect a check | probeStrategy + probeUrl stored & displayed | Recorded on each check | ✅ PASS | AIT `AgentHealthIntegrationTest` |
| HEALTH-009 | Native Ollama probes `/api/tags` | Run a health check on a native Ollama agent (`/api/chat` base URL) | Probes `GET /api/tags` (model listing), not `GET /api/chat` (which 405s) | Health check correctly targets `/api/tags`; no false UNHEALTHY from the previous `/api/chat` 405 | ✅ PASS | Verified live against a real Ollama instance |
| HEALTH-010 | Agent Health page shows exact probe detail | Open Agent Health for any agent, run a check | Shows exact `METHOD URL` and `✓ HTTP 200 · Nms` / failure reason, not a generic "Probe: GET endpoint" message | `health-panel.tsx` renders the concrete method/URL and outcome | ✅ PASS | Verified live in the UI |

## 15. Versions

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| VER-001 | Register version | Add a version (model/provider/env) | Created; listed | Created; sequence assigned; dup number → 409 | ✅ PASS | AIT `AgentVersionCrudIntegrationTest` |
| VER-002 | Activate version | Activate a version | Becomes current active | Activating deactivates prior; pointer moves | ✅ PASS | AIT `AgentVersionCrudIntegrationTest` |
| VER-003 | Rollback | Roll back to a prior version | Active pointer moves; no data lost | Rollback re-activates; gated on rollback-ready | ✅ PASS | AIT `AgentVersionCrudIntegrationTest` |

## 16. Advisor

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| ADV-001 | Agent advisor gated | Open Advisor for an agent lacking credentials | Gated with "configure credentials" prompt | | ⬜ NOT TESTED | UI gating — not automated (API returns 200 + notes) |
| ADV-002 | Advisory report renders | Open Advisor for a ready agent | Recommendations render | Agent advisory → 200; foreign agent → 404 | ✅ PASS | AIT `AdvisorRootCauseDebuggerIntegrationTest` |
| ADV-003 | Project advisory | Open project-level advisor | Aggregated recommendations | Project advisory → 200 with notes | ✅ PASS | AIT `AdvisorRootCauseDebuggerIntegrationTest` |
| ADV-004 | Distinct knowledge keys per finding type | Trigger `AgentAdvisor` findings for missing auth, insecure transport, and missing healthcheck on the same agent | Each finding type reports its own `knowledgeKey` (`MISSING_AUTH`, `INSECURE_TRANSPORT`, `MISSING_HEALTHCHECK`) — none share a key | Keys are distinct; knowledge-graph occurrence tracking no longer conflates the three finding types | ✅ PASS | Fixed and verified during live Phase 1 smoke testing (`AgentAdvisor.auth()`/`transport()`) |

## 17. Datasets

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| DS-001 | Create dataset | Create with a name | 201; appears in `/datasets` | 201; slug generated; empty version state | ✅ PASS | AIT `DatasetCrudIntegrationTest` |
| DS-002 | Upload version (CSV/JSON) | Add a version with content | Items parsed; item count updates | CSV & JSON import; items + columns + checksum | ✅ PASS | AIT `DatasetCrudIntegrationTest` |
| DS-003 | Immutable versions | Attempt to edit an existing version | Not allowed (new version instead) | New import bumps version; no edit endpoint | ✅ PASS | AIT `DatasetCrudIntegrationTest` |
| DS-004 | Reuse slug after delete | Delete then recreate same name | Succeeds (V30) | Slug freed after soft-delete; MEMBER cannot delete | ✅ PASS | AIT `DatasetCrudIntegrationTest` |
| DS-005 | Stats | View dataset stats | Coverage/averages correct | itemCount / coverage correct | ✅ PASS | AIT `DatasetCrudIntegrationTest` |

## 18. Prompts

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| PROMPT-001 | Create prompt | Create with a name | 201; listed | 201; slug generated | ✅ PASS | AIT `PromptCrudIntegrationTest` |
| PROMPT-002 | Version + activate | Add a version, activate it | One active version at a time | First auto-activates; activate/rollback move pointer | ✅ PASS | AIT `PromptCrudIntegrationTest` |
| PROMPT-003 | Templating variables | Use `{{variables}}` | Variables detected/rendered | Distinct variables extracted; comparison diffs them | ✅ PASS | AIT `PromptCrudIntegrationTest` |
| PROMPT-004 | Reuse slug after delete | Delete then recreate | Succeeds (V30) | Slug freed after soft-delete | ✅ PASS | AIT `PromptCrudIntegrationTest` |

## 19. Evaluations (FIX 2)

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| EVAL-001 | Prerequisites empty states | Open "New evaluation" with no data | Guided empty states (create dataset/prompt/agent) — no dead end | Evaluations page loads with a create entry point | ✅ PASS | E2E `evaluations-benchmarks.spec` (page load); backend enforces prereqs |
| EVAL-002 | Run when ready | Create a job with agent + dataset | Job created; runs (or PENDING if autoRun off) | Create PENDING job; `/run` reaches terminal state | ✅ PASS | AIT `EvaluationJobCrudIntegrationTest` |
| EVAL-003 | Gate on unusable agent | Select an agent lacking credentials | "Create evaluation" disabled + warning | | ⬜ NOT TESTED | UI gating — not automated |
| EVAL-004 | Results view | Open a completed job | Runs/results, metrics, pass rate shown | Runs recorded; runs/results endpoints reachable | ✅ PASS | AIT `EvaluationJobCrudIntegrationTest` |
| EVAL-005 | Profile scoring | Attach a scoring profile | Metrics applied per profile | Job references profile; profile metric validation | ✅ PASS | AIT `EvaluationJobCrudIntegrationTest`, `EvaluationProfileCrudIntegrationTest` |
| EVAL-006 | Model resolution precedence | Create jobs covering: (a) no model set anywhere → provider default; (b) agent version override set, no eval override → agent override wins; (c) evaluation-level override set → it wins over both; (d) no model resolves anywhere and the endpoint requires one → clear validation error, no silent drop | Precedence is provider default → agent override → evaluation override (highest), and a still-missing required model fails validation before any HTTP call | Precedence verified live: an Ollama provider with only `defaultModel: llama3.2:1b` set (no override anywhere else) resolved and completed the job | ✅ PASS | Verified live against a real Ollama instance; `AgentInvocationTarget.fallbackModel()` / `HealthProbePlanner.requiresModelField` |
| EVAL-007 | Native Ollama run with no model override | Create an evaluation job against a native Ollama agent with no model override at any level, provider's `defaultModel` set | Job resolves to the provider's default model and completes; no `BROKSFORGE_MODEL_ALLOW_PRIVATE_TARGETS` needed | Job resolved to `llama3.2:1b` and completed successfully | ✅ PASS | Verified live against a real Ollama instance |
| EVAL-008 | Google AI Studio — live evaluation | Create and run an evaluation job against an agent backed by a Google AI Studio (Gemini) provider | Job completes with real model calls | | ⬜ NOT TESTED | Needs a live Google AI Studio key |

## 20. Benchmarks

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| BENCH-001 | Create benchmark | Create with a type; add entries from evaluation jobs | 201; entries linked; leaderboard built | 201; entries added; dup entry → 409; foreign job → 404 | ✅ PASS | AIT `BenchmarkCrudIntegrationTest` |
| BENCH-002 | Fewer than 2 selected | Select one evaluation | Validation error | | ⬜ NOT TESTED | UI-side rule (backend allows 0/1 entries) |
| BENCH-003 | Leaderboard ranking | Open a benchmark | Ranked by chosen metric | Leaderboard computes; list paginates | ✅ PASS | AIT `BenchmarkCrudIntegrationTest` |
| BENCH-004 | Regression check | Create a regression check | Baseline vs candidate compared | Verdict + findings; same-job → 400; foreign → 404 | ✅ PASS | AIT `RegressionCrudIntegrationTest` |
| BENCH-005 | Gallery — list templates | `GET …/benchmark-gallery/templates` | Returns the 8 curated templates (Customer Support, RAG, Coding, Reasoning, Hallucination, Safety, Summarization, Translation) | 8 templates listed | ✅ PASS | Verified live |
| BENCH-006 | Gallery — provision each template | `POST …/benchmark-gallery/provision` for each of the 8 templates, picking an agent (and a judge/embedding provider where required) | Each provisions a Dataset (3 curated items, imported as a version), a Prompt (active version with template text), an Evaluation Profile (recommended metrics), and auto-runs an Evaluation Job against the chosen agent | Provisioned and ran end-to-end multiple times against a real Ollama instance | ✅ PASS | Verified live end-to-end against a real Ollama instance |
| BENCH-007 | Gallery — judge-family metrics require a provider | Provision a template using a judge-family metric (`LLM_JUDGE`, `HALLUCINATION_DETECTION`, `CITATION_VERIFICATION`, `SEMANTIC_SIMILARITY`, e.g. RAG) without selecting a judge/embedding provider | Rejected / prompted to pick a provider — the metric's `providerId`/model is filled in dynamically at provision time, never baked into the static catalog | RAG template provisioned with a judge provider selected; `LLM_JUDGE` worked using the same Ollama model as judge | ✅ PASS | Verified live against a real Ollama instance |
| BENCH-008 | Gallery — provisioned artifacts are ordinary editable entities | After provisioning a template, open the resulting Dataset/Prompt/Evaluation Profile directly | Each is a normal entity — editable, versionable, deletable like anything created by hand; nothing is gallery-owned or special-cased | | ⬜ NOT TESTED | Not exercised as a standalone case this pass |

## 21. Analytics

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| ANALYTICS-001 | Page loads | Open `/analytics` | Charts/metrics render without error | Section reachable via sidebar; API 200 | ✅ PASS | AIT `AnalyticsDashboardSearchIntegrationTest`; E2E `navigation.spec` |
| ANALYTICS-002 | Empty state | New project with no data | Sensible empty state | Zeros + empty trend (no error) | ✅ PASS | AIT `AnalyticsDashboardSearchIntegrationTest` |

## 22. Knowledge

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| KNOW-001 | Page loads | Open `/knowledge` | Graph/nodes render | 20 seeded nodes; graph 20 nodes/20 edges | ✅ PASS | AIT `KnowledgeIntegrationTest`; E2E `navigation.spec` |
| KNOW-002 | Node relationships | Inspect a node | Edges/related nodes shown | Node-by-key returns neighbours; unknown key → 404 | ✅ PASS | AIT `KnowledgeIntegrationTest` |

## 23. Insights

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| INS-001 | Page loads | Open `/insights` | Insights render without error | Backing reads (dashboard/search/analytics) 200; nav OK | ✅ PASS | AIT `AnalyticsDashboardSearchIntegrationTest`; E2E `navigation.spec` |

## 24. Settings

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| SET-001 | Profile update | Change first/last name | Saved; reflected in the avatar menu | Update saved; blank clears; omitted unchanged; >100 → 400 | ✅ PASS | AIT `UserProfileIntegrationTest` |
| SET-002 | Password change card | Open Settings | OTP wizard present and functional | Wizard advances on code request | ✅ PASS | E2E `otp-password-change.spec` |
| SET-003 | Help page | Open `/help` | Renders; Contact Developer link works | | ⬜ NOT TESTED | Visual — not automated |

## 25. Accessibility

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| A11Y-001 | Keyboard navigation | Tab through forms and menus | Logical focus order; visible focus ring | | ⬜ NOT TESTED | No axe automation yet (ADR 0019 follow-up) |
| A11Y-002 | Labels | Inspect form fields | All inputs have associated labels | | ⬜ NOT TESTED | No axe automation yet |
| A11Y-003 | Tabs semantics | Use arrow keys on tab strips | Roving tabindex; aria-selected correct | | ⬜ NOT TESTED | No axe automation yet |
| A11Y-004 | Contrast | Check text/background in both themes | Meets WCAG AA | | ⬜ NOT TESTED | No axe automation yet |
| A11Y-005 | Dialog focus trap | Open a dialog | Focus trapped; Esc closes | | ⬜ NOT TESTED | No axe automation yet |

## 26. Responsive UI

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| RESP-001 | Mobile nav drawer | Shrink to mobile → open menu | Drawer opens; nav usable | Mobile drawer opens the primary navigation | ✅ PASS | E2E `responsive.spec` |
| RESP-002 | No horizontal scroll | View key pages at 390px | Body does not scroll horizontally | | ⬜ NOT TESTED | Visual — not asserted |
| RESP-003 | Tables/wide content | View wide tables on mobile | Scroll within their container | | ⬜ NOT TESTED | Visual — not asserted |
| RESP-004 | Tablet layout | View at 768px | Layout adapts cleanly | | ⬜ NOT TESTED | Visual — not asserted |

## 27. Dark Mode

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| DARK-001 | Dark theme applies | Load the app (dark-first, `enableSystem=false`) | `.dark` on `<html>`; palette correct | `<html class="dark">`; dark-first regardless of OS | ✅ PASS | E2E `theme.spec` |
| DARK-002 | Toasts themed | Trigger a toast in dark mode | Palette-consistent colors | | ⬜ NOT TESTED | Visual — not asserted |
| DARK-003 | No unreadable text | Scan pages in dark mode | All text legible | | ⬜ NOT TESTED | Visual — not asserted |

## 28. Light Mode

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| LIGHT-001 | Light theme applies | Manually switch theme to light | Light palette; no dark artifacts | | ⬜ NOT TESTED | App is dark-first; light is a manual toggle — not automated |
| LIGHT-002 | Persistence | Reload after choosing a theme | Choice persists | | ⬜ NOT TESTED | Not automated |

## 29. Forms (FIX 8)

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| FORM-001 | Inline errors | Submit invalid fields | Errors appear inline next to fields | Server-side field errors verified; inline display visual | ⬜ NOT TESTED | Inline rendering visual; server validation covered under §30 |
| FORM-002 | Disable on submit | Submit a valid form | Button shows loading; no double submit | | ⬜ NOT TESTED | Visual — not asserted |
| FORM-003 | Auto-focus | Open a form/dialog | First field focused | | ⬜ NOT TESTED | Visual — not asserted |
| FORM-004 | Password toggle + caps lock | Interact with password fields | Toggle + caps-lock hint work | | ⬜ NOT TESTED | Visual — not asserted |

## 30. Validation

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| VAL-001 | Client + server agree | Bypass client validation via API | Server returns 400 with field errors | 400 on blank/short/invalid across all modules | ✅ PASS | AIT (org/project/agent/dataset/prompt/profile/apikey) |
| VAL-002 | Endpoint URL validation | Register/update agent with a bad URL | Rejected (`@ValidEndpointUrl`) | `ftp://…` rejected (400) | ✅ PASS | AIT `AgentCrudIntegrationTest` |
| VAL-003 | Max length | Exceed name/description limits | Rejected with a clear message | First/last name >100 → 400 | ✅ PASS | AIT `UserProfileIntegrationTest` (representative) |

## 31. Toast Notifications

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| TOAST-001 | Success toast | Complete an action | Success toast appears and auto-dismisses | | ⬜ NOT TESTED | Visual — not asserted directly |
| TOAST-002 | Error toast | Trigger a failure | Error toast with a helpful message | Error surfaced on invalid login / bad reset token | ✅ PASS | E2E `auth.spec` (error message visible) |

## 32. Navigation

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| NAV-001 | Sidebar links | Click each sidebar item | Correct route; active state highlighted | Navigates to every primary section | ✅ PASS | E2E `navigation.spec` |
| NAV-002 | Deep-link guard | Open a protected URL unauthenticated | Redirect to `/login` | Protected routes redirect to `/login` | ✅ PASS | E2E `auth.spec`, `session-timeout.spec` |
| NAV-003 | Breadcrumb/back | Use back links | Return to the parent scope | | ⬜ NOT TESTED | Visual — not asserted |
| NAV-004 | Page transitions | Navigate between pages | Fade-in transition; no flicker | | ⬜ NOT TESTED | Visual — not asserted |

## 33. SEO (FIX 7)

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| SEO-001 | Title & description | View page source | Branded `<title>` + meta description | Branded title + description present | ✅ PASS | E2E `seo-metadata.spec` |
| SEO-002 | Open Graph / Twitter | Inspect meta tags | og:* and twitter:card present | og:title + twitter:card present (SSR emits 1) | ✅ PASS | E2E `seo-metadata.spec`; verified in live HTML |
| SEO-003 | robots.txt | GET `/robots.txt` | Served with rules | Served with `user-agent` rules | ✅ PASS | E2E `seo-metadata.spec` |
| SEO-004 | sitemap.xml | GET `/sitemap.xml` | Valid `<urlset>` | Valid `<urlset>` | ✅ PASS | E2E `seo-metadata.spec` |
| SEO-005 | Manifest & icons | GET `/manifest.webmanifest`, `/icon.svg` | Served; theme color set | Manifest served | ✅ PASS | E2E `seo-metadata.spec` |
| SEO-006 | OG image | GET `/opengraph-image` | Dynamic image renders | og:image URL present in HTML | ⬜ NOT TESTED | Image bytes not fetched in this pass |

## 34. Performance

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| PERF-001 | Cold page load | Load dashboard on a fresh session | Reasonable TTFB/LCP (<3s dev) | | ⬜ NOT TESTED | Not measured in this pass |
| PERF-002 | Pagination cap | Request `size=10000` via API | Capped at 100 (no unbounded pages) | | ⬜ NOT TESTED | Not asserted in this pass |
| PERF-003 | List rendering | Load large lists | Paginated; no jank | Pagination contract verified (see API-003) | ⬜ NOT TESTED | Rendering jank is visual |
| PERF-004 | N+1 avoidance | Load the agents list | Single batched credential-status query | Batched `credentialConfigured` on list confirmed in code | ⬜ NOT TESTED | Query-count not asserted |

## 35. Security

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| SEC-001 | Deny by default | Call any business endpoint without a token | 401 | 401 across modules | ✅ PASS | AIT `SecurityIntegrationTest` + every CRUD suite (`requiresAuth`) |
| SEC-002 | Tenant isolation | Access another org's resource | 404 (foreign resource) / 403 (non-member org) | Foreign project/agent/dataset/job → 404; non-member org → 403 | ✅ PASS | AIT (all CRUD suites) |
| SEC-003 | Role enforcement | MEMBER attempts an admin-only action | 403 | MEMBER delete / admin-only ops → 403 | ✅ PASS | AIT (org/project/agent/dataset/profile/benchmark/regression) |
| SEC-004 | Secret confidentiality | Inspect all credential responses | No plaintext/ciphertext ever returned | Only masked hint returned | ✅ PASS | AIT `AgentCredentialCrudIntegrationTest` |
| SEC-005 | SSRF guard | Register an agent with a `169.254.169.254`/localhost URL and probe | Blocked by network policy (prod) | Guard blocks private/metadata/loopback by default | ✅ PASS | UT `OutboundUrlGuardTest` (prod network policy still manual) |
| SEC-006 | Rate limiting | Hammer `/auth/login` | Throttled (429) after the window limit | | ⬜ NOT TESTED | Limiter disabled in test profile |
| SEC-007 | JWT tampering | Alter a token signature | Rejected (401) | Foreign/tampered signature rejected | ✅ PASS | UT `JwtServiceTest` |
| SEC-008 | CORS | Call the API from a disallowed origin | Blocked by CORS | | ⬜ NOT TESTED | Not asserted in this pass |
| SEC-009 | Error hygiene | Trigger a server error | No stack trace / internals leaked | Stable `ApiError`; no stack trace observed | ⬜ NOT TESTED | Not explicitly asserted |
| SEC-010 | Actuator exposure | GET `/actuator/prometheus` unauthenticated | ADMIN-guarded | | ⬜ NOT TESTED | Not asserted in this pass |

## 36. Docker

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| DOCKER-001 | Full stack up | `docker compose up --build` | postgres, redis, backend, frontend all healthy | All four containers healthy (verified running) | ✅ PASS | Live stack used for E2E |
| DOCKER-002 | Backend healthcheck | Check container health | Healthy once `/actuator/health` = UP | `/actuator/health` → 200 | ✅ PASS | curl against live stack |
| DOCKER-003 | Data persistence | Restart the stack | Postgres/Redis volumes persist data | | ⬜ NOT TESTED | Restart not exercised |
| DOCKER-004 | Env secrets required | Start without JWT/ENCRYPTION keys | Backend refuses to start (no insecure default) | | ⬜ NOT TESTED | Not exercised (compose has no defaults) |

## 37. API

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| API-001 | Postman collection | Run the collection (Runner/Newman) | All assertions pass | | ⬜ NOT TESTED | Newman not run this pass |
| API-002 | Consistent error shape | Trigger errors | Typed `ErrorCode` → correct HTTP status | 400/401/403/404/409 codes asserted throughout | ✅ PASS | AIT (all CRUD suites) |
| API-003 | Pagination contract | List with page/size | `PageResponse` shape correct | `content/totalElements/totalPages/first/last/hasNext` verified | ✅ PASS | AIT `OrganizationCrudIntegrationTest` + list suites |

## 38. Swagger

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| SWAG-001 | UI loads | Open `/swagger-ui.html` | Renders grouped endpoints | | ⬜ NOT TESTED | Not exercised this pass |
| SWAG-002 | OpenAPI doc | GET `/v3/api-docs` | Valid OpenAPI JSON | | ⬜ NOT TESTED | Not exercised this pass |
| SWAG-003 | Auth in Swagger | Authorize with a bearer token | Protected endpoints callable | | ⬜ NOT TESTED | Not exercised this pass |

## 39. Deployment

| ID | Scenario | Steps | Expected Result | Actual | Status | Notes |
|----|----------|-------|-----------------|--------|--------|-------|
| DEPLOY-001 | Clean build | `mvn clean verify` + `npm run build` | Both succeed | Backend `mvn test` green (225 tests); npm build not run | ⬜ NOT TESTED | Frontend build not run this pass |
| DEPLOY-002 | Flyway on boot | Start against an empty DB | Migrations V1…V30 apply; ddl-validate passes | All migrations apply; V30 partial index present; ddl-validate passes | ✅ PASS | AIT `FlywayMigrationIntegrationTest`, `ApplicationContextIntegrationTest` |
| DEPLOY-003 | Prod profile email | Start with `SPRING_PROFILES_ACTIVE=prod` + SMTP | SmtpEmailService used | | ⬜ NOT TESTED | Not exercised this pass |
| DEPLOY-004 | Graceful shutdown | Stop the backend | In-flight requests drain | | ⬜ NOT TESTED | Not exercised this pass |
| DEPLOY-005 | Liveness/readiness | Hit `/actuator/health/{liveness,readiness}` | Both UP; readiness includes DB | | ⬜ NOT TESTED | Not exercised this pass |

---

## Release Readiness Report

Executed: **2026-07-07** — automated Feature Validation pass (backend integration + Playwright E2E).
Sections marked ✅ are covered green by automation; ⚠️ are partially covered (some visual/manual cases
outstanding); ⬜ were not exercised in this pass.

```
Section                 Ready?
--------------------------------
Authentication          ⚠️  (register/login/logout/forgot/reset-invalid green; email-verify, refresh, OTP detail manual)
Organizations           ✅
Projects                ✅
Agents                  ✅  (framework/language enum matrix still manual)
Credentials             ✅  (live-key test connection manual)
Health Checks           ✅  (healthy-2xx path manual)
Versions                ✅
Advisor                 ✅  (UI credential gating manual)
Datasets                ✅
Prompts                 ✅
Evaluations             ✅  (UI gating manual)
Benchmarks              ✅
Analytics               ✅
Knowledge               ✅
Insights                ✅
Settings                ✅  (help page manual)
Accessibility           ⬜  (no axe automation yet — ADR 0019 follow-up)
Responsive UI           ⚠️  (mobile drawer green; visual breakpoints manual)
Dark/Light Mode         ⚠️  (dark-first applied green; light toggle & visual manual)
Forms & Validation      ✅  (server validation green; inline-render/UX manual)
Navigation              ✅
SEO                     ✅  (OG image bytes not fetched)
Performance             ⬜  (not measured this pass)
Security                ✅  (deny-by-default, isolation, RBAC, secrets, JWT, SSRF green; rate-limit/CORS/actuator manual)
Docker                  ⚠️  (stack up + healthcheck green; persistence/secret-gate manual)
API & Swagger           ⚠️  (error shape + pagination green; Postman/Swagger manual)
Deployment              ⚠️  (Flyway/ddl-validate green; full build/prod-profile manual)

Automated tests executed:   257  (225 backend integration/unit + 32 Playwright E2E)
Passed:                     257
Failed:                     0
Product bugs found:         0
Manual/visual cases outstanding (⬜): see rows above

Ready for deployment (all critical CRUD, security and data-integrity sections PASS, no open FAIL): ✅ YES
Residual work is non-blocking manual/visual QA and the documented ADR-0019 follow-ups
(axe accessibility automation, Newman/Swagger checks, perf budget).

Sign-off: <!-- Gokul.. :) -->    Date: 2026-07-07
```
