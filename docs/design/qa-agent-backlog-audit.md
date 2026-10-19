# QA Agent — Backlog Audit Log

Append a dated entry after every completed story: what was built, how it was
verified, what was deliberately left out or deferred, and any open questions raised
for the user. Do not rewrite or delete prior entries.

---

## 2026-09-14 — First dispatch: full P0 backlog, run last per `docs/RUN_ORDER.md`

**Agent:** QA Agent · **Branch:** `claude/wonderagent-setup-lasmly` (same
environment-pinned-branch deviation every prior module recorded).

QA Agent is the last module in the run order — this dispatch runs after all ten
domain/platform/experience/operations modules reached their P0 `Done`/`Partial`
state. Full detail for every story is in the new `INTEGRATION_STATUS.md` at the
repository root (this document's own §1–8); this entry summarizes what was built,
fixed, and left open, and does not duplicate that detail.

**Done outright:** QA-P0-01.1 (repository & contract inventory), QA-P0-01.2 (route
map & permission matrix — found and fixed a stale route-prefix drift in
`docs/design/ownership-map.md`), QA-P0-02.3 (platform-admin isolation sweep, live),
QA-P0-04.1 (repo-wide pipeline sweep), QA-P0-04.2 (migration validation), QA-P0-04.4
(regression-fix discipline), QA-P0-09 (SHOULD/CAN/DID reproducibility — already
directly proven by `modules/runtime-assurance/compare.test.ts`).

**Two real defects found and fixed, both logged in Foundation's own audit log per
QA-P0-04.4's rule (fix lives in, and is logged by, the owning module):**

1. `lib/security/encryptSecret.test.ts`'s tamper test was intermittently flaky
   (base64 padding-boundary non-determinism in the *test's* tamper method, not a
   GCM authentication defect). Fixed by moving the tamper target to an always-
   unpadded byte position. Verified deterministic across 5 isolated + 3 full-suite
   reruns.
2. Two `SECURITY DEFINER` functions (`current_tenant_ids()`, `rls_auto_enable()`)
   were executable by roles with no legitimate reason to call them (`anon` for both;
   `authenticated` too for `rls_auto_enable()`, an event-trigger function never
   meant to be called via RPC). Applied migrations `0049`/`0050` revoking the
   unnecessary `EXECUTE` grants, while deliberately *keeping* `authenticated`'s grant
   on `current_tenant_ids()` since every tenant-scoped RLS policy in this database
   depends on it — revoking that one would have broken RLS entirely. Re-verified
   live post-fix: an authenticated Tenant-A5 session still sees exactly its own
   agent row, no regression. `get_advisors(security)` re-run clean of both findings
   afterward (only the already-accepted `create_tenant_with_owner()` exception and
   the dashboard-only `auth_leaked_password_protection` setting remain).

**Backlog reconciliation (separate from the P0 work above, but same dispatch):**
the user separately uploaded a more detailed module-08 requirements document
(`08_UI_UX.md`) mid-session; its new §38 ("Locked Product Design System") was
reconciled into `docs/plan/08-EXPERIENCE-AGENT-BACKLOG.md` as a new, explicitly
flagged-not-implemented row (`EXPERIENCE-P0-09`) rather than silently built, since
it materially conflicts with already-shipped, widely-depended-upon shell/token/nav
work — see that backlog's own Requirements Refresh addendum and
`docs/design/experience-agent-backlog-audit.md`'s matching entry. Not QA's own
story, recorded here only because it happened in the same dispatch window.

**Real, named gap found and not fixed (QA-P0-04.3):** grepped every module's list-
style service function for `.range(`/`.limit(` usage. Only 4 files (Runtime's
`events.ts`/`quarantine.ts`, Operations' `audit.ts`/`notifications.ts`) bound their
result set — roughly 22 other `list*()` functions across Identity, Access,
Compliance, Integration, Platform, and Operations' own `savedReports.ts` fetch an
unbounded full table scan, violating CLAUDE.md §15's mandatory pagination rule.
**Not fixed here** — rewriting ~22 files across 6 modules' own service layers is
not a "smallest safe change" and would make QA a second implementation pass inside
other modules' owned files (non-negotiable #18; this backlog's own "DO NOT
IMPLEMENT — sweeping refactors"). Recorded in `INTEGRATION_STATUS.md` §5 as a named
release-gate item for each owning module.

**Partial, with specific documented gaps (not fabricated as complete):**
QA-P0-02.1 (cross-tenant sweep — DB/API/search/reports/jobs layers verified live;
no dedicated isolation fixture yet for Operations'/Platform's newest tables),
QA-P0-02.2 (RBAC sweep — orphaned-permission check clean, but the negative-
permission proof is generic rather than per-key-enumerated), QA-P0-03.1 (the
FinanceBot scenario — 6 of 8 steps confirmed live against the real fixture; step 6
honestly partial and step 7 not exercised end-to-end, both already recorded as
cross-module blockers in Risk Agent's own audit log, not new QA findings), QA-P0-05
(clean install — lockfile/env-example present and a cold-cache build verified;
a true from-scratch clone+install+fresh-database run was not attempted, judged out
of scope for a verification pass given the cost/quota implications of a second
Supabase project), and QA-P0-06 through QA-P0-14 (the requirements-refresh's
extended hardening epics — authentication suite, connector contract tests, runtime
test corpus, risk regression suite, certification regression, security scanning,
failure recovery, observability sweep). Each of these carries existing, real partial
test coverage (cited specifically in `INTEGRATION_STATUS.md` §7) rather than zero
coverage, but none is a complete suite — building the full versions (e.g. QA-P0-10's
40-case risk-category matrix) responsibly requires the kind of deep domain
familiarity that belongs to each owning module's own further work, not a QA
dispatch attempting to fabricate shallow passes or silently duplicate another
module's implementation logic.

**Verification:** full pipeline (`npm run typecheck`, `npm run lint`, `npx vitest
run` — 139/139 passing, `npm run build` with `.next` deleted first) green;
`grep -rl SUPABASE_SERVICE_ROLE_KEY .next/static` — no match; live smoke test
against a locally built production server for platform-admin isolation (torn down
after); `get_advisors(security)` re-run clean of both fixed findings; live SQL
queries against the FinanceBot fixture and the RLS/policy catalog, both re-run
after this dispatch's own migrations to confirm no regression.

**Open questions for the user:** none new from QA's own P0 work — every gap above
is either blocked on a specific cross-module contract already recorded by its
owning module, or a sandbox/infrastructure constraint already accepted elsewhere
in this session (real SSO/MFA IdP round-trip, real-browser visual verification,
a genuinely fresh install environment). The one open question from this dispatch
window is EXPERIENCE-P0-09 (the Locked Design System v2 addendum), already raised
separately in Experience Agent's own audit log.

**Release Gate:** per `docs/plan/11-QA-AGENT-BACKLOG.md`'s own Release Gate section
and `INTEGRATION_STATUS.md` §8 — not yet a clean pass. No defect was found in any
deterministic security/isolation/authorization logic itself; the gate is held open
by the pagination gap, FinanceBot step 7, the QA-P0-06–14 partial epics, and the
already-accepted sandbox constraints, each named and owned rather than silent. This
is the last module in `docs/RUN_ORDER.md` — with this dispatch, the full run order
has been exercised at least once; no further module remains to auto-chain into.

## 2026-09-14 — Second dispatch: dependency vulnerability scan, Operations
isolation fixture

**Agent:** QA Agent · **Branch:** `claude/wonderagent-setup-lasmly`. Picked
up after Experience Agent's own follow-on dispatch closed its remaining
named gaps; this session closes two of QA's own previously-recorded
release-gate items rather than re-opening the full P0 backlog.

**QA-P0-12 (security scanning):** ran `npm audit` at both `--omit=dev`
(production-only) and full scope (including dev dependencies) — **0
vulnerabilities** either way. Closes the "dependency vulnerability
scanning... not run" half of this story's previously-recorded gap. The
other half (a static-analysis pass beyond ESLint, and
`auth_leaked_password_protection` — a Supabase Auth dashboard-only toggle)
remains open, unchanged.

**QA-P0-02.1 (full cross-tenant sweep):** built `tests/operations/
tenant-isolation.sql` (new), closing the specific gap this backlog's own
audit already named — no `tests/**` fixture existed for Operations
Agent's newest tables (`notifications`, `notification_preferences`,
`reports`). Before building anything, re-checked
`platform_config_versions`/`platform_announcements` (the other two tables
named in that same gap) directly against `pg_policies`, not just the
earlier advisor-level "11 tables, RLS enabled, no policies" count — both
have genuinely zero policies for any role. Correctly excluded them from
this fixture: a "does tenant A's session see only tenant A's rows"
property has nothing to test on a table no customer session can read at
all; that absence is itself what one of the fixture's own checks proves
directly for `platform_config_versions`.

The new fixture (Tenant A6/B6, a fresh pair distinct from every existing
fixture ID range) proves, run live via the Supabase MCP `execute_sql`
tool against project `ekgyjwoenteadaaqakmd` (same tool used throughout
this session for direct DB verification — this sandbox's plain network
egress cannot reach Supabase directly, a hard constraint confirmed
empirically earlier this session, distinct from this MCP tool's own
separate/privileged channel):

- Tenant A6's authenticated session sees exactly its own direct
  notification, its own tenant-wide broadcast notification (`user_id
  is null`), its own notification preferences row, and its own saved
  report — never Tenant B6's rows, whether queried by list or by direct
  lookup (`B6_notification_by_pk_row_count` → 0).
- Attempting to mark another tenant's notification as read affects 0
  rows (RLS silently filters the `UPDATE` target, doesn't throw — same
  "check row_count, not just absence of an exception" lesson this
  session's earlier fixtures already established).
- A direct client-side `INSERT` into `notifications` (bypassing the
  real app's only writer, `notify()`, which uses the service-role
  client) is rejected by RLS — no client-facing insert policy exists
  on this table by design.

All results matched the fixture's own documented expected values exactly
on first live run. Fixtures cleaned up afterward (this A6/B6 pair is not
a shared "central scenario" fixture reused across modules, unlike the
FinanceBot aaaaaaaa-5000-.../bbbbbbbb-5000-... pair, so there was no
reason to leave it seeded). `get_advisors(security)` re-run clean
afterward — no new finding introduced, same three already-accepted
exceptions as every prior pass (11 vendor-only RLS-enabled-no-policy
tables, the two intentional `SECURITY DEFINER` grants, the dashboard-only
leaked-password-protection setting).

**Verification:** `npm audit` (both scopes, above); live SQL fixture
insert → verify → cleanup cycle against the dev Supabase project, all
three phases executed and all results matched expectations;
`get_advisors(security)` re-run post-fixture, clean.

**Updated `docs/RUN_ORDER.md`:** the Experience Agent row was also
refreshed in this same session window (not a QA action, but recorded
here since it happened in this dispatch's timeframe) — it had gone stale,
still describing Experience Agent's pre-Locked-Design-System-v2 state
from an earlier pass, and now reflects the actual current 9-of-12-`Done`
state with the three remaining `Partial` rows' real, narrow causes.

**Release Gate — still not a clean pass**, for the same reasons named in
`INTEGRATION_STATUS.md` §8, now with two of the four blocking categories
partially narrowed rather than eliminated: the pagination gap (§5) and
the QA-P0-06–14 extended epics (§7, apart from QA-P0-12's now-closed
`npm audit` sub-item) are unchanged from the first dispatch; FinanceBot
step 7 and the sandbox-only constraints are unchanged and unchangeable
from this environment. Not claiming a release-gate pass this dispatch —
recording concrete, verified progress against two specific named items
instead.

## 2026-09-14 — Third dispatch: documentation-only re-check against the
expanded requirements doc (round 2), no application/test code touched

**Agent:** QA Agent. Documentation/planning pass only, per this dispatch's
explicit scope: read the newly re-uploaded, expanded
`11_INTEGRATION_QA_HARDENING.md` in full, re-checked it against the current
`docs/plan/11-QA-AGENT-BACKLOG.md` (including its existing Requirements
Refresh section), `INTEGRATION_STATUS.md`, and this audit log's own two
prior entries, to find anything genuinely new that the first Requirements
Refresh pass missed. No migration, service code, route, or test file was
touched; the verification pipeline (typecheck/lint/test/build) was not run,
per this dispatch's explicit instruction.

**Finding: the doc is almost entirely already reconciled.** The uploaded
doc's structure is a header/Purpose/Engineering-rules block, the full
original master PRD (§46–§55 — P0/P1 feature lists, the P0 acceptance
scenario, development order, Claude Code operating instructions, Definition
of Done, Non-Goals, final product definition, implementation guardrails,
first commercial wedge, final-pass procedure, release gate), and then the
same "Expanded Requirements" flat list (`QA-P0-01`–`QA-P0-15`,
`QA-P1-01`–`06`, `QA-P2-01`–`03`) the first Requirements Refresh pass already
fully reconciled (mapped to `QA-P0-05`–`QA-P0-14`, marked "already covered,"
or copied verbatim into this backlog's own `## P1`/`## P2` sections). The
master-PRD sections restate `CLAUDE.md` §9–§16 almost verbatim and add no
new scope.

**Three specific re-checks performed before concluding "no gap," rather than
trusting the first pass's mapping claims at face value:**

1. Doc's `QA-P0-03` (Tenant Isolation Suite) names "RPC" and "caches" as
   surfaces distinct from what `QA-P0-02.1`'s own text enumerates. Grepped
   the whole codebase for `.rpc(` — only `create_tenant_with_owner`
   (already audited, intentionally `authenticated`-executable) and the MCP
   connector's own outbound JSON-RPC client method (an unrelated meaning of
   "RPC"). Grepped for cache/memoization patterns — none exist anywhere;
   reports and computed views are explicitly built and commented "never
   cached." Both surfaces are genuinely non-issues: nothing exists to leak
   cross-tenant data through, not an untested gap.
2. Doc's `QA-P0-11` (Security Scanning) names "secure headers checks."
   Confirmed `next.config.ts` (FOUNDATION-P0-05.3) sets
   `X-Content-Type-Options`, `X-Frame-Options`, `Referrer-Policy`,
   `Permissions-Policy`, and a `Content-Security-Policy` repo-wide. This
   detail wasn't itself named in `INTEGRATION_STATUS.md` §7's `QA-P0-12`
   write-up, but it is a sub-detail of that already-tracked `Partial` story,
   not a new requirement — no new row added for it.
3. Diffed the doc's full "Expanded Requirements" wording against every
   corresponding backlog story's own wording line by line (not just ID
   matching) — no material wording differences found; the first pass's
   reconciliation is accurate, not just superficially ID-matched.

**One genuinely new item found and added: `QA-P1-07` — Release record
completeness standard.** After the doc's `QA-P2-03` entry sits an unlabeled
closing paragraph the first Requirements Refresh pass's own summary
(which explicitly stopped at "`QA-P2-03`") read past: *"The release record
must include commit/version, migration status, test summary, known
limitations, connector compatibility and security findings and explicit
P0/P1/P2 status."* Checked each named field against the current
`INTEGRATION_STATUS.md` directly: migration status, test summary, known
limitations, and security findings are all present; connector compatibility
is present inline (the dedicated matrix is already tracked as `QA-P1-04`,
not duplicated); but **no commit/version identifier appears anywhere in the
document, and it never gives an explicit P1/P2 status summary** — only
exhaustive P0 detail. This is real, scoped entirely to a file QA already
owns (`INTEGRATION_STATUS.md`), requires no new table/route/type, and was
missed by the first pass for an identifiable reason (it sits outside the
numbered list that pass was reconciling). Classified `P1` per `CLAUDE.md`
§3's "when genuinely unsure, prefer P1/P2 over P0" — it is a
documentation-completeness requirement on the release record's own
contents, not itself a security/isolation gate. Added as a new Progress
Tracker row (status: Not Started), a new bullet in `## P1`, and a full
"Requirements Refresh — 2026-09-14 (round 2, expanded doc)" section in
`docs/plan/11-QA-AGENT-BACKLOG.md` documenting the reasoning above.

**Explicitly not touched:** no row already `Done`/`Partial` was reopened or
changed; `INTEGRATION_STATUS.md` itself was read but not edited (its
release-gate conclusion is a live-verification artifact, out of scope for
this documentation-only pass, per this dispatch's own instruction); no other
module's backlog, ownership map, or application code was touched; none of
this task's named "known existing tracked gaps" (pagination, FinanceBot step
7, `QA-P0-06`–`14` partial coverage, sandbox-only constraints) were
re-added.

**Verification:** documentation cross-referencing only (`grep`/`diff`
against the doc, the backlog, `INTEGRATION_STATUS.md`, both prior audit
entries, and `next.config.ts`) — no build/test/typecheck/lint run, per this
dispatch's explicit scope.

**Open questions for the user:** none new. The doc's "Modular Execution
Guide" process-model note already flagged in the first Requirements Refresh
(manual-dispatch-only vs. this repo's standing autopilot policy) remains
open and unchanged by this pass.

---

## 2026-09-16 — Final re-verification pass (post governance-requirements build-out)

**Agent:** QA Agent, per the user's standing authorization, after the
session completed the entire pending P0 backlog (Foundation's `lib/ai/`
primitive, Risk's Governance Drift, Compliance's Posture/Attestation/
Evidence Pack, Operations' evidence export, Experience's four UI gaps,
Risk/Compliance unblocks, Platform's stale-row fix and unblock,
Operations' `notify()` wiring and job-status page — see
`INTEGRATION_STATUS.md` §9 for the full list).

**Approach:** a single repo-wide pipeline sweep plus targeted advisor/
isolation checks, rather than re-deriving every `QA-P0-*` story from
scratch — every new story this session already carried its own
module-level verification (typecheck/lint/tests/build/secret-leak, and
live Supabase checks where schema changed), recorded in each module's own
audit log. This pass's job was to catch anything those per-story checks
individually couldn't: cross-cutting drift (migration counts, advisor
state) and gaps a single module's own pass wouldn't think to check for
itself (a missing isolation test on another module's new table).

**Findings, both real and fixed, not just re-confirmations:**
1. `mcp__Supabase__get_advisors(performance)` — `governance_attestations_
   agent_id_fkey` (Compliance's migration `0055`) had no covering index.
   The composite `(tenant_id, agent_id)` index that migration already
   added doesn't cover a lookup on `agent_id` alone (not the leading
   column), which is exactly what the FK-constraint check needs on an
   agent delete. Fixed via `supabase/migrations/0056_compliance_
   governance_attestation_fk_index.sql`
   (`governance_attestations_agent_id_idx`), applied live; re-checked —
   the finding cleared (`unindexed_foreign_keys` count 14→13, the
   remaining 13 all pre-existing from before this session).
2. `governance_attestations` (`COMPLIANCE-P0-08`, built earlier this
   session) had no tenant-isolation SQL fixture — a real violation of
   CLAUDE.md §14's "new tables/routes without an isolation test are not
   Done" that COMPLIANCE-P0-08's own audit entry didn't catch at the
   time. Added `tests/compliance/governance-attestation-tenant-isolation.sql`,
   reusing the existing FinanceBot fixture (Tenant A5/agent/User A5,
   Tenant B5's User B5) rather than a new one. Ran live against the dev
   project via `execute_sql`: visible to Tenant A5's user (1 row),
   invisible to Tenant B5's user (0 rows), a client-role insert correctly
   rejected by RLS (no client INSERT policy exists, per the table's own
   design), a client-role update affects 0 rows (immutability). Fixture
   row deleted after the run — the script itself is left in `tests/` for
   future re-runs, consistent with every other isolation script in this
   repo.
3. `mcp__Supabase__get_advisors(security)` — re-checked across every
   migration applied this session (`0054`, `0055`, `0056`): no new
   findings; the 3 pre-existing ones (Platform's own 11
   `rls_enabled_no_policy` rows, 2 known security-definer functions, the
   dashboard-only leaked-password-protection setting) are unchanged.
4. Migration count/prefix check: 56 files, no duplicate numeric prefixes
   (`ls | sed -E 's/^([0-9]{4})_.*/\1/' | sort | uniq -d` — empty).

**Full pipeline, re-run clean:** `npm run typecheck`, `npm run lint`,
`npx vitest run` (214/214, up from 139 at this doc's last full-sweep
entry), `npm run build` with `.next` deleted first, `grep -rl
SUPABASE_SERVICE_ROLE_KEY .next/static` (no match), `node scripts/
contrast-check.mjs` (every pair passes, both themes — confirms the new
`AiSummaryPanel`/`AnnouncementsBanner`/job-status page's reused `info`/
`warning` tones didn't regress anything), `npm audit --production` (0
vulnerabilities).

**Not attempted this pass** (unchanged sandbox/scope constraints already
named in `INTEGRATION_STATUS.md` §8, not re-litigated here): real
SSO/MFA IdP round-trip, real-browser authenticated visual verification, a
true from-scratch clean-room install, full coverage of the extended
`QA-P0-06`–`14` epics, `QA-P1-07`.

**Updated:** `docs/plan/11-QA-AGENT-BACKLOG.md`'s `QA-P0-04.1`,
`QA-P0-04.2` (re-verified, counts updated), `QA-P0-02.1` (new isolation
test referenced). `INTEGRATION_STATUS.md` §9 added as this pass's full
account.

## 2026-09-16 — QA-P0-05: genuine from-scratch clean-install run attempted

**Trigger:** the standing "any P0 item open to work?" sweep, bucket A
(pure-code, no product decision needed).

**Done:** a real from-scratch verification, not the existing checkout's
cold-cache build this story's `Partial` status previously relied on.
`git clone --branch main --depth 1 https://github.com/luvchakra/wonder-agent.git`
into a scratch directory (no shared `node_modules`, no `.env.local`
carried over from this working checkout), then:
- `npm ci` (lockfile-driven install, not `npm install`) — 598 packages,
  0 vulnerabilities, ~30s.
- A `.env.local` synthesized purely from `.env.local.example`'s own
  documented variable names (placeholder values) — proving the app
  builds from documented env vars alone, not some undocumented local
  override.
- `npm run typecheck` — clean.
- `npm run lint` — clean.
- `npx vitest run` — 260/260, matching the working checkout's count
  exactly (proves the test suite has no dependency on anything outside
  the committed repo + documented env vars).
- `npm run build` — clean production build, ~25s. The client bundle
  correctly inlines the `NEXT_PUBLIC_*` placeholder values (expected —
  those are meant to be public) and does not contain
  `SUPABASE_SERVICE_ROLE_KEY` (confirmed via the same `grep -rl` check
  this pipeline always runs).

**Deliberately still not attempted:** applying every migration to a
genuinely fresh database (rather than the existing dev Supabase
project). `mcp__Supabase__create_branch` requires a `confirm_cost` step
first — the tool's own description says to "always repeat the cost to
the user and confirm their understanding before proceeding," since
branch creation is real, hourly-billed infrastructure spend on the
user's Supabase organization, not a free/local action. Asked the user
directly (check the cost and proceed if small, vs. skip the paid step);
the user chose to skip it. This is a documented, informed scoping
decision, not a silently-abandoned acceptance criterion — the code-level
half of QA-P0-05's acceptance criteria (fresh clone, fresh install,
build) is now genuinely verified; the fresh-migration-apply half remains
`Partial` for a real, named cost reason rather than a "sandbox
limitation" excuse.

**Verification:** as described above, run entirely in an isolated
scratch directory separate from the working checkout, output captured
in this session's transcript. No files in the working checkout were
touched by this story (verification-only, no code change) — Progress
Tracker updated to reflect the narrower, honest scope of what's still
open.

## 2026-09-16 — QA-P0-16: full Playwright E2E suite (user-requested, browser-driven, real Supabase Auth)

**Request and scoping:** user asked for "a full qa suite based on
playwright." No Playwright/E2E infrastructure existed at all beforehand —
every prior `tests/**` fixture was a SQL-level RLS/session-claims
simulation, never a real browser login. Asked 3 scoping questions before
starting: (1) run against the existing dev Supabase project with
namespaced test tenants, vs. a paid fresh branch — user chose the existing
project; (2) framework-only vs. deep per-module coverage — user chose deep
coverage; (3) CI-wired vs. local-only — user chose CI-wired. Full detail on
what was built is in `docs/plan/11-QA-AGENT-BACKLOG.md`'s own `QA-P0-16`
section; this entry covers the build/verification trail and the one real
blocker hit along the way.

**Genuine mid-build blocker, reported not routed around:** after building
the framework, seed script and auth-setup project, running the setup
project against a real `next start` server failed with "Host not in
allowlist" from a Node fetch, then a direct `curl` to the same host
confirmed a `403 CONNECT tunnel failed... organization policy` from this
session's own agent proxy — this sandbox cannot reach the dev Supabase
project's host at all, for any process, regardless of how the code is
written. Per this environment's own proxy documentation ("do not retry or
route around it — report the blocked host"), stopped and asked the user
how to proceed rather than silently downgrading scope or fabricating a
"tests pass" claim. User chose to have the full suite built anyway, with
CI as the real validation gate — recorded here so a future reader
understands why this story shipped `Partial` with zero live executions,
not because the work is incomplete but because this specific sandbox
cannot run it.

**Built** (see `docs/plan/11-QA-AGENT-BACKLOG.md`'s `QA-P0-16` for the full
file-by-file account): `playwright.config.ts`; `.gitignore` additions for
`test-results/`/`playwright-report/`/`tests/e2e/.auth/` (the last holds
real session tokens — never committed); `package.json` gains
`test:e2e`/`test:e2e:ui`/`test:e2e:report`; `@playwright/test` added as a
devDependency; `tests/e2e/support/testUsers.ts`, `seedTestData.ts`,
`seedFinanceBotAccess.ts`; `tests/e2e/auth.setup.ts`; 9 spec files
(`auth`, `navigation-smoke`, `agents`, `access`, `runtime`, `risk`,
`compliance`, `integrations`, `platform-admin`,
`financebot-central-scenario`); `.github/workflows/e2e.yml`.

**A real product gap this work surfaced, not fixed (non-negotiable #18 —
recorded, not silently patched into another module's code):** there is no
UI path anywhere in this codebase to create an `accounts` row for an
agent — they only ever arrive via an integration sync. This blocked a
pure-UI FinanceBot central-scenario spec; `seedFinanceBotAccess.ts` seeds
that one piece directly via the Supabase Admin API instead, mirroring the
shape `tests/access/financebot-scenario-and-tenant-isolation.sql` already
uses at the SQL level. Worth Access/Experience Agent's attention if a
"manually connect an account" flow is ever wanted as a P1/P2 story — not
raised as a bug against this pass, since manual account creation was never
an acceptance criterion of any existing Access Agent story.

**Verification:** `npm run typecheck` clean, `npm run lint` clean, `npx
vitest run` unaffected — 260/260, confirming zero collision between
Playwright's `*.spec.ts` naming and vitest's `*.test.ts` include glob.
`npm run build` (with `.next` deleted first) clean, `grep -rl
SUPABASE_SERVICE_ROLE_KEY .next/static` no match. Every Playwright spec
was written against the actual source (page components, server actions,
the shared `Field`/`Table`/`ConfirmActionDialog` primitives, exact
migration schemas) rather than guessed selectors — including catching and
correcting, before commit, two selector-locality traps a naive read would
have missed: the campaign-launch page's `<details>` element whose
`<summary>` text collides with its own submit button's text, and
`ConfirmActionDialog`'s trigger and in-dialog confirm button sharing an
identical accessible name. **Not run live** — see the blocker note above;
first real execution is the CI workflow's first run once the 4 required
Supabase secrets are added to the repo (the user's own action, not
performed here).

Progress Tracker: `QA-P0-16` added (`Partial`); `QA-P0-06` and
`QA-P0-03.1` both updated to reference the new real browser coverage
without being marked `Done`, since neither has a confirmed live pass yet.

---

## 2026-09-16 (later) — QA-P0-16 taken as far as available credentials allow; live cross-module isolation proof added

The sandbox's Supabase egress blocker that this log, and every other module's,
recorded as a hard constraint is **gone** for HTTPS (see
`docs/design/foundation-agent-backlog-audit.md`'s entry of this date for the
full re-test, including what is still blocked: raw Postgres on 5432/6543).
So this pass retried everything that had been deferred to "when the network
allows it."

**Done, and passing: `tests/live-client-tenant-isolation.mjs` (new,
QA-owned).** Cross-module tenant isolation proven through two genuinely
authenticated Supabase JS client sessions over HTTPS rather than server-side
JWT simulation — all 44 tenant-scoped tables both directions, a fixture
reality check, foreign primary-key lookup, cross-tenant update/delete/insert,
a forged `audit_logs` insert, and an anon sweep. Every check passed. Details
and the `auth.users` seeding gotcha are in the Foundation entry.

**QA-P0-16 (Playwright E2E): the framework is now proven against a real
server, the suite itself is still not fully run — and the reason has changed
from "network" to "credentials."** What actually happened:

- Config gained three optional env hooks so the suite can target something
  other than a local build: `E2E_BASE_URL` (run against a deployment, skipping
  the local `webServer`), `E2E_BOOTSTRAP_URL` (visit a deployment-protection
  bypass link first so its cookie lands in the saved storage state),
  `E2E_SKIP_SEED=1` (fixtures seeded out of band, no service-role key in the
  process), and `E2E_CHROMIUM_PATH`/`E2E_CHROMIUM_ARGS`. All unset in normal
  local and CI runs, so nothing about the default path changed.
- Pointed at the **production** deployment (the only one with environment
  variables configured), the setup project reached the real app and **signed
  in for real through Supabase Auth** — `authenticate as platformAdmin`
  passed end to end, landing on `/onboarding` and saving storage state. That
  is the first time any part of this suite has executed against a live server.
- The four tenant-user logins failed, and the failure was **a genuine product
  bug, not a test defect** — `getTenantContext()` returning every colleague's
  membership row. Fixed (Foundation + Experience); see their audit logs.
- Re-running against a **preview** deployment of the fix is not possible: the
  Vercel project's Supabase environment variables are scoped to Production
  only, so every preview 500s with `Missing required environment variable:
  NEXT_PUBLIC_SUPABASE_URL` (confirmed in the deployment's runtime logs).
  That is a real deployment-configuration gap in its own right — every PR
  preview of this project is broken — and it is the user's Vercel setting to
  change, not a code fix.
- The CI path is equally blocked: both `E2E (Playwright)` workflow runs to
  date failed, and the job log shows all five secrets resolving **empty**
  (`NEXT_PUBLIC_SUPABASE_URL:` with no value, and the same for
  `NEXT_PUBLIC_SUPABASE_PUBLISHABLE_KEY`, `SUPABASE_SERVICE_ROLE_KEY`,
  `SECRET_ENCRYPTION_KEY`, `CRON_SECRET`). The repo secrets named in the
  previous entry still have not been added.

**Stop-and-report, per CLAUDE.md §4.** A complete run needs
`SUPABASE_SERVICE_ROLE_KEY` (and `SECRET_ENCRYPTION_KEY`) somewhere this
process can read them — as GitHub Actions repo secrets, as Vercel Preview
environment variables, or handed to a session directly. No key is inferable
from anything this environment can reach, and inventing a degraded substitute
(pointing the service-role client at the anon key) would produce confidently
wrong results, which is worse than an honest gap. `QA-P0-16` therefore stays
`Partial`, with its blocker restated accurately rather than left as the
now-false "network egress blocks the Supabase host."

## 2026-09-19 — QA-P0-08: the runtime event corpus, built and wired for reuse

Picked up the next actionable, unblocked gap from `INTEGRATION_STATUS.md` §7
(QA-P0-08 was the only one of the extended hardening epics that is entirely
QA-owned — under `tests/**` — and needs no external infrastructure this
sandbox lacks, unlike QA-P0-06/07's real-IdP dependency or the
credential-gated QA-P0-16).

**Built** `tests/runtime/should-can-did-corpus.ts`: six deterministic,
versioned `{contract, effectiveAccess, didTuples}` cases, one per category
named in the story text — `allowed`, `can_only_unused` (granted but idle),
`did_only_unexpected` (used but not approved), `unauthorized_resource`
(no CAN grant and no approval at all), `sensitive_data` (the product's own
central FinanceBot/CustomerDB scenario, CLAUDE.md §11), and `unmappable`
(a DID tuple with an unresolved application). Each case carries a hand-
traced `expectedOutcomes`/`expectedOutcomeTypes` and a doc comment
explaining exactly why — e.g. `can_only_unused` deliberately uses one
shared `approvedData` term across two applications, documented inline,
because `compareShouldCanDid()` builds SHOULD as the full cross-product of
`approvedApplications x approvedData` (found this the hard way — the first
draft used two apps with two distinct data terms and every case spuriously
produced `insufficient_access`, since each app's grant wasn't compatible
with the *other* app's data term; fixed by giving both apps one shared,
substring-compatible term).

**Reused, not re-authored — the story's own acceptance criterion:**
- `modules/runtime-assurance/compare.test.ts` (QA-P0-09) gained a new
  `describe` block that runs the REAL `compareShouldCanDid()` against all
  six cases and asserts it reproduces exactly `expectedOutcomes` — this is
  what keeps the corpus honest; the expected outcomes are asserted against
  the implementation on every run, not just hand-verified once. Also
  replaced three pre-existing tests' inline literal duplicates of the
  `sensitive_data`, `allowed`, and `unmappable` scenarios with calls to
  `corpusCase(...)`, removing ~70 lines of duplicated fixture data rather
  than adding a fourth copy of the same scenario.
- `modules/risk/rules.test.ts` gained a matching `describe` block: for each
  of the six cases, feeds the corpus's `contract`/`effectiveAccess`
  (mapped to `CanEntry[]`)/`didTuples`/`expectedOutcomes` into
  `evaluateAgentRisk()`'s mocked dependencies and asserts the exact set of
  finding categories it triggers — independently re-derived from rules.ts's
  own logic (not copied from compare.ts's outcome types), since
  `unauthorized_resource` and `sensitive_data_violation` are Risk's own
  checks computed straight from `did.tuples`/`comparison.can`, not a
  passthrough of compare.ts's `unexpected_capability`/`behavioral_violation`.
  Every one of the six hand-derived predictions matched on the first test
  run.

**A real, current gap this pass surfaced rather than silently working
around:** `unused_capability`, `unexpected_capability`, `insufficient_access`
and `unscored_unknown` — four of `compareShouldCanDid()`'s seven outcome
types — are never read anywhere in `modules/risk/rules.ts`. Only
`excessive_access` and `behavioral_violation` feed a Risk finding today. The
`can_only_unused` and `unmappable` corpus cases both assert **zero** Risk
findings for exactly this reason, documented in each case's own comment and
in the new `rules.test.ts` describe block's `EXPECTED_CATEGORIES` map, so
the behavior is pinned rather than accidentally masked. Per non-negotiable
#18 this is Risk Agent's own scope to close (a new "unused entitlement"/
"technically-impossible activity" finding category is a real product
decision — severity, whether it's worth a finding at all for every unused
grant — not a QA-owned fix), so it is recorded here rather than invented.

**Verified:** typecheck and lint clean. `compare.test.ts` 15/15 (was 8),
`rules.test.ts` 10/10 (was 4). Full vitest suite 308/308 (was 295 before
this pass — the 13 new tests are the corpus coverage; no existing test's
assertions changed, only their fixture data source for the three
de-duplicated ones).

**Progress Tracker:** QA-P0-08 moved from `Partial` to `Done`.

## 2026-09-19 (later) — QA-P0-11: certification regression closed; one stale claim corrected

Continuing down the same actionable-gap list (INTEGRATION_STATUS.md §7)
after QA-P0-08 above.

**Built** the missing half: a fast unit test for COMPLIANCE-P0-04's
Segregation-of-Duties self-certification restriction, added to
`modules/certification-compliance/decisions.test.ts` (reusing that file's
existing mocked `supabaseServer`/`supabaseServiceRole` table doubles rather
than standing up a second mocking scheme). Four cases: blocked with
`SOD_CONFLICT`/409 when the reviewer owns the agent and passes no override
(and audits `compliance.sod_conflict_blocked`, no decision row written);
succeeds and audits `compliance.sod_override_used` as its own event
(distinct from `compliance.decision_recorded`) when `overrideSoD: true` is
passed; does not apply at all when the reviewer isn't an owner; does not
apply to a non-`approve` decision even when the reviewer is an owner (the
code's own documented scoping — self-serving bias is specific to
affirming your own access, not to revoke/modify/delegate/
request_information).

**Found the other named gap was stale, not real.** This row also said "no
dedicated escalation regression test," attributed to escalation having no
scheduler yet. `git log --follow` on
`modules/certification-compliance/escalation.test.ts` shows it was added in
the same commit as COMPLIANCE-P0-05's real Vercel Cron scheduler for
`escalateOverdueItems()` — which post-dates the QA pass that wrote this
row. The file already has six real regression cases: notifies the
escalated-to user per overdue item, falls back to the campaign creator
when there's no business owner, no-ops cleanly with nothing overdue, sweeps
every active tenant and sums counts, isolates one tenant's failure from the
rest of the sweep, and no-ops cleanly with no active tenants. Verified this
directly rather than trusting the stale note, then corrected the record
instead of re-authoring coverage that already exists — CLAUDE.md's
instruction to report state accurately applies as much to fixing a false
`Partial` as to fixing a false `Done`.

**Verified:** typecheck, lint clean. `decisions.test.ts` 7/7 (was 3). Full
vitest suite 312/312 (was 308 after the QA-P0-08 pass earlier today).

**Progress Tracker:** QA-P0-11 moved from `Partial` to `Done`.

## 2026-09-19 (later still) — QA-P1-07: release record completeness

Closed the last of today's three actionable, unblocked QA gaps.
`INTEGRATION_STATUS.md` now opens with:
- A **release identifier** — the commit this snapshot is built on
  (`2c6f5d8`) plus the date, and an explicit note that "production ready"
  is never claimed while a mandatory P0 gate fails (§8 remains the single
  authoritative statement of gate status).
- An **explicit P0/P1/P2 status summary** — P0 is the individually-tracked,
  per-story Progress Tracker table detail every section already cites
  (141/165 Done as of this commit, per `docs/PROGRESS.md`); P1/P2 are each
  module's own prose scope bullets (~52 P1 / ~32 P2 combined), explicitly
  named as overwhelmingly Not Started **by design** — CLAUDE.md §3 says an
  agent must not build P1/P2 scope ahead of its own module's P0 stories,
  so "mostly not started" is the correct, intended state of a program still
  finishing its P0 release gate, not an oversight.

No code changed this pass — documentation-completeness only, per the
story's own scope (CLAUDE.md §3: a release-process rigor requirement, not
a security/isolation gate).

**Progress Tracker:** QA-P1-07 moved from `Not Started` to `Done`.

---

**Three-story summary for today's dispatch:** QA-P0-08 (runtime event
corpus), QA-P0-11 (certification regression), QA-P1-07 (release record
completeness) all closed. `INTEGRATION_STATUS.md` §8's Release Gate blockers
are unchanged by this pass — none of today's three stories touched a
release-gate blocker directly (FinanceBot step 7, the extended QA-P0-06/07
epics' real-IdP/deeper-connector gaps, or the sandbox-only constraints) —
each was a genuinely separate, independently-closeable QA-owned gap. The
remaining `Partial` QA-P0-0x rows (§7) are blocked on real external
infrastructure this environment cannot provide (a test IdP, GitHub Actions
secrets/Vercel Preview env vars, a Lighthouse/timing run against a loaded
tenant) or are explicitly another module's own scope per non-negotiable #18
(the Risk regression matrix, QA-P0-10) — recorded, not silently worked
around.

---

## 2026-09-25 — Handed over: RLS-only tenant reads

`listAgents()` was found relying on RLS alone. `current_tenant_ids()` admits
every tenant the user belongs to, so a member of two organizations saw both
organizations' agents in whichever one was selected. It was fixed in
Identity (codebase-map D10).

**Handed to QA Agent:** sweep every service read that takes a `tenantId`
and queries a tenant table without an explicit `.eq("tenant_id", …)`, and
add a two-membership isolation case to the E2E suite.

Full Playwright run, same date: 140/141 passed. The one failure is the
known GoTrue rejection of `@example.com` in the sign-up spec, unrelated to
this change.

Later the same day, after the responsive pass, a full run went 141/142.
The FinanceBot scenario's final `resolved` assertion failed under the
two-worker load, then passed 3 of 3 when run alone. **Handed to QA:**
harden that step to wait on the re-evaluation outcome instead of a fixed
10-second visibility timeout.

**Later on 2026-09-25: sign-up spec adjusted, not skipped.** GoTrue on
this project rejects `@example.com` sign-ups ("Email address … is
invalid") on most runs. That is provider-side domain validation, the same
category as the "email rate limit exceeded" answer the spec already
accepted.

The spec's stated intent is unchanged: the app must complete sign-up or
surface the provider's own message, never fail silently. It now accepts
either message, scoped to `role="alert"`. It passes, and would still fail
on a silent failure or an app error.

---

## 2026-09-25 — QA-P0-19: FinanceBot scenario hardened (root cause, not a retry)

**The flake.** The final step clicks "Run risk evaluation now", then
Resolve. Both are server actions that re-render the same URL, so the old
`toHaveURL` check passed before the evaluation finished. Under the full
suite's two-worker load the Resolve click could land on the page while it
was still re-rendering, the submission was lost, and "resolved" never
appeared. Run alone it always passed, which is why it looked random.

**The fix.** Each action now awaits its own POST response
(`page.waitForResponse` on the action's URL) and `networkidle` before the
next step. No assertion was weakened and no timeout was raised; the test
now waits for the thing that actually has to finish.

**Verified.** It passed alone 3/3 before the change. After it, the runtime,
risk and FinanceBot specs pass together under two workers, 22/22, and the
full suite passes (see the next line).
Full suite after the fix: **156/156**.

---

## 2026-09-25 — QA-P0-17: RLS-only read sweep (codebase-map D10), and the writes it led to

**Why it matters.** RLS admits every organization a user belongs to
(`current_tenant_ids()`). A member of two organizations therefore gets
both organizations' rows from any query that relies on RLS alone. Writes
are worse: the caller's permission is checked only in the active
organization, but an RLS write can land in the other one.

**Method.** A read-only search agent walked every one of the 337
`.from(...)` chains in `modules/`, `lib/` and `app/`, checking for a
`tenant_id` filter. A second pass covered writes: any RLS-client write
that trusts a caller-supplied parent id. Every hit was then confirmed by
reading the code before it was changed.

### Reads fixed (an explicit `tenant_id` filter; RLS stays underneath)

- **Mixed organizations with no filter at all:**
  - `GET /api/v1/users`: the member list of every organization;
  - Identity's discovery inbox (agents and identities);
  - the duplicate check at registration: registering in organization B
    could be diverted to "duplicate review" against organization A's
    agent;
  - the duplicate-candidate list.
- **By id, with `tenantId` already in scope:**
  - `getAgent`, `getApplication`, `getIntegration`, `discoverMcpTools`;
  - `getSyncJob`, `listSyncJobs`, `getNormalizedObjects`;
  - the integration status update in `testIntegrationConnection`;
  - the credential read and update in `setCredential`.
- **By id, now taking a required `tenantId`, so the type checker found
  every caller:**
  - `getPolicy`, `listPolicyExceptions`, `getAgentContract` (8 callers
    across Access, Risk, Runtime and Compliance);
  - `classifyActionsForAgent`;
  - the child tables with no `tenant_id` column, filtered through their
    parent with an `!inner` embed: `listPolicyRules`,
    `listPolicyVersions` and `listMappings`.
- **Low-risk, filtered for consistency:** effective-access grants, the
  access-path explanation, and policy-exception evaluation.
- **Correctly unfiltered, left as they are:**
  - the user's own memberships and roles (by `user_id`);
  - SSO domain lookup and API-key verification (they identify the tenant);
  - the platform-admin console, which is platform-wide by design.

### Writes fixed

- **`addPolicyRule` and `createMapping`** now take the tenant and confirm
  the parent is in it first. `integration_mappings` has no `tenant_id`,
  so this check is its only guard.
- **`createControlMapping`** is a service-role write, so it could point at
  any tenant's policy. It now also requires the owner to be an active
  member.
- **`createApplication`** checks its `sourceIntegrationId`, which has no
  foreign key.
- **Migration 0076** replaces 13 single-column foreign keys with
  `(col, tenant_id)` keys to the parent's `(id, tenant_id)`:
  - Access: `accounts`, `entitlements`, `access_grants`,
    `access_requests`, `policy_exceptions`;
  - Compliance: `control_mappings`;
  - Integration: `integration_sync_jobs`.
  - Each key keeps its name and its ON DELETE rule, the lesson of the
    0073/0074 incident, so every PostgREST embed resolves as before.
  - No live row crossed tenants beforehand (checked).
  - A refused reference now answers 404 ("… is not in this organization"),
    not 500.
- **`selectTenantAction` (the organization switcher) was broken.** It
  looked up the membership without the user's id, so in any organization
  with two or more members it got several rows, `maybeSingle()` returned
  nothing, and switching failed with "Not a member". It now filters by
  the signed-in user.
- **`createPolicy`** now answers 400 for an unknown action; before, the
  database check turned it into a 500. The new spec found this.

### Tests

- **New E2E `multi-org-isolation.spec.ts`**, with a new seeded identity
  `multiOrg`: READ_ONLY in Tenant One, TENANT_SUPER_ADMIN in Tenant Two.
  It switches organization through the real sidebar switcher.
  - In Tenant Two, registering an agent with a Tenant One agent's name is
    201, not a 202 duplicate. The list shows only Tenant Two's agent.
  - In Tenant One:
    - the list holds only Tenant One;
    - Tenant Two's agent and policy are 404 by id;
    - their rules and versions are empty;
    - the Agent 360 page renders not-found;
    - duplicates hold nothing from Tenant Two.
  - In Tenant One, the Tenant Two admin role does not carry over:
    creating an agent is 403, adding a rule to Tenant Two's policy is
    refused, and `/api/v1/users` is 403.
  - In Tenant Two:
    - an exception on its policy for Tenant One's agent is 404, while the
      same exception for its own agent is 201;
    - an access request for Tenant One's agent is 404;
    - the member list is Tenant Two's only;
    - Tenant One's agent is 404.
- **SQL `tests/qa/same-tenant-references.sql`,** run live as a member of
  both fixture tenants:
  - an entitlement, account, access request and two policy exceptions
    pointing across tenants are all denied with 23503;
  - the service-role control mapping to another tenant's policy is also
    denied with 23503;
  - own-tenant writes are 1, 1 and 1;
  - forged rows are 0;
  - fixtures cleaned up.
- **Unit:** `credentials.test.ts`'s mock now follows the tenant-filtered
  chains. Vitest 536/536.
- **After 0076,** the navigation, access, data-sources, FinanceBot and
  compliance specs pass (54/54).
- Full pipeline: `tsc` and `eslint` clean, vitest **536/536**, Playwright
  **201/201** (9.9 min, fresh build, with 0076 applied live).

---

## 2026-09-26 — QA-P0-20: WonderID adopted; baseline locked before any change

**What happened.** The user supplied the WonderID P0 implementation
specification: v2, then a repository-grounded v3 with 5 mockup boards. Its
scope contradicts the contract: an identity governance (IGA) platform for
human, external, machine and AI-agent identities, where non-negotiable #7 and
§10 said "not a replacement IAM/IGA". Asked directly, the user chose to:

- adopt WonderID and amend the contract;
- rename the product in the app now, keeping the repo, Vercel project,
  database and domain;
- replace the light-console rail with the dark navy sidebar.

v3 settles the fourth question, which went unanswered: v2 §25 named
`agent_runs`, households and similar, which do not exist here. v3 makes this
repository the only implementation source, and "WonderAgent" means its own
agent governance.

**What changed:**

- **`CLAUDE.md`:**
  - the header now describes WonderID, with WonderAgent kept as the
    repository lineage;
  - a dated adoption note;
  - non-negotiable #7 rewritten: WonderID governs identities and access, but
    is not an IdP, vault, SIEM or SOC, and HR/directory sources stay the
    system of record for what they own;
  - §10 items 1 and 7 replaced;
  - a WonderID extension line per module under the ownership table;
  - the navigation decision recorded in §13.
- **The specification and mockups** are stored in `docs/requirements/`.
- **`docs/plan/WONDERID-ROADMAP.md`** lists 36 stories across 12 phases,
  each owned by an existing module. It also records five planning decisions
  taken by the spec's autonomy rule: the identity reference model, three
  separate kinds of role, where the workflow engine lives, passwordless on
  Supabase Auth, and brownfield access defaulting to UNPROVEN.
- **Every affected backlog** gained Progress Tracker rows and a
  "WonderID (2026-09-26)" section defining its stories.

**Baseline** (`docs/implementation/wonderid-baseline.json`), at `84e3dda`:

- typecheck and lint clean;
- vitest 74 files, 536/536;
- `next build` passes;
- 76 migrations (latest 0076);
- 28 E2E spec files, last full run 201/201.

## 2026-09-26 — design-review width sweep split in two (suite health)

The layout sweep in `design-review.spec.ts` loads every listed route in one
test per width, with a 300 s budget. The WonderID routes have taken the list
past 30 routes. Two full runs on 2026-09-26 timed out on the last routes at
1680 and 1440 px, yet the spec passed alone.

Each width now sweeps the list in two halves, in two tests. No route or
check was removed. Agent 360 is still resolved from the list, in part 1.
The split spec passed alone, 29/29, in 5.6 min.

---

## 2026-10-01 — New isolation proof for billing, privacy and the audit trail

`tests/compliance/billing-privacy-tenant-isolation.sql` covers migrations
0101–0104. It runs in one transaction and rolls back. It was run live and all
28 checks matched (see the Foundation, Platform and Compliance entries for the
list). The full Playwright suite was **not** run in this session. Because
`proxy.ts`, security headers and RLS changed, §17.8 requires it before the
next release. The existing `csrf.spec.ts` should still pass: it uses a GET,
which the new cross-site write guard does not touch.

### 2026-10-01 (later) — E2E spec for payments, privacy, audit integrity and security

New file: `tests/e2e/trust-compliance.spec.ts`, 7 serial tests.
- Security: headers, `security.txt`, and the cross-site write guard returning
  403 `CROSS_SITE_REQUEST`.
- Billing:
  - The screen renders.
  - A bad GSTIN is refused and a good one is accepted.
  - A body `tenant_id` is ignored.
  - Checkout is refused truthfully when no provider is configured.
  - Unsigned webhooks are refused.
- Privacy:
  - A GDPR request's deadline is one month, and completion is refused until
    the identity is verified.
  - The export works, and a closed request never reopens.
  - A DPDP erasure gets 90 days, an extension is refused, and self-approval is
    refused.
  - A DPDP breach lists the Board obligations, and closing is refused while
    they are outstanding.
- Self-service export works, and the audit chain verifies intact.
- A read-only member gets 403 on billing and privacy administration but still
  reaches `/privacy/me`. Tenant Two gets 404 on everything of Tenant One's.

The spec typechecks, lints and is discovered by `playwright test --list`. It
was **not run**: this sandbox has no `SUPABASE_SERVICE_ROLE_KEY`, which
`auth.setup.ts` needs. The `e2e.yml` workflow has it as a repository secret and
runs it on the next push to `main` or the next PR, together with the full suite
§17.8 requires.

---

## 2026-10-09 — CI and deploy optimized; Playwright moved to nightly

User request: optimize CI and CD and minimize build and deploy time. End-to-end
tests run nightly; per-change CI runs feature-specific tests only.

**Before** (measured from the last runs):
- **CI `checks`:** about 80s, one serial job:
  - `npm ci` 15s;
  - typecheck 19s;
  - lint 25s;
  - all unit tests 17s.
- **CI `e2e`:** the full Playwright suite on every pull request and push. It
  has been red on every commit because the repository has no Actions secrets.
- **Vercel production deploy:** about 92s from start to ready (2-core build
  machine):
  - install 3s;
  - compile 27s;
  - `next build`'s TypeScript pass 34s;
  - page data and static pages 7s;
  - deploy 11s.
  
  Every merge deployed, including docs-only ones.

**What changed.**
- **`security.yml`** is now four parallel jobs: typecheck, lint, test and
  security.
  - `node_modules` is cached on the lockfile hash, so `npm ci` runs only when
    the lockfile changes (new `.github/actions/setup`).
  - `tsconfig.tsbuildinfo` and `.eslintcache` are cached, so tsc and eslint
    re-check only what changed.
  - On a pull request, lint covers the changed files and the unit tests are
    `vitest related` on the changed files (the tests that import them). This
    uses the merge commit's first parent, so a depth-2 checkout is enough.
  - A change to `package.json`, the lockfile, `tsconfig.json`, the
    Vitest/ESLint/Next config or `.github/` runs everything, and so do push
    to `main` and the nightly schedule (03:17 UTC daily, previously weekly).
  - Docs-only changes skip CI, and a newer push cancels the older run.
  - `npm audit` reads the lockfile without installing.
- **`e2e.yml`** no longer runs on pull requests or pushes. It runs nightly at
  21:30 UTC (03:00 IST) and by hand (`workflow_dispatch`).
  - A hand-started run takes an optional list of spec files. The list is
    passed through an environment variable, never interpolated into the
    script.
  - The timeout is raised to 60 minutes for the full suite.
  - It still needs the repository's Actions secrets
    (`NEXT_PUBLIC_SUPABASE_URL`, `NEXT_PUBLIC_SUPABASE_PUBLISHABLE_KEY`,
    `SUPABASE_SERVICE_ROLE_KEY`, `SECRET_ENCRYPTION_KEY`, `CRON_SECRET`). Until
    the owner adds them, the nightly run fails at setup.
- **Vercel.**
  - `next.config.ts` sets `typescript.ignoreBuildErrors` only when
    `VERCEL=1`, which removes the 34s duplicate of CI's typecheck from every
    deploy. Local and E2E builds still type-check.
  - `vercel.json` gains `ignoreCommand: bash scripts/vercel-ignore-build.sh`.
    It keeps the project's existing behaviour (production only, no preview
    builds). It skips a production deploy when everything changed since
    `VERCEL_GIT_PREVIOUS_SHA` is docs, tests, CI, Supabase migrations,
    scripts or test config, and builds whenever it is unsure.
- CLAUDE.md §4, §12, §17.8, §19.6 and §19.8, ORCHESTRATION §2–3 and
  RUN_ORDER now describe the new policy:
  - pull requests merge on green `security.yml`;
  - shared-infrastructure changes run their affected specs first, locally
    or by a hand-started `e2e.yml`;
  - a red nightly run is fixed before anything else merges.

**Verified.**
- All three YAML files parse.
- `vercel-ignore-build.sh`, dry-run against real commits:
  - docs-only #7 → skip (exit 0);
  - a range including #6's app code → build (exit 1);
  - a preview → skip;
  - an unknown previous SHA → build.
- The changed-file commands run locally:
  - `vitest related` on `lib/tenant/organizationName.ts` ran its 4 tests in
    3.4s;
  - changed-file eslint finished in 1.8s.
- Typecheck is clean.
- Expected afterwards:
  - pull request CI about 30–40s wall clock, down from about 80s;
  - production deploys about 55–60s, down from about 92s;
  - docs-only merges no longer deploy.

  The numbers will be confirmed on this PR and the next deploy.

**Left to the owner.**
- Add the five Actions secrets so the nightly suite can run.
- Optionally, a larger Vercel build machine. Compile time scales with cores:
  the current machine has 2 cores and 8 GB.

**Measured after merging (#8, `3a969ad`).**
- **Pull request CI:** 52s wall clock on its own PR, down from about 83s.
  That was the slowest case:
  - an empty `node_modules` cache, so `npm ci` ran;
  - full lint and tests, because `.github/` changed.

  Each job took 7–50s, all running in parallel.
- **Production deploy:** 38s from build start to ready, down from 92s.
  - "Skipping validation of types": the 34s TypeScript pass is gone.
  - Compiled in 5.2s from the restored build cache.
  - `vercel-ignore-build.sh` logged "App code changed since 2e81268;
    building".
- **Local full Playwright run** of the earlier sign-up change (before #8):
  350 passed, 3 failed, 4 did not run.
  - The 3 failures were `mcp-bridge`, `mcp-inventory` and one
    `request-catalog` test that lost its connection ("socket hang up").
  - All three specs passed on rerun (21/21).
  - The likely cause: `npm audit fix` replaced `node_modules` under the
    running server mid-run. This is not proven. None of the three touch
    the sign-up change.

## 2026-10-10 — Isolation proof for connector_definitions (migration 0108)

`tests/integrations/connector-definitions-isolation.sql` was run against the
dev project as one transaction, then rolled back. It reuses the FinanceBot
fixture (Tenants A5/B5). All 9 checks came out as expected:

- tenant A reads its own definitions and none of tenant B's, and B reads none
  of A's;
- a member without `integration.create` cannot publish (42501);
- an IAM Admin publishes into their own organization but not into another
  (42501);
- client updates and deletes affect 0 rows;
- the immutability trigger refuses a service-role edit (23514).

Nothing persisted, as a follow-up count confirmed. Security advisors after
0108 show no new findings.

The connector framework also gets a live contract test,
`modules/integrations/framework/live.test.ts`. It is skipped unless
`CONNECTOR_LIVE_FILE` is set, and it is run by hand against the Planet
Express demo company (10/10 connectors pass). Recorded in the Integration
audit log.

## 2026-10-10 — Architecture test for the connector boundary (non-negotiable #20)

`tests/architecture/connector-boundary.test.ts` scans `app/`, `modules/` and
`lib/` on every unit run and fails when:

- any server code outside the connector framework calls out (the allowlist
  is WonderID's own AI model and email providers);
- browser code calls anything but WonderID's own API;
- a route runs without a user session outside the allowlist (`/api/connect/`,
  `/api/cron/`, billing webhooks, SSO domain lookup);
- a retired direct route reappears.

Widening an allowlist needs the user's approval. 4/4 pass.

## 2026-10-10 — Two-level connections, the Connector Gateway, CSV files and object-page import/export: integration and verification

Four slices built in parallel worktrees (Integration, Experience and
Operations Agent scope), reviewed and integrated by the lead session into
one branch:

- **Connection types and connections:** two levels under Integrations.
  `/integrations/types` lists every type with its protocol details; the
  old catalog URLs redirect to it. `/integrations` is the list of actual
  connections, each made from a type.
- **Connector Gateway:** every connection's traffic, in both directions,
  passes `modules/integrations/gateway`. It checks, in order, that the
  connection is enabled, then the request budget, then the rate limit, and
  writes a per-minute traffic ledger (`connector_traffic`, migration 0110).
  The `/integrations/gateway` page and a Traffic card show it.
  - The boundary test's outbound allowlist now names the gateway. This is
    the user's 2026-10-10 requirement that all connections pass one
    gateway.
- **CSV files:** the `file` driver and the `csv-file` type, read from an
  HTTPS address or pushed to `/api/connect/v1/<id>/file`.
  - Connection schedules run through the daily cron
    `/api/cron/connector-syncs`.
  - `POST /api/v1/imports` puts an object page's file through the
    organization's "File imports" connection (migration 0111).
- **Actions menu:** "Export CSV", plus "Import CSV…" where the kind is
  importable, on 28 list pages, behind `GET /api/v1/exports/<object>`.

Lead fixes made while integrating:
- Capability validation for connector connections is checked against their
  definition, which kept the 0109 fix through the gateway merge.
- The import dialog now says where the rows went (the File imports
  connection) and links to it. It no longer implies they are already in the
  page's list.
- Vitest skips agent worktrees.

Verification:
- **Unit tests:** `npm run typecheck` clean; vitest 995/995 (122 files); eslint
  shows 0 errors on the changed files.
- **Migrations:** 0110 and 0111 applied to the dev/prod project. The
  isolation SQL for each ran in one transaction that was aborted, so it left
  nothing behind.
  - `connector_traffic`: 14/14 checks as expected. Each organization reads
    only its own rows. A row naming another organization's connection is
    refused by the foreign key. Clients cannot insert, update, delete, record
    or purge. The purge keeps recent rows.
  - `connector_files`: 8/8 checks as expected. Files are invisible and
    immutable to clients, and a client job cannot claim a schedule window.
    The same-organization foreign key and the single File imports connection
    both hold.
- **Playwright, run locally against a production build:**
  - Connection types/connections and exports: integrations, navigation-smoke,
    mcp-bridge, mcp-inventory, design-review and the audit specs, 83/83.
  - Gateway: runtime-gateway, emergency-controls, gateway-enforcement,
    policy-publish, shadow-ai, mcp-bridge, mcp-inventory, outbound-guard,
    integrations, account-inventory and navigation-smoke, 95/95.
  - CSV: the new `file-import.spec.ts` plus the integration and gateway
    specs, 85/85.

Open, for the owner:
- Rows imported from an object page land in the File imports connection's
  staging records. They reach the directory or inventory only when that
  connection is reconciled (Identity Sources, application onboarding).
  Reconciling automatically from a partial file could treat everyone
  missing from it as a leaver, so it is not done.
- Vercel caps request bodies at 4.5 MB. Uploads through the hosted app top
  out there; files fetched from an address can be 10 MB.
- The retired integration types and the stale Zendesk credential still need
  a delete migration. The database tool refused delete statements in 0109.

## 2026-10-10 — The nightly Playwright suite runs on Vercel; parallel-agent rule

**Why:** the nightly `e2e.yml` run had been running zero tests. Its five
GitHub Actions secrets were empty, so sign-in failed in setup. The owner
decided the suite should run on Vercel, where the variables are already
defined.
- Three of them (service role key, encryption key, cron secret) are
  Sensitive in Vercel. Vercel never hands those out, through the API or
  `vercel env pull`, so they cannot be copied to a GitHub runner.
- This session also cannot write GitHub Actions secrets: the proxy refuses
  that path.

**What changed:**
- `vercel.json` `buildCommand` → `scripts/vercel-build.sh`. Every deployment
  still runs `npm run build`.
- On the `e2e/nightly` branch only, the build runs `scripts/e2e-on-vercel.sh`.
  It:
  1. installs Chromium's system libraries with `dnf` (Amazon Linux 2023);
  2. installs Playwright's headless Chromium and checks with `ldd` that no
     library is missing;
  3. builds the app, starts it on localhost:3100 with private-network stubs
     allowed, as playwright.config.ts's webServer does (that process only);
  4. runs the suite with a 38-minute cap under Vercel's 45-minute build limit.

  A failure fails the build.
- `scripts/vercel-ignore-build.sh` builds that branch even though preview
  deployments are otherwise off.
- `.github/workflows/e2e.yml` no longer runs the suite and needs no secrets.
  - It moves `e2e/nightly` to main with one marker commit, attributed to the
    owner so Vercel builds it. A manual run's `specs:` line goes in that
    commit's message.
  - It then waits for Vercel's commit status, so a red suite still shows red
    in the Actions tab.
- The dependency list came from a probe in a Vercel Sandbox: `ldd` on the
  headless shell showed exactly which libraries it needs. The sandbox's image
  was Ubuntu, not the build's Amazon Linux, so the first real nightly build
  is the confirmation.
- Trade-off: while the nightly build runs (03:00 IST), it holds Vercel's
  single build slot, so a production deploy at that hour queues behind it.

**Parallel agents:** the owner's rule is now in `docs/ORCHESTRATION.md` §1.
Several agents may work at once only on independent slices, each in a
worktree the lead creates from an exact, already-pushed base commit. The
dependencies, contracts and shared numbers are fixed up front. Finished
slices are rebased and re-verified one at a time. The first parallel run
broke this: two of its four agents started from `main` without the
unmerged work they built on.

### 2026-10-10 — First full run on Vercel; the suite now runs in two halves

The first full run on Vercel reached test 355 of 367 before the 38-minute cap
stopped it.

Measured cause:
- 367 tests take about 12.8 s per test per worker. That is the same in this
  Ohio container and in Vercel's Washington builds, so the distance to the
  Singapore database is not the difference.
- With 2 workers, the whole suite needs about 39 minutes anywhere.
- On Vercel's 2-core build machine, the app server and two browsers compete
  for CPU. The heaviest pages (`/runtime`, `/risk`) then missed the 10 s
  heading check, which they pass on 4 cores.

Changes:
- The full suite runs as two halves (`--shard=1/2`, `--shard=2/2`) on the
  `e2e/nightly-1` and `e2e/nightly-2` branches. Each is about 20 minutes, with
  a 35-minute cap. The workflow waits for both.
- `E2E_SLOW_MACHINE` (set only in the Vercel build) doubles Playwright's
  timeouts there: 60 s per test, 20 s per expectation. Local runs keep
  30 s and 10 s.
- The build log ends with a compact summary written from Playwright's JSON
  report: counts, then each failed test with the first line of its error.
  Playwright is interrupted with SIGINT on time-out, so the report is
  written even when a run is cut short.
- Checked locally: `bash -n`, the summary parser against a sample report
  and a missing one, and the workflow's branch marking against a throwaway
  remote.

Earlier in the day, the trial run of one spec (navigation-smoke) proved the
pipeline on Vercel:
- the `dnf` libraries and Playwright's Chromium installed;
- the app built and the suite ran: 14 passed.

The remaining failures in that run came from the Vercel Toolbar script that
Preview builds inject, which the app's CSP blocks. It is switched off for the
test build (#16).

### 2026-10-10 — The other Vercel project, and fuller failure output

- A second Vercel project (`kunals-projects-9f64757f/wonder-id`) is connected
  to this repository.
  - It started building the test branches too, and failed, because it has
    none of the suite's variables.
  - It posts its status under the same name ("Vercel – wonder-id"), so the
    workflow read its failure as the suite's result.
  - Fixed in three places:
    - the ignore script builds the test branches only in this project
      (`VERCEL_PROJECT_ID`, or the service role key being present);
    - the test build stops at once without those variables;
    - the workflow reads only statuses linking to
      `luvchakras-projects/wonder-id`.
- First two-half result, half 1: 182 passed, 2 failed, 3 skipped, 30 min.
  - `branding.spec.ts:47`: the sign-in screenshot baseline was recorded on
    Ubuntu, and the Vercel builder runs Amazon Linux, so text renders
    differently there.
  - `gateway-enforcement.spec.ts:83`: `toHaveURL` after registering an
    agent. The spec passes locally, 11/11 on the same commit. The
    difference is under investigation; the summary now prints six lines of
    each error to show where the page went.

### 2026-10-10 — Clean two-half run on Vercel

This was the first run after the other Vercel project stopped building the
test branches (#18).

- **Half 1** (`e2e/nightly-1`, 2 cores, iad1): **185 passed, 1 failed,
  1 flaky, 25 min.**
  - `gateway-enforcement`, which had failed while the other project's
    suite ran at the same time, passed.
  - The only failure was `branding.spec.ts:47`, the sign-in screenshot:
    5,023 pixels (2%) differed, against a 1% tolerance. The baselines are
    Ubuntu renders (`*-chromium-linux.png`), and the builder renders text on
    Amazon Linux 2023.
  - Next step: environment-specific baselines recorded on the Vercel
    builder, not a looser tolerance.
- **Half 2** (`e2e/nightly-2`) was CANCELED about 4 minutes into its tests,
  after 26 minutes queued behind half 1.
  - The build log ends mid-run with no error.
  - No other deployment of the project was created at that time.
  - The cause is not known.
- **Rule:** never run Playwright locally, or anywhere else against the
  shared database, while a run on Vercel is in progress. The suites share
  the same test users, and their setup signs those users in again, which
  ends the other run's sessions.

### 2026-10-10 — Nightly E2E paused

- The owner cancelled the second half of the clean run and asked for no
  more runs for now.
- The nightly schedule in `e2e.yml` is commented out. A run can still be
  started by hand.
- The other Vercel project (`kunals-projects-9f64757f/wonder-id`) is the
  owner's, and the owner has paused it.
- The one open issue is the sign-in screenshot baselines for the Vercel
  builder (Amazon Linux rendering). Restore the schedule once they are
  recorded.

### 2026-10-10 — Nightly E2E schedule restored

The owner asked for the schedule back, so it is restored (03:00 IST). Until
the sign-in screenshot baselines are recorded for the Vercel builder, the
nightly run is expected to fail on `branding.spec.ts:47` alone.

### 2026-10-10 — Screenshot baselines per rendering environment

**Diagnosis:**
- On the sign-in page, every glyph is drawn in the Geist web font.
  Chromium's `CSS.getPlatformFontsForNode`, run over the whole page,
  reported only "Geist (web font)", and the page has no characters outside
  ASCII, so no system font fallback is involved.
- The 2% difference on the Vercel builder is therefore rasterization: the
  same font hinted and anti-aliased by Amazon Linux's FreeType and font
  configuration rather than Ubuntu's. No single setting makes the two
  identical.

**Fix:** each environment is compared with its own recording, at the same
tolerance.
- `playwright.config.ts` names baselines `*-linux-vercel.png` when
  `E2E_SNAPSHOT_ENV=vercel`, which only `scripts/e2e-on-vercel.sh` sets.
  Local runs keep `*-linux.png`.
- **Recording:** the workflow's `record_baselines` input, used with chosen
  specs, adds `record-baselines: yes` to the marker commit. The Vercel build
  then:
  1. runs `--update-snapshots=missing`, which never overwrites an existing
     baseline;
  2. copies the new images into `public/brand/__e2e-baselines/` (served
     without a session; it exists in that build only) and builds again,
     so that preview deployment serves them;
  3. finishes successfully, even though Playwright marks the run failed
     because it had to write baselines.

  The images are reviewed and committed by hand.

**Verified locally:**
- Default paths: branding baseline spec 8/8 passed.
- `E2E_SNAPSHOT_ENV=vercel`: the test looks for and writes
  `sign-in-{desktop,mobile}-chromium-linux-vercel.png`.

  The `-vercel` images written locally were Ubuntu renders and were
  deleted, never committed.
- Workflow marker commit and message parsing, checked against a throwaway
  remote.

### 2026-10-10 — Vercel builder baselines recorded

- Two recording runs on Vercel for `branding.spec.ts`. In both, everything
  else in the spec passed: 11 of 12, the twelfth being the expected
  write-the-baseline failure.
  - Both runs produced byte-identical images: desktop 1280×872, 49,960
    bytes; mobile 390×844, 42,161 bytes. Rendering on the builder is
    stable.
  - The images were downloaded from the recording deployment through a
    Vercel share link.
- **Review:** compared by eye with the Ubuntu baselines. Same layout and
  elements; only the text rasterization differs. They are committed as
  `tests/e2e/branding.spec.ts-snapshots/sign-in-{desktop,mobile}-chromium-linux-vercel.png`.

### 2026-10-10 — Owner decisions recorded: gateway allowlist, screenshot difference

- **Gateway allowlist: approved.** The owner explicitly confirmed adding the
  Connector Gateway (`modules/integrations/gateway/`) to the outbound
  allowlist of `tests/architecture/connector-boundary.test.ts`.
  - Non-negotiable #20 requires approval for any widening.
  - The allowlist entry and `docs/integrations/CONNECTOR-FRAMEWORK.md` now
    say so.
- **Screenshot difference: accepted as a pass.** The owner accepted the
  remaining rendering difference between the Ubuntu and Vercel builder
  screenshots, and asked that no more time go into it.
  - The sign-in baselines stay per environment, as recorded above.
  - No further work is planned.
- **Object-page CSV import.** `tests/e2e/file-import.spec.ts` was rewritten
  for the preview-then-import flow. The spec run on Vercel is recorded in
  the next entry.

### 2026-10-10 — `file-import.spec.ts` on Vercel: 16 passed

The rewritten spec was run on the Vercel builder before merging PR #25 (a
marker commit on `e2e/nightly` with `specs: tests/e2e/file-import.spec.ts`).

- Deployment `H1MQ7uJgH47YVm3dR4zf1Z1uPz8t`: **16 passed, 0 failed, 0 flaky**
  in 2.7 min.
  - The 7 sign-in setups.
  - The 9 import tests:
    - the preview stores nothing;
    - confirming adds the records to the list;
    - a later file updates one record and leaves the omitted one active;
    - the dialog's preview table, then Confirm import;
    - Cancel import stores nothing;
    - files and kinds that are refused;
    - export;
    - another organization and a read-only member are refused.
- PR CI (typecheck, lint, test, security) was green. `next build` passed
  locally.

### 2026-10-10 — Vercel Toolbar back in the test build: the switch moved

The run of the sidebar specs for PR #30 (deployment
`DnfiK9hmUTgoG5emJyk6EHMa4HRW`) failed `navigation-smoke.spec.ts` on almost
every route. Each page logged the same console error: the CSP blocked
`https://vercel.live/_next-live/feedback/feedback.js`.

- **Cause.** Vercel now builds Next.js 16 through its build adapter
  (`@vercel/next` 22, "Applying modifyConfig from Vercel" in the log). The
  adapter injects the toolbar into every page through
  `instrumentationClientInject` when `VERCEL_PREVIEW_COMMENTS_ENABLED=1`. The
  older builder read `VERCEL_PREVIEW_FEEDBACK_ENABLED`, which is the only
  variable PR #16 switched off.
  - The clean two-half run earlier today came before the change.
- **Fix.** `scripts/e2e-on-vercel.sh` now also exports
  `VERCEL_PREVIEW_COMMENTS_ENABLED=0`, for the test build only. Production
  never carries the script, and the app's CSP is unchanged.
- The result of the re-run is recorded in the experience audit log's
  sidebar entry.

### 2026-10-10 — Fewer E2E runs before merging (owner decision)

The owner asked for fewer E2E runs. Pre-merge spec runs on Vercel had been
started for most pull requests, UI work included.

- **Decision.** Affected specs run before a merge only for a
  security-sensitive change:
  - sign-in, sessions or `proxy.ts`;
  - tenant resolution;
  - RBAC and permissions;
  - RLS and migrations;
  - connectors, with their webhooks and file imports.

  Everything else, UI work included, waits for the nightly full suite.
- **Unchanged.** The nightly full suite still runs every night, and a red
  nightly run is still fixed before anything else merges.
- **Where.** `CLAUDE.md` §17.8 and `docs/ORCHESTRATION.md` §3.

### 2026-10-10 — Vercel's daily deployment limit blocked production

At 13:16 UTC Vercel refused every deployment: "Resource is limited — try
again in 24 hours (more than 100, code: api-deployments-free-per-day)".
That covered the production deploys of PR #30 (sidebar) and PR #33, PR #32's
preview and its E2E run.

- **Cause.** Of the last 100 deployments (06:51–13:12 UTC):
  - 68 were builds the ignore script cancelled: 51 on working branches and
    17 docs-only pushes to main. A cancelled deployment still counts toward
    the free plan's 100 a day.
  - 12 were E2E runs, 13 were production builds that went live, and 1 was a
    preview that went live; 6 had states the listing cut off.
- **Fix.** `vercel.json` `git.deploymentEnabled` turns off deployments for
  `claude/**` and `module/**` branches. Previews were already off by
  design, so nothing is lost. Production (`main`) and the `e2e/nightly*`
  branches still deploy.
- **Also.** Pre-merge E2E runs are limited to security-sensitive changes
  (previous entry).
- **Still to do once the window frees.**
  - Redeploy production, so #30 and #33 go live.
  - The nightly run may be refused tonight; if so, it is re-run, not
    treated as a test failure.

### 2026-10-10 — Build slot budget written into CLAUDE.md (owner request)

The owner asked for a strategy to use fewer build slots, recorded in
`CLAUDE.md` and also written generically for other apps.

- `CLAUDE.md` §19.9 covers:
  - no deployments for working branches;
  - one production deployment per merge, so docs ride with code;
  - E2E runs on Vercel only when needed, and locally first;
  - verify before pushing;
  - count the last 24 hours before deployment-heavy work, and keep the rest
    for production above 70;
  - what to do when the limit is hit.
- This entry rides with PR #32 rather than its own docs-only pull request,
  per rule 2.

### 2026-10-10 — Vercel builds only on "merge now" or "build now" (owner decision)

The owner set a rule to cut builds further: nothing that makes Vercel build
happens unless the owner's message says "merge now" (merge the ready pull
requests) or "build now" (a redeploy or an E2E run on Vercel).

- Pull requests are still pushed and opened. Each waits, green, until then.
- "merge now" covers every pull request open and waiting at that moment
  (owner clarification, same day). Every green one is merged; any that
  cannot merge are reported with the reason. "build now" likewise covers
  every waiting Vercel build.
- The nightly suite stays at two builds a night, both halves (owner
  decision). One alternating half a night was considered and declined:
  every test should run every night.
- Checks run locally.
- The nightly suite is unchanged.

Recorded in:
- `CLAUDE.md` §19.9, rule 0, with §4 step 7, §12 and §19.6 amended to
  match;
- `docs/ORCHESTRATION.md` §2.

The "share its Vercel preview URL" steps were dropped. Working branches have
had no previews since PR #34.

This change is itself waiting for "merge now".

### 2026-10-11 — Nightly E2E: half 1 green, half 2 one failure (tenant addresses on Vercel)

GitHub started the scheduled run late, at 00:16 UTC (run 38097869451), not
at 21:30 UTC. It was not started by hand: at 22:45 UTC the project had 82
deployments in 24 hours, above §19.9's limit of 70. Both halves ran on
`3baa5cc` (#39).

- **Half 1** (`e2e/nightly-1`): passed.
- **Half 2** (`e2e/nightly-2`, `dpl_CUpcx6qs8nSeTFA6ZzVFjpXQ5xxb`): **188
  passed, 1 failed, 1 flaky, 11 min.** It is the first half 2 to finish on
  Vercel (the 10-10 runs timed out or were cancelled).
- The fixes in #39 held: the sign-in provider tests and the "AI Agents"
  heading lookups passed.

**Failed: `tenant-address.spec.ts:54`, line 63.** `no-such-organization.localhost:3100/`
answered 200, not 404, on both attempts. The rest of the file passed,
including the tenant's own sign-in page.
- It failed the same way in the 10-10 07:52 run, so it is not a regression
  from #37–#39. It fails only on the Vercel builder.
- It passes locally (1/1), and `curl` returns 404 for both unknown and
  reserved addresses, on each of these builds:
  - a plain build;
  - a build without `BASE_APP_HOST`, started with it, as the Vercel script
    does;
  - a build with Vercel's own Next.js adapter loaded (`@vercel/next`
    22.0.1, `NEXT_ADAPTER_PATH`, `VERCEL=1`, `CI=1`), which is what
    "Applying modifyConfig from Vercel" in the build log refers to. The
    adapter changes nothing that touches the proxy.
- Ruled out:
  - no tenant or domain named `no-such-organization` exists;
  - `resolve_tenant_host()` returns no rows for it and is a set-returning
    function, so the proxy cannot mistake an empty result for a match;
  - the Vercel project defines no `BASE_APP_HOST`.
- Both remaining explanations answer 200 and cannot be told apart from the
  log:
  - the proxy did not see a tenant address and served the landing page;
  - it found one and redirected to sign-in.
- **Change (test only):** each 404 check in that test now reports the final
  URL, any redirect and the page title when it fails, so the next nightly
  shows which explanation holds. The fix follows once that is known. No
  Vercel run was started for it (00:10 instruction).

**Flaky: `trust-compliance.spec.ts:144`** (members download their own data;
the audit chain verifies intact). On the first attempt, "Intact" was not
visible on `/audit/integrity` within 20 seconds. It passed on retry. The
other tests in that serial group were re-run with it and passed. To watch:
the verification walks the whole tenant chain, and the shared E2E tenant's
chain keeps growing.

The file-import spec (10 tests, in half 1) ran in the full suite for the first time and passed.


### 2026-10-11 — QA-P0-23: F1 reconciliation suite (#48)

**Built.** `tests/e2e/f1-reconciliation.spec.ts`, one serial group, against
the shared E2E tenant (`adminOne`) and checked from `adminTwo`:
- **Setup.** A person (Ana), an agent declaring an OAuth client id, and a
  connection whose staging holds what a sync leaves: four accounts (Ana; a
  service account whose source names Ana as owner; the agent's account by
  its client id; an unowned service account), two entitlements, three
  grants. An application is onboarded with `entitlementSource: connector`,
  validated, approved by `iamAdminOne` (four-eyes) and promoted.
- **Accounts.** Ana correlates to her identity; the owned service account
  gets a service identity owned by Ana; the agent's account links to the
  agent, not a service identity; the unowned one is queued.
- **Requests.** The unowned service account cannot be a request subject
  (409 `SUBJECT_UNOWNED`) and is listed on Onboarding › Unowned Identities.
- **Baseline.** The first preview and apply add 2 entitlements and 3
  grants, apply equals preview, and what was found is `LEGACY_EXCEPTION`
  with no finding. A second run changes nothing.
- **Rogue.** A grant added at the source afterwards is `ROGUE` with exactly
  one open finding; applying again opens no second one.
- **Removed.** When the source drops it, the grant is marked missing (not
  revoked), the ledger records `missing_from_source`, and the finding
  resolves.
- **Isolation.** The other organization sees no runs, no accounts and no
  identity (404).

Support: `tests/e2e/support/readAccessGovernance.ts` (service-role reads,
every query filtered by tenant) and `seedIntegrationAccounts.ts`
(entitlement and grant kinds, `normalized` values).

**Defects found and fixed (owners' audit logs updated).**
- Access: onboarding validation's "Entitlement model discovered" counted
  only WonderID entitlements, which a connector-sourced application gets
  only after promotion (ACCESS-P0-27). It now also counts what the
  connector staged for the application. Without it no such application
  could go live.
- Access: the unowned-subject refusal now runs before the policy checks,
  so the reason a request is refused is the subject, whatever the policy.

**Verified.** Local run against dev Supabase (`E2E_CHROMIUM_PATH`): 14/14
(7 sign-in setup, 7 suite), 2.9 min. `npm run typecheck` clean;
`vitest run modules/access-governance` 222/222. No Vercel run (§19.9).

**F1 exit test:** passed on seeded staging. A live connector is not part
of it.

### 2026-10-11 — QA-P0-24: request-to-verified suite (#56)

**What was built.** The F2 loop is now proven end to end in
`tests/e2e/f1-reconciliation.spec.ts`, run against the app's own routes with
a connector's staged records standing in for the target. With the F2 stories'
own tests, the suite covers each acceptance criterion:

| Criterion | Where it is proven |
|---|---|
| A person: request → approve → task → added on the target → verified | ACCESS-P0-28 test |
| A service account (owned) | QA-P0-24 test. The owner asks and the access manager approves (the owner cannot). Task done. The account and the grant appear at the source. Verified on the service account's own account. |
| An AI agent, within its contract | ACCESS-P0-31 test (contract checked, out-of-contract refused), then the QA-P0-24 test: task done, the grant appears on the agent's account, verified. |
| Removal ends revoked | ACCESS-P0-30 test: removal → revoked by reconciliation, REVOKED in the ledger. |
| Expiry ends revoked | ACCESS-P0-32 test: one removal task, revoked by reconciliation, EXPIRED in the ledger. |
| Approver ≠ requester | QA-P0-24 test: the requester's own decision is refused and the request stays pending. Also `approval-engine.spec.ts` and `sod.spec.ts`. |
| Tenant isolation of new tables and columns | `tests/access/pending-grants-isolation.sql` (0121), `fulfilment-tasks-isolation.sql` (0122), and the new `request-lifecycle-isolation.sql` (0123/0124, 11/11). In the browser, the last test: another organization sees none of the requests, tasks or accounts, and cannot decide or claim any of them. |
| A repeated reconciliation never duplicates grants or closes a task twice | QA-P0-24 test: a second access reconciliation reports added 0, verified 0, revoked 0. The grants and the tasks (status, `closed_at`, `updated_at`) are byte-for-byte the same as before it. The expiry sweep's idempotency is in the ACCESS-P0-32 test. |

**New SQL checks** (`request-lifecycle-isolation.sql`, run through
`execute_sql`, self-cleaning). All 11 passed:
- a removal or account task naming another organization's grant or account
  is refused (23503);
- a second live removal task for a grant is refused (23505);
- a task's kind must match what it names (23514);
- an unknown request type is refused (23514);
- a member cannot mark a grant for removal, or stamp a request's expiry
  fields, directly (0 rows);
- another organization reads none of the extension or removal task, and
  cannot cancel the task.

**Verified.**
- E2E (local, dev Supabase): `f1-reconciliation` 20/20, including the new
  test and the extra isolation checks.
- Typecheck and ESLint clean.

**The F2 exit test** ("a person, a service account they own and an agent
within its contract; approvals; tasks; the access added by hand; the next
reconciliation marks each verified; removal and expiry end revoked") passes
on the seeded test organization. FOUNDATION-P0-32 (bulk invitation) is F2's
remaining story; it does not gate the phase.

## 2026-10-12 — Provisioning safety suite (QA-P0-26, F3)

**Built.**
- **The mass-change guard on writes**, which did not exist before.
  `executeConnectorWrite()` (Integration) refuses a write when the
  connection has already made, or is making, the organization's limit of
  changes in the last hour (`integration.maxWritesPerHour`, Global
  Configuration → Connections, default 100, 1–10 000):
  - The write is recorded `blocked` with the reason
    (`integration.write_blocked`) and nothing is sent.
  - The fulfilment task goes back to its owner, who is told. They can do it
    by hand, or Try again once the hour allows.
  - Counting happens after the idempotency claim, so writes racing each
    other count each other and the guard errs towards refusing.
  - If the count itself fails, the write is refused.
  - Pure rule `overWriteLimit()`, unit-tested. The "Imports" section of
    Global Configuration is now "Connections".
- **The suite** (in `connector-provisioning.spec.ts`, alongside the
  pipeline tests it relies on):
  - Read-only enforcement: a connection type with no `write` reports
    nothing supported, and turning writes on is refused (409). Writes off
    leaves every change a person's task (existing tests).
  - The guard: with the limit set to the changes this connection already
    made this hour, an approved removal sends nothing, and the task goes to
    its owner with "Mass-change guard … (limit n)". Try again at the limit is
    refused the same way. With room again, Try again makes the change and
    it is verified. The setting is restored afterwards.
  - Idempotency: no attempt key reached the stub system twice, every request
    it received has exactly one record, and blocked writes never reached it.
  - Verification of every operation (remove, disable, add, create) was
    already covered by INTEGRATION-P0-13's tests.

**Verified.**
- `npm run typecheck` clean; eslint clean on the changed files.
- `npx vitest run modules/integrations lib/config`: 305 passed.
- `connector-provisioning.spec.ts`, local: 18 passed (11 in the spec, 7
  setup), 6.0 min. `global-configuration.spec.ts`: 10 passed.
- `next build` succeeds.

**Left out.** A per-organization (all connections) limit, and a held
"approve the rest" queue like the mass-missing guard's: refused changes
stay ordinary tasks for their owners.

### 2026-10-12 — Failed-page and leaver-outage tests (WID-H03, WID-C02)

Two tracked findings items that needed tests only.
- **`tests/e2e/sync-failed-page.spec.ts` (new, WID-H03).** A stub system
  pages five accounts two at a time.
  - A full read stages all five.
  - Page 2 then fails (503) while `u-5` was really deleted. The run does
    not succeed, and no account is marked missing, neither the unread
    `u-3` and `u-4` nor the deleted `u-5`.
  - Once it recovers, a complete read marks only `u-5` missing.
- **`connector-provisioning.spec.ts`, "WID-C02 leaver" (new case).**
  - Eve leaves (DISABLED) while the connection's writes are on. One
    removal task opens (reason `leaver`, no connector status), and no
    write is sent.
  - With the stub down (`system.down`), the sync fails. The task stays
    open and the grant `pending_removal`.
  - Claimed and marked done while the system still has the membership,
    the next read leaves the task `completed` and the grant
    `removed_unverified`, not revoked.
  - Once the membership is really removed, the next read verifies the
    task and revokes the grant.

Verified, locally against a production build (`npm run build` of main
d58957b):
- `sync-failed-page.spec.ts`: 3/3.
- `connector-provisioning.spec.ts`: 22/22 (8.7 min).
- `tsc --noEmit` and eslint on both specs: clean.

No product code changed.

### 2026-10-12 — Nightly E2E of 12 October red: shared sessions logged out mid-run

The scheduled run at 00:39 UTC (run 38188817822) failed on both halves.
- Half 1 (`dpl_oWxa2xqt34kZaHrhnxci1CozUdis`): 122 passed, 13 failed, 5
  flaky, 66 did not run. It hit the 35-minute cap.
- Half 2 failed too; its log tail shows only stream-closed noise.

It was not investigated at the time, and #96 to #128 merged on top of it.
That broke §17.8 ("a red nightly run is fixed before anything else
merges"). This entry records the investigation and the fix.

Reproduced locally on `main` (9157a18), full suite with 2 workers: 240
passed, 101 failed, 109 did not run, 56.5 minutes. Supabase Auth logs and
the failure times show three causes.

1. **A spec reset a shared user's password.**
   - `automation-credentials.spec.ts` signed in as `iamAdminOne` by
     setting its password through the Admin API (PUTs at 17:55:21 and
     17:55:50). That ends every session the user holds.
   - From then on every spec using the saved `iamAdminOne` session got 401
     "Session is no longer valid" (Auth `/user` 403 "Session not found").
   - These were the onboarding, approval and connector-provisioning setup
     failures, the same as in the nightly.
   - Fix: the spec uses the saved session (`asIamAdmin`). It never
     changes the shared user's password.
2. **Saved sessions carried a setup-time "last seen".**
   - The saved storage state included `wa_session_last_seen` and
     `wa_session_started_at`.
   - A context opened more than the organization's idle limit (30
     minutes) after setup looked idle. The proxy then signed adminOne out
     globally (Auth `/logout` at 18:16, exactly 30 minutes after setup),
     and every later adminOne context failed.
   - The suite has outgrown 30 minutes per half, which is why this is
     new.
   - Fix: `auth.setup.ts` saves the state without the `wa_session_*`
     cookies, so each context's clock starts at its first request.
   - The product's idle and global-sign-out behaviour is unchanged.
3. **Real defects the suite caught.**
   - Launching an agent-scope certification campaign took about 28 s for
     56 agents: one agent after another, five reads each, then one insert
     per item. Fixed: agents are read 16 at a time and items inserted in
     bulk (Compliance).
   - File imports could not update existing people. #127 records value
     history (and #126 disagreements) for every change, and a file
     import's connection is not an identity source, so the history row
     broke its foreign key and failed the record. Fixed: history and
     disagreements are recorded only for real identity sources
     (Identity).
   - `groups.spec.ts` now removes its own leftover groups from runs cut
     short before it starts. An aborted run had left a group still giving
     the requester report access.

Verified, locally:
- the earlier-failing specs (automation-credentials, compliance,
  emergency-controls, connector-provisioning, file-import, groups) after
  the session fixes, then compliance, file-import, groups and
  identity-sources after the code fixes: 43 passed;
- the full suite: see the next entry.

`branding.spec.ts:47` (a screenshot baseline) fails locally as before. It
is environment-specific and known since 10-10.

### 2026-10-12 — full suite after the fixes (local)

Full suite, 2 workers, on the fix branch: **407 passed, 19 failed, 24 did
not run, 51.6 minutes**, against 240 passed and 101 failed before. No
session was lost in this run: adminOne and iamAdminOne stayed valid past
the 30-minute idle limit.

Each remaining failure was looked at; they are not session losses.
- **Layout, real:** `/agents/identities` scrolls sideways at 1024px (a
  722px table in 670px; `design-review.spec.ts:149`). Not fixed here; for
  the Experience Agent.
- **Slowness under load:**
  - campaign launches, once more agents had been added during the run.
    A launch now takes 5.5 s at 80 agents, against 28 s at 56. A large
    organization still needs the campaign filled in the background
    (§15); that is a follow-up;
  - design-review timeouts;
  - bulk invitation (42 invites in 240 s);
  - agent creation (`gateway-enforcement`);
  - `connection-schedule`, `f1-reconciliation:208`, the FinanceBot
    scenario, the connector verification (`connector-provisioning:333`)
    and the automation-credential revocation row.

  The local server is one Next.js process against the remote database,
  and the shared E2E organization grows with every run: 284 campaigns,
  and 80 agents locally, where seeding (skipped here) prunes them.
- **Data left by runs cut short:** `mcp-inventory.spec.ts:57` found two
  `ledger://fy2026` resources.
- **Sign-up:** `first-organization.spec.ts:30` was sent back to sign-in.
  It sits on Auth's sign-up rate limit, already documented in
  `auth.spec.ts`.
- **Known:** `branding.spec.ts:47` (local baseline).

The scheduled nightly on Vercel (21:30 UTC) is the check of record. It
seeds and prunes first; its result is recorded in the next entry.

### 2026-10-12 — the nightly checks the production edge (WID-H08)

- `scripts/e2e-on-vercel.sh` now sets `E2E_INGRESS_URL=https://id.wonderapps.biz`.
- With it, `automation-credentials.spec.ts` "WID-H08" also calls production
  through Vercel's edge with spoofed address headers, and expects a refusal.
- The positive control (the rate limit) uses only that credential, in the
  E2E organization. It sends three API reads to production per night.
- Without the variable, as in a plain local run, the test checks only the
  local server's fail-closed refusal.

Run by hand: 13 passed.
### 2026-10-13 — E2E run started by hand: 2 failures, both looked into

GitHub never fired the 12 October 21:30 UTC schedule (no run was created;
the workflow is active). I started the full suite by hand at 01:32 UTC on
`main` (`cd75238`, which includes #129 and #130); run 38332589533.

| Half | Result |
|---|---|
| 1 (`dpl_7yqBCct7KZFWhxHc61Qr6PAUETKx`) | 171 passed, 1 failed, 56 not run; hit the 35-minute limit |
| 2 (`dpl_Cpi6VxCARecu5bMngmqijiMuuuob`) | 226 passed, 1 failed, 1 flaky |

#129's fix held: the 12 October run had 13 failures and 66 tests not run.

**`tenant-address.spec.ts:54` — fixed.**
- The diagnostics added on 10 October showed the cause:
  - the unknown address was rewritten to "Organization not found", with no
    redirect;
  - so the proxy correctly found no organization;
  - but Vercel's build served the rewritten page with 200, ignoring the
    rewrite's status (404).
- Locally the status survives, which is why only the Vercel builder failed.
- Fix:
  - `app/tenant-not-found/page.tsx` calls `notFound()`, so the page answers
    404 itself;
  - `not-found.tsx` renders the same message;
  - `layout.tsx` sets the title, because a page's metadata is not applied
    once it calls `notFound()`.
- Locally: 404 for unknown and reserved addresses, title "WonderID ·
  Organization not found". `tenant-address.spec.ts` 12/12 and
  `auth.spec.ts` 41/41 (with tenant-address).
- `/service-unavailable` (503) uses the same rewrite, so Vercel may serve it
  with 200 too. No test covers it. Recorded as a follow-up.

**`connector-provisioning.spec.ts:515` (mass-change guard) — not yet
explained.**
- It timed out at 120 s on both attempts. The serial group re-ran, and the
  half ran out of time.
- The audit trail shows:
  - the guard blocked twice;
  - the limit was raised;
  - the connector made the change at 02:00:21;
  - the verifying read never completed before the test gave up at 02:01:47.
- Every other connector change in the run was followed by its verifying
  read within 6–10 s.
- Locally the file passes 28/28; this test takes 47 s.
- Ruled out:
  - no lock or unique index stops a second sync job;
  - verification reads always run in full;
  - the tenant configuration is cached per request only;
  - a configuration update starts no background work.
- The connection and its sync jobs were deleted by the spec's clean-up, so
  the job's own state is gone.
- **Change (test only):** when verification does not arrive, the test now
  reports the connection's latest sync jobs (trigger, mode, status,
  pipeline status, times and errors). A run of the two specs on Vercel
  follows this merge.

### 2026-10-13 — Targeted run after #132: both failing specs pass on Vercel

- Run 38338640100, started by hand at 08:18 IST on `main` `4198c52` (#132),
  Vercel `dpl_9ZYgzy5M7fueaHnxpEfDrow7JiZV`:
  `tenant-address.spec.ts` and `connector-provisioning.spec.ts`, **28 passed,
  0 failed, 0 flaky** in 12 min.
- The unknown-address 404 now holds on the Vercel builder.
- The mass-change guard test passed in about 57 s. Its verification arrived
  this time, so the new diagnostics did not fire.
- The full-suite cause (verification never finishing while the design-review
  spec ran in parallel) is not reproduced. It stays open:
  - if it recurs, the test now names the connection's sync jobs;
  - the next nightly is the check.
- GitHub fired the missed 12 October schedule late, at 08:08 IST, on the
  pre-fix commit. It would have repeated the known 404 failure and held this
  run behind it for about 90 minutes, so I cancelled it: the workflow run and
  its two Vercel builds.

### 2026-10-13 — Follow-ups looked at, and left as they are

- **`/service-unavailable` on Vercel (200, not 503):** left as is, on
  purpose.
  - API callers already get a direct 503 with `Retry-After` from the proxy.
  - Only the browser page goes through the rewrite whose status Vercel
    drops.
  - Next.js has no `notFound()` equivalent for 503. A correct status would
    need hand-written HTML outside the design system (§13).
  - The page says what happened and grants nothing (§17.5 holds).
- **approval-engine and automation-credentials clashing under parallel
  runs (seen locally on 12 October):** not reproduced. Both passed in the
  13 October full run on Vercel, which also runs two workers. Left until it
  recurs, with the failing output.

## 2026-10-14 — QA-P0-02.1 and QA-P0-02.2: schema-wide RLS sweep and enumerated gate sweep

**What was built.** Two architecture tests, run by CI with the unit tests on every change that touches them.
- **`tests/architecture/route-gates.test.ts`** (QA-P0-02.2):
  - all 203 customer API routes check a named permission (`requirePermission`, `requirePermissionFor`, `requireAnyPermission(For)`, or a per-kind permission table), except 7 self-service routes that must resolve the tenant from membership and 3 public ones that must authenticate themselves, each listed with its reason;
  - every `app/api/platform` route requires a platform administrator, and every cron route checks `CRON_SECRET`;
  - every exported server action reaches a gate, itself or through a local helper that does. Only sign-in, sign-up, password reset, password update (recovery session) and sign-out are exempt;
  - every permission key the code checks exists in the catalogue the migrations build. All keys found are present.
- **`tests/architecture/tenant-rls.test.ts`** (QA-P0-02.1):
  - every table any migration creates with a `tenant_id` has RLS on. None was missing;
  - each has at least one policy, except 14 tables that are vendor-only or service-role-only by design: platform records, billing intake, encrypted secrets and keys, and receiver credentials. Each is listed with its reason, and each migration's own comment confirms the intent;
  - a listed table that later gains a policy has to come off the list.

**Verified.**
- `tests/architecture` 21/21.
- Mutation check: a temporary ungated route and a temporary ungated action each failed the sweep, and the run passed again once they were removed.

**Left.** QA-P0-06's real SAML/OIDC exchange, and the real-IdP part of QA-P0-02.2, need the SSO provider configured (owner action, FOUNDATION-P0-03.3).

## 2026-10-14 — QA-P0-22: brownfield migration fixture (partial)

**What was built.** `tests/e2e/brownfield.spec.ts` brings an organization that ran for years without WonderID under governance, through the app's own routes:
- **People.** An HR CSV creates two people and holds a match that fits two existing identities for a person to decide. A lower-precedence directory disagrees on a department: the HR value stays and the disagreement is listed.
- **Accounts.** One application's connector staging holds eight accounts, and each lands where it belongs:
  - a person's everyday account and their admin account (`privileged`);
  - a stale account, last used in 2024 (`dormant`);
  - an orphan;
  - an account whose address fits two people (`ambiguous`, nobody picked);
  - a service account owned by the person the source names;
  - an AI agent's account, by its declared client id;
  - an external contractor's account, with a sponsor and an end date.
- **Baseline.** Every grant without a request id is `LEGACY_EXCEPTION`, with no findings, and a re-run changes nothing.
- **Request.** The person asks for more access, the application owner approves, and a fulfilment task is done. The source then shows the access: the request is verified and the ledger shows `VALID`.
- **Removal.** Stale access is removed the same way and ends `REVOKED` and verified.
- **Isolation.** Another organization sees none of the accounts, the request or the person.

**Found and fixed (Access module, recorded in its audit log).** A person with a standard account and an admin account on the same application got no fulfilment task after approval. The request stayed `untracked`.

**Verified.**
- Local production build: `brownfield.spec.ts` 7/7, after a run that exposed the defect above.
- `f1-reconciliation.spec.ts` 17/17 with the fix in place.
- `pendingGrantRules.test.ts` 14/14.
- Typecheck and eslint are clean.

**Left.** The certification step needs campaigns over people's application access (COMPLIANCE-P0-10). Today's campaigns certify AI agents' access only. Once that story lands, the step goes into this spec and the story becomes Done.

## 2026-10-14 — QA-P0-07: connector contract tests

**What was built.** `modules/integrations/framework/contract.test.ts`, 145 tests over every built-in connector. It covers nine properties: authentication, discovery, pagination, partial failure, retry, rate limiting, idempotency, credential rotation and traceability.
- **HTTP connectors (11).** The suite is generated from `BUILTIN_DEFINITIONS`: frappe-hr, erpnext, keycloak, gitea, mattermost, nextcloud, openbao, kubernetes, saviynt, zendesk and scim-2.
  - A fake server builds its records from each definition's own requests, paging, record paths, fields and filters.
  - A new HTTP built-in is therefore covered without a fixture.
- **Other drivers.**
  - ldap-directory and postgresql run their real drivers against fake `ldapts` and `pg` clients.
  - csv-file and mcp-server use fake fetches.
  - webhook, runtime-gateway and scim-inbound go through the receive and SCIM rules.
- **Gaps.** What a connector does not do is listed in an exported `GAPS` table with the reason. A last block checks that every connector × property pair is either tested or listed.

**Gaps recorded (behaviour pinned by the tests, not changed).**
- **Reads are not retried.** A 5xx, timeout or network error fails that kind for the run, and the next sync is the retry. The only exception is an OAuth 401, which is retried once with a new token. Writes are never resent by the driver; `writeIsRepeatable` decides whether a retry is allowed.
- **A 429 is not waited out**, and `Retry-After` is not read. Rate limiting is the Gateway's outbound pacing.
- **The `/api/connect` receivers have no per-connection rate limit.** They have body-size caps and at most 500 events per request. Handed to Integration as a follow-up.
- **Paging:**
  - openbao: Vault's LIST returns every key in one response;
  - SQL: one statement with `LIMIT`;
  - CSV: one file per kind, at most 10 MB;
  - webhook and runtime-gateway: data is pushed, so there is nothing to page.
- **Redelivered events.** Deduplication runs in the database (`receive.ts`), and only the stable id it keys on is unit-tested.

**Observations, not defects.**
- `http.ts:332`, the "after refreshing the token" message, can never be reached: a second 401 fails earlier with "HTTP 401". The behaviour is right; only the wording differs.
- The Gateway wrapper for LDAP and SQL (`gateway.ts:253`) does not pass a driver's read-completeness report through. Neither driver produces one today.

**Verified.**
- `npx vitest run modules/integrations/framework`: 17 files, 318 tests passed (1 live file skipped).
- Typecheck and eslint are clean.

## 2026-10-14 — Nightly E2E of 14 October: causes and fixes

The full run (Actions run 38489991517, both halves on Vercel) was red.

**Second half.** `permission-catalog.spec.ts` matched the Admin sidebar's own "Administration" heading, which has existed since the new navigation (13 October). It was fixed in #189 by scoping the lookup to the page.

**First half.** It ran past its 35 minutes, so 73 tests did not run. Three tests failed:
1. **`automation-credentials.spec.ts:74`.** `getByLabel("Role")` also matched the sidebar list `<ul aria-label="Users & Roles">` (`modules/ui/AppSidebar.tsx:125`). The lookup is now scoped to `main`. Every other `getByLabel`, `getByPlaceholder` and unscoped role lookup in `tests/e2e` was checked against the sidebar labels; none other collides.
2. **`bulk-invitations.spec.ts`, `afterAll` timeout.** It deleted about 46 invited users one at a time, at roughly 3.5 s each because of cascades, against a 60 s hook limit. It also ignored errors and used an array that was never filled.
   - The deletes now run eight at a time, under a 180 s hook limit, and any failed delete fails the hook.
   - Locally: 46 users in 21 s.
3. **`connector-provisioning.spec.ts:537`** ended "fulfilled_unverified", not verified, at its 180 s limit, during its second 90 s wait.
   - The product does reach verified: about 31 s locally, every task ending `verified`.
   - The chain is slow because each read is followed by an organization-wide access-ledger rebuild, including the rogue-findings sync, after both its account and its access steps. That is 8–10 s each unloaded and 20–23 s with two workers.
   - The test's limit is now 240 s, which fits both of its own waits.
   - The slowness itself is a product item, handed to Access (see that audit log). It is also why the first half overran.

**Flaky.**
- design-review at 390 px, parts 1 and 2: these were stopped by the 35-minute cut-off, not by a layout fault.
- `integrations.spec.ts`, the "authoring page" spec: it clicked the JSON tab before the page was interactive. It now retries the click until the tab is selected. The EXPERIENCE-P0-30 form spec likewise retries its first entry until the form shows it.

**Verified locally (`next start`, `--retries=0`).**
- `connector-provisioning`: 25/25.
- `automation-credentials`, `bulk-invitations` and `integrations`: 23 passed. The one failure was `integrations.spec.ts:7` waiting for a navigation after "New connection"; it did not recur in two reruns, and is noted, unexplained.
- `integrations` with `--repeat-each=2`: 21/21.

**Left.**
- The ledger-rebuild cost (Access, with Integration and Risk).
- A race in `connectorFulfilment.ts`, fixed in the same pull request (Access audit log).
- With two workers, the RISK-P0-13 "added to a package" test (line 524) can fill its 180 s the same way; it is unchanged pending the performance fix.

## 2026-10-14 — QA-P0-22: brownfield migration fixture (done)

`brownfield.spec.ts` gains its certification step now that
COMPLIANCE-P0-10 part 1 exists: an application-owner review of the
imported access (5 items, all reviewed by the application owner), a
read-only user refused (403), one grant certified, the external person's
grant revoked through to a `remove` fulfilment task, and another
organization seeing no items. Local E2E with `compliance.spec.ts`: 24/24.
QA-P0-22 is Done.

### 2026-10-14 — Nightly E2E: half 1 out of time; design-review sweep made 10× cheaper

The 14 October nightly was red in both halves. #192 (merged after that run)
already fixed four of its failures: permission-catalog and
automation-credentials lookups scoped to the page, bulk-invitations' cleanup
batched, and connector-provisioning's create-then-grant budget. Re-run
locally on today's main, permission-catalog and automation-credentials
pass, and so does the 50-row bulk invitation when run on its own.

What #192 did not address: half 1 ran out of its 35 minutes (157 passed,
73 never ran). The design-review spec loaded every route once per width (39
routes × 8 widths = 312 loads in 16 tests), then three more tests loaded
every route again (headings and leaked values at 1440px, tables collapsing at
390px). Locally that spec took more than 40 minutes.

- The sweep now loads each route once and measures it at all eight widths by
  resizing the window. It runs the heading and leaked-value checks at 1440px
  and the phone-table check at 390px in the same pass. The routes are split
  into four parts. The checks are the same; the agent-scoped and report pages
  keep only the phone-table check, as before.
- The sweep found a real overflow: `/agents` at 1280px was 8px wider than its
  card, because a long owner name could not wrap. Owner names now wrap
  (`AgentsTable.tsx`).
- bulk-invitations' first preview check gets 60s instead of 20s: the
  50-row preview through the connector framework took longer than 20s on the
  2-core Vercel build machine.

Verified locally:
- the design-review spec, all 7 tests, passes in 4.1 minutes (over 40 before);
- the bulk-invitation 50-row test passes on its own (2.6 minutes);
- automation-credentials and permission-catalog pass 9/9.

Concurrent sign-ins by other sessions running E2E against the same test
users made the auth setup fail locally at times (the sign-in rate limit), so
the design-review run used `--no-deps` with the saved adminOne session.
Tonight's nightly is the full check.

## 2026-10-15 — Nightly E2E of 15 October: causes and fixes

The run (started 23:59 UTC on 14 Oct) was red in both halves. Half 1:
200 passed, 1 failed, 65 not run. Half 2: 261 passed, 1 failed.

- **Half 1 ran out of its 35 minutes.** Playwright's `--shard` splits the
  suite by test order, and the slow specs (connector-provisioning,
  f1-reconciliation, design-review, bulk-invitations, access-packages,
  account-inventory, automation-credentials) all sort early, so they all
  landed in half 1. Half 2 finished in about 20 minutes. Fix:
  `scripts/e2e-on-vercel.sh` now gives each half its own list of spec files.
  The slow specs alternate between the halves first, then every other spec
  file does (38 files each). No third nightly build is added.
- **WID-H08 failed only on Vercel.** The Vercel build environment sets
  `VERCEL=1`. The local test server inherited it, so `trustedClientIp()`
  believed the test's spoofed `x-vercel-forwarded-for`, which only Vercel's
  edge may set. The production check passes. Fix: the local server starts
  with `env -u VERCEL`. The rule itself is unchanged.
- **leaver-removals expected a UUID link.** The termination SLA report now
  links to the identity's number URL (FOUNDATION-P0-34). The test reads the
  identity's `ref` and expects `/identities/<ref>`.

Verified: leaver-removals 9/9 locally (with setup); automation-credentials
passed 14/14 locally against production ingress earlier; `bash -n` on the
script, and the split printed 38 + 38 files; typecheck and eslint pass.
Tonight's nightly run is the full check.

## 2026-10-15 — Nightly suite in three parts (owner decision)

The owner changed the rule to three nightly builds. Two balanced halves came
to about 30 minutes each against the 35-minute budget. `e2e.yml` now moves
`e2e/nightly-1`, `-2` and `-3` (marker "part N of 3"), and waits up to
150 minutes in all. `scripts/vercel-build.sh` and `vercel-ignore-build.sh`
accept `e2e/nightly-3`. `scripts/e2e-on-vercel.sh` deals the spec files
round-robin over three parts, slow specs first. CLAUDE.md §19.8, §19.9 and
RUN-ORDER are updated. Verified: `bash -n` on the scripts. Tonight's nightly
run is the check.

## 2026-10-15 — QA-P0-21 part 1: database security and performance review

**Checked against the dev database (Supabase advisors and the catalog):**

- **RLS on every table.** No table in `public` has RLS disabled. The tables
  without `tenant_id` fall into three groups, each expected:
  - global catalogs: `permissions`, `controls`, `control_frameworks`,
    `integration_types`, `billing_prices`;
  - child tables whose policies go through their parent: `certification_decisions`,
    `policy_rules`, `policy_versions`, `integration_mappings`, `risk_evidence`,
    `role_permissions`;
  - vendor-only platform tables.
- **RLS on with no policy (17 tables, advisor INFO).** All are service-role only
  by design: the platform tables, integration credentials, connector
  receivers and files, agent API keys, billing internals and the auth rate
  limiter. With RLS on and no policy, a signed-in user reads none of their
  rows. No change.
- **SECURITY DEFINER functions callable by signed-in users (16, advisor
  WARN).** These are the membership helpers that RLS itself relies on, and the
  owner and organization functions, each of which checks its caller. No
  change.
- **`resolve_tenant_host` callable by anonymous users.** This is deliberate
  (migration 0095): the proxy resolves an organization's address before
  sign-in. It returns only the name, address and status that the sign-in
  page shows anyway.
- **Leaked-password protection.** Off by owner decision (CLAUDE.md §18.1).

**Fixed, migration `0195_qa_hardening_fk_indexes_rls_initplan.sql`:**

- Seven RLS policies (notifications, notification preferences, privacy
  consent and requests) now call `auth.uid()` once per query, as
  `(select auth.uid())`. Each is recreated with the same meaning.
- 50 indexes are added for foreign keys that had none, generated from the
  catalog.
- The migration is not applied yet. Applying it through the Supabase tool was
  cancelled, because it drops and recreates policies. It waits for the owner
  to run it in the SQL editor, as with 0192. Until then nothing changes, and
  the file is idempotent (`if not exists`).

**Left in QA-P0-21:** the 37A test matrix across the new surface (ID
tampering, SSRF, webhook replay, prompt injection, audit completeness) and the
PDP performance budget.

## 2026-10-15 — QA-P0-21 part 2: security test matrix (done)

The specification's security test taxonomy (37A.34) and matrix (S15) are now
mapped to the tests that cover them, in `docs/security/SECURITY-TEST-MATRIX.md`.
The gaps the mapping found were closed as follows:

- **Injection, a real gap fixed.** The runtime events list decoded the page
  cursor sent by the browser and put its parts into a PostgREST `or()` filter
  unchecked. The tenant and RLS filters still applied, so it could not cross
  organizations, but a crafted cursor could add clauses of its own.
  `decodeCursor` (`modules/runtime-assurance/events.ts`) now accepts only a
  timestamp and a UUID, and refuses anything else with 400 `INVALID_CURSOR`.
- **Injection guard.** `tests/architecture/postgrest-filters.test.ts` checks
  every `or()` filter in `lib`, `modules` and `app`. A value may be a server
  value (tenant, user, a UUID the function checks, a computed timestamp) or a
  search term cleaned in the same file. All seven search boxes already
  cleaned their term; the test keeps it that way.
- **Prompt injection.** The AI summary's system prompt now says that
  instructions inside the data are content, not instructions. A test in
  `lib/ai/summarize.test.ts` shows that injected text stays JSON-quoted
  inside the data, never in the system prompt, and that the result is prose
  only.
- **Replay.** `mcp-bridge.spec.ts`: an event 31 days old, or one dated a day
  ahead, is quarantined (`quarantined_replay_window`) and never recorded as
  activity. A forged cursor gets 400.
- **ID tampering.** `multi-org-isolation.spec.ts`: an agent created in
  Tenant Two with Tenant One's id in `tenant_id` and `tenantId` lands in
  Tenant Two. Tenant One's administrator gets 404 for it.
- **Authorization engine budget** (RUN-ORDER: p95 ≤ 50 ms).
  `authorizeCore.test.ts` times 40 roles of 150 permissions with 30
  policies. One decision takes 0.05 ms (budget 1 ms). The full tenant-wide
  permission list, which `getTenantContext()` builds on every request, takes
  4 ms (budget 50 ms). Measured here.

The design's §7.2 threats are covered by existing tests: the mass-change
guard (`connector-provisioning.spec.ts`), connector template escaping
(`ldapWrite.test.ts`), approval links that need the signed-in approver
(`approval-links-drafts.spec.ts`), and four-eyes and self-approval
(`sod.spec.ts`, `delegatedRoleRules.test.ts`). Agent token replay (DPoP)
applies once agent tokens are built.

**Verified:**
- Typecheck and eslint on the changed files: clean.
- Vitest, the touched files: `authorizeCore.test.ts`, `summarize.test.ts`,
  `events.test.ts` and `postgrest-filters.test.ts`, 42 passed.
- `next build` passed.
- Local E2E: `mcp-bridge.spec.ts` and `multi-org-isolation.spec.ts`,
  19 passed (including setup).

**Left, recorded in the matrix as known gaps:**
- no generic check that every sensitive mutation writes an audit event;
- the Razorpay replay path (unique event id) has no test;
- no E2E sends an oversized body to the import route.

## 2026-10-15 — Full E2E run by hand (owner request): causes and fixes

The owner asked for the full suite now rather than at night (workflow run
38708923443, three parts on Vercel, three deployments).

**Results:**
- Part 1: 206 passed, 0 failed, 3 flaky. It hit the 35-minute cap and two
  tests were cut off.
- Part 2: 178 passed, 2 flaky, 22 minutes.
- Part 3: 140 passed, 2 failed, 1 flaky, 24 minutes.

**Causes and fixes:**
- **`identity-sources.spec.ts:115`, a product bug.** The pending-matches
  page looked up source names in `listIdentitySources()`, which reads at
  most 200 sources. The E2E organization has 296, so a newer source showed
  as "a source". The same lookup named the sources on an identity's page.
  - Both now use `getIdentitySourceNames(tenantId, ids)`, which reads the
    sources actually shown, by id, filtered by tenant.
- **`mcp-bridge.spec.ts:91`.** The replay and cursor checks added by #229
  pushed it past the 60-second limit on the Vercel builder. They are now a
  test of their own.
- **Part 1 over time.** The round robin gave part 1 three slow specs
  (connector provisioning, design review, automation credentials).
  `scripts/e2e-on-vercel.sh` now gives connector provisioning part 1 alone
  among the slow specs; the other six alternate between parts 2 and 3. The
  file counts are 25, 26 and 26.
- **`identity-sources.spec.ts:253`.** It took 58 seconds locally on the
  slow-machine setting, against a 60-second limit. It is four imports, so
  it gets 150 seconds.

**Verified:**
- Local E2E, `mcp-bridge` and `identity-sources`: 26 passed, plus the
  custom-attributes test passed alone.
- Typecheck and eslint on the changed files: clean.
- `next build` passed.

**Left:** six tests passed only on retry:
- connector provisioning WID-H04, which waits for the import pipeline;
- the request catalog setup;
- lifecycle expiry;
- the approval engine;
- identity rules;
- F1 reconciliation.

They pass on retry, so the run is green, but each still needs its root cause
found.

## 2026-10-15 — Nightly suite in four parts (owner decision)

The owner asked for four parts instead of three, so each part keeps a margin
under the 35-minute budget as the suite grows. Today's run took 35+ minutes
for part 1, against 22 and 24 for the others.

**Changes:**
- `scripts/e2e-on-vercel.sh` adds `e2e/nightly-4`:
  - connector provisioning has part 1 to itself among the slow specs;
  - the other six slow specs take turns between parts 2, 3 and 4;
  - every other spec is dealt round-robin over the four parts;
  - files per part: 19, 20, 20 and 19, all 78 dealt once.
- `scripts/vercel-build.sh` and `vercel-ignore-build.sh` accept
  `e2e/nightly-4`.
- `.github/workflows/e2e.yml`:
  - it marks four branches;
  - the job limit goes from 130 to 230 minutes, and the wait from 150 to
    220 minutes. The free plan builds one deployment at a time, so the
    parts run one after another; three parts took about 85 minutes on
    15 Oct.

**Cost:** one more Vercel deployment a night, four of the 100 a day.

**Not changed:** CLAUDE.md §19.8 and §19.9 still say "three parts". The
owner asked for no CLAUDE.md change for now, so the contract text waits for
the owner's word.

## 2026-10-15 — The six retried E2E tests, and a leftover hourly limit

**The six tests that passed only on retry** (from the afternoon run) were
investigated by a multi-agent workflow. The owner asked to try the approach.
For each test:
1. an agent pulled the first attempt's error from the Vercel log and
   proposed a cause;
2. an independent agent tried to refute it;
3. a fix was written in an isolated worktree;
4. each diff was reviewed here before being applied.

**What the workflow found:**
- Each first-attempt error, which the logs had not been read for:
  - WID-H04: a 180 s test timeout while waiting for the sync pipeline;
  - request catalog: the page was still loading after 20 s;
  - lifecycle expiry: a response with no `data`;
  - identity rules: simulate returned 500;
  - F1 reconciliation: a response with no `data`, with a 502 from the
    database API at the same time;
  - approval engine: FORBIDDEN on a second decision.
- No cause could be proven: the logs do not capture response bodies. The
  refuters rejected 5 of 6 diagnoses as unproven, including one change that
  would have narrowed tenant-wide rogue-access detection on a guess.

**Applied (making failures diagnosable, not fixes of unproven causes):**
- Tests now print the status and body on failure:
  - `lifecycle-expiry-disable` has `getLifecycle`;
  - `f1-reconciliation` has `getData`;
  - `identity-rules` prints its simulate responses.
- `syncAndWait` reports the pipeline's steps when it times out.
- Longer limits only where the work is legitimately long, each with its
  reason in a comment:
  - WID-H04: 300 s, for three syncs;
  - the request catalog setup: 180 s, with 45 s for its page checks.
- Product code:
  - `rowsById` throws `ApiError(500, QUERY_FAILED)`, so the cause reaches
    the response;
  - `getTenantContext` logs a failed membership, role, group or policy read
    (redacted) and a member resolved to no permissions. Logging only;
    refusals still fail closed.

**Found while verifying: a leftover hourly write limit.**
- Symptom: `connector-provisioning.spec.ts:751` (WID-C02 leaver) failed in
  both local runs, with the disable refused by the mass-change guard
  ("8 changes in the last hour (limit 7)").
- Cause: the afternoon's part 1 was cut off inside the QA-P0-26 mass-change
  test, which had set `integration.maxWritesPerHour` to 7. Its `finally`
  block never ran (`tenant_config_versions` v91, 09:30 UTC). Every later
  run read 7 as the "original" value and restored it.
- Fix: the file's setup now resets the limit to the registry default (100)
  first, so a killed run cannot affect later ones.

**Verified, locally (E2E_SLOW_MACHINE):**
- the six specs: 68 of 69 passed; the one failure was the leaver test
  above;
- `connector-provisioning.spec.ts` after the reset: 25 of 25 passed.
- Typecheck and eslint: clean.

**Owner decision open:** `getTenantContext` turns a failed database read into
"no permissions", so under load a person sees 403 FORBIDDEN instead of
"temporarily unavailable". It fails closed, which is safe, but the message
is misleading (§17.5). Changing it touches tenant resolution and needs the
owner's say.

## 2026-10-16 — Nightly of 16 Oct: two fixes

The scheduled run (03:00 IST) failed in two parts:
- **Part 1:** 133 passed, 1 flaky. It was cut off at 35 minutes with one
  test interrupted and one not run.
- **Part 2:** 151 passed, 1 failed, 3 flaky (22 min).
- **Parts 3 and 4:** passed (16 and 17 min).

**Part 1 over time again.** Part 1 held connector-provisioning plus a quarter
of the other specs. `scripts/e2e-on-vercel.sh` now gives part 1
connector-provisioning alone, and deals every other spec over parts 2, 3 and
4 (26, 26 and 25 files).

**`users.spec.ts:211` failed: product bug.** "Give WonderID access" opens
Add user with `?identity=`. The form looked the person up in
`listPeopleWithoutAccess()`, which reads the first 500 people by name. The
E2E organization has about 3,000, so a person named "E2E From Identity…"
was not in the list and the form came up empty. The function now also reads
the linked person by id, with the same tenant and eligibility filters (owned
by Identity; recorded in its audit log too).

**Verified:** typecheck and eslint clean, `next build` passed, local E2E
`users.spec.ts` 16 of 16 passed, and the new split was simulated (part 1
holds one file).

**Still flaky, not changed here:**
- the WID-C02 leaver test, `connector-provisioning.spec.ts:756`;
- `users.spec.ts:102`;
- navigation-smoke `/controls`;
- auth.setup `iamAdminOne`.

All of these run in an organization holding thousands of leftover test
rows. The cleanup SQL waits on the owner.

## 2026-10-16 — Old test data cleaned before every run (owner request)

The owner ran the one-off cleanup SQL, which brought Tenant One down from
3,359 identities to 234. They then asked for it to run on every run, so the
data cannot build up again.
- `pruneThrowawayGovernanceData()` (`tests/e2e/support/seedTestData.ts`)
  runs in `auth.setup.ts` after the existing prunes. It deletes, in the two
  `e2e-*` tenants only:
  - campaigns named "E2E …";
  - access packages named "E2E …", after their assignments and requests;
  - identity sources named "E2E …";
  - identities with no sign-in that are not agents.
- Only rows older than two hours go, so a run in progress keeps its own.
- The audit trail, ledger and settings history stay; they are append-only.
- **Verified:** typecheck and eslint clean; local setup project (seed plus
  prunes) 7 of 7 passed. Vercel runs do not set `E2E_SKIP_SEED`, so it
  runs before every nightly part.

## 2026-10-17 — Nightly of 17 Oct: all four parts green

The first nightly with clean test data and the new split.
- **Start:** GitHub started the run at 05:13 IST, 2 h 13 min after its
  `30 21` (03:00 IST) schedule, exactly as on 16 Oct.
- **Results:**
  - part 1: 24 passed, 1 flaky (20 min);
  - part 2: 203 passed (24 min);
  - part 3: 173 passed (13 min);
  - part 4: 153 passed, 1 flaky (25 min).
  - In all, 553 passed, 0 failed. The parts ran one after another, ending
    at 06:43 IST.
- **The four retried tests from 16 Oct passed first time:** the WID-C02
  leaver, `users.spec.ts:102`, navigation `/controls` and the `iamAdminOne`
  sign-in setup.

**Flaky, and what changed:**
- **`connector-provisioning.spec.ts:387` (F3 exit).** On the first try, the
  account page showed no "Ticket RA-000165 open", although the database had
  the finding and ticket open (checked afterwards). The page turned a failed
  findings read into "none" (`.catch(() => [])`). It now says "Rogue access
  on this account could not be checked just now" and logs the redacted
  reason, so the next occurrence names its cause. The retry passed.
- **`identity-sources.spec.ts:172` (leaver guard).** A six-row CSV run had
  not finished within `runCsv`'s 30 s poll on the nightly machine. The poll
  is now 90 s, and the test has 240 s.

**Schedule:** the cron moved from `30 21` to `17 21` UTC (02:47 IST), off
the busy minute, so the run should start by about 03:00. CLAUDE.md §19.6
and §19.8 and ORCHESTRATION.md say so.

**Verified:** eslint clean on the changed files. Typecheck is clean except
for product screenshots missing from this container's checkout
(`app/welcome`), which CI has.

## 2026-10-19 — Performance review (owner request: "make the application fast and snappier")

**Measured first, on production, signed in as the E2E administrator**
(`scripts/perf-pages.mjs`, added here). Before: every page's server HTML took
1.1–2.0 s (median about 1.2 s over 20 routes). Breakdown:
- an unauthenticated request costs about 300 ms from the test client (network);
- the same public page costs about 450 ms more once a session cookie is present:
  the proxy's `auth.getUser()` round trip. The proxy runs at Vercel's edge near
  the visitor (`x-vercel-id: iad1::sin1`), not beside Supabase in Singapore;
- each further sequential Supabase round trip in a route costs about 60 ms;
- Supabase itself answers in about 36 ms from the client on a warm connection,
  and the hot queries take 1–15 ms in the database (`pg_stat_statements`).
  `current_tenant_ids()` costs 16 ms on a new connection and 0.6 ms after.

**Changed:**
1. `proxy.ts` verifies the session locally (`getClaims()`; tokens are ES256)
   and makes no auth-server call unless a token must be refreshed. The host
   lookup and the session limits (both cached) run in one wave.
2. `getSessionUser()` (`lib/tenant/session.ts`) is where a revoked session is
   refused: `getClaims()` and `getUser()` in parallel, both required. Global
   sign-out stays immediate. Every route that reads data goes through it (checked:
   nothing in `app/` queries without a session check).
3. Pages: All Requests runs its sweeps in `after()` and reads what waits for
   the caller in the same wave as the caller's identity. The package expiry
   sweep reads its two lists together. The agent page's contract comparison
   explains each application once, in parallel, and is cached for the
   request (the posture panel reused it). The posture runs in three waves
   instead of twelve. The access ledger refresh reads its evidence and stored
   rows together and updates ten rows at a time. Controls reads its lists
   alongside the settings.
4. Bug found by the review: a cancelled request left its approval steps open,
   so the timeout sweep re-read them on every view and could crowd out real
   timeouts past 200. Cancelling now skips them; the sweep filters to waiting
   requests in the database and reads each policy once.
5. Migration 0205 (applied): the audit log's action filter
   `(tenant_id, action, created_at)` (1.1 s average before); partial indexes
   for the two badge counts on every page; the eleven foreign keys the advisor
   listed without an index; one stale approval step repaired. Advisors: no
   unindexed foreign keys left.
6. CLAUDE.md §15.1: the rules from this review, binding for new work.

**Kept as it was, on purpose:** the request page's and the leaver page's
pre-render sweeps (a decision on the page depends on them); the identity page's
ledger refresh (shown right after an approval; made cheaper instead); the
tenant context is never cached across requests (revocation applies on the
next request).

**Left for later (page audit findings not done here):** the agent discovery
inbox's wide reads; the home page's 5,000-row finding summaries (an RPC
grouping by day would replace them); `/risk`'s unbounded open-findings read;
the account summary's seven counts; listing owners tenant-wide on the agent
page; lean group lists for filters; streaming the agent and identity pages'
slow panels with `<Suspense>`.

**Verified:** typecheck; eslint on the changed files; unit tests 210 files,
1,888 passed (new `lib/tenant/session.test.ts`: a revoked session, another
user, an unreachable auth server and a bad token are all "nobody");
`next build`. E2E on Vercel before merging: see the pull request.

## 2026-10-19 — Performance review, round 2 (owner: "continue with the next performance targets")

**After round 1 (#250), measured on production** with `scripts/perf-pages.mjs`:
median page server time 1.07 s over 18 pages (before: about 1.2 s); the extra
cost of a session cookie on a public page fell from about 450 ms to about
185 ms; a signed-in API call from 858 ms to 710 ms. The migration 0206 fix
(memberships in a fixed order) shipped in the same pull request.

**Round 2:**
1. The proxy sends `Server-Timing: claims, host, limits` (durations only), so
   production shows where its remaining ~185 ms goes. Next decision from that
   data: the JWKS fetch inside `getClaims()`, or the cached host and
   session-policy reads from the edge.
2. `getTenantContext()` no longer waits for the auth server's live-session
   check before its reads: the reads need only the verified token's user id
   (`getSessionClaims()`, new) and run alongside `getSessionUser()`; nothing is
   returned unless the session is live (new test: a revoked session gets no
   context). `getMyMemberships()`, used on its own by a few routes, still
   requires the live check.
3. The customer layout starts the reads that need only the person (profile,
   vendor-console check, environments) alongside the tenant context, each
   with its "not shown" fallback.

**Verified:** typecheck; eslint on the changed files; unit tests 210 files,
1,889 passed (`lib/tenant/getTenantContext.test.ts` +1); `next build`. E2E on
Vercel for the session specs before merging: see the pull request.

## 2026-10-19 — Performance round 3: where page render time goes

**After round 2 (#251), on production:** the proxy's `Server-Timing` shows its
steps at 1–4 ms on signed-in requests (`claims` about 1 ms: the token is
verified locally). One cache miss of the organization-address lookup cost
688 ms from the edge, then 0. Median page server time 969 ms over 18 pages
(1,073 after round 1, about 1.2 s before). About 300 ms of that is the test
client's network; the rest is the route's own render.

**Round 3 (measurement):** `lib/db/requestTimings.ts` records each Supabase
call of a page request (API path only, never the query string; start offset
and duration). The customer layout logs one `[perf] supabase` line after the
response when the calls spanned 250 ms or more. This shows from production
logs which calls make a page slow, for the next round's fixes.

**Verified:** typecheck; eslint; unit tests 211 files, 1,891 passed (new
`lib/db/requestTimings.test.ts`: no query strings, only slow requests
logged); `next build`.

## 2026-10-19 — Performance round 4: fewer calls per page (migration 0207)

**Found (the round 3 `[perf]` logs on production):** each Supabase call takes
40–130 ms. Every page made four separate reads to build the access context
(memberships, roles, group roles, policies). The dashboard and list headers
made 8 (identities by type), 5 (application catalog) and 7 (account
inventory) head counts each.

**Changed:**
1. `my_access_context()` returns the memberships (from `my_memberships()`),
   the person's own direct roles and group roles, and the active
   authorization policies in one call. It is SECURITY INVOKER, so RLS applies
   to every row as with the four reads. Roles and group members are filtered
   by `auth.uid()` in the function, as before. `getTenantContext()` and
   `getMyMemberships()` share it per request. A failed read still means
   "unavailable, nothing permitted", and now covers the organization as well.
2. `identity_type_counts()`, `application_catalog_counts()` and
   `account_summary_counts()`: one grouped count each, SECURITY INVOKER, with
   an explicit tenant filter. They replace `countIdentitiesByType()`,
   `getCatalogSummary()` and `getAccountSummary()`, which keep the same return
   shapes. The account filters mirror `applyView()`.
3. Execute on all four is revoked from `public` and `anon`, and granted to
   `authenticated` and `service_role`.

**Verified:**
- Applied to production. As the E2E administrator, `my_access_context()`
  returned the same numbers of memberships, roles, group rows and policies as
  the old reads (1/1/0/0).
- The three count functions match direct counts on the largest tenant.
- Security advisors: no new findings.
- Typecheck, eslint on the changed files, and `next build` pass.
- Unit tests over `lib`, `modules/agent-identity` and
  `modules/access-governance`: 95 files, 767 passed. In
  `getTenantContext.test.ts` the mock now answers the single call, and a new
  test checks that another tenant's role, or a role RLS hides, grants
  nothing.
- E2E on Vercel for the session and RBAC specs before merging: see the pull
  request.
