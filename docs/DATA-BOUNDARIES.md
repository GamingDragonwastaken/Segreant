# Segreant data boundaries

Segreant is a local-first AI coding-agent FinOps and evidence-of-value tool. It is
not a hosted telemetry product. By default it does not send product analytics,
the local ledger, prompts, source code, or stored proposals to Segreant or any
Segreant-operated service.

Local-first does not mean that an AI provider request is made offline. This page
states exactly what crosses the machine boundary, when it happens, and what the
operator controls.

## Normal proxy traffic

When a tool is pointed at the Segreant proxy, Segreant forwards that tool's request
to the one upstream configured in `upstreams.anthropic` or `upstreams.openai`.
That request can contain prompts, source snippets, tool payloads, and the
provider credential exactly as required by the provider API. Segreant does not
store credentials and does not forward them to any Segreant service.

The proxy deliberately ignores `x-segreant-openai-base`, including in old configs.
A request-controlled destination would otherwise be able to receive a caller's
provider credential. To use a different provider, change the trusted configured
upstream or run a separate Segreant process with its own configuration.

## What Segreant stores locally

The local SQLite ledger records metering and outcome information: timestamps,
provider/model labels, token counts, calculated cost, project/session labels,
and configured outcome signals. For every newly local-priced row it also keeps
the SHA-256 of the local rate card, card source kind, and whether the model
matched exactly, by family, or by fallback. An explicit `segreant reprice --apply`
adds an append-only before/after event; it does not silently reinterpret an old
amount. Tool-reported amounts, zero-cost audit events, synthetic demo data, and
pre-lineage historical rows are separately labelled. These are local pricing
evidence labels, not provider invoice, discount, credit, tax, or reconciliation
data. The ledger does not intentionally store provider API keys.

"Labels" is too comfortable a word for five of those columns, so they are named
individually. Each holds material a person produced rather than a metering
figure, and each stays on the machine under the Segreant home:

- `requests.cwd` — the full working-directory path a request was made from,
  when the calling tool sends one. Directory names routinely carry client,
  employer, or project names, and the path itself discloses account and
  directory layout. It is stored to attribute spend to a project and to build
  the project/path mapping the GUI shows.
- `requests.user` — the operator label a calling tool reported, unmodified.
- `git_commits.subject` — the first line of each correlated commit message, as
  written. Segreant reads it from the local repository; it never sends it.
- `proposals.files_json` — captured proposed code lines with their file paths,
  which is the case `metadataOnly: true` exists to switch off entirely.
- `scan_snapshots.repos_json` — repository locations discovered by a local
  scan, so the same disclosure applies as for `requests.cwd`.

Everything above is local. Only the declared egress paths below leave the
Segreant process, and none of them carries these columns.

The 0.2.0 readers add local reads only; none of them opens an outbound connection. `import` and `scan` read
the session logs that Claude Code, Codex, opencode and Antigravity write on this
machine. They keep token counts, model names, working directories (stored as
`requests.cwd`) and the vendors' own rate-limit readings (`quota_events`; the
`detail` column holds at most 120 characters of the vendor's limit message). `plan`
reads only the `oauthAccount` plan fields of `~/.claude.json` and the `plan_type` of
the newest Codex session log. It never opens Claude Code's credentials file. A plan
price exists only when the operator sets it. `segreant-statusline` reads the JSON
that Claude Code passes on standard input and makes no network request.

When an operator explicitly runs `segreant billing import --file ... --apply`,
Segreant also stores an immutable, provider-declared billing-evidence ledger. V1
accepts only a strict local OpenAI evidence JSON contract. It retains the file
basename, SHA-256 digest, size, import/source-period metadata, non-secret local
billing-account reference, coverage declaration, and allowlisted normalized
charge fields. It does **not** retain the raw file by default and does not read
provider credentials, browser sessions, or billing pages. These records remain
separate from proxy/local-tool requests: they do not affect caps, RoI, request
estimates, or `today` totals, and their status is `not_reconciled`. See
[BILLING-EVIDENCE-IMPORT.md](BILLING-EVIDENCE-IMPORT.md) for the exact local
schema and retention implications.

`segreant billing scope set ... --apply` separately records only an operator's
non-secret local statement that future OpenAI-proxy traffic is routed to the
exact configured endpoint for a named account/project reference. Segreant stores
the sanitized endpoint display and fingerprint, never an endpoint credential,
provider session, or API key. The status is always
`operator_declared_unverified`; it is not provider-account verification,
reconciliation, or an instruction to change routing.

When an operator runs `segreant billing openai-costs pull ... --apply`, Segreant
may make exactly one additional outbound type: a read-only `GET` to the fixed
OpenAI Organization Costs endpoint at `https://api.openai.com/v1/organization/costs`.
The command first requires a local scope for exactly that endpoint plus a
`proj_...` project reference, and requires a UTC day range of no more than 180
days. Preview and a pull without `--apply` do not read a credential or contact
OpenAI. On an applied pull only, `OPENAI_ADMIN_API_KEY` is read from the current
process environment; it is never persisted, printed, included in an error, or
sent to any destination other than the fixed OpenAI request. Segreant retains only
allowlisted normalized daily observations plus a digest chain/run status; it
does not retain raw response bodies. Direct provider observations are a separate
unreconciled collection, not request spend, and do not affect caps, RoI, or
recommendations. Failed/partial pulls retain failure metadata with no usable
provider observations.

All Segreant-process HTTP(S) transport is now governed by the egress boundary.
The default `egress.mode: "local_locked"` permits literal loopback targets only
and refuses non-loopback targets before DNS. A cloud operation needs
`controlled_cloud` mode plus one enabled exact rule for its purpose, data class,
method, HTTPS origin, and leading path. Before an allowed request is dialled,
Segreant persists redacted local receipts for policy preflight and dial start; it
adds a response or failure receipt afterwards. The receipt chain contains
hashes, rule identifiers, event metadata, byte counts, and status only—not
request bodies, query strings, API keys, headers, raw origins, or response
bodies. A missing receipt file is the only genesis case. If the path is present
but empty, malformed, truncated, hash-invalid, unreadable, or cannot be safely
locked/extended, Segreant refuses before DNS/socket creation; it never treats that
state as a fresh chain. `segreant egress status` and `segreant egress verify` expose
the configured scope, exact failure reason, and local chain health so the
operator can repair or restore the retained history before retrying. A bounded
stale-lock refusal requires confirming that no Segreant writer is active before
the operator removes only that lock; abandoned locks are never auto-deleted.
Receipt writes are synchronous, but Segreant does not claim `fsync` or power-loss
durability for this local ledger.

The append path keeps a redacted, hash-checked checkpoint in
`egress-receipts.checkpoint.json` containing only the last verified file
identity, count, and chain hash. The persisted sidecar is informational and is
never trusted to authorize a new process: each process performs one complete
chain validation before it earns an in-memory append state, then reuses that
state only while the file identity remains stable. A changed identity or an
invalid chain fails closed, and `segreant egress verify` always scans the complete
history. Verification streams the history in bounded chunks rather than
materializing every parsed receipt; an individual line above the supported
1 MiB limit is refused, and retained error diagnostics are capped with an
omitted-error count. The history itself is retained until an operator explicitly
preserves/archives it—Segreant does not silently delete audit receipts. Checkpoint
or state persistence failure fails closed. Status-only egress callers cancel
the returned response body so repeated health, webhook, and team operations do
not retain unused response streams. As with the rest of this local boundary,
an administrator who can rewrite both the receipt file and the running process
is outside the guarantee.

When the proxy receives an upstream redirect, it preserves the status/body for
diagnosis but strips `Location` before returning the response. A downstream
client therefore cannot silently follow a provider redirect to a destination
outside the configured Segreant-process egress policy.

## Declared egress paths

A rule authorizes an exact purpose and data class, so these two tokens are the
whole authorization vocabulary an operator writes into `egress.rules` and reads
back from `segreant egress status`. This table is the complete list: the code
refuses any purpose or data class not named here, and a test pins the table
against the constants in both directions, so a new outbound path cannot be
added without appearing on this page.

| Purpose | Data class | What may cross | Reached by |
| --- | --- | --- | --- |
| `provider_inference` | `provider_request` | prompts, source snippets, tool payloads, and the caller's provider credential, exactly as the provider API requires | any tool pointed at the Segreant proxy |
| `pricing_refresh` | `pricing_manifest` | nothing about you — a plain GET for a public pricing manifest | `segreant pricing --refresh`, or `pricing.autoRefresh` |
| `market_refresh` | `market_manifest` | nothing about you — plain GETs for the public leaderboard and price files listed in `docs/MARKET-SOURCES.md` | `segreant market --refresh <source|all>` |
| `baseline_refresh` | `baseline_manifest` | nothing about you — a plain GET for the manifest at an operator-supplied URL | `segreant baseline --refresh --url ...` |
| `alert_delivery` | `alert_metadata` | configured alert summaries; never prompts, source, or credentials | `segreant alerts --set-webhook ...` |
| `provider_cost_observation` | `provider_cost_aggregate` | a read-only day-range query, plus `OPENAI_ADMIN_API_KEY` read from the process environment for that one request | `segreant billing openai-costs pull ... --apply` |
| `team_rollup` | `team_rollup` | a signed numeric rollup to an operator-run team server | `segreant team push --url ...` |
| `hosted_judge` | `judge_structural_summary`, `judge_transcript_excerpt` | the bounded session excerpt the selected judge tier describes, to the configured judge provider | an explicitly configured hosted judge |
| `local_judge` | `judge_structural_summary`, `judge_transcript_excerpt` | the same payload shapes, to a literal loopback target that does not leave the machine | the local judge tier |
| `local_healthcheck` | `healthcheck` | nothing beyond the request itself, to literal IPv4 loopback | the proxy status checks in the CLI and dashboard |

Two of these purposes are loopback-only in normal operation. `local_judge` and
`local_healthcheck` still travel the same policy, DNS-pinning, and receipt path
as the rest; naming them here is not a claim that they contact a network
service.

With the default `metadataOnly: false`, Segreant may also retain parsed proposed
code lines locally to measure whether an AI proposal later appeared in a Git
commit. This is a local-only convenience signal, not a claim that source never
touches the disk. Set `metadataOnly: true` to disable proposal capture and
First-Pass Acceptance measurement.

Proposal rows are pruned when `segreant start` begins if they exceed
`proposalRetentionDays` (30 days by default). They can be deleted immediately
with the Settings action or `segreant prune --apply` (plain `segreant prune` only previews). If Segreant is not running, no
background process is active to delete data; run one of those controls when an
immediate deletion deadline matters.

The request ledger itself has its own, separate period: `retentionDays` (180
days by default), configurable in Settings or the config file. Unlike
proposals, request rows are **not** pruned automatically when `segreant start`
begins — only an explicit `segreant prune` deletes request rows older than
`retentionDays`. A window that reaches behind whatever boundary is actually on
record is disclosed on the figures themselves (`retention` in `/api/overview`
and the CLI's own windowed reports) rather than silently narrowed; see
`Store.windowCoverage` and `Store.retentionFloor` in `src/store/db.ts`. To get
your own data out before pruning it, `segreant pack export --out <file>` writes
the local epistemic ledger's records to disk (described above); there is no
separate hosted subject-access request path because there is no hosted copy of
this data to request in the first place.

## Optional outbound paths

These paths are off unless an operator deliberately invokes or configures them:

- `segreant pricing --refresh`, or `pricing.autoRefresh` with a configured manifest,
  downloads a public pricing manifest from the selected HTTPS URL. The request is
  a plain GET with no usage, prompt, or customer data; the accepted normalized
  card and redacted source provenance remain local under the Segreant home. It
  additionally needs an exact `pricing_refresh` egress rule in controlled-cloud
  mode.
- `segreant baseline --refresh --url ...` downloads a baseline manifest from the
  URL supplied by the operator and needs an exact `baseline_refresh` rule.
- `segreant alerts --set-webhook ...` sends configured alert summaries to the
  operator's webhook. It is not for prompts, source, or credentials, and needs
  an exact `alert_delivery` rule.
- A hosted judge is an explicit configuration choice. It can send the bounded
  session excerpt described by the selected judge tier to that configured judge
  provider and needs an exact `hosted_judge` rule. The local judge tier remains
  on-device through a literal loopback target.
- `segreant team push --url ...` sends a signed, numeric rollup to an operator-run
  team server. It is opt-in and separate from the local product. It needs an
  exact `team_rollup` rule for a cloud endpoint; literal loopback development
  targets are permitted without a cloud rule. Segreant refuses a non-loopback
  `http://` endpoint for this command; use HTTPS in deployment, or
  `http://localhost`, `http://127.0.0.1`, or `http://[::1]` only for local
  development.

The signed GitHub Actions outcome importer is offline: it reads an artifact from
disk, verifies it against a locally pinned public key and explicit policy flags,
then retains the verified envelope in the local ledger. It does not call GitHub.

`segreant pack export --out <file>` writes the epistemic ledger's records as a
`.segreantpack` file on local disk and sends nothing anywhere; what you then do
with the file is an egress you choose. The manifest binds every record by
digest and states what was left out. Evidence classed `confidential` or
`restricted` travels with its `payload` removed and a redaction entry naming
it; `internal` and `public` evidence travels whole, so read
`segreant pack inspect` before sharing a pack. A pack proves integrity and,
with an out-of-band key, authenticity — never whether its claims are true.

## What this page does not promise

Segreant cannot change an upstream provider's retention, training, privacy, or
security terms. Review the provider and any optional endpoint you choose before
routing sensitive material. Segreant's privacy promise is about its own local
operation and the explicit controls above, not a guarantee about every service
you configure around it.

The egress boundary is also not a machine-wide firewall: it cannot stop a
client from bypassing Segreant, another process, the operating-system resolver,
VPN/firewall policy, a machine administrator, or a provider after Segreant has
deliberately forwarded a permitted request. Those guarantees need independently
managed operating-system, network, identity, and provider controls.
