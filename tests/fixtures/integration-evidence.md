# Live integration evidence — Phase 2

Record of the enforcement suite running against the real Phase 2 testnet
instance. Reproduce with `npm run test:integration` (requires `.env.phase2`).

## Instance under test

| | |
| --- | --- |
| Guard (custom account) | `CAPADGEK457RHKN4RYVUMDJTFHDSG7R5HREQONKLYK7MFKC5WFENPP44` |
| Token (SAC) | `CDCYDGBGS5AZ5BZS6XY2SK2PHJHSOEGTN3N4INCK34KF6GU2BGC7Z6MB` |
| Network | Test SDF Network ; September 2015 |
| Deployed WASM SHA-256 | `f47919f92e78fdd034836aa61955fc338dd56a218c448c37df1867a8c3da0f63` |
| Same artifact as Phase 1 | yes — verified against the ledger's `ContractExecutable` and the SHA-256 of the fetched bytecode |

This is **not** the Phase 1 instance. Phase 1's guard (`CAYJZT4X…`) is left frozen
by its own dead-man switch as Phase 1's evidence, and is never touched by this
suite. See `phase2-instance.json` for the deployment record.

Live policy the suite runs against and asserts on:

```
per_tx_cap 1000, window_cap 150, window_secs 60,
assets [token], recipients [allowlisted recipient], allow_any_recipient false,
protocols [], paused false, dms_grace_secs 0
```

## What counts as evidence for a block

A guard block happens in enforced pre-simulation, **before broadcast**. It
therefore cannot have a transaction hash — that is the entire point of the
pre-flight path, so demanding a hash for a blocked action would be a demand for
fabricated evidence. The evidence for a block is:

1. the contract's own `event_auth_checked, blocked, <reason>` event, taken from
   the failed enforced simulation's diagnostics — signed by the contract, not
   inferred from a generic failure;
2. the specific `BlockReason` from `src/reasons.ts`;
3. no submission at all (the result carries no hash), and
4. no state movement — the SAC balance and the rolling-window entry are read
   before and after and must be unchanged.

Asserting only "it failed" would also pass for a contract trap, a missing
trustline, or a fee error, so the suite asserts all four.

## Run output

```
[live] guard CAPADGEK457RHKN4RYVUMDJTFHDSG7R5HREQONKLYK7MFKC5WFENPP44
[live] per-tx cap 1000, rolling window 150/60s, 1 allowlisted recipient(s)
[allowed] tx f8f5b3c51b85c8777c956d71330d015fcf72fa57548077d8b32969f8ba9c762e at ledger 4704849
  ✔ allows a transfer inside both caps, with a real on-chain hash (12192.988915ms)
[blocked] per_tx_cap_exceeded (1001 > 1000)
  ✔ blocks a per-transaction-cap violation, pre-broadcast (8519.903622ms)
[rolling] 76 + 76 = 152 > window_cap 150
  ✔ blocks a rolling-window-cap violation that only accumulation can explain (12667.333992ms)
[blocked] recipient_not_allowed (GDZOKF3HGA6XSKIEEPJC5ANON3IJ5OGZMCX7GEGJLZN7JFRKOO4N2HXM)
  ✔ blocks a recipient-allowlist violation (5238.482785ms)
[blocked] paused (account-state refusal)
  ✔ distinguishes an account-state refusal from a policy refusal (9390.520814ms)
✔ live enforcement: SAC transfer (48594.535501ms)
ℹ tests 5
ℹ pass 5
ℹ fail 0
```

## Scenario by scenario

### 1. Allowed transfer

`transfer` of 50 from the guarded account to the allowlisted recipient, authorized
by the agent key through `__check_auth`.

- real transaction `f8f5b3c51b85c8777c956d71330d015fcf72fa57548077d8b32969f8ba9c762e`
- landed in ledger `4704849`, re-read from the RPC and confirmed `SUCCESS`
- the guarded account's SAC balance decreased by exactly 50
- the rolling window recorded exactly 50

### 2. Per-transaction-cap violation

`transfer` of **1001** against a `per_tx_cap` of 1000.

- outcome: `blocked`, reason `per_tx_cap_exceeded`
- no transaction hash exists (nothing was broadcast)
- the contract emitted, in the failed enforced simulation:

```
[Failed Contract Event (not emitted)] contract:CAPADGEK…,
  topics:[event_auth_checked, blocked, per_tx_cap_exceeded], data:{}
```

- balance and window unchanged

### 3. Rolling-window-cap violation

Two `transfer` calls of **76** each, each individually admissible (below both the
1000 per-tx cap and the 150 window cap). Their sum, 152, exceeds the window cap of
150 — so the block can only be explained by genuine accumulation.

- first transfer: allowed; window went from 0 to 76
- second transfer: `blocked`, reason `window_cap_exceeded`
- emitted `topics:[event_auth_checked, blocked, window_cap_exceeded]`
- balance and window remained at the post-first-transfer values

The amounts are derived from the live policy (`window_cap / 2 + 1`) rather than
hardcoded, and the test asserts each is individually admissible — otherwise it
could pass by tripping the per-tx cap instead.

### 4. Recipient-allowlist violation

`transfer` of 10 to an address not in the policy's `recipients` list, with
`allow_any_recipient: false`.

- outcome: `blocked`, reason `recipient_not_allowed`
- emitted `topics:[event_auth_checked, blocked, recipient_not_allowed]`
- balance unchanged

### 5. Account-state refusal is distinguishable

With `paused: true`, a transfer is refused with `paused` — an account-state
reason, not a spend violation. This matters because the two need different
responses: a spend violation is the guardrail working, a pause is the operator
speaking. The test restores the policy afterwards and asserts it was restored.

## A stale-ledger failure this suite found

The first runs of scenario 3 failed intermittently, and not because of policy: a
transfer passed enforcement, was **included**, and was then rejected by core with:

```
error, scecExceededLimit
data: ["operation byte-write resources exceeds amount specified", "724", "652"]
```

Six back-to-back transfers in a closed window produced:

| window entries before | simulation declared `write_bytes` | ledger charged | outcome |
| --- | --- | --- | --- |
| 0 | 652 | 652 | allowed |
| 1 | 652 | 724 | **error** |
| 1 | 724 | 724 | allowed |
| 2 | 724 | 796 | **error** |
| 2 | 796 | 796 | allowed |
| 3 | 796 | 868 | **error** |

Every declared value is exactly one rolling-window entry (72 bytes) short
whenever the simulation observed state from before the previous transfer's commit.
Waiting for the ledger to advance past the previous write fixed 6 of 6 runs,
confirming the cause: the enforced simulation priced the transaction against a
ledger snapshot that predated the write the SDK had just made.

At the time of this recorded run, the SDK fix was a single bounded retry, gated
on this specific failure (`isStaleLedgerResourceFailure`). It is safe because a
transaction rejected for exceeding a resource limit applies nothing, and
inclusion proves the ledger has since advanced. It is deliberately *not* applied
to `Auth` failures — those are the guard refusing, and retrying a block would be
wrong. Re-running the same six transfers returned 6 of 6 allowed with no waits.
The retry-hardening change in this branch preserves that safety boundary while
making the retry budget and backoff explicit.

This is worth stating plainly rather than burying: it is a client-side resource
pricing issue, not a guard defect, and it did not let any transaction through that
policy forbade.

## Addendum — 2026-09-24 (maintenance PR: #33, #29, #46)

This PR touches the enforcement path (`src/tx.ts`, `src/invoke.ts`,
`src/policy.ts`, `src/preflight.ts`), so per `CONTRIBUTING.md` it is recorded
here. **It is not accompanied by a fresh live-testnet run**: the contributor
environment has no funded Phase 2 testnet credentials, so the live suite was
not re-executed. What that means for review, stated plainly:

- **The enforcement *behaviour* on-chain is unchanged by this diff.** The four
  files were touched only as follows: `src/tx.ts` extracts an `AgentSigner`
  interface for digest signing (the single-`Keypair` path is identical);
  `src/invoke.ts`/`src/preflight.ts` widen a config *type* (`AgentSigner |
  Keypair`) and `await` the now-async entry builder; `src/policy.ts` documents
  and guards the `LastHeartbeat = 0` ("never") case in the dead-man helpers.
  The authorization preimage, nonce policy, credential types, policy encoding,
  footprint assembly and block classification are all untouched, so the five
  scenarios above must still hold — but that is an argument, not a measurement.
- **A maintainer with `.env.phase2` should run `npm run test:integration` against
  this branch before merge** and replace this addendum with the fresh run
  output, per the rule the gate exists to enforce. The CI gate only verifies
  that this file was touched; it cannot verify the numbers, and this addendum
  does not pretend otherwise.

## Pre-flight Input Validation Verification

Pre-flight interceptor input validation checks execute prior to RPC simulation dispatch:
- Programmatic validation (`validateContractCall`) synchronously rejects invalid StrKey addresses, invalid symbols, non-array arguments, and non-i128 amounts with typed `InvalidInputError`.
- Valid calls continue through the enforcement pipeline and retain parity with on-chain policy enforcement outcomes.

## Pre-flight cache validation (2026-09-25)

The opt-in cache behavior is covered without network access in
`tests/unit/preflight.test.ts` using a mocked RPC and the real
probe/enforced-simulation path. The tests verify default opt-out, cache hits,
ledger-based configuration, TTL expiry, full and call-specific invalidation,
ledger advance invalidation, policy-revision invalidation, argument-sensitive
keys, and non-caching of transient undetermined results.

Local checks completed successfully:

```text
npm run typecheck
npm run lint
npm test                 # 89 passing unit tests
npm run build
```

A fresh live-testnet run was not claimed for this change: `.env.phase2` is
absent from this checkout, and the available runtime is Node 22 while the
package requires Node 24 for the documented live workflow. The cache tests are
fully mocked and reproducible without credentials; a maintainer can rerun the
live suite with the repository's documented testnet credentials before merge.

## Paired pre-flight fidelity: verdict vs on-chain outcome, delay = 0 (2026-09-26)

`tests/integration/enforcement.test.ts` now carries a paired test: the *same*
transfer is sent through `PreFlightInterceptor.check()` and then, with no delay
in between, through the full `invoke()` pipeline, and the two results are
compared. Both paths call the same `enforceCall()`, so the comparison is two
independent observations of one state — a verdict, and the outcome it predicted.

**Allow case.** Pre-flight reports `admissible`, `invoke()` reports `allowed`,
and the transaction is then re-read from the RPC and asserted `SUCCESS`, with the
guarded account's balance down by exactly the transfer amount and the rolling
window recording it. The evidence is a transaction hash, not a claim.

**Block case.** Pre-flight reports `blocked, per_tx_cap_exceeded` for an
over-cap transfer, and the immediately following `invoke()` attempt reports the
*identical* reason symbol. The reason is additionally decoded from the
`event_auth_checked` diagnostic carried by each refusal, so the paired assertion
is between two decisions the contract itself made.

Why the block case stops at the enforced-simulation refusal rather than forcing a
broadcast: the block happens in enforced simulation, before broadcast, so no
transaction exists to look up — that is the pre-flight guarantee, and demanding a
hash for it would be demanding fabricated evidence (see "What counts as evidence
for a block" above). Broadcasting past that gate would require hand-assembling an
envelope that bypasses this SDK's enforcement, a path the SDK deliberately does
not provide, and it would add nothing the contract has not already stated: the
reason asserted here comes from `__check_auth`'s own diagnostic event. This is
the honest variant the issue permits, and the reason for choosing it.

**Not run live in this checkout.** `.env.phase2` is absent, so
`npm run test:integration` cannot execute here, and no fresh transaction hash is
claimed for this section — unlike the scenario run above, which was recorded from
a real run. What did run locally, on Node 25:

```text
npm run typecheck
npm run lint
npm test                 # 131 passing unit tests
npm run build
npm run test:smoke
```

The paired test compiles and type-checks against the same harness the live
scenarios use. A maintainer with `.env.phase2` can reproduce it with
`npm run test:integration` before merge; it needs no new credentials, no new
deployment, and no policy change beyond the `installPolicy()` call every scenario
already makes.

## Addendum — 2026-09-26 (PR: structured pipeline step timing for observability hooks)

Recorded because this PR touches the enforcement path (`src/invoke.ts`,
`src/preflight.ts`) and CI's `enforcement-path evidence gate` therefore requires
this file in the diff.

**It is not accompanied by a fresh live-testnet run**: `.env.phase2` is absent
from this checkout, so `npm run test:integration` cannot execute here. As with
the addenda above, this is stated rather than glossed, and the CI gate verifies
only that this file was touched — not the numbers.

### What the PR changes on the enforcement path

The diff is observability plumbing only. It adds an optional `onStep` hook to
`invoke()`/`enforceCall()`, an `InvokeStepEvent` shape (name, status, durationMs,
attempt) over the existing `TraceStepName` vocabulary, and a `withStepTiming`
wrapper around the pipeline's existing stages: `probe` (discovery simulation),
`sign` (all entries, one stage per attempt), `simulate` (enforced simulation) and
`broadcast`. The stale-ledger retry threads an `attempt` index (0/1) through
those events. A throwing callback is swallowed; with no hook supplied, each
stage runs directly — no timers, no events, no added work.

Unchanged, deliberately: the authorization preimage and nonce policy, credential
kinds answered, the probe → sign → enforced-simulation ordering, resource
assembly, submission, block classification and every outcome value and detail
string. The one behavioural nuance is internal only: signing-shape refusals are
raised as an internal `SigningStageError` so the `sign` stage emits a real `fail`
event, and `enforceCall` converts it straight back into the same `error` outcome
text the pipeline has always returned. The enforcement *decisions* the five
scenarios above assert on are produced by the contract during enforced
simulation, which this diff does not touch.

### What did run locally (Node 24.21.0, matching the package's engine)

```text
npm run typecheck                        # clean
npm run lint                             # clean
npm test                                 # 171 unit tests passing, 0 fail
npm run build                            # clean
npm run test:smoke                       # 44 exports resolve via the ESM export map
```

The unit suite includes `tests/unit/invoke.test.ts`, which drives the real
pipeline against a mocked RPC and asserts the enforcement outcomes this file's
live scenarios exercise — allowed, blocked (with the contract's reason decoded
from `event_auth_checked` diagnostics), error, and the stale-ledger retry's
two-attempt event stream — plus `PreFlightInterceptor` validation and cache
behavior in `tests/unit/preflight.test.ts`. Those cover the classification and
plumbing this PR touched, but they are mocks: they cannot substitute for the
live run, and this addendum does not claim otherwise.

**A maintainer with `.env.phase2` should run `npm run test:integration` against
this branch before merge** and replace this addendum with the fresh run output.
No credentials, deployment or policy change are needed beyond what the suite
already does.

## Addendum — 2026-09-26 (PR #182: Admin operations, SDK jitter, adapter examples, AgentSigner type fixes)

Recorded because this PR touches the enforcement path (`src/tx.ts`, `src/invoke.ts`)
and CI's `enforcement-path evidence gate` therefore requires this file in the diff.

**It is not accompanied by a fresh live-testnet run**: `.env.phase2` is absent from
this checkout, so `npm run test:integration` cannot execute here. The on-chain
enforcement behaviour is unchanged by this diff.

### Summary of changes to the enforcement path

- `src/tx.ts`: Deduplicated `GuardCredentialType` and unified `AgentSigner` to the clean `readonly publicKey: string` / `signDigest` definition; updated `submitAndPoll` options parameter types for compatibility with `exactOptionalPropertyTypes`.
- `src/invoke.ts`: Imported `AdminSigner`, added `pollAttempts` and `pollIntervalMs` to `InvokeParams` and forwarded them to `submitAndPoll`, and updated `enforceCall` to `await` `publicKey()` across `accountSigners` so asynchronous custom admin signers (e.g., Freighter) match correctly.

### What did run locally

```text
npm run typecheck                        # clean
npm run lint                             # clean
npm test                                 # 191 unit tests passing, 0 fail
npm run build                            # clean
npm run test:smoke                       # 64 exports resolve via the ESM export map
```

**A maintainer with `.env.phase2` should run `npm run test:integration` against this branch before merge** and replace this addendum with the fresh run output.

## Addendum — 2026-09-26 (PR #184: GuardBlockedError decision payload and differential fixture test table #63, #70)

Recorded because this PR touches the enforcement path (`src/preflight.ts`) and CI's `enforcement-path evidence gate` therefore requires this file in the diff.

**It is not accompanied by a fresh live-testnet run**: `.env.phase2` is absent from this checkout, so `npm run test:integration` cannot execute here. The on-chain enforcement behaviour is unchanged by this diff.

### Summary of changes to the enforcement path

- `src/preflight.ts`: Updated `assertAllowed()` in `PreFlightInterceptor` to pass the offending `call` and `rawEvent` (the contract's first diagnostic event) into `GuardBlockedError` when rejecting blocked invocations.
- `src/reasons.ts`: Extended `GuardBlockedErrorOptions` and `GuardBlockedError` to carry `call?: ContractCall` and `rawEvent?: DiagnosticEvent`, along with a structured `toJSON()` serialization method for observability and logging.
- `scripts/sync-contract-fixtures.ts` & `tests/fixtures/contract-fixtures.json`: Added differential fixture tables and synchronization tooling asserting parity between contract diagnostics and SDK preflight reasoning.

### What did run locally (Node 24)

```text
npm run typecheck                        # clean
npm run lint                             # clean
npm test                                 # 215 unit tests passing, 0 fail
npm run build                            # clean
npm run test:smoke                       # 64 exports resolve via the ESM export map
```

**A maintainer with `.env.phase2` should run `npm run test:integration` against this branch before merge** and replace this addendum with the fresh run output if needed.

## Addendum — 2026-09-27 (PR #175: bounded jittered stale-ledger retries)

Recorded because this PR touches the enforcement path (`src/invoke.ts`,
`src/preflight.ts`) and CI's `enforcement-path evidence gate` therefore requires
this file in the diff.

**It is not accompanied by a fresh live-testnet run**: `.env.phase2` is absent from
this checkout, so `npm run test:integration` cannot execute here. The recorded
6-of-6 stale-ledger run earlier in this file remains the live evidence for the
failure mode; what follows is the argument that this diff does not widen it.

### What the PR changes on the enforcement path

- `src/invoke.ts`: the single hard-coded retry becomes a bounded budget
  (`retry.maxAttempts`, default 3) with full-jitter exponential backoff
  (`baseDelayMs` 100, `maxDelayMs` 2000, RNG and sleep injectable). Each attempt
  still re-enters the whole pipeline — fresh account lookup, probe simulation,
  signing, enforced simulation, broadcast — so the resource declaration is always
  priced against current ledger state. Exhaustion returns a typed
  `InvokeRetryError` carrying `attempts`, `lastCause` and `lastOutcome` instead of
  a generic error.
- `src/invoke.ts`: error outcomes now carry a `cause`
  (`undetermined` | `stale_ledger_resource_limit`), so a host/RPC/input failure is
  never confused with a guard refusal.

### Why the safety boundary is unchanged

Retry is still gated *only* on `isStaleLedgerResourceFailure` — a post-inclusion
`scecExceededLimit`. A guard block returns `blocked` immediately and is never
retried, and an undetermined failure (bad input, RPC/host error, unsupported auth
shape) returns immediately without sleeping. The predicate is untouched by this
diff, so the set of failures eligible for a retry is identical to the recorded
6-of-6 run; only the number of eligible attempts and the delay between them
changed.

The one behavioural difference from the recorded run: the default budget is now 3
attempts rather than 2, so a persistently stale ledger can produce two retries
instead of one before the budget is exhausted. Each retry is still a full
re-simulation against a fresh ledger snapshot, and inclusion of a prior attempt
proves the ledger has advanced — the argument the single retry rested on, applied
the same way.

`tests/unit/invoke.test.ts` now asserts the per-attempt `onStep` index across all
three attempts (`a0`, `a1`, `a2`), so the added attempts are observably
individuation, not silent extra work.

### What did run locally (Node 24.16.0)

```text
npm run typecheck                        # clean
npm run lint                             # clean
npm test                                 # 252 unit tests passing, 0 fail
npm run build                            # clean
npm run test:smoke                       # 72 exports resolve via the ESM export map
```

The retry-specific coverage is `tests/unit/invoke.test.ts` with a mocked RPC while
still driving the real transaction builder and signing path:

- three total attempts are bounded, and exhaustion returns `InvokeRetryError` with
  `attempts = 3` and `lastCause = stale_ledger_resource_limit`;
- full jitter produces the injected-RNG delays `25ms` then `150ms` against the
  documented exponential window and cap, and `50ms`/`100ms` at a fixed 0.5 sample;
- every attempt performs both probe and enforced simulations — 6 simulation calls
  and 3 account lookups for 3 attempts, proving a genuinely fresh transaction per
  retry rather than a resubmission of the first resource declaration;
- `maxAttempts: 1` performs one attempt and never sleeps;
- an `invalid_input`/undetermined result returns with no retry sleep and no
  broadcast (`cause: "undetermined"`); and
- a retry that discovers a non-retryable failure does not sleep again.

**A maintainer with `.env.phase2` should run `npm run test:integration` against this branch before merge** and replace this addendum with the fresh run output.

This diff is merged on top of the batched pre-flight addendum below, and the two
share `src/preflight.ts`: the batch path calls `check()` per call and reads only
`kind`, while this change alters `invoke()`'s retry budget, so they do not
interact. The merged tree type-checks and the full suite runs on both together,
which is the state the numbers above describe.

## Addendum — 2026-09-27 (PR #170: batched pre-flight `checkBatch`)

Recorded because this PR touches the enforcement path (`src/preflight.ts`,
`src/policy.ts`) and CI's `enforcement-path evidence gate` therefore requires
this file in the diff.

**It is not accompanied by a fresh live-testnet run**: `.env.phase2` is absent from
this checkout, so `npm run test:integration` cannot execute here. The five
scenarios recorded above remain the live evidence for the single-call path.

### What the PR changes on the enforcement path

- `src/preflight.ts`: adds `checkBatch()`, `assertBatchAllowed()` and the
  `preflightBatch()` one-shot form. `checkBatch` evaluates each call in order
  through the existing `check()`, then *stages* the cumulative window spend of
  SAC transfers in memory. A call that passes enforced simulation in isolation
  but would push the staged total past `window_cap` is returned as `blocked` with
  `window_cap_exceeded`. The batch is admissible only when every call is.
- `src/preflight.ts`: `PreFlightConfig.policy` is a new optional field so a caller
  can supply the policy for staging without an extra ledger read.
- `src/policy.ts`: adds `extractTransferAmount()` (the SAC `transfer` /
  `transfer_from` amount argument), `readPersistentEntry()`, and
  `fetchGuardPolicyAndWindow()` for the "no policy supplied" path.

### What this is, and what it is not

`checkBatch` is an **off-chain approximation** of the contract's atomic auth-batch
evaluation, and the code says so at the call site. The three known divergences,
restated here because they bear on how much weight the evidence can carry:

- state mutations between calls are not observed, because each call is simulated
  independently;
- the window is staged against the initial snapshot, with no modelling of
  intra-batch time expiration;
- `totalEstimatedResourceFee` is the sum of per-call estimates, not the resource
  fee of a single batched envelope.

The synthetic `window_cap_exceeded` verdict is the part that most needs review: it
is produced by this SDK rather than by the contract, so on its own it is an
argument and not a measurement. The single-call path it is layered on top of is
unchanged — `check()`, `assertAllowed()` and `preflight()` are untouched, and a
`blocked` or `undetermined` verdict from the contract is propagated verbatim
rather than re-derived.

### What did run locally (Node 24.16.0)

```text
npm run typecheck                        # clean
npm run lint                             # clean
npm test                                 # 252 unit tests passing, 0 fail
npm run build                            # clean
npm run test:smoke                       # 72 exports resolve via the ESM export map
```

`tests/unit/preflight.test.ts` gains a `PreFlightInterceptor.checkBatch()` suite
against a mocked RPC, covering:

- the empty batch (admissible, no verdicts, zero fee, zero simulations);
- one verdict per call in input order, with per-call fees summed;
- a call that passes alone but breaches the staged cap, asserting the
  `window_cap_exceeded` reason and the `120 > window_cap 100` arithmetic, and that
  a staged-out call is excluded from the fee total;
- the already-committed window spend counting against the cap;
- a contract refusal propagating its own decoded reason (`per_tx_cap_exceeded`)
  and making the batch inadmissible;
- a `null` cap meaning "no objection" rather than "refuse everything";
- a missing `getLedgerEntries` degrading to a zero committed spend instead of
  failing closed; and
- `assertBatchAllowed` returning the batch when admissible, throwing
  `GuardBlockedError` on the first refusal, and throwing
  `PreFlightUndeterminedError` — never a block — on a host rejection.

What these tests do **not** establish: that staged in-memory accumulation matches
the contract's own batch accounting under real concurrency. That needs the live
suite, and it needs the contract-side `check_batch` entrypoint to compare against.

**A maintainer with `.env.phase2` should run `npm run test:integration` against this branch before merge** and replace this addendum with the fresh run output.


