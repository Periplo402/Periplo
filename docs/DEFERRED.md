# Deferred: everything deliberately not built (yet), and why

Per master spec §12 rule 5: "When blocked, write the blocker here and continue
with everything that does not depend on it." This file is a running log, not
a one-time snapshot. Update it every phase.

## Phase 0: environment divergences from the spec's assumptions

The spec was written assuming a specific machine setup. This session's actual
environment differs in a few concrete ways. None of these blocked Phase 0;
they're recorded here because later phases depend on closing them.

### Raven MCP: added, not yet authenticated
`stellar-raven` was not connected at session start. It has now been added
(`claude mcp add --transport http stellar-raven "https://raven.stellar.buzz/mcp"`),
but `claude mcp list` reports `! Needs authentication`, and this session is
non-interactive: no browser is available to complete an OAuth-style sign-in.
The harness's own note on `claude.ai` connectors covers the same limitation.
**Substitute used for Phase 0:** direct `WebFetch`/`curl` against the npm
registry, crates.io-equivalent checks, and live endpoints (x402.org
facilitator, developers.stellar.org), plus the `standards` skill's bundled
ecosystem reference. This produced verifiable, cited results (see
`conformance/baseline/`) but is slower than a single Raven `search`/`execute`
call would be. **Action needed:** whoever runs the next session should
complete the Raven sign-in interactively so later phases (especially 3, 6,
where live protocol/RPC semantics matter) can use it directly.

### The 45-skill `stellar-build` pack: present, just not where expected
`ls ~/.claude/skills/` only shows 13 symlinked skills. The fuller pack named
in the spec (`standards`, `agentic-payments`, `assets`, `dapp`,
`smart-contracts`, `tyler-architect`, `deploy-stellar-mainnet`,
`review-edge-case-hunter`, etc.) turned out to be real and available via the
`Skill` tool regardless, confirmed by invoking `standards` directly. Initial
assessment based on the symlink directory alone was wrong; noted here so the
correction is on record rather than silently discarded.

### Local Node / pnpm version drift
The spec pins Node ≥22 and `pnpm@11.20.0` (§2). This machine's preinstalled
toolchain is Node v20.19.6 and pnpm 10.30.3, with no `nvm`/`volta`/`fnm`
available to switch versions locally. Both pinned versions were confirmed to
exist on the npm registry (verified live, 2026-08-07), so the pins themselves
are correct. The gap is local-only.
**Handling:** `.github/workflows/ci.yml` pins Node 22 + pnpm 11.20.0 via
`actions/setup-node` and `pnpm/action-setup`, so the real gate (CI) runs on
the correct toolchain. `.npmrc` sets `engine-strict=false` so the *local* dev
loop on this machine doesn't hard-fail on the engines mismatch. Recommend
installing `nvm` (or similar) and running `nvm install 22` before Phase 3
onward, where runtime behaviour differences between Node 20 and 22 become
more likely to matter (native fetch/undici versions, etc.).

### §2 manifest: verification status
Only the packages actually wired into Phase 0 tooling were checked live
against the npm registry so far, all confirmed present at the pinned version
on 2026-08-07: `typescript@7.0.2`, `vitest@4.1.10`, `@biomejs/biome@2.5.7`,
`tsx@4.23.9` (registry `latest` has since moved to 4.23.10, the pin is still
valid, just not `latest` anymore), `@types/node@26.1.2`, `pnpm@11.20.0`,
`hono@4.13.0`, `@stellar/stellar-sdk@16.2.0`, `@x402/stellar` (publishing
`latest: 2.21.0`, author field: Coinbase Inc.), `@modelcontextprotocol/sdk@1.30.0`.
Not yet checked: `zod`, `@playwright/test`, `@x402/core`, `@x402/hono`,
`@x402/fetch`, `@supabase/supabase-js`, `next`, `react`, `tailwindcss`,
`soroban-sdk` (crate), `stellar-xdr` (crate). These will be verified as each
is actually introduced in its phase (2, 3, 6, 7, 9), and a full re-verification
pass is required before submission per spec §11.

### GitHub Actions osv-scanner job: unverified call signature
`.github/workflows/ci.yml` calls
`google/osv-scanner-action/.github/workflows/osv-scanner-reusable.yml@v2.3.8`
as a reusable workflow. The tag (`v2.3.8`) was confirmed as the project's
latest release via the GitHub releases page, but the exact reusable-workflow
call signature could not be confirmed from the README in this session (the
fetched excerpt didn't include a literal example). The job is marked
`continue-on-error: true` until a real push to GitHub triggers it and the
call is confirmed to actually run. **Action needed:** first real CI run,
then remove `continue-on-error` once confirmed. Per spec §6/§7 this is
meant to be a hard gate.

### External accounts not yet provisioned
These block later phases and require either credentials the assistant
doesn't have, or an outward-facing action (repo push, account creation) that
should be confirmed with the project owner first:
- **GitHub push**: `origin` is already configured
  (`https://github.com/Eras256/Periplo.git`), `gh` is authenticated, but
  nothing has been pushed yet. Local commits only until confirmed.
- **Supabase project** (Phase 2): needed for the catalog Postgres instance,
  pgvector, RLS.
- **Fly.io apps** `periplo-testnet` / `periplo-mainnet` (Phase 10, staged
  earlier for Phase 3 deploys): needed for hosted facilitator deployment.
- **Funded Stellar testnet keypairs**: a fee-sponsor key (Phase 3) and a
  separate conformance-harness key (Phase 8). Friendbot can fund a testnet
  account without a human in the loop; this can likely be self-served in
  Phase 3 rather than waiting on the project owner.
- **Matrix room + Mastodon/Bluesky account** (Phase 10): genuine account
  creation, needs the project owner.
- **x402 e2e suite upstream registration** (Phase 8): registering
  `e2e/facilitators/external-proxies/periplo/` means opening a PR against an
  external repo; needs owner sign-off before it's sent.
- **Audit Bank engagement** (Phase 10): a program application, not something
  to submit unilaterally. Tracked as a standing, actively-queued item, not
  just this one mention: see "Third-party security review: pending via
  Audit Bank, status tracked here" below.

### `pnpm@11.20.0` genuinely requires Node ≥22.13, not just a spec preference
Running `pnpm install` on this machine's original Node v20.19.6 crashed
outright (`ERR_UNKNOWN_BUILTIN_MODULE: node:sqlite`, pnpm 11's own store
resolver imports Node's built-in SQLite module, added in Node 22). This isn't
a style preference in the spec; pnpm 11.20.0 cannot run at all on Node <22.
**Resolved, not deferred:** `nvm` was already installed on this machine
(just not aliased/used yet). Installed Node 22.23.2 via `nvm install 22`,
set it as `nvm alias default 22`, and added `.nvmrc` (`22`) to the repo so
`nvm use` picks it up automatically in any properly-configured shell. The
one remaining friction: this harness's `Bash` tool starts a fresh, non-login
shell per call, so `nvm use` doesn't persist automatically between tool
calls within a session. Each command that needs Node 22 currently sources
`~/.nvm/nvm.sh` and runs `nvm use 22` explicitly first. A real terminal
session (or a shell profile with `nvm use` wired to `.nvmrc` on `cd`, e.g.
via `avn` or a `.bashrc` hook) won't have this friction.

### `packages/licence-check`: production vs. build-tooling license scope
First real run of the gate against actual installed packages caught a live
case worth recording rather than silently special-casing: `vitest@4.1.10`
(pinned, spec §2) hard-depends on `vite@8.2.0`, which hard-depends on
`lightningcss` (and its platform binary `lightningcss-linux-x64-gnu`), both
MPL-2.0, a copyleft-adjacent license `DENIED_PATTERNS` correctly flags.
This is unavoidable while using vitest as pinned; it is not optional or
prunable (confirmed: `lightningcss` is a plain `dependencies` entry in
vite's own `package.json`, not `optionalDependencies`).
**Design decision, not a policy weakening:** `packages/licence-check/src/cli.ts`
now runs the classifier twice: once scoped to `pnpm licenses list --prod`
(what a consumer actually installs and runs: "dependencies" +
"optionalDependencies") as the **hard, blocking gate**, and once over the
full graph (prod + dev + optional) to surface dev-only findings as
**warnings only**. Rationale: devDependencies are never bundled into a
deployed Periplo service, and MPL-2.0's actual obligation is file-level
(share modifications to *that* file if distributed) rather than viral onto
surrounding code. Using it unmodified as a test/build tool doesn't create
the risk spec §1 is guarding against (a copyleft obligation reaching the
*operated* service or its self-hosted deployments). A strict AGPL/GPL/LGPL
hit would still warn the same way if it only appeared in devDependencies,
but the classifier itself (`classify.ts`) is unchanged and still denies
every copyleft family unconditionally when it's in the shipped graph.
Verify with `pnpm licence-check` once Phase 3 adds real runtime
dependencies (`hono`, `@x402/stellar`, etc.), which is when this distinction
starts actually mattering.

## Phase 0: scope not built (by design, not by omission)

Nothing in this category yet. Phase 0 as scoped (§5) is monorepo tooling +
baseline capture; both are complete for what's reachable without the
external accounts above.

## Phase 2: environment divergences and real findings

Supabase project provisioned and credentials supplied directly in the build
session (2026-08-07). **Handling:** credentials went straight into a local
`.env` (gitignored, never committed, verified with `git status --porcelain`
and `git check-ignore -v .env` before every commit this phase) and into this
repo's GitHub Actions secrets (`gh secret set`, values piped via stdin, never
put in an argv or echoed). **Rotation note:** the DB password and both
service-role/anon JWTs were pasted as plaintext chat content, which may be
retained in conversation history outside this repo's control. Rotating
them (Supabase dashboard → Settings → Database / API) once Phase 2's
migrations are confirmed stable is good hygiene, not an emergency, since
nothing else has had access to them.

### Direct Postgres connection (port 5432) is unreachable from this sandbox
`db.<ref>.supabase.co` resolves **IPv6-only**, and this sandbox has no IPv6
egress at all (verified: `curl -6` to an external IPv6 host also fails, not
just to Supabase). `supabase db push --db-url <direct-url>` failed with
`ECONNREFUSED` on the IPv6 address before any DNS/auth issue was even
reached. **Fix:** used the transaction-pooler connection instead (port 6543,
`aws-0-ca-central-1.pooler.supabase.com`, resolves IPv4), which Supabase
itself documents as the recommended path for IPv4-only environments. All
migrations and integration tests in this phase went through the pooler.
Plain DDL (CREATE TABLE/INDEX/POLICY, no CONCURRENTLY, no advisory locks)
worked fine through it, no caveats hit in practice. If a future phase needs
the direct connection specifically, this sandbox is the blocker, not Supabase.

### `to_tsvector('english', text)` is not IMMUTABLE: can't use it directly in a generated column
The master spec's literal SQL (§5 Phase 2) defines `fts` as
`generated always as (to_tsvector('english', ...)) stored`. PostgreSQL's
two-argument `to_tsvector(regconfig, text)` is marked STABLE, not IMMUTABLE
(the named text search configuration could theoretically change), and
generated columns require an IMMUTABLE expression. This is a standing,
well-known PostgreSQL limitation, not something specific to Supabase or this
schema. **Fix, applied proactively rather than after a failed migration:**
wrapped it in `periplo_fts(text) returns tsvector language sql immutable`,
which is a safe promise here because `'english'` is a literal, never a
variable, in this project. See `supabase/migrations/*_resources.sql` for
the full reasoning inline.

### Plain `unique (url, route_template, tool_name)` doesn't dedupe the way the spec intends
Standard SQL `UNIQUE` treats `NULL` as distinct from `NULL`, so two HTTP
listings sharing `(url, route_template)` with `tool_name` NULL in both rows
would NOT collide and could both be inserted, silently defeating "one
catalog entry per resource." **Fix:** `unique nulls not distinct (...)`
(PostgreSQL 15+, supported on Supabase's managed Postgres, confirmed by
the migration applying cleanly). Not in the master spec's literal SQL;
added and documented rather than reproducing a schema bug verbatim.

### `auto_expose_new_tables` defaults to off: RLS policies alone aren't enough
Supabase's current default (confirmed via `supabase init`'s generated
`config.toml` comment, not assumed) does **not** auto-grant the
`anon`/`authenticated` Data API roles access to newly created tables. An RLS
policy with no matching `GRANT` is unreachable dead code, PostgREST rejects
the request at the grant level before RLS is even evaluated. **Fix:**
explicit `grant select on resources to anon, authenticated;` (plus
`grant usage on schema public`) alongside the RLS policy. Verified end to
end with real HTTP requests (anon SELECT 200, anon INSERT 401 RLS violation,
service-role INSERT 201) before writing the automated test suite, and again
via the automated `resources.integration.test.ts` suite, which passes for
real against the live project (`pnpm test`, gated by
`SUPABASE_URL`/`SUPABASE_ANON_KEY`/`SUPABASE_SERVICE_ROLE_KEY`, present in
this repo's GitHub Actions secrets and in local `.env`).

### `@supabase/supabase-js@2.112.2`'s generic types silently collapse to `never` with an `interface`
Not a Supabase-specific bug, a general TypeScript behavior that happens to
bite hard here. `postgrest-js`'s `.from()` resolves its row/insert/update
types via a conditional type that checks `Row extends Record<string,
unknown>`. A named `interface` does **not** satisfy that check the way a
`type` object literal does, even though both are otherwise structurally
identical and an `interface` value assigns to `Record<string, unknown>`
just fine directly. The failure mode is silent and confusing: every
`.from("resources")` call's inferred argument/result type quietly becomes
`never` instead of raising a type error pointing at the real cause.
Diagnosed empirically with an isolated conditional-type repro, not by
guessing. See `packages/bazaar/src/db/client.ts`'s comments. **Fix:**
`Database` and `ResourceRow` are declared with `type`, not `interface`.
Worth remembering for any future generated-types file (Phase 4/5 will need
richer row types as the schema grows).

## Phase 3: environment divergences and real findings

### Circle's testnet USDC faucet has no API: blocks using real testnet USDC for an automated settlement
`faucet.circle.com` requires a browser and reCAPTCHA; there is no
programmatic endpoint (checked directly, not assumed, see the WebFetch
result in this phase's session). This session can't complete that flow.
**Resolved, not deferred:** issued a self-owned test SEP-41 token instead
(`PTEST`, classic asset wrapped as a Stellar Asset Contract via `stellar
contract asset deploy`, no custom contract code needed) and used it for
the Phase 3 gate's settled transaction. `@x402/stellar`'s exact scheme
treats the asset address as a parameter; nothing in the facilitator's
logic is USDC-specific. Getting a real testnet-USDC-funded account (via
the faucet, which needs a human) would let a future session additionally
prove it works with the canonical asset. Not required for the gate, since
the gate asks for *a* settled transaction hash, not specifically a USDC
one, but worth doing before claiming full parity with the reference
facilitator's asset support.

### Paying a classic asset back to its own issuer is a burn, not a transfer
First settlement attempt used the test asset's own issuer account as
`payTo`. Under classic Stellar semantics, sending an asset to its issuer
redeems/burns it. The Stellar Asset Contract (SAC) bridge correctly
represents this as a `burn` event (`topics: [burn, from, asset_code]`),
not a CAP-46 `transfer` event (`topics: [transfer, from, to, asset]`).
`@x402/stellar`'s `validateSimulationEvents` requires a `transfer` event
matching sender/recipient/amount exactly and rejects anything else
(`invalid_exact_stellar_payload_event_not_transfer`), working as
designed; the bug was in the test setup, not the library. **Fix:** use a
genuine third-party account, never the asset's own issuer, as `payTo`.
Diagnosed by decoding the real simulation's diagnostic events directly
(`Address.fromScAddress`/`scValToNative` over the raw XDR) rather than
guessing from the error string alone, worth doing again if a similarly
opaque `invalid_exact_stellar_payload_event_*` reason shows up later.

### A classic-asset-backed SAC still requires a classic trustline on both ends
Also discovered while diagnosing the above: transferring a classic-asset
SAC token to an account with no trustline for that asset fails outright
(`HostError: Error(Contract, #13)`, `"trustline entry is missing for
account"`). SAC does not let a classic asset bypass trustlines for plain
G-accounts; that bridging only happens once the trustline exists. A
genuinely Soroban-native token (not a classic-asset wrapper) wouldn't have
this requirement, but this project's test asset is classic-backed since
`stellar contract asset deploy` is what's actually available without
writing a custom contract. **Fix:** the test seller account establishes a
`PTEST` trustline before receiving the demo payment (see
`apps/facilitator/scripts/settle-demo.ts` and the accounts recorded in
`.env`). Real testnet/mainnet USDC is also classic-asset-backed, so a real
x402 seller integrating against USDC needs the same trustline step. This
is exactly the "an account needs a trustline before it can receive a
SEP-41 asset... surface it as a distinct, actionable error" case spec §2
already calls out; worth building that error path explicitly in a later
phase (Phase 4 seller helpers, or the hub's `/buyers` trustline-step docs).

### `@x402/stellar`'s facilitator `ExactStellarScheme` is a different export than the client one: same class name, different subpath
The package's main entry (`@x402/stellar`) re-exports `ExactStellarScheme`
from `./exact/client` (the CLIENT variant, `SchemeNetworkClient`, used to
*build* a payment). The FACILITATOR variant (`SchemeNetworkFacilitator`,
used to *verify/settle* one) is a separate subpath export,
`@x402/stellar/exact/facilitator`. Importing the wrong one from the main
barrel type-errors in a confusing way (TypeScript reports the argument as
missing `ClientStellarSigner` properties, not "wrong class") rather than
pointing at the real cause. **Fix:** `apps/facilitator/src/core.ts`
imports explicitly from the `/exact/facilitator` subpath, with a comment
explaining why, specifically so this isn't "fixed" back to the barrel
import later by someone who sees `ExactStellarScheme` unqualified and
assumes there's only one.

### No Node HTTP adapter for Hono chosen yet: needed before real deployment
`apps/facilitator` is tested via Hono's own `app.request()` (in-memory,
no real port), sufficient for Phase 3's gate (verify/settle logic +
one settled transaction), but running this as an actual listening service
(Fly.io, Phase 10, or any "hosted"/"self-hosted" deployment path) needs a
Node HTTP adapter, most likely `@hono/node-server` (official, small,
MIT-licensed). Not added yet: it's a new dependency outside spec §2's
manifest, and working rule 6 says ask before adding one rather than
sneaking it in alongside unrelated work. Flagging here now so it's a
known, upcoming decision rather than a surprise at Phase 10.

### `Exact scheme requires areFeesSponsored to be true`: client-side requirement, not just facilitator-side
`@x402/stellar`'s client `ExactStellarScheme.createPaymentPayload` throws
outright if `paymentRequirements.extra.areFeesSponsored` isn't `true`.
The client needs to know fee sponsorship is happening so it doesn't try to
provision its own fee payment when building the transaction. Found by
running the demo script and reading the real error, not documented
anywhere obvious beforehand. Any seller-side helper built in Phase 4 that
constructs `paymentRequirements` for Stellar must set this field, or every
client using `@x402/stellar` against it will fail before even reaching the
facilitator.

## Phase 10: started early, at explicit request (deployment, not the full phase)

`apps/facilitator` is live on Fly.io (`stellar:testnet` only) at
`https://periplo-testnet.fly.dev`, deployed 2026-08-07 out of the normal
phase sequence because the project owner asked for it directly. **This is
not "Phase 10 complete"**: it's the one piece (facilitator deployment)
pulled forward; the rest of Phase 10's scope (an equivalent
`periplo-mainnet` app, the runbook, both example integrations, hardening
pass, Matrix/Mastodon channels) is still not built, and shouldn't be
inferred from the app being live. Two more pieces were pulled forward
the same way on 2026-09-03, found real and missing against a competitor
comparison rather than assumed still-fine because they're "later phase":
the channel-account pool (spec §2/§7) and `GET /status` (spec §8/§9,
"monitoring beyond a bare `/health`, public telemetry endpoint" above,
now real, not a gap), both real, tested, and evidenced (the 4-transaction
channel-pool burst in `conformance/RESULTS.md` dated 2026-09-03, and
`apps/facilitator/src/telemetry.test.ts` plus the `GET /status` cases in
`app.test.ts`). A third piece landed the same round: `GET /demo/play`,
a wallet-less one-click payment demo, real and verified twice end to end
from Node (real settled transactions), with one honest, stated gap: a
real browser click-through hasn't happened, this session's own sandbox
lacks the system libraries (`libnspr4`, `libnss3`) a real headless
Chromium needs to launch, and there's no root access to install them.
`scripts/demo-play-browser-verify.mjs` is real and ready to close this
gap in any environment with a working Chromium (still not run
successfully in this session; the Fly account gap below is a different,
now-resolved blocker, not this one).

**Resolved the same day: the Fly account gap.** The user re-authenticated
`fly` as the Fly account that owns `periplo-testnet` (this session's own CLI
had been on a different Fly account, a third distinct one on top of the two
this file already documented recurring). All three pieces above deployed for real
(`STELLAR_TEST_BUYER_SECRET`/`STELLAR_CHANNEL_ACCOUNT_SECRETS_TESTNET`
set via `fly secrets set`, `fly deploy`), verified against the live URL,
not just the deploy command's own success output: `GET /supported`
lists all 4 channel-pool signer addresses, `GET /demo/play` serves the
real page, and `apps/facilitator/scripts/demo-play-full-verify.ts` run
against the live URL settled two real transactions. One real bug found
deploying, not before: `GET /status` kept reporting an empty
`lastSettledTransaction` after the first live settlement, because
`telemetry.recordSettlement` only lived in the HTTP `/settle` route,
which self-facilitation (the route `/demo/play` actually pays) never
calls. Fixed (`demo-resource.ts`'s own `onAfterSettle` hook now records
it too, commit `9f0067a`), redeployed, re-verified: the second live run
shows up correctly. Also caught and fixed before this deploy, not
after: `demo-play.ts` resolves its esbuild entry point relative to its
own `import.meta.url`, which works under `tsx` in dev but has no
`browser/` sibling in the compiled `dist/` the Docker image actually
runs (`src/browser` is intentionally excluded from the facilitator's
own Node-targeted `tsc` build). Fixed in the Dockerfile itself
(`RUN cp -r apps/facilitator/src/browser apps/facilitator/dist/browser`,
commit `4954869`), verified by rebuilding the real compiled output
locally and running the actual `dist/serve.js` (not `tsx`) before ever
deploying. Full evidence (all four real transaction hashes) in
`conformance/RESULTS.md`.

**Same day, immediately after: a real user's real click found a real
third bug, and the browser-verification gap above got closed for
real.** A person actually clicked "Pay and convert" on the live page
and hit an error: `resourceUrl`'s default carried no `value`/`from`/
`to` query string. The 402 challenge succeeds either way (price doesn't
depend on the query), so an unparameterized request paid in full and
only then 400'd on the actual conversion, a real visitor charged for
nothing. `demo-play-full-verify.ts` never caught this, since it always
hardcoded its own query string directly, never exercising
`loadDemoPlayConfig`'s real default. Fixed by baking the query string
into `resourceUrl` itself (commit `71c595b`); needed exporting
`loadDemoPlayConfig` and, for that, an entrypoint guard around
`main()` in `serve.ts` so importing it for the new `serve.test.ts`
doesn't try to boot a real server. Redeployed, then closed the
DOM-wiring gap for real, not just argued as low-risk: this session's
sandbox still has no root to `apt install` the missing Chromium system
libraries (`libnspr4`, `libnss3`, others), but `apt-get download`
fetches individual `.deb` files without privileges, `dpkg-deb -x`
extracts them without privileges too; pointed `LD_LIBRARY_PATH` at the
extracted directory and ran `scripts/demo-play-browser-verify.mjs` for
real, in an actual launched Chromium, against the real live URL —
navigated to `/demo/play`, clicked the real button, waited on the real
DOM, got a real result, transaction `5d020d7e...`, Horizon-confirmed.
Five real transaction hashes now in `conformance/RESULTS.md` for this
round alone.

- **`@hono/node-server@2.1.0` (MIT) added.** This closes the gap flagged
  in Phase 3's entry above ("No Node HTTP adapter for Hono chosen yet").
  It's outside spec §2's manifest; flagged here rather than silently
  bundled into an unrelated commit, per working rule 6, even though the
  deploy itself was the explicit ask that made it necessary.
- **`periplo-mainnet` does not exist and won't until a real mainnet
  fee-sponsor key exists.** Spec §2/§13 commit to both networks, but
  nothing about "deploy now" implies fabricating mainnet infrastructure
  ahead of having real funds/a real key to back it. That's a distinct,
  later decision, not an oversight.
- **Fly API token** was pasted directly in the build session (same
  handling as the Supabase/Stellar secrets before it): stored in local
  `.env` only, never committed. Not actually needed for this deploy: the
  `fly` CLI on this machine was already authenticated interactively
  (as the Fly account that owns the app), kept for a possible future GitHub
  Actions deploy workflow instead.
- **Docker build context is the whole monorepo** (`Dockerfile.facilitator`
  builds only `apps/facilitator`, but needs the workspace root for pnpm
  resolution). Added `.dockerignore` to keep `node_modules`/`dist` out of
  the ~217MB context Fly's builder otherwise re-uploads on every deploy.
- **Circle testnet USDC: first funding attempt bounced, cause found and
  fixed.** The project owner funded `STELLAR_TEST_BUYER_PUBLIC` via
  Circle's faucet ("Tokens sent, 20 testnet USDC..."), but the buyer
  account had no classic trustline for USDC yet, same "trustline entry
  is missing" failure mode discovered with `PTEST` earlier in this phase,
  now confirmed to apply to real USDC too (it's classic-asset-backed, not
  a pure Soroban-native token). Checked directly: no balance, no claimable
  balance either, so the transfer genuinely never landed rather than
  being recoverable. **Fixed**: established the trustline
  (`USDC:GBBD47IF6LWK7P7MDEVSCWR7DPUWV3NY3DTQEVFL4NAT4AQH3ZLLFLA5`, the
  real issuer, read authoritatively off the SAC contract's own `name()`
  call rather than guessed) via the `stellar` CLI using the buyer's key
  this project already holds. Balance is `0.0000000 USDC`, ready to
  receive, needs a resend from the faucet now that the trustline exists.

## CI was broken from Phase 1 through Phase 3: the local gate was real, the CI gate wasn't

`gh run list` showed every push since Phase 1 failing in ~0 seconds with
zero jobs scheduled. GitHub rejected `.github/workflows/ci.yml` outright
before running anything, including the `build` job (typecheck/lint/test/
licence-check). Root cause: the `osv-scan` job's reusable-workflow call
(`google/osv-scanner-action/.../osv-scanner-reusable.yml@v2.3.8`,
originally flagged in Phase 0's own commit as unverified) had a workflow
file issue GitHub's schema validator rejects, and that rejection takes
down the *entire* file, not just that one job. This was flagged as a risk
in every phase's `docs/DEFERRED.md` entry ("has not yet had a live CI run
to confirm the call signature") but never actually followed up on until
now, checking `gh run list` directly rather than continuing to trust the
local `pnpm ci` result as a stand-in for CI passing. **Fix**: removed the
broken `osv-scan` job outright rather than guess at the correct reusable-
workflow syntax a second time; `build` now runs on its own. Re-adding a
working `osv-scan` job (spec §6/§7 want it as a hard gate) is still open;
next attempt should be validated against a real, isolated push before
being trusted, not assumed correct from the manifest/release-tag check
alone.
**Lesson for future phases**: "the gate passed" claims in commit messages
so far were accurate for the *local* gate every time (never fabricated),
but conflated with CI passing when CI silently wasn't running at all.
Worth periodically checking `gh run list` directly rather than only
running `pnpm ci` locally and assuming CI mirrors it.

## Fly deployment follow-ups (from live testing after the initial deploy)

- **Scaled from 2 machines to 1** (`fly scale count 1`). Fly creates 2 by
  default for zero-downtime rolling deploys; for a testnet demo (not yet
  under any uptime SLA, that's Phase 10's runbook territory) 1 is
  simpler and cheaper, and `min_machines_running = 1` in
  `fly.facilitator.toml` already covers "never 0." Both machines were
  observed idling to `stopped` between requests regardless
  (`auto_stop_machines = "stop"`) and Fly's proxy auto-starts one on
  demand, confirmed this works via a real cold request, not assumed.
- **Added a `GET /` route.** Hitting the bare host 404ed with no context
  (nothing was ever routed there), not a bug, but confusing without
  explanation, so it now returns a small JSON description of the service
  and its real endpoints. No new claims: it's honest about what exists
  today (no frontend, no `/browse` etc.).
- **`fly deploy` prints a "not listening on the expected address" warning
  every time** even with `@hono/node-server`'s `hostname` explicitly set
  to `0.0.0.0`. Real external `curl` requests succeed regardless (checked
  after both the warned and the explicit-hostname deploys), treated as a
  startup-timing false positive in Fly's smoke-check, not a real
  reachability problem, since the actual behavior (not the warning text)
  is what was verified.

## CI, part 2: resolved. The billing block was private-repo Actions minutes

After removing the broken `osv-scan` job, the next push's run parsed and
scheduled `build` (12s runtime, not 0s, confirming the workflow-file fix
worked), but the job itself never started:
> "The job was not started because recent account payments have failed or
> your spending limit needs to be increased."

Cause, per the project owner: the repo was private, and private repos on
GitHub only get a limited free tier of Actions minutes before requiring
billing/a spending limit; public repos get free standard-runner minutes
without that constraint. **Fixed** by making `Eras256/Periplo` public.

**Verified twice, not assumed once:**
1. `gh run rerun 31222094411` after the visibility change actually
   executed this time (`in_progress`, not an instant billing-error
   failure) and finished `build`, success, 24s.
2. The project owner (correctly) pushed back on trusting a manual rerun
   alone, a rerun can behave differently from an organic trigger. The
   very next real `push` (no `rerun` involved) triggered its own new run,
   `31222406798`, and it also passed for real: `build` in 23s
   (`https://github.com/Eras256/Periplo/actions/runs/31222406798`).

Also re-verified the earlier "workflow file issue" runs weren't actually
the same billing problem wearing a different message, rather than just
asserting the two-cause story: `gh api
repos/Eras256/Periplo/actions/runs/31220202302/jobs` (a pre-fix, `push`-
triggered run) returns `{"total_count":0,"jobs":[]}`, literally zero job
entries created. That's structurally different from the billing block,
which *does* create a `build` job entry and then blocks it from starting.
Two distinct GitHub error messages, two distinct job-scheduling shapes,
two independent fixes, both confirmed against real runs, not one
misdiagnosed cause redescribed. CI is confirmed green as of 2026-08-07.

One harmless annotation surfaced on the passing run: `actions/checkout@v4`,
`actions/setup-node@v4`, and `pnpm/action-setup@v4` are running on a
deprecated internal Node 20 runner-action-runtime (unrelated to this
project's own Node 22 pin, it's about the version GitHub's runner uses to
execute the action's own code). Not urgent; worth bumping to newer action
versions eventually.

Re-adding a working `osv-scan` job (spec §6/§7 want it as a hard gate) is
still open; next attempt should be validated against a real, isolated
push before being trusted, same caution as before.

**Update 2026-08-08: the billing message resurfaced once, transiently.**
After four consecutive green organic-push runs, one run
(`31241780851`, the `docs(spec)` commit) failed with the exact same
"recent account payments have failed or your spending limit needs to be
increased" message, with the repo confirmed still public
(`gh repo view --json isPrivate` → `false`) at the time. The very next
push, 8 minutes later with no changes to repo settings, succeeded
normally (`31242097451`). Read as a transient false-positive in GitHub's
billing check itself, not a regression back to the private-repo state,
worth knowing this can happen even on a public repo, not worth blocking
on. If it recurs persistently (not just once), revisit.

## README's `upto` link: resolved before Phase 6 formally started

README's "What Periplo is (planned)" section linked `upto`'s spec to
[`spec/`](../spec/), a directory that has never existed in this repo, a
dead link in the most-read file. Turned out moot rather than needing a
wait for Phase 6: the network spec was already opened upstream directly
against `x402-foundation/x402` (PR #3098, issue #3097, both verified real
via the GitHub API: title, draft status, and the same three open
on-chain assumptions this repo's own `docs/SPEC.md` §6 names), work done
in parallel outside this repo's own phase sequence. README now links the
PR directly instead of a local directory.

**Deliberately not mirrored into this repo** (`spec/scheme_upto_stellar.md`
does not exist here, and won't): the RFP deliverable is "merged upstream
into the x402 package" (`#3098` is still open, not merged, as of
2026-09-27), so the PR itself is the evidence, not a local
copy. A duplicate invites drift (one copy updates, the other doesn't) and
a fork of a spec that's actively being upstreamed reads oddly, the
spec's place is upstream. The Soroban contract
(`contracts/upto-settlement`) was still genuinely not started as of this
note. See "Phase 6: environment divergences and real findings" below
for what actually got built.

## Phase 4: environment divergences and real findings

### `Dockerfile.facilitator` didn't build or ship `@periplo/bazaar`: first Phase 4 deploy crash-looped

Found live, immediately after pushing and redeploying: `apps/facilitator`
never had a real runtime dependency on `packages/bazaar` before Phase 4, so
`Dockerfile.facilitator` never built or copied it. Two failures, found and
fixed in sequence against the real deployment, not caught by `pnpm typecheck`
locally (which uses `tsc -b`, project-reference mode, and doesn't need
`dist/` to exist):

1. **Build stage:** `pnpm --filter @periplo/facilitator build` runs plain
   `tsc -p tsconfig.json` (not `-b`), which does not auto-build referenced
   projects. It resolves `@periplo/bazaar` via normal node-module
   resolution against `packages/bazaar/package.json`'s `types` field
   (`dist/index.d.ts`), which didn't exist because nothing had built
   `packages/bazaar` in the image. Fixed: `RUN pnpm --filter @periplo/bazaar
   build` before the facilitator build step.
2. **Runtime stage:** even after the build succeeded, the deployed machine
   crash-looped on `ERR_MODULE_NOT_FOUND: Cannot find package
   '@supabase/supabase-js'`. pnpm gives every workspace package its own
   `node_modules/` of symlinks to its own direct dependencies (resolved
   from the shared store), and `packages/bazaar/node_modules` was never
   copied into the runtime stage, only `dist/` and `package.json`. Fixed by
   adding that copy too.

Both fixes verified against the real deployment: `curl
https://periplo-testnet.fly.dev/supported` returned `"extensions":["bazaar"]`
only after the second deploy, not the first. The first one looked
successful in `fly deploy`'s own output (image built, pushed) right up
until the machine actually tried to boot the new code.

### Bare `pnpm ci` was never actually running the gate script

`pnpm ci` is a reserved pnpm CLI command (`pnpm help ci` → alias for
`clean-install`: `pnpm clean` + `pnpm install --frozen-lockfile`), which
shadows the root `package.json` script of the same name. Bare `pnpm ci`
silently reinstalls dependencies instead of running
`typecheck && lint && test && licence-check`, with nothing pointing at the
shadowing. `pnpm run ci` (explicit `run`) forces package.json resolution
and is the command that actually runs the gate. Caught running this exact
command during Phase 4; low severity in practice, `.github/workflows/ci.yml`
already invokes each step individually (`pnpm typecheck`, `pnpm lint`,
`pnpm test`, `pnpm licence-check`), never the compound `pnpm ci`, and this
session's own phase-gate verifications ran the individual commands too, so
no phase's gate was actually unverified, just documented with a command
that would have silently done the wrong thing if anyone (a reviewer
reproducing the gate locally, most plausibly) had copy-pasted it verbatim.
`CLAUDE.md`'s Commands section now says `pnpm run ci`.

Full detail in `docs/INTEROP.md` (spec §5 Phase 4 requires recording
divergences there specifically); summarized here for the running log.

### Built on `@x402/extensions/bazaar@2.21.0`, not a from-scratch implementation

Discovered mid-phase, before writing any extension-handling code: the
official x402 project ships a complete facilitator-side and resource-server-
side implementation of the bazaar discovery extension as a real published
npm package (`@x402/extensions`, same `2.21.0` pin as `@x402/core`/
`@x402/stellar`, Apache-2.0, confirmed clean by `pnpm licence-check`
including its transitive deps). `apps/facilitator/src/discovery.ts` is built
on `extractDiscoveryInfo`/`validateDiscoveryExtension`/
`validateDiscoveryExtensionSpec` from that package rather than
reimplementing the extension's JSON-Schema validation and info-extraction
logic, same "don't reimplement the wire protocol" principle spec §1
applies to verify/settle, extended here on the session's own judgment
(the package wasn't in the original manifest, so this is flagged per
working rule 6, not silently added).

**Dependency-weight tradeoff, accepted not hidden:** `@x402/extensions`
bundles several extensions in one package (`bazaar`, `builder-code`,
`offer-receipt`, `sign-in-with-x`, `payment-identifier`), and its
`package.json` declares dependencies for all of them: `viem`, `jose`,
`@signinwithethereum/siwe`, `tweetnacl`, `@noble/curves`, even though
`apps/facilitator` only imports the `./bazaar` subpath. pnpm installs the
full declared dependency graph regardless of which subpath is actually
imported, so these ship in `node_modules` (and the Docker image) unused.
No tree-shaking boundary exists at the package-manager level to avoid
this without vendoring or a bundler step, and every one of those
transitive deps passed the license gate on inspection (predominantly MIT).
Not revisited unless image size becomes an actual operational problem.

### `checkRouteTemplate` (Phase 1) used instead of upstream's `isValidRouteTemplate`

One deliberate divergence from "build on the official package": Periplo's
own Phase 1 `routeTemplate` validator (bounded-repeated percent-decoding,
backslash normalization) is used instead of the official package's
single-decode-pass equivalent, because upstream's version doesn't satisfy
spec Phase 4's gate (hard-reject a hostile `routeTemplate`, no catalog row.
Upstream instead silently drops the field and catalogs the unparameterized
URL). Full comparison table in `docs/INTEROP.md` §1.

**Two genuine upstream findings.** The `mcp://` one is filed; the
single-decode one is not yet, pending the project owner's go-ahead
(flagged per working rule 6, not done unilaterally):

1. The single-decode gap above is a real (if narrow) catalog-poisoning
   surface for anyone calling `isValidRouteTemplate` directly. Not filed.
2. `extractDiscoveryInfo` breaks on the `mcp://tool/{toolName}` URL form
   that `docs/SPEC.md` §4 (and the x402 e2e test itself) documents as the
   *expected* MCP resource URL. `mcp:` isn't a WHATWG special scheme, so
   `new URL(...).origin` returns the literal string `"null"`, and upstream's
   canonical-URL logic (`${url.origin}${url.pathname}`) produces
   `"null/toolName"`. Found empirically via the real Supabase integration
   test (`discovery.integration.test.ts`), not by inspection, first run
   against live Supabase surfaced a wrong catalog `url` value. Worked
   around in `discovery.ts` by reconstructing the URL from `toolName`
   directly, bypassing the broken helper's output for MCP resources only.
   **Filed:** [x402-foundation/x402#3121](https://github.com/x402-foundation/x402/issues/3121).
   **Fix open:** [x402-foundation/x402#3138](https://github.com/x402-foundation/x402/pull/3138),
   built to the scheme-agnostic shape a reviewer (whawk46) suggested in the
   issue thread rather than an `mcp://`-specific patch, with a second
   regression test on an unrelated made-up scheme so the fix cannot
   regress the same way for the next undocumented scheme. Full detail in
   `docs/INTEROP.md` §2.

### `resource.serviceName`/`tags`/`iconUrl` are sanitized by upstream but have no catalog column yet

`@x402/extensions/bazaar`'s `extractDiscoveryInfo` already soft-drop-sanitizes
these three optional fields internally (`sanitizeResourceServiceMetadata`,
`isValidServiceName`, `sanitizeTags`, `isValidIconUrl`, printable-ASCII,
length caps, SSRF-defended URL checks) and returns them on the
`DiscoveredResource` it hands back. Periplo's `resources` table
(`supabase/migrations/20260807202307_resources.sql`, Phase 2, unchanged
since before this phase read the upstream package) has no columns for any
of the three, so `discovery.ts` currently reads but discards them rather
than storing something a migration hasn't been gated for. Not silently
dropped: the values are real and sanitized, there's just nowhere to put
them yet. If added later, this is the concrete case `packages/bazaar`'s
`softDropFields` mechanism (Phase 1, already built and tested, currently
unused by Phase 4's own path) was built for: three independently-optional
fields where one failing validation shouldn't reject the other two or the
listing as a whole.

### `docs/SPEC.md` §4's search param name (`q`) doesn't match the real wire (`query`)

Found while reading the official client types (`SearchDiscoveryResourcesParams`)
and the x402 e2e test's own probe, both use `query`. `docs/SPEC.md` was
written from a wire-contract description before this phase actually opened
the source, and Phase 0's own baseline probe against `x402.org` used `?q=`
too, but that request 404'd regardless (no discovery endpoints exist there),
so the wrong param name was never exercised against anything live. Not
corrected in `docs/SPEC.md` yet, `GET /discovery/search` itself is Phase 5
scope, not built in Phase 4. Recorded in `docs/INTEROP.md` §3 so Phase 5
starts from the right name instead of re-deriving it.

## Phase 5: environment divergences and real findings

### Embedding model: no provider was pinned; picked and verified this phase

`docs/SPEC.md` §5 specifies pgvector/HNSW/RRF exactly but never names an
embedding model or provider, a real gap, not an oversight to defer.
Resolved with the project owner (not decided unilaterally): a local model,
no API key, no per-call cost, no new CI secret. Landed on `fastembed`'s
`BGESmallENV15` (384-dim, MIT), not `@huggingface/transformers`:

- `@huggingface/transformers` hard-depends on `sharp` for vision-model
  utilities this project never uses. `sharp`'s prebuilt `libvips` binary
  (`@img/sharp-libvips-linux-x64`) is LGPL-3.0-or-later, a hard `deny`
  under `packages/licence-check`'s own `DENIED_PATTERNS` (spec §1: no
  copyleft anywhere in the *shipped* dependency path), confirmed by
  actually adding the package and running `license-checker` against it,
  not assumed from the package's own top-level `Apache-2.0` claim.
- Considered hand-rolling with `onnxruntime-node` + `@huggingface/
  tokenizers` directly (both clean-licensed) to avoid `sharp` entirely.
  Abandoned: `@huggingface/tokenizers`'s own `Tokenizer` constructor takes
  pre-parsed `(tokenizer, config)` objects, not a `tokenizer.json` file
  path. The file-loading/config-splitting logic lives inside
  `@huggingface/transformers` itself, unexported. Reimplementing HF's own
  tokenizer-config parser from scratch risked a silent correctness bug
  (subtly wrong tokenization degrading search quality with no error
  thrown) for a phase whose entire gate is *measured* quality, a worse
  trade than the alternative below.
- `fastembed` (MIT throughout, verified with `license-checker` before
  adopting it) carried, at `2.1.0`, an unpatched, no-non-major-bump-available
  critical `tar@^6.2.0` advisory (path traversal / arbitrary write on archive
  extraction, `npm audit`, `fixAvailable: {isSemVerMajor: true}` to
  `tar@>7.5.20`, which `fastembed@2.1.0`'s own dependency range couldn't
  reach). Accepted at the time: the archive `tar` extracted was the model
  file this code itself requested from a name it pins
  (`EmbeddingModel.BGESmallENV15`), not attacker-supplied input, the same
  trust boundary every ONNX-model-downloading library in this space has,
  `@huggingface/transformers` included. **Resolved as of the `2.1.1` bump
  below: `fastembed` dropped `tar` entirely** (confirmed via its own
  published `package.json`), replacing the one-archive download with
  per-file downloads from Hugging Face via `@huggingface/hub`. Nothing
  left to accept here; this paragraph stays as history.

### `fastembed` upstream is archived, and its type declarations do not match its runtime

Found 2026-09-10 running the widened dependency review over Periplo's own
production graph. Two separate facts about `fastembed@2.1.0` (the current
`latest`, and what `packages/search` ships):

1. **`Anush008/fastembed-js` is an archived GitHub repository**
   (`archived: true`, last push 2025-12-15, verified directly via the
   GitHub API), so it is read-only: no issues can be filed and no fixes
   will land. There is no JavaScript successor (`fastembed-rs` and
   `fastembed-go` are separate projects by the same author; the Python
   `fastembed` is Qdrant's). npm's `fastembed` still resolves to this
   archived source.
2. **`FlagEmbedding.embed()` is typed `AsyncGenerator<number[][]>` and
   `queryEmbed()` `Promise<number[]>`, but both return `Float32Array` at
   runtime.** Root cause is the `as unknown[] as number[]` double cast at
   `src/fastembed.ts:481` on an `onnxruntime` float32 tensor's `.data`:
   `getEmbeddings`'s `data.slice(...)` and `normalize`'s `v.map(...)`
   both preserve `Float32Array` rather than producing a plain array. The
   practical bite is `JSON.stringify` serializing a result as
   `{"0":v,...}` instead of `[v,...]` (the same symptom in the repo's
   own closed issues #10 and #22, neither root-caused there). This was
   already hit and worked around in Periplo before this review:
   `packages/search/src/embed.ts` wraps every fastembed output in
   `Array.from(...)`, and that mitigation is load-bearing, not styling
   (already documented in `embed.ts`'s own comment and in `CLAUDE.md`'s
   list of traps).

**Status as of 2026-09-10: mitigation in place, no upstream action possible.**
An issue was drafted with the exact lines and a proposed `Array.from` fix;
filing was blocked by the archive. Longer-term this is a candidate to vendor
(MIT, ~500 lines of real logic in `src/fastembed.ts`) or replace, but
replacement is not trivial: the licence constraint documented above
(the `@huggingface/transformers` -> `sharp` -> LGPL `libvips` path that
`pnpm licence-check` hard-denies) is exactly why `fastembed` was chosen
over the more obvious alternative, and any replacement has to clear the
same Apache-2.0-only bar.

**2026-10-22, both facts above updated, confirmed live, not assumed.**
`gh api repos/Anush008/fastembed-js` still reports `archived: true`
today, but `npm view fastembed time --json` shows two releases landed
after the archive date anyway: `3.0.0` (2026-09-24) and `2.1.1`
(2026-09-30). So "no fixes will land" was wrong, or at least incomplete:
the GitHub repo being archived evidently doesn't block the maintainer's
own npm publishes. This surfaced because `2.1.0`'s model download broke
for real: its Google Cloud Storage bucket
(`storage.googleapis.com/qdrant-fastembed`) started returning `403
AccessDenied` to anonymous reads (confirmed with a plain `curl`, not
inferred from CI logs alone), so every CI run needing a fresh download
(any cache miss) failed `TAR_BAD_ARCHIVE` trying to untar the 403's XML
error body. Bumped to `2.1.1`, which downloads individual files from
Hugging Face via `@huggingface/hub` instead (no single archive, `tar`
dropped as a dependency entirely, so the advisory above is moot now, not
just mitigated). Also re-tested fact 2 empirically against `2.1.1`:
`passageEmbed`/`queryEmbed` now return a plain `Array`, not
`Float32Array`. `embed.ts` keeps the `Array.from(...)` wrapper anyway, as
a defensive no-op rather than removing it, since the published `.d.ts`
already proved wrong once. `CLAUDE.md`'s trap entry updated to match.
Not vendoring or replacing `fastembed`: the live fix removes the only
concrete problem (the broken download), the archived-repo risk is now
better understood (publishes still happen) rather than resolved, worth
revisiting only if a future release breaks again with nowhere to file
it.

### `resources.embedding` dimension corrected: 512 (Phase 2 placeholder) → 384

Phase 2 pinned `vector(512)` before any embedding model was chosen.
Migrated in place (`supabase/migrations/20260812080000_search.sql`) since
the column was all-NULL, Phase 4 never wrote embeddings, so there was no
data to lose. HNSW indexes can't survive an `ALTER COLUMN TYPE` on the
underlying vector column; the migration drops and recreates
`resources_embedding_idx` around the `ALTER`, verified by querying
`pg_indexes`/`pg_attribute` against the real project afterward, not
assumed from the migration succeeding silently.

### `onnxruntime-node`'s postinstall downloads a ~340MB CUDA binary by default on Linux/x64: skipped

Found by inspecting `du -sh` on the installed package after a plain
`pnpm install`: `libonnxruntime_providers_cuda.so` alone was 342MB, on a
CPU-only sandbox and a CPU-only Fly deployment (`shared-cpu-1x`, no GPU).
`onnxruntime-node`'s own install script supports
`ONNXRUNTIME_NODE_INSTALL_CUDA=skip` to avoid this; set as an env var
around `pnpm install` in `Dockerfile.facilitator` and
`.github/workflows/ci.yml`. One real gotcha while fixing this locally:
pnpm's content-addressable store caches a package's postinstall *output*,
not just its manifest. Re-running `pnpm install` with the env var newly
set did not re-trigger the download-skip until the store's cached copy of
`onnxruntime-node` was invalidated (`pnpm install --side-effects-cache=false`
after deleting `node_modules`). A fresh Docker build or CI runner has no
such pre-existing cache, so this only mattered for verifying the fix
locally, not for correctness of the actual fix.

Not addressed: the remaining ~208MB still bundles prebuilt binaries for
every platform (darwin, win32, linux/arm64) that this Linux/x64-only
deployment never uses. `Dockerfile.facilitator` copies the whole
`node_modules` tree regardless. A real, smaller follow-up (platform-scoped
pruning) if image size becomes an actual operational problem; not blocking
Phase 5's own gate.

### `fastembed`'s embedding output is a `Float32Array`, not the `number[]` its own `.d.ts` declares

Found against the real Supabase integration test, not from reading the
types: the first live write failed with `invalid input syntax for type
vector`, carrying a payload shaped like `{"0":v0,"1":v1,...}` instead of
`[v0,v1,...]`. Root cause: `JSON.stringify` serializes a `Float32Array` as
a plain object keyed by index, not as a JSON array, and `passageEmbed`/
`queryEmbed` both return `Float32Array` at runtime despite the package's
own type declarations saying `number[]`. Fixed with `Array.from(...)` in
`packages/search/src/embed.ts` before the vector ever reaches
`upsertCatalogResource`; documented inline so it survives a future
refactor. Verified against the live project afterward (insert, then a real
`periplo_hybrid_search` call, then delete), the fix, not just the absence
of a thrown error, is what got checked.

### The eval harness's synthetic catalog is hand-authored, not sampled from real cataloged resources

`eval/fixtures.ts`'s resources and `eval/golden.jsonl`'s queries are
written by hand, not harvested from `resources` table rows a real payment
cataloged. The live catalog doesn't yet have enough diverse, real
listings to build a meaningful graded set from (most rows so far are
Phase 3/4 test/demo artifacts, not a real marketplace). Each fixture is
still seeded through the real write path (`@periplo/bazaar`'s
`upsertCatalogResource`, the same function a real payment calls) and
embedded through the real model, only the *content* of what's being
cataloged is synthetic, not the mechanism cataloging it. Revisit once the
catalog has organic, diverse listings to sample from instead.

### The first eval set (20 resources, 40 queries) was too easy: a review caught it before it became the committed baseline

The original design put every resource in an unrelated domain (weather,
translate, currency, ...), so every query had exactly one plausible
candidate out of twenty wildly different options. That scored nDCG@10
0.9908, MRR 0.9875, a near-perfect result on a small, self-authored
golden set, which is a classic overfitting signal, not evidence the
ranker actually discriminates between similar options. Caught by review
before committing it as the baseline, not after.

Fixed by adding ~15 clusters of 2-5 genuine near-duplicate resources each
on top of the original 20 (`geocode` vs. `reverse-geocode`; `weather` vs.
`weather-forecast` vs. `air-quality` vs. `uv-index` vs. `weather-alerts`;
`send-email` vs. `send-sms` vs. `send-push`; and eleven more), and writing
queries designed to force real discrimination: paraphrases that share no
vocabulary with the *wrong* sibling resource, deliberately ambiguous
"convert"/"check"/"look up" queries tested against multiple plausible
candidates, and multi-relevant judgments (grade 3 for the best match,
grade 1 for a plausible-but-wrong sibling) instead of a single correct
answer per query. Final set: 55 resources, 300 graded queries.

The real, unmodified result: **nDCG@10 0.9346, MRR 0.9226**, a genuine
drop from 0.9908, reported as-is rather than tuned back toward the old
number (the person who flagged the overfitting risk explicitly said the
score dropping was an acceptable, expected outcome). A worst-query
breakdown (run once, not committed as a script) showed 231/300 queries
still scoring a perfect nDCG@10, 0/300 scoring zero (the ranker never
completely misses, some relevant result always appears, just not always
ranked first), and every one of the 69 imperfect queries was a genuine
near-duplicate confusion the clusters were built to surface, e.g.
`reverse-geocode` queries occasionally ranking plain `geocode` first, or
`weather` queries occasionally ranking `uv-index` first. That distribution
(mostly right, sometimes confuses close near-duplicates, never totally
lost) reads as a believable result for a real hybrid retrieval system,
which the original 0.99 did not.

### Not yet done: growing the golden set further, and load-hardening the search endpoint

Two engineering follow-ups this phase's gate does not require but a later
one should:

- The golden query set (55 resources, 300 graded queries) is planned to
  grow toward 500 graded queries, for stronger coverage of near-duplicate
  clusters beyond what's built so far and more stable nDCG@10/MRR numbers
  than 300 queries give.
- The search endpoint itself has not been hardened or tested under real
  load (concurrent request handling, embedding-model warm-up contention,
  Supabase connection pooling under sustained traffic). Phase 5's gate is
  ranking quality, not throughput, and production readiness on that axis
  is still open.

## Phase 6: environment divergences and real findings

### `stellar contract init`'s default layout double-nests the crate directory

Scaffolding with `stellar contract init contracts/upto-settlement --name
upto-settlement` produces `contracts/upto-settlement/contracts/upto-settlement/`,
a workspace-of-workspaces layout meant for repos with multiple
contracts. Since this repo only ever plans one Soroban contract, flattened
it: single `Cargo.toml` at `contracts/upto-settlement/`, `src/` directly
underneath, matching the path `docs/SPEC.md` §3 names.

### `env.register()` panics at ledger sequences near `u32::MAX`: a testutils/host limitation, not a contract bug

Found by the `cargo-fuzz` target after removing an earlier clamp: an
unclamped `u32` ledger-sequence input near 4.29 billion made
`env.register(UptoSettlement, ())` itself panic
(`HostError: Error(Context, InternalError)`, `soroban-sdk-27.0.5/src/env.rs:1106`),
before any `UptoSettlement` code ran. Isolated with a standalone test
containing only `Env::default()` + `ledger().with_mut()` +
`env.register()`, same panic, zero contract-specific code involved,
confirming it's `soroban-sdk`'s test-contract registration path running
out of internal TTL headroom at that height, not anything this contract
does. Real Stellar is nowhere near ledger 4.29 billion (~680 years of
runtime at 5s/ledger from genesis) and won't be for centuries, so
`fuzz_settle_arithmetic` clamps ledger inputs to a realistic-but-generous
`0..100_000_000` range instead of the raw `u32` space. Not filed upstream,
fuzzing an unreachable-in-practice height isn't a useful bug report,
and the fix (bound the fuzz input to a plausible range) is the correct
response either way.

### Property tests wrote a snapshot per randomized case: 1,557 files, 24MB, never committed

`soroban-sdk`'s test harness writes a `test_snapshots/*.json` file per
test by default (`EnvTestConfig::capture_snapshot_at_drop`, on by
default), sensible for the 21 fixed-point unit tests (committed as
regression evidence, per the smart-contracts skill's own recommendation),
useless noise for `proptest`-driven property tests that each run ~256
randomized cases. Caught before committing anything, not after: `git diff
--stat` on the untracked `contracts/` tree showed page after page of
`..._rejects_every_subsequent_actual_amount.1.json` through `.256.json`
style filenames. Fixed by splitting `test::setup` into `setup` (default
`Env`, snapshots on) and `setup_with_env` (takes a pre-built `Env`), with
`property_test::setup_at` constructing its own `Env::new_with_config(
EnvTestConfig { capture_snapshot_at_drop: false })` instead of reusing
`setup` directly, exactly the skill's own documented escape hatch for
this exact situation ("Disable per-env with `Env::new_with_config` if
they're noise"), not a workaround improvised after the fact.

### `cargo-fuzz` needed no `clang`: `gcc` was already sufficient

The smart-contracts skill's fuzz-testing section assumes `clang`/LLVM for
libFuzzer; this machine has no `clang` and no passwordless `sudo` to
install it. Before treating that as a blocker, tried building anyway:
`cargo install cargo-fuzz --locked` and `cargo +nightly fuzz build`
succeeded cleanly against the system `gcc` (13.3.0), `libfuzzer-sys`
bundles its own libFuzzer runtime and only needs a working C compiler to
build it, not specifically `clang`. Ran for real: 47,630 executions in
180 seconds, zero crashes after fixing two harness bugs it found along
the way (a fixed buyer-supply constant smaller than a fuzzed `max_amount`,
and the ledger-height issue above), both harness issues, not contract
bugs, confirmed by isolating each with a standalone reproduction before
"fixing" anything.

### An internal security review ran on this contract. It is not, and is not presented as, a third-party audit.

`docs/SKILLS.md` had flagged `security-review` as overdue since Phase 3,
specifically for "the `upto` contract, real money-adjacent," so it ran
before this phase was called done: every vulnerability class in the
`smart-contracts` skill's own checklist (missing auth, auth replay
through middleware, reentrancy, integer overflow, TTL-as-security,
arbitrary token addresses) walked by hand against the actual code, plus
the Soroban-specific properties the checklist doesn't name directly
(atomicity-on-panic protecting the nonce-then-transfer ordering, the
platform's own reentrancy guarantee ruling out a hostile-token
callback). Nothing above a false-positive threshold survived scrutiny.

**What this is not:** a substitute for independent third-party review.
This was a single AI-assisted pass by the same agent that wrote the
contract, with no second reviewer, no formal verification tooling
(Certora Sunbeam, Komet), and no adversarial incentive the way a paid
audit or a bug bounty carries one. It found no issues, which is weaker
evidence of correctness than an external audit finding no issues would
be, the same blind spots that shaped the code are available to review
it. The real pending step before this contract should move any
production value is a third-party audit. **Audit Bank** is the
SDF-subsidized program built for exactly this (SCF-funded protocols,
partner firms including OtterSec, Veridise, Runtime Verification,
CoinFabrik, Certora, Zellic, Code4rena), tracked as a genuine Phase 10
blocker in this file's "Deliberately not self-served" list ("Audit Bank
engagement, a program application, not something to submit
unilaterally"), not something this session can complete on its own.
**Partially closed 2026-08-21**: `cargo audit` (RustSec advisories) and
`cargo clippy` (including `-W clippy::pedantic`, the strictest built-in
tier) have now been run for real against all three Rust crates in
`contracts/`, clean results reported as-is, not oversold as a
substitute for the audit itself; full writeup in
`docs/THREAT-MODEL.md`'s "Automated static analysis" section. `cargo
scout-audit` and OpenZeppelin's Security Detectors SDK specifically are
still not run, a real, narrower remaining gap than before, not the same
one.

### Third-party security review: pending via Audit Bank, status tracked here

This is the canonical status entry for the Audit Bank engagement; the
Phase 0 "External accounts not yet provisioned" bullet above and
`docs/SPEC.md`'s own gate checklist (`- [ ] Security review complete via
the Audit Bank, findings resolved`) both point back to this section
rather than restating it. Current state, as of this writing: **not yet
submitted.** Audit Bank is an SDF-run program (partner firms include
OtterSec, Veridise, Runtime Verification, CoinFabrik, Certora, Zellic,
Code4rena) with its own application, review, and firm-matching timeline;
nothing in this repository can shorten that once an application is in.
There is nothing to self-serve or accelerate from this session's side.
`docs/SPEC.md` §10 scopes what the application should cover once
submitted: the off-chain facilitator and its cryptographic validation as
the primary review target (v1 ships no new Soroban contract on the
settlement path), with `UptoSettlement` scoped as a separate, smaller
contract-level review, distinct from the internal, non-adversarial pass
already recorded above. Audit fees are explicitly not an eligible SCF
budget line; Audit Bank is a distinct programme from the Build Award
itself. Kept open here deliberately, as a genuinely active item this
project is waiting on, not archived as a closed or low-priority
deferral: update this section the moment an application is actually
submitted (with a date and, once available, a link/reference), not only
when a firm is assigned or the review completes.

### `Client.from(...)` fetches the on-chain contract spec live: no generated bindings committed

`apps/facilitator/scripts/upto-settle-demo.ts` (the verification script
that produced the settled transaction in `conformance/RESULTS.md`) uses
`@stellar/stellar-sdk/contract`'s `Client.from({ contractId, ... })`
rather than `stellar contract bindings typescript`'s generated package.
`Client.from` resolves the contract's spec from the deployed WASM over
RPC at call time, so the script has no generated-bindings artifact to
keep in sync with the contract or commit. It stays reproducible from a
clean checkout against whatever is actually deployed at
`UPTO_SETTLEMENT_CONTRACT_TESTNET`. Bindings were generated once, into
the session scratchpad, only to read the exact generated method
signature (`settle({authorization, actual_amount}, opts?)`) before writing
the hand-rolled call, never committed, not needed at runtime.

### The full upstream TypeScript package is still open work, not this phase's gate

`docs/SPEC.md` §6 names `typescript/packages/mechanisms/stellar/src/upto/`
(mirroring `@x402/stellar`'s existing `src/exact/`) as part of Phase 6's
scope, alongside the contract and the spec. The spec is upstream (PR
#3098, already open). The contract is built, tested, deployed, and
settled a real transaction (this phase's actual gate, per §6's own gate
line: `cargo test` passes, contract deployed to testnet, a settled `upto`
transaction hash recorded, three assumptions closed). At the time this
section was first written, the facilitator-side TypeScript package that
would let `apps/facilitator`'s own `/verify`/`/settle` routes actually
serve `upto` requests over HTTP, not just a one-off verification script,
was separate, larger, not-yet-started work.
`apps/facilitator/scripts/upto-settle-demo.ts` proved the contract and
the wire-level auth mechanism both work for real, but was not that
package. **Done as of 2026-08-21**: `apps/facilitator/src/upto-stellar-scheme.ts`
now implements this, registered in `core.ts`, a real settlement through
the facilitator's own `verify()`/`settle()` recorded in
`conformance/RESULTS.md`, design notes in the module's own doc comment
(`upto-stellar-scheme.ts`). The live
`https://periplo-testnet.fly.dev` deployment doesn't have it configured
yet, a real, separately-logged Fly account blocker, not silently
skipped: see "Fly.io redeploy blocked" below for the recurring shape of
that gap.

### `upto` spec convergence with a competing PR: #3098 now documents two profiles

A second PR against the same spec file,
[x402-foundation/x402#3134](https://github.com/x402-foundation/x402/pull/3134)
by [Iam0TI](https://github.com/Iam0TI) with a reference implementation at
[`0d1026/Rialto`](https://github.com/0d1026/Rialto), proposed a different
`upto` mechanism: a stateless settlement contract using SEP-41
`approve`/`transfer_from` instead of this project's pull-and-refund
design, relying on Soroban's own per-entry auth nonce instead of an
app-managed `temporary()`-storage nonce, and settling without binding to
one named facilitator. Both PRs touched the exact same file, which the
`#3134` author's own PR description flagged as something worth
converging on rather than leaving for maintainers to arbitrate between.

Before drafting anything public, ran an honest technical comparison of
the two designs, not advocacy for either, covering: whether the native
Soroban nonce actually gives equivalent replay protection, what the
`stateless` design's facilitator-agnostic tradeoff means concretely, what
pull-and-refund buys against a straight `transfer_from`, and whether
either design changes for a C-account payer. Found real strengths on
both sides. `stateless` genuinely removes an entire implementation-bug
class, since there is no author-sized TTL to get wrong, replay
protection is the protocol's own guarantee, and it settles measurably
cheaper: pulled real `fee_charged` numbers from both projects' own
settled testnet transactions, roughly 25 to 30 percent lower. This
project's `contract` design closes a real gap `stateless` leaves open. A
leaked or multiply-forwarded authorization can be settled by anyone
holding it, for up to the full signed ceiling, not just the facilitator
the resource server intended.

Also found, while comparing the two contracts closely: `stateless`'s
`autoRevoke = false` option lets a **later, unrelated** authorization
silently overwrite a deliberately preserved leftover allowance, since
SEP-41 `approve` replaces rather than adds. Raised generously as a
finding worth documenting, not a defect, in the PR comment.

Both of `#3134`'s cited testnet transactions were independently verified
before being cited as fact in a spec change, not taken on trust. Decoded
the `settle` call's own I128 arguments straight from each operation's
raw XDR, confirming one is a genuine partial settlement (`300,000` of a
`1,000,000` signed ceiling) and the other a genuine maximum settlement
(`500,000` of `500,000`), matching the same bar this project holds its
own numbers to.

**Outcome:** `#3098` now documents both profiles, `contract`, this
project's design, still the default, and `stateless`, credited to
Iam0TI, `0d1026/Rialto`, and `#3134` by name, plus the C-account/smart-wallet
spec language `#3098`'s prose was missing entirely (it was written in
G-account terms only, even though the contract mechanism already worked
for C-accounts). A comment was posted to `#3134` crediting the specific
strengths found, raising the `autoRevoke` finding, and proposing the
consolidated-spec outcome the author had already asked for. `#3098` was marked
ready for review once this landed.

### x402-foundation/x402 requires signed commits. Nothing was configured for it in this environment

Found when `#3098`'s bot check flagged a pushed commit as unsigned, with
a one-week auto-close clock attached. `commit.gpgsign`, `user.signingkey`,
and `gpg.format` were all unset in this environment, no SSH keypair
existed under `~/.ssh` beyond `known_hosts`, and the local GPG keyring
was empty. Confirmed rather than assumed, checked each setting directly
before concluding nothing existed.

Registering a new SSH signing key against a GitHub account through the
API needs the `admin:ssh_signing_key` OAuth scope, which the `gh` token
in this environment did not have. Requesting it triggers an interactive
browser device-code flow
(`gh auth refresh -h github.com -s admin:ssh_signing_key`) with no way to
complete it non-interactively, the same class of blocker already
recorded for the Raven MCP sign-in. Generated a dedicated,
passphrase-less ed25519 signing-only key locally instead
(`~/.ssh/id_ed25519_signing`, no push or login authority), and had the
user add its public half through GitHub's own web UI as a Signing Key, a
thirty-second manual action that needed no elevated token scope at all.
Verified the key was actually registered via the public, unauthenticated
`GET /users/{username}/ssh_signing_keys` endpoint before trusting it, not
just the screenshot the user pasted back.

One thing this surfaced: the account already had a signing key
registered from a different machine (titled to reference an Eras256
laptop, added 2026-08-08), absent from this environment entirely,
confirming key material genuinely does not travel between environments
even for the same account.

Configured `gpg.format=ssh`, `user.signingkey`, `commit.gpgsign=true`,
and a local `gpg.ssh.allowedSignersFile` scoped per repository clone, not
globally, since the actual requirement, `x402-foundation/x402`'s own
contribution policy, is specific to that one upstream project, not a
Periplo-wide or portfolio-wide default. Applied identically to both
`#3098`'s branch and `#3138`'s branch, and confirmed `Verified` on
GitHub's own API (`verified: true`, `reason: valid`) for every commit on
both, not just checked locally.

## `upto` profile discrimination: three real implementation gaps, found responding to external review, not self-discovered

[HeylmStoned's comment](https://github.com/x402-foundation/x402/pull/3134)
on `#3134` raised a wire-level concern: if both `contract` and `stateless`
ship as conformant `upto` profiles, `scheme: "upto"` alone is ambiguous on
the wire, and Periplo's own `/supported`, `PaymentRequirements.extra`, and
Bazaar catalog filters need a stable way to discriminate between them. The
spec text itself already has an answer: `extra.uptoProfile` is defined as a
required, shared `PaymentRequirements` field in `#3098`'s
`scheme_upto_stellar.md`. Checked against Periplo's actual code, not the
spec text, per the same standard this project holds every other capability
claim to, three real gaps surfaced, none of them previously recorded:

1. **Closed 2026-08-21.** `/supported` could not report `upto` at all,
   in any form, since `apps/facilitator/src/core.ts` registered only
   `ExactStellarScheme` and `upto` wasn't wired into the HTTP facilitator
   at all. Closed for real, not stubbed: `apps/facilitator/src/upto-stellar-scheme.ts`'s
   `UptoStellarScheme` (verify/settle/getSigners/getExtra) is now
   registered against `x402Facilitator` in `core.ts`, for any network
   with a configured settlement-contract address, mirroring the real,
   installed `ExactStellarScheme`'s own mechanics as closely as the two
   schemes' real differences allow. A real settlement through this exact
   code path is recorded in `conformance/RESULTS.md`; design notes in
   the module's own doc comment. The live
   `periplo-testnet.fly.dev` deployment doesn't have the settlement
   contract configured yet (a real, separately-logged Fly account
   blocker, see "Fly.io redeploy blocked" below), so `/supported` on
   that specific deployment still won't show `upto` until that redeploy
   happens; the code itself is done and proven.
2. **Closed 2026-08-17.** No `GET /discovery/resources` or
   `GET /discovery/search` HTTP route existed in `apps/facilitator` at all
   (grepped, zero hits; even the filters `docs/SPEC.md` §4 names, `type`,
   `payTo`, `network`, `extensions`, were unimplemented, not just a
   `scheme`/profile dimension). Both routes now exist:
   `apps/facilitator/src/discovery-routes.ts`, reusing
   `@x402/extensions/bazaar`'s own `DiscoveryResource`/
   `DiscoveryResourcesResponse`/`SearchDiscoveryResourcesResponse` types
   directly rather than redefining the wire shape, wired into `app.ts` and
   covered by 12 new tests (`discovery-routes.test.ts`, plus route-level
   tests in `app.test.ts`). `GET /discovery/search`'s filters apply as an
   in-process post-filter over `hybridSearch`'s ranked rows, not a fifth SQL
   parameter, since `periplo_hybrid_search` doesn't take them, documented as
   a real, honest limitation in the module's own doc comment, not hidden.
3. **Closed 2026-08-17.** `packages/bazaar/src/db/catalog.ts`'s
   `mergeAccepts` dedupe key was not `extra`-aware, a real data-loss risk,
   not just a missing feature: the key was
   `${scheme}|${network}|${asset}|${payTo}`, so two `accepts` entries
   differing only in `extra.uptoProfile` hashed to the same key and would
   have silently overwritten each other. `dedupeKey` now folds in
   `extra.uptoProfile` unconditionally (safe for every existing scheme: one
   without a profile, like `exact`, degrades to the pre-fix key exactly),
   with three new regression tests covering distinct profiles coexisting, a
   same-profile entry still replacing rather than duplicating, and a missing
   profile being treated as distinct from a present one.

Recorded here first, deliberately, before any reply was drafted or posted
for #1-#3 originally, so the finding was on record independent of how the
thread response read. All three are now closed, with their own commits
and tests, clickable rather than asserted, #1 as of 2026-08-21.

## Phase 6b: additional evidence for `upto` on Stellar, not an SCF tranche deliverable

Two extension scenarios beyond Phase 6's own gate, same treatment as the
Phase 4/5/6 additions before it: real testnet transactions, checked
against Horizon, not unit tests standing in for them.

### Zero-settlement: done, with real evidence

A genuine `actual_amount = 0` settlement against the already-deployed
Phase 6 contract (`CAK3R734WLT4JU2XMQOJ6NIB3BWGPI442CH44EFJG5AORMXFE7G4MQFW`,
unchanged), needing no contract code at all: `settle` never special-cases
`actual_amount == 0`, so the existing pull-and-refund logic already
handles it correctly, confirmed first by the pre-existing unit test
`zero_settlement_refunds_everything`, then for real.
`apps/facilitator/scripts/upto-settle-zero-demo.ts` produced a real
settled transaction
(`2138c0418a85e1bb29c2eab6cea6c76b3b0231d894450a35905053f36403d358`),
independently checked against Horizon: the buyer's balance is unchanged
before and after (the full `0.05 PTEST` ceiling came back), the seller's
balance is unchanged (nothing was charged), and `/effects` shows the full
pull-then-refund sequence with no transfer to the seller at all, matching
`settle`'s own `if actual_amount > 0` guard around that leg. A second,
genuine replay attempt against the same authorization was rejected on
testnet with `Error(Contract, #6)` (`AuthorizationConsumed`), confirming
the nonce is consumed even when nothing was actually charged, not just
when a real transfer happens. Recorded in `conformance/RESULTS.md`.

### OpenZeppelin smart-account integration: contract and account both built and tested, live transaction still open

The scenario: an agent's key wrapped in a real `stellar-accounts` smart
account, scoped so it can only ever authorize calls to the deployed
`UptoSettlement` instance, spending against a reserved budget reconciled
against the actual amount charged, not the signed ceiling.

**What's genuinely done, verified two different ways:**

- `contracts/upto-settlement/src/budget.rs`: a new, purely additive,
  strictly opt-in reconciliation path in `settle`, called after
  `actual_amount` is validated and before any transfer moves funds. Eight
  new unit tests prove it's keyed on `actual_amount`, not `max_amount`
  (`budget_is_debited_by_actual_amount_not_max_amount` settles for far
  less than `max_amount` and confirms the budget only moved by the real
  charge), that a settlement exceeding the remaining budget is rejected
  even when `max_amount` has room (`a_settlement_that_would_exceed_the_
  remaining_budget_is_rejected`), that a zero-amount settlement never
  touches the budget (`zero_settlement_never_touches_the_budget`,
  matching OpenZeppelin's own rule for the stock policy), and that the
  rolling window genuinely evicts expired spend
  (`budget_rolling_window_evicts_expired_spend`). All 27 pre-existing
  Phase 6 tests still pass unchanged, and the fuzz target still runs
  clean (21,402 executions, zero crashes, after adding the three new
  `Error` variants to its exhaustive match).
- `contracts/agent-smart-account/`: a new, standalone Cargo crate, a real
  `stellar-accounts` (MIT, `OpenZeppelin/stellar-contracts`) smart
  account, not a mock. Its `__constructor` creates one `ContextRule` of
  type `CallContract(upto_settlement_address)` with a single
  `Signer::Delegated(agent_key)`. Three unit tests call `__check_auth`
  directly (via `env.as_contract`, not mocked past): a call scoped to the
  registered contract with the right signer succeeds, a call to any other
  contract is rejected even with a fully valid signature (the actual
  claim this scenario makes: the agent key cannot spend anywhere except
  through `UptoSettlement`), and a signature from an unregistered signer
  is rejected. Both contracts are deployed to `stellar:testnet`:
  `UptoSettlement` (Phase 6b) at
  `CDJY6YLHORR5WYCJM5OQZQZ5SBGBMFZZFRHSIMKEQ2N2KNX237K2B42Q` (a new
  instance, not an upgrade of Phase 6's own deployment, since the
  contract has no upgrade mechanism and re-verifying the whole Phase 6
  gate against a downgraded SDK version to add one was rejected, see
  below), and `agent-smart-account` at
  `CAG4OYCEYXHM3SYWMXBITBB6RGYDDHXUQKILFSBTMTPIGLJHDSX42DAJ`, constructed
  against a real, dedicated, funded testnet keypair
  (`GA7VZHIP2TJPXJGAMCN5BO7HJC5H4YWX5PZ5ZBHRD4BFD6EXT6NALLP5`) as the
  agent key. Queried directly from the live contract, not just asserted:
  `get_context_rule(0)` on the deployed account returns exactly the
  configured rule, scoped to the deployed `UptoSettlement` address, with
  the agent key as its one Delegated signer.

**A real, load-bearing environment finding along the way**: the published
`stellar-accounts` crate on crates.io (0.7.2, the latest stable as of
this writing) pins `soroban-sdk ^26.1`, not the `27.x` line this
project's already-deployed, already-proven Phase 6 contract targets
(matching the live testnet protocol version). **Update, 2026-10-22: this
supersedes "the latest stable" above, see the dated note further down
this section.** Confirmed by a real build
attempt, not assumed from the version numbers: adding `stellar-accounts`
directly to `upto-settlement`'s own `Cargo.toml` pulled in a second,
incompatible `soroban-sdk` into the same dependency graph, producing
genuine type errors at every storage read and write (two distinct
`soroban_sdk::Vec` types, neither convertible to the other). The upstream
`stellar-contracts` repo's own unreleased `main` branch has already moved
its workspace pin to `soroban-sdk 27.0.2`, so this is a real but likely
temporary publish lag, not a permanent incompatibility. Resolved by
keeping `upto-settlement` dependency-free of `stellar-accounts` (its
`budget.rs` mirrors `SpendingLimitData`/`SpendingEntry` field-for-field
instead of importing them, documented as such in that module's own doc
comment) and giving the real dependency only to the new,
independent `agent-smart-account` crate, which has no such conflict and
can freely target the SDK version the account framework actually
requires.

**What's still open: a real, signed, cross-contract settlement
transaction specifically.** Everything above is proven at the Rust level
and independently confirmed against the live, deployed contract state.
What has not yet been produced is a genuine testnet transaction where
`authorization.from` is the smart account and the settlement actually
goes through, the same evidence bar every other Phase 6/6b claim in this
file meets. This was attempted at real length, not given up on early:

- Simulating a call where the smart account is the buyer correctly
  surfaces the need for its own top-level authorization entry
  (`needsNonInvokerSigningBy()` reports the smart account's address), but
  the simulation's auth-recording pass does not itself invoke
  `__check_auth`, so it never surfaces the *nested* requirement
  `authenticate()` creates for the agent's own key
  (`Signer::Delegated`'s verification is `addr.require_auth_for_args(
  (auth_digest,))`, called from inside `__check_auth` itself). That
  nested entry has to be constructed by hand, which OpenZeppelin's own
  documentation explicitly names as a real gap in tooling, not something
  this session missed: "This model requires manual authorization entry
  crafting, because it is not returned in a simulation mode."
- Reasoned out and confirmed against `do_check_auth`'s real source (not
  guessed) that the nested entry's digest is not `signature_payload`
  directly, but `sha256(signature_payload.to_bytes() ++
  context_rule_ids.to_xdr())`, binding which context rule was selected
  into what the delegated signer actually attests to.
- Correctly encoding the `AuthPayload` signature itself required
  abandoning a hand-built XDR attempt (which produced a value the
  contract's own generated argument-unmarshaling code silently rejected)
  in favor of generating real TypeScript bindings from the deployed
  contract's own spec (`stellar contract bindings typescript`) and
  encoding through its embedded `ContractSpec`, eliminating guesswork
  about the exact shape.
- None of this closed the gap. Every constructed transaction still traps
  inside `__check_auth` itself
  (`HostError: Error(Auth, InvalidAction)`, `VM call trapped:
  UnreachableCodeReached`) before `do_check_auth`'s own business logic
  ever runs, confirmed by testing with an empty `signers` map (which
  should fail with a *typed*, controlled `SmartAccountError` at worst,
  not a raw VM trap, if the encoding were the only remaining problem) and
  by testing with only the smart account's own entry present, no nested
  entry at all (identical trap either way, ruling out the nested entry as
  the cause). The isolation work rules out several specific hypotheses
  (hand-built vs. spec-generated `AuthPayload` encoding, nonce reuse
  across two `simulateTransaction` calls vs. a fresh nonce, the nested
  entry's presence or absence) without yet finding what actually causes
  the trap.

Not fabricated, not skipped silently. The contract-level and
account-level work above is real, tested, and deployed; the live
transaction is a genuinely open item, most likely worth a fresh attempt
using `Signer::External` (a direct signature check against a verifier
contract, architecturally simpler and needing no nested auth entry at
all) instead of `Signer::Delegated`, or a working example from
OpenZeppelin directly, since their own documentation names this exact
gap without supplying one.

### 2026-09-02: the trap explained by a third party, then a real partial success against this project's own contract

The "working example from OpenZeppelin directly" this section asked for
arrived, from an unexpected direction: a separate project independently
hit the identical `Signer::Delegated` trap and root-caused it for real,
filed as
[OpenZeppelin/stellar-contracts#863](https://github.com/OpenZeppelin/stellar-contracts/issues/863),
closing this project's own
[OpenZeppelin/stellar-contracts#839](https://github.com/OpenZeppelin/stellar-contracts/issues/839).
The trap was never inside `__check_auth` at all: `AssembledTransaction.
needsNonInvokerSigningBy()`/`signAuthEntries()` never surface a
`Signer::Delegated`'s own signing requirement, because Soroban's
recording-mode simulation never actually invokes `__check_auth`'s body,
so `require_auth_for_args()` calls that only happen inside it can't be
discovered ahead of time. A caller trusting the standard discovery flow
submits a transaction missing the delegate's entry entirely, which
`authenticate()` then traps on — this exact symptom, now explained.
That separate reproduction (a trivial `probe` contract, one `ContextRule`,
hand-constructed entries via `smart-account-kit`) settled for real:
[`f5835897d8b42544f2c98efbef7110be9d50308717885012b5a6bc9c20644d9f`](https://stellar.expert/explorer/testnet/tx/f5835897d8b42544f2c98efbef7110be9d50308717885012b5a6bc9c20644d9f).
Full attribution is in the linked issue; this is Periplo's own record of
what was tried against this project's own contracts, not a repeat of that
writeup.

Tried the same day, at the user's direction, against this project's own
deployed contracts: a fresh `agent-smart-account` instance
(`CDGCOHRV6XIFGQ2ZYCIOCJ3GDLOEYFWUP3UICE6DD5HQQTEO3OWRK243`, a local,
uncommitted rebuild of the original `Signer::Delegated` constructor with
both `ContextRule`s the real `settle()` flow needs — id 0 for the
deployed `UptoSettlement` instance, id 1 for the `PTEST` asset, matching
this contract's own doc comment about why two rules exist), funded with
`0.5 PTEST`. Both required auth entries were hand-constructed exactly as
`smart-account-kit`'s real source does it (transcribed from
`src/managers/multi-signer-manager.ts` and `src/kit/auth-payload.ts`,
not re-derived from scratch a second time, unlike the original attempt
above): the smart account's own top-level entry with an `AuthPayload`
signature (`context_rule_ids: [0, 1]`, a `signers` map with an
empty-bytes entry for the delegate, its real authorization living
elsewhere), and a second, entirely separate entry for the agent key
whose `rootInvocation` targets `__check_auth(auth_digest)` on the smart
account directly, signed with a plain Ed25519 signature over that
entry's own preimage hash.

The full two-context call (`settle()`'s root invocation plus its nested
SEP-41 `transfer`) still failed — but with a clean, typed
`Error(Contract, #3002)` (`SmartAccountError::UnvalidatedContext`), not
the opaque `UnreachableCodeReached` this section already documents.
Real progress on its own: the trap itself is gone, replaced by a
`stellar-accounts`-native, typed rejection.

To isolate whether the construction technique itself was sound, a
minimal single-context test was built: a fresh `probe` contract
(identical to the separate reproduction's, `fn ping(caller: Address) {
caller.require_auth(); }`, deployed at
`CCYTDGYRDN2SYNTYLIP743TKJZ6W77RM2XC74U22NKQ7UNH27A343SEE`) and a
single-`ContextRule` `agent-smart-account` instance
(`CCDUCHKB2QKM5U7LHXWJOKJAPYIMEJ5WCFR4NRKYY5LEPMMFX3XUUH52`), same
construction code, `context_rule_ids: [0]` only. **This settled for real
and confirmed on-chain**:
[`428021a6ef648937bf0edeec96d42f13e44447eac9b036c127c90cf4bebdd71b`](https://stellar.expert/explorer/testnet/tx/428021a6ef648937bf0edeec96d42f13e44447eac9b036c127c90cf4bebdd71b),
Horizon-verified independently (`successful: true`, source account the
fee-sponsor, `fee_charged: 203541` stroops). **This is Periplo's own
first real signed testnet transaction where a `Signer::Delegated` smart
account genuinely authorized a call** — proof the discovery-gap fix
transfers to this project's own environment, confirmed empirically
rather than assumed from that separate reproduction's result alone.

One quick diagnostic tried on the still-failing two-context case:
reversing `context_rule_ids` to `[1, 0]`. No change, and inconclusive by
construction — `stellar_accounts::smart_account::storage`'s own
`do_check_auth` collects validated contexts via `Vec::from_iter` over a
mapping closure that panics inside `get_validated_context_by_id` on the
first failing iteration, so which of the two contexts (the `settle`
root call or the nested `transfer`) actually fails
`UnvalidatedContext`'s checks (rule expiry, context-type match, or
signer match) isn't visible from the panic alone, in either id order.

**Genuinely open, not resolved this round**: why the two-context
`settle()` + nested `transfer` case still fails `UnvalidatedContext`
when the identical single-context construction succeeds cleanly.
Candidates not yet checked: whether the SEP-41 token's own `transfer`
implementation constructs its `require_auth_for_args` call in a shape
`get_validated_context_by_id`'s type-matching doesn't expect, or
something specific to validating two contexts against two distinct
rules in one `__check_auth` invocation that the single-rule case never
exercises. `contracts/agent-smart-account/src/lib.rs` was reverted to
its committed `Signer::External` state afterward — no permanent contract
change was made. Local, uncommitted artifacts from this round:
`apps/facilitator/scripts/agent-smart-account-settle-demo.ts`,
`contracts/probe-contract/` (the isolation contract), and
`smart-account-kit` added as an `apps/facilitator` devDependency
(`package.json`/`pnpm-lock.yaml`) — kept only for its exported, real
`computeEntryAuthDigest`/`signerToScVal`/`createDelegatedSigner`
helpers, not the full SDK's wallet/relayer machinery, which this
project's own deployed contracts (created outside the kit's own
deployer flow) don't fit anyway.

**Watch-item, opened 2026-09-07, updated 2026-09-10:**
[OpenZeppelin/stellar-contracts#868](https://github.com/OpenZeppelin/stellar-contracts/pull/868)
("Smart account: auth payload digest") merged
`2026-09-10T12:49:27Z` (merge commit
[`4529d708`](https://github.com/OpenZeppelin/stellar-contracts/commit/4529d708c47866bec790223b88036f9aa9e404b3),
closing the new issue
[`#876`](https://github.com/OpenZeppelin/stellar-contracts/issues/876)),
which brozorec had flagged on `#839`'s thread as the place `Signer::Delegated`
test coverage and docs would land. What it changes, read from the merged
diff directly, not the release notes:

- The opaque digest `sha256(signature_payload || context_rule_ids.to_xdr())`
  is replaced by a `#[contracttype] AuthDigestPreimage { account,
  signature_payload, context_rule_ids }`. `Signer::External` signers now
  sign `sha256(preimage.to_xdr())`; `Signer::Delegated` signers authorize
  the struct itself through `require_auth_for_args((preimage,))`, not a
  bare 32-byte value.
- A new `auth_digest(preimage)` view puts the type in the contract spec so
  a client can check its encoding by simulation.
- `packages/accounts/src/smart_account/test/auth_entries.rs` (new, 327
  lines) drives both auth entries through the host end to end, using a
  `Probe` contract (`ping(caller) { caller.require_auth() }`) that mirrors
  the isolation probe this round already built. Its negative test
  `delegated_signer_nested_entry_with_digest_argument_fails` asserts that
  passing the raw digest as the nested entry's argument fails: that is
  exactly the construction attempted here on 2026-09-02, now confirmed as
  a known-wrong pattern rather than an open mystery.
- The `packages/accounts/README.md` gains an "Authorizing from a Client"
  section and a v0.7.x to 0.8.0 migration guide. It is a breaking change,
  and points at `smart-account-kit`, warning to align its version with the
  `stellar-accounts` release the account was built with.

**Still an open blocker, for two concrete reasons:**
1. No release ships it. `stellar-accounts` on crates.io is still `0.7.2`
   (2026-06-09); `0.8.0` is unreleased. This project pins `0.7.2`.
2. Every new test uses a single `context_rule_id`. There is still no
   multi-`ContextRule` delegate test, so the specific two-context
   `settle()` + nested `transfer` case that fails `UnvalidatedContext
   #3002` is neither reproduced nor explained upstream.

The decision (user, 2026-09-10) is to wait for the official `0.8.0`
crates.io release rather than pin a git rev now: reattempting means
reopening a diagnostic round closed on purpose, against an unpublished
dependency, with the multi-context path still uncovered upstream. When
`0.8.0` publishes, the retry path is defined: bump the pin, rebuild the
delegate nested entry to carry the `AuthDigestPreimage` struct instead of
the raw digest, and re-run the two-context `settle()` against testnet.

### 2026-10-27: resolved. The two-context `settle()` blocker is closed, for real, on testnet

`stellar-accounts 0.8.0` published 2026-10-20 (confirmed via
`curl https://index.crates.io/st/el/stellar-accounts`, not yanked), the
trigger this section named. The retry path defined above was followed
exactly: `contracts/agent-smart-account` and `contracts/agent-verifier`
bumped to `soroban-sdk 28.0.0`/`stellar-accounts 0.8.0`
(`cargo build`/`cargo test` both needed the real `stellar contract build`
orchestration this soroban-sdk line requires, not a bare
`cargo build --release --target wasm32v1-none`; it refuses with "soroban-sdk
requires stellar-cli v25.2.0+ to build a contract" otherwise, confirmed
with `stellar-cli 27.1.0` already installed). `agent-smart-account`
rebuilt for `Signer::Delegated` (back from the `Signer::External` this
repo committed after the 2026-08-15 round ruled out signer type as the
real differentiator): same two `ContextRule`s as the 2026-09-02 attempt
(id 0 `UptoSettlement`, id 1 the asset), same `__check_auth` wiring.
Redeployed fresh to `stellar:testnet` at
`CA2UIDXPSECCJLK3ZBIMCBCWTIMDRC4NPNPABVFYH2IH35ACIY6ILW5H`, confirmed via
`get_context_rule(0)`/`get_context_rule(1)` returning exactly the
configured rules.

The one real change from the 2026-09-02 attempt:
`apps/facilitator/scripts/agent-smart-account-settle-demo.ts`'s delegate
nested entry now carries a structured `AuthDigestPreimage { account,
signature_payload, context_rule_ids }` as its `__check_auth` argument,
not the old raw `sha256(signature_payload ++ context_rule_ids.to_xdr())`
digest (`OpenZeppelin/stellar-contracts#868`'s own
`delegated_signer_nested_entry_with_digest_argument_fails` test already
named that old shape as known-wrong). Built via `smart-account-kit`'s
real, published `computeEntryAuthDigest(..., "preimage-v1")`
(`smart-account-kit` bumped `0.6.2` → `0.9.1`, the version whose own
dependency on `@stellar/stellar-sdk` still matches this repo's pinned
`16.3.0`; `0.10.0` needs `^16.4.1`), not hand-rolled a second time.
Everything else in the script (extracting the smart account's own entry
from simulation, building the separate delegate entry's root invocation
and signature, re-simulating, signing, submitting) is unchanged from the
attempt that failed with `UnvalidatedContext #3002`, isolating the
digest scheme as the one variable that changed.

**Real, signed, settled, independently verified three ways, not just
trusted from the script's own "SUCCESS" output:**
[`d493b6f5d16e0ac8002e115470d634bb0ab87f23e167890406a3d8922260961b`](https://stellar.expert/explorer/testnet/tx/d493b6f5d16e0ac8002e115470d634bb0ab87f23e167890406a3d8922260961b),
ledger `5424730`. (1) Horizon confirms `successful: true`,
`fee_charged: 6050447` stroops (a genuinely expensive multi-auth
invocation), source account the fee-sponsor. (2) Horizon's own
`/effects` for the transaction shows `account_credited` the seller
exactly `0.0400000 PTEST`, the real `actual_amount` (`400_000` of a
`1_000_000`/`0.1 PTEST` signed ceiling), not the ceiling itself. (3) The
smart account's own on-chain SAC balance, read directly via
`stellar contract invoke ... -- balance --id
CA2UIDXPSECCJLK3ZBIMCBCWTIMDRC4NPNPABVFYH2IH35ACIY6ILW5H`, dropped from
`10_000_000` to `9_600_000`, exactly `400_000` (the actual charge, not
the `1_000_000` ceiling), confirming the pull-then-refund mechanic
completed and only the real charge stuck, the same claim every other
`upto` settlement row in `conformance/RESULTS.md` makes.

**What this closes, stated precisely**: the specific two-context
`settle()` + nested `transfer` case that failed `UnvalidatedContext
#3002` under the pre-`#868` raw-digest construction now succeeds under
`AuthDigestPreimage`. This does not retroactively explain *why* the old
construction failed `#3002` specifically (that root cause was never
found, per the 2026-09-02 entry above); it confirms that the fix
`OpenZeppelin/stellar-contracts#868` shipped, despite adding no
multi-`ContextRule` delegate test of its own, does cover this case in
practice. `agent-smart-account`'s committed contract moves to
`Signer::Delegated` as a result (see this file's own module doc for the
updated history); `Signer::External` stays ruled out as documented, not
revisited.

### The `soroban-sdk ^26.1` vs `27.x` mismatch was tested directly as a cause of the trap, and ruled out

Before treating the trap above as a real, independent problem worth an
upstream issue, the most obvious simpler explanation was checked
directly rather than assumed away: the already-documented `soroban-sdk`
version mismatch between the published `stellar-accounts` crate
(`^26.1`) and `upto-settlement` (`27.0.5`).

`agent-smart-account` was rebuilt against `stellar-contracts`' own
unreleased `main` branch (commit `fbfde388e1b72afa93d6b1c922067879b20e81db`,
which already pins `soroban-sdk 27.0.2`) instead of the published
`0.7.2` crate, resolving to `soroban-sdk 27.0.6`, the same major.minor
line as `upto-settlement`'s `27.0.5`. All three unit tests still passed
unchanged. A fresh instance was deployed to testnet
(`CB3XXKZLHTTTJEZF6URNVK66E5JAEBYRO2VMRP6JO3SYPCV4GAA7MNN2`) with the
same `agent_key`/`upto_settlement` constructor arguments as the original,
and the exact same auth-entry construction (spec-driven `AuthPayload`
encoding, the `auth_digest = sha256(signature_payload ++
xdr(context_rule_ids))` derivation confirmed against `do_check_auth`'s
own source, both entries built via `authorizeEntry`/`authorizeInvocation`)
was retried against it.

The trap was identical: the same `HostError: Error(Auth, InvalidAction)`,
the same `VM call trapped: UnreachableCodeReached` inside `__check_auth`.
Version alignment changed nothing. The experiment was reverted
(`agent-smart-account` back to the published `stellar-accounts@0.7.2` /
`soroban-sdk@26.1.1` pin, no permanent change), since a git dependency
on an unreleased, movable branch is less reproducible than a published
crate version and bought nothing once the hypothesis came back negative.

The `^26.1` vs `27.x` mismatch stands as a real, independently worth
recording environment finding (see above), but it is now confirmed, not
assumed, to be a separate thing from the `__check_auth` trap, not its
cause.

### Isolated from `UptoSettlement` entirely: the trap reproduces identically against a trivial target contract

The second simpler explanation checked before treating the trap as a
real, independent problem: that it was specific to `UptoSettlement`'s
own complexity (storage reads, nonce handling, the `budget` module),
not to the smart-account/auth layer itself.

A minimal `probe` contract was built with no storage, no nonce, and no
business logic at all:

```rust
#![no_std]
use soroban_sdk::{contract, contractimpl, Address, Env};
#[contract]
pub struct Probe;
#[contractimpl]
impl Probe {
    pub fn ping(_env: Env, caller: Address) {
        caller.require_auth();
    }
}
```

Deployed to testnet at
`CCLBQEUKTDBJTMK7BYP2NGTGH5FF5HY5RJGOXWKGRTNUSFBH6S77A23H` (429 bytes,
wasm hash `2bcc2ed52aab41eaf772a1d546ea65cf2ec04abfbdd4d0660881090692fa470b`).
A fresh `agent-smart-account` instance, built from the published
`stellar-accounts@0.7.2` crate (not the version-alignment experiment
above), was deployed and scoped via `ContextRule::CallContract` to this
`probe` contract instead of `UptoSettlement`:
`CBQAYHHTFAYUL7OY7SCVP67LGTCMW77K6UUH6B5LRTUF52GCMNJICRG3` (wasm hash
`7c9ed845a00a9ff7638c7b64bfaa089fed7a1f8d771772f6bbf9877d377a1ab7`).

`probe.ping({caller: smart_account})` was simulated with the same
two-entry auth tree used throughout this investigation: entry0 for the
smart account via `authorizeEntry` with a spec-encoded `AuthPayload`
signer callback, entry1 for the agent key via `authorizeInvocation`
with the `auth_digest = sha256(signature_payload ++
xdr(context_rule_ids))` derivation confirmed against `do_check_auth`'s
own source.

The trap was identical:

```
SIMULATION ERROR: HostError: Error(Auth, InvalidAction)
...
2: contract:CBQAYHHTF... topics:[error, Error(WasmVm, InvalidAction)]
   data:["VM call trapped: UnreachableCodeReached", __check_auth]
```

Confirmed, not assumed: the trap does not depend on `UptoSettlement`,
its storage, its nonce handling, or its budget-reconciliation logic. It
reproduces against a target contract with a single line of body
(`caller.require_auth()`), scoped through the exact same
`ContextRule::CallContract` mechanism. This narrows the trap to the
`stellar-accounts`/`__check_auth` machinery itself, or to how this
build's client-side auth-entry construction feeds it, independent of
anything specific to Periplo's own contract.

### `stellar-accounts` itself has no test that exercises this path: checked two independent ways

Before drafting an upstream issue, checked whether `stellar-accounts`
(the published `0.7.2` crate) or its own official example
(`examples/multisig-smart-account` in `OpenZeppelin/stellar-contracts`)
already has a reference test for `Signer::Delegated` +
`ContextRuleType::CallContract` that could be diffed against, in either
direction: does the reference case pass clean (compare construction
step by step), or does it trap identically (a clean library bug)?

Neither. `grep -rn "SorobanAuthorizationEntry\|set_auths\|
authorize_as_current_contract"` across the full crate source returned
nothing, and manual reading of every test touching `Signer::Delegated`
+ `ContextRuleType::CallContract` (`src/smart_account/test/
context_rules.rs` in the crate itself,
`examples/multisig-smart-account/account/src/test.rs` in the repo's own
official example) confirmed the same pattern in both: every one calls
`do_check_auth` directly as a plain Rust function inside
`e.mock_all_auths()`, with empty signature bytes
(`create_signatures`'s `Bytes::new(e)` per signer) and an arbitrary
payload never derived by the host. None of them construct a real
`SorobanAuthorizationEntry` tree or drive it through the host's actual
`__check_auth` invocation, the mechanism this build's auth-entry
construction depends on. `Architecture.md` does not document the
`auth_digest` derivation either; the only source for it is
`do_check_auth`'s own Rust body, already read directly for this build's
construction.

This does not rule out an error on this build's own side. It does mean
there is no reference case, in either direction, to diff against, and
that the real host-driven path for `Signer::Delegated` +
`ContextRuleType::CallContract` appears to have no test coverage
upstream, at either the library or its own example level, which raises
the odds this is a genuine, currently-untested gap rather than a
misuse of a well-exercised path.

**Filed:** [OpenZeppelin/stellar-contracts#839](https://github.com/OpenZeppelin/stellar-contracts/issues/839),
framed as a request for diagnostic help rather than a confirmed bug
report, first contact with this maintainer. Open, unresolved as of
this writing; the live cross-contract settlement transaction for this
scenario remains blocked on whatever the answer turns out to be.

### `Signer::External` retried in place of `Signer::Delegated`, and ruled out as the differentiator

Reviewing `stellar_accounts::smart_account::storage::authenticate`'s two
arms side by side (`Delegated` needs a second, nested, hand-constructed
auth entry; `External` verifies a raw Ed25519 signature via one
cross-contract call, entirely inside the account's own single entry) was
a real, motivated reason to retry with `External`, not a guess. The
retry was built completely, not half-attempted:

- `contracts/agent-verifier` (new crate): a deployable Ed25519 `Verifier`
  wrapping `stellar_accounts::verifiers::ed25519`, five unit tests with
  real signatures (genuine accept, wrong-key rejection, tampered-message
  rejection, both canonicalization paths). Deployed to `stellar:testnet`
  at `CAG4XLOGOBQUKRV4QESCYDJHY5IPTINTC64XDXF5EHA5GXACVVRA6TU3`.
- `contracts/agent-smart-account` rewritten for `Signer::External`, and
  given a *second* `ContextRule`: a real `settle()` call presents
  `__check_auth` with two contexts in one invocation (the top-level
  `settle`, and the nested SEP-41 `transfer` it makes to pull the
  buyer's funds), each needing its own matching
  `ContextRuleType::CallContract`. Four unit tests pass, including one
  proving both contexts validate together against `context_rule_ids`
  aligned by index, matching `stellar-accounts`' own
  `do_check_auth_multiple_contexts_success` convention. Redeployed at
  `CA3LQLUJWT3GIRIGFIRKLO73CLLOWY7TKTFFOB5VCSYHARGHNVEPSZEB`, scoped to
  the Phase 6b `UptoSettlement` instance
  (`CDJY6YLHORR5WYCJM5OQZQZ5SBGBMFZZFRHSIMKEQ2N2KNX237K2B42Q`) and the
  test asset.
- The `Signer::External` ScVal encoding used to sign was checked against
  ground truth, not assumed correct: `get_context_rule(0)`'s real,
  on-chain, already-encoded `Signer::External` value was pulled via a
  live simulation and diffed byte-for-byte against this build's own
  `spec.nativeToUdt(...)` output for the same logical value. Identical.

A real, signed `settle()` transaction was submitted through the
two-context smart account:
[`9cc42fde13834730b4c6d031a7be9562f6dc7080f91d8c2daefa6413c51640c0`](https://stellar.expert/explorer/testnet/tx/9cc42fde13834730b4c6d031a7be9562f6dc7080f91d8c2daefa6413c51640c0)
(ledger 4148611). **It failed on-chain**, the identical trap as before
(`HostError: Error(Auth, InvalidAction)`, `VM call trapped:
UnreachableCodeReached` inside `__check_auth`). Soroban's atomicity
guarantee held: a failed invocation rolls back completely, confirmed by
re-reading balances after the fact, not just trusting the "no error"
absence, so nothing was lost beyond the network fee.

Isolated once more against the same minimal `probe` contract from the
`Signer::Delegated` round (single context this time, the simplest
possible construction): the identical trap.

**Conclusion, stated plainly: `Signer::Delegated` vs. `Signer::External`
is ruled out as the actual differentiator for this build's own
construction.** Both signer types trap identically here, which means the
two external implementations that work with `External` elsewhere don't
automatically transfer, something else in this build's own transaction
construction still differs from theirs, not yet found. The Signer
encoding itself is now proven correct by direct on-chain comparison, so
that specific piece is no longer a live suspect.

### One more isolation round: `Client.from(...).methodName()` vs. building `AssembledTransaction` directly

The one remaining structural difference between this build's construction
and the pattern used by every outside reference point consulted:
this build calls the generated `Client.from({contractId,
...}).methodName(...)` convenience wrapper throughout, never
`AssembledTransaction.build({contractId, method, args, ...})` directly.
`Client`'s generated methods are documented to delegate to
`AssembledTransaction.build` underneath, so this was not expected to
matter, but it was the one remaining untested variable after ruling out
signer type, encoding method, nonce reuse, nested-entry presence, SDK
version alignment, and target-contract complexity.

Retried once, against the same minimal `probe` contract, everything else
held constant: `probe.ping({caller: smart_account})` built via
`AssembledTransaction.build(...)` directly instead of
`Client.from(...).ping(...)`, same `Signer::External` construction, same
`authorizeEntry` signing. **Identical trap**
(`HostError: Error(Auth, InvalidAction)`, `VM call trapped:
UnreachableCodeReached` inside `__check_auth`). `Client.from` vs. direct
`AssembledTransaction.build` is now also ruled out.

This closes this diagnostic round, per its own stated scope: seven
specific hypotheses tested and ruled out (hand-built vs. spec-driven
encoding, nonce reuse, nested-entry presence, `AuthPayload` content,
`soroban-sdk` version alignment, target-contract complexity, signer type
`Delegated` vs. `External`), plus signer encoding independently confirmed
byte-correct against live on-chain state, plus the transaction-building
API surface itself (`Client.from` vs. `AssembledTransaction.build`). The
trap remains unexplained. Further attempts, if warranted, get their own
separately-scoped investigation rather than continuing to stack onto this
one; `OpenZeppelin/stellar-contracts#839` carries the full picture as of
this update.

## `routeTemplate` for opaque-origin schemes: deliberately left unbuilt, on a reviewer's own reasoning

`x402-foundation/x402#3138`'s fix (the opaque-origin canonical-URL
stripping, closing
[#3121](https://github.com/x402-foundation/x402/issues/3121)) only
covers the raw-URL branch. The `routeTemplate` branch (dynamic,
parameterized routes) still only applies to WHATWG special schemes; an
opaque scheme like `mcp://` never takes it, even if a producer someday
declares a templated MCP tool URL.

This is not an oversight left unfiled. whawk46, the same reviewer who
found the query-stripping gap and whose suggested shape closed it,
raised it directly and gave the reasoning for leaving it unbuilt,
quoted verbatim from the PR thread: "I'd leave it unpinned,
deliberately. The mechanical form is obvious whenever it's needed —
protocol + host + template, same shape as this commit — but whether
collapsing templated tools into one canonical is even the right catalog
semantics for a non-special scheme is a question I'd rather answer with
a real producer in hand than by guessing ahead of one. The first time
someone declares a template on an opaque scheme, it's a five-line PR
with a test, and this thread is the paper trail for where it goes."

Recorded here for the same reason the thread itself exists: not a gap
in Periplo's own work, and not something to build ahead of a real need,
on a reviewer's own explicit call, not this project's guess. If a real
opaque-scheme `routeTemplate` producer shows up, the fix is small and
already sketched (`protocol + host + template`, the same reconstruction
`#3138` already uses for the raw-URL branch) and belongs in
`@x402/extensions/bazaar` itself, following the same "don't reimplement
the wire protocol" principle every other upstream-facing piece of this
project already follows.

## A design note for any future usage-based ranking signal: wash-trading resistance has to be designed in, not added after

Not a gap in what's built today. `packages/search`'s ranking is purely
metadata-based: `periplo_hybrid_search`
(`supabase/migrations/20260812080000_search.sql`) scores on lexical
relevance (`ts_rank_cd` over `fts`) and semantic similarity (`embedding
<#> query_embedding`) fused by RRF, confirmed directly in the SQL, not
assumed: no payment amount, volume, buyer count, or usage figure
appears anywhere in the scoring formula. There is nothing to
wash-trade today, since the ranking never looks at payments at all.

Worth writing down anyway, since the temptation to add a
usage-based credibility signal (payment volume, buyer diversity, a
low observed failure rate) is an obvious future direction for search
quality, and the wash-trading resistance for it is much cheaper to
design in from the start than to retrofit once real listings depend on
the ranking behaving a certain way:

- Payer diversity, discounted for shared funding origin, not raw
  payment count. A resource paid for many times by the same buyer, or
  by buyers funded from the same source, should not score as more
  credible than one paid for by genuinely independent buyers a few
  times.
- Keep any credibility score separate from the relevance score, never
  folded into one number. A padded credibility signal must never be
  able to outrank a genuinely more relevant result on its own; the two
  need to compose in a way that keeps that bound obvious, not just
  likely.

Not a decision made now, since there is no usage signal to secure yet.
Recorded here so the next session that adds one starts from this list
instead of rediscovering it after the ranking is already live and
harder to change.

## A skill for skills.stellar.org, deliberately after Phase 7, not before

A skill for skills.stellar.org, deliberately after Phase 7 (MCP
discovery server), not before: without it, there is not yet enough to
teach an agent. Today's surface is facilitator and Bazaar APIs only,
thin next to what an agent actually wants to do, discover and pay for
an x402 service with no prior integration, which is what Phase 7
exists to make possible. A sequencing decision, not an oversight.

## Fly.io redeploy blocked, then resolved: this session's CLI auth couldn't see `periplo-testnet`

The new `GET /discovery/resources`/`GET /discovery/search` routes and the
repo-wide em-dash cleanup (committed and pushed, `70b7c20`/`93df21e`/
`d29f0fd`) were not live on `https://periplo-testnet.fly.dev` at first.
`fly deploy --config fly.facilitator.toml --dockerfile Dockerfile.facilitator
-a periplo-testnet` failed with `Error: unauthorized`, and `fly status -a
periplo-testnet` failed harder, `Could not find App "periplo-testnet"`, not
just a permission denial. `fly auth whoami` confirmed this session was
authenticated as a Fly account other than the app's owner; `fly apps list`
under that account did not include `periplo-testnet` at all. The app was
provisioned under a different Fly.io account than that CLI session, a genuine
credential gap.
Logged rather than worked around, per this project's own rule for a
genuinely blocked, outward-facing action.

**Resolved the same day**: the project owner logged into the correct Fly
account (the Fly account that owns the app, confirmed via `fly apps list`
showing `periplo-testnet`) and the redeploy was run for real. `fly deploy` itself
printed a false-positive warning ("app is not listening on the expected
address... 0.0.0.0:8402"), not trusted at face value: verified live
instead with real `curl` requests against all three routes.
`GET /` returns the updated `endpoints` map (including the two new
discovery routes) and the em-dash-free description; `GET /discovery/resources`
returns the real single-row catalog with the correct wire shape;
`GET /discovery/search?query=financial` returns a valid empty result
(200, correct shape, no match for that specific query against the one
real row, not an error). All three checked directly against the live
service, not assumed from the deploy command's own success output.

## Fly.io redeploy blocked again, same recurring gap: real external QA fix (2026-08-19), resolved same day

The write-time URL gate, the `null/*`/`localhost` backfill migration, and
`apps/facilitator/src/demo-resource.ts` (the one real, externally-reachable
demo resource) are all built,
tested (`pnpm run ci` green, 217 tests), and typechecked. The backfill
migration itself already ran for real against the live Supabase project
(confirmed by re-querying the table). What's still blocked: getting
`demo-resource.ts` actually deployed to `https://periplo-testnet.fly.dev`
and running a real settled payment against it, the same "cataloging only
counts once it happens for real, not just once the code exists" standard
this project holds everything else to.

Blocked the same exact way as the entry above, same root cause recurring:
`fly auth whoami` in this session resolves to a different Fly account than the
one that owns the app, `fly secrets list -a periplo-testnet` fails
`unauthorized`, `periplo-testnet` lives under the app-owning account
specifically. Logged rather than
routed around, per this project's own rule for a genuinely blocked,
outward-facing action; not attempting to hunt for a workaround credential.

**Resolved the same day**: the user re-logged into the correct Fly account
(the Fly account that owns the app, confirmed via `fly auth whoami` and
`fly apps list` showing `periplo-testnet`) and asked to finish the deploy. All four
steps above were run for real, in order, and hit two further real bugs
along the way (both root-caused and fixed before the settlement that
finally worked): the demo route's own `resource.url`
came out `http://...` instead of `https://...` behind Fly's
TLS-terminating proxy (`@hono/node-server` has no `X-Forwarded-Proto`
awareness, confirmed by reading its source), fixed with an explicit
`DemoResourceConfig.baseUrl` overriding the SDK's request-derived URL;
and the first two real settlement attempts failed with
`invalid_exact_stellar_payload_fee_exceeds_maximum`, real testnet Soroban
fees (~72,000 stroops that day) exceeding `@x402/stellar`'s inherited
50,000-stroop default ceiling, fixed with a new
`MAX_TRANSACTION_FEE_STROOPS=200000` Fly secret. The real settlement that
finally succeeded: transaction
[`dde62ac5e6...`](https://stellar.expert/explorer/testnet/tx/dde62ac5e67730a0751052a2dafc67dffc595df20bacbae9aaa1c758081deaea),
Horizon-verified, recorded in `conformance/RESULTS.md`. The catalog now
holds `https://periplo-testnet.fly.dev/demo/temperature-convert`,
confirmed via `GET /discovery/resources` against the live deployment, not
just from the script's own printed success output.

## `docs/SPEC.md` §11's pre-submission dependency re-verification ran 8 days late, not before submitting

Spec §11 is explicit: "before submission, re-verify each pinned version
and state the verification date in the README." The manifest was
verified once, 2026-08-07, four days before the actual 2026-08-11
submission, and the required second pass never happened before
submitting. README's own "Dependency versions" section said so plainly,
in its own words, for the full 8 days after submission until this was
caught: "That pass has not happened yet." A real, unforced miss against
the project's own stated requirement, not something the panel would need
to find on its own.

**Run for real 2026-08-19**, prompted by an external audit against this
project's own `docs/SPEC.md` §13 checklist. Every pinned package
re-checked against the live npm registry / crates.io, not assumed
current from memory. Real findings, not a clean bill of health rubber-
stamped: `pnpm` moved two minor versions (11.20.0 → 11.22.0), several
patch/minor bumps across `vitest`/`@biomejs/biome`/`hono`/`@types/node`/
`tsx`/`@supabase/supabase-js`, all applied and the full gate re-run green
after (`pnpm run ci`, 218 tests). This caught a real, separate bug along
the way: `eval/package.json` had its own stale `@supabase/supabase-js`
pin that the workspace's other packages didn't share, producing a type
mismatch (`protected supabaseUrl` on two nominally different classes)
only visible once the version actually diverged across the workspace,
not caught by any single package's own typecheck in isolation.

Two packages deliberately were not bumped to the literal latest
available, both judgment calls made and stated, not silent gaps:
`@x402/core`'s family stayed at 2.22.0 rather than the actual latest
2.23.0, held back specifically because `pnpm`'s own `minimumReleaseAge`
supply-chain policy flagged 2.23.0 as under 24 hours old at check time,
with no changelog available to review what changed in the package this
project's real (if testnet-only) fee-sponsor signs through; and
`soroban-sdk` stayed at 27.0.5 rather than 27.0.6 (a plain patch bump),
because the already-deployed `UptoSettlement` contract was built and
verified against 27.0.5 specifically, and bumping the source pin without
redeploying would leave the repo and the live contract mismatched, while
redeploying a new instance is a bigger action than a version bump and
wasn't asked for. Full reasoning and the corrected `stellar-xdr` table
entry (was `28.0.0`, a value that was wrong from the start, not drifted;
the real, transitively-resolved version is `27.0.0`, confirmed by
reading `Cargo.lock` directly) are in `docs/SPEC.md` §2.

Deliberately not redeployed to `periplo-testnet.fly.dev` as part of this
pass: the live facilitator keeps running against the previously pinned
`@x402/core` family until a real redeploy is asked for separately, same
"local change and a live redeploy are two different actions" boundary
already applied elsewhere in this file.

## Search relevance floor: fixed for real, but not fully, and a global cosine cutoff turned out to be the wrong shape of fix

A live user re-testing search against `periplo-testnet.fly.dev` (with
only two rows in the catalog at the time: the demo `temperature-convert`
HTTP resource and a stale MCP row cataloged back in Phase 4, before Phase
5's embedding pipeline existed) found that `GET /discovery/search`
returned `temperature-convert` for essentially any query string,
including `weather+forecast` and `financial_analysis`, always with
`partialResults: false`. Reproduced independently against the live
deployment before touching any code, not just trusted from the report.

Root-caused to two separate, stacked bugs, both confirmed directly
against the real live database with a raw `pg` connection before fixing
anything, not assumed from reading the SQL:

1. The `fts` generated column (`supabase/migrations/
   20260807202307_resources.sql`) only ever indexed `description` and
   `parameters`. The stale MCP row has `description: null` (the payment
   that cataloged it in Phase 4 never carried one), so its `fts` was an
   empty tsvector, unsearchable by any query, including its own literal
   tool name. Fixed by folding `tool_name`/`route_template` into the
   indexed text (`supabase/migrations/
   20260820100000_search_relevance_floor.sql`), and into
   `buildDiscoveryText` (`packages/search/src/discovery-text.ts`) for
   future embeddings too, so a thin listing is still findable by its own
   identity. The stale row's embedding was also backfilled from its
   (loosened) tool name via a one-off script, real code run against the
   live project, not a fabricated description.
2. `periplo_hybrid_search`'s semantic leg had no similarity floor at all:
   it returns the nearest embedded rows by `<#>` distance unconditionally,
   so with only one embedded row in a small catalog, that row was
   "nearest" (and therefore returned with a nonzero RRF score) for any
   query, relevant or not.

The second bug is the one that turned out to be genuinely hard, and the
first attempt at fixing it was wrong in a way worth recording rather than
quietly overwriting. A floor of 0.8 cosine similarity, calibrated against
real measurements of the one demo resource's own description (weather
forecast: 0.764, financial_analysis: 0.685, versus true matches like
"temperature conversion" at 0.870), was pushed live in
`20260820100000_search_relevance_floor.sql` and cleanly separated true
from false matches *for that one resource*. Re-running `pnpm eval` (the
real Phase 5 gate, 55 resources, 300 graded queries) against the migrated
database immediately showed why that calibration didn't generalize:
nDCG@10 collapsed from the committed baseline 0.9346 to 0.4632, a 50.4%
regression. Measuring the same model against `eval/golden.jsonl`'s own
372 real query/relevant-fixture pairs showed true-positive cosine
similarities ranging down to 0.625, with the graded-relevant (grade >= 2)
subset still as low as 0.678, both well inside the 0.6-0.8 band the
demo-resource calibration had treated as a clean cutoff.

There is no single global cosine floor that both preserves that real
recall and suppresses every false positive the original report
demonstrated: real true positives and the reported false positives
occupy overlapping ranges of the same model's raw similarity output, a
genuine property of BGESmallENV15's anisotropy on short text, not a
tuning miss fixable with a better constant. Corrected the default to 0.6
(`supabase/migrations/20260820110000_fix_semantic_floor_regression.sql`),
just under the real measured minimum true positive, verified back to
zero regression with a second real `pnpm eval` run. That default closes
the most degenerate case (a near-empty catalog returning any embedded row
for any query at all) and the `financial_analysis` reproduction (now
correctly returns the MCP resource, via the lexical fix above, ranked
alongside rather than hidden behind the semantic false positive). It does
**not** fully close the `weather forecast` reproduction: that query's
0.764 similarity to the demo resource sits well above 0.6, so
`temperature-convert` still appears for it, live, confirmed after the
fix. Left open on purpose rather than tuned back down to hide it: the
real fix for that case is architectural (RRF's `1/(k+rank)` fusion is
magnitude-blind by design, so it can't distinguish "the nearest of many
at 0.87" from "the nearest of one at 0.68"), not a constant, and is worth
its own scoped design pass once the catalog has enough real, non-fixture
resources to calibrate a magnitude-aware signal against.

## A second `exact`-scheme signer mode was attempted for real: real infrastructure, a real new upstream bug, no completed settlement yet

Every settled `exact` transaction recorded before this attempt
(`conformance/RESULTS.md`) signed the buyer's payment with that
account's own master key. Per direct feedback that conformance evidence
should cover more than one signer mode, run for real rather than
reasoned about, this attempted classic Stellar multisig: a second
Ed25519 key registered on `STELLAR_TEST_BUYER_PUBLIC` as an additional
signer (weight 1, the account's thresholds are the default 0, so any
registered signer's signature already satisfies every operation),
signing the payment instead of the master key.

**What's real and confirmed:** the second signer is genuinely registered
on-chain, a real `set_options` transaction
([`b398b5d7e02cd0b03965238bc504e82887e3406d70954b5c32683b0133434d70`](https://stellar.expert/explorer/testnet/tx/b398b5d7e02cd0b03965238bc504e82887e3406d70954b5c32683b0133434d70),
Horizon-verified: operation type `set_options`, `signer_key`
`GCZEA3FDEBKLJZDZZY4N6YDXPLAYUPW4YR2RDTDC33ARILF3T5BG4DRA`, weight `1`).
`apps/facilitator/scripts/multisig-signer-demo.ts` is the real script:
it registers the signer (idempotent, checked live against Horizon, not
assumed from a prior run), then builds a payment via `@x402/stellar`'s
real, unmodified `ExactStellarScheme` client, with a `ClientStellarSigner`
whose `address` is the buyer's account but whose `signAuthEntry`/
`signTransaction` sign with the second key only, the master key never
touched. `@x402/stellar`'s signer interface is SEP-43-based and
signer-agnostic by design (`{ address, signAuthEntry, signTransaction? }`,
never assumes the signing key matches `address`), which is what makes
this representable at all with zero changes to `@x402/stellar` itself.

**What actually happened, run for real, not assumed:** the payment build
step fails locally, before any network call, with `Error: signature
doesn't match payload`, thrown from `@stellar/stellar-sdk`'s own
`authorizeEntry()` (`base/auth.ts`). Traced to the real cause, not
guessed: `AssembledTransaction.signAuthEntries` (`contract/
assembled_transaction.js`, the method `@x402/stellar`'s client scheme
calls internally) wraps the caller's SEP-43 `signAuthEntry` in a closure
that calls it, then does exactly this and nothing else:

```js
const { signedAuthEntry, error } = await sign(preimage.toXDR("base64"), { address });
this.handleWalletError(error);
return Buffer.from(signedAuthEntry, "base64");
```

The `signerAddress` field a SEP-43-conformant signer explicitly returns
(and which our second-signer implementation does return, correctly, as
its own address) is read, then discarded: only the raw signature bytes
are passed on. Inside `authorizeEntry()`, receiving a bare `Buffer` (not
an object carrying `signature`/`publicKey`, the shape the function
otherwise supports) makes it fall into the "bare-signature fallback path"
of a *different*, previously-found bug in this same module (found while
working
[stellar/js-stellar-sdk#1655](https://github.com/stellar/js-stellar-sdk/issues/1655),
later filed on its own as
[#1683](https://github.com/stellar/js-stellar-sdk/issues/1683)):
it infers the verifying public key from the auth entry's own top-level
address (`Address.fromScAddress(addrAuth.address()).toString()`, the
buyer's master-key address) rather than from the signer that actually
produced the signature. The local sanity check then fails, correctly,
because the second signer's signature genuinely doesn't verify against
the buyer's master public key, exactly as written, but the *correct*
behavior would be to verify it against the second signer's own address,
which the discarded `signerAddress` field would have supplied.

**This looks like a real, new, filable bug, distinct from `#1655`, not
yet checked against duplicates or shown for approval.** `#1655` is about
`needsNonInvokerSigningBy()`/`signAuthEntries()` missing an outstanding
*delegate* signature in a CAP-71
`SOROBAN_CREDENTIALS_ADDRESS_WITH_DELEGATES` entry specifically. This
finding is different and broader: `signAuthEntries`'s own adapter to
`authorizeEntry` drops `signerAddress` unconditionally, for a plain,
non-delegate `SOROBAN_CREDENTIALS_ADDRESS` entry, which means *any*
signer whose returned address differs from the auth entry's top-level
address, not just a CAP-71 delegate, can never produce a signature
`authorizeEntry`'s bare-signature fallback will accept. Checked against
[`stellar/js-stellar-sdk#1610`](https://github.com/stellar/js-stellar-sdk/issues/1610)
(the closest-looking open issue found searching first): confirmed **not**
a duplicate, `#1610` is about `authorizeEntry`-override safety checks
being skipped and a different silent-`address`-fallback case, it does not
describe `signerAddress` being dropped. Root-caused to
`@stellar/stellar-sdk`, not to `@x402/stellar` or to anything in this
repo: the failing call (`authorizeEntry` in `base/auth.ts`) and its
caller (`signAuthEntries` in `contract/assembled_transaction.js`) are
both stellar-sdk source, read directly, not guessed from behavior alone.
Also confirmed structural, not something a different local script could
route around: `AssembledTransaction.signAuthEntries` is the *only* path
`@x402/stellar`'s exact-scheme client uses to produce a Soroban auth
entry signature, so this blocks every non-master-key signer mode
through the real, unmodified client path, not just classic multisig.
Soroban's own protocol-level check for a G-account `SorobanCredentials
::Address` entry is understood to replicate classic multisig
weight/threshold verification (the account-contract abstraction CAP-46-11
describes), so nothing here suggests the network itself would reject a
correctly-signed second-signer authorization, only that the client SDK
never manages to produce one.

**Filed as [stellar/js-stellar-sdk#1681](https://github.com/stellar/js-stellar-sdk/issues/1681),
same discipline as the six upstream bugs already filed before it, all
of it actually satisfied, not skipped for speed.** Re-verified against
the real published package a second time, this time by the user
independently, downloading `@stellar/stellar-sdk@latest` (17.0.0) and
reading the source directly rather than trusting this file's own
16.2.0-pinned repro: confirmed the same two defects present, byte-for-
byte identical logic in both versions. That independent pass also
sharpened the root cause of the first defect precisely:
`signAuthEntries`'s own `address = signerAddress(signAuthEntry) ??
this.options.publicKey` default calls `signerAddress` on `signAuthEntry`
itself, a plain function per `SignAuthEntryLike`'s own documented union
type (`SignAuthEntry | Signer | Keypair`), and `signerAddress`'s guard
(`typeof value !== "object"`) can never pass for a function, so the
default silently resolves to `this.options.publicKey` for the
simplest, most common, fully-documented usage pattern, not an edge
case. Checked for duplicates against `#1610` (confirmed not a
duplicate, that issue is about `authorizeEntry`-override preflight
checks being skipped, a different problem) and four other
`signAuthEntries`-related issues found searching first. The issue
itself proposes a fix for both defects, verified against the real
`authorizeEntry`/`toSignAuthEntry` source, not just the finding, per
the standing rule that a confirmed root cause with a reasonable fix
gets the fix included. Severity, stated honestly: not a security
vulnerability, it fails closed (a wrong signature is rejected, funds
are never at risk), it degrades functionality (this specific
signer-agnosticism the SEP-43 interface advertises silently doesn't
work end to end for the one path that actually needs it).

**Net effect on the "second signer mode" evidence goal:** not achieved
as a second settled transaction, the honest outcome of actually running
it rather than the one that would have made the strongest evidence-table
entry. What's real instead: a second signer genuinely registered
on-chain (kept, harmless, adds a key without touching the master one or
the account's thresholds), and `#1681` filed, the seventh real,
independently verified upstream bug this project has found and reported.
Revisit `multisig-signer-demo.ts` once a release ships the `#1681` fixes;
until then a non-master-key signer for this scheme stays unrepresentable
through `@x402/stellar`'s real, unmodified client, not a gap this repo can
close on its own.

**Update, 2026-09-26 (checked against the GitHub API that day):** `#1681`
was closed as completed. Both defects were fixed on `main` by
[#1743](https://github.com/stellar/js-stellar-sdk/pull/1743) (a
`signAuthEntries` call that signs no entry now throws `NoSignatureNeeded`)
and [#1744](https://github.com/stellar/js-stellar-sdk/pull/1744) (the
wallet's `signerAddress` is forwarded to the default authorizer), both
merged 2026-09-24. No `@stellar/stellar-sdk` release contains them yet
(latest `v17.1.0`, 2026-09-14; LTS `16.3.0`, 2026-08-28), so the
revisit above still waits on a release.

**Update, 2026-10-02 (checked against the GitHub API that day):** the
release the revisit was waiting on exists. [v17.2.0](https://github.com/stellar/js-stellar-sdk/releases/tag/v17.2.0) (2026-09-28) contains
`#1743` and `#1744` (their merge commits are ancestors of the tag and not
of `v17.1.0`); the latest release is now [v17.2.1](https://github.com/stellar/js-stellar-sdk/releases/tag/v17.2.1) (2026-10-01). So the
revisit of `multisig-signer-demo.ts` is unblocked, not done: it has not
been re-run against `v17.2.0` (this repo pins `@stellar/stellar-sdk`
`16.3.0`), and the LTS line (`16.3.1`, 2026-10-01)
carries only an asset-ordering backport, not these fixes.

## A second real catalog resource: genuinely blocked, not attempted with a shortcut

**Superseded 2026-08-26, see "`EXTENSION-RESPONSES` never reached a
seller through the official client" below**: the first real external
seller (Fer, `agentpayments.fi`) published and settled for real,
closing exactly the gap this section describes.

Per direct feedback that the catalog's weakest point against rival
submissions' real payment volume is having exactly one real, externally-reachable
resource, not two: a second one, ideally from a third party, was asked
for. Not built this round, for two separate, real reasons, neither
worked around:

1. **A second self-authored resource still needs a real, externally-
   reachable deployment**, and the one thing this repo already deploys
   to, `periplo-testnet.fly.dev`, is exactly the app the same
   `fly`-CLI-account gap above (and twice before it, see "Fly.io
   redeploy blocked" below) currently blocks this session from
   redeploying. A resource that exists only in this repo's source and
   never actually serves a request behind a real URL cannot pass
   `packages/bazaar/src/catalog-url.ts`'s own `checkCatalogUrl` gate
   (rejects `localhost`/unreachable hosts, the exact bug class the
   2026-08-19 external-QA round already fixed once), so building the
   code without the ability to deploy it would not produce a real
   second catalog row, only the appearance of one. Not attempted as a
   fake/local-only entry for that reason.
2. **A third-party resource is a real coordination problem, not an
   engineering one.** It needs an actual second team choosing to list a
   real paid service against this project's live catalog. That is
   outside what a single build session can produce unilaterally, the
   same category of limit as the Audit Bank application and the Matrix/
   Mastodon channels in the "External accounts not yet provisioned"
   list above, not a gap this session declined to close out of
   laziness.

Both blockers are logged rather than routed around. The practical next
step, once the Fly account is resolved: redeploy with a second, genuinely
different demo resource (not a copy of temperature-convert), which at
minimum restores "two real self-hosted resources" and gives the search-
ranking evidence `docs/DEFERRED.md`'s own search-relevance section
already flags as thin (`eval/`'s fixtures are synthetic; the live
catalog itself has never had more than one real row to rank against). A
third-party listing stays a standing ask, not something to manufacture.

## Cataloging moved to settle-only, closing a real free-mint path the spec text leaves open

`apps/facilitator/src/app.ts`'s `/verify` handler used to run
`processBazaarExtension` whenever `core.verify()` returned
`isValid: true`, the same trigger `/settle` uses on `result.success`.
That reading is spec-conforming as written:
`specs/extensions/bazaar.md`'s Facilitator Behavior section describes
validating `info`/`schema` and extracting discovery information without
mentioning settlement anywhere, and the `EXTENSION-RESPONSES`
response-header section is written generically as "the verify or
settlement response." But `isValid: true` only proves a payload is a
well-formed, correctly-signed authorization that *could* settle. No
funds move on verify, and a signed-but-never-submitted (or never-funded)
authorization still verifies. Cataloging on that signal means a catalog
row, and each `accepts` entry in it, costs one HTTP request and no
balance.

This is exactly the ambiguity
[x402-foundation/x402#3226](https://github.com/x402-foundation/x402/issues/3226)
opened to audit, with a real, reproduced example: a payload sent to a
live facilitator's `/verify` and deliberately never settled still
produced a catalog entry, no tokens moved. Two other implementers
independently reached the same read this session did, worth noting
because none of the three coordinated on it beforehand: the issue itself
observes that CDP's own pipeline engages at verify, and
[pedro-pelicioni](https://github.com/pedro-pelicioni) (stellarsight, a
second real Stellar-side facilitator+Bazaar implementation, see
`docs/UPTO-CONVERGENCE.md`) replied in the same thread that his
facilitator's catalog write sits inside `if (success)` in the `/settle`
handler and that `/verify` never touches the catalog at all, code
checked directly at
[`stellarsight/apps/facilitator/src/server.mjs`](https://github.com/pedro-pelicioni/stellarsight/blob/main/apps/facilitator/src/server.mjs)
before citing it here, not taken on the strength of the comment alone.

Periplo's own catalog schema has no popularity, call-count, or
buyer-count column today (`supabase/migrations/*.sql`, checked directly:
`hybridSearch`'s ranking is lexical+semantic only, see the wash-trading
design note above), so the specific "counter reads as a demand signal"
harm the issue centers on does not apply to this project's ranking yet.
What does apply regardless of ranking: a resource's mere presence in the
catalog, and which payment options it claims to accept, could previously
be minted for free, for any `resource.url` an attacker chose to claim,
without ever completing a payment. Settle-only closes that path
entirely, since `result.success` means a real transfer happened,
confirmed the same way every other settlement in this repo is confirmed
(Horizon/RPC, not the facilitator's own say-so).

Changed in `apps/facilitator/src/app.ts` (the `/verify` handler no
longer calls `processBazaarExtension` under any condition) and
`apps/facilitator/src/discovery.ts` (comments corrected to stop
describing cataloging as a "/verify or /settle" concern, since it is now
settle-only everywhere `processBazaarExtension` is ever called,
including `demo-resource.ts`'s `onAfterSettle` hook, which was already
settle-only). `apps/facilitator/src/app.test.ts` updated to match: the
tests that used to exercise bazaar validation/rejection against `/verify`
now exercise the identical logic against `/settle` instead (the
validation code itself is unchanged, only which endpoint triggers it),
plus a new regression test asserting `/verify` never emits
`EXTENSION-RESPONSES` for a valid declared extension. `pnpm run ci`
green throughout, 255 tests (net -1 from the prior count: two
verify-specific cases collapsed into one settle-only case that already
covered the same validation logic, plus one new regression test).

No upstream issue filed for this: `#3226` already exists, already
frames the ambiguity precisely, and already has this project's own data
point in it via Pedro's reply citing the equivalent stellarsight code.
Filing a second, near-duplicate report would add noise to a thread that
is already being read carefully by the working group, not signal.

## `extensions.bazaar` was echoed empty for every resource, found reconciling a third party's report rather than assuming either side

A conformance report from a real integrator claimed three gaps against
`temperature-convert` (the demo resource): empty `description`, no
`bazaar` declaration, and phantom CORS headers. Checking the raw 402
challenge directly (`GET /demo/temperature-convert` unpaid) contradicted
two of the three: `description` was fully populated, and `extensions.bazaar`
carried the complete declared object (`info`, `schema`, per-parameter
descriptions). Only the empty `mimeType` matched, and CORS was
genuinely absent everywhere tested (no `access-control-*` header on any
route, `Origin` present or not), matching neither the report's specific
"phantom headers" framing nor a real CORS implementation.

Rather than conclude the report was simply wrong, the discrepancy was
checked against the actual discovery API instead of the raw challenge:
`GET /discovery/resources` and `GET /discovery/search` both returned
`extensions.bazaar: {}` for `temperature-convert`, the same symptom the
report described. This is a real, general bug, not specific to the two
already-known stale rows: `resources.extensions: text[]` (added Phase 2)
only ever recorded which extension *keys* a resource declared, never
their payloads. `discovery-routes.ts`'s `toDiscoveryResource` then
mapped each key to a fabricated `{}` rather than omitting the field or
sourcing real content, since there was no real content stored to source.
This directly contradicts the installed `@x402/extensions/bazaar`
package's own `DiscoveryResource` type, which documents that field as
"Extension payloads echoed from discovery (e.g. bazaar info/schema)",
checked against the real `.d.ts`, not assumed from the wire spec's
prose.

Fixed by persisting the missing half: `extension_payloads jsonb`
(migration `20260826010000_extension_payloads.sql`), written from
`discovery.ts`'s already-validated `rawExtRecord`, the same object
`processBazaarExtension` already extracts `description`/`parameters`
from, just never stored verbatim before. `periplo_hybrid_search`'s
`RETURNS TABLE` shape changed to include it, which required an explicit
`DROP FUNCTION` before `CREATE FUNCTION`: PostgreSQL's `CREATE OR
REPLACE FUNCTION` cannot change a function's return type at all, the
return-type sibling of the argument-list lesson
`20260820103000_drop_old_hybrid_search_overload.sql` already learned
the hard way. Applied proactively this time rather than rediscovered via
a failed `supabase db push`.

Verified against the live deployment, not just locally: deployed the
fix (`fly deploy --config fly.facilitator.toml --dockerfile
Dockerfile.facilitator`), then ran a real signed payment against the
live `/demo/temperature-convert`
(`apps/facilitator/scripts/demo-resource-settle.ts`) to re-catalog it
through the new write path, since a row cataloged before this migration
keeps `extension_payloads: {}` until its next payment. Settled
transaction
[`12470945ac72aed3b781f102848f2346c85e3c85d874fb2a3ff6cf17df6cd375`](https://stellar.expert/explorer/testnet/tx/12470945ac72aed3b781f102848f2346c85e3c85d874fb2a3ff6cf17df6cd375),
Horizon-verified (`successful: true`). Re-queried `GET /discovery/search`
afterward: the full `info`/`schema` object is now present, confirmed
directly against the live response, not inferred from the code change
alone.

Separately, the same reconciliation surfaced the `financial_analysis`
Phase 4 fixture (`mcp://tool/financial_analysis_da8703fa-...`) as real,
ongoing pollution: it appeared in every search result regardless of
query relevance (confirmed with two unrelated queries), still carrying
literal placeholder `asset`/`pay_to` values from 2026-08-11 that the
2026-08-19 backfill's URL fix never addressed. Deleted (migration
`20260826020000_delete_stale_financial_analysis_fixture.sql`), confirmed
gone via the live REST API and both discovery endpoints (`GET
/discovery/resources` now reports `total: 1`, `temperature-convert`
only).

**Resolved, 2026-08-26: the CORS-header part of the report was never
about Periplo.** Confirmed by the report's own author directly, and
independently corroborated rather than taken on their word alone: their
CORS/conformance table measures a different `.fly.dev` deployment,
not Periplo's. Checked that endpoint directly to confirm it's
structurally capable of producing the report's
observations: it genuinely runs `@x402/express` with a real CORS setup
(`access-control-expose-headers` present, listing `X-MPP-Warning`, the
exact unrelated header already named in `#3148`'s own root cause),
unlike Periplo's facilitator, which was already confirmed to have zero
CORS code anywhere. Both zero-CORS-in-Periplo and real-CORS-in-the-other-
deployment are independently verifiable facts, not a report reinterpreted to fit a
convenient story.

**A separate, adjacent finding noticed while verifying the fix above,
not yet acted on:** `resources.last_updated` never actually updates on
a repeat payment. Its schema default (`timestamptz not null default
now()`) only applies on the initial `INSERT`; `upsertCatalogResource`
never explicitly sets it, and PostgREST's `upsert` only touches columns
present in the write payload, so a resource paid for many times still
reports its original cataloging date. Confirmed live:
`temperature-convert`'s `lastUpdated` stayed `2026-08-19T17:59:27...`
even immediately after the real re-cataloging payment above. Undermines
`GET /discovery/resources`'s own `order by last_updated desc` (a
repeatedly-paid resource doesn't actually sort as "recently active"),
though the practical impact on a catalog this size is currently zero
(one real resource). Not fixed in this round: found verifying a
different fix, not the thing being verified, and flagged rather than
folded in silently.

## `EXTENSION-RESPONSES` never reached a seller through the official client, found live by the first external seller

The first real external seller (Fer, `agentpayments.fi`) published a
resource and settled a real payment against it, closing the loop this
whole round of fixes exists for: cataloging worked, search worked, and
the loop actually reached a third party's real code, not just this
project's own scripts. In the process they found a new, real,
money-relevant bug: `EXTENSION-RESPONSES` never reached their code from
`/settle`, even though the catalog write genuinely happened. They ruled
out their own side carefully (their client forwards and exposes headers
correctly when one arrives) before reporting it.

Root cause verified before proposing anything, same standard as every
other finding here. A direct `fetch` to `/settle` (Node, not a browser,
so no CORS header-visibility restriction applies) shows the header
genuinely present and correctly decoded on the raw wire -- Periplo's own
code was never the problem. The actual gap is in the installed
`@x402/core@2.22.0` dependency itself: `HTTPFacilitatorClient`'s
`settle()`/`verify()` methods call `logExtensionResponsesHeader`, which
reads `EXTENSION-RESPONSES`, `console.log`s a sanitized summary, and
discards it -- nothing about the extension outcome is attached to the
object those methods return to the caller. Confirmed reading the actual
compiled source (`dist/cjs/server/index.js` and `dist/cjs/http/index.js`
both bundle the identical function), not assumed from behavior alone. A
seller using the officially documented client, the same one
`docs/SELLERS.md`'s own quickstart shows, structurally cannot read this
header: the client never exposes the raw `Response` object, only the
parsed JSON body.

Fixed without waiting on an upstream change. `SettleResponse` (and
`VerifyResponse`) already declare an optional `extensions` field,
verified against the real `.d.ts`, which `HTTPFacilitatorClient`'s own
response schema already parses and returns to the caller: the field
exists, it was simply never populated because Periplo's own `/settle`
never put anything in the body's `extensions` key, only the header.
Sending it in both places now costs nothing and needs no upstream fix
to start working today, for every seller already using the current
pinned SDK version. Verified through the actual official client, not
just a raw fetch: a real settled payment via
`HTTPFacilitatorClient.settle()` now returns `settleResult.extensions`
populated with `{ bazaar: { status: "success" } }`, transaction
[`10919a59342fc0cc69d3698a58cf7fb76f3e997914e16562ffa39bbf7f70af28`](https://stellar.expert/explorer/testnet/tx/10919a59342fc0cc69d3698a58cf7fb76f3e997914e16562ffa39bbf7f70af28),
Horizon-verified. `docs/SELLERS.md`'s "Confirm the listing landed"
section was also corrected: it referenced "/verify and /settle" (stale
since the settle-only fix earlier this round) and its "decode it
yourself" advice didn't warn that doing so means bypassing
`HTTPFacilitatorClient` entirely; the more reliable alternative
(query `GET /discovery/resources`/`search` right after settling) is now
documented alongside it.

**Filed, 2026-08-26, after explicit approval:**
[x402-foundation/x402#3270](https://github.com/x402-foundation/x402/issues/3270),
the ninth real, independently verified upstream bug this project has
found, same bar as the other eight (verified against the real published
package, not just source reading; severity calibrated honestly, not a
security issue, fails closed). Draft reviewed line-by-line against the
real installed source before approval, not accepted on the strength of
the writeup alone; root cause correctly attributed to `@x402/core`
throughout, nothing in it implicates Periplo's own code.

**A metric correction adopted from the same seller, going forward, not
retroactive:** citing a raw JSON character count (e.g. "1,346
characters") to compare a discovery payload's completeness across
implementations is not a real measure -- it depends on serialization
choices (key order, whitespace, JS vs. Python's JSON encoder) that have
nothing to do with actual content. Never written into this repo's own
docs, so nothing to correct there, but noted here so a future session
doesn't reach for it: count parameters actually described instead,
which is what the underlying claim ("the declaration is complete") is
actually about.

**A separate, narrow, transient finding, not a bug in the classic
sense:** `pnpm eval` seeds and cleans up its 55-fixture golden dataset
against this project's one and only Supabase project, the same one the
live catalog uses (`eval/run.ts` reads `SUPABASE_URL`/
`SUPABASE_SERVICE_ROLE_KEY` directly, no separate eval-only project
exists). Caught live: a `GET /discovery/resources` call made during a
CI run's `pnpm eval` step (triggered by a push, confirmed by correlating
the exact fixture-insertion timestamps against `gh run list`'s
`createdAt` for that commit) briefly showed 57 resources, 55 of them
eval fixtures, before the run's own `finally`-block cleanup removed them
seconds later, confirmed by re-querying immediately after and seeing the
real count again. Working as designed (`cleanupFixtures` in `eval/run.ts`
runs in a `finally`, even on failure), but the design itself means
anyone, an SCF panelist included, who happens to load `/discovery/search`
during the roughly 30-second window a CI eval run is active sees a
badly polluted result. Not fixed in this round: the practical fix (a
separate eval-only database, or seeding into a schema/tenant the public
routes never query) is a real infrastructure change, not something to
retrofit into an unrelated bug-fix commit.

**2026-08-31: the same root cause caused a real CI failure, not just a
cosmetic polling window.** Two pushes 83 seconds apart
(`3497edab`/`68141738`) triggered two overlapping GitHub Actions runs,
confirmed by comparing both runs' own `Seeding`/`Running`/result log
timestamps: the earlier run's query loop (13:36:54-13:38:11) was still
active when the later run started seeding (13:37:47) and querying
(13:38:01) the same 55 deterministic fixture URLs, then the earlier
run's `finally`-block cleanup (starting ~13:38:11) deleted those shared
rows while the later run's own 300-query loop was still reading them.
`nDCG@10` collapsed from 0.9332/0.9346 to 0.2121, correctly failing the
gate; the live catalog itself was confirmed back to its real 2-resource
count immediately after, so this was a transient race, not a lasting
data-loss incident. Root-caused before considering it resolved, not
just re-run past: `.github/workflows/ci.yml` had no `concurrency` group
at all, so nothing prevented two pushes from ever racing the same
production catalog. Fixed with a `concurrency: { group: ci-${{
github.ref }}, cancel-in-progress: true }` block, which cancels a
still-running run for the same ref the moment a newer one supersedes
it, closing this specific race. The underlying "eval and production
share one database" design this section already flagged is still real
and still open; the concurrency fix prevents the two-runs-racing
symptom, not the single-run pollution window above.

**2026-09-27: resolved, CI no longer touches the production project.**
`ci.yml` starts an ephemeral local Supabase (`supabase start`, CLI
2.115.0, `supabase/setup-cli` pinned by SHA) built from
`supabase/migrations/`, and both `pnpm eval` and the integration suites
run against it; the `build` job no longer references the production
Supabase secrets. The pollution window was visible from the public site:
`/status` showed `catalogSize` 58 (the 3 real rows plus the 55 fixtures)
while a push's CI ran `pnpm eval`, and 3 again once cleanup finished.
Three guards keep it from returning:

- `assertSupabaseUrlSafeForTests` makes both `loadSupabaseTestEnv` helpers
  and `pnpm eval` refuse a non-local `SUPABASE_URL` unless
  `PERIPLO_ALLOW_REMOTE_SUPABASE_TESTS=1`, so a local run with the
  production URL in `.env` cannot write to the live catalog either.
- The integration suites delete leftovers under their reserved URL prefix
  in `beforeAll`. Their comment used to say they swept a crashed run's
  leftovers while the code only deleted exact URLs.
- The RLS suite can still be run against the real project, on demand, from
  the manual `prod-parity` workflow (`workflow_dispatch` only). It was added
  in this change and has not been run yet.

A Phase 2 test row (`https://periplo-phase2-test.example/...`, written
2026-09-11T01:40Z, between two CI runs) stayed in the public catalog until
2026-09-27; the likely cause is an interrupted local `pnpm test`, not
confirmed. Measured on the ephemeral stack: nDCG@10 0.9334 and MRR 0.9209
on the first run, against 0.9330 to 0.9354 and 0.9203 to 0.9237 on the last
seven runs on `main` against production. The committed baseline stays
0.9346.

## Production's `anon` role has table privileges the migrations do not declare

Found 2026-09-27, the first time the RLS suite ran against a database
built only from `supabase/migrations/`. `20260807202307_resources.sql`
grants `anon` and `authenticated` `select` on `resources` and nothing
else. On that database, an `anon` UPDATE or DELETE fails with `42501
permission denied` (two tests failed in
[CI run 36376547022](https://github.com/Eras256/Periplo/actions/runs/36376547022)).
On the production project the same requests, sent as no-ops on a row that
cannot exist, return HTTP 200 with an empty result, which means `anon`
holds table-level UPDATE and DELETE there and only RLS (no write policy)
stops the write. Writes are still blocked in production; what is missing
is the second barrier the migration intends. Not checked: the exact grants
on the production table, or whether INSERT differs. The two tests now
accept either outcome and confirm through the service role that the row is
unchanged. Open, and a production change for the owner to decide: a
migration that revokes `insert, update, delete` on `resources` from
`anon` and `authenticated`. The manual `prod-parity` workflow shows the
current state on demand.

## `describe.skipIf` does not skip when the env helper returns `null`

The integration suites read `env` inside the `describe.skipIf(!env)`
callback (`const { url } = env as NonNullable<typeof env>`). With
`vitest@4.1.11` the callback still runs while collecting, so without
credentials the file fails with `Cannot destructure property ... of 'env'
as it is null` instead of skipping. Reproduced on a pristine checkout of
`origin/main`. CI is unaffected for the Supabase suites now that it always
provides a local stack; `apps/facilitator/src/core.test.ts` still fails
this way without the `STELLAR_FEE_SPONSOR_*` secrets (fork PRs, local runs
with no `.env`). Not fixed here.

## `@x402/core` has a newer client-side `spendControls` guard than what's pinned, found testing someone else's PR, not our own dependency review

Found live, 2026-08-26, running a real end-to-end check of
[x402-foundation/x402#3278](https://github.com/x402-foundation/x402/pull/3278)
(the community's fix for our own `#3270`) against the live facilitator:
building `@x402/core` from that PR's branch (based on a newer `main`
than the `2.22.0` this project pins,
`apps/facilitator/package.json`) pulled in a client-side
`spendControls` guard that rejects a payment requirement whose asset
isn't in a default allowlist unless the caller explicitly opts in
(`client.setSpendControls(false)`, or an `allowedAssets` entry).
`temperature-convert`'s self-issued `PTEST`-backed asset isn't a
default one, so `x402Client.createPaymentPayload` threw until that was
set. Not a bug in `#3278` itself, unrelated to its diff, and not
reproducible against `2.22.0` at all since the feature doesn't exist
there yet.

Worth tracking deliberately rather than discovering it again at the
next dependency bump: this project's own `x402Client` usage (any
script or future resource-server code building payment payloads
client-side, e.g. `apps/facilitator/scripts/*-settle*.ts`,
`demo-resource-settle.ts`) will need the same `setSpendControls(false)`
(or a real `allowedAssets` entry naming `PTEST`/testnet USDC) the
moment `@x402/core` is bumped past whatever version introduces this
guard, or those scripts start failing exactly the way this
verification run initially did. Not urgent (still pinned to `2.22.0`,
which predates the guard), but a real, concrete thing to check the
changelog for before the next `@x402/core` version bump, not just
"upgrade and see what breaks."

## `#3270` closed upstream on a different field shape than this project's own workaround uses

`x402-foundation/x402#3270` closed 2026-08-31, but not via `#3278`
(TypeScript) or `#3301` (Go), the two community PRs `README.md`
tracked. The actual fix was a maintainer's own separate PR,
[`#3306`](https://github.com/x402-foundation/x402/pull/3306) (Python,
phdargen), which explicitly rejected the shape this project's own
`/settle` workaround (`apps/facilitator/src/app.ts`,
`c.json({ ...result, extensions: extensionResponses })`) and the
original `#3278`/`#3301` all took: merging the `EXTENSION-RESPONSES`
header data into the existing `extensions` field. `#3306`'s own
description calls that "the wrong shape," since `extensions` is
forwarded to buyers via `PAYMENT-RESPONSE`, leaking a server-only
facilitator sidechannel into buyer-facing data. It introduces a
separate `extension_responses` (Python) / `extensionResponses` (TS,
after `#3278` was revised to match before its own, later merge) field
instead, excluded from that encoding.

Worth tracking, not urgent, and not gated on an upstream release: no
`@x402/core` release ships this new field shape yet (npm `latest` is
`2.24.0`, from 2026-08-27, predates both merges), but `app.ts`'s own
`/settle` response body is entirely this project's own code, the same
way it already sent `extensions` ahead of any client actually reading
it. Add `extensionResponses` alongside the existing `extensions` field
(both, during a transition window, not a replacement) the next real
time `app.ts` is touched, rather than waiting on a package bump that
isn't a precondition for it. Acknowledged publicly on
[x402-foundation/x402#3270](https://github.com/x402-foundation/x402/issues/3270#issuecomment-5488304824),
2026-08-31.

**Done, 2026-09-01** (`ddc2a38`): `/settle` sends `extensionResponses`
alongside `extensions`, `extensions` itself untouched, per the plan
above. Re-verified the shape against the real merged source before
writing the change, not from this file's own prior description alone:
`typescript/packages/core/src/types/facilitator.ts` and
`http/httpFacilitatorClient.ts` on `x402-foundation/x402`'s current
`main`. One thing that description above didn't say, found doing the
verification: the official `HTTPFacilitatorClient` doesn't read
`extensionResponses` from the response body at all.
`settleResponseSchema`/`verifyResponseSchema` don't declare it as a
field, so Zod strips it from the parsed body, and
`attachExtensionResponsesFromHeader` sets it afterward purely from the
`EXTENSION-RESPONSES` header, which this facilitator already sends
correctly (the original `#3270` fix). That client gets
`extensionResponses` for free, from the header, with no body change
needed; sending it in the body is for any other caller reading the
JSON directly, the same reasoning `extensions` was added under
originally. New regression test in `app.test.ts` covers the body
shape (`extensionResponses` present, equal to `extensions`), not
client-side header parsing, which was already covered by the existing
`EXTENSION-RESPONSES` header tests. `pnpm run ci` green, 258 tests.

**Upstream follow-up, verified live 2026-09-07:**
[`#3301`](https://github.com/x402-foundation/x402/pull/3301) (Go) merged
`2026-09-02T12:57:19Z` (merge commit `eb0d899e`, by phdargen), carrying
the same `extensionResponses`/`extension_responses` sidechannel shape
`#3278` (TypeScript) and `#3306` (Python) landed, not the
merge-into-`extensions` shape the original community PRs took. Three
SDK-language fixes now trace to `#3270`: TypeScript and Go merged
upstream, Python resolved via `#3306`; one further Python attempt stays
open in its author's own fork, never proposed upstream. No `@x402/core`
npm release ships this shape yet (`latest` is still `2.24.0`), and it
isn't a precondition for anything here: `/settle` already sends both
fields. `README.md` carries the full writeup; this is the dated pointer.

## Proactive dependency audit, 2026-09-01: four filed, three real fixes, one genuine retraction

Following the pattern that already produced `#3121`, `#3169`/`#3213`,
`#3172`, `#3187`/`#3228`, `#3270`/`#3306`, and the `js-stellar-sdk` auth-entry
findings, this round searched deliberately rather than waiting to trip
over the next bug: three background passes over the latest published
`@x402/core@2.24.0`, `@x402/stellar@2.24.0`, and
`@stellar/stellar-sdk@17.0.1`, each reading compiled source against its
own documented type or JSDoc contract and building a real repro before
reporting anything. Four candidate findings came out of that pass, and
per direct instruction, each fixable one got a PR opened immediately
rather than left as a bug report for a maintainer to fix (the lesson
named explicitly: reporting `#3270` without a proposed fix meant the
maintainer's own, differently-shaped fix landed instead of this
project's).

**One finding was wrong, and closing it honestly mattered more than
the fix count.**
[stellar/js-stellar-sdk#1699](https://github.com/stellar/js-stellar-sdk/issues/1699)
originally reported that `XdrLargeInt.toU128()`/`.toU256()`/`.toU64()`
silently wrap a negative value into a huge unsigned magnitude instead
of throwing `RangeError`, based on reading `XdrLargeInt`'s own unit
tests in isolation. Writing the actual fix and running the package's
*full* test suite (not just the touched file) surfaced
`test/unit/base/numbers/sc_int.test.ts`, a block explicitly labeled
"from scint_test.js" (a shared, cross-SDK test-vector file), which
deliberately constructs a negative `ScInt` and asserts `.toU128()`/
`.toU256()` return the two's-complement reinterpretation, the exact
behavior reported as a bug. Combined with an existing `toU64()` test
already named "reinterprets negative signed value as unsigned," this
confirmed the wrap is intentional, cross-SDK-consistent design, not an
oversight. The patch was reverted before ever being pushed; the issue
was corrected with the full evidence and closed by the same session
that filed it, rather than left for a maintainer to untangle. Standing
lesson for any future dependency audit: run the *whole* test suite
after writing a fix, not just the file the fix touches. A prior round's
`#3172`/`derivePattern` finding never had this risk since it had no
adjacent hidden consumer; this one did, and only running everything
caught it.

**Three real, fixable findings, each with a PR opened the same
session, not just an issue:**

- [stellar/js-stellar-sdk#1699](https://github.com/stellar/js-stellar-sdk/issues/1699):
  closed as not-a-bug, see above.
- [x402-foundation/x402#3332](https://github.com/x402-foundation/x402/issues/3332),
  fix at
  [x402-foundation/x402#3336](https://github.com/x402-foundation/x402/pull/3336):
  `ExactStellarScheme`'s `feeBumpSigner` is documented by `getSigners()`
  as a facilitator address, but the internal set every facilitator-
  safety check actually consulted (`signingAddresses`) never included
  it. Fixed with a separate `facilitatorSafetyAddresses` set rather
  than merging into `signingAddresses` directly, since that set also
  backs signer *selection* in `settle()` and `feeBumpSigner` has no
  entry in the signer map, a distinction that would have been an easy
  regression to introduce carelessly. Regression test added and run
  against the real class; full `@x402/stellar` suite green before and
  after (157 to 158 tests).
- [x402-foundation/x402#3334](https://github.com/x402-foundation/x402/issues/3334),
  fix at
  [x402-foundation/x402#3338](https://github.com/x402-foundation/x402/pull/3338):
  `resolveSettlementOverrideAmount()` never enforced its own documented
  invariant, "the resolved amount must be `<=` the authorized maximum
  in `PaymentRequirements`," for any of its three input formats. Fixed
  with one check centralized at the end of the function rather than
  duplicated per branch. Writing this fix surfaced its own lesson: two
  existing test fixtures and one integration fixture (a `"$10.00"`
  price that produced a non-integer `PaymentRequirements.amount` the
  new check's `BigInt()` parse can't accept) needed adjusting, none of
  it a behavior change, all confirmed by re-reading what each test
  actually asserted before touching it. Full `@x402/core` suite green
  before and after (691 to 695 tests), plus a check of every other
  workspace package that references `SettlementOverrides` to confirm
  none had hidden dependence on the old, unchecked behavior.
- [x402-foundation/x402#3333](https://github.com/x402-foundation/x402/issues/3333),
  addressed at
  [x402-foundation/x402#3339](https://github.com/x402-foundation/x402/pull/3339):
  `areFeesSponsored: false` is accepted with no validation at
  construction time, then breaks every settlement through the official
  client elsewhere, with no indication the facilitator's own config is
  the cause. The originally proposed fix (throw at construction) turned
  out to be wrong for the same reason as the `#1699` retraction above:
  an existing, clearly deliberate test,
  `"should use custom areFeesSponsored"`, asserts that constructing
  with `false` succeeds. Landed as a doc-only PR instead (cross-
  referencing the limitation on the constructor's own JSDoc, where
  `getExtra()` already states it two methods away), not a behavior
  change, so it can't conflict with that test.

A stray fork of `x402-foundation/x402` from an earlier session round
was 89 commits behind upstream when re-cloned for this round (`gh repo
fork --clone` does not sync an existing fork before cloning it,
confirmed via `git rev-list --count`). The `#3332` fix's PR was opened
from that stale base, but not affected in substance, since the diffed
file was untouched across those 89 commits (confirmed via `git log`).
Caught and fixed (fast-forward-merged onto the real upstream `main`,
pushed to the fork) before starting work on `#3334`, whose target file
*had* moved between the stale base and current upstream. Worth naming
as its own environment gotcha: a fork used across multiple sessions can
silently drift stale, and the safe default is to fetch and
fast-forward the fork's default branch before branching off it, not
assume a fresh `--clone` implies a fresh fork.

None of these four findings is a security vulnerability; each fails
closed, degrades functionally, or (`#1699`) turned out not to be a bug
at all, calibrated the same honest way as every other finding in this
list.

## A real maintainer review on #1672, then the same defect recurring independently in a different SDK, 2026-09-01

Two more findings the same day, in the base Stellar SDKs rather than
x402 packages, per a direct instruction to widen the search past
`x402-foundation/x402` to the tooling the whole Stellar ecosystem builds
on, not just this project's own SCF-round competitors.

**First, a real human maintainer, not Copilot, reviewed #1672 itself.**
Ryang-21 left `CHANGES_REQUESTED` and five inline comments on
[stellar/js-stellar-sdk#1672](https://github.com/stellar/js-stellar-sdk/pull/1672),
each a genuine silent-signature-corruption or dead-end path on the new
CAP-71 delegate-signing surface: stale-expiration reuse across
sequential signers, a missing already-signed guard, an unreachable path
for a contract-address delegate, a custom `authorizeEntry` silently
dropping the new `forAddress` argument, and the #1683 fix belonging in
`base/auth.ts` rather than the narrower workaround #1672 shipped with.
All five fixed in one commit (`0dd1c624`), each with a dedicated new
test, `upstream/main` merged afterward (`81466fd9`, a merge commit, not
a rebase, so Ryang-21's existing comment anchors didn't move), full
suite re-verified post-merge (132 files, 6743 tests), replied to each
thread with the real commit. CI shows `action_required`, GitHub's
standard external-PR gate, not a failure. Full detail in `README.md`'s
#1672 history; not repeated here since that account didn't need
correcting, unlike the retraction above.

**Update, 2026-09-26 (checked against the GitHub API that day):** #1672
was closed without merging, in favor of Ryang-21's own
[#1747](https://github.com/stellar/js-stellar-sdk/pull/1747)
(`Closes #1655`, approved 2026-09-24), which walks CAP-71 delegate trees in
`needsNonInvokerSigningBy()` behind an opt-in `includeDelegates` option.
Two other points from this section landed upstream as separate,
maintainer-authored PRs: the `forAddress` fix for
[#1683](https://github.com/stellar/js-stellar-sdk/issues/1683) in
`base/auth.ts`
([#1742](https://github.com/stellar/js-stellar-sdk/pull/1742), merged
2026-09-24, `Closes #1683`), and documentation of what
`needsNonInvokerSigningBy()` can and cannot see
([#1745](https://github.com/stellar/js-stellar-sdk/pull/1745), merged
2026-09-25, `Closes #1700`). A comment on #1747 (2026-09-26) names one case
it does not cover, a signed `C…` account with an unsigned nested delegate
(its docstring documents that a signed node's delegates are not checked),
and corrects this project's earlier #1655 reproduction, which used `G…`
top-level accounts: per #1747's docs, a `G…` node's delegates are not
consulted in protocol 27 (CAP-72, which adds delegation for `G…` accounts,
is still Draft). `#1655` remains open pending #1747. None of these fixes is
in a published `@stellar/stellar-sdk` release yet. One more correction:
entries in this file say CAP-71 is not live on any network, which was true
when they were written. CAP-71's own header says protocol 27, and both
`horizon.stellar.org` and `horizon-testnet.stellar.org` report protocol 28
as of 2026-09-26, so those "no impact today" severity notes no longer hold.

**Update, 2026-10-02 (checked against the GitHub API that day; this
supersedes "`#1655` remains open pending #1747" and "none of these fixes is
in a published release" above):** `#1747` merged on 2026-09-28 and closed
`#1655` as completed. [v17.2.0](https://github.com/stellar/js-stellar-sdk/releases/tag/v17.2.0) (2026-09-28) contains `#1742`, `#1745` and
`#1747` (plus `#1743`/`#1744`, see the `#1681` entry above); each merge
commit is an ancestor of the `v17.2.0` tag and none is in `v17.1.0`. The
released `needsNonInvokerSigningBy()` has no `includeDelegates` option:
it always walks delegate trees, so the "opt-in `includeDelegates`" shape
described above did not ship, and `ignoreContractDelegates` on `sign()` and
`signAndSend()` is the opt-out. The latest release is now [v17.2.1](https://github.com/stellar/js-stellar-sdk/releases/tag/v17.2.1)
(2026-10-01).

**Second, resuming the broader search this review had paused, the same
defect class turned up independently, the same day, in a different
official SDK.** `StellarCN/py-stellar-base`'s `authorize_entry()`
(`stellar_sdk/auth.py`) signs each CAP-71-01 delegate correctly in
isolation, but silently overwrites the entry's one shared
`signature_expiration_ledger` field on a later delegate's signing call,
invalidating an earlier delegate's already-stored signature whenever the
two calls pass different expirations, with no error raised at either
step. The library's own docstrings state the requirement in prose twice
("every signer of one entry must use the same
`valid_until_ledger_sequence`, otherwise earlier signatures are
invalidated") but nothing in code enforces it, and
`AssembledTransaction.authorize()`/`sign_auth_entries()` never reach this
path at all: by explicit design they only ever target the top-level
address (`needs_non_invoker_signing_by()`'s own docstring: "delegate
signers ... are account-specific policy and are not reported"), so
`authorize_entry(..., for_address=...)` isn't a fallback, it's the only
documented way to sign a delegates entry with this library.

Reproduced for real, not just read, against `a0e9f8b7` (the commit last
touching `auth.py`): built a two-delegate entry, signed delegate 1 with
`valid_until_ledger_sequence=1000`, signed delegate 2 with `2000`, then
rebuilt the payload the network would actually verify delegate 1's
already-stored signature against, using the entry's current (now
`2000`) shared expiration field, and compared it byte-for-byte against
the payload delegate 1 actually signed (built with `1000`). Confirmed
different. Checked for duplicates first: nothing found searching for
"delegate"/"CAP-71"/"expiration" across open and closed issues and PRs,
and `#1189` (the PR that added this support) has no discussion of this
case in its own review comments. Filed as
[StellarCN/py-stellar-base#1215](https://github.com/StellarCN/py-stellar-base/issues/1215)
with a proposed fix included, not just the finding: raise a clear
`ValueError` in `authorize_entry()` when an already-partially-signed
entry's stored expiration disagrees with the value just passed, instead
of silently overwriting it, favoring an explicit error over silently
substituting the stored value since `valid_until_ledger_sequence` is
always an explicit caller argument in this SDK, never library-computed
the way it is in `js-stellar-sdk`'s higher-level `signAuthEntries()`
wrapper (where the equivalent #1672 fix does silently reuse the stored
value, appropriately, since that value was only ever a library-computed
default in the first place).

No PR opened from this side, unlike the three fixable findings in the
section above: `StellarCN/py-stellar-base`'s own `CONTRIBUTING.md`
explicitly asks contributors to check in before starting work on a
significant change, a different convention than `x402-foundation/x402`'s,
and the issue text carries a full fix sketch so that step is fast once a
maintainer responds. Severity calibrated the same honest way as every
other CAP-71 finding this project has filed: not live on any network
yet, so no impact on a real transaction today, but the bug is real in
code already shipped, in the only path this specific library offers for
delegate signing.

**Fixed upstream 2026-09-08.** Maintainer `overcat` opened
[`#1218`](https://github.com/StellarCN/py-stellar-base/pull/1218)
("fix: guard CAP-71 delegate signing against expiration mismatch",
merged `2026-09-08T02:49:53Z`, `Fixes #1215`): inline the expiration
guard in `authorize_entry()` so a delegate signer is rejected when the
requested expiration does not match the entry, and only write signed
auth entries back after every entry has been signed. Essentially the
proposed fix; `#1215` closed COMPLETED. Same outcome shape as
`#3270`/`#3306` (maintainer's own PR, not this project's), but here the
adopted fix matches what the issue asked for rather than taking a
different shape. This is the Python-SDK parity of the same CAP-71
delegated-signing bug class this project worked in `js-stellar-sdk`:
the discovery-gap generalization
[`#1700`](https://github.com/stellar/js-stellar-sdk/issues/1700), and
for this exact shared-`expiration` mechanism, the reuse defect
Ryang-21's `#1672` review already had fixed in `base/auth.ts` this
session.

Notable for what it says about the underlying skill, not just the
individual bug: the exact same subtle mistake (a shared, single
`signature_expiration_ledger` field that every signer's signature
commits to, with no code-level protection against a later signer
picking a different value) was independently made by two different
teams building two different SDKs in two different languages. Neither
caught it until this session's own accumulated CAP-71 expertise, built
fixing the `js-stellar-sdk` case first under a real maintainer's review,
made the Python SDK's version immediately recognizable rather than
something that had to be rediscovered from scratch.

## Three deliverables shipped ahead of the tranche originally scheduled to fund them

`GET /discovery/resources` (Phase 4, shipped 2026-08-17), hybrid search
(Phase 5, shipped closing that phase), and the `UptoSettlement` Soroban
contract (Phase 6, deployed and later wired into the facilitator's own
HTTP routes) were all completed and evidenced in this repo before the
submission's own funding schedule reached the tranche each one was
originally scoped under, since engineering work here has run ahead of
tranche approval throughout. This is a scheduling fact about this
repo's own build order, not a claim about submission budget or tranche
line items, which is intentionally kept out of this repo per
`docs/SPEC.md`'s own stated boundary; how that gets reflected in the
actual submission is tracked separately, outside this repo.

## An OpenZeppelin fee-abstraction finding was filed with a fix and not accepted upstream, 2026-09-07

A bug-hunt pass over `OpenZeppelin/stellar-contracts` (the crate behind
`contracts/agent-smart-account`) produced
[OpenZeppelin/stellar-contracts#840](https://github.com/OpenZeppelin/stellar-contracts/issues/840),
with a fix at
[`#844`](https://github.com/OpenZeppelin/stellar-contracts/pull/844):
the Lazy-mode `expiration_ledger` check added in `#546`
(`fee_abstraction`) was read as validating the wrong value rather than
the actual allowance. `#844` was CI-green and mergeable from 2026-08-24
(`b68a9ab`).

Maintainer brozorec closed both `#840` and `#844` on 2026-09-07,
reading the check as intentional: it covers the case where allowance is
sufficient but `expiration_ledger` is stale, for the path that does not
rely on `token.approve()`. A counter-example was left on the issue (a
real allowance of 100, not expired, that still reverts with error
`#5006`).

**Resolved 2026-09-08: the finding was wrong, and the thread is
genuinely closed.** brozorec replied to the counter-example the next day
with a complete, technically sound explanation: `expiration_ledger` here
does not validate the allowance state at all. It is the deadline of the
`collect_fee` call itself as one step of the atomic fee-forwarding
operation, the same role a DEX swap's `deadline` parameter plays.
Allowance sufficiency and call-deadline validity are two independent
checks; a non-expired allowance failing with `InvalidExpirationLedger`
because the call's own deadline is in the past is the expected
behavior, not a bug. `#844` correctly rejected. No counter-evidence is
pending; do not reopen this.

**Do not record this as an accepted upstream fix in any doc.** It was a
filed finding with a proposed fix, both correctly rejected by the
maintainer with a sound explanation. Nothing in Periplo's own code path
depends on the outcome: `agent-smart-account` is Phase 6b research with
no live testnet transaction of its own regardless (see the Phase 6b
section above).

Same live check, same day, no doc change needed for either:
`OpenZeppelin/stellar-contracts#865` (Protocol 28 non-exhaustive
`ContractExecutable` match, `README.md` carries the writeup) had no
maintainer response since 2026-09-02; `x402-foundation/x402#3301` (Go)
is covered above. The Periplo repo itself is CI-green with no open PRs
or issues, last commit `2a12856` (2026-09-04).

**Update, 2026-09-26 (checked against the GitHub API and crates.io that
day):** `OpenZeppelin/stellar-contracts#865` was closed as completed by
its maintainer via
[#866](https://github.com/OpenZeppelin/stellar-contracts/pull/866) (merged
2026-09-26), which adds the `ContractExecutable::ExternalRef` arm and moves
the workspace to `soroban-sdk 28.0.0`. That is fixed on `main`, with no
release published: `stellar-accounts` on crates.io is still `0.7.2`.
`soroban-sdk 28.0.0` itself was published as a stable release on
2026-09-18, so earlier statements in this repo that no stable 28.x
existed were true only until then.

**Update, 2026-10-22 (checked against crates.io that day): the wait
condition above is met.** `stellar-accounts` `0.8.0` published on
crates.io 2026-10-20 (`curl -s https://index.crates.io/st/el/stellar-accounts`
lists it, confirmed via the crates.io API's own `created_at` timestamp:
`2026-10-20T17:02:26Z`). Its release notes confirm both changes this
section has been waiting on: the `Signer::Delegated` redefinition to the
`AuthDigestPreimage` struct (`#868`) and a security fix rejecting a
cyclic/self-referential `Delegated` signer
(`GHSA-jpg9-m7w4-c7wc`, patched first in `0.7.3`, same day). This is the
trigger this section's 2026-09-10 decision named: "wait for the official
`0.8.0` release before re-attempting the two-context case." **Update,
2026-10-27: the re-attempt happened and succeeded**, see this file's own
"resolved" entry further up this section
([`d493b6f5…`](https://stellar.expert/explorer/testnet/tx/d493b6f5d16e0ac8002e115470d634bb0ab87f23e167890406a3d8922260961b)).

## Helper library and mainnet-ops roadmap, opened 2026-09-10

Three items worth resolving on their own merits, scoped and budgeted
outside this repo: the seller-side discovery metadata helper and the
buyer/agent SDK helper, both scoped since the first draft of
`docs/SPEC.md` but never built until now, and mainnet sponsor-key
operational planning, scoped the same day. None of the three touches
the `stellar-accounts` `0.7.2` pin or the Phase 6b
`UnvalidatedContext #3002` blocker; all three are independent of it.

**Correction made before scoping, not silently accepted:** the request
described the buyer/agent SDK helper as being for use "outside the MCP
runtime (the MCP server already exists)". Checked against the real
repo, not assumed: `packages/mcp` does not exist and Phase 7 (MCP
discovery server) has not started, confirmed via `ls packages/` and
`docs/SPEC.md` §3's own phase table. The buyer helper below is scoped as
the library form of Phase 7's own discover/pay/retry loop, built ahead
of and independent from Phase 7's MCP wrapper, not as a companion to an
MCP server that doesn't exist yet in this repo.

1. **Seller-side discovery metadata helper: done.** `packages/helpers`
   (spec §3 row 5), scoped since the first draft of `docs/SPEC.md` but
   never built until now. `definePaidResource` turns one declarative
   per-parameter spec into both the discovery JSON Schema and a runtime
   query-param parser, closing a real gap: missing/driftable
   per-parameter descriptions. Reuses
   `declareDiscoveryExtension` from `@x402/extensions/bazaar` rather
   than reimplementing the wire format. 13 unit tests,
   `pnpm run ci` green (307 tests). **Not yet done:** wiring it into
   `demo-resource.ts` (the one real, live resource server this repo
   runs) to prove it against something already deployed rather than
   only in isolation, and a README mention once that's done. This was
   the fastest of the three to close, and was built first; items 2 and
   3 followed the same day, see below.

2. **Buyer/agent SDK helper: done (2026-09-10, same day as item 1),
   including a wrong diagnosis found and corrected the same round rather
   than left standing.** `packages/helpers/src/buyer-client.ts`'s
   `payAndFetch`/`discoverPayAndFetch` wrap discover (search the Bazaar)
   -> pay (`x402Client` from `@x402/core/client`, registered with
   `@x402/stellar/exact/client`'s real signing, via an injectable
   `PaymentPayer`) -> retry, for use outside an MCP runtime, ahead of and
   independent from Phase 7's own MCP-wrapped version of the same loop
   (`packages/mcp`, not started). Uses `@x402/core/http`'s own header
   encode/decode functions rather than reimplementing them. 18 unit
   tests, `pnpm run ci` green (336 tests).

   Run for real against the live deployment three times the same day
   (`apps/facilitator/scripts/buyer-helper-demo.ts`), each run finding
   and fixing a distinct real gap rather than stopping at the first
   success:

   - **Run 1**: `payAndFetch` alone settled
     [`4b45d170...`](https://stellar.expert/explorer/testnet/tx/4b45d17095aaa8c740c3985a040ab5ac0ee455674e8bb3e53bb22707adab41bc).
     `discoverPayAndFetch` failed: the live-cataloged resource carried a
     bare URL with no query string, so paying it as discovered 400'd on
     the handler's own validation. Confirmed fund-safe first, not
     assumed: `@x402/hono@2.22.0`'s own compiled `paymentMiddleware`
     only calls `processSettlement` after the handler returns a sub-400
     status, and Horizon showed no transaction, no balance change for
     the test buyer.
   - **A wrong fix, corrected before it misled anyone further, not left
     standing.** First attempt: bake a default query string into
     `demo-resource.ts`'s own `resource` field (mirroring `/demo/play`'s
     already-fixed `resourceUrl`), on the theory that this field is what
     gets cataloged. Deployed (`fly deploy` after commit `4826458`),
     re-tested, **run 2** settled
     [`c2fbad40...`](https://stellar.expert/explorer/testnet/tx/c2fbad40dd692cf9e0d9eda9781328ad4377fadbb914b9c1dcb6a900bed28cb2)
     for real, `discoverPayAndFetch` still failed the identical way.
     Root-caused properly this time by reading
     `@x402/extensions/bazaar`'s own compiled `extractDiscoveryInfo`
     directly: it builds the cataloged `canonicalUrl` as
     `${url.origin}${url.pathname}` unconditionally, stripping any
     query string by design, regardless of what a seller's own resource
     field contains. The `demo-resource.ts` change is harmless (the raw
     402 challenge itself now shows a fuller example URL) but was never
     going to fix the catalog case. Stated here plainly rather than
     leaving the earlier (wrong) claim standing in this file.
   - **The real fix, in this library, not the resource server.**
     `resolveResourceRequestUrl` reads the discovered resource's own
     declared `extensions.bazaar.info.input.queryParams` (the exact
     example a seller's own `definePaidResource`, item 1, declares,
     closing the loop between this package's two halves) and appends it
     before paying, instead of naively paying the bare canonical URL.
     Also found and fixed the same round, verified by directly
     inspecting a real built payload before trusting it: an earlier
     `PaymentPayer` design called `ExactStellarScheme`'s own
     lower-level `createPaymentPayload(x402Version, requirements)`
     directly and hand-assembled the outgoing payload, which never set
     `payload.resource`, so `discovery.ts`'s own cataloging gate
     (`paymentPayload.resource.url` required) silently skipped
     cataloging for every payment this library made, with no error.
     Fixed by building on the full `x402Client` instead (the same class
     `scripts/demo-resource-settle.ts` already used correctly), whose
     `createPaymentPayload(paymentRequired)` builds the complete
     payload, `resource` and the bazaar extension echo included.
     **Run 3, genuinely clean**: transaction
     [`8573061305...`](https://stellar.expert/explorer/testnet/tx/8573061305f58eb6c0cfdab5af3a15a3f67f070eb24d2f411a0c0b1b34b41402),
     `discoverPayAndFetch` searched, found, resolved the request URL,
     paid, and returned the settled result in one call, no caught
     error, no manual URL override, no fallback path exercised.

   Regression coverage added for both real bugs (the missing
   `payload.resource` and the canonical-vs-requestable URL gap), not
   just the fix: `buyer-client.test.ts`'s "fetches the resource's own
   declared query-param example, not the bare canonical URL" and the
   `.resource`-propagation assertion in the main `payAndFetch` test.

   **One honestly-open question, not resolved and not overclaimed:**
   whether run 3's payment actually refreshed the live catalog row's
   stored content couldn't be confirmed externally. Checked
   `GET /discovery/resources` after each of the three runs; the row's
   `lastUpdated` never moved from `2026-08-19`. Investigated why rather
   than treating that as more evidence of failure:
   `supabase/migrations/20260807202307_resources.sql` declares
   `last_updated timestamptz not null default now()`, a plain column
   default with no update trigger, and `upsertCatalogResource`
   (`packages/bazaar/src/db/catalog.ts`) never includes `last_updated`
   in the row it upserts. A `DEFAULT` only applies on `INSERT`; an
   `ON CONFLICT DO UPDATE` that never names the column leaves its
   existing stored value untouched. So `last_updated` **never bumps on
   a repeat catalog write, successful or not**, a genuine, separate,
   minor tracking gap found investigating this, distinct from the two
   real bugs above and not itself fixed here (cosmetic, doesn't affect
   catalog correctness, out of this round's scope). Its practical effect
   here: neither `lastUpdated` nor the canonicalized `resource` URL
   (identical either way, per the canonicalization finding above) can
   serve as external proof that run 3 actually rewrote the row, since a
   successful idempotent re-catalog of unchanged content is invisible
   through the public API by design. What **is** solidly confirmed: the
   full `discoverPayAndFetch` loop completed for real, no thrown error,
   a genuine settled transaction, which is the actual roadmap
   deliverable; the catalog-freshness side effect of that specific run
   stays an open question rather than a claimed fact.

3. **Mainnet sponsor-key rotation runbook: the testnet-provable half is
   done (2026-09-10), mainnet execution stays blocked on a key that
   doesn't exist.** `docs/OPERATIONS.md` documents the full 90-day/
   suspected-exposure rotation cadence and a seven-step no-downtime
   cutover procedure, built entirely from mechanisms this repo already
   has and has already proven live (the channel-account pool's
   round-robin signer set, `assertNonCustodialSigner`'s boot-time gate,
   `fly secrets set` + `fly deploy`, `GET /supported`'s signer listing),
   not new machinery invented for the runbook. **Real constraint found
   scoping this, not assumed:** no mainnet fee-sponsor key exists yet.
   `periplo-mainnet` (the Fly app) and any mainnet Stellar identity are
   both genuinely absent (confirmed above, and in
   [[periplo-mainnet-key-hygiene]]); mainnet key generation is expected
   at SCF Tranche #3 / Phase 10, so the rotation procedure itself can't
   be executed for real until then, and stays a documented-not-executed
   runbook until it is. The other half, runway monitoring, doesn't need
   to wait: a fee-sponsor account only ever holds native XLM
   (`boot-safety.ts` enforces this at boot), so "how many hours of
   fee-paying can this balance still cover" is the same question on
   testnet as on mainnet. `apps/facilitator/src/sponsor-runway.ts`
   (pure, unit-tested) + `sponsor-runway-fetch.ts` (real Horizon calls)
   compute balance, observed burn rate over a lookback window, and
   projected runway; `scripts/sponsor-runway-alert.ts` is the read-only
   (public-key-only, never the secret) operational entry point, exits
   non-zero below the threshold. Run for real against the live testnet
   fee-sponsor, not just unit-tested against fakes: `9999.2623571 XLM`,
   zero fee spend in the trailing 24h, infinite projected runway, exit
   0. 11 new unit tests cover the alert path itself (a manufactured
   low-balance/high-burn scenario), which the currently-idle live
   testnet account can't exercise without spending real fees just to
   prove it. `pnpm run ci` green (318 tests, up from 307). Deliberately
   does not send a notification itself: no email/Slack/webhook channel
   is configured anywhere in this repo, and wiring one would be
   invented scope this tool doesn't own (spec §12); the script's exit
   code is meant to be read by whatever already runs scheduled checks
   for the deployment, none of which exists yet either, stated as an
   honest, open gap in `docs/OPERATIONS.md` itself rather than implied
   solved.

## `apps/upto-demo`: an UptoSettlement page built ahead of the Phase 9 hub, 2026-09-27

**Divergence:** spec §10 puts every public page in `apps/hub` (Phase 9,
not started). A single page showing `upto` settlement was needed now for
the GOYA HACK 2026 entry, so it lives in its own `apps/upto-demo`
(Vite + React, static) instead, and does not claim Phase 9 has begun.
Nothing in it depends on `apps/hub`; when Phase 9 starts it can be folded
in or linked.

**Target contract:** a separate, isolated `upto-settlement` deployment,
`CA7OYVXWPSQHXNBWJQZ7TCKQILAVBHWDAPNRJTKY66LHR5K5LFXRV6TW` (created at
ledger 4905262), not the `CAK3R734...` deployment cited in
`conformance/RESULTS.md`, so demo traffic never mixes with that evidence.
Its first real settlement, read by the page itself:
[`cf33b513...`](https://stellar.expert/explorer/testnet/tx/cf33b51350f6e4c871b3f0a36e2151ad895dadbe2e237ef413259cf4a0533823),
0.1 PTEST authorized, 0.05 charged, 0.05 refunded.

**Environment differences found building it:**

- `api.stellar.expert` sends `Access-Control-Allow-Origin: *` to requests
  with no `Origin` (what `curl` sends) but answers `403` to any
  third-party origin, so it cannot back a browser page hosted anywhere
  but stellar.expert. Found only by loading the page in a real headless
  Chromium; `curl` said it worked. Switched to Soroban RPC `getEvents`,
  which allows any origin and includes `txHash`. Trade-off: the RPC keeps
  about 7 days of events (120,960 ledgers), which the page states.
- `getEvents` scans a bounded ledger range per call and returns a cursor;
  starting from the RPC's oldest ledger returned zero events and a cursor
  far behind the tip. The page starts from the contract's deploy ledger
  (or the retention floor, whichever is later) and follows cursors.
- The contract's asset is `PTEST` (7 decimals), not USDC; an early draft
  of the page said USDC and was corrected before any commit.

**Still open:**

- The metered backend (real buyer signature, facilitator-side settle of
  measured usage) is built separately and its API is not confirmed, so the
  interactive section of the page is an in-browser simulation, labeled as
  such, that never produces a transaction hash.
- No hosting account is wired to this machine (the `fly` CLI here has no
  login), so publishing the page is left to the repo owner's static host.
- ~~The deployed Wasm hash (`110a3758...`) has not been compared against a
  local build.~~ Resolved in `776accc`: the on-chain WASM was rebuilt from
  `contracts/upto-settlement` at `7d13b59` and matched byte for byte, twice
  (details in `demo/goyahack/README.md`, "Reproducible build").
  `apps/upto-demo/README.md` still carries the old sentence and is left
  untouched while that app backs the GOYA HACK submission.
- Machine note: `pnpm` on this machine's `PATH` is a standalone 9.15.0,
  not the pinned 11.22.0, and `licence-check` shells out to whatever
  `pnpm` is on `PATH`, failing with `ERR_PNPM_MISSING_PACKAGE_INDEX_FILE`.
  Running it through `corepack pnpm` works (140 production packages, 0
  denied). Separately, three integration suites
  (`core.test.ts`, `discovery.integration.test.ts`,
  `resources.integration.test.ts`) fail to load without a `.env`, on
  `main` too: they destructure `env` inside a `describe.skipIf(!env)`
  body, which Vitest 4 still executes.

## `apps/site`: periplo.xyz as a Next.js app, outside Phase 9, 2026-09-27

**Divergence:** spec §10 puts every public page in `apps/hub` (Phase 9, not
started). The project site (landing, legal pages, security page, and the
UptoSettlement demo at `/demo`) lives in its own `apps/site` instead, and
does not claim Phase 9 has begun. `apps/upto-demo` is left untouched: it
is the source of the GOYA HACK submission's deployment, so the site keeps
its own translated copy of the demo logic.

**Environment differences found building it:**

- `periplo-testnet.fly.dev` answers `/supported` and `/status` with no
  `Access-Control-Allow-Origin`, so no browser page on another origin can
  read them. `curl` without an `Origin` header does not show this. The
  site reads them from a server route (`apps/site/src/app/api/facilitator`)
  with a 30 s CDN cache instead of changing the facilitator.
- `next` lists `sharp` as an optional dependency, and sharp's
  `@img/sharp-libvips-*` binaries are LGPL-3.0-or-later, which
  licence-check denies. The site uses no `next/image` optimization
  (`images.unoptimized`), so `sharp` is excluded with pnpm's
  `ignoredOptionalDependencies` (`pnpm-workspace.yaml`) instead of being
  installed and waived. `caniuse-lite` (CC-BY-4.0, build-time only) is
  left as a non-blocking "review" item.
- `pnpm licenses list` fails on this machine for any newly installed
  package (`ERR_PNPM_MISSING_PACKAGE_INDEX_FILE`, now also for `marked`),
  even through `corepack pnpm` and after `pnpm install --force`, so the
  full `licence-check` could not run here. The site's production graph was
  checked instead by walking `pnpm list --prod` and classifying each
  package with licence-check's own `classifyLicense`: 26 allowed, 0
  denied, 1 review (`caniuse-lite`). CI runs the real gate on push.
- `/status` reported `catalogSize: 58` at 18:45 CDMX and `3` about half an
  hour later, with no restart in between. Not caused by the site. 58 is
  exactly the 3 real rows plus the 55 `eval` fixtures, seen again on
  2026-09-27 while a push's CI ran `pnpm eval` against the production
  project; fixed by moving CI to an ephemeral database (see the `eval`
  entry above).

Private vulnerability reporting was enabled on the repository the same
day (`gh api repos/Eras256/Periplo/private-vulnerability-reporting`:
`{"enabled":true}`); `/security` and `security.txt` point to it.

**Still open before a public deploy** (also in `apps/site/README.md`):
the privacy page cannot state
Fly.io's log retention or the Vercel project's analytics settings from
the code; the legal pages have had no legal review.
