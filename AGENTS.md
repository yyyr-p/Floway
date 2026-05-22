# AGENTS.md

## Hard Rules

- Do not open a Pull Request without explicit human approval. The human must
  understand the goal and risk, read the AI-generated code and PR text, and
  believe code, docs, and tests are internally consistent.
- Do not create commits unless the human explicitly asks for a commit.
- Before claiming work is complete, run the relevant verification command and
  read the result.
- Keep this file aligned with real architecture. Rewrite it when needed; do not
  accrete contradictory notes.

## Project

`copilot-gateway` is a Cloudflare Workers API proxy. It exposes Anthropic
Messages, OpenAI Responses, OpenAI Chat Completions, Embeddings, and Google
Gemini-compatible APIs over unified upstream records. Supported provider kinds
are `copilot`, `custom`, and `azure`.

`custom` means an OpenAI-compatible bearer-token upstream. It is not an OpenAI
official-account concept. Azure OpenAI / Foundry OpenAI v1 deployments and Azure
Foundry Anthropic deployments use the `azure` provider. GitHub Copilot accounts
are persisted as `copilot` upstreams.

Stack: Hono + Web APIs, repository-backed persistence, D1 on Cloudflare Workers,
in-memory repositories for tests, TypeScript, pnpm, and Vitest.

The production runtime contract is Workers-compatible: a fetch entrypoint,
Workers bindings, Web APIs, and a D1-compatible SQL binding. Keep the narrow
`src/runtime/` compatibility layer for future runtimes that can provide the same
semantics. Do not add a separate Node.js HTTP server or Node+SQLite production
binding unless that becomes an explicit product goal.

## Boundaries

- `entry-cloudflare.ts`: Workers entrypoint and environment wiring.
- `src/app.ts`: Hono app wiring, middleware, and plane mounting.
- `src/control-plane/`: dashboard, auth, admin APIs, import/export, usage and
  performance views.
- `src/control-plane/upstreams/`: unified upstream CRUD, custom/Azure probing,
  Copilot device-flow auth, and Copilot per-upstream quota.
- `src/data-plane/`: client-facing compatibility APIs, model/provider routing,
  protocol translation, embeddings, and data-plane tools.
- `src/data-plane/providers/`: provider interface, provider registry, model
  merge, provider-owned alias resolution, optional fix catalog, and concrete
  provider implementations.
- `src/data-plane/providers/copilot/`: Copilot provider projection, raw model
  variant selection, endpoint capability projection, and Copilot-specific
  provider registrations.
- `src/data-plane/providers/custom/`: generic OpenAI-compatible provider
  behavior for configured bearer-token upstreams.
- `src/data-plane/providers/azure/`: Azure OpenAI / Foundry OpenAI v1 and
  Azure Foundry Anthropic provider behavior, deployment catalog projection, and
  API-key request construction.
- `src/repo/`: persistence interfaces and implementations.
- `src/runtime/`: runtime integration helpers for environment access and
  background scheduling.
- `src/shared/`: project-wide helpers that are not owned by one plane.
- `src/shared/upstream/`: low-level HTTP adapters. These know how to call an
  upstream, but they do not own LLM planning or provider selection.

Keep behavior in the subtree that owns the boundary where it is true. Avoid flat
shared utility modules unless the rule is genuinely cross-boundary.

## Unified Upstreams

The `upstreams` table is the only runtime upstream store. Migration 0010
replaces the old `github_accounts` and `upstream_configs` tables, rewrites
legacy telemetry identities into upstream row ids, drops the old tables, and
clears stale model cache entries. Do not add runtime compatibility for the old
tables or prefixed identities.

`UpstreamRecord` is the persistence contract:

```text
id: string
provider: "copilot" | "custom" | "azure"
name: string
enabled: boolean
sortOrder: number
createdAt: string
updatedAt: string
config: unknown
enabledFixes: string[]
```

The row id is the runtime upstream identity. Do not prefix it with provider type
in usage, performance telemetry, model cache keys, or provider bindings.
Provider selection and display should use the separate `provider` field.

Provider-owned `config` JSON is intentionally opaque to the repo layer. The
control plane validates configs before save, and provider factories assert them
again before use. Malformed enabled upstream config is a real configuration
error and should surface rather than being silently skipped.

Provider config rules:

- `custom`: `baseUrl`, `bearerToken`, `supportedEndpoints`, and optional
  `pathOverrides`. Models come from the configured models endpoint. The provider
  calls upstream models by their raw model id.
- `azure`: one `endpoint`, `apiKey`, and deployment rows. `endpoint` must be an
  HTTPS Azure URL on `*.openai.azure.com` or `*.services.ai.azure.com`; it may
  be an Azure resource root, a Foundry project endpoint, an OpenAI v1 URL ending
  in `/openai/v1`, or an Anthropic URL ending in `/anthropic` or
  `/anthropic/v1`; the Foundry Claude target URI ending in
  `/anthropic/v1/messages` is also accepted and normalized to the Anthropic
  base. Runtime derives protocol bases from that one field.
  OpenAI-shaped calls use `api-key` auth and append `/chat/completions`,
  `/responses`, `/embeddings`, and `/models` to the derived OpenAI v1 base.
  Foundry project endpoints derive OpenAI calls under
  `/api/projects/<project>/openai/v1`. Native Messages calls use the
  resource-level `/anthropic` base and call `/v1/messages` plus
  `/v1/messages/count_tokens` with `x-api-key` auth and
  `anthropic-version: 2023-06-01`. The Azure OpenAI / Foundry OpenAI v1 surface
  is cross-provider for Foundry models such as DeepSeek, Grok, Kimi,
  Microsoft/OpenAI, and similar deployments, but it is not the Anthropic/Claude
  Messages endpoint shape. Gateway Messages requests can still route through
  Azure Chat Completions or Responses via the normal planner. Each deployment's
  `modelKey` is the deployment name; the public model id is `publicModelId` when
  non-empty and otherwise defaults to the deployment name. The dashboard edits
  Azure deployments as one row per deployment with a compact API type preset;
  code persists the provider-owned `supportedEndpoints` capability set. Azure
  deployment rows may also carry provider-owned catalog metadata such as
  `display_name`, limits, and `model_picker_enabled`; keep that metadata out of
  the main dashboard form unless a concrete UI workflow needs it. The configured
  endpoint plus API key is not enough to fetch rich Azure deployment metadata;
  Azure management-plane metadata requires ARM/AAD credentials and subscription
  resource context. Do not add a Chat+Messages Azure preset unless Azure
  documents a native deployment surface that supports both shapes; Chat source
  calls to Messages-only Claude deployments should use the existing planner
  translation.
- `copilot`: `githubToken`, `accountType`, and `user`. Copilot auth and quota
  are upstream-owned control-plane flows, not separate account resources.

`enabledFixes` is a common upstream field for admin-opt-in behavior. Custom and
Azure upstreams use it directly. Copilot providers union stored `enabledFixes`
with provider-owned default fixes and structural workarounds; the dashboard does
not expose Copilot default fixes as admin-editable toggles.

Control-plane `/api/models` is UI-owned. It may expose `provider` and
`upstream_ids` so the dashboard can group model pickers and count models per
upstream row. Public data-plane model APIs must continue to hide provider
bindings and upstream ids.

## Providers

The data plane treats every enabled upstream row as a `ModelProviderInstance`.
The LLM pipeline must not branch on provider kind. Provider methods receive the
exact `UpstreamModel` object previously returned by that provider.

Provider API shape:

```text
getProvidedModels() -> UpstreamModel[]
getPricingForModelKey(modelKey) -> ModelPricing | null
callChatCompletions(upstreamModel, bodyWithoutModel, signal?)
callResponses(upstreamModel, bodyWithoutModel, signal?)
callMessages(upstreamModel, bodyWithoutModel, signal?, anthropicBeta?)
callMessagesCountTokens(upstreamModel, bodyWithoutModel, signal?, anthropicBeta?)
callEmbeddings(upstreamModel, bodyWithoutModel, signal?)
```

`UpstreamModel.supportedEndpoints` is the source of truth for routing. The
registry separates public catalog data from execution bindings:

- `CatalogModel` is the public model-listing DTO. It must not expose provider
  bindings, raw upstream variants, or UI-only provider metadata.
- `ResolvedModel` extends the catalog shape with ordered `ProviderModelRecord`
  bindings for execution.
- `ProviderModelRecord` keeps the provider instance, upstream row id, exact
  `UpstreamModel`, enabled fixes, and provider-registered source/target
  interceptors.

Request execution tries provider bindings in order only until the first binding
that can serve the requested source shape. That provider's result is final for
the request. The only fallback is provider fallback across bindings for the same
public model id. Copilot account fallback is removed. If no binding can produce
a plan, return a source-shaped unsupported-model error instead of inventing
legacy model-name routing. Source and capability handlers should loop over
provider bindings directly; do not hide provider eligibility behind
callback-based wrappers or "try-next-provider" pseudo-results.

Provider-specific behavior is registered by the provider and then executed at
the owning source or target boundary. Copilot behavior includes raw model
variant selection, Claude public-name normalization, request-alias resolution,
endpoint projection, `anthropic-beta` filtering, and Copilot upstream request
fixes. Generic source/target pipelines execute registered interceptor lists but
do not choose behavior based on provider kind.

Messages web-search behavior is decided by the post-plan Messages protocol
interceptor. Messages via Responses or Chat Completions always uses the gateway
shim when native web-search tools are present, because those targets cannot run
Anthropic server tools. Native Messages targets receive native web-search tools
directly by default; Copilot providers enable the shim directly, while custom
and Azure providers enable it only through the `messages-web-search-shim`
upstream fix flag. Do not rewrite the shim as part of unrelated data-plane flow
work.

Backoff is intentionally disabled for now. Control-plane status returns empty
temporary-unavailability data until a provider-level backoff design lands.

### Pricing

`ModelMetadata.cost?: ModelPricing` carries optional per-model pricing in
`{ input, output, cache_read?, cache_write? }` shape. Values are USD per
million tokens. Field names and semantics follow the
[sst/models.dev `Cost` schema](https://github.com/sst/models.dev/blob/main/packages/core/src/schema.ts);
future fields (`reasoning`, `input_audio`, `output_audio`, tiered context)
should reuse that schema's names.

Each provider attaches pricing per upstream model and resolves
`getPricingForModelKey(modelKey)` over its own internal model id space:

- `copilot`: hardcoded table at
  `src/data-plane/providers/copilot/pricing.ts`, keyed by the public model
  name that survives Claude variant merging. `getPricingForModelKey` strips
  Copilot raw-id variant suffixes (`-high`, `-xhigh`, `-1m`,
  `-1m-internal`, trailing date) before lookup, mirroring migration 0009.
- `azure`: per-deployment `cost` field on `AzureDeploymentConfig`,
  validated as `input` + `output` paired and `cache_read` / `cache_write`
  independently optional. `getPricingForModelKey` resolves by deployment
  name.
- `custom`: never priced. `getPricingForModelKey` always returns null;
  `cost` is never attached to `UpstreamModel`.

Public `/models` shapes (`/v1/models`, `/models`, `/v1beta/models`) and
control-plane `/api/models` expose `cost` directly when present. Cost
aggregation in `src/control-plane/token-usage/aggregate.ts` resolves
pricing by `(upstream, modelKey)` through the provider registry; NULL
upstream or unresolved modelKey contributes 0 to cost, matching the
pre-refactor "no rule matched" behaviour.

## Data Plane

`src/data-plane/llm/` owns LLM source routing for Messages, Responses, Chat
Completions, Gemini generation, and source-owned token counting endpoints.
Models, embeddings, and data-plane tools live outside that LLM routing graph in
their capability directories.

Model listing belongs in `src/data-plane/models/`: `/v1/models` is
OpenAI-shaped, `/models` is Anthropic-shaped, and `/v1beta/models` is
Gemini-shaped. Public data-plane model APIs consume `CatalogModel`; execution
paths use `ResolvedModel` and `ProviderModelRecord`.

The LLM execution flow is:

```text
serve -> source request cleanup -> resolve model -> provider binding loop
  -> plan from that provider's UpstreamModel
  -> provider-registered source interceptors -> build target request
  -> target interceptors -> emit through provider method
  -> translate target events to source events -> source respond
```

Use those terms. Planning is the only layer that chooses a target. Successful
execution after `emit` is event-first and should flow through protocol events
whenever practical.

Interceptors are protocol-exchange scoped, not source/target-contract scoped.
`MessagesInterceptor`, `ResponsesInterceptor`, `ChatCompletionsInterceptor`,
and `GeminiInterceptor` each have one concrete `(invocation, request, run)`
shape, whether they appear on the client/source side or the upstream/target
side. Provider source and target registrations are separate execution slots,
but they share the same protocol type for the same protocol.

Per-HTTP-request invariants live on `RequestContext`: `apiKeyId`,
`runtimeLocation`, `scheduleBackground`, `recordUsage`,
`recordRequestPerformance`, `downstreamAbortSignal`, `clientStream`,
`requestStartedAt`. Per-provider-binding-attempt request-side state lives on
`Invocation<TPayload>`: `sourceApi`, `targetApi`, the resolved model id,
provider/upstream/upstreamModel/enabledFixes, `targetInterceptors`, and the
mutable source-shape `payload`. `MessagesInvocation` additionally carries
`anthropicBeta`. Mutable per-request state (last performance row, downstream
abort controller) is intentionally not on either context; it lives as
serve-local `let` variables and is passed explicitly to the source
responder. Raw upstream frames stay inside target emitters and
raw-to-protocol converters; protocol interceptors see protocol request
payloads and `ExecuteResult<ProtocolFrame<Event>>` envelopes only.

Source response flow is source-owned. Each concrete source responder owns its
own upstream/internal error shaping, non-stream collection, stream terminal
observation, downstream SSE serialization, usage extraction, usage recording,
and request performance recording in forward order. Shared source helpers in
`src/data-plane/llm/sources/respond.ts` may hold only low-level stream state,
final metadata, usage recording, and request performance helpers; they must not
accept source-specific callback tables or call back into source behavior.
Protocol `events/to-sse.ts` serializers must stay pure: they convert source
protocol frames to SSE frames and must not record usage, mutate external state,
or accept callback listeners for accounting.

Target emission is target-owned. Each concrete target emit file owns its forward
order: force target-required streaming, run target interceptors, call the
provider method, build model accounting, normalize the upstream response into
raw frames, translate raw frames into target protocol events, and preserve
target-shaped failures. Shared target helpers in
`src/data-plane/llm/targets/emit.ts` may hold only low-level provider body,
accounting, upstream response, telemetry, and internal-error helpers; they must
not accept target-specific callback tables or call back into target behavior.

Request translation is direct and pairwise. Do not introduce a canonical
internal request IR. Each cross-protocol pair lives under
`src/data-plane/llm/translate/<source>-via-<target>/` and exposes a single
`translateXxxViaYyy: TranslateTrip<...>` from `translate.ts`. A trip function
builds the target-shape payload and returns the events translator as a closure,
so trip-scoped state (synthetic ids, custom-tool name sets, etc.) lives as
locals shared between the two halves of the trip — the source serve never sees
them. Substantive request/event helpers stay in sibling `request.ts` and
`events.ts` files so existing unit tests target them directly; small pairs may
inline. Source serves dispatch via
`viaTranslation(translateXxxViaYyy, targetEmit)` inside their
`Record<LlmTargetApi, SourceEmit<...>>` map — the map key is the only source of
truth for which target was picked. Cross-pair helpers (envelope shapers shared
between Gemini pairs, etc.) live in `translate/shared/`.

Workarounds belong at the owning boundary:

- source request cleanup, provider-registered source interceptors, whole-flow
  retry, final response shaping, usage observation, and request performance
  recording stay under `src/data-plane/llm/sources/<source>/` or the shared
  source responder.
- target upstream request fixes, upstream retries, target event fixes, provider
  call normalization, and target telemetry stay under
  `src/data-plane/llm/targets/<target>/` or shared target helpers.
- provider-specific interceptor registrations live on provider records;
  concrete interceptor implementations live at the source or target boundary
  they patch.
- shared translation primitives belong in `src/data-plane/llm/translate/shared/`
  only when multiple pair directions need the same protocol rule.

## Routing

Target preferences:

- Messages: native Messages, then Responses, then Chat Completions.
- Responses: native Responses, then Messages, then Chat Completions.
- Chat Completions: native Chat Completions, then Messages, then Responses.
- Gemini generation has no native upstream target in the provider API; it uses
  Chat Completions, then Messages, then Responses.

Claude compatibility aliases and Copilot raw variant selection live in the
provider layer. Until there is a general model-alias feature, Responses rewrites
`codex-auto-review` to `gpt-5.4` with reasoning effort `low` at the Responses
source entry, before model resolution and usage/performance metadata.
Historical accounting rows are converted to the public model id only in
migrations.

## Control Plane Contracts

Public data-plane compatibility APIs are stable external contracts.
Control-plane APIs and data-plane tool management APIs are UI-owned and must
stay consistent with frontend code, tests, and auth policy.

Authentication has two roles: `admin` via `ADMIN_KEY`, and API key user via a
stored API key. Mutating key APIs and upstream management are admin-only;
`GET /api/token-usage` is intentionally visible to any authenticated user.

Upstream control-plane routes:

- `GET/POST /api/upstreams` and `PATCH/DELETE /api/upstreams/:id` manage all
  provider kinds.
- `POST /api/upstreams/:id/test` probes saved upstream connectivity. Custom and
  Copilot tests use model listing; Azure tests probe declared deployment
  endpoints.
- `POST /api/upstreams/copilot/auth/start` and
  `POST /api/upstreams/copilot/auth/poll` own Copilot device-flow connection.
- `GET /api/upstreams/:id/copilot/quota` reads quota for one Copilot upstream.
  Quota is shown only inside the Copilot upstream edit UI.

Do not reintroduce separate GitHub-account management routes or a top-level
Copilot quota route. Control-plane model DTOs expose `provider` as
`copilot | custom | azure`; do not emit legacy provider-kind fields.

Import/export is latest-only. Export payloads use `version: 2` and
`data.upstreams`. Import must reject missing or mismatched versions before any
mutation. It must not accept old split account/config payloads in runtime code.

## Errors and Style

- Preserve upstream status, headers, and body as directly as possible.
- Internal failures must expose useful debug information, including stack
  traces.
- Use explicit result unions for expected control flow.
- Keep fallback semantics strict; do not add synthetic defaults for convenience.
- Avoid `catch` for normal control flow. Use it at real boundaries: fetch,
  parsing, probing, top-level request guards, and explicit workaround retries.
- Prefer functional TypeScript, arrow functions, single quotes, and semicolons.
- ESLint is the source of truth for import order and code style. Use
  `pnpm run lint:fix` for mechanical cleanup, and keep the existing compact
  handwritten wrapping style instead of reintroducing Deno fmt-style hard
  column wrapping.
- Do not extract tiny one-off helpers unless they encode a real domain rule, are
  reused, materially simplify a flow, or need isolated tests.
- Comment only non-obvious decisions, upstream quirks, protocol mismatches, or
  references. Workaround comments should explain why the behavior exists and why
  it lives at that boundary. Use permalink URLs for external code.

## Verification

Primary commands:

```bash
pnpm run test
pnpm run lint
pnpm run typecheck
pnpm run dev
pnpm run deploy
pnpm run db:migrate
```

Wrangler commands should go through the local dependency with `pnpm wrangler` or
package scripts. When deploying, use `pnpm run deploy` or `pnpm wrangler deploy`
directly; do not pass `--dry-run`.

For manual data-plane validation, prefer `ADMIN_KEY` with the existing
`x-models-playground: 1` header on approved playground routes. Do not reuse or
create normal API keys for manual testing.

For Copilot-specific quirks, compare nearby Copilot gateway implementations
before inventing a new policy. For generic adapter behavior, compare at least
one Copilot gateway and one general LLM gateway. Do not cargo-cult behavior from
a single project.

## Deployment

A production deploy can disconnect the agent that triggers it, especially when
the deploy includes a D1 migration and the live schema briefly does not match
the code that the same agent is still running against. That window is hard to
avoid, so every production deploy must be a deliberate, announced step.

Always tell the user before you deploy. If the user already asked for the
deploy up front, you do not have to re-ask for confirmation, but you still
explicitly announce that the deploy is starting. Beyond that single up-front
announcement, the whole flow proceeds autonomously — no further user
confirmation between steps.

Use the three-step workflow below for every production deploy. Substitute
`<WORKER_NAME>` (the top-level `name`) and `<DB_NAME>` (the D1 binding's
`database_name`) from `wrangler.jsonc` wherever those placeholders appear in
the commands.

**Step 1 — gather current state.** Read `wrangler.jsonc` to learn
`<WORKER_NAME>` and `<DB_NAME>`, then run a single chained shell command that
reports the currently active Worker version and the D1 migration diff:

```bash
pnpm wrangler deployments list \
  && pnpm wrangler d1 migrations list <DB_NAME> --remote
```

`deployments list` shows recent deployments for `<WORKER_NAME>` with their
version ids and marks the currently active one — that gives both the active
deployment timestamp and the version id you would later roll back to.
`d1 migrations list --remote` prints applied migrations and the pending
migrations this deploy would apply, i.e. the diff between the live database
version and the target.

**Step 2 — report findings and stage the rollback.** Tell the user what Step 1
returned: the active version id, the active deployment timestamp, the latest
applied migration, and the migrations this deploy will apply (or that there
are none).

If migrations are pending, take an explicit D1 backup to a temp file outside
the repo so the working tree stays clean:

```bash
pnpm wrangler d1 export <DB_NAME> --remote \
  --output "${TMPDIR:-/tmp}/<DB_NAME>-$(date -u +%Y%m%dT%H%M%SZ).sql"
```

Report the resolved backup path to the user, then give them two rollback
commands, in this order:

- Restore the database from that dump, e.g. `pnpm wrangler d1 execute <DB_NAME>
  --remote --file <backup-path>` (drop the migrated tables first if the dump's
  `CREATE`s would collide), or `pnpm wrangler d1 time-travel restore <DB_NAME>
  --bookmark <bookmark>` if a pre-deploy bookmark was captured.
- Roll back the Worker code to the previous active version id from Step 1:
  `pnpm wrangler rollback <PREVIOUS_VERSION_ID>`.

If no migrations are pending, skip the backup and the database-rollback
command. Give the user only the code-rollback command and proceed straight to
Step 3.

**Step 3 — deploy with one chained shell command.** Migrate (when needed) and
publish the new code in the same command so the system spends as little time
as possible in an inconsistent state:

```bash
pnpm run db:migrate && pnpm run deploy
```

Print this exact command to the user before running it, and tell them that if
the deploy stops halfway they can rerun the same command to recover —
`wrangler d1 migrations apply` is idempotent on already-applied migrations and
`wrangler deploy` always publishes the current code regardless of prior state.
When there are no pending migrations, the command reduces to `pnpm run
deploy`.

Worker rollback by version id is supported (`pnpm wrangler rollback
<VERSION_ID>`) across the 100 most recent versions, but Cloudflare blocks
rollback when intervening deployments changed Durable Object migrations or
removed referenced KV/R2/Queue bindings. This Worker only binds D1, so plain
code rollback is currently safe; D1 state is rolled back separately as
described above.

A complete deploy fits in a strict turn budget: **three agent turns when
migrations are pending** (Step 1 = gather, Step 2 = backup + report + two
rollback commands, Step 3 = deploy) and **two agent turns when no migrations
are pending** (Step 2 has no backup work, so it collapses into the gather
turn: Turn 1 = gather + report + single code-rollback command, Turn 2 =
deploy). Do not insert extra turns to ask for confirmation along the way.
