# Foundation Agent — Backlog Audit Log

Append a dated entry after every completed story: what was built, how it was
verified, what was deliberately left out or deferred, and any open questions raised
for the user. Do not rewrite or delete prior entries.

---

## 2026-09-13 — FOUNDATION-P0-01 through P0-06 (initial implementation)

**Agent:** Foundation Agent · **Branch:** `claude/wonderagent-setup-lasmly` (this
session develops directly on the harness-assigned branch rather than a separate
`module/foundation` worktree branch — see note under "Deviations" below).

**Built:**

- **FOUNDATION-P0-01** — Next.js 16 (App Router) + TypeScript (strict) + Tailwind
  v4 + ESLint scaffold, via `create-next-app` in a scratch directory then merged
  into the repo (`app/`, `next.config.ts`, `tsconfig.json`, `eslint.config.mjs`,
  `postcss.config.mjs`). Added `@supabase/supabase-js`, `@supabase/ssr`, `zod`,
  `recharts`, `reactflow`, Radix UI primitives, `server-only`, and a Vitest +
  Testing Library dev toolchain. `.env.local.example` committed;
  `.gitignore` fixed to exclude `.env*.local` while explicitly un-ignoring
  `.env.local.example` (the stock Next.js `.gitignore` ignores `.env*`
  unconditionally, which would have silently excluded the example file too).
  `lib/db/env.ts` centralizes env var access with a hard runtime guard
  (`typeof window`) on the service-role key and the secret-encryption key.
  `lib/db/supabaseBrowser.ts` / `supabaseServer.ts` provide the two sanctioned
  client factories (`supabaseServer()` request-scoped/RLS-respecting,
  `supabaseServiceRole()` trusted-only). Verified the service-role key does not
  reach the client bundle by grepping `.next/static` after a production build.
  Renamed `middleware.ts` → `proxy.ts` (Next 16 deprecated the old convention).
- **FOUNDATION-P0-02** — Full schema applied to the live dev Supabase project
  (`ekgyjwoenteadaaqakmd`, the only Supabase project this app may use) via the
  Supabase MCP `apply_migration` tool, as
  `supabase/migrations/0001`–`0008_foundation_*.sql`: `tenants`,
  `tenant_settings`, `users` + `handle_new_user()` trigger, `tenant_memberships`,
  `roles`/`permissions`/`role_permissions`/`user_roles` with the full P0
  permission catalog and all 11 system roles seeded and mapped per the backlog's
  worked table, RLS on every table via `current_tenant_ids()`, and the
  `create_tenant_with_owner()` self-service RPC (solves the tenant-creation
  chicken-and-egg problem under RLS).
- **FOUNDATION-P0-03** — Email/password sign-up/sign-in pages
  (`app/sign-up`, `app/sign-in`), self-service tenant creation and tenant
  picker (`app/onboarding`, `app/actions/tenant.ts`) backed by the RPC above.
  **Deferred**: SAML/OIDC SSO (03.3) and MFA enrollment (03.4) — the
  `sso_connections` table and its RLS exist, but the actual IdP handshake
  wiring was not started this session; flagging per the backlog's own
  instruction to stop rather than fabricate a SAML implementation. No open
  question yet since no story time was spent guessing at it — this is a
  straightforward "not started," to be picked up in a follow-up run.
- **FOUNDATION-P0-04** — `requirePermission()` and `requirePlatformAdmin()`
  guards (`lib/rbac/`), exercised by `app/api/v1/tenant` (no permission
  required beyond an active tenant) and `app/api/v1/users` (requires
  `user.manage`, used to prove RBAC denial). **Deferred**: the role-management
  UI (04.3) — no screen yet to assign/revoke roles through the app; the RPC/DB
  layer supports it, only the UI is missing.
- **FOUNDATION-P0-05** — `lib/audit/writeAudit.ts` (service-role-only writer,
  matching `audit_logs`' RLS which grants no client insert policy at all).
  `lib/security/encryptSecret.ts`/`decryptSecret.ts` implemented with Node's
  built-in AES-256-GCM rather than pgcrypto or Supabase Vault — see the
  rationale in that file's docblock (no project-tier-dependent feature, no
  extra DB round trip, standard authenticated-encryption construction). This
  resolves the backlog's "stop and report if unclear" flag without needing to
  actually stop, since a clean, dependency-free standard option existed.
  Baseline HTTP security headers/rate limiting (05.3) — **deferred**, not
  started.
- **FOUNDATION-P0-06** — `platform_admins` table (zero RLS policies —
  intentionally unreachable by any client role), `requirePlatformAdmin()`,
  `app/platform-admin/layout.tsx` (denial renders a bare 404 via `notFound()`,
  never a "no permission" page that leaks structure). Verified via a running
  `next start` server: unauthenticated hits to `/platform-admin` return 404,
  `/api/v1/tenant` and `/api/v1/users` return 401 `NO_TENANT`, `/` redirects to
  `/sign-in`. No platform admin has been seeded yet in the dev project (no user
  exists to seed against) — first real seeding happens when the user actually
  signs up.
- **FOUNDATION-P0-07 (critical acceptance test)** — Ran the full tenant
  isolation proof directly against the live dev database via the Supabase MCP
  `execute_sql` tool (this sandbox's plain outbound network is blocked by an
  organization egress allowlist — confirmed by a direct `curl`/`fetch` test to
  `*.supabase.co` failing with `connect_rejected`, so a JS-client-based
  integration test could not run from this session; simulating the JWT via
  `set_config('request.jwt.claims', ...)` + `set role authenticated`/`anon`
  exercises the identical RLS policies a real client session would). Fixture:
  two tenants, two users, one membership/role/audit row each. Result, acting
  as Tenant A's user: every tenant-scoped table returned only Tenant A's rows;
  Tenant B was invisible even by direct primary-key lookup (0 rows, no error);
  a direct `UPDATE` targeting Tenant B affected 0 rows; inserts into
  `tenant_memberships` (claiming Tenant B), `audit_logs`, and `platform_admins`
  were all rejected with an explicit RLS policy-violation error, not silently
  dropped. As `anon`: every tenant-scoped table returned zero rows; the
  `permissions` catalog and system `roles` rows (both non-sensitive catalog
  data) remained readable. Fixture data was deleted afterward — the dev
  project is clean. The reusable script (with the exact commands and observed
  results) is committed at `tests/foundation/tenant-isolation.sql` for
  re-running by a future session or the QA Agent. Also added Vitest unit tests
  for the pure logic that doesn't require a live database or Next's request
  context: `lib/security/encryptSecret.test.ts` (round-trip, random IV,
  tamper detection, malformed-payload rejection) and
  `lib/rbac/requirePermission.test.ts` (401/403/success paths against a
  mocked tenant context).

**Self-inflicted issue found and fixed during this session:** an early
"harden the security advisories" pass revoked `EXECUTE` on
`current_tenant_ids()` from `authenticated`/`anon` in response to a
`get_advisors` WARN about the function being callable via REST RPC — but RLS
policies invoke that function *as the querying role*, so this broke RLS
entirely (`permission denied for function current_tenant_ids`) until
`0011_foundation_fix_current_tenant_ids_grant.sql` restored the grant. Left as
a reviewed, intentional exception (same treatment as
`create_tenant_with_owner`): the function only ever returns the caller's own
tenant memberships, so REST-RPC exposure carries no cross-tenant risk.
`get_advisors(security)` and `get_advisors(performance)` are clean after
`0009`–`0011` other than that one accepted WARN and the intentional
"no-policy" INFO on `platform_admins`. `rls_auto_enable()`, a Supabase-managed
function neither created nor owned by this module, also still shows in the
advisories and was left untouched.

**Verification run:** `npm run lint`, `npm run typecheck`, `npm run test`
(7/7 passing), `npm run build` — all clean. Confirmed no leak of the
service-role key into `.next/static`. Confirmed via a locally-started
production server (`next start`) that every route above returns the expected
status code without a live Supabase network call being required for the
unauthenticated paths tested.

**Deviations from the backlog's stated workflow (flagging for the user,
not guessing silently):**

1. This session develops directly on the harness-assigned branch
   (`claude/wonderagent-setup-lasmly`) rather than creating a separate
   `module/foundation` git worktree/branch — the calling environment's own
   instructions pin all work to that one branch and forbid pushing elsewhere
   without explicit permission, which supersedes `docs/ORCHESTRATION.md`'s
   default multi-worktree convention for *this* environment. Future sessions
   that do run as genuinely separate Claude Code consoles should follow
   `docs/ORCHESTRATION.md` as written.
2. `.env.local` contains the real Supabase credentials the user pasted in
   chat, so this session could exercise the Supabase MCP tools and read the
   env-var names correctly; it is gitignored and was never committed.

**Not started this session (still open for a future Foundation Agent run,
not blocking other agents):** SSO handshake wiring (03.3), MFA enrollment
UI (03.4), role-management UI (04.3), baseline security headers/rate
limiting (05.3). None of these block Identity/Integration/Access/etc. from
starting, since the schema, RLS, RBAC guards, tenant context, audit writer,
and secret encryption they all depend on are in place and tested.

---

## 2026-09-14 — CRITICAL gap flagged by Platform Agent: `current_tenant_ids()` doesn't check `tenants.status`

Platform Agent's own run (docs/design/platform-agent-backlog-audit.md, same
date) discovered and verified live that `current_tenant_ids()` (this
file's own `0004_foundation_rls.sql`) filters only on
`tenant_memberships.status = 'active'` and never checks `tenants.status` —
so every RLS policy in the entire system that relies on it (every module
built so far) continues granting full access to a tenant's active members
even after that tenant is suspended. `tenants.status` becomes a label with
no enforcement effect. Platform Agent did not patch this itself (correctly,
per non-negotiable #14/#18 — this is Foundation's shared authentication-
model function, not Platform Agent's to change), and recorded a proposed,
minimal, additive fix in its own audit log:

```sql
create or replace function current_tenant_ids()
returns setof uuid
language sql stable security definer set search_path = public
as $$
  select tm.tenant_id from tenant_memberships tm
  join tenants t on t.id = tm.tenant_id
  where tm.user_id = auth.uid() and tm.status = 'active' and t.status = 'active';
$$;
```

**Not applied yet** — left as an explicit open question for the user
(per the stop-and-report rule) rather than guessed past, since a change to
this function has system-wide blast radius (every module's RLS policies
call it) and deserves a dedicated Foundation Agent verification pass across
every other module's own tenant-isolation tests once applied, not a
same-turn patch made while building Platform Agent's console. Whoever runs
Foundation Agent next should apply this fix and re-run
`tests/foundation/tenant-isolation.sql` plus spot-check one or two other
modules' isolation scripts against a suspended-tenant fixture (a case none
of them tested, since every existing isolation test only ever checks
cross-tenant access between two *active* tenants, never a suspended
tenant's own members).

---

## 2026-09-14 — RESOLVED: `current_tenant_ids()` now enforces `tenants.status`

**Agent:** Foundation Agent · **Branch:** `claude/wonderagent-setup-lasmly`,
dispatched directly by the user in response to the finding above ("dispatch
Foundation Agent now to apply this fix and re-verify isolation tests
across the other modules").

**Applied**: migration
`0039_foundation_fix_current_tenant_ids_status_check.sql` —
`create or replace function current_tenant_ids()`, unchanged name/
signature/return type (so every existing `GRANT EXECUTE` from
`0009`/`0011` and every RLS policy calling
`tenant_id in (select current_tenant_ids())` keeps working unmodified),
now joining to `tenants` and requiring `t.status = 'active'` in addition to
`tm.status = 'active'` — exactly the fix proposed in the entry above.

**Verified live against the dev Supabase project, in this order:**
1. **The gap is closed**: set `tenants.status = 'suspended'` on the
   existing FinanceBot fixture tenant (`aaaaaaaa-5000-...`, from Runtime/
   Risk/Compliance's own fixtures), then re-ran, as that tenant's
   authenticated member, the exact checks that previously proved the gap:
   `current_tenant_ids()` no longer includes the suspended tenant (`false`,
   was `true`), and reads against `agents`/`tenants`/`runtime_events`/
   `risk_findings` for that tenant all now return zero rows (were 1/1/1/1).
   Reverted the fixture back to `status = 'active'` immediately after and
   confirmed the revert took effect.
2. **No regression on ordinary active-tenant access**: attempted to re-run
   the original `tests/foundation/tenant-isolation.sql` fixture
   (`aaaaaaaa-0000-...`/`bbbbbbbb-0000-...`) and found it had been cleaned
   up between sessions (its rows no longer exist in the dev project) —
   rather than silently accept an empty/inconclusive result, re-ran the
   equivalent checks against the still-present, richer FinanceBot fixture
   instead: as Tenant A5's active member, `tenants`/`agents`/
   `risk_findings`/`runtime_events`/`certification_items` all still return
   exactly that tenant's own rows (`{fixture-tenant-a5-test}`,
   `{FinanceBot}`, 1, 1, 3 respectively — matching every prior module's own
   recorded fixture state), and Tenant B5 remains a zero-row cross-tenant
   lookup. This spans Foundation's own tables plus Identity's, Risk's,
   Runtime's and Compliance's — a broader regression check than the
   original fixture alone would have given, since it proves the fix didn't
   disturb any downstream module's RLS behavior either.
3. `get_advisors` (security) re-checked: identical set of previously-
   reviewed exceptions (the intentional `rls_enabled_no_policy` tables,
   `current_tenant_ids()`'s own now-longer-standing `anon`/`authenticated`
   SECURITY DEFINER exposure warning, `create_tenant_with_owner`'s and
   `rls_auto_enable()`'s equivalents, leaked-password-protection) — nothing
   new introduced by this change.

**Added a permanent regression test** to
`tests/foundation/tenant-isolation.sql` (new §5, commented like the
existing anon-role section for manual re-run against a dev project) so a
future change to this function or the `tenants`/`tenant_memberships`
schema gets checked against a suspended-tenant scenario, not only
cross-tenant access between active tenants.

**Not done, and deliberately out of scope for this fix**: did not re-seed
the original cleaned-up Foundation fixture (`aaaaaaaa-0000-...`) — the
FinanceBot fixture already served as a valid, arguably stronger,
substitute for this specific regression check. Did not re-run every other
module's own isolation script individually (Access/Integration/Identity's
own `tests/*/tenant-isolation.sql` files) — the cross-module regression
check in step 2 above already exercises RLS on tables owned by four of the
downstream modules (Identity, Risk, Runtime, Compliance) through the same
`current_tenant_ids()` code path every one of those scripts also depends
on, so re-running each individually would be redundant with what step 2
already proves about the shared function; a full QA-Agent-level sweep
across every module's own script remains QA Agent's job per its own
backlog (QA-P0-02.1).

**No application code changed** — this was a pure database migration; no
`npm run lint`/`typecheck`/`test`/`build` impact expected or found (all
re-run as a matter of pipeline discipline; unaffected, still clean).

---

## 2026-09-14 — Remaining Foundation P0 stories (03.3, 03.4, 04.3, 05.3, 08, 09, 11)

**Agent:** Foundation Agent · **Branch:** `claude/wonderagent-setup-lasmly`.
Per the user's explicit instruction ("operate like before... start with the
first requirement backlog document, focusing on p0 only for now"), picked up
every remaining P0-tier story in this module's own backlog, in order, one at
a time, auto-continuing without stopping between stories.

### FOUNDATION-P0-03.3 — SSO connection foundation

Schema already existed (`0007_foundation_sso.sql`, from the 2026-09-13 run)
but no code did. Built: `lib/auth/sso.ts` (CRUD + `resolveJitRole()` +
`provisionSsoMembership()` + `getFullActiveSsoConnectionByDomain()` +
`findActiveSsoConnectionForDomain()`), `app/api/v1/sso/route.ts` +
`[id]/route.ts` (gated by `sso.manage`) + `domain-lookup/route.ts`
(deliberately unauthenticated, exposes only `{domain, protocol}`), a bare
admin page at `/settings/sso`, domain-based "Sign in with SSO" routing added
to the sign-in page, and `app/auth/callback/route.ts` (code exchange +
SSO JIT tenant-membership provisioning, recording `source: 'sso_jit'` in the
audit event per the backlog's own requirement).

**Verified live** (Supabase MCP, against the `aaaaaaaa-5000-...`/
`bbbbbbbb-5000-...` FinanceBot fixtures — see `tests/foundation/
tenant-isolation.sql` §7 for the exact commands): Tenant A5's user sees only
its own `sso_connections` row, Tenant B5's user sees zero; a plain
authenticated client's direct INSERT is rejected, and its direct UPDATE
affects 0 rows (no policy exists for either, matching the intentional
select-only + service-role-write design). `resolveJitRole()`'s claim→role
mapping logic is unit-tested (`lib/auth/sso.test.ts`, 5 cases: default
fallback, direct match, array-valued claim match, unmapped value fallback,
missing claim fallback).

**Not verified, honestly flagged rather than fabricated** (matches the
backlog's own stop-and-report allowance for this exact situation): an actual
end-to-end SAML/OIDC redirect against a real identity provider, and
`provisionSsoMembership()`'s database writes exercised via a real SSO login.
Both require a real IdP and a Supabase-project-level SSO provider
registration (an Enterprise/Pro-tier, dashboard/CLI setup step, not
application code) that does not exist on this environment's connected
project. Tracker marked `Partial`, not `Done`.

### FOUNDATION-P0-03.4 — MFA foundation

`/settings/security` (client component) using Supabase Auth's own
`mfa.enroll`/`mfa.challengeAndVerify`/`mfa.unenroll`/`mfa.listFactors`
exclusively — no custom TOTP implementation, per the backlog's explicit
instruction. No new database table (Supabase manages MFA factors
internally). **Not verified**: real enrollment against a physical/software
authenticator app (no such device is available in this sandbox) — the code
correctly follows the documented SDK response shape
(`data.totp.qr_code`/`secret`/`uri`), but a live TOTP round-trip was not
exercised. Tracker marked `Partial`.

### FOUNDATION-P0-04.3 — Role management UI (minimal)

`lib/rbac/roles.ts` (`listTenantMembersWithRoles`, `listAssignableRoles`,
`assignRole`, `removeRole` — all service-role writes gated by
`requirePermission('role.manage')`, each manually verifying the target user
is an active tenant member before mutating, matching CLAUDE.md §14's
service-role guardrail) plus `/settings/roles`. **Verified live**: a plain
authenticated client's direct INSERT into `user_roles` is rejected, and its
direct DELETE affects 0 rows — same pattern as `sso_connections`. Marked
`Done`.

### FOUNDATION-P0-05.3 — Baseline HTTP security

`next.config.ts` now sets CSP (script-src/style-src `'unsafe-inline'` as a
P0 baseline — a full nonce-based strict CSP is a reasonable P1 refinement,
not attempted here), `X-Content-Type-Options`, `X-Frame-Options: DENY`,
`Referrer-Policy`, `Permissions-Policy`. For the rate limiter: sign-in and
sign-up were **moved from a client component calling
`supabase.auth.signInWithPassword`/`signUp` directly to server actions**
(`app/actions/auth.ts`) specifically so a rate limit could be enforced
before Supabase Auth is ever called — the previous direct-from-browser
architecture had no interception point at all. Backed by a new table
(`auth_rate_limit_attempts`, migration `0040`, RLS-enabled with zero
policies — service-role only, same treatment as `platform_admins`), a
sliding-window helper (`lib/security/rateLimiter.ts`), keyed per-email AND
per-IP (10 attempts/5 min for sign-in, 5/hour for sign-up). **Verified
live**: (1) RLS confirmed zero-policy for both `authenticated` and `anon`
(no error, zero rows); (2) the exact count-then-insert threshold logic was
simulated directly in SQL against the live table (attempts 1-3 allowed,
attempts 4-5 blocked once `count >= maxAttempts`) — a direct Node script
calling the real TS function was attempted first but blocked by this
sandbox's network egress proxy (`Host not in allowlist`), the same
constraint documented throughout this session; the SQL-level simulation
exercises the identical query logic. Marked `Done`.

### FOUNDATION-P0-08 — Job Security primitive

Published `lib/jobs/tenantScopedJob.ts` — `runTenantScopedJob(ctx,
requiredPermission, idempotencyKey, jobBody)`, enforcing a resolved tenant
context, the required permission, and a real idempotency key before running
the job body, and auditing any thrown failure. Unit-tested (7 cases).
**Deliberately not retrofitted into Integration Agent's existing
`integration_sync_jobs` code** — per CLAUDE.md non-negotiable #18, a module
agent must never modify another module's implementation to make its own
story pass. Recommendation recorded here (not acted on unilaterally): a
future Integration Agent run should adopt this wrapper around its own
sync-job creation code.

### FOUNDATION-P0-09 — Session Security

`lib/tenant/sessionSecurity.ts` (pure `checkSessionExpiry()`, unit-tested —
5 cases covering idle-only, absolute-only, both, neither, and missing
cookies) plus two cookies (`wa_session_started_at`,
`wa_session_last_seen`) stamped at every sign-in path (password sign-in via
`app/actions/auth.ts`, SSO via `app/auth/callback/route.ts`) and cleared on
sign-out. Enforced in `proxy.ts`: on every authenticated request outside
`/sign-in`/`/sign-up`/`/auth/callback`, checks idle (30 min) and absolute
(12 hour) expiry; on expiry, calls `supabase.auth.signOut()` and redirects
to `/sign-in?reason=expired`, clearing all three cookies. Session fixation
is mitigated by construction (Supabase issues a brand-new session on every
sign-in; there is no pre-auth session identifier to fixate) rather than a
separate control. Marked `Done`.

### FOUNDATION-P0-11 — Input/Output Safety

Published `lib/security/validate.ts` (`assertNonEmptyString`, `assertUuid`,
`assertOneOf`, `assertPlainObject`, `assertJsonSizeWithinLimit`,
`sanitizePlainText`), unit-tested (15 cases). Adopted immediately in the new
SSO connection-creation path (`lib/auth/sso.ts`'s `createSsoConnection()`)
as a real usage example, since that route was written in this same session
— existing shipped route handlers from prior sessions were **not** rewritten
to adopt this retroactively, per CLAUDE.md §3 ("don't refactor unrelated
code while implementing a story"); this is the contract for new/future
routes.

**Full verification run across all seven stories**: `npm run typecheck`,
`npm run lint`, `npm run build` (all routes present, including the four new
ones: `/api/v1/sso*`, `/auth/callback`, `/settings/sso`,
`/settings/security`, `/settings/roles`), `npx vitest run` — 85/85 passing
(27 new tests this session: 5 SSO role-mapping + 7 job-security + 5
session-expiry + 15 input-validation, minus overlap already counted).
`get_advisors(security)`/`get_advisors(performance)` re-checked after the
new migration (`0040`) — identical accepted-exception set as before, plus
`auth_rate_limit_attempts` correctly showing as an intentional
zero-policy table (INFO level, not a new WARN/ERROR).

**Open items carried forward, not blocking**: FOUNDATION-P1-01 (SCIM)
through P1-04, and the P2 items, remain untouched per CLAUDE.md §3's
priority-tier rule (P0 first). The two `Partial` items above (03.3, 03.4)
have a real, honestly-scoped gap (a live IdP/authenticator round-trip) that
only a non-sandboxed environment with a real IdP/device can close — not
something to keep re-attempting here.

---

## 2026-09-14 — QA-P0-04.2 finding: flaky `encryptSecret.test.ts` tamper
test (smallest-safe-change fix, logged here per QA-P0-04.4)

**Found by:** QA Agent, during its repo-wide pipeline sweep (QA-P0-04.1/
04.2). **Fixed by:** QA Agent, as the smallest safe change in the owning
module's own test file, logged here in Foundation's audit log per
QA-P0-04.4's rule (QA logs a defect fix in the *owning* module's log, not
a QA-owned file — `lib/security/encryptSecret.ts` and its test are
Foundation-owned).

**Symptom:** `lib/security/encryptSecret.test.ts`'s "rejects a tampered
ciphertext" test failed intermittently (~25% observed rate across
repeated `vitest run` invocations of the file alone, and occasionally in
full-suite runs), with no code change between passing and failing runs.

**Root cause:** the test tampered the *last* character of the ciphertext
envelope's base64 `data` segment. For a base64 group that lands on a
padding/"don't-care bits" boundary, flipping that specific character can
leave the decoded bytes unchanged — base64 decoding ignores certain bits
in the final sextet of a padded group — so the AES-256-GCM auth tag
would occasionally still verify against the (actually-unchanged)
plaintext, and the test's `.rejects.toThrow()` assertion failed. This is
**not a security bug**: GCM authentication itself works correctly and
does reject any actual ciphertext mutation; only this specific test's
tamper method was occasionally a no-op on the underlying bytes.

**Fix:** moved the tamper target from the last character of `data` to
the first character. For the test's plaintext (`"another-secret"`, 15
bytes = exactly five complete 3-byte base64 groups, no padding),
position 0 is always part of a complete, unpadded group, so flipping it
always changes real ciphertext bytes deterministically.

**Verification:** reran the isolated test file 5 times and the full
`npx vitest run` suite 3 times after the fix — 139/139 tests passing
consistently every run, no further flakiness observed. No other test in
the suite was touched.

**File changed:** `lib/security/encryptSecret.test.ts` only (the single
`it("rejects a tampered ciphertext", ...)` block) — no change to
`lib/security/encryptSecret.ts` itself, since the encryption/decryption
logic was never the defect.

---

## 2026-09-14 — Requirements re-check against expanded doc (round 2), documentation only

**Agent:** Foundation Agent. **Nature of this entry:** planning/backlog
reconciliation only — no application code, migration, or test was written or
modified in this pass, per the task's explicit scope.

The user re-supplied `01_FOUNDATION_SECURITY.md` (at a new upload path) as a
newer/expanded version of the same module doc already reconciled once in the
"Requirements Refresh — 2026-09-14" section of
`docs/plan/01-FOUNDATION-AGENT-BACKLOG.md` (round 1). This entry records a
fresh, independent re-check of the new upload against: (a) the full current
backlog (Progress Tracker + every existing story + the round-1 refresh
section), and (b) the live codebase — `lib/security/`, `lib/tenant/`,
`lib/jobs/`, `lib/rbac/`, `lib/audit/`, `lib/auth/`, `app/api/**`, and
`supabase/migrations/` — so that anything already *implemented* but not yet
*recorded* would not be mistaken for a gap.

**Method:** diffed the new doc's own "Expanded Requirements — Foundation
P0/P1/P2" section (its numbered `FOUNDATION-P0-01` … `P0-15`, `P1-01` …
`P1-04`, `P2-01`/`P2-02` items) against the round-1 refresh's reconciliation
of the same numbering — found them identical in substance and acceptance
wording, confirming round 1 already fully captured that section. Then
separately walked the doc's supporting narrative sections (1 Research-
Informed Product Principles, 2 Target Users, 3 Multi-Tenant Architecture, 26
SSO, 27 Customer RBAC, 39 Recommended Technology Stack, 40 Database Core
Model, 41 RLS Requirements, 42 API Architecture, 43 Integration Job
Architecture, 44 Security Requirements, 45 AI/LLM Architecture, "Foundation
test matrix") line by line against existing stories/code, since those
sections carry more free-text detail than the numbered items and were the
most likely place for something to have been missed.

**Result:** one genuinely new, previously-untracked item found — **CSRF
protection**, named explicitly in section 44's mandatory Security
Requirements list ("CSRF protection where relevant") but absent from every
existing Foundation story, the round-1 refresh, and any code comment in the
repo, despite the app now exposing 50 state-changing `POST`/`PUT`/`PATCH`/
`DELETE` routes under `app/api/**` authorized via cookie-forwarded sessions
— exactly the surface CSRF protection is about. Verified via `grep` that no
existing file mentions CSRF, and confirmed the only existing mitigation is
incidental: every cookie WonderAgent itself sets already uses `sameSite:
"lax"` (`app/auth/callback/route.ts`, `app/actions/auth.ts`,
`app/actions/tenant.ts`) — a real baseline, but never verified against
Supabase Auth's own session cookie or tested.

**Added:** `FOUNDATION-P1-05 — CSRF protection verification & hardening for
state-changing /api/v1/* routes`, status `Not Started`, to the Progress
Tracker and to the P1 list, plus a new "Requirements Refresh — 2026-09-14
(round 2, expanded doc)" section in the backlog documenting the full
reconciliation and the reasoning for scoping it P1 (existing `SameSite=Lax`
baseline already blocks the classic cross-site form-POST CSRF vector; the
doc doesn't tier or give this item its own acceptance criterion beyond a
one-line mandatory-list mention; CLAUDE.md §3 defaults ambiguous/undertiered
scope to P1/P2 rather than P0).

**Not added (already covered elsewhere, verified rather than assumed):**
`npm audit` + GitHub secret scanning → QA Agent (`QA-P0-12`, confirmed
present in `docs/plan/11-QA-AGENT-BACKLOG.md`); integration-credential
rotation → Integration Agent (`INTEGRATION-P0-05.1`, confirmed `Done`);
platform/encryption-key rotation → Platform Agent
(`09-PLATFORM-AGENT-BACKLOG.md`); job-architecture status/progress fields
(records processed/failed, retry count) → correctly out of Foundation's
scope by `lib/jobs/tenantScopedJob.ts`'s own design (each owning module's
job table, e.g. Integration Agent's `integration_sync_jobs`, carries its own
status schema; Foundation's wrapper only standardizes the tenant-context/
authorization/idempotency envelope — confirmed this is a deliberate,
documented design choice, not an oversight, by reading the file's docblock).
"Magic link" auth (section 39) not added — explicitly optional ("if
desired") in the doc, no acceptance criterion attached.

**No existing row's status was changed.** No application code, migration, or
test was touched in this pass — this was a documentation/planning-only
reconciliation as instructed.

## 2026-09-16 — FOUNDATION-P0-16: `lib/ai/` primitive, interface/stub only

**Agent:** Foundation Agent · **Branch:** `claude/wonderagent-setup-lasmly`.
Picked up as the first item in a P0-ordered sweep of the backlog per the
user's explicit "pick up P0 items in order, no need to ask before picking
the next story" instruction, following the 2026-09-15 governance
reconciliation's resolved decision ("start now, read-only summaries
only").

Built exactly what that story's own text says is buildable without the
still-open provider/credential decision: `lib/shared/types/ai.ts`
(`AiSummaryKind`, `AiSummaryRequest`, `AiSummaryResult` — a closed
`AiSummaryKind` enum, not free-text, so every summarizable shape is a
deliberate addition) and `lib/ai/summarize.ts` (`summarize()`,
`AiNotConfiguredError`).

**Boundary enforcement is structural, not just documented:** the file has
no Supabase client import anywhere in it (a unit test asserts this by
reading the file's own source and regex-matching for
`supabaseServer|supabaseServiceRole|supabaseBrowser` — genuinely
impossible for this module to query a database itself, not merely
promised not to), has no write path at all (its only export returns a
string), and its result type is prose (`summary: string`), never a
structured value — nothing in the codebase can read a summarization
result back into a deterministic decision (non-negotiable #9).

**Deliberately NOT done:** the actual provider wiring. `summarize()`
deterministically throws `AiNotConfiguredError` on every call —
`isConfigured()` is a single hardcoded `return false`, the one place this
changes once a provider is chosen. This is not an oversight: the story's
own text explicitly gates "the first real call" on an explicit
provider/credential decision (which LLM API, where its credential is
stored/scoped — a new table? platform-wide or per-tenant? via
`encryptSecret()`?), and that is the *same* open question
`PLATFORM-P0-05.2` (AI Provider Configuration) was already deferred on.
Inventing a schema/credential-storage answer here to unblock the "real"
implementation would be exactly the kind of new shared-foundation-location
decision `docs/design/ownership-map.md` §5 reserves to the user — recorded
as still-open, not guessed at.

**Verified:** 4 new unit tests (`lib/ai/summarize.test.ts`) — throws
`AiNotConfiguredError` rather than returning a fake/empty summary;
rejects (never resolves) so callers can rely on `.catch()`; source-level
assertion of no DB client import; exported surface is exactly
`{AiNotConfiguredError, summarize}` (no accidental extra exports). Also
ran `npm install` first — the other session's recent commits added
`lucide-react` to `package.json` but `node_modules` hadn't been updated
in this environment, which was blocking `npm run typecheck` before this
change even started (unrelated to this story; fixed as a prerequisite).
Full pipeline after: `npm run typecheck`, `npm run lint`, `npx vitest run`
(158/158, up from 141 — the other session's own new tests plus these 4,
all green), `npm run build` with `.next` deleted first, `grep -rl
SUPABASE_SERVICE_ROLE_KEY .next/static` (no match) — all green.

FOUNDATION-P0-16 moves from `Not Started` to `Partial` — the primitive's
contract and boundary are real and tested; the live capability
(`EXPERIENCE-P0-14` needs a working `summarize()` to build against) is
still blocked on the provider decision.

---

## 2026-09-16 — FOUNDATION-P0-16 unblocked by PLATFORM-P0-05.2, moves to Done

The provider/credential decision this row was waiting on was resolved today
(user picked this up as one of 3 "not fully done P0" gaps): OpenAI, both
platform-wide default and per-tenant BYOK. Platform Agent built the actual
credential storage/resolution (`platform_ai_provider_configs`,
`modules/platform-admin/aiProviderConfig.ts`'s `resolveAiProviderKey()`) —
see `docs/design/platform-agent-backlog-audit.md`'s 2026-09-16 entry for the
full detail. This module's own file, `lib/ai/summarize.ts`, needed a small,
directly-expected change as a consequence: `summarize()` gained a leading
`tenantId` parameter, calls `resolveAiProviderKey(tenantId)` (a published
Platform contract call — not a database query of its own; the "no DB client
import" boundary this file's tests assert is unchanged and still enforced
structurally), and makes a real OpenAI `fetch()` call when a key resolves.
`app/api/v1/ai/summarize/route.ts` (Experience-owned) was updated to pass
`ctx.tenantId!` through. Full verification pipeline re-run (typecheck, lint,
217/217 vitest, clean build, no service-role-key leakage) — all green.
FOUNDATION-P0-16 moves from `Partial` to `Done`.

---

## 2026-09-16 — FOUNDATION-P0-03.3 (SSO) confirmed infra-blocked, user chose to skip

As part of the user's P0-gap-closure pass (3 gaps picked from the earlier
"not completely done P0 items" audit: SSO, AI Provider Configuration,
agents.risk_score persistence), re-investigated this row's real blocker
rather than assuming. Verified live via `mcp__Supabase__get_organization`
(org `ryahximilsdatarfcjcq`, plan `free`) and Supabase's own docs
(`mcp__Supabase__search_docs` — "SAML 2.0 support is offered on plans Pro
and above") that this is a genuine infrastructure/billing blocker, not a
code gap: every application-side piece (connection CRUD, domain routing,
JIT provisioning, the auth callback) is already built and unit-tested —
only the real end-to-end IdP handshake needs a paid Supabase plan plus a
real identity provider, neither of which this environment or this agent
can provide.

Presented this to the user with the concrete steps to unblock it
(upgrade to Pro+, enable SAML in Auth Providers, register a real IdP).
**User's explicit decision: skip SSO, close out the P0 gap-closure pass
without it.** This story stays `Partial` — not marked `Done`, not silently
dropped — and is not blocking anything else; the other two gaps in this
pass (`PLATFORM-P0-05.2` AI Provider Configuration, `RISK-P0-02.1`
agents.risk_score persistence) were both fully closed the same day. Resume
this story only if the user later upgrades the Supabase plan and supplies
a real IdP to test against.

---

## 2026-09-16 — Live JS-client tenant-isolation proof (the deferred half of FOUNDATION-P0-07), plus a real `getTenantContext()` defect

**The standing egress blocker is gone.** Re-tested from this session's
sandbox: `https://ekgyjwoenteadaaqakmd.supabase.co` now resolves and answers
over HTTPS — `/auth/v1/health` 200 (GoTrue v2.197.0), `/rest/v1/...` 200 with
real rows against the anon key, `/storage/v1/bucket` 200 — from `curl` *and*
from Node's global `fetch`, which is what actually matters: a JS-client
integration test can run from here now. General egress is open too
(`api.github.com`, `httpbin.org`, `documenter.getpostman.com` all 200), so
the "non-Supabase hosts are blocked" note recorded throughout this repo's
audit logs is also obsolete. Still unreachable: **raw Postgres**.
`db.<ref>.supabase.co` has no A record from here and every
`aws-0/aws-1-ap-southeast-1.pooler.supabase.com` endpoint on 5432/6543 times
out — only 443 gets out, so `psql`/`supabase db push` still cannot be used
and migrations continue to go through the Supabase MCP.

**FOUNDATION-P0-07, the half that was always deferred.** Every prior module
proved tenant isolation by simulating the JWT server-side
(`set_config('request.jwt.claims', ...)` + `set role authenticated`), because
no client could reach Supabase. That half is now done for real:
`tests/live-client-tenant-isolation.mjs` (new, QA-owned per CLAUDE.md §5)
signs two users in through GoTrue with email and password and drives
PostgREST over HTTPS exactly as the browser does. Coverage: all 44
tenant-scoped tables read in both directions (A must see no row of B's and no
foreign tenant_id at all, and vice versa); a fixture reality check, because a
zero-row result only proves isolation when the other tenant's rows are known
to exist; direct primary-key lookup of a known foreign row; cross-tenant
`UPDATE`/`DELETE` (0 rows affected) and `INSERT` (rejected by RLS policy); a
forged `audit_logs` insert claiming the other tenant (rejected); a
survivability check that B's row is untouched afterwards; and an
unauthenticated anon sweep over all 44 tables. **Result: every check passed.**
Anon is denied at `current_tenant_ids()` on the tenant-scoped tables and
returns 0 rows on the platform-only ones. The simulated proof and the live
one agree.

Fixture: the `e2e-*` tenants/users the Playwright suite already defines
(`tests/e2e/support/testUsers.ts`), seeded directly in Postgres via the
Supabase MCP rather than `auth.admin.createUser` (no service-role key is
available to this sandbox), plus one representative row per module in each of
the two tenants. Two notes for whoever picks this up: (1) rows inserted into
`auth.users` by hand need `confirmation_token`/`recovery_token`/
`email_change*`/`phone_change*`/`reauthentication_token` set to `''`, not
NULL, or GoTrue fails every sign-in with "Database error querying schema";
(2) this fixture is deliberately **left in place** rather than deleted like
earlier ones, because the committed script is meant to be re-runnable — it is
all under the `e2e-*` namespace and `seedTestData()` is idempotent against it.

**Real defect found, fixed (QA-P0-04.4 discipline).** The Playwright suite's
first-ever live run failed to sign in as any tenant user: they landed on
`/onboarding` showing three identical "E2E Tenant One" buttons instead of
Overview. Cause: `getTenantContext()` selected `tenant_memberships` filtered
only by `status`, leaving the user-level filter to RLS — but that policy is
*tenant*-scoped (`tenant_id in current_tenant_ids()`), so the query returned
every member of the tenant, not the user's own membership. Measured against
the live database: the old query returns 3 rows (`SELF`, `COLLEAGUE`,
`COLLEAGUE`), the fixed one returns exactly 1 (`SELF`). `app/onboarding/
page.tsx` had the identical query and rendered one organization button per
member. Both now filter `.eq("user_id", user.id)` explicitly, with a comment
saying why RLS is not sufficient here. This is not a tenant-isolation breach —
every row RLS returns still belongs to a tenant the user is a member of — but
it is a direct instance of CLAUDE.md §14's rule that application-level
filtering is defence-in-depth and must not be *replaced* by RLS. The
`/onboarding` half is Experience-owned; logged there too.

Verified: `npm run typecheck`, `npm run lint`, `npm test` (44 files, 260
tests) all clean after the change.

---

## 2026-09-17 — Sign-out scope decided: global, and now stated rather than inherited

The E2E suite's first working sign-out test exposed that `signOutAction()`
revoked every session the user held, on every device — one test logging out
invalidated 39 other specs running in parallel on the same identity. That was
never a written decision: `supabase.auth.signOut()` defaults to
`scope: "global"` in supabase-js v2, and the code simply took the default.

**Put to the user, who chose global.** Appropriate for a security product —
an administrator who suspects a session is compromised gets one control that
ends all of them, rather than having to hunt device by device. The trade-off
they accepted is the ordinary one: logging out on a laptop also signs you out
on your phone.

Behaviour is therefore unchanged; what changed is that it is now explicit.
`app/actions/tenant.ts` passes `{ scope: "global" }` with the decision and its
date recorded inline, so a supabase-js upgrade that changes the default cannot
silently downgrade the posture — which is exactly the kind of drift an
inherited default invites.

`proxy.ts`'s expiry path was made explicit the same way, but is **flagged, not
decided**: that call is the idle/absolute-timeout path, not a user-initiated
logout, so as written, timing out on one device also ends the user's sessions
elsewhere. That was already the behaviour (same library default) and is
consistent with the global posture, but the user decided the logout case, not
this one. Left as-is and raised rather than changed unilaterally.

Covered by a new test in `tests/e2e/auth.spec.ts`: two independent browser
contexts sign in as the same identity, one logs out through the account menu,
and the other is asserted to be bounced to `/sign-in` on its next navigation —
a direct assertion of the global scope rather than a comment claiming it. It
uses the dedicated `signOutOnly` identity for the same reason the other
sign-out test does: a global revocation would otherwise take every parallel
spec's session with it. 18/18 passing in `auth.spec.ts`.

---

## 2026-09-17 — Proxy no longer takes the whole deployment down on missing env

**Reported:** the Vercel preview served "Internal Server Error" on every URL,
including `/welcome`, which is a static marketing page that touches no
database. The build itself was clean.

**Cause:** `proxy.ts` called Foundation's `getSupabaseUrl()` /
`getSupabasePublishableKey()`, which throw when the variable is unset. The
proxy runs ahead of every route (`matcher` covers everything but
`_next/static`, `_next/image`, `favicon.ico`), so a single missing variable
turned into a 500 on every path rather than only the pages that need a
session. Vercel's runtime-error grouping showed it as
`Error running the exported Web Handler: Missing required environment
variable: NEXT_PUBLIC_SUPABASE_URL`, route `/middleware`.

**Change:** added non-throwing `getOptionalSupabaseUrl()` /
`getOptionalSupabasePublishableKey()` to `lib/db/env.ts` and used them in
`proxy.ts` only. When either is absent the proxy skips all session work —
there can be no session to read or refresh, so every visitor is signed out
and `/` is rewritten to `/welcome` as it already is for signed-out visitors;
everything else passes through untouched.

**Deliberately not done:** the throwing getters are unchanged and every other
caller still uses them. A route that genuinely needs the database must fail
loudly rather than silently render as though no user were signed in — this
fix makes a misconfigured deployment *legible* (public pages up, app pages
erroring) instead of uniformly broken, it does not paper one over. No
authorization behaviour changes: the proxy's expiry check was already
defense-in-depth on top of per-route `getTenantContext()`/
`requirePlatformAdmin()` enforcement (non-negotiable #3), and that per-route
enforcement is what actually gates access.

**Verified:** built and served with both variables unset — `/`, `/welcome`
and `/sign-in` return 200 and render, `/agents` does not. `npm run
typecheck`, `npm run lint`, and `welcome.spec.ts` + `auth.spec.ts` +
`navigation-smoke.spec.ts` (53 passed; the one failure is the pre-existing
GoTrue fresh-signup case that needs an MX-backed domain). On the resulting
preview deployment `dpl_48kHKDmRFB2eTeXmH2GSfk45cTtm`, `/`, `/welcome` and
`/sign-up` return 200 and the landing page renders.

**Open — not an application defect:** the Vercel project has no
`NEXT_PUBLIC_SUPABASE_URL`, `NEXT_PUBLIC_SUPABASE_PUBLISHABLE_KEY`,
`SUPABASE_SERVICE_ROLE_KEY` or `SECRET_ENCRYPTION_KEY` in its Preview scope,
which is why the authenticated routes still 500 there. That is a project
configuration step in Vercel's dashboard, not a code change, and none of
these values may be committed (CLAUDE.md §16). Flagged to the user.

---

## 2026-09-17 — Sign-in/sign-up rate limiter could lock out unrelated users on a shared/non-distinguishing IP

**Reported:** the user observed login and sign-up "not working properly."

**Investigated two independent causes, both confirmed with live evidence, not guessed:**

1. **This project's Vercel Preview environment is missing
   `NEXT_PUBLIC_SUPABASE_URL` / `NEXT_PUBLIC_SUPABASE_PUBLISHABLE_KEY` /
   `SUPABASE_SERVICE_ROLE_KEY` / `SECRET_ENCRYPTION_KEY`** — the same gap
   flagged as open in the 2026-09-17 "Proxy no longer takes the whole
   deployment down on missing env" entry above, still unresolved.
   `get_runtime_errors` on the Vercel project shows `Missing required
   environment variable: NEXT_PUBLIC_SUPABASE_URL` on routes `/sign-in`,
   `/sign-up`, `/agents` — 9 occurrences, 4 distinct users, as recently as
   2026-09-17T17:30:16Z (deployment `dpl_HsrzHs87ntugqDnv3k1R6sLjrmHw`,
   `target: null` — a Preview build). Any Preview deployment 500s on
   sign-in/sign-up outright until this is fixed. **Not a code change** —
   these are secrets that must be set in Vercel's dashboard (Project
   Settings → Environment Variables, Preview scope) and must never be
   typed into a committed file or this conversation (CLAUDE.md §16). No
   Vercel MCP tool in this session can write environment variable values
   (deliberately — they're secrets), so this cannot be applied by an
   agent; it needs the user, or whoever holds the project's Vercel access,
   to do it directly.

2. **The sign-in/sign-up rate limiter's IP bucket could collapse many
   unrelated visitors into one counter and block all of them together —
   a real code defect, now fixed.** `app/actions/auth.ts`'s `clientIp()`
   falls back to the literal string `"unknown"` when `x-forwarded-for` is
   absent, and — confirmed against this project's own
   `auth_rate_limit_attempts` table — an intermediary in front of at least
   one deployment reports the loopback address `127.0.0.1` for every
   request regardless of the real visitor. Both values get used as the
   `signin:ip`/`signup:ip` rate-limit bucket key exactly like a real,
   distinguishing client IP would be. Queried the live table directly: the
   `signin:ip` bucket for subject `127.0.0.1` was sitting at 10/10 attempts
   within its 5-minute window as of 17:22:31Z — meaning every sign-in from
   behind that address, by anyone, for any account, was being rejected
   with "Too many sign-in attempts" regardless of whose credentials they
   used. `tests/e2e/support/seedTestData.ts`'s `clearAuthRateLimits()`
   already works around the *test suite* tripping this same mechanism
   (its own comment: "looks like an auth bug and isn't one") — but the
   identical mechanism was never fixed for real traffic, and a corporate
   NAT/shared IP, not just a test runner, can trigger it for real users.

   **Change:** added `isDistinguishingClientIp()` to
   `lib/security/rateLimiter.ts` — rejects `"unknown"`, `""`, and known
   non-distinguishing loopback/unspecified addresses
   (`127.0.0.1`/`::1`/`::ffff:127.0.0.1`/`0.0.0.0`). `signInAction()` and
   `signUpAction()` in `app/actions/auth.ts` now skip the IP-bucket check
   entirely when the resolved address fails that test, relying solely on
   the per-email bucket (unchanged: 10/5min sign-in, 5/hour sign-up),
   which already fully protects each individual account regardless of
   which IP it's attempted from. **Deliberately not done:** did not widen
   or remove the IP bucket for a genuinely distinguishing address — it
   stays as defense-in-depth against a single source hitting many
   different accounts.

   Unblocked the live project immediately: deleted the saturated
   `signin:ip`/`signup:ip` rows from `auth_rate_limit_attempts` directly
   (an operational rate-limit cache, not the audit trail — `audit_logs` is
   untouched).

**Tests added:**
- `lib/security/rateLimiter.test.ts` (new) — `checkAndRecordAttempt()`
  allow/block/prune behavior, and `isDistinguishingClientIp()` against
  every case above plus a real distinguishing IP (must still enforce).
- `tests/e2e/auth.spec.ts` — new `"rate limiting"` describe block:
  sign-in's own rate-limit message is now actually asserted (previously
  untested even though the feature existed); a regression test signing in
  as 11 distinct, never-before-used identities from one client and
  asserting none is ever blocked by a shared IP bucket (the defect above,
  directly); sign-up's rate-limit message. Also added: empty-field
  submission is blocked client-side on both screens (never reaches the
  server action), and a signed-in session survives a full page reload
  without bouncing to `/welcome` or `/sign-in` (regression coverage for
  EXPERIENCE-P0-14's proxy rewrite of `/`).

**Verified:** `npm run typecheck`, `npm run lint`, and the full `npm run
test` (vitest) suite — 269/269 passing, including the 19 new/changed
tests in `lib/security/rateLimiter.test.ts`. The new
`tests/e2e/auth.spec.ts` cases were not run in this environment — no
`SUPABASE_SERVICE_ROLE_KEY` is available here (correctly: it's a secret,
and this session has no tool that exposes it), so `next build`/`next
start` cannot serve authenticated routes locally. They follow this
suite's existing conventions exactly (dedicated, timestamp-unique
identities per CLAUDE.md's isolation pattern; never touch a shared
`TEST_USERS` identity's bucket) and should be run for real with `npm run
test:e2e` wherever `.env.local` is configured, before merging.

**Open — needs the user:** the Vercel Preview environment variable gap in
finding 1 above. Everything in finding 2 is code-complete on this branch.

---

## 2026-09-17 — Forgot-password (FOUNDATION)

**Built:** the missing password-reset flow — `/forgot-password` (request a
reset link), `/update-password` (set a new one), and the supporting server
actions in `app/actions/auth.ts`: `requestPasswordResetAction()` and
`updatePasswordAction()`.

- **Rate-limited** the same way as sign-in/sign-up (`checkAndRecordAttempt`,
  5/hour per email, per-IP too when `isDistinguishingClientIp()` says the
  resolved address is real — see the 2026-09-17 rate-limiter entry above).
- **Email-enumeration protected**: `requestPasswordResetAction()` always
  returns the same `ok: true` shape and the UI always shows one generic "if
  an account exists…" message, matching sign-up's existing property —
  Supabase Auth itself does not reveal account existence through this call.
- **Reuses the existing SSO callback route** (`app/auth/callback/route.ts`)
  rather than adding a second one: `requestPasswordResetAction()` builds
  `redirectTo` as `${origin}/auth/callback?next=/update-password`, and the
  callback now honors a same-origin-only `next` param (new exported
  `isSafeRelativeNextPath()`, unit-tested against the protocol-relative and
  absolute-URL open-redirect vectors) right after its existing
  session-cookie stamping, before the SSO/onboarding branches.
- **`/update-password` is a server component** that checks
  `supabase.auth.getUser()` before rendering anything, so an
  expired/already-used/missing link shows a real "Link expired" state
  immediately rather than a form that only fails on submit.
- Added a **"Forgot password?"** link to `/sign-in`.

**Verified live against this project's real Supabase instance** (not
mocked): rate limiting (both sign-in-style and this feature's own),
email-enumeration protection, and `/update-password`'s expired-link guard
— all pass in `tests/e2e/auth.spec.ts`'s new `"password reset"` describe
block. Also unit-tested directly: `app/actions/auth.test.ts` (rate
limiting, the exact `redirectTo` shape, session guard, real-Supabase-error
surfacing) and `app/auth/callback/route.test.ts` (`isSafeRelativeNextPath`
against every open-redirect case). Full suite: `npm run typecheck`, `npm
run lint`, `npm run test` (283/283), `npm run test:e2e` for
`tests/e2e/auth.spec.ts` (27/27).

**Confirmed the real request-side wiring is correct** by querying
`auth.flow_state` directly after a real `requestPasswordResetAction()` call
(triggered by the enumeration test above): it recorded a PKCE row
(`code_challenge_method: "s256"`, a non-null `code_challenge`) for the
tested user — proof the app's server action correctly negotiates PKCE, the
same mechanism `app/auth/callback/route.ts`'s `exchangeCodeForSession()`
expects on the other end.

**Not verified — flagged rather than faked, same category as this file's
existing SSO-callback caveat:** actually clicking a real recovery link
through to a completed password change. Blocked by three compounding,
environment-specific limitations, not a code issue: (1) this session has no
real email inbox: `supabase.auth.admin.generateLink()` — the only way to
mint a verification link without sending real mail — does not go through
the PKCE code-challenge a genuine `resetPasswordForEmail()` call negotiates,
so it returns tokens in a URL fragment instead of `?code=`, which cannot
exercise this app's callback route or represent what a real user's flow
does; (2) this project's own built-in-SMTP quota (a couple sends/hour —
already documented on the "fresh, valid email" sign-up test) was exhausted
by this same test run, so triggering enough real emails to test around (1)
wasn't an option either; (3) this sandbox's outbound-HTTPS proxy re-
terminates TLS with a CA the pre-installed Chromium doesn't trust, so
Playwright can't even navigate directly to `<project>.supabase.co` to
inspect a verify link's behavior (confirmed via `curl`, which does trust
the proxy's CA, that `admin.generateLink()`'s link resolves via a 303 to a
fragment-based redirect — consistent with point (1), and separately
surfaced a real, unrelated finding: the generated link's `redirect_to`
silently fell back to the project's configured Site URL rather than the
`http://localhost:3100/...` this suite requested, meaning `localhost` is
not in this Supabase project's redirect-URL allowlist — a dashboard
configuration item, not code, and irrelevant to the real flow since real
users are redirected against the deployed origin, not localhost).

**Open — needs the user, whenever full click-through verification against
a real inbox is wanted:** confirm the deployed origin (and any other origin
this app is ever served from) is in the Supabase project's Auth → URL
Configuration → Redirect URLs allowlist, ideally as a wildcard
(`https://<domain>/**`) rather than an exact match, so `/auth/callback` with
a `next` query param is honored rather than silently falling back to the
bare Site URL.

---

## 2026-09-18 — Per-request auth and tenant resolution: 5 network round trips → 1 local check + 1 parallel query wave

**Reported:** every page in the customer shell had a ~1,350 ms TTFB, even
trivial ones like `/settings`, measured as the median of warm runs with
`scripts/measure-page-timings.mjs`. Page content was not the cost; the shell's
auth and tenant plumbing was, and it was identical on every route.

**Cause, measured:** from the environment used to test, one Supabase call —
any call — costs ~270–330 ms of network. `supabase.auth.getUser()` is such a
call, and a single page made it four or five times: once in `proxy.ts` before
routing, once in the layout, once inside `getTenantContext()`, once inside
`isPlatformAdmin()`, and then the page's own `requirePermission()` ran
`getTenantContext()` all over again because nothing was deduplicated between
the layout and the page. `getTenantContext()` itself then ran its membership
and role queries one after the other.

**Changes (all in Foundation-owned plumbing, no schema change):**

- `proxy.ts` is now the ONE place per request that asks the auth server
  whether the session is still good (`getUser()`, one round trip), and it
  enforces the answer: a presented-but-rejected session is redirected to
  `/sign-in` on pages and refused with 401 on `/api/*`; a request with no
  session at all is redirected on protected pages and passed through on the
  API, whose sessionless routes (cron, integration webhooks, MCP ingest, SSO
  domain lookup) gate themselves. Unauthenticated-page enforcement thereby
  moved earlier, from the customer layout into the proxy.
- `lib/tenant/session.ts` (new): `getSessionUser()` resolves the user from
  `supabase.auth.getClaims()`, which verifies the access token's **ES256**
  signature locally against the project JWKS — auth-js caches that JWKS
  globally across client instances, so it is ~1 ms after the first request.
  The project's tokens were checked: header `{"alg":"ES256"}`, so
  verification is genuinely local. This is safe only because the proxy has
  already validated the same session against the server; the layout, page
  and services merely re-derive identity from it.
- **A first version of this change used `getClaims()` in the proxy too, and
  the suite caught it**: `auth.spec.ts`'s "signing out is global" case
  failed, because a revoked session's token still verifies until it
  expires. That test encodes the user's 2026-09-17 decision that logout is
  global and immediate, so the proxy's check went back to a real round trip
  rather than the test being weakened. Net: one GoTrue call per request
  instead of five, with revocation semantics exactly as before.
- `supabaseServer()`, `getSessionUser()`, `getTenantContext()`,
  `getMyMemberships()`, `getProfile()` and `isPlatformAdmin()` are wrapped in
  React's `cache()`: resolved once per request and shared by the layout, the
  page and every module service under them.
- `getTenantContext()` now fetches memberships and role rows **in parallel**
  (roles for the user across tenants, then filtered to the active tenant in
  code) instead of sequentially. Both queries keep their explicit `user_id`
  filter — the privilege-escalation guard noted in the previous entry is
  unchanged.
- `getMyMemberships()` is published for the customer shell's organization
  switcher, which had been re-running the same membership query itself.

**Result, same script, same machine:** every page ~830 ms TTFB, from
~1,350 — one auth-server round trip in the proxy, one parallel wave of
tenant/profile/shell queries, then the page's own wave. Each of those is a
~270 ms trip from this environment; see the Experience entry of the same
date for the deployment-region change that makes them tens of milliseconds
in production.

**Deliberately not done:** embedding memberships and roles in the JWT via a
custom access-token hook would make tenant resolution fully local (zero round
trips) and CLAUDE.md §2 explicitly permits claims as a source — but claims go
stale until the token refreshes, so a role revocation would lag by up to the
token lifetime. That is a security-semantics decision for the user, recorded
here rather than made.

**Verified:** typecheck, lint, build, and the full Playwright suite
(sign-in/out, session expiry redirect, platform-admin gate, RBAC negatives,
tenant isolation) — see the Experience entry for the run.

---

## 2026-09-18 — AI key fallback: message where to fix "not configured" (BYOK → platform default → tell the user)

**Reported:** the app's AI API key should default to the platform-wide key
when a tenant hasn't configured BYOK, and when neither is available the
user should be told where to fix it — the Platform Admin page if one
exists for this, otherwise the environment variable to set.

**Found the fallback mechanism (BYOK → platform default) was already
fully implemented and correct** — `resolveAiProviderKey()`
(`modules/platform-admin/aiProviderConfig.ts`, PLATFORM-P0-05.2, shipped
2026-09-16): BYOK-first, falls back to that provider's
`PLATFORM_OPENAI_API_KEY`/`PLATFORM_GEMINI_API_KEY`, returns `null` only
when neither exists. Nothing to change there.

**What was actually missing:** when `resolveAiProviderKey()` returns
`null`, `AiNotConfiguredError`'s message was just "No AI provider is
configured for this deployment." — true, but not actionable. And
`modules/ui/AiSummaryPanel.tsx` (used on `/risk/rogue/[agentId]`) threw
that message away entirely: on a 501 it always rendered the same
hard-coded "AI summaries aren't configured for this workspace yet.",
regardless of what the API actually said.

**Confirmed there is no Platform Admin page for this setting** — checked
every route under `app/platform-admin/*`: admins, announcements, branding,
features, health, tenants, tenant usage. None of them configure AI
provider keys; the only UI for this is the tenant-level
`/settings/ai` (BYOK), and the platform-wide default has only ever been
settable via the two env vars. So the correct message, per the user's own
"ask me to configure it on platform admin page (if it exists), if not
then ask me to set in environment variable," is the environment-variable
instruction — there's no page to point to instead.

**Changes:**
- `AiNotConfiguredError`'s message (`lib/ai/summarize.ts`) now says both
  things: bring your own key in Settings → AI, or a platform administrator
  should set `PLATFORM_OPENAI_API_KEY`/`PLATFORM_GEMINI_API_KEY` — stated
  explicitly that there's no Platform Admin page for this yet, so nobody
  goes looking for one.
- `AiSummaryPanel.tsx` now reads and renders that message from the API's
  501 body instead of discarding it for a generic string.
- `/settings/ai`'s existing "no platform-wide default key" status line
  gained the same environment-variable instruction (it already correctly
  showed BYOK vs platform-default vs not-configured status and prompted
  BYOK — this only adds the missing half for whoever controls the
  deployment).

**Verified live:** rebuilt and served the app (`next build && next
start`), signed in, confirmed `/settings/ai` renders the updated message
(screenshotted), and called `POST /api/v1/ai/summarize` directly to
confirm the 501 response body now carries the full actionable message
end-to-end (this deployment's `.env.local` has neither platform key set,
so the not-configured path is real, not simulated). Full vitest suite:
283/283 (no existing test asserted the old message's exact text, so
nothing needed updating there).

**Deliberately not done:** did not build a `/platform-admin` AI provider
config page. The user's own phrasing ("if it exists... if not") signals
this is a scope decision, not an oversight to silently fix — building
platform-wide config storage/UI is materially larger (global config table,
Platform Agent's own module) and wasn't asked for; flagged here rather
than assumed.

---

## 2026-09-18 — Google sign-in on /sign-in and /sign-up

**Built:** `modules/ui/GoogleAuthButton.tsx` — one control on both auth
screens (Google itself decides new vs returning, so there is no separate
"sign up with Google" flow to build). Starts Supabase Auth's OAuth flow
via the browser client's `signInWithOAuth({ provider: "google" })`, which
returns to the existing `/auth/callback` route — the same one SSO and
password recovery already use. The browser client is used deliberately:
`@supabase/ssr`'s `createBrowserClient` writes the PKCE code verifier to a
cookie the server callback can read, which is what lets
`exchangeCodeForSession()` complete server-side.

**Also fixed on the way:** `/auth/callback`'s final fallback sent every
non-SSO user to `/onboarding`, and `/onboarding` deliberately does not
auto-forward a user who already has memberships (it doubles as the "create
another organization" screen) — so every returning OAuth or email user
would have picked their organization on each sign-in. That is exactly the
friction removed from the password path in "sign-in lands on the app, not
the organization picker"; the callback now resolves tenant context and
sends a user with a tenant to `/`, keeping `/onboarding` for genuinely new
users.

**Deliberately not rate-limited** through `app/actions/auth.ts` like the
password paths: no credential is presented to this app to throttle —
Google authenticates, and Supabase Auth applies its own limits.

**Verified:** typecheck, lint, build, and the full `auth.spec.ts` suite
(32 tests). New e2e case intercepts the outgoing `/auth/v1/authorize`
request and asserts it carries `provider=google` and a `redirect_to`
pointing back at this app's `/auth/callback` — no dependency on Google
being enabled yet or on egress this sandbox's TLS-intercepting proxy
blocks. Screenshotted both screens.

**Two real test flakes found and fixed while running this** (both
pre-existing, both mine from earlier in the session): the sign-up and
password-reset rate-limit tests navigated away 300ms after submitting,
which aborted some server actions in flight so they were never recorded
and the final over-limit request wasn't over the limit. Both now wait for
the attempt to actually complete. The password-reset one also had to match
its outcome paragraphs by CSS (`p[role="status"], p[role="alert"]`) rather
than by role — the document carries an always-present empty alert region
that a role-based wait resolves against instantly, so it never waited.

**Needs the user (configuration, not code) — Google is not enabled on the
Supabase project yet**, so the button currently surfaces Supabase's
"provider is not enabled" message rather than reaching Google. See the
handover notes given to the user: a Google Cloud OAuth client, the
client ID/secret pasted into Supabase's Google provider, and the redirect
URL allowlist (which, as recorded in the forgot-password entry above,
still does not include this app's origins).

---

## 2026-09-18 — Help assistant: deterministic retrieval, AI phrasing optional

**Built** `lib/ai/helpAnswer.ts` and `POST /api/v1/help/ask`, behind the
Experience Agent's `/help` page (see that module's audit entry for the guide
itself).

**Design point worth keeping:** retrieval runs first and is deterministic.
The question is scored against the guide sections
(`modules/ui/help/content.ts`) by weighted term matching — title and curated
keywords weighted far above body prose, with a per-section body cap so a long
section cannot win on length alone — and **those matches, not the model,
produce the links shown to the user.** An LLM, when configured, only phrases
an answer grounded in the sections retrieval already chose, under a system
prompt that forbids writing links at all.

Two properties follow, both deliberate:
- The assistant cannot cite a page that does not exist, because it never
  chooses links.
- It works with no AI provider at all, returning the best-matching section's
  summary and the section links, and disclosing in the UI that the answer
  came from the guide text rather than a model. AI improves phrasing; it is
  not load-bearing (non-negotiable #9's posture, applied to a help feature).

**Refactor:** the OpenAI/Gemini request shapes moved out of
`lib/ai/summarize.ts` into a new `lib/ai/provider.ts` when this second caller
appeared, so the two request formats, error handling and empty-response
handling exist once. `summarize.ts` keeps its exact export shape — its own
test asserts the module exports exactly `["AiNotConfiguredError",
"summarize"]`, and that still holds.

**Also:** `/api/v1/help/ask` deliberately does not 501 when no provider is
configured, unlike `/api/v1/ai/summarize`. Falling back to retrieval is the
correct behaviour for a help feature; returning an error would be worse than
the answer it can already give. It requires a session but no module
permission — the guide is product documentation, identical for every tenant,
and no tenant-scoped data is ever sent to a provider.

**Verified:** `lib/ai/helpAnswer.test.ts` — 12 tests covering routing
accuracy (password → sign-in section, Saviynt → integrations, SHOULD/CAN/DID
→ the concept section), the no-match case, the cap, the "only ever returns
real sections" property, and all three answer paths (no provider, provider
failure, provider success keeping retrieval's links). Full vitest suite
295/295; `summarize.test.ts` still 8/8 after the refactor.

## 2026-09-19 — FOUNDATION-P1-05: CSRF protection verified and tested

**Confirmed the baseline is real, from the library's own source, not
assumed.** `@supabase/ssr`'s `node_modules/@supabase/ssr/dist/main/utils/
constants.js` defines `DEFAULT_COOKIE_OPTIONS = { path: "/", sameSite:
"lax", httpOnly: false, maxAge: ... }`. Neither `proxy.ts` nor
`lib/db/supabaseServer.ts` passes an overriding `cookieOptions` to
`createServerClient()`, so every `sb-*-auth-token` cookie Supabase Auth
sets on this app genuinely carries `SameSite=Lax` — this row's acceptance
criterion's first branch ("confirm Supabase Auth's own session cookie is
also SameSite=Lax") is satisfied outright; its "or add explicit Origin/
Referer verification" fallback is therefore not needed.

**Built the isolation-style positive/negative test the row asked for** —
`tests/e2e/csrf.spec.ts`. SameSite is a *browser-enforced* cookie policy,
not application code, so the only faithful way to prove it is a real
browser making a real cross-site request; a raw HTTP client has no
cookie-jar SameSite policy to violate in the first place, and would
"pass" a fake version of this test regardless of whether the real
protection works. The cross-site page is a Playwright-intercepted
`http://csrf-attack.invalid` origin (never resolved via real DNS, no
outbound network dependency) whose script issues an authenticated-looking
`fetch(..., { credentials: "include" })` at the real app; the request to
the real app is left un-intercepted except to inspect (not fake) the
`Cookie` header Chromium actually sent, which is the fact under test.

**A finding along the way, not a defect:** the cross-site request is
rejected by *two* independent layers, not one — SameSite=Lax withholds
the cookie (confirmed directly: no `sb-*-auth-token` in the captured
header), and separately this app sends no CORS headers permitting a
foreign origin to read a cross-site response at all, so the attacker
page's `fetch()` never even sees a status code — it gets an opaque
network error before either the cookie exclusion or the resulting 401
would matter to it. The test's first draft wrongly expected the page to
read a `401`; it can't, by design, and that opacity is itself a second,
correctly-functioning defense, not a test bug to route around.

**Verified:** ran the new spec live against this session's actual dev
server (not simulated) — 2/2 passing, including a same-origin positive
control (`fetch("/api/v1/tenant")` from within the app itself returns
`200`, proving the negative case is a real contrast and not just "every
request fails"). `npm run typecheck`/`npm run lint` clean (no non-test
code changed — this story's gap was verification and test coverage, not
a missing mitigation). No schema/migration change.

**Progress Tracker:** FOUNDATION-P1-05 moved from `Not Started` to `Done`.

---

## 2026-09-25 — FOUNDATION-P0-17 (agent API keys) and FOUNDATION-P0-18 (permission keys)

Master stories P0-27 and P0-42. The user decided on 2026-09-25 that agents
authenticate to the Runtime Gateway with per-agent API keys, and that only
the missing permission keys are added.

**Migration `0061_foundation_agent_api_keys_and_permissions.sql`** (applied
live via `apply_migration`).

- **Seven permission keys**: `agent.suspend`, `discovery.read`,
  `discovery.manage`, `access.simulate`, `policy.publish`,
  `runtime.enforce`, `runtime.emergency`. Each is granted explicitly by
  least privilege, because 0003's cross-joins covered only the keys that
  existed then.
  - TENANT_SUPER_ADMIN gets all seven.
  - READ_ONLY and AUDITOR get `discovery.read` only.
  - IAM_ADMIN gets suspend, discovery and simulate.
  - IAM_ARCHITECT gets discovery.read, simulate, publish and enforce.
  - SECURITY_ADMIN gets suspend, discovery.read, simulate, publish, enforce
    and emergency.
  - No existing key is renamed.
- **`agent_api_keys`** columns: tenant_id, agent_id, name, key_prefix,
  key_hash (unique), created_by, expires_at, last_used_at, revoked_at,
  revoked_by, revoked_reason.
  - Only a SHA-256 hash of the secret is stored.
  - It has the same lockdown as `integration_credentials` (0021) and
    `platform_ai_provider_configs` (0057): RLS on and **no client
    policies**, so no browser session can read even a hash.
  - Indexes: (tenant_id, agent_id, created_at), agent_id, created_by and
    revoked_by. Every FK is covered, and the advisor shows no new
    unindexed FK.

**`lib/security/agentApiKeys.ts`** (Foundation primitive)

- **Key format**: `wa_ak_` plus 32 random bytes in base64url. A 12-character
  prefix is kept for display.
- **Create / list / revoke**: service-role reads and writes that check
  `tenant_id` on every row, visibly (§14). The agent must belong to the
  caller's tenant. Create and revoke are audited as
  `agent_api_key.created` and `agent_api_key.revoked`, with the prefix and
  never the secret or hash (#10, #11).
- **`verifyAgentApiKey()`** is the gateway's authentication step, and it
  fails closed. It returns `{ keyId, tenantId, agentId }` taken **from the
  key row**, so a caller can never choose its tenant or agent (#2). It
  returns null for a malformed, unknown, revoked or expired key, for a key
  whose tenant is suspended, and for one whose agent is not in its tenant.
  The hash is compared in constant time, and `last_used_at` is refreshed at
  most once a minute.
- **`bearerAgentKey()`** reads `Authorization: Bearer`.

**RBAC**: `requireAnyPermission()` was added beside `requirePermission()`,
for actions two roles reach legitimately. Key revocation is open to
`agent.update` (owners and admins) or `runtime.emergency` (incident
responders).

**Surfaces**

- `GET` and `POST /api/v1/agents/:id/api-keys`: list needs `agent.read`,
  create needs `agent.update`. The create response carries the secret once,
  with `Cache-Control: no-store`.
- `DELETE /api/v1/agents/:id/api-keys/:keyId`: revoke.
- An "API keys" card on Agent 360
  (`app/(customer)/agents/[id]/AgentApiKeysPanel.tsx`), with server
  actions in `app/actions/agentApiKeys.ts`.
  - The secret is shown once, with a copy button and a "will not be shown
    again" warning. Nothing stores it.
  - Keys are listed by prefix and status.
  - Revoke goes through `ConfirmActionDialog` with a required reason.
  - Controls are hidden without the permission, and the server enforces it
    anyway.

**Verified**

- **Unit**: `lib/security/agentApiKeys.test.ts`, 16 cases.
  - Key format and uniqueness; hash-only storage; audit carries neither the
    secret nor the hash.
  - Verify returns null for malformed, unknown, revoked and expired keys,
    for a suspended tenant, and for a cross-tenant agent binding.
  - `last_used_at` is refreshed within the key's own tenant.
  - Create is refused for another tenant's agent; name and expiry are
    validated.
  - List and revoke are tenant-scoped.
  - Plus 3 new `requireAnyPermission` cases.
- **Live SQL**: `tests/foundation/agent-api-keys-isolation.sql`, 9/9.
  - A signed-in tenant-A user sees 0 of their own tenant's key rows and 0
    of tenant B's.
  - UPDATE and DELETE touch 0 rows; INSERT is denied (42501); the rows are
    intact afterwards.
  - All 7 keys are present. READ_ONLY holds only `discovery.read`.
    `runtime.emergency` is held only by SECURITY_ADMIN and
    TENANT_SUPER_ADMIN.
  - Fixtures cleaned up (0 left).
- **E2E**: `tests/e2e/agent-api-keys.spec.ts`, 4/4.
  - The key is shown once and is gone after a reload; the prefix is listed;
    revoke shows "Revoked".
  - The list API never returns a secret or a 64-hex hash.
  - READ_ONLY: POST gives 403 and GET gives 200.
  - Tenant Two's admin sees `[]` and gets 404 on create.
- **Live audit rows**: `agent_api_key.created` and `.revoked` carry the
  actor and prefix, with no secret or hash (checked by regex in SQL).
- **Advisors**: security shows only the expected INFO
  `rls_enabled_no_policy` for the deliberate lockdown. Performance shows
  nothing new for this table.

**Not in scope.** Using the key belongs to RUNTIME-P0-15, the gateway
endpoint, which will call `verifyAgentApiKey()`. Key rotation reminders
and expiry notifications are not built.

**Full-suite regression** (§17.8, because auth, RBAC and a migration
changed):

- `tsc` clean; `eslint` exit 0; `vitest` 52 files / 371 tests.
- Full Playwright 145/146. The one failure was the sign-up spec: GoTrue
  answered `Email address "…@example.com" is invalid`.
  - That is the provider's domain validation, not an app defect. It is the
    same category as the "email rate limit exceeded" answer the spec
    already accepted.
  - The assertion now accepts either provider message, scoped to the
    `alert` role, and passes. Recorded in the QA log.

**Follow-up, same day (RUNTIME-P0-15 performance):**

- `verifyAgentApiKey()` now checks the key, its tenant's status and its
  agent's tenant in **one** query, embedding `tenants` and `agents`
  through their FKs, instead of two round trips.
- The `last_used_at` stamp runs after the response through the new
  `lib/shared/afterResponse.ts` (`next/server` `after()`, with a
  background fallback outside a request scope).
- Behaviour is unchanged, and it still fails closed. The unit tests were
  updated for the embedded shape (16/16), and the live API-key and gateway
  specs pass (12/12).

**Addition (RUNTIME-P0-18):** `revokeAllAgentApiKeys(tenantId, actorId,
agentId, reason)` is emergency credential revocation. It checks the agent
is in the tenant, revokes every active key in one tenant-filtered update,
and writes one audit event, `agent_api_key.revoked_all`, with the count
and key ids. It is covered by the emergency E2E spec: the next gateway
call gets 401.

## 2026-09-26 — Open item: a network failure to Supabase Auth reads as "session expired"

Found while verifying INTEGRATION-P0-12:

- During a roughly 4-minute egress outage, no request reached Supabase:
  the edge logs are empty from 04:06 to 04:09.
- `proxy.ts` ignores the error from `supabase.auth.getUser()`. A network
  failure (`AuthRetryableFetchError`) therefore looks the same as a
  revoked session: pages redirect to `/sign-in?reason=expired`, and APIs
  return 401 UNAUTHENTICATED.
- Failing closed is correct, but the state is untruthful (§17.5), and a
  user is told their session expired when it did not.

Proposed fix (a proxy and authentication change, so a full-suite story):

- On a retryable network error, APIs return 503 `AUTH_UNAVAILABLE`.
- Pages render a "sign-in service unavailable, try again" state instead
  of the expired message.
- Still no access.

## 2026-09-26 — Resolved: "sign-in service unavailable" is no longer reported as "session expired"

Resolves the open item above. The behaviour is still fail-closed, now with a
truthful message (§17.5):

- **`isAuthServiceUnavailable(error)`** (`lib/tenant/sessionSecurity.ts`,
  pure) is true for `AuthRetryableFetchError`, or a status of 0 or 5xx
  from `getUser()`.
- **`proxy.ts`:** when the session cookie is present but the auth server
  cannot be reached, access is still refused, but truthfully:
  - APIs return **503** `AUTH_UNAVAILABLE`, with `Retry-After: 30`;
  - protected pages are rewritten to `/service-unavailable` with **503**.
    The URL is kept, so "Try again" reloads the page that was asked for;
  - public pages pass through as before.
  - A **rejected** session behaves exactly as before: a redirect to
    `/sign-in?reason=expired`, or 401.
- **`/service-unavailable`** (AuthShell, public) says the session was not
  ended, that nothing is shown until it can be confirmed, and that
  nothing was changed.

**Verified:**

- unit: `sessionSecurity.test` 6/6 and a new `proxy.test.ts` 4/4, with a
  mocked auth client for API 503, page rewrite 503, public page
  pass-through, and an unchanged rejected-session redirect and 401;
- vitest 659/659;
- the page was checked in light (1280) and dark (390).
- **Not simulated end to end:** that would mean breaking the sandbox's
  egress proxy.
- The full Playwright suite result is recorded in the next entry.
- **Full Playwright suite** (§17.8: `proxy.ts` and authentication changed):
  **273/273 passed** (16.1 min).

## 2026-09-26 — FOUNDATION-P0-22: tenant identity, tenant URL and domain registry (WonderID Phase 4b)

Implements TENANT-001/002/003 of
`docs/requirements/WonderID_Tenant_User_Permissioning_Model.md`. The
address narrows which tenant a request is for; it never grants access
(non-negotiable #2). Access still needs an active membership, and RLS still
scopes every read.

**Migration `0095_foundation_tenant_domains.sql` (applied to the dev project):**

- `tenants.slug` is the tenant's address:
  - `tenant_slug_is_valid()` (immutable, pinned `search_path`): lowercase,
    URL-safe, 3–40 characters, no `--`, reserved words refused
    (`www`, `api`, `admin`, `platform`, `auth`, `sso`, …);
  - enforced by the `tenants_slug_policy` check;
  - a trigger refuses any slug change.
- `tenants.suspended_at` / `suspension_reason`: stamped on suspension,
  cleared on reactivation (same trigger).
- `tenant_domains`:
  - PLATFORM_SUBDOMAIN stores only the label, so one database serves every
    environment's `<slug>.<BASE_APP_HOST>`;
  - CUSTOM_DOMAIN stores the full hostname; verification is P1, so these
    stay `pending` and never resolve;
  - one primary per tenant; `verified` ⇔ `verified_at`;
  - select-only RLS for members; writes come from the platform (service
    role) and the trigger.
- Every new tenant gets its verified primary subdomain from a trigger;
  existing tenants were backfilled. Trigger functions have execute revoked
  from public, anon and authenticated.
- `resolve_tenant_host(p_subdomain, p_hostname)`:
  - the one public lookup (anon and authenticated);
  - verified domains only;
  - returns only id, name, slug and status.

**App:**

- `lib/tenant/host.ts` (pure):
  - `BASE_APP_HOST` normalization;
  - `parseTenantHost` → none / base / subdomain / invalid. Nested labels,
    reserved or malformed labels and lookalike hosts are not subdomains;
  - `slugProblem`; `tenantUrl`.
- `lib/tenant/hostTenant.ts`:
  - `getHostTenant()` resolves once per request (`cache`); a failed lookup
    resolves nothing;
  - `urlForTenant()` keeps the request's scheme and port.
- `getTenantContext()`: on a tenant address the only candidate membership
  is the addressed tenant's. The active-tenant cookie cannot pull in
  another tenant there. Elsewhere it behaves as before.
- `proxy.ts`:
  - the host lookup runs in parallel with the session check, with a 30 s
    bounded cache;
  - an unknown, unverified or invalid address answers 404
    (`TENANT_NOT_FOUND` for APIs, `/tenant-not-found` for pages) without
    naming any tenant;
  - a failed lookup answers 503 (fail closed);
  - a signed-out visitor on a tenant address is sent to `/sign-in`, not
    the marketing page.
- Sign-in on a tenant address (`app/sign-in/page.tsx` server component +
  `SignInForm.tsx`):
  - shows the organization's name; no organization picker, sign-up or
    Google;
  - a suspended organization says so and the form is disabled;
  - `signInAction` refuses an unknown or suspended address. A successful
    password check without an active membership there ends that new
    session (local sign-out), writes `auth.sign_in_refused`, and says
    "This account is not an active member of X."
- `/no-access` (suspended or not a member, with sign out): the customer
  layout sends a tenant address there instead of `/onboarding`.
  Onboarding and creating an organization are refused on a tenant address.
- The workspace switcher shows each organization's address. Switching on a
  tenant address navigates to the target tenant's own URL, because sessions
  are per host.
- `BASE_APP_HOST` is documented in `.env.local.example`; unset, tenant
  addresses are off and nothing changes. The Playwright server runs with
  `BASE_APP_HOST=localhost` (Chromium resolves `*.localhost`).

**Verified:**

- tsc clean; eslint clean on every changed file.
- vitest **700/700**, including the new `host.test.ts` (6) and
  `proxy.test.ts` now at 10: unknown-address 404 for APIs and pages, 503
  on lookup failure, signed-out redirect to `/sign-in`, and pass-through
  for a known address.
- SQL check `tests/foundation/tenant-domains-isolation.sql`, run live:
  every check held (results in the file header); fixtures removed.
- E2E `tests/e2e/tenant-address.spec.ts` **12/12**:
  - the tenant sign-in page;
  - unknown and reserved addresses are 404 for pages and the API;
  - a member lands in the addressed tenant;
  - a non-member is refused and the new session ends;
  - a two-organization member gets the addressed one each time;
  - a suspended organization refuses and says so.
- Screenshots: tenant sign-in (light, 1280), suspended (dark, 390),
  "No organization at this address" (light, 1280).

**Left out / handed on:**

- Custom-domain verification (DNS TXT) and management UI: P1, with
  PLATFORM-P0-14's tenant pages.
- The shell's environment label arrives with FOUNDATION-P0-27's security
  profile.
- **Production needs `BASE_APP_HOST` in Vercel and a wildcard domain
  `*.<BASE_APP_HOST>`.** Not configured by this change.
- Pre-existing, not introduced here: two
  `invalid input syntax for type uuid: "null"` server log lines during the
  platform-admin auth setup. Noted for QA.

## 2026-09-26 — FOUNDATION-P0-22 full suite, and a short production regression from 0096

**Full Playwright run on the FOUNDATION-P0-22 build:** 300 passed, 3 failed,
1 did not run (21.4 min). The 3 failures were not P0-22's:

- During that run, migration 0096 (FOUNDATION-P0-23, below) was applied to
  the shared database.
- Its first form gave `tenant_memberships` two more foreign keys to `users`
  (`status_changed_by`, `invited_by`), and `user_roles` one more
  (`granted_by`).
- PostgREST then found every existing `users(...)` embed from those tables
  ambiguous (PGRST201). That broke:
  - `GET /api/v1/users` (the multi-org spec);
  - `/settings/roles` (navigation smoke);
  - one onboarding-proposals step.

**Production shares this database**, so the same two screens were broken in
production for about 20 minutes.

**Fixed without a deploy:** a follow-up step
(`0096_foundation_user_lifecycle_actor_columns`) dropped the three foreign
keys. The actor ids stay plain uuids, and the audit log also records the
actor. The migration file was corrected to the equivalent end state. The 3
specs were then re-run on the same build: 54/54 passed.

**Lesson, for every module:** a second foreign key between two tables
changes the meaning of every existing PostgREST embed between them. Use a
plain uuid, or update every embed to name its foreign key
(`users!tenant_memberships_user_id_fkey(...)`) in the same change.

## 2026-09-26 — FOUNDATION-P0-23: users and the membership lifecycle (WonderID Phase 4b)

Implements IAM-001 and the user-management requirements (§5–10, 23–25,
30–34 of `docs/requirements/WonderID_User_Role_Permission_Management_Requirements.md`;
mockups 1–3 and 9).

**Migration `0096_foundation_user_lifecycle.sql`** (applied in four steps,
see above):

- Memberships:
  - the statuses gain `deactivated`;
  - each status change records when, by whom and why;
  - invitations record who invited and when;
  - account type (internal, external) and sign-in method are recorded.
    Service accounts are machine identities, not members;
  - an index on `(tenant_id, status)`.
- **Self-protection in the database:**
  - `user_roles.granted_by <> user_id` (check constraint);
  - a trigger refuses a member changing their own status, except accepting
    their own invitation.
- **Last-administrator guard in the database:** a trigger on
  membership status changes and deletes, and on role deletes.
  - It refuses anything that would leave an organization with no active
    Tenant Administrator.
  - It is serialized on the tenant row, so two administrators cannot
    remove each other at once.
  - A cascade from a deleted organization or account is let through.
- Permission keys `users.view/invite/create/update/suspend/remove`:
  - Tenant Administrator: all;
  - Identity Administrator: all but remove;
  - Security Administrator: view and suspend;
  - Auditor: view.
- Service-role-only functions:
  - `tenant_user_directory` (search escaped literally, status and role
    filters, paged, with total);
  - `tenant_user_summary`;
  - `user_sessions` (browser and times, no IP);
  - `revoke_user_sessions` (deletes the user's auth sessions; the proxy's
    per-request check then refuses their next request).
- An `audit_logs (tenant_id, object_id, created_at)` index for access
  history.
- Both new trigger functions (and 0095's) have a pinned search path; the
  security advisor is otherwise unchanged.

**Service** (`lib/users/`):

- `userRules.ts` (pure): the lifecycle transitions and their permissions,
  self-protection, invitation validation, effective permissions with
  provenance, and database refusals mapped to answers.
- `users.ts`:
  - every query filters by the server-resolved tenant, and every change
    re-reads the membership in this tenant first;
  - conditional updates, with a 409 on a concurrent change;
  - refusals are audited as failures;
  - suspension, deactivation and removal end the person's sessions;
  - removal also drops their roles here.
- `lib/rbac/roles.ts`:
  - assigning a role to yourself is refused (403 `SELF_ESCALATION`);
  - `granted_by` is recorded;
  - removing the last administrator's role answers 409
    `LAST_TENANT_ADMIN`;
  - roles can be managed for invited, suspended and deactivated members.

**Invitations:**

- The wizard (basic details, roles, review) invites or adds someone:
  - it creates the account if the address has none;
  - it grants the chosen roles as the administrator. Granting roles also
    needs `role.manage`.
- Job title, department and account type go to the person's identity
  through the Identity Agent's published `updateIdentity`, only when the
  administrator may edit identities. Otherwise the page says so.
- The set-password link is e-mailed only to the invitee (Resend, when
  configured) and never shown to the administrator, since it signs in as
  that person. With no e-mail set up, the page says truthfully that
  nothing was sent.
- The invitee accepts:
  - on `/onboarding` on the base address;
  - on `/no-access` on the organization's own address.

  Sign-in on an organization's address lets an invited member in far
  enough to accept.

**Screens:**

- `/settings/users`: counts, search, status and role filters, paged at
  the database.
- `/settings/users/new`: the wizard.
- `/settings/users/[id]`, with four tabs:
  - roles, with who granted each and when;
  - effective permissions, with the roles that grant each;
  - access history, including refusals and reasons;
  - sessions.

  Its actions are suspend, reactivate, deactivate, remove (each with a
  reason) and revoke sessions, plus edit name and assign or remove roles.
  None is offered on your own page.
- API:
  - `GET /api/v1/users/[id]`;
  - `POST .../status`;
  - `POST`/`DELETE .../roles`;
  - `GET`/`DELETE .../sessions`.
- "Users" is in the sidebar and on `/settings`. The Users & Roles page no
  longer offers you a role form on your own row, and shows removal
  refusals.

**Verified:**

- tsc and eslint clean.
- vitest **715/715**, with the new `userRules.test.ts` (10).
- SQL check `tests/foundation/user-lifecycle-isolation.sql`, run live:
  all 22 checks as expected (header); fixtures removed.
- E2E `tests/e2e/users.spec.ts`:
  - list search and filters;
  - add now with Read Only: roles, effective permissions with
    provenance, and the job title reaches the identity;
  - suspension ends the person's session (their next API call refused)
    and history shows the reason;
  - reactivation restores access;
  - an invitee accepts and lands in the organization;
  - self-suspend 403 and self-grant 403;
  - last-admin role removal 409, with the role kept;
  - read-only 403, cross-tenant 404.

  With the branding spec: **20/20**.
- Screenshots: Users list (1440 light), Add user (1440 light), User
  detail (1440 light; 390 dark).
- The full suite on the combined build is recorded in the next entry.

**Left out / handed on:**

- The group filter and groups tab: FOUNDATION-P0-26.
- The scope and conditions step: FOUNDATION-P0-19.
- Enforcing the chosen sign-in method: FOUNDATION-P0-27's security profile.
- Invitation expiry and resend: P1.
- Session listing shows a person's sessions across all their organizations
  (sessions are per account). Revoking them signs the person out
  everywhere, as the specification's suspension requires. Recorded, not
  narrowed.

## 2026-09-26 — Combined full suite (FOUNDATION-P0-22/23, EXPERIENCE-P0-22/23) and a test-data fix

**Full Playwright run on the combined build:** 314 passed, 1 failed, 3 did
not run (21.8 min).

- The failure was data-sources.spec's first step, and it reproduced on
  re-run.
- **Cause:** 213 throwaway "E2E Acc App …" applications, which other specs
  create on every run, had pushed the seeded "Snowflake" past the
  application picker's 200-row list limit.
- **Fix:** the seed's prune now removes throwaway "E2E …" applications
  (their access requests first, the one foreign key that does not
  cascade) and throwaway custom roles (`tests/e2e/support/seedTestData.ts`).
- data-sources.spec then passed 11/11, including the 3 steps that had not
  run.

The product limit itself is unchanged: a picker of more than 200
applications truncates. That belongs to the Access Agent's pickers and is
recorded here for them.

## 2026-09-26 — FOUNDATION-P0-24 and FOUNDATION-P0-25: the permission catalog, and system and custom roles

IAM-002/003 and spec §13–17, 21–22, 28, 53.

**FOUNDATION-P0-24, migration `0097_foundation_permission_catalog.sql` (applied):**

- Every stable key gains resource and action (in the specification's
  `<resource>.<action>` vocabulary), product module, label and
  sensitivity. The columns are then **required**, with checks on module,
  sensitivity and the resource/action shape, so no key can exist
  uncatalogued.
- The §28 administrative keys are added:
  - `groups.*`, `roles.*`, `permissions.view`, `access_reviews.*`;
  - `tenant.security.manage`, `authentication.manage`, `mfa.manage`.
- The Tenant Administrator holds all of them. Identity, Security, Auditor
  and Certification Manager roles get their share.
- No key was renamed (Phase 4b decision 1).
- `lib/rbac/catalog.ts` (pure) and `permissionCatalog.ts`.
- `/settings/permissions`: grouped by module with counts, search, module
  and sensitivity filters, each key's system roles. Read-only, gated by
  `permissions.view`.

**FOUNDATION-P0-25, migration `0098_foundation_custom_roles.sql` (applied):**

- Roles gain display name, status, creator, copy source and updated time.
  The actor and source are plain uuids, per the 0096 lesson.
- The specification's system roles are added, with their permissions:
  Agent, Runtime Security and Governance Administrators, and Security
  Analyst. Every system role gets its display name; the keys are unchanged.
- **System role definitions and their permissions are protected by
  trigger**, even against the service role. A migration that changes them
  sets `wonderid.system_roles_change = 'allow'` first.
- Custom roles:
  - never take a system role's name;
  - are unique per tenant (case-insensitive);
  - are never assigned outside their tenant (trigger on `user_roles`).
- **An inactive role grants nothing:** `getTenantContext()` skips it.
  Assigning an inactive role is refused (409 `ROLE_INACTIVE`).
- **No escalation by design** (`lib/rbac/roleRules.ts`): a role gains only
  permissions its designer holds. On edit it may keep what it had, and
  removing is always allowed. Refusals are audited.
- Service `lib/rbac/customRoles.ts`:
  - list, detail (holders, per-module summary), create (from scratch or a
    copy), update, activate/deactivate;
  - delete only when nobody holds the role (409 `ROLE_IN_USE`);
  - every change audited with the added and removed keys.
- `lib/rbac/roles.ts` resolves a role by name among system roles and this
  tenant's custom roles. `listAssignableRoles(tenantId)` includes the
  tenant's active custom roles.
- Assignment accepts `roles.assign` as well as the legacy `role.manage`.
- Screens:
  - `/settings/roles` is now **Roles**: custom and system roles, with
    permission and holder counts. It replaces the old "Users & Roles"
    member table; assignment is on each user's page;
  - `/settings/roles/[id]`: per-module summary bars, permissions by
    module, people, and activate/deactivate/delete for custom roles;
  - `/settings/roles/new` (optionally `?copy=`) and `/[id]/edit`: the
    wizard (basic details, permissions by module with search, select-all
    and collapse, review). Permissions the designer lacks are disabled,
    with the reason.
- API:
  - `GET`/`POST /api/v1/roles`;
  - `GET`/`PATCH`/`DELETE /api/v1/roles/[id]`;
  - `POST /api/v1/roles/[id]/status`.
- Sidebar: "Users", "WonderID Roles", "Permission Catalog".

**Verified:**

- tsc and eslint clean.
- vitest **721/721**, with the new `catalog.test.ts` and
  `roleRules.test.ts`.
- SQL checks, run live:
  - `tests/foundation/permission-catalog-check.sql`: 10/10;
  - `tests/foundation/custom-roles-isolation.sql`: 14/14, fixtures
    removed.
- E2E `permission-catalog.spec.ts` and `custom-roles.spec.ts`, with users,
  branding, shell and navigation smoke: 71 passed.
  - A requester given the custom role can read compliance controls (403 →
    200).
  - Deactivating the role takes that away and activating restores it; an
    inactive role cannot be assigned.
  - A role in use cannot be deleted.
  - System role PATCH 403; a reserved name 400.
  - Another organization gets 404 and cannot assign it; read-only is
    redirected.
  - Edit, then delete once unused.
- Screenshots: Roles, role detail (light 1440; dark 390), and the create
  wizard's permissions step.
- The full suite is recorded in the next entry.

**Left out / handed on:**

- The scope and conditions step and scoped assignments: FOUNDATION-P0-19.
- The groups tab: FOUNDATION-P0-26.
- Custom roles cannot yet include permissions a tenant does not hold at
  all, which is by design.

## 2026-09-26 — Full suite on FOUNDATION-P0-24/25 and the light console (741aabf)

**What ran:** the full Playwright suite (326 tests) against a production
build of `741aabf` — FOUNDATION-P0-22..25, EXPERIENCE-P0-22/23 and the
light-console sidebar. Migrations 0095–0098 were applied; no migration was
applied during the run.

**Result:** 310 passed, 8 failed and 8 did not run (dependants of the
failures in serial blocks).

- All 16 sat in one ten-minute window (tests 134–155, about 10:30–10:40
  UTC).
- The server log shows `TypeError: fetch failed` from the Supabase client
  in that window. The session check in `proxy.ts` failed, so signed-in
  users were treated as signed out:
  - the signed-in help test landed on the landing page;
  - `/agents/new` never rendered its form;
  - the platform tenants API returned no data;
  - design-review page loads aborted.
- The sandbox proxy recorded relay failures over the same minutes.
- This was network egress, not this change.

**Rerun:** the five affected specs (design-review, emergency-controls,
financebot-central-scenario, gateway-enforcement, help) against the same
build: **54/54 passed**.

With the 310 passed in the full run, every test in the suite has passed on
this build. `741aabf` goes to main.

## 2026-09-26 — FOUNDATION-P0-26: groups (WonderID Phase 4b)

**What was built** (IAM-004; spec §11–12, §16–17):

- **Migration 0099** (applied live):
  - `groups`: tenant-owned; name unique per tenant ignoring case; status
    active or inactive.
  - `group_members`: composite foreign keys to `groups(id, tenant_id)`
    and to `tenant_memberships(tenant_id, user_id)`, so a member is always
    in the group's own tenant. `added_by <> user_id`: nobody is recorded
    as adding themselves.
  - `group_roles`: a guard trigger allows only a system role or the
    tenant's own custom role, and refuses a grant by anyone who is in the
    group (SELF_ESCALATION, 42501).
  - RLS: select only, for the tenant's members. Writes go through the
    service.
  - `tenant_user_directory` gains `p_group` (default null, so deployed
    callers are unaffected).
  - Actor columns are plain uuids (the 0096 lesson about PostgREST
    embeds).
- **Effective permissions** come from direct roles plus the roles of the
  user's active groups. `getTenantContext()` reads them in the same
  parallel batch, per request, so joining or leaving a group applies on
  the next request with no cache. Inactive roles and inactive groups grant
  nothing.
- **Service** `lib/users/groups.ts`:
  - list, detail, `groupsOfUser`, create, update, delete;
  - add and remove members;
  - give and take roles.
  - Every write is audited, and refusals are audited as failures.
- **No escalation through groups:**
  - nobody adds themselves;
  - a member cannot give their own group roles;
  - giving a group a role needs `roles.assign` (or `role.manage`);
  - adding people to a group that carries roles needs role assignment
    too, not just `groups.manage_members`.
  - Each rule is checked in the service and again in the database.
- **Removing a member** from the organization also removes them from
  every group.
- **Screens:**
  - `/settings/groups`: list and create.
  - `/settings/groups/[id]`: roles, members, details, delete.
  - User detail:
    - a Groups card;
    - custom and system role badges;
    - inactive roles marked;
    - permissions attributed as "Role (via Group)";
    - group events in the access history.
  - Users list: a group filter.
  - Role detail: a Groups tab.
  - Sidebar: "Groups".
- **A role a group carries cannot be deleted** (409 `ROLE_IN_USE`).
  Deleting it would silently take it from the group's members.
- **API:**
  - `GET`/`POST /api/v1/groups`;
  - `GET`/`PATCH`/`DELETE /api/v1/groups/[id]`;
  - `POST /api/v1/groups/[id]/members`;
  - `DELETE /api/v1/groups/[id]/members/[userId]`;
  - `POST /api/v1/groups/[id]/roles`;
  - `DELETE /api/v1/groups/[id]/roles/[roleId]`.

**Verified:**

- tsc and eslint clean; vitest **721/721**; production build succeeds.
- `tests/foundation/groups-isolation.sql`, run live: **16/16** as
  expected.
  - Another tenant's member or group is refused (23503).
  - Self-add is refused (23514); another tenant's custom role is refused
    (23514).
  - A member granting their own group a role is refused (42501).
  - The directory filters by group (1 of 2).
  - A tenant-A member sees A's groups, members and roles, and none of
    B's.
  - They cannot create a group, add a member or give a role directly
    (42501), cannot delete members (0 rows), and cannot call the
    directory function (42501).
  - Fixtures removed (0 left). Security advisors show nothing new.
- `tests/e2e/groups.spec.ts` (new): created through the screens.
  - The group's role grants real access: `/api/v1/reports` goes 403 →
    200.
  - Removing the member revokes it and re-adding restores it; an inactive
    role grants nothing through a group.
  - Provenance shows on the user page, the users list filters by group,
    and the role page lists the group.
  - Deleting the role is refused while the group carries it.
  - Self-add is 403 SELF_ESCALATION. The Identity Administrator cannot
    add people to a group that carries roles, nor give roles.
  - A member giving their own group a role is 403 SELF_ESCALATION.
  - Other tenants get 404; read-only users are redirected; deleting the
    group revokes the access.
- Targeted run: groups, users, custom-roles, navigation-smoke and shell
  specs. 67 passed and 1 failed. The failure was interference between
  specs:
  - custom-roles and groups ran in parallel, and both toggled
    `compliance.read` for the same requester;
  - the groups spec now probes `report.read`, which no other spec
    toggles;
  - re-run: 17/17.
- **Full suite** on the production build of this change (0099 applied,
  nothing applied during the run): **331/331 passed** in 22.9 minutes.

**Left out / handed on:**

- Group scopes and conditions: FOUNDATION-P0-19. That work is in
  progress, unmerged; migration 0100 is not applied.
- Dynamic (rule-based) membership and nested groups: P1.
- Group owners and access reviews of groups: COMPLIANCE-P0-11.

## 2026-09-26 — FOUNDATION-P0-19: scoped assignments and the authorization engine (WonderID Phase 4b)

**What was built** (spec §18–23, 33–34; re-scoped story):

- **Migration 0100** (applied live, additive):
  - Terms on every role assignment, direct (`user_roles`) and through a
    group (`group_roles`):
    - `scope_type`: `tenant` (the default, kept by every existing row),
      `environment`, `application` or `agent`;
    - `scope_values`;
    - a validity window (`starts_at`, `expires_at`);
    - a condition, `requires_mfa`.
  - The source is DIRECT or GROUP by table. Who assigned it is
    `granted_by`.
  - The `role_assignment_scope_guard` trigger enforces two rules:
    - a scope names only the tenant's own applications and agents;
    - a Tenant Administrator assignment stays organization-wide, permanent
      and unconditional (the last-administrator guard counts rows).
  - `authorization_policies` (DENY or REQUIRE_APPROVAL):
    - covers permission keys or `prefix.*`, in a scope, with exempt roles;
    - RLS select for members; writes by the service;
    - a check constraint means a policy never covers
      `tenant.security.manage`, so a mistaken policy can always be undone;
    - exempt roles and scopes must be the tenant's own.
- **Engine** `lib/rbac/authorizeCore.ts`: pure and deterministic. It
  evaluates in this order: grant validity → permission → scope → MFA
  condition → explicit policies. It returns:
  - ALLOW, DENY or REQUIRE_APPROVAL;
  - reason codes;
  - the grants that allowed it (role, source, group, scope);
  - the grants that did not apply, and why;
  - the policies that decided.
  - Scope rule: a grant narrower than the tenant counts only when the
    check names a resource inside it. A check with no resource counts
    tenant-wide grants only, so a scoped grant never widens into
    tenant-wide access through a route that does not say what it touches.
- **Context:**
  - `getTenantContext()` reads assignments with their terms, group
    assignments and the tenant's active policies in the same parallel
    batch. `permissions` is now "allowed without naming a resource" after
    policies.
  - Unreadable policies fail closed: no permissions.
  - The session's assurance level (`aal`) comes from the verified token.
- **Enforcement:**
  - `requirePermission()` is now a thin call to the engine. A plain
    missing permission is still 403 FORBIDDEN. Policy, MFA and approval
    refusals get their own codes (POLICY_DENIED, MFA_REQUIRED,
    APPROVAL_REQUIRED) and are audited as AUTHORIZATION_DENIED.
  - `requirePermissionFor()` and `requireAnyPermissionFor()` check against
    a named resource. Every per-agent route and action now uses them:
    - owners, owner review, lifecycle, contracts, identities,
      relationships;
    - API keys (create and revoke), revoke-all;
    - the agent page itself.
  - So agent- and environment-scoped grants and policies apply there.
- **Screens and API:**
  - The user page's roles table shows each assignment's terms ("Not in
    effect" when outside its window).
  - "Assign a role" has collapsible scope, timing and conditions; posting
    a held role changes its terms.
  - The group page does the same.
  - Effective-permission provenance counts only assignments in effect, and
    names their scope.
  - New Authorization Policies screen (list, create, edit, activate or
    deactivate, delete). It needs `permissions.view` to see and
    `tenant.security.manage` to change.
  - `POST /api/v1/users/[id]/roles` and `POST /api/v1/groups/[id]/roles`
    take the terms.
  - `/api/v1/authorization-policies` (GET, POST), `[id]` (GET, PATCH,
    DELETE) and `[id]/status`.

**Verified:**

- tsc and eslint clean; vitest **746/746**:
  - new `authorizeCore.test.ts` (15);
  - `assignmentRules.test.ts` (5);
  - `policyRules.test.ts` (5).
- Production build succeeds.
- `tests/foundation/authorization-isolation.sql`, run live: **14/14** as
  expected.
  - Existing assignments are all organization-wide (0 otherwise).
  - A scoped, expiring assignment is accepted.
  - Refused with 23514:
    - a scope pointing at another tenant's application;
    - an unknown environment;
    - a backwards validity window;
    - an expiring Tenant Administrator;
    - a policy over `tenant.security.manage`;
    - a policy exempting another tenant's role, or scoped to another
      tenant's application.
  - A member reads their tenant's policies (1) and not the other's (0).
  - They cannot write a policy (42501), nor deactivate a policy or widen
    their own assignment directly (0 rows).
  - Fixtures removed. Security advisors show nothing new.
- `tests/e2e/authorization.spec.ts` (new, 7 tests). The requester gets a
  throwaway custom role holding only `agent.update`; policies are scoped
  to the spec's own agent, so parallel specs are unaffected.
  - Environment scope: the production agent 201, the development agent
    403, and a check naming no agent 403.
  - Agent scope works the same way.
  - A not-yet-started grant gets 403. An MFA-conditioned grant on an aal1
    session gets 403 MFA_REQUIRED.
  - A past expiry is refused (400), and so is an expiring Tenant
    Administrator (400).
  - Deny policy: 403 POLICY_DENIED for the requester and the admin alike,
    while the other agent is unaffected. The refusal is in the audit trail.
  - Exempting the role lets it through. Require-approval gets 403
    APPROVAL_REQUIRED.
  - Lockout policies are refused (400).
  - Tenant Two gets 404 on the policy. It cannot see the policy, delete it
    or scope an assignment to Tenant One's agent (400).
  - A non-admin cannot create a policy (403).
  - Screens: set an environment scope on the user page and see it shown;
    create a policy through the form, see its scope, delete it.
- Targeted run (authorization, users, groups, custom-roles,
  navigation-smoke): **72/72**.
- **Full suite** on the production build of this change (0100 applied,
  nothing applied during the run): **340/340 passed** in 23.0 minutes.

**Left out / handed on:**

- A generic `resource` scope type, and resource-named checks on
  application routes. Application scope is modelled and evaluated but no
  application route names its resource yet; both follow with
  FOUNDATION-P0-20.
- REQUIRE_APPROVAL refuses the direct action and says approval is needed.
  Routing such actions into the approval engine is P1.
- Other resource checks still count tenant-wide grants, by design. That
  covers emergency controls (tenant-wide kill switch), agent creation and
  relationship removal by id.
- "Why can / why can't" explanations: FOUNDATION-P0-20 (the engine
  already returns the facts).

---

## 2026-10-01 — FOUNDATION-P0-28 / P0-29 / P0-30: compliance permissions, tamper-evident audit trail, IT security hardening

Explicit user request: implement Razorpay and Stripe, GDPR and DPDP, SOX and
other financial compliance, and IT security best practice. These are the
Foundation-owned parts. Platform (billing) and Compliance (privacy,
frameworks) have their own entries.

**Findings that drove the work.**
- `audit_logs` had no client write policy, but any service-role caller could
  UPDATE or DELETE rows, and nothing would show it.
- Sensitive new tables needed role-aware RLS. The existing member-wide pattern
  would let any member read invoices or breach records through PostgREST.
- There was no HSTS/COOP/CORP header, no cross-site check on the JSON API, no
  CI for typecheck/lint/unit tests/dependency audit, no `security.txt`, and no
  way to rotate the encryption key.

**What was built.**
- `0101_foundation_compliance_permissions.sql` adds 6 catalogued keys
  (`billing.view`, `billing.manage`, `privacy.view`, `privacy.manage`,
  `privacy.requests.process`, `privacy.incidents.manage`), granted to Tenant
  Administrator, Governance Admin, Security Admin and Auditor. It uses `set local
  wonderid.system_roles_change` because 0098's guard rejected the first apply.
  It also adds `has_tenant_permission(tenant, key)`: tenant-wide, currently
  valid, active-role grants only, MFA-conditioned grants only on aal2, and
  narrower than `getTenantContext()` by design.
- `0104_foundation_audit_integrity.sql`:
  - `audit_logs.chain_seq/prev_hash/row_hash`, backfilled for all 8,940
    existing rows.
  - The `audit_logs_chain` BEFORE INSERT trigger: a per-tenant advisory lock,
    then SHA-256 over the previous hash and the row's fields.
  - `audit_logs_append_only`: UPDATE is always refused; DELETE is refused
    except through the retention purge or a tenant's own hard-delete cascade.
  - `purge_audit_logs()`: oldest prefix only, never under 365 days, legal holds
    honoured, checkpoint in `audit_log_purges`.
  - `verify_audit_chain()`.
  - `platform_audit_logs` is append-only too; only the FK's set-null on a
    tenant hard delete may touch it.
- `lib/audit/integrity.ts` + `GET /api/v1/audit/integrity` + `/audit/integrity`
  (audit.read). The verification itself is audited.
- `lib/rbac/permissionHolders.ts`: notification recipients for one tenant.
  It never decides authorization.
- `lib/security/redact.ts`: key deny-list, secret shapes, Luhn card numbers,
  bounded depth and size.
- `lib/security/encryptSecret.ts` key rotation via
  `SECRET_ENCRYPTION_KEY_PREVIOUS` and `reencryptSecret()`. The existing format
  is unchanged.
- `lib/security/origin.ts` `isCrossSiteApiWrite()`, wired into `proxy.ts`
  before any session work.
- `next.config.ts`:
  - New headers: HSTS 2y with preload, COOP/CORP same-origin,
    `X-DNS-Prefetch-Control: off`, `X-Permitted-Cross-Domain-Policies: none`,
    and a wider Permissions-Policy.
  - CSP gains `frame-src 'none'`, `object-src 'none'` and a `form-action`
    allow-list for the payment providers' hosted pages.
  - `poweredByHeader: false`.
  - `upgrade-insecure-requests` was tried and dropped: it risks breaking the
    http://localhost E2E server, and HSTS covers production.
- `public/.well-known/security.txt`, excluded from the proxy matcher so it is
  public. `.github/workflows/security.yml` runs typecheck, lint, unit tests,
  `npm audit --omit=dev --audit-level=high`, and a committed-secret grep.

**Verification.**
- `verify_audit_chain()` on the three live tenants with audit rows: intact
  (8,287 / 609 / 44 rows).
- Rolled-back tamper test on the live project:
  - A new row chained to seq 45 with a matching prev hash.
  - UPDATE, DELETE, a purge inside 365 days, and a `platform_audit_logs`
    update were all rejected.
  - With the trigger disabled, an altered row was found at its exact
    sequence ("row content does not match its hash").
- `tests/compliance/billing-privacy-tenant-isolation.sql`: 28/28 checks as
  expected (rolled back, verified clean).
- Unit tests: `redact` 5, `origin` 4, `encryptSecret` rotation 1, full suite
  797/797.
- `next build` succeeded. Header and route behaviour was checked against a
  built server: `curl -I` shows HSTS/COOP/CORP/CSP and no `X-Powered-By`; a
  cross-origin POST to `/api/v1/billing/checkout` returns 403; security.txt is
  served signed-out.
- eslint is clean on the whole repo.
- Security advisors after the migrations raise nothing new beyond the expected
  ones:
  - INFO "RLS enabled, no policy" on the vendor-only billing tables, the same
    pattern as `platform_*`.
  - WARN `has_tenant_permission` executable by authenticated. This is
    intended: RLS calls it, and it only answers about the caller themself.

**Not done / handed on.**
- Supabase Auth leaked-password protection is still OFF (advisor WARN). It is a
  dashboard setting this session cannot change; the project owner must enable
  it.
- CSP `'unsafe-inline'` scripts remain, for Next's bootstrap. Per-request
  nonces in `proxy.ts` are the follow-up.
- The full Playwright suite was not run in this session. The proxy, headers
  and RLS changed, so CLAUDE.md §17.8 requires the full suite before release.
  It is the first thing for the next session or CI.
- `security.txt` has a placeholder contact (`security@wonderid.example`). The
  owner must set the real one.

### 2026-10-01 (later) — critical Next.js advisory patched; new CI workflow verified locally

Running the new security workflow's checks locally found one failure.
`npm audit --omit=dev --audit-level=high` reported a **critical** advisory,
GHSA-vcvr-r3jv-pc5j (remote code execution in `next/og` `ImageResponse`,
`>=16.2.0 <16.3.6`), against the pinned `next@16.3.5`. The app does not import
`next/og`, so it was not directly exposed. `next` and `eslint-config-next`
were bumped to the non-breaking patch release **16.3.8**; the lockfile changed
50 lines.

After the bump, every check in `.github/workflows/security.yml` was run
locally:
- `npm audit` exits 0 and the secret scan finds nothing.
- typecheck is clean except the 8 existing `app/welcome` image-module errors,
  which a fresh clone without a build always shows; `next build` generates the
  types.
- eslint is clean and vitest is 797/797.
- `next build` passes on Next.js 16.3.8.
- A built-server smoke test passed: `/welcome` 200 with HSTS/COOP/CSP and no
  `X-Powered-By`, a cross-site POST to `/api/v1/privacy/requests` is 403, and
  the trust section renders.

The typecheck step needed a fix. `next-env.d.ts` is gitignored, so on a fresh
checkout typecheck reported 8 errors (verified: with the file removed, 8; after
`npx next typegen`, 0). The workflow now runs `npx next typegen` before
`npm run typecheck`.

---

## 2026-10-02 — Google sign-up / sign-in: readiness check and two safe-failure fixes

User request: make sure Google sign-up and sign-in work, and list what the
owner must do.

**Finding.** The code path is correct: `GoogleAuthButton` calls
`signInWithOAuth({ provider: "google" })` with PKCE, back to `/auth/callback`,
which exchanges the code. A user who already belongs to an organization lands
on `/`; a new user lands on `/onboarding`. It cannot work yet only because
Google is **disabled on the Supabase project**:
- `GET /auth/v1/settings` returns `external.google: false`.
- `/auth/v1/authorize?provider=google` returns 400 "Unsupported provider:
  provider is not enabled".
- Because `signInWithOAuth` just navigates to that URL, users saw a raw JSON
  error page.

**Fixes (code).**
- `modules/ui/GoogleAuthButton.tsx` (Experience-owned UI primitive):
  - Before redirecting, the button reads Supabase Auth's public settings
    (publishable key, 3 s timeout).
  - If Google is disabled, it shows "Google sign-in is not enabled for
    WonderID yet…" and stays on the page.
  - If the check cannot be made, the redirect proceeds and Supabase stays the
    authority. This is a UX guard only, never an authorization decision.
- `app/auth/callback/route.ts`:
  - A round trip that returns without a session is no longer a silent bounce.
    The causes are `?error=…` from Google/Supabase or a failed code exchange.
  - `/sign-in` now gets a fixed `reason` code: `oauth_cancelled` for
    `access_denied`, otherwise `oauth_failed`. `SignInForm` shows a matching
    notice.
  - The provider's `error_description` is never reflected (§17.2).
  - Behaviour with a valid session, `?next=`, SSO JIT provisioning and the
    recovery flow is unchanged.

**Verification.**
- `tsc --noEmit`: 0 errors. eslint: clean. Vitest: 806/806 (104 files),
  including 5 new `GoogleAuthButton` tests and 4 new `signInFailureReason`
  tests.
- `tests/e2e/auth.spec.ts`:
  - The existing Google test now stubs the settings answer. It also fulfills
    (rather than aborts) the authorize request; an abort raced the next
    `page.goto` (3/6 failures before the change, 0 after).
  - Two new tests: the disabled-provider message, and the callback error path,
    covering cancelled, failed, provider text not reflected, and a bad code.
  - The three Google tests ran 5× against a local production build: 15/15.
- Against the real dev project's settings payload (`google: false`), in
  Chromium light and dark, on /sign-in and /sign-up: the message appears in
  under 110 ms, the URL is unchanged and the button stays enabled.
- In this sandbox Chromium cannot complete the cross-origin settings GET
  through the TLS-intercepting proxy, although the preflight succeeds. curl
  confirms Supabase returns the right CORS headers for `agent.wonderapps.biz`.
  The 3 s timeout fallback was observed working there.
- **Not run:** the full Playwright suite (§17.8 lists auth changes). The
  repository has no `SUPABASE_SERVICE_ROLE_KEY` here, so auth setup cannot run.
  The diff is confined to the no-session branch of the callback and the
  Google button.
- **Not verified:** a real Google login. It needs the provider enabled.

**Owner steps to enable Google** (dashboard settings, not code):
1. Google Cloud Console → APIs & Services:
   - OAuth consent screen (External; app name WonderID; support email;
     authorized domain `wonderapps.biz`; scopes `openid`, `email`,
     `profile`).
   - Then Credentials → Create OAuth client ID → Web application.
   - Authorized JavaScript origins: `https://agent.wonderapps.biz`.
   - Authorized redirect URI:
     `https://ekgyjwoenteadaaqakmd.supabase.co/auth/v1/callback`.
2. Supabase → Authentication → Sign In / Providers → Google: enable it and
   paste the Client ID and Client Secret.
3. Supabase → Authentication → URL Configuration:
   - Site URL `https://agent.wonderapps.biz`.
   - Redirect URLs `https://agent.wonderapps.biz/auth/callback`,
     `https://wonder-agent-tau.vercel.app/auth/callback`,
     `https://*-luvchakras-projects.vercel.app/auth/callback` (previews) and
     `http://localhost:3000/auth/callback`.
4. Publish the consent screen; in "Testing" only listed test users can sign in.

---

## 2026-10-02 — Microsoft and LinkedIn sign-up / sign-in; SSO JIT restricted to SSO sign-ins

User request: make sure Microsoft and LinkedIn sign-up and sign-in work, and
list what the owner must do.

**Finding.**
- Neither provider existed in the code: only Google had a button.
- Both are disabled on the Supabase project (`azure: false`,
  `linkedin_oidc: false`; `/auth/v1/authorize` returns 400 "provider is not
  enabled").
- **Security issue found while reviewing the callback:** `/auth/callback`
  just-in-time provisioned membership of whichever organization had an
  active SSO connection for the user's email domain, *however the user
  signed in*. With social sign-in that is a cross-tenant path
  (non-negotiables #2, #4). A Microsoft work account's `email` claim is not
  verified (the "nOAuth" attack), and even a verified Google/LinkedIn
  address bypasses the organization's IdP controls. The issue predated this
  change (Google); adding Microsoft made it exploitable in practice.

**Changes.**
- `modules/ui/SocialAuthButtons.tsx` replaces `GoogleAuthButton.tsx`:
  - The same provider-enabled guard and timeout for Google, Microsoft
    (Supabase provider `azure`, with the `email` scope Microsoft needs) and
    LinkedIn (`linkedin_oidc`).
  - Brand marks per each provider's guidance.
  - Used on /sign-in (still hidden on tenant addresses) and /sign-up.
- `app/auth/callback/route.ts`:
  - New `isSsoAuthenticated(user)`: true only for an `sso:` identity.
    Supabase never links SSO identities to other accounts.
  - SSO JIT provisioning now runs only when it holds. A social sign-in on an
    SSO domain falls through to the normal path: existing memberships go to
    `/`, otherwise `/onboarding`.
  - The failure notices are now provider-neutral.
- Copy updated: the Get Help sign-in article (also states that only SSO
  auto-joins an organization) and the landing page security card.

**Verification.**
- `tsc --noEmit`: 0 errors. eslint: clean. Vitest: 812/812, including 8
  `SocialAuthButtons` tests and 3 `isSsoAuthenticated` tests.
- E2E (`auth.spec.ts`), 3 social tests run 4× against a local production
  build: 12/12. They check:
  - every button on both screens reaches `/auth/v1/authorize` with the right
    `provider`, the `/auth/callback` return and Microsoft's `email` scope;
  - the disabled messages;
  - the callback error paths.
- Against the real dev settings payload, at 1280 and 390 px, light and dark:
  all three buttons render, the Microsoft/LinkedIn messages appear, the URL
  is unchanged and there is no overflow.
- **Not run:** the full Playwright suite (no service-role key here) and any
  real provider login (the providers are disabled). SSO JIT has no E2E
  coverage because SAML is not enabled on the project.

**Owner steps — Microsoft** (Supabase provider "Azure"):
1. Azure portal → Microsoft Entra ID → App registrations → New registration.
   - Name: WonderID.
   - Supported accounts: "Any organizational directory and personal
     Microsoft accounts".
   - Redirect URI (Web):
     `https://ekgyjwoenteadaaqakmd.supabase.co/auth/v1/callback`.
2. Copy the Application (client) ID.
3. Certificates & secrets → New client secret. Copy its **Value** and diary
   its expiry (24 months maximum).
4. Token configuration → Add optional claim → ID token: `email` and
   `xms_edov`. Supabase uses the latter to trust the email.
5. Optionally complete publisher verification, so users don't see
   "unverified".
6. Supabase → Authentication → Providers → Azure: enable it and paste the ID
   and secret. Leave Tenant URL empty (common), or set
   `https://login.microsoftonline.com/<tenant-id>` to restrict sign-in to one
   directory.

**Owner steps — LinkedIn:**
1. linkedin.com/developers → Create app. This needs a WonderID LinkedIn
   Company Page, a logo and a privacy-policy URL. The page admin verifies the
   app.
2. Products → add "Sign In with LinkedIn using OpenID Connect".
3. Auth → Authorized redirect URLs:
   `https://ekgyjwoenteadaaqakmd.supabase.co/auth/v1/callback`. Copy the
   Client ID and Primary Client Secret.
4. Supabase → Providers → **LinkedIn (OIDC)**, not the deprecated
   "LinkedIn": enable it and paste the ID and secret.

The Supabase URL Configuration (Site URL and redirect URLs) is the same as in
the Google entry above.

---

## 2026-10-02 — Social sign-in readiness re-check via the Supabase MCP connection

User request: re-check Google/Microsoft/LinkedIn now that Supabase is
connected over MCP. No code changed. The MCP server exposes no Auth-config
tool, so it can **read** state (project, logs, advisors) but cannot enable
providers or edit URL settings. The OAuth client IDs and secrets have to come
from Google Cloud, Microsoft Entra and LinkedIn in any case.

**Findings (project `ekgyjwoenteadaaqakmd`, ACTIVE_HEALTHY).**
- **All three providers are still disabled.** `/auth/v1/settings` reports
  `google`, `azure` and `linkedin_oidc` all `false`. `auth_logs` shows every
  `/authorize` attempt today returning 400 "provider is not enabled".
- **The Site URL and redirect allow-list cover only
  `wonder-agent-tau.vercel.app`.**
  - Method: `/authorize` was probed with chosen `redirect_to` values, and the
    `referer` GoTrue logged for each (the address it would actually return
    to) was read back.
  - Allowed: `https://wonder-agent-tau.vercel.app/auth/callback`, including
    with a query string, so the entry is a wildcard.
  - Replaced by the Site URL `https://wonder-agent-tau.vercel.app/`:
    `https://agent.wonderapps.biz/auth/callback` (with or without `?next=`),
    the Vercel preview URL and `http://localhost:3000/auth/callback`.
  - Consequences on the production domain `agent.wonderapps.biz`:
    - **Password reset is broken today.** `requestPasswordResetAction` builds
      `redirectTo` from the request host, so its emailed link returns to the
      `tau` root without reaching `/auth/callback`.
    - Social sign-in would fail the same way once enabled: the PKCE verifier
      cookie lives on the other domain.
  - No code change can fix this. The owner must set the Site URL to
    `https://agent.wonderapps.biz` and add `https://agent.wonderapps.biz/**`
    (plus the tau, preview and localhost entries) to Redirect URLs.
- **Security advisor:** no new issues.
  - `auth_leaked_password_protection` is still off; the owner turns it on in
    the dashboard.
  - The remaining lints are long-standing and intentional:
    - service-role-only tables (RLS enabled with no client policies);
    - `current_tenant_ids`, `has_tenant_permission` and
      `create_tenant_with_owner`, executable by signed-in users by design;
    - `resolve_tenant_host`, executable by `anon` for host-based tenant
      resolution before sign-in.

---

## 2026-10-09 — Google sign-in verified on production (`id.wonderapps.biz`)

User request: check Google sign-in now that the Google OAuth client and the
Supabase provider are configured. No code changed. All checks were read-only,
used only the publishable key, and printed no secret.

**What was checked and found.**
- **Provider enabled.** `/auth/v1/settings` reports `external.google = true`
  (with `email`). Microsoft (`azure`) and LinkedIn are still off; their
  buttons show the "not enabled yet" message (SocialAuthButtons' settings check).
- **Supabase → Google.** `/auth/v1/authorize?provider=google` returns 302 to
  `accounts.google.com` with the configured web client, `redirect_uri`
  `https://ekgyjwoenteadaaqakmd.supabase.co/auth/v1/callback`, and scope
  `email profile`. Following it reaches Google's account chooser with no
  `redirect_uri_mismatch`, `invalid_client` or "Access blocked" error, so the
  Google Console redirect URI and client credentials match.
- **Return address allow-list** (method as on 2026-10-02: probe `redirect_to`
  and read GoTrue's logged `referer` in `auth_logs`):
  - Site URL is now `https://id.wonderapps.biz`.
  - Accepted: `https://id.wonderapps.biz/auth/callback`, including
    `?next=/update-password`. Password reset links and social sign-in return
    correctly on production.
  - Replaced by the Site URL: `wonder-agent-tau.vercel.app`, Vercel preview
    URLs, `localhost:3000`, `agent.wonderapps.biz` (now 404, no longer the
    production domain) and an arbitrary external host.
- **Production domain.** The Vercel project `wonder-id` serves
  `id.wonderapps.biz` (verified) and `wonder-agent-tau.vercel.app`. No
  application code references the old `agent.wonderapps.biz`.
- **End to end in a browser.** Headless Chromium on
  `https://id.wonderapps.biz/sign-in` → "Sign in with Google" lands on Google's
  sign-in page with `redirect_to=https://id.wonderapps.biz/auth/callback`, and
  the PKCE code-verifier cookie is set on `id.wonderapps.biz`, which is what
  `/auth/callback`'s `exchangeCodeForSession()` needs. The final step (a real
  Google account consenting) needs a human and was not performed.
- **CSP.** Not affected: OAuth is a top-level navigation, not a form post or
  fetch to Google; `connect-src` already allows `https://*.supabase.co`.

**Optional owner settings (not blockers).**
- Google's consent screen names the app `ekgyjwoenteadaaqakmd.supabase.co`.
  Showing "WonderID" needs a Supabase custom auth domain (e.g.
  `auth.wonderapps.biz`) plus that domain's callback in the Google client's
  redirect URIs.
- To use Google sign-in on the tau URL, previews or localhost, add
  `https://wonder-agent-tau.vercel.app/**`,
  `https://*-luvchakras-projects.vercel.app/**` and `http://localhost:3000/**`
  to Supabase Redirect URLs. Without them those hosts return to production.
- While the Google consent screen is in "Testing", only listed test users can
  sign in. Publish it for general use.
- Vercel has no `APP_BASE_URL`. Billing return URLs need it
  (`https://id.wonderapps.biz`). This does not affect sign-in.

**Follow-up the same day: the first real sign-in failed at the code exchange.**
- The owner's first real attempts (19:20:51 and 19:21:03 UTC) returned to
  `/sign-in?reason=oauth_failed`.
- `auth_logs` shows `/callback` failing with
  `oauth2: "invalid_client" "The provided client secret is invalid."`.
- The client ID and redirect URI are accepted, so the Client Secret saved in
  Supabase's Google provider does not match the client. The app's handling is
  correct: no session is created and the reason is shown.
- Fix (owner, in the dashboards): generate a new client secret on that Google
  OAuth client and paste it into Supabase → Authentication → Providers →
  Google.

**Resolved the same day: Google sign-in works end to end on production.**
- After the owner replaced the client secret, `auth_logs` at 19:24:27 UTC
  shows `/callback` 302 with `user_signedup` (provider `google`), then
  `/token` 200 with `grant_type: pkce` and `login`. The PKCE exchange in
  `/auth/callback` completed and a session was issued.
- `https://id.wonderapps.biz/sign-in` renders "Sign in with Google" (and
  Microsoft, LinkedIn and SSO). `/sign-up` shows the same buttons.
- By design, the social buttons are hidden on an organization's own
  address (`<slug>.<BASE_APP_HOST>`, FOUNDATION-P0-22), because Supabase's
  redirect allow-list holds only `https://id.wonderapps.biz`. Showing them
  there would need `https://*.id.wonderapps.biz/**` in Supabase Redirect
  URLs and a code change in `app/sign-in/SignInForm.tsx`. Not done; waiting
  for the owner to decide.
- No code changed. Read-only checks: production page fetch, Supabase
  `auth_logs` query.

---

## 2026-10-09 — Sign-up lands in the product: automatic first organization, and renaming it

User request (after confirming Google sign-in works): remove the "Create a
new organization" screen that followed sign-up.

**What changed.**
- **Migration `0107_foundation_first_organization.sql`** (applied to the dev
  project) adds `create_first_tenant_for_current_user(name, slug)`. It wraps
  `create_tenant_with_owner()` (0008) with two checks, made in the database:
  - A per-user `pg_advisory_xact_lock` makes the check-and-create atomic, so
    a double redirect or two tabs still produce exactly one organization.
  - It returns null, creating nothing, when the account has any membership
    row (active, invited, suspended or removed) or is a platform
    administrator. Invited people still choose on `/onboarding`. Removed
    people are not silently given a new organization. Platform
    administrators hold no tenant by design (non-negotiable #3).
  - It runs as the caller (`auth.uid()`), never a service role. Execute is
    revoked from `public` and `anon`.
- **`/onboarding/start`** (new page) is where the customer layout and
  `/auth/callback` now send a signed-in person with no organization.
  - It calls `ensureFirstOrganization()` (`lib/tenant/firstOrganization.ts`,
    session client, audit `tenant.created` with `automatic: true`), then
    hands over with a full page load (`EnterOrganization`, a "Setting up …"
    status).
  - Anything else goes to `/onboarding`, which keeps invitations and the
    manual form; the workspace switcher's "Create new organization" link
    still points there.
  - Two bugs found and fixed while building it:
    - A route handler did not work: the layout's redirect happens during
      client navigation, which does not follow a route handler's redirect.
    - A plain `redirect("/")` after creating looped `/ ⇄ /onboarding/start`
      inside the client router cache, which still held the
      pre-organization redirect.
- **Naming** (`lib/tenant/organizationName.ts`, pure, unit-tested):
  - A company address names the company: `ava@acme-corp.co.uk` → "Acme Corp".
  - A personal address (Gmail, Outlook, iCloud, …) names the person:
    "Ava's organization", from the provider's full name, else the address.
  - `slugify` moved here from `app/actions/tenant.ts`; the manual create
    action reuses it, caps the name at 80 characters, and now also writes a
    `tenant.created` audit event.
- **Rename**: a new Organization card on Administration (`/settings`).
  - People with `tenant.settings` (Tenant Administrator) see a name form:
    `renameOrganizationAction` → `renameOrganization()` in
    `lib/tenant/organization.ts`.
    - It uses the service role (`tenants` has no client UPDATE policy).
    - The write is pinned to the session's tenant and to `status = 'active'`.
    - The name is trimmed to 2–80 characters.
    - It writes a `tenant.renamed` audit event with the old and new names.
    - The slug (the organization's address) never changes.
  - Everyone else sees the name read-only.
  - The "Tenant Settings administration screens are not yet available" line
    was removed.

**Verified.**
- `tsc`, eslint on the changed files, and `npm run build`: clean.
- Vitest: 106 files, 829 tests passed, including the 4 new naming tests.
- `tests/foundation/first-organization.sql`, run live: 9/9 as expected.
  - A new account gets 1 organization, and a second call creates none.
  - It is Tenant Administrator of it.
  - The invited, suspended and platform-admin accounts get none.
  - `anon` is refused with 42501.
- The two cleanup calls for that test were cancelled, so its fixture rows
  remain: tenants with slugs `fixture-a107` and `fixture-new-107-aaaaaa`, and
  the four `fixture-*107@example.test` accounts. The cleanup statements are at
  the end of the SQL file.
- Playwright `first-organization.spec.ts` (new) together with
  `users.spec.ts`, `auth.spec.ts` and `welcome.spec.ts`: 53/53. The new spec
  covers:
  - a password sign-in by a brand-new account lands on Overview in "Wonderagent";
  - a repeat visit to `/onboarding/start` creates nothing;
  - rename, with both audit events;
  - a too-short name refused by the server;
  - a read-only member sees no rename form.
  
  The invited-person (`users.spec`) and platform-admin (`auth.setup`) paths
  still reach `/onboarding`.
- Security advisor: one new expected WARN, that signed-in users can execute
  `create_first_tenant_for_current_user`. It is intended, like
  `create_tenant_with_owner`. No other change.

## 2026-10-10 — Proxy matcher: the web app manifest is public (EXPERIENCE-P0-26)

Cross-module change for Experience's installable app. Browsers fetch the
web app manifest without cookies, so behind the session check
`/manifest.webmanifest` redirected to `/sign-in` and the app could never be
installed. The matcher in `proxy.ts` now excludes `manifest.webmanifest`,
beside the site icons and `brand/`; nothing else changed. The manifest
holds no tenant or user data (name, colours, icon paths, its own URL), and
the app icons were already public under `brand/`. No CSP or header change:
`default-src 'self'` and `img-src 'self'` already cover the manifest and
icons.

Verified: `proxy.test.ts` has two new matcher tests
(`unstable_doesMiddlewareMatch`): the manifest and icons skip the proxy;
`/`, `/sign-in`, `/agents`, `/platform-admin`, `/api/v1/search` and
`/manifest` still run it. 12/12 pass. Because §17.8 lists `proxy.ts`, the
affected E2E specs (`auth`, `navigation-smoke`) should be run by hand or
checked in the next nightly; they were not run here (they need
service-role secrets).

### 2026-10-10 — Leaked-password protection: won't do (owner decision)

The owner decided Supabase Auth's leaked-password protection stays off. It
is no longer an open item. The security advisor's warning for it is
accepted. CLAUDE.md §18.1 and `docs/security/SECURITY-CONTROLS.md` now say
so.

### 2026-10-10 — Google sign-in enabled; `security.txt` contact set (owner)

**Google sign-in: closed.** The owner set up the Google sign-in steps
recorded above, so the item is closed:
- a Google OAuth client;
- the Google provider turned on in Supabase;
- the redirect URLs.

**`security.txt`:** filled in with the owner's details (`public/.well-known/security.txt`).
- `Contact` is `mailto:connect@wonderapps.biz`, given by the owner.
- `Policy` and `Canonical` now point at the production domain,
  `id.wonderapps.biz`; they were `wonderid.example` placeholders.
- `Expires` stays 2027-10-01, under a year away.
- `docs/security/SECURITY-CONTROLS.md` no longer lists the contact as an
  owner action.

## 2026-10-10 — Record provenance on every object (migration 0115)

**Why.** Owner request: "show created by, updated by, create date, update
date in all the objects including the ones above related to the
connections, add this rule in claude.md, run it for all such objects." The
rule is CLAUDE.md §19.10; the Definition of Done (§12) gained a bullet.

**What changed.**
- `supabase/migrations/0115_foundation_record_provenance.sql`: 66 object
  tables across every module gain `created_at`, `updated_at`, `created_by`,
  `updated_by` (`add column if not exists`; existing columns are kept) and
  the `record_provenance` before-insert/update trigger. `current_actor_id()`
  returns `auth.uid()`, or on a service-role request the
  `x-wonderid-actor` header when it is a UUID; the trigger never rewrites
  `created_*`, and a caller that sets `updated_by` itself keeps it. The two
  functions are SECURITY INVOKER; `current_actor_id()` is executable by
  `authenticated` and `service_role` only, the trigger function by nobody
  directly. Append-only, event, run and snapshot tables are excluded (list
  in the header). Applied to the dev project with the MCP tool (the first
  version, with `drop trigger if exists`, was refused as destructive; the
  trigger is now created only when missing).
- `lib/security/actorHeader.ts`: `ACTOR_HEADER`, `currentActorId()` (the
  request's session user, null outside a request) and `actorAwareFetch()`,
  which `supabaseServiceRole()` now uses (`global.fetch`) so every
  service-role write names the acting user without touching the 78 call
  sites.
- `lib/provenance/tables.ts` (the table list, typed), `tables.test.ts`
  (equals the migration's list; excludes the append-only tables) and
  `recordProvenance.ts` (`getRecordProvenance(tenantId, table, id, key)`:
  reads as the user under RLS and by tenant; names from `users` via the
  service role for the two ids only; "A former member" when gone).
- `tests/foundation/record-provenance.sql`: seven checks.
- `tests/architecture/connector-boundary.test.ts`: `lib/security/actorHeader.ts`
  joins the outbound allowlist, with the same reasoning as `lib/ai/provider.ts`
  and the email provider: it is the Supabase client's own transport to
  WonderID's database, not a call to an organization's system. Non-negotiable
  #20 says widening an allowlist needs the owner's approval; it is flagged in
  the pull request for that.

**Verified.**
- `tests/foundation/record-provenance.sql` on the dev project: 7/7 true
  (job write unnamed; header names the actor; malformed header ignored;
  update keeps `created_*` and sets `updated_by`; `created_*` cannot be
  rewritten; explicit `updated_by` kept; a signed-in user's id wins over a
  header naming someone else).
- Advisors after the migration: nothing new; the pre-existing items are
  unchanged.
- `lib/provenance` unit tests 2/2; typecheck and eslint clean.

**Left out.** The columns are not foreign keys (a former member must not
block a write) and are not indexed (nothing queries by them). Lists do not
show provenance (§19.5); only object pages do. The experience log records
the page work; the integration log the connection pages.

## 2026-10-10 — Global Configuration: versioned organization settings; session timeouts per organization

**Why.** Owner request: "under admin, create a global config, it should
[have] many key settings that control entire app behavior, study deeply and
implement". CLAUDE.md §19.11 records the rules.

**Study.** Every hard-coded behaviour constant was inventoried. Most are
technical safety limits (file sizes, row caps, provider timeouts) and stay
in code. The business rules an organization would want to set were kept,
each confirmed to be read by running code: session idle and absolute
timeouts (proxy.ts), the dormant-account threshold, the duplicate-agent
match threshold, the unregistered-activity window, the runtime-alert
throttle, the credential rotation age and key count, the high-risk campaign
score and the Control Center's SoD window. The control-evidence cadence
(90 days) was left out: `recomputeStaleControlMappings()` is never called, so
the setting would do nothing. `tenant_settings.settings` existed since 0001
but nothing read it.

**What changed (Foundation).**
- `lib/config/registry.ts` (pure): the ten settings, defaults equal to the
  previous behaviour, bounds, permissions (sessions need
  `tenant.security.manage`, the rest `tenant.settings`), `resolveConfig()`,
  `planConfigChange()` (all-or-nothing; per-setting permission).
- `lib/config/tenantConfig.ts`: `getTenantConfig()` (per request, service
  role pinned to the tenant, defaults on failure), `updateTenantConfig()`,
  `restoreTenantConfigVersion()`, `listTenantConfigVersions()` (as the
  member under RLS); audit `tenant.config_updated` / `tenant.config_restored`.
- Migration `0116_foundation_tenant_config.sql`: `tenant_config_versions`
  (RLS select for `tenant.settings` or `tenant.security.manage`; no client
  writes; append-only trigger that lets a deleted organization's rows go),
  `save_tenant_config()` (service role only; locks the tenant row; refuses a
  stale version with 40001; writes the version and the current values in
  one transaction), `my_session_policy()` (the caller's strictest active
  organization, clamped to 5–30 minutes and 1–12 hours, defaults when unset).
- `lib/tenant/sessionSecurity.ts`: `SessionLimits`, `sessionLimitsFrom()`;
  `checkSessionExpiry()` takes limits and never exceeds the global ones.
- `proxy.ts`: reads `my_session_policy()` per user, cached 60 seconds in a
  bounded per-user map; a failed read applies the global limits.

**Security.** Session settings can only shorten sessions. The policy is read
with the member's own session (the function keys on `auth.uid()`); the cache
is per user and holds only two numbers. The new advisor note on
`my_session_policy()` (signed-in users can execute a SECURITY DEFINER
function) is intended, like `current_tenant_ids()`. No secret is stored.

**Verified.**
- `tests/foundation/tenant-config-isolation.sql` on the dev project: 12/12
  (version 1 first; stale save refused 40001; values stored; history
  rewrite refused; admin reads own history, not another organization's; a
  member can neither call `save_tenant_config()` nor write history (42501);
  a read-only member reads none; strictest of two organizations 10 min/4 h;
  a single organization's limits; out-of-range clamped and unset default).
- Unit tests: `lib/config/registry.test.ts`, `sessionSecurity.test.ts`
  (limits), plus the touched modules: 447 passed.
- Supabase security advisors: only the intended note above is new.
- Local Playwright: see the Experience log.

**Left out.** SSO-required and MFA-required, the certification interval, AI
agent defaults and audit retention (the rest of FOUNDATION-P0-27); the
declarative configuration objects, draft/simulate/approve and environment
promotion (the rest of PLATFORM-P0-13).

### 2026-10-10 — Browser run for Global Configuration; stale auth tests fixed

Local Playwright on a fresh build: `global-configuration`, `auth`,
`authorization`, `tenant-address`, `shell`, `navigation-smoke` and
`account-inventory`: 111 of 114 passed. The three failures were not from
this change and are fixed in it:
- `auth.spec.ts` "each button really starts its OAuth flow" and "when a
  social provider is not enabled…" still expected the behaviour before #31,
  which shows a provider that is not switched on as disabled ("Not available
  yet"); the sign-in page reads that on the server, so the browser stub did
  not apply. They now check that every enabled button starts its flow
  (sign-up stubbed enabled; sign-in per the real project) and that a
  provider that is off is disabled and never leaves the app. 3/3 passed.
- `auth.spec.ts` "a REQUESTER … can view agents" and `agents.spec.ts`
  looked up the heading "AI Agents", which since #38 also names the open
  area menu in the sidebar; they now target the page title (level 1).
  15/15 passed.
One later local setup sign-in stalled on the sign-in page (auth
rate-limiting after many local runs this hour); the tests that need no
signed-in user were run without it.

### 2026-10-11 — Security note: `wonderapps_dashboard` role (found, not changed)

While checking advisors after migration 0121, the performance advisor listed
`wonderapps_dashboard_read` policies. On inspection:
- `wonderapps_dashboard` is a role that can sign in;
- it has `SELECT ... USING (true)` on about 24 customer tables
  (access_requests, accounts, identities, audit_logs, risk_findings,
  tenants and others);
- it can therefore read every organization's rows in them.

No migration in this repository creates the role or the policies.
Non-negotiables #4 and #13 apply. Nothing was changed, because who uses it
is unknown. It is recorded as an open owner action in
`docs/WonderID/progress/PROGRESS.md`.

### 2026-10-11 — FOUNDATION-P0-32: bulk invitation and the invitation API (#68)

**What was built.**
- **Bulk invitation from CSV, through the connector framework**
  (non-negotiable #20). Users → Actions → Import CSV… previews a file of
  people (`email`, `displayName`, `roles`, optional `accountType` and
  `authMethod`). Each row is:
  - **new**: an invitation will be sent;
  - **already a member**: left as is, including yourself;
  - **invalid**, with the reason: bad e-mail, no name, unknown role, role
    management missing, a role beyond your own permissions, or the same
    e-mail earlier in the file.

  Confirm invites exactly the new rows, one by one, through `inviteUser`
  (each audited `user.invited`). The same file again invites nobody, so
  sending is idempotent on e-mail. The file is a `member` upload of the
  File imports connection (Integration Agent, migration 0125). Foundation
  decides and applies (`planMemberInvitations`, `applyMemberInvitations`
  in `lib/users/users.ts`). Users → Actions → Export CSV lists the members
  in the same columns.
- **`POST /api/v1/users/invitations`**: `{ invitations: [...], dryRun? }`,
  at most 500. It makes the same decisions as the CSV path; `dryRun`
  returns the plan and sends nothing. It needs `users.invite` in the
  signed-in session's organization. The automation credential for scripts
  comes with FOUNDATION-P0-31 (§8.2 of the foundation design), which waits
  on D11. The route is written so that credential only changes how the
  caller is resolved.
- **No escalation.** `inviteUser` (single and bulk) refuses roles that
  carry a permission the inviter does not hold (`invitationEscalation`;
  audited `user.invited` failure with the missing permissions). Giving
  roles at all still needs `roles.assign` or `role.manage`.
  - Found and fixed on the way: an invitation granted only *system* roles.
    A custom role chosen in the wizard was silently not granted. It now
    resolves the organization's own custom roles as well.
- **Expiry, re-send, revoke.**
  - **Expiry.** An invitation expires after Global Configuration → Members
    → "Invitations expire after" (`users.invitationExpiryDays`, 1–90 days,
    default 30). Before this, invitations never expired.
  - **Accepting.** `acceptInvitation` refuses an expired invitation (410
    `INVITATION_EXPIRED`, audited). It accepts only the invitation it
    checked: a re-send in between starts a new one. The onboarding and
    no-access pages show "Expired" and offer no Accept button.
  - **Re-send.** The user's page shows when a pending invitation expires
    and offers "Send invitation again", which renews it from today and
    sends the e-mail (`resendInvitation`, audited
    `user.invitation_resent`).
  - **Revoke.** Revoking is the existing "Remove" status action on an
    invited membership.

**Verified.**
- Typecheck, ESLint and `next build` are clean.
- Vitest 1232/1232. New tests:
  - expiry, escalation and row classification (new, member, self,
    removed-then-invited, invalid e-mail, no name, unknown role, roles
    without role management, a role beyond the inviter);
  - the import-kind and export-registry tests now include `member`.
- E2E (local, dev Supabase): `bulk-invitations.spec.ts` 4/4.
  - **CSV.** A 50-row file: 42 new, 5 existing members, 3 invalid. The
    preview shows each kind; Confirm adds exactly 42 invited memberships;
    the same file again offers "Nothing to import".
  - **API.** The dry run sends nothing. Sending invites 2, leaves 1, skips
    1. Sending again invites 0.
  - **Escalation.** An inviter holding only users.view, users.invite and
    roles.assign cannot give TENANT_SUPER_ADMIN, but can give a role
    within those permissions.
  - **Expiry.** A 40-day-old invitation shows Expired with no Accept.
    "Send invitation again" renews it, and it is then accepted.
- Affected specs (§17.8: RBAC, file imports): `users`, `file-import`,
  `custom-roles` and `authorization` 37/37; `identity-sources` 18/18.

**Left out.**
- An organization scope per row: invitations give organization-wide roles.
  Scoped assignments are made on the user's page afterwards.
- The automation credential (FOUNDATION-P0-31, D11).

### 2026-10-12 — FOUNDATION-P0-31: automation credentials for the administration API (#67)

Decision D11 approved by the owner on 2026-10-12 (design §8.2). F1's last
story; F1 is complete.

**Built.**
- **Model (migrations 0126, 0127).**
  - `automation_credentials`: one per application identity of the
    organization (same-tenant FK). Hashed secret (`wa_ac_` + 32 random
    bytes, shown once), status pending/active/revoked, expiry (1–365 days,
    90 by default), optional CIDR allowlist (≤ 20), calls a minute (120 by
    default). Four-eyes in the database: `approved_by <> created_by`, and
    active needs an approver. RLS: read only with `automation.manage` in the
    credential's own organization; no client write policy.
  - `automation_credential_usage` + `automation_credential_hit()`: the
    per-minute counter, service role only.
  - Membership account type `'automation'`; permission `automation.manage`
    (Tenant Administrator); system role `CONFIGURATION_ADMIN`
    (integrations, policies, organization settings, notifications, roles and
    permissions view; no personal data).
  - 0127: an automation membership creates no HUMAN identity (Identity's
    `identity_sync_membership()`, additive), and the users directory and its
    summary leave automation members out.
- **How a call is authenticated.** Each credential has a backing member of
  its own (an auth user with `app_metadata.automation`, a random password
  held with `encryptSecret`, never shown). Its roles are the credential's
  roles, so RLS, `getTenantContext()`, scoped assignments and the
  authorization engine apply unchanged, and the tenant comes from the
  credential's row (non-negotiable #2).
  - `proxy.ts`: a `wa_ac_` bearer is accepted only on `/api/v1/*` (401
    elsewhere); no cookie session is read for it; the proxy stamps the
    method, path and a fresh request id. A cookie session of an automation
    account is ended and refused.
  - `lib/security/automationCredentials.ts`: hash lookup, then the use
    decision (pending, revoked, expired or suspended organization: 401;
    address outside the allowlist: 403, audited), the rate limit (429), the
    backing member's token (signed in server-side, held in memory until a
    minute before expiry, bounded), and an `automation.api_call` audit entry
    per call (actor type `integration`, `onBehalfOf` = the application
    identity, its owner, method, path).
  - `supabaseServer()` and `getSessionUser()` use that token when the
    request carries a credential; the actor header (0115) names the backing
    member. React's `cache()` does not memoize in route handlers, so the
    check is held per request id: found in E2E, where every helper call
    re-ran it (11 s per call; one call refused).
- **Console and API.** Admin → Users & Permissions → Automation
  Credentials (`/settings/automation`): create (name, application identity,
  role; expiry and limits folded), approve (not the creator), and under
  Manage: give or remove a role, request an extension (another person
  approves), rotate, revoke (ends the backing member's sessions).
  `GET/POST /api/v1/automation-credentials`,
  `POST /api/v1/automation-credentials/{id}` (actions),
  `GET/PATCH /api/v1/tenant/configuration`. Schedules already had
  `/api/v1/integrations/{id}/schedule` (INTEGRATION-P0-20).
- **Escalation.** A credential's role carries only permissions its giver
  holds, never `automation.manage` (so never Tenant Administrator, which
  also keeps it out of the last-administrator count). `assignRole()` /
  `removeRole()` refuse an automation member unless called from the
  credential service, so `/api/v1/users/{id}/roles` cannot bypass that.

**Verified.**
- Typecheck and ESLint clean; Vitest 1244/1244 (new: secret shape, bearer
  parsing, expiry, CIDR parsing and matching for IPv4/IPv6/mapped, the use
  decision, rate limit, role escalation).
- `tests/foundation/automation-credentials-isolation.sql` 16/16 on dev:
  read only with `automation.manage` in the same organization; no direct
  insert or update; creator cannot approve; active needs an approver; no
  credential for another organization's identity; counter not callable by
  members; no person identity; not in the users directory; the template
  has no personal-data permission.
- E2E (local, dev Supabase): `automation-credentials.spec.ts` 4/4.
  Secret shown once; pending is 401; the creator cannot approve (console
  and API: FOUR_EYES); a second administrator approves; the credential
  lists exactly its own organization's connections (a `wa_tenant` cookie
  naming the other organization changes nothing; the other's connection is
  404); Global Configuration 200; users 403; credentials 403; a page 401;
  each call audited with the identity as on-behalf-of; TENANT_SUPER_ADMIN
  refused as ROLE_ESCALATION; rate limit 429; expired 401; revoked 401; the
  backing account is not in the users directory.
- Supabase advisors: only the expected "RLS enabled, no policy" note on the
  service-only usage table.
- Affected specs (§17.8: sessions, `proxy.ts`, RBAC), local against dev:
  `auth`, `csrf`, `authorization`, `multi-org-isolation`, `users`,
  `custom-roles`, `groups`, `global-configuration`, `agent-api-keys`,
  `tenant-address`, `runtime-gateway` and `bulk-invitations` 96/96. The
  first run had one failure: the 42-row import in `bulk-invitations` did not
  finish within 120 s while dev Supabase was slow (password sign-in 7 s,
  auth health 0.6–2.2 s). The same spec on `main` passed after the
  recovery, and on this branch it then passed in the same 2.1 min. With
  temporary counters on both branches, an invitation API call made the same
  number of session lookups, clients and service-role calls (31 / 48 / 16
  for two invitations), at the same speed. That import wait was already at
  its limit: 42 sequential invitations take about 3 s each from a remote
  runner. It is now 240 s, within a 360 s test budget.

**Left out.**
- Four-eyes on an extension is enforced in the service (the requester
  cannot approve); the database enforces it for approval, and keeps the
  request and its requester as a pair.
- Pruning old `automation_credential_usage` rows (one per credential per
  minute used): a retention follow-up.
- Each server instance signs the backing member in once per token lifetime,
  so auth sessions accumulate slowly; they end when the credential is
  revoked.
- Other modules' member pickers (owners, investigations) may list an
  automation member by its "Automation: …" name; excluding them there is
  for those modules.

### 2026-10-12 — Automation credentials never approve or certify (WID-H06, owner decision)

The owner approved forbidding automation credentials from approving access.
- `HUMAN_ONLY_PERMISSIONS` (`automationCredentialRules.ts`) =
  `automation.manage`, `access.approve`, `agent.certify`.
- `roleEscalation` refuses assigning them, even when the assigner holds
  them.
- `getTenantContext` strips them from an automation call's grants, so a
  role changed later cannot reintroduce them.
- `refuseAutomationCaller` refuses automation callers at:
  - access decisions;
  - certification decisions and attestations, which use
    `compliance.manage`, a permission automation legitimately holds;
  - onboarding approval.

Verified:
- `automationCredentialRules.test.ts`: 13 passed.
- E2E `automation-credentials.spec.ts`: 4/4.

Tracked in `docs/WonderID/FINDINGS-REMEDIATION.md`. Next: four-eyes on role
changes to an active credential.

### 2026-10-12 — Automation address allow-list trusts only the edge (WID-H08)

Raised by the hourly findings audit. `automationAccessNow` took the
caller's first `x-forwarded-for` value, which a caller can set. Now
`trustedClientIp` reads:
- the header named by `CLIENT_IP_HEADER` (self-hosted ingress; last hop);
- on Vercel, `x-vercel-forwarded-for` or `x-real-ip`;
- otherwise nothing, so a credential with address limits is refused.

Credentials without address limits are unaffected.

Verified: `npx vitest run lib/security`, 71 passed, including the new
WID-H08 tests (spoofed header ignored, Vercel headers, configured header's
last hop, unknown address refused).

Tracked in `docs/WonderID/FINDINGS-REMEDIATION.md`.

### 2026-10-12 — Four-eyes on role changes to automation credentials (WID-H06)

- Migration 0133 adds `automation_credentials.changed_by`, with the check
  `automation_credentials_change_four_eyes` (approved_by <> changed_by).
  Applied to the project; advisors show no new issue.
- `assignAutomationCredentialRole` on an active credential:
  - sets it to pending and clears the approval;
  - records `changed_by`;
  - drops the cached token, deactivates the backing membership and ends
    its sessions, so the credential stops working at once.
- On a pending credential it only records `changed_by`.
- `approveAutomationCredential` refuses the creator and `changed_by`
  (FOUR_EYES).
- Audit: `automation_credential.role_change_requested`.
- Removing a role needs no approval.

Verified:
- `npx vitest run lib/security`: 71 passed.
- E2E `automation-credentials.spec.ts`: 5/5, including the new WID-H06
  test. The paused credential gets 401; the role giver gets FOUR_EYES;
  another administrator approves; then the credential works again.

Tracked in `docs/WonderID/FINDINGS-REMEDIATION.md`.

### 2026-10-12 — Refused automation calls are audited; database cap on expiry (WID-H06)

- `getAutomationAccess` audits every refusal with a known credential as
  `automation.api_call`, outcome failure, with `refused` set to the code:
  - pending, revoked and expired (401), and an address that is not allowed
    (403): at most once per credential and code a minute. A bounded
    in-process map decides (`refusalAuditDue`, 1,000 keys). Before this,
    only 403 was audited, on every call;
  - the rate limit (429): only the call that first goes over in a minute
    (`firstOverRateLimit`: calls = limit + 1). The database counter decides
    this, so it holds across instances.
- An unknown key has no tenant to audit to. It is answered 401, as before.
- Migration 0134 adds the `automation_credentials_expiry_cap` trigger. An
  `expires_at` or `requested_expires_at` that is set or changed may be at
  most 366 days after the write: 365 days plus one day of slack. It is
  applied to the dev/prod project; security advisors show nothing new.

Verified:
- `npx vitest run lib/security modules/access-governance "app/(customer)/access" lib/config`:
  347 passed.
- `npm run typecheck` and eslint on the changed files: clean.
- E2E, local: `automation-credentials.spec.ts` 5/5. The rate limit, expiry
  and revocation test now also checks:
  - the RATE_LIMITED, CREDENTIAL_EXPIRED and CREDENTIAL_REVOKED audit rows;
  - that the database refuses an expiry 400 days ahead;
  - rotation: the old secret gets 401 at once, and the new one works.

Tracked in `docs/WonderID/FINDINGS-REMEDIATION.md`.

### 2026-10-12 — A SQL test for the audit trail's integrity (WID-H07)

New `tests/foundation/audit-trail-integrity.sql`. It is one block that
rolls back, run through the Supabase MCP `execute_sql`. It checks, against
migration 0104:
- an `audit_logs` row cannot be updated or deleted (42501);
- `purge_audit_logs` refuses a cut inside 365 days (22023);
- an active legal hold on audit logs makes the purge remove nothing;
- once released, the purge removes only the 400-day-old row, records it
  in `audit_log_purges`, and `verify_audit_chain` reports no break.

Run against the live project on 12 October: "AUDIT TRAIL CHECKS PASSED".
The block rolls back, so it leaves no fixtures. No code changed.

### 2026-10-12 — typed text out of audit records (WID-H07, owner decision)

- `lib/audit/typedText.ts`: `fingerprintText`, `matchesFingerprint` and
  `withTypedText`. The fingerprint is HMAC-SHA256 under a key derived from
  `SECRET_ENCRYPTION_KEY` (the retired keys in
  `SECRET_ENCRYPTION_KEY_PREVIOUS` still verify), over the tenant id and
  the text.
- `AuditEvent.typedText` and `writeAudit` turn each value into
  `metadata.typedText.<field> = { fingerprint, length }`. Any metadata key
  of the same name is dropped. No new environment variable.
- Foundation call sites converted:
  - member status reason (`users.ts`);
  - agent API key revocation, one and all (`agentApiKeys.ts`);
  - automation credential revocation;
  - authorization policy description (created and updated).
- Other modules' call sites are listed in their audit logs and in
  `docs/WonderID/FINDINGS-REMEDIATION.md` (WID-H07).

Verified:
- typecheck and eslint on the changed files: clean;
- `npx vitest run lib modules`: 1360 passed, after updating the
  identity-link audit assertion to the new shape;
- E2E, run locally after rebasing on #129 (migration 0150 is on §17.8's
  list):
  - application-onboarding, emergency-controls, automation-credentials,
    users, access-packages and approval-engine: 43 passed, 2 failed, 7
    did not run;
  - the 2 failures, approval-engine `:187` and automation-credentials
    `:106`, passed when their two specs were rerun on their own with one
    worker (20 passed);
  - in parallel they read data other specs were changing (a manager
    link, and the organization's connection list between two reads).
    That is a QA follow-up, not this change.

### 2026-10-12 — WID-H07, identifiers only

WID-H07 identifiers only (audit side). `AuditEvent.typedText` now also takes an outside system's value that may identify a person; it is fingerprinted the same way. The module audits that wrote personal data are listed in the Access, Integration, Identity and Platform logs and in the tracker. Verified: `npx vitest run lib modules` 1360 passed, typecheck and eslint clean.

### 2026-10-12 — WID-H08 tested end to end at the production edge; deployments documented

- `tests/e2e/automation-credentials.spec.ts`, new test "WID-H08". It limits
  the approved credential to 203.0.113.0/24, then calls the API with that
  address in six headers (`x-forwarded-for`, `x-vercel-forwarded-for`,
  `x-real-ip`, `forwarded`, `true-client-ip`, `x-client-ip`):
  - the local server: refused, 403 `ADDRESS_NOT_ALLOWED` (fails closed);
  - production through Vercel's edge (`E2E_INGRESS_URL`): refused, 403
    `ADDRESS_NOT_ALLOWED`;
  - positive control: with every address allowed, the calls pass the
    address check and reach the rate limit (429).
- `scripts/e2e-on-vercel.sh` sets `E2E_INGRESS_URL` to production, so the
  nightly re-checks the edge.
- `docs/security/SECURITY-CONTROLS.md` §5: where the address comes from on
  each supported deployment, and what an operator must do when
  self-hosting.

Verified: the spec, run locally with `E2E_INGRESS_URL=https://id.wonderapps.biz`:
13 passed. A first attempt used a 200 as the positive control and got 500.
Production cannot decrypt a credential's backing secret created under the
local server's encryption key (runtime log: "Unsupported state or unable to
authenticate data"). Hence the rate-limit control, which needs no key.
### 2026-10-13 — An unknown organization address answers 404 on Vercel too (FOUNDATION-P0-22)

The proxy rewrites an address that names no organization to
`/tenant-not-found` with status 404. Vercel's build served that page with
200: the rewrite's status was lost (E2E `tenant-address.spec.ts:54`, Vercel
builder only).

The page now calls `notFound()`, so the 404 comes from the page itself:
- `not-found.tsx` beside it renders the same message;
- a `layout.tsx` sets the title ("Organization not found").

The proxy is unchanged, and nothing about which organizations exist is
revealed.

Verified locally:
- `curl` returns 404 for unknown and reserved addresses, with the right
  title;
- `tenant-address.spec.ts` 12/12; `auth.spec.ts` 41/41.

Follow-up: `/service-unavailable` (503) relies on the same rewrite status.

### 2026-10-13 — Global Configuration takes a host list (WID-H05)

`lib/config/registry.ts`:
- a third setting type, `hosts` (`HostsSetting`);
- the first such setting, `integration.allowedHosts` (security
  permission, up to 50 entries, default empty);
- `acceptHosts` validates host names, lower-cased, sorted, without
  repeats; a scheme, port or path is refused;
- `TenantConfig` is typed per key, so numeric settings stay numbers;
- changes compare by value and are shown with `formatConfigValue`.

`lib/config/tenantConfig.ts`: `readTenantConfigStrict` throws when the
store cannot be read. The Gateway needs this so a restriction never falls
back to "no restriction".

UI: the Global Configuration page shows a textarea for a host list.

Tests: `registry.test.ts` (new "the allowed hosts" cases; the defaults
test lists the new key).

### 2026-10-13 — An organization can require MFA (FOUNDATION-P0-27)

New Global Configuration setting `security.mfaRequired` (security
permission, default not required), in the renamed section "Sign-in and
sessions". When it is on, a member's session reaches the organization only
after MFA (aal2). Automation members are exempt: they cannot do MFA, and
their credentials have their own four-eyes approval, address list and
expiry.

Enforced in two places:
- **Database** (migration `0152_foundation_mfa_required.sql`, applied):
  `current_tenant_ids()` leaves the organization out for a session that is
  not aal2, so every RLS policy hides its rows and a direct PostgREST call
  gets nothing. Only the stored value 1 means required, matching
  `resolveConfig()`.
- **Application:** `getTenantContext()` returns no tenant and no
  permissions, only `mfaStepUp`. `requirePermission*` answer 403
  `MFA_REQUIRED` (`noTenantError`). The customer layout sends the person to
  `/verify-mfa`.

`/verify-mfa` verifies an authenticator app already set up, or sets one
up, with Supabase Auth's own TOTP. It also offers the person's other
organizations that don't require MFA, and sign out. A member whose
organization doesn't require it may verify there voluntarily.

Lock-out guard: `planConfigChange` refuses to turn the setting on unless
the saving session is aal2 (`MFA_ENABLE_NEEDS_AAL2`), from the page, the
API or a version restore. Turning it off needs no MFA: an aal1 session in
such an organization has no permissions anyway.

Memberships are now read through `my_memberships()` (security definer, the
caller's own active memberships of active organizations, with the MFA
flag). RLS hides an MFA organization's membership rows from an aal1
session, and without this the person would look as if they had no
organization. `selectTenantAction` uses the same list. Choice settings can
now carry labels ("Not required" / "Required"), also in the version
history.

Verified:
- `npm run typecheck`; eslint on the changed files.
- Vitest `lib/config lib/tenant lib/rbac`: 75/75, including the new
  "requiring MFA" cases and `mfaRequired.test.ts`.
- `tests/foundation/mfa-required.sql` on the dev project: 10/10. The checks:
  - an aal1 session reaches only the organization that doesn't require
    MFA, and sees 0 rows of the one that does;
  - an aal2 session reaches both;
  - a session with no aal claim is refused;
  - an automation member is exempt;
  - a stored value other than 1 means not required;
  - `my_memberships()` lists only the caller's own memberships, never a
    suspended organization;
  - anon is denied.
- Supabase security advisors: only the expected note that signed-in users
  can call `my_memberships()`, the same as for `my_session_policy()`.
- Local E2E (production build):
  - new `mfa-required.spec.ts`: 3/3;
  - regression: `auth`, `first-organization`, `multi-org-isolation`,
    `global-configuration`, `automation-credentials`, `tenant-address` and
    `authorization` specs, 63/65 on the first run. The 1 failure was
    `global-configuration` looking for the old section title, now
    updated, and it passed 10/10 on rerun. The other test did not run
    after that failure.

Left out:
- SSO required is blocked: the free Supabase plan has no SAML.
- Certification interval, AI-agent defaults and audit retention are still
  to do under this story.
- `/settings/security` still only adds factors; verifying an existing one
  happens on `/verify-mfa`.

### 2026-10-13 — Platform administrators can also be listed in `PLATFORM_ADMIN_EMAILS` (owner request)

`isPlatformAdmin()` now also admits a signed-in account whose email is in
the `PLATFORM_ADMIN_EMAILS` environment variable (comma-separated), in
addition to the `platform_admins` table.
- The email must be confirmed in Supabase Auth: it is read with the
  service role (`auth.admin.getUserById`), never from the request, so a
  typed or unconfirmed address never opens the console.
- Removing an address and redeploying removes the access.
- The rule is pure and tested in `platformAdminEmails.ts`
  (`platformAdminEmails.test.ts`, with `lib/rbac` 39/39).

Set in Vercel (production and preview, encrypted) to
aitoolshubsaas@gmail.com, the account the owner uses; documented in
`.env.local.example`.

Separately, found in `platform_admins`: `fixture-pa107@example.test`, a
leftover from a database test. It has no password and has never signed
in. The owner was given the SQL to remove it; it is not removed here,
because deleting from the platform boundary needs the owner.

### 2026-10-13 — The main address is the landing page; the product opens on an organization's address (owner request)

**Request.** "id.wonderapps.biz should open landing page, to login to specific org, user must select specific org+env url."

**Built.**
- **The flag.** `ORG_ADDRESS_REQUIRED=true`, set on Vercel production only, so local, preview and nightly E2E runs keep using the main address. Setting it to false serves the product on the main address again.
- **The rule.** With the flag on, the proxy applies `mainAddressRedirect()` on the main address. It is pure and tested in `lib/tenant/host.test.ts`:
  - The landing page stays for visitors who are signed out.
  - These stay on the main address: sign-in, sign-up, `/auth/`, password recovery, help, the vendor console, `/organizations`, `/onboarding`, the error pages, and every `/api/` route (connector receivers, webhooks, cron).
  - Paths match whole path segments only, so a look-alike such as `/platform-administration` does not match.
  - Any other page goes to `/sign-in` when signed out, or to `/organizations` when signed in.
- **`/organizations` (new).** The person's own active organizations and environments, grouped by organization with production first and each with its colour.
  - Each links to `https://<prefix>[-env].id.wonderapps.biz/sign-in`, where they sign in; sessions are per address.
  - It also offers "Create or join an organization", the platform console for platform administrators, and sign-out.
  - On an organization's address it redirects to `/`.
- **The address still never authorizes anything.** Access comes from an active membership, as before.

**Verified.**
- Vitest `lib/tenant/host.test.ts` 8/8.
- Typecheck and eslint clean; `next build` succeeds.
- Local E2E with the flag (a second server with `ORG_ADDRESS_REQUIRED=true`): `org-address-required.spec.ts` 1/1. It covers:
  - the landing page on the main address;
  - a product page there sending a signed-out visitor to sign-in;
  - sign-in landing on `/organizations`;
  - product pages and `/` staying on `/organizations` once signed in;
  - the API answering 200 on the main address;
  - the organization link opening its own sign-in, then the product there.
- Without the flag: tenant-address, first-organization, auth and platform-admin, 53 passed, with the flag spec skipped by design.
- The shared sign-in setup cannot run against a server with the flag, because it expects the product on the main address, so the flag spec runs with `--no-deps`. This is recorded in the spec.

**Left out.** Google, Microsoft and LinkedIn sign-in on organization addresses. Their buttons show only once the owner adds `https://*.id.wonderapps.biz/**` to Supabase's redirect URLs.

### 2026-10-13 — Google, Microsoft and LinkedIn sign-in on organization addresses

**Owner action done.** `https://*.id.wonderapps.biz/**` was added to Supabase's redirect URLs.

**Built.**
- **Buttons.** The social sign-in buttons now show on an organization's own sign-in page, except for a suspended organization. They return to that address's `/auth/callback`, since the return address is built from the page's own origin.
- **The same membership check on both paths.** `/auth/callback` now applies the refusal the password path already had: someone who is not an active (or invited) member of the addressed organization has the new session ended and lands on sign-in with a fixed notice ("not an active member" or "cannot be signed in to right now").
- **One shared function.** The check moved into `lib/auth/tenantAddressGate.ts` (`refuseNonMemberOnTenantAddress`, audited `auth.sign_in_refused`), so both paths use it rather than two inline copies.

**Verified.**
- Vitest: the gate 3/3, and `app/actions` with `app/auth` 26/26.
- Typecheck and eslint clean; `next build` succeeds.
- Local E2E: tenant-address and auth, 42 passed. The new test checks that Google sign-in on an organization's address asks Supabase to return to that same address's callback, and that a suspended organization shows no social sign-in.

## 2026-10-13 — Manage organizations (owner request)

**What changed.** The organization switcher's "Create new organization" is now "Manage organizations" (`/organizations/manage`). An organization's owner (TENANT_SUPER_ADMIN of the organization) can:
- rename the organization; its environments follow ("<name> (Test)");
- disable or enable the organization, which takes its environments with it, or disable or enable one environment;
- add a development, test or staging environment, which is paid for. Owner decisions: organizations stay free, environments are paid at a plan's price, and until Stripe or Razorpay keys are set, payment is a test payment (no money moves, recorded as `payment_mode = 'test'`).

Owner feedback the same day: an organization set up as development, with no production organization above it, could not add environments. Any top-level organization can now, both here and in the platform console; its own kind can't be added twice.

**Database (migration 0161).**
- `tenants.disabled_by_owner` tells an owner's disable from a platform suspension. Only an owner's disable can be lifted by an owner. A platform suspension clears the flag (`setTenantStatus`).
- `is_organization_owner()`, `my_managed_organizations()`, `owner_rename_organization()` and `owner_set_organization_disabled()`: SECURITY DEFINER, run as the caller, and the ownership check is in the database.
- `environment_orders` (Platform): RLS on, read by `billing.view` holders, written only by the service role. It holds one open order per organization and environment.
- `create_tenant_environment()` now accepts any top-level organization.

**Security.** Disabling is the existing suspension, which `current_tenant_ids()` already refuses (0152), so a disabled organization's data is unreachable to every member. The page sits outside the product shell, so an owner can still enable an organization they disabled. The no-access page links to it. Each change is audited (`tenant.renamed`, `tenant.disabled_by_owner`, `tenant.enabled_by_owner`, `billing.environment_ordered`, `billing.environment_setup`). The order is written before set-up; a failure marks it failed and is reported, never shown as success.

**Verified.**
- Live SQL (`tests/foundation/manage-organizations.sql`, rolls back), every expected result:
  - another organization's owner sees none of it, can't rename or disable it, and can't read its orders;
  - a client insert of an order is refused;
  - the owner renames it, and its environments follow;
  - a disabled organization is unreachable but still listed for its owner;
  - an environment can't be enabled while its organization is disabled;
  - a platform suspension can't be lifted by the owner;
  - a development organization adds Test, but not Development, and an environment can't have environments.
- Vitest: `environmentOrders` 7/7 (test mode only without a provider, ownership, disabled organization, wrong currency, double click, failed set-up recorded), `manage` grouping 2/2, platform-admin 30/30.
- Typecheck and eslint clean; `next build` succeeds.
- Local E2E: manage-organizations (new), first-organization and platform-admin, 21/21. The new test: rename, buy Test, disable and enable it. It caught a UI bug, a confirm step that survived Enable, which is fixed.

**Left out.** Real checkout for environments through Stripe or Razorpay: once keys are set, test payments stop and the page says online payment isn't available yet. That checkout is the follow-up. The address prefix stays the platform console's to change.

## 2026-10-13 — Onboarding lists organizations with their environments (owner request)

"Select an organization" on `/onboarding` now lists each organization once with its environments under it, using the same grouping as the switcher (the person's own memberships only). The switcher button shows the organization's name only. The environment is its coloured dot and the chips below it. Verified by local E2E: first-organization and tenant-address, part of the 34/34 run recorded in the Platform audit log.

## 2026-10-13 — Onboarding is for creating an organization only (owner request)

`/onboarding` no longer lists your organizations; that list is `/organizations`. It keeps invitations and the create form, with **← Back** at the top and **Cancel** beside **Create organization**, both to `/organizations`. Verified with local E2E first-organization (part of a 30/30 run).

## 2026-10-13 — No organization list on the main address (owner request)

`/organizations` no longer lists anything. A signed-in person on the main address is sent straight to their organization's own address, at its sign-in page because sessions are per address: the organization they last used, else their first.
- With no organization, they go to `/onboarding`; a platform administrator with none goes to the platform console.
- Without organization addresses (local runs), they go to `/`.
- Only their own active memberships are considered.
- `/organizations/manage` is unchanged.

**Verified.** Typecheck and eslint clean. Local E2E: org-address-required (a server with the flag on) 1/1; first-organization and tenant-address 16/16.

## 2026-10-14 — Delegated role assignments (for ACCESS-P0-23 part 3, owner-approved)

Administration delegation is approved by the owner, and Access's delegations call it.

**What changed.**
- `lib/rbac/delegatedRoles.ts` (`grantDelegatedRoles`, `revokeDelegatedRoles`) writes and removes time-bound copies of one member's directly assigned roles for another.
- Migration 0178 adds `user_roles.delegation_id`.

**What did not change.** The authorization engine, permissions and RLS: a copy is an ordinary scoped, expiring assignment.

**Guards.**
- Tenant Administrator is never copied.
- The no-self-grant check still applies.
- A role already held is left alone.
- There is no re-delegation.
- `assignRole` turns a copy into an ordinary assignment when an administrator sets its terms.

**Verified.** Detail in the Access audit log of the same date: unit tests, isolation SQL 10/10, and the authorization, custom-roles, users and permission-catalog E2E specs.

## 2026-10-14 — WID-H10: the listed-email vendor path proves the mailbox

The high-risk register's WID-H10: `PLATFORM_ADMIN_EMAILS` opened the
vendor console for any confirmed account with a listed email, whatever
signed it in. Done, pending the owner's decision on keeping the path:
- `isListedPlatformAdmin` (`lib/rbac/platformAdminEmails.ts`) now also
  refuses an SSO user or an `sso:` identity, and needs an identity from
  `PROVEN_EMAIL_PROVIDERS` (email, Google, LinkedIn). Microsoft-only is
  refused (its email claim is not verified).
- `isPlatformAdmin` reads the account's identities from Auth and, on the
  first admission through the variable, writes the platform audit record
  `platform.admin_access_via_env`.
- The `platform_admins` table path is unchanged. The owner's own account
  (Google) still passes; checked read-only before the change.

Verified: typecheck; eslint; `platformAdminEmails.test.ts` 3/3 (1 new,
"WID-H10"); local E2E `platform-admin.spec.ts` with the delegation and
automation specs: 32/32. Owner decision (14 Oct, 13:45 IST): keep the variable with this
binding; it still relies on Supabase's "Confirm email" setting, and removal
still needs a redeploy. Tracker: `docs/WonderID/FINDINGS-REMEDIATION.md`,
WID-H10.

## 2026-10-14 — Role assignments for reviews (COMPLIANCE-P0-11)

Published `listRoleAssignmentsForReview(tenantId, { privilegedOnly })`
(`lib/rbac/roleAssignmentReview.ts`) for Compliance's reviews of WonderID
roles: one row per role an active person holds, directly (not a
delegation's copy) or through an active group, within its current terms,
with whether the role is privileged (any permission with sensitivity
`privileged`). Service role, every query filtered by `tenant_id`. Revokes
go through the existing `removeRole` and `removeGroupMember`; no change to
either. No schema change in this module.

## 2026-10-14 — Role assignment end date for review exceptions (COMPLIANCE-P0-10 part 2)

Published `setRoleAssignmentEnd(tenantId, actorId, targetUserId, roleId,
expiresAt)` (`lib/rbac/roles.ts`): sets only `expires_at` on a member's
direct assignment (never a delegation's copy), keeping its scope and other
terms; refuses the actor's own role (`SELF_ESCALATION`) and automation
members (`assertTenantMember`); 409 `NO_ASSIGNMENT` when the role is no
longer held directly. Service role, filtered by tenant; audited
`role.assignment_changed`. Used by Compliance's review exceptions.

## 2026-10-14 — WID-H10: vendor access only from platform_admins (owner decision)

The owner clarified the WID-H10 decision: vendor access comes only from
the audited `platform_admins` table, and `PLATFORM_ADMIN_EMAILS` only
bootstraps it.
- `isPlatformAdmin` and `requirePlatformAdmin` read only the table.
- `isPlatformAdminBootstrap` (the earlier proven-mailbox check, first use
  audited) and `requirePlatformAdminOrBootstrap` allow only Platform Admins
  and granting an entry; `platformConsoleAccess()` returns full, bootstrap
  or none for the console layouts and the customer "Admin console" link.
- Every other console page moved into the route group
  `app/platform-admin/(console)` (URLs unchanged), whose layout sends a
  bootstrap session to Platform Admins and anyone else to a 404.
- `tests/architecture/route-gates.test.ts` recognises
  `requirePlatformAdminOrBootstrap` as a gate.

Before the change, 3 accounts were in `platform_admins`; the owner's
account was not, so the owner adds it once through Platform Admins (the
form fills in their own id).

Verified: typecheck; eslint; Vitest rbac and architecture 64/64; `next
build`; local E2E with `PLATFORM_ADMIN_EMAILS` set to the IAM admin:
`platform-admin`, `manage-organizations`, `first-organization` 24/24.

## 2026-10-14 — /install is public and served on the main address

For the one installed app (Experience audit log, same date): `/install`
joins `PUBLIC_PATHS` in `proxy.ts` and `MAIN_ADDRESS_PATHS` in
`lib/tenant/host.ts`. It shows only install guidance, reads no data. Local
E2E `auth`, `org-address-required`, `tenant-address`: 42 passed, 1 skipped.

### 2026-10-14 — Add user from an identity (owner test feedback 8, part 1)

Owner feedback: a person added under Identities did not appear under
Users, and there was no way to give them a sign-in from there. Identities
are the people the organization governs; Users are the people who can sign
in to WonderID. Now:
- Add user has a "From an identity (optional)" picker of active person
  identities with an e-mail and no membership (Identity's
  `listPeopleWithoutAccess`, read under RLS, membership read by tenant);
  choosing one fills name, e-mail, title and department. The invitation
  itself is unchanged (`inviteUser`: no role escalation, audited).
- A person's identity page has "Give WonderID access" (users.invite or
  users.create), opening Add user with that person chosen.

Next (part 2, owner decision in chat): a default role in the HR import
(identity source) settings, and an "ID Role" (WonderID platform role)
option on each person's page.

Verified: typecheck; eslint; `next build`; local E2E `users` (new test:
identity → Give WonderID access → form filled) with
`application-onboarding`, 26/26.

### 2026-10-14 — "ID roles", and ID roles on a person's page (owner feedback)

Owner feedback: "give option on every user page to add Platform Role, lets
call it 'ID Role'" and "Call these Roles as 'ID Roles'". ID roles are
WonderID's own roles (the `roles` table: system roles such as Tenant
Administrator, Identity Administrator, and custom roles), as opposed to
roles people hold in applications, which stay "roles".

- Wording only, on Foundation's screens: the ID Roles page, role detail,
  create and edit, the Users list (column and filter), a user's page
  ("ID roles & groups", "Assign an ID role", "Assign ID role"), the Add
  user wizard's "ID roles" step, groups, the permission catalog, and the
  messages of `assignUserRoleAction`. No route, API path, table,
  permission key or identifier was renamed; the help guide was not changed
  (owner rule).
- New `findMemberForPerson(tenantId, { userId, email })` in
  `lib/users/users.ts`: the member a person's identity stands for (its own
  user, else the account with the same email), only when that account has
  a non-removed membership in this tenant (`tenant_memberships` filtered by
  `tenant_id`, §14). The identity page reads that member's ID roles with
  `getUserDetail` and changes them only through the existing
  `assignUserRoleAction` / `removeRoleAction` → `assignRole` / `removeRole`
  (roles.assign or role.manage, self-grant refused in the service and the
  database, audited). `assignUserRoleAction` now also revalidates
  `/identities/[id]`.
- No schema, permission or RLS change.

Verified: typecheck; eslint on changed files; vitest `modules/ui
tests/architecture lib/users` 153/153; `next build`; local E2E on :3200:
`identities` 19/19 (new test: admin adds Auditor from the requester's
person page, sees it, removes it; read-only sees no "Add ID role"), and
`custom-roles`, `users`, `groups`, `authorization`, `shell`,
`navigation-smoke` 92/92 (counts include the 7 sign-in setup steps).

Left out: nothing of this request. (The default ID role in the HR import
settings, part 2's other half, shipped separately in #208.)

### 2026-10-14 — FOUNDATION-P0-34 part 1: short number keys in URLs

Owner: "all the keys displayed in url should be integers, not the really
long alphanumeric strings; add this to claude.md" (CLAUDE.md §19.13).

- Migration 0192 (the MCP apply was cancelled twice, so the owner ran the
  file in the SQL editor): `ref bigint not null` on 22 object tables with
  pages, numbered per organization oldest first (each table's own triggers
  paused for the backfill, so no provenance changed), unique
  `(tenant_id, ref)`, `assign_object_ref` (next number from
  `object_ref_counters`, RLS read-own, trigger-only writes) and
  `keep_object_ref` (a number never changes, 23514). Access requests: `ref`
  is the number of their REQ number (0190's trigger sets both). Roles:
  built-in roles 1–16, each organization's own roles continue after them
  (`assign_role_ref`). Organizations: a global sequence (platform console).
- `lib/refs/objectRef.ts`: `parseRefParam` (a positive whole number, or a
  UUID from an old link), `resolveRef` (as the user, filtered by tenant,
  RLS applies), `pageRef` (404, or redirect an old UUID link keeping the
  query string), `platformTenantRef` (vendor console).
- Access requests converted: the request page takes the number; the
  requests list, the barcode after submitting and basket results link by
  number; e-mailed approval links (UUID) redirect with their `?link=`.

Verified: live `tests/foundation/object-refs.sql` 10/10; typecheck; eslint;
Vitest lib/refs + access-governance 340/340; local E2E request-catalog,
approval-links-drafts and request-baskets 25/25 (a request row opens at
/access/requests/<number>; e-mailed UUID approval links redirect with their
token).

Next: the other object pages (identities, agents, applications, accounts,
packages, integrations and sources, policies, risk, compliance, settings,
privacy, platform tenants), and their links.

### 2026-10-14 — FOUNDATION-P0-34 part 3: number URLs for settings, compliance, risk and the platform console

Converted to the object's short number (`pageRef`; an old UUID link
redirects, keeping the query string), with every main link switched:

- Users (`/settings/users/<membership ref>`; `pageRef` on
  `tenant_memberships` returns the member's user id): `listUsers` reads the
  page's membership numbers in one extra query (this tenant only);
  `getUserDetail`, group members and role holders carry `memberRef`; the
  invite/add wizard redirects to the number.
- Roles (`/settings/roles/<ref>` and `/<ref>/edit`; built-in roles keep
  their own numbers), groups (`/settings/groups/<ref>`), authorization
  policies (`/settings/authorization-policies/<ref>`): lists, create
  redirects, cross-links (role ↔ group ↔ user, "copied from"), and
  `roles/new?copy=` now take the number (a UUID still works).
- Privacy requests and breaches (`/settings/privacy/{requests,breaches}/<ref>`).
- Server actions revalidate the dynamic route (`"/settings/users/[userId]"`,
  `"page"`, …) instead of a UUID path that no longer matches.
- Shared types gained an optional `ref` (`CertificationCampaign`,
  `Investigation`, `AccessFinding`, `PlatformTenant`); API routes unchanged
  (their JSON gains the additive `ref`).

Left as UUID links (they redirect): the identity page's group and
rogue-finding links (identities are another conversion's area), the
revocation-closure report's campaign link, the unused
`recordDecisionAction` redirect, and `/settings/users?group=<uuid>` (a
filter, not a page key). No database change (0192 already applied).

Verified: typecheck; eslint on the 51 changed files and 9 specs; Vitest
lib/users, lib/rbac, lib/refs, lib/shared, modules/platform-admin,
operations, risk, privacy, certification-compliance, app and
tests/architecture 442/442 (66 files). E2E specs updated: number URLs
expected after create (groups, custom-roles, authorization, users,
compliance, investigations) and an old UUID link asserted to redirect in
each area (groups, roles editor, user page, policy, campaign,
investigation, rogue finding, consultation, privacy request and breach,
platform organization). Local E2E (production build on port 3400) on the
ten affected specs (groups, custom-roles, authorization, users, compliance,
investigations, role-reviews, first-organization, trust-compliance,
bulk-invitations): 65/69 passed in the full run. The 4 failures were 3
compliance launches whose dialog never submitted and one role-review answer
that was not saved, all while other agents' E2E runs loaded the machine.
compliance + role-reviews then passed 23/23 when run again on their own.

## 2026-10-15 — FOUNDATION-P0-33: attribute-level old and new values in audit detail (done)

**What.** `lib/audit/changes.ts`: `fieldChanges(before, after)` returns the
fields an edit changed as `{ field, from, to }`, stored as
`metadata.changes` on the audit event. It ignores bookkeeping columns,
compares objects and arrays by value, and never stores two kinds of value:
typed text (description, notes, reason, justification, comment, exception
process) is listed as `omitted: "text"` (WID-H07 keeps it on the record),
and secret-shaped fields as `omitted: "secret"` (#10). Values over 2,000
characters are `omitted: "too_long"`; at most 50 changes per event.

Wired into the update paths of configuration objects: roles (name,
description, permission list), groups, authorization policies, policies,
request policies, identity rules, classification rules, onboarding
templates, entitlement types, applications, access packages, data sources,
identity sources and connection names. Connection setting values stay out,
as before (only their names). Applications and packages read the row before
writing it (as the user under RLS for applications; service role filtered
by tenant for packages, the path that already writes them). Existing
metadata keys are kept, so exports and readers are unchanged.

**UI (Operations' Audit Trail).** `modules/ui/AuditChanges.tsx` folds
"N changes" under the action (§19.5): each field, old → new.

**Verified.** typecheck and eslint pass; Vitest on the changed areas
725/725, including `lib/audit/changes.test.ts` (7 cases: values,
order-independent comparison, null handling, text and secret omission,
bookkeeping, long values, malformed metadata). Local E2E
`custom-roles.spec.ts` 12/12, with a new step: after a role edit, the Audit
Trail row shows "permissions:" with `report.read` in the new value.

**Left out.** User profile edits (personal data, not configuration) and the
platform console (it already records old and new values).

## 2026-10-15 — AI summary: external data is not instructions (QA-P0-21)

`lib/ai/summarize.ts`'s system prompt now states that instructions written
inside the data are content to describe, never instructions (CLAUDE.md
§17.2). New test in `summarize.test.ts`: injected text stays JSON-quoted in
the user message, never in the system prompt, and the result is prose only.
`authorizeCore.test.ts` gains a performance budget: one decision under 1 ms,
and the tenant-wide permission list under 50 ms, for 40 roles and 30
policies (measured 0.05 ms and 4 ms). See the QA entry of the same date.


## 2026-10-16 — `/help` needs a session (owner request)

- `proxy.ts`: `/help` is no longer a public or unenforced path.
- `lib/auth/returnTo.ts`: sign-in returns only to a same-site help path
  (`next`), refusing other sites, other pages and backslash tricks; unit
  tested.
- `proxy.test.ts` covers the redirect with and without a query, and that
  other protected pages carry no return address.
- Detail is in the Experience audit log of the same date.
- CLAUDE.md was amended the same day by owner decision:
  - merges happen without asking once CI is green;
  - the nightly runs at 03:00 IST in four parts;
  - the E2E runs may create test data freely while the app is not live;
  - the help guide is updated with each feature change.

## 2026-10-17 — Access that could not be checked says so (owner decision)

**Before:** a failed read of memberships, roles, groups or policies in
`getTenantContext()` became "no permissions". The person then saw 403
FORBIDDEN, or was sent to onboarding as if they had no organization. It was
safe (fail closed) but untrue (§17.5).

**Now:**
- `getTenantContext()` sets `unavailable: true` when any of the four reads
  fails, still with no roles and no permissions.
- `requirePermission`, `requireAnyPermission`, `requirePermissionFor` and
  `requireAnyPermissionFor` refuse such a context with 503
  `TEMPORARILY_UNAVAILABLE` ("WonderID could not check your access just
  now. Try again in a moment."). A permission list on an unavailable
  context is never trusted.
- The customer layout shows "We couldn't check your access", with a Try
  again link, instead of redirecting to onboarding or no-access.
- An empty but successful read is unchanged: still plain no access.

**Verified:**
- `lib/tenant/getTenantContext.test.ts` (new, 6): each of the four failed
  reads gives unavailable with no permissions; success and empty reads are
  unchanged.
- `lib/rbac/requirePermission.test.ts`: 503 for both unavailable cases.
- `lib/rbac` and `lib/tenant`: all pass.
- eslint clean. Typecheck clean except for the product screenshots missing
  from this checkout.

## 2026-10-17 — FOUNDATION-P0-03.4 closed: MFA enrollment verified end to end

The story was Partial only because "real enrollment against a physical
authenticator app" had not been verified in a sandbox. That is now
covered by `tests/e2e/mfa-required.spec.ts`:
- it enrolls a TOTP factor through Supabase Auth's `mfa.enroll` on the
  verify page;
- it computes the RFC 6238 code an authenticator app would show from the
  returned secret;
- it verifies the code, then signs in again through the challenge.

It passed on Vercel on 2026-10-17 in the access-unavailable run (121
passed). No code changed. The tracker row is Done.

## 2026-10-18 — WID-H06 group path and WID-H10 email proof

Two open findings of the high-risk register, both in Foundation code.

**WID-H06 (REOPENED 17 Oct: group membership as a second path to an
automation credential's roles).**
- `addGroupMember` and `addGroupMemberByRule` (`lib/users/groups.ts`) refuse
  an automation member, 409 `AUTOMATION_MEMBER` (the manual path audits
  the refusal).
- Migration 0201: a trigger on `group_members` refuses an automation member
  for every writer. Checked first: no automation member was in a group.
- `getTenantContext` drops every GROUP grant on an automation call, so a
  credential's power comes only from the roles on its own page.

**WID-H10 (CHANGED 17 Oct: the bootstrap relied on "Confirm email" being
on).** An `email` identity counts for the `PLATFORM_ADMIN_EMAILS` bootstrap
only when Supabase mailed a confirmation and the address was confirmed
after it (`confirmation_sent_at`, `mailedConfirmation` in
`platformAdminEmails.ts`), whatever that project setting is.

**Verified:** `platformAdminEmails.test.ts` (new case), `getTenantContext.test.ts`
(2 new cases) and `lib/rbac`, with the identity merge tests: 10 files, 64
passed. Live `tests/identity/identity-merge-checks.sql`: automation member
into a group 23514, a person ok (8/8 overall). Migration applied to the dev
project; no new advisor item. Typecheck and eslint clean.

**Left out:** the E2E bootstrap describe stays skipped unless the run lists
the IAM admin; when it is listed, that account now also needs a
mail-confirmed address.

## 2026-10-19 — Performance review (cross-module; detail in the QA audit log)

The owner asked for the app to be faster. This module's part, with numbers,
verification and what was left out, is in `docs/design/qa-agent-backlog-audit.md`
(2026-10-19). The rules that came out of it are CLAUDE.md §15.1.

## 2026-10-19 — Memberships in a fixed order (migration 0206)

Found while root-causing the 19 Oct nightly (part 3): `my_memberships()` had
no `ORDER BY`. Away from an organization's own address, with no organization
chosen (`wa_tenant` cookie), the tenant context falls back to the first
membership, so a person in two organizations could land in either one from
one request to the next. It was never a leak (each is theirs), but it is wrong.
The nightly hit it when `platform-admin.spec.ts` briefly gave the E2E
administrator a Development environment, and an onboarding template looked
missing (404). Now: oldest membership first, then tenant id. The rows,
columns, security definer and execute grants are unchanged (checked after
applying: the E2E administrator's first organization is E2E Tenant One;
execute stays with authenticated and service_role only).

## 2026-10-19 — Performance round 2: the live-session check runs alongside the context reads

`getSessionClaims()` (local token verification only) feeds the tenant
context's reads, and `getSessionUser()` (with the auth server's live check)
runs alongside them; `getTenantContext()` returns nothing unless the session
is live. The proxy sends a `Server-Timing` header. Detail and verification in
the QA audit log (2026-10-19, round 2).
