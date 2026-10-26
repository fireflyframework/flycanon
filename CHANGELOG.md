# Changelog

All notable changes to **flycanon** are documented here.

## [26.10.6] - 2026-10-26

### Fixed

- Apply nonempty `source_ids` membership before the BM25 and dense candidate windows, Reciprocal Rank Fusion and `top_k` selection. Lower-ranked admitted sources are no longer lost behind unrelated higher-ranked candidates.
- Intersect source membership with the authenticated tenant and workspace in both retrieval channels. A selected source with no matching chunks returns no hits; retrieval never falls back to the global source set. Hydrated filtering remains defense in depth.
- Preserve the existing request schema and the meaning of omitted, `null` and empty-list source selectors: no additional source constraint within the authenticated scope. Knowledge metadata filters retain their hydration behavior.

### Distribution

- Align server and Python/Java SDK version metadata at `26.10.6`. SDK search methods, runtime dependency pins, database migrations, source intake and EDA event schemas are unchanged.
- Retain pyfly `v26.09.04` and Agentic `26.10.1`. Upgrade the server to obtain the source-filter correction; compatible existing SDKs continue to work.

## [26.10.5] - 2026-10-17

### Fixed

- Select the operator's working-directory `alembic.ini` for `flycanon migrate`. Installed wheels now use the reviewed release scaffold instead of looking relative to `site-packages`. Missing or non-file configuration returns a nonzero exit with setup guidance before migration starts; parent and package directories are not searched. The configured database URL and `upgrade head` behavior are retained.
- Document the working-directory contract and the direct Alembic workaround for retained `26.10.4` wheels. The source archive remains the migration/configuration scaffold; wheel contents, migrations and listener behavior are unchanged.
- Give concurrency unit tests independent SQLite connections through a module-local temporary file database. Causal checks cover distinct connections and rollback isolation; existing service assertions, production transactions and ordinary unit fixtures are unchanged.

### Distribution

- Align server and Python/Java SDK version metadata at `26.10.5`. SDK behavior, HTTP contracts and runtime dependency pins are unchanged.

## [26.10.4] - 2026-10-14

### Fixed

- Reject workspace creation when the body `id` differs from `X-Workspace-Id`. The service returns `400 workspace_scope_mismatch` before any storage or lifecycle event write, rather than exposing a PostgreSQL RLS failure as HTTP 500. Matching requests retain their existing `201` response.
- Correct the workspace reference: lookup returns `workspace_not_found`, and the list endpoint accepts no filter or pagination arguments. A separate configured admin connection permits tenant-wide listing; otherwise the request connection's RLS scope controls visibility.

### Distribution

- Align the server and Python/Java SDK versions at `26.10.4`. SDK methods, wire schemas, dependency pins and RLS policies are unchanged. Configure the SDK's workspace header to match the workspace being created; the published Python SDK `26.10.3` remains compatible with the corrected server.
- Native local checks cover creation, RFC 7807 errors, SDK propagation, foreign-scope visibility and credential denial. Lifecycle event delivery remains best-effort after a successful workspace write; this patch adds no delivery guarantee or tenant-bound platform-key grant.

## [26.10.3] - 2026-10-14

### Fixed

- Serialize Python SDK token expiry in JSON mode before HTTP dispatch. Timezone-aware datetime values now reach the mint endpoint, while omitted fields retain their existing behavior. UTC and offset cases cover request and response values; native local mint, list and revoke verify the bounded token lifecycle.

## [26.10.2] - 2026-10-14

### Dependencies

- Adopt the published Agentic `26.10.1` wheel, with its exact digest recorded in the lock. Remove the obsolete Mistral 1.x resolver override and undeclared Agentic `rest`/`redis` extras; Canon continues to supply web and Redis support through its existing dependencies.
- Retain the qualified pyfly `v26.09.04` pin and existing EDA migration history. A later pyfly upgrade requires a separately qualified drain or replay of queued legacy outbox events.

### Distribution

- Synchronize server and SDK versions, workflow references, and released-server installation examples for `26.10.2`. HTTP schemas and Canon's Azure builder and independent RLM cache behavior retain their existing contracts.

## [26.10.0] - 2026-10-12

### Fixed

- Phone PII matching respects hexadecimal identifier boundaries. Numeric substrings in revision and digest identifiers no longer reject canonical memory writes; standalone US and international phone numbers remain detected. Regression coverage includes strict-policy rejection of real phone numbers.
- Release manifests, SDK runtime version strings and package coordinates now agree on `26.10.0`.
- Docker publication uses the same `fireflyframework-agentic` tag as the locked server and PR gate.

### Distribution

- GitHub Releases include server and Python SDK wheels/source archives, the Java SDK JAR, and `SHA256SUMS`. Java SDK publication to GitHub Packages and multi-architecture GHCR builds retain their existing workflows.

## [26.9.0] - 2026-09-24

### Fixed

- **The knowledge plane could not migrate or start against a managed PostgreSQL.** Three places
  issued `CREATE EXTENSION IF NOT EXISTS vector` — migration `0016`, flycanon's own
  `vector_table_ddl`, and the framework's `PgVectorVectorStore._create_schema` on first use of the
  store. On a managed service the PERMISSION check runs BEFORE the existence check, so the statement
  fails against a database that ALREADY HAS the extension, which is every managed database because
  an administrator installs it there first. Azure Database for PostgreSQL answers:

      Because vector isn't a trusted extension, only members of "azure_pg_admin" are allowed to
      use CREATE EXTENSION vector

  `vector` is untrusted in PostgreSQL's own sense, so a managed service is right to reserve it. The
  answer is not to put `flycanon_admin` and `flycanon_app` into the administrator group: that grant
  carries far more than one extension, and a deployment whose roles are separated precisely so no
  application role holds it would be undoing its own posture to get past one statement.

  The two flycanon paths now guard the statement with a `DO` block that asks `pg_extension` first.
  The framework guards it in Python instead, because it holds a connection and can branch on the
  answer — released as `fireflyframework-agentic` v26.06.16, which this release pins.

  The drift test between the migration and the framework changed shape with them: the columns, the
  index names and the HNSW build parameters are still compared literally, the extension is asserted
  per side because the two guard in different places for a reason, and a new case proves the
  framework issues nothing when `pg_extension` says the extension is installed. That test also had
  to stop lying — it drove the framework with an `AsyncMock`, whose `fetchval` answers with a truthy
  `Mock`, so the moment the framework started asking, the mock said yes and the comparison silently
  lost the statement it exists to compare.

### Changed

- `fireflyframework-agentic` moves from `v26.06.14` to `v26.06.16`, in `pyproject.toml`'s git source
  and in the pr-gate's `AGENTIC_REF`.

### Added

- **The answer engine is provider-agnostic.** `FLYCANON_RLM_ROOT_MODEL`
  and `FLYCANON_RLM_SUB_MODEL` accept `azure:<deployment>` and route to
  Azure OpenAI Chat Completions, reading the same
  `FLYCANON_AZURE_OPENAI_ENDPOINT` / `_API_KEY` / `_API_VERSION` /
  `FLYCANON_AZURE_AUTH` (with the bare `AZURE_*` fallbacks) that the
  embedding path already reads. `anthropic:<model>` behaves exactly as
  before, byte for byte on the wire.

  The engine gained a seam rather than a wider client:
  `rlm/chat.py` holds the `RlmChatClient` protocol and
  `build_rlm_client()`, `rlm/client.py` keeps the Anthropic Messages wire
  untouched, and `rlm/azure_client.py` translates the Chat Completions
  wire into the Anthropic content-block vocabulary `RLMSession` speaks,
  in both directions -- `tool_use` <-> `tool_calls`, `tool_result` <-> a
  `role: tool` message, `finish_reason` -> `stop_reason`,
  `prompt_tokens`/`completion_tokens` -> input/output. The CodeAct loop
  is unchanged and does not know which provider answered.

  Three deliberate differences on the Azure path, each commented where it
  lives: no sampling knobs are ever sent (a deployment name does not
  reveal whether the model behind it is a GPT-5 / o-series model that
  answers `400` to `temperature`), the budget travels as
  `max_completion_tokens`, and `FLYCANON_RLM_PROMPT_CACHE` does not apply
  (Azure caches long prefixes automatically and has no `cache_control`
  field).
- **`FLYCANON_ANSWER_MODEL=azure:<deployment>` works from flycanon's own
  settings.** pydantic-ai's `AzureProvider` reads the bare
  `AZURE_OPENAI_ENDPOINT`, `AZURE_OPENAI_API_KEY` and
  `OPENAI_API_VERSION`, and flycanon has no `OPENAI_API_VERSION` at all,
  so a deployment configured the flycanon way had working Azure
  *embeddings* and a RAG answer path that raised `UserError: Must provide
  one of the api_version argument or the OPENAI_API_VERSION environment
  variable` on the first query. `build_agent()` now constructs an
  `azure:` model explicitly from `CanonSettings` (managed identity
  included); every other provider id is still handed to pydantic-ai as a
  string.
- **`FLYCANON_AZURE_MODEL_PRICES`** -- `<deployment>=<usd-per-million-in>/<usd-per-million-out>`,
  comma-separated. Azure rates are per deployment and per agreement and a
  deployment name carries no model identity, so flycanon cannot ship a
  table for them. Unset, the Azure answer path counts tokens exactly,
  records `cost_usd` as `0.00` and says so once per deployment at
  `WARNING`, naming the deployment and this setting. A malformed entry is
  refused at construction rather than skipped.

### Changed

- **An unsupported RLM provider prefix is refused with the list of the
  ones that work.** 26.8.0 refused every non-Anthropic prefix with a
  message explaining that the engine speaks only Anthropic; that message
  is now wrong, because `azure:` works. `parse_model_ref()` names the
  setting, the prefix it was handed and every supported prefix.
  `AnthropicClient` keeps its own narrower guard for the case where it is
  constructed directly with an id it cannot serve.
- **A root and a sub model on two different providers is refused at
  boot.** One client carries one endpoint and one credential, so both
  settings must name the same provider. Refused in a sentence rather than
  half-served.
- The pyfly bean `anthropic_client` is now `rlm_chat_client` and is typed
  `RlmChatClient`. Nothing outside `core/configuration.py` named it.

## [26.8.0] - 2026-09-24

Any embedder, and a way to change it.

Until this release the embedding model was pluggable *per process* and
completely absent *from the data*. Two environment variables picked the
provider and the width; nothing in `canon_chunk_vectors` recorded which
model had produced a row; and the only guard in the system was a width
guard that refused to boot -- "the dimension is fixed when the table is
created and a different width needs a fresh database". A change of MODEL
at the same width was not even refused: it passed every check, and the
query stage then cosine-compared queries from one embedding space against
a corpus in another, with no error and no log line.

**There is no production data in flycanon anywhere**, which is exactly
why this landed now: making the model and its width first-class costs one
migration and zero downtime today, and would cost a maintenance window
and a data move later.

### One thing nobody should be allowed to assume

**Anthropic's Claude models are not served by Azure OpenAI.** An Azure
OpenAI deployment runs the GPT family. Claude is reachable on Anthropic's
own API, on AWS Bedrock and on Google Vertex. Embeddings and answers are
therefore two independent decisions, and the recommended shape for an
Azure preproduction is:

```yaml
FLYCANON_EMBEDDING_MODEL:  azure:<deployment-name>   # embeddings on Azure
FLYCANON_RLM_ROOT_MODEL:   anthropic:claude-sonnet-5 # answers on Anthropic
```

That combination was impossible to express before this release and is
the default recommendation after it.

### Added

- **Embedding sets** (`canon_embedding_sets`, migration `0017`). An
  embedding set is every vector one (provider, model, dimensions,
  endpoint) configuration produced for one workspace.
  `canon_workspaces.active_embedding_set_id` names the set that answers a
  workspace's searches, and **changing the embedder is one `UPDATE` of
  that column**. `canon_chunk_vectors.embedding` loses its typmod and
  every row gains `set_id` / `dim` / `model`, re-keyed
  `PRIMARY KEY (set_id, id)` so one chunk can hold a vector in two sets
  at once. One **partial expression HNSW per set** replaces the single
  global index; the predicate is the SET, not the width, so two sets at
  one width never share an index.
- **`flycanon reindex`** -- the verb `docs/deployment.md` and
  `docs/operations-runbook.md` have been telling operators to run since
  26.5 and which the software did not have.

  ```
  flycanon reindex --to azure:<deployment> --dimensions 1536 \
                   [--workspace w --tenant t | --tenant t | --all]
                   [--estimate-only] [--yes] [--resume <set-id>]
                   [--batch-size 256] [--no-activate]
  flycanon reindex --list | --activate <set-id> | --rollback | --drop-set <set-id>
  ```

  It plans and prices first, creates one set per workspace, embeds in
  batches from `canon_chunks`, catches up anything ingested during the
  run, builds the ANN index, and only then switches. **The old set serves
  every search for the whole run** -- the search predicate IS the set id,
  so the new set is invisible until it is activated -- and the old set's
  rows and index are kept, so `--rollback` is the same `UPDATE`
  backwards. Progress rides the existing `canon_ingest_jobs` /
  `canon_ingest_job_events` tables (`kind='reindex'`, cursor in
  `metadata_json`), so the SSE stream works with no new plumbing, and
  `ON CONFLICT (set_id, id)` makes a replayed batch a rewrite.
- **Azure OpenAI as real configuration.**
  `FLYCANON_AZURE_OPENAI_ENDPOINT` / `_API_VERSION` / `_API_KEY` (falling
  back to the bare `AZURE_*` names) and
  `FLYCANON_AZURE_AUTH=api_key|managed_identity`, validated at config
  time with messages that name the setting. `managed_identity` acquires a
  bearer token through `DefaultAzureCredential`
  (`uv sync --extra azure`), so no key exists in the environment to leak.
  The api-version was previously pinned at `2024-02-01` inside the
  framework and unreachable from flycanon; it now defaults to
  `2026-05-01`.
- **Per-workspace model choice.** One shared flycanon can serve tenant A
  on Azure and tenant B on Ollama: `EmbeddingRegistry` caches one
  embedder per `(provider, model, dimensions)` and a query is embedded by
  the model that produced the corpus it searches. Per-**tenant
  credentials** are still per deployment -- named as a limitation in
  `docs/security-model.md`, because it is a compliance statement and not
  an implementation detail.
- `ChunkStats.by_embedding_model` on `GET /api/v1/stats` (and both SDKs):
  the chunk count per `<provider>:<model>`. During a reindex the corpus
  is split across two identifiers and the split moving is the run making
  progress.

### Fixed

- **The admin dashboard reported `embedded_pct: 0.0` on a fully embedded
  corpus.** `StatsService` counted `canon_chunks.embedding`, a JSON
  column nothing in `src/` has ever written. The column is dropped and
  coverage is counted from `embedding_model`, which every indexed chunk
  carries. That number is what an operator stares at while a reindex
  runs.
- **A model change at the same width could no longer corrupt retrieval
  silently.** A `SECURITY DEFINER` trigger refuses a vector whose
  `(model, dim)` disagrees with its set's, with a message naming
  `flycanon reindex`. This is the single most valuable guard in the
  release: the failure it closes had no error and no log line.
- **The RLM engine refuses a non-Anthropic model at boot.**
  `AnthropicClient` stripped ANY provider prefix, so
  `FLYCANON_RLM_ROOT_MODEL=azure:gpt-5.2` POSTed `{"model": "gpt-5.2"}`
  to `api.anthropic.com`, retried six times with exponential backoff and
  surfaced a 404 that blamed the wrong vendor. It now raises at
  construction, naming the setting and the two configurations that work.
- **An unknown embedding model is priced `cost unknown`, never `$0.00`.**
  `prices.py` keys rows by `(provider, model)` with a named `basis`
  (`2026-09-azure-published`) and returns `None` for a model it does not
  know. A local embedder is priced at zero with the basis `local`, which
  is a fact rather than an absence.
- **Zero vectors on a per-item embedding failure are opt-in.** The
  previous behaviour wrote `[0.0] * dimensions` with a warning; those
  rows entered the ANN index indistinguishable from real ones, nothing
  marked them, and they were unrecoverable afterwards.
  `FLYCANON_EMBEDDING_ZERO_VECTOR_ON_FAILURE` defaults to `false`, and
  the reindex path refuses them whatever it says.
- **A 429 is a throttle, not an error.** `Retry-After` is honoured
  exactly (with jitter), the in-flight window halves and recovers, and a
  sustained throttle during a reindex records `reindex.throttled` and
  keeps the cursor instead of consuming one of the job's three attempts.
- **A 3072-wide model had no ANN index at all.** pgvector refuses an HNSW
  on a `vector` column wider than 2000 dimensions, so
  `text-embedding-3-large` at its native width -- the exact configuration
  this release exists to support -- would have sequential-scanned in
  silence. Sets above that ceiling are indexed as `halfvec(N)`: full
  precision in the column, half in the index. Found by running the
  end-to-end suite against a real server, which is what it is for.
- **Searches set `hnsw.iterative_scan = relaxed_order`** alongside
  `ef_search`, so the post-ANN namespace filter cannot under-recall a
  small workspace inside a large set.
- `docs/deployment.md` listed Voyage under the token `voyageai:`, which
  `_build_embedder` has never accepted (it is `voyage`), and omitted
  Azure, Bedrock and Google entirely. Google is now marked as needing an
  extra flycanon does not install (`google-generativeai`; the
  transitively present `google-genai` is a different package).

### Changed

- **The boot-time width refusal is deleted.** After `0017` the column has
  no width to disagree with, and three better things replace it:
  pgvector raises `expected N dimensions, not M` on a mis-scoped query
  (an error, not a wrong answer); the coherence trigger catches the
  same-width model change the width check never could; and a workspace
  that is not on this process's embedder logs a WARNING naming
  `flycanon reindex` -- a warning and not a refusal, because one process
  legitimately serves workspaces on several sets.
- Migration `0017` reads settings only to **label** the set it adopts,
  never to size a column. `0016` read `FLYCANON_EMBEDDING_DIMENSIONS` to
  bake `vector(N)` into the schema, which is why a migrate/serve
  environment mismatch created one width and then failed every pod's
  boot. After `0017` the schema has no environment dependency at all.
- `partition_admin.py` is **deleted**. Its Tier-B recipe partitioned
  `canon_chunk_vectors` by `LIST (tenant_id)`, a column migration `0014`
  dropped and `0016` never recreated, so it could not have worked -- and
  a reader of that table would have found it and believed it.
  `docs/architecture.md` and `docs/scale-and-performance.md` say what
  replaced it.

### Migration `0017`, and what it does to data

**Reversible, and lossless where rows exist.** The upgrade relaxes the
column in place (a typmod relaxation rewrites no value and cannot drop a
row), adopts existing vectors into one set per namespace sized by
`vector_dims()` **measured per row**, re-keys the table and builds one
partial index per adopted set. The downgrade restores `vector(N)` at one
width, and **refuses at two widths** -- naming
`flycanon reindex --drop-set` -- rather than truncating rows into a width
they were not embedded at. Both directions are proven against a live
pgvector in `tests/integration/test_migration_0017_populated.py`.

On every deployment that exists today the adoption path finds nothing and
the migration is pure DDL. It still ships, and is still tested, because
it is the only thing between a future populated deployment and a fresh
database.

Run `flycanon migrate` before rolling the new image, as for every
`YY.MM.0`.

### What a POPULATED deployment would need on top

Stated plainly, because this release ships the schema, the command and
the switch, and deliberately not an online zero-downtime dual-serving
proxy:

1. **Write-path fan-out during the window.** A catch-up pass re-embeds
   anything ingested while the run was walking the corpus, before the
   switch -- that ships. Genuine dual-write in `IndexService` to every
   non-retired set is the real zero-downtime answer and is **not** here;
   a deployment that cannot tolerate the catch-up window should freeze
   ingestion for it.
2. **Batches run in the CLI process, not on the ingest worker.**
   `FLYCANON_WORKER_HANDLER_TIMEOUT_S` is 120 s, so a worker-dispatched
   re-embed needs one event per batch with its own retry accounting; a
   CLI has no such wall. The cursor is what makes a killed shell
   survivable.
3. **Index build under load.** Above ~100k chunks the HNSW build is the
   dominant cost and wants `maintenance_work_mem`,
   `max_parallel_maintenance_workers` and a maintenance window.
4. **Storage.** Two sets double the vector table for the length of the
   rollback window; `VACUUM FULL` or `pg_repack` after `--drop-set`
   reclaims it. Neither is automated.

## [26.7.1] - 2026-09-24

Hardening for a multi-tenant caller (the dworkers control plane, which
runs one shared flycanon for all its tenants). Every item below was
found by wiring that caller against 26.7.0.

### Security

- **`FLYCANON_API_KEYS` is now enforced.** The setting existed since
  the first release and was read by nothing: anyone who could reach
  port 8500 could read or write any tenant and mint agent tokens for
  it. `ApiKeyMiddleware` now requires `X-API-Key: <key>` or
  `Authorization: ApiKey <key>` on every `/api/v1/*` route except
  `GET /api/v1/version`, and on the admin dashboard, whenever at least
  one key is configured (`401 missing_api_key` / `401 invalid_api_key`,
  RFC 7807, constant-time comparison). `/api/v1/agent/*` requests that
  carry `X-Agent-Token` are exempt -- the token is their credential.
  With the setting empty the service stays open as before and the boot
  log says so (`api-key gate DISABLED`); with keys it logs
  `api-key gate ENABLED: n key(s)`.
- **Admin dashboard requires authentication** (`pyfly.admin.require-auth`
  defaults to `true`, overridable with `FLYCANON_ADMIN_REQUIRE_AUTH=false`
  for loopback dev). A validated platform key is bridged into pyfly's
  `SecurityContext` (`ApiKeyPrincipalFilter`) so the dashboard answers
  to the key and refuses everything else.
- **Outbound host policy (SSRF guard).** `uri` fetches and
  `callback_url` webhooks refuse every address that is not globally
  routable -- loopback, private (RFC 1918 / ULA), link-local (instance
  metadata), multicast, reserved, unspecified, RFC 6598 shared address
  space (`100.64.0.0/10`: CGNAT, Tailscale, the pod CIDR of most
  managed Kubernetes clusters), site-local, documentation and
  benchmarking blocks; the decision is `ipaddress`'s `is_global`, the
  named checks only shape the message -- literal, DNS-resolved, and on
  every redirect hop (redirects are now followed by hand, at most
  five) -- with `400 url_fetch_forbidden_host`
  / `400 callback_url_not_allowed`. `FLYCANON_URL_FETCH_ALLOW_PRIVATE=true`
  lifts the denylist for private dev stacks. Fetcher failures now render
  as problem+json (`url_fetch_*` codes, 400 / 413 / 502) instead of the
  framework 500. Documented gap: DNS rebinding between check and dial.
- **Signed webhooks.** Async-ingest callbacks carry
  `X-Flycanon-Signature: t=<unix>,v1=<hex HMAC-SHA256 over the raw
  body>` when `FLYCANON_WEBHOOK_SECRET` is set (unsigned + boot warning
  otherwise), and the payload now carries `tenant_id` / `workspace_id`.
  `verify_signature` ships in `flycanon.web.conventions.webhook_signature`.

### Added

- **User-tier `DELETE /api/v1/sources/{id}`** (204; `404
  source_not_found`). Both it and the agent-tier DELETE now **delete the
  stored original from the object store** as well as the index, chunks
  and row -- before, an "erased" document stayed readable by the RLM
  corpus. `IntakeService.remove` returns a `SourceRemoval`, and its
  `original_deleted` is a fact, not a promise: the store is asked
  whether the object exists before the (no-op-on-missing) delete, and a
  key that is not in this process's store is logged as a warning and
  reported `false` -- the audit payload, the `SourceRemoved` event and
  the purge counter all carry that same value.
- **`POST /api/v1/workspaces/{id}:purge`** -> `WorkspacePurgeResult`.
  Removes every source through the full pipeline, then knowledge items
  / versions / citations / relations, candidates, conversations /
  turns, ingest jobs / events and cost events in one transaction,
  closes the workspace and emits `WorkspaceDeleted`; audit rows are
  kept and a `workspace.purged` row records the counts. `X-Workspace-Id`
  must equal the path id (`400 workspace_scope_mismatch`). Idempotent
  in the literal sense: every counter is what this call erased,
  `originals_deleted` counts objects actually found and deleted, and
  `closed` is `true` only for the call that moved the row to `closed`
  (`WorkspaceRepository.close_if_open`); a repeat is all zeros with
  `closed: false`, restamps nothing, publishes no second
  `WorkspaceDeleted` and writes no second audit row.
- **Job-stream resume.** `GET /api/v1/ingest-jobs/{id}/stream` accepts
  `?after_id=<id>` and the standard `Last-Event-ID` header, and stamps
  `id:` on every `event` frame, so a reconnect no longer replays the
  whole history (the docs had promised `after_id` since 26.5).
- **`FLYCANON_ADMIN_DATABASE_URL`.** `WorkspaceRepository.list_for_tenant`
  (`GET /api/v1/workspaces`) runs on this BYPASSRLS engine; under the
  production `flycanon_app` role the request engine could only ever
  return the caller's own header workspace.
- **OpenAPI wire contract.** `openapi.json` declares `securitySchemes`
  (`ApiKeyHeader`, `ApiKeyAuthorization`, `AgentToken`) and reusable
  header parameters (`X-Tenant-Id`, `X-Workspace-Id`, `X-Correlation-Id`,
  `Idempotency-Key`) attached to every operation, so a generated client
  sends the mandatory headers. `security` describes what satisfies the
  operation, not what the middleware lets through: `/api/v1/agent/*`
  lists `AgentToken` alone (the platform key is neither required nor
  accepted there -- the route answers `401 missing_agent_token`), every
  other tenant operation lists the two platform-key forms.
- **Scope on ingest events.** Every `flycanon.ingest` payload
  (`SourceIngested`, `SourceReplaced`, `SourceRemoved`,
  `SourceIngestionFailed`, `IngestSourceRequested`, `IngestSourceFinished`,
  `IngestSourceFailed`) carries `tenant_id` / `workspace_id` -- including
  the `IngestSourceRequested` the stuck-job sweep republishes:
  `IngestJobRepository.reclaim_stuck` returns `ReclaimedJob(job_id,
  tenant_id, workspace_id)` and the service has no unscoped publish path.

### Changed

- **Conversations use the same engine as `/query`.** `ConversationService`
  is wired to `AnswerDispatcher`, so `POST /conversations/{id}/turn`
  answers with RLM by default and only with the deprecated RAG engine
  under `FLYCANON_ANSWER_MODE=rag` (then with the `X-Flycanon-Deprecation`
  header, like `/query`).
- **Framework pins moved** to pyfly `v26.09.04` and fireflyframework-agentic
  `v26.06.14`; the unit suite, ruff and pyright pass unchanged on them.
  **`uv.lock` is now committed** and CI / the Dockerfile run
  `uv sync --locked`.
- **API and worker no longer share a Postgres-outbox consumer group.**
  pyfly's CQRS auto-configuration subscribes a cache-invalidation
  bridge on `*` in every process, so an API on the worker's group
  advanced the shared cursor past `IngestSourceRequested` events and
  `?mode=async` jobs stayed `queued` forever. The API defaults to
  `flycanon-api`, `flycanon worker` to `flycanon-workers`
  (`FLYCANON_EDA_GROUP` overrides either).
- **`FLYCANON_RLM_ANSWER_MODEL` removed.** `CanonSettings.rlm_answer_model`
  shipped with the RLM settings in 26.7.0, documented as "the model for
  the final single-shot answer synthesis", and was read by nothing: the
  RLM's final answer is produced by the **root** model, either as the
  `final(...)` tool call of the CodeAct loop or as the tool-less
  forced-final turn when the loop runs out (both `chat_raw` turns on
  `FLYCANON_RLM_ROOT_MODEL`); the sub model serves the `llm()` / `rlm()`
  helpers and the self-consistency selector. There is no single-shot
  synthesis step for a third model to drive, so the knob is gone rather
  than wired; `CanonSettings` ignores unknown `FLYCANON_*` variables, so
  an env file that still sets it boots unchanged. The docs, `env_template`
  and the README now name two RLM models and say which one answers
  (`tests/unit/rlm/test_which_model_answers.py` records the request
  bodies of a whole session and pins it).
- **Both entry points export pyfly's `_PYFLY_SERVER_*` variables.**
  pyfly logs `server_started` in every process with `0.0.0.0:8080` as
  the fallback. `flycanon serve` exports `uvicorn` / `0.0.0.0` /
  `FLYCANON_PORT` so the line reports the real socket; `flycanon worker`,
  which runs no server, exports `none` / `-` / `0` so the line cannot
  claim a listener the process does not hold, and logs its own "no HTTP
  listener in this process" line beside it.

### Fixed

- **The shipped image could not ingest.** The localfs object-store
  default `./var/objects` resolved to the root-owned `/app/var` under the
  `canon` user, so the first ingest failed with EACCES. The image now
  exports `FLYCANON_OBJECT_STORE_LOCALFS_ROOT=/app/canon-data/objects`
  (volume-backed) and pre-creates `/app/canon-data/objects` and
  `/app/var/objects` with `canon` ownership.
- **Sandbox child on macOS.** `RLIMIT_AS` is not settable on Darwin;
  the RLM sandbox runner now tolerates that refusal there (CPU and
  file-size caps still apply) instead of dying at startup, which had
  failed 27 unit tests on every developer Mac.
- **Zero search hits under the application role.** `PostgresCorpus`
  (the BM25 channel) ran its reads on a bare Core connection of its own
  engine, where the ORM `after_begin` listener that sets the
  `app.tenant_id` / `app.workspace_id` GUCs never fires; under FORCE
  RLS a `NOBYPASSRLS` serving role (`flycanon_app`, as
  `docs/deployment.md` prescribes) therefore saw no chunk on the
  lexical channel and no row on the RRF hydration, and `/search` and
  `/agent/search` answered `hits: []` while the vector channel alone
  found the chunk. Invisible in a stack where every process is the
  database owner. Every scoped corpus read now binds the GUCs itself,
  from the explicit `(tenant_id, workspace_id)` it is handed, through
  `set_config(..., is_local => true)` inside the read's own transaction.
  `tests/integration/test_search_under_app_role.py` runs the real
  `RetrievalService.search` as a NOBYPASSRLS role and gets the row;
  `tests/unit/test_postgres_corpus_scope_filter.py` pins the corpus
  alone, with the bare-connection control that returns nothing.
- **DDL at boot under the serving role.** `canon_chunk_vectors`
  (framework `PgVectorVectorStore`: extension, table, HNSW + namespace
  indexes, flycanon's RLS policy) and PyFly's `pyfly_eda_outbox` /
  `pyfly_eda_offsets` were created lazily by whichever process first
  touched them. PostgreSQL checks `CREATE` on the schema before it
  honours `CREATE TABLE IF NOT EXISTS`, and demands ownership before
  `CREATE INDEX IF NOT EXISTS`, so a serving role with USAGE + DML could
  not boot the dense store (its first ingest died with
  `permission denied for schema public`). New migration
  `0016_boot_created_tables` creates all three as the migration role
  (the vector table sized by `FLYCANON_EMBEDDING_DIMENSIONS` and the
  `FLYCANON_PGVECTOR_HNSW_*` settings of the migrate job, the outbox
  tables from PyFly's own DDL constants), and
  `RlsPgVectorVectorStore._create_schema` is verify-first: on an
  existing table it runs no DDL and refuses a width other than the
  configured one (`VectorStoreError`, before the first vector is
  written). PyFly's outbox DDL still runs in `start()` -- an upstream
  ask -- so a non-owner serving role keeps `CREATE` on the schema and
  membership of the owning role until it ships (`docs/deployment.md`).
- **`temperature` refused by Claude 5 / 4.7 / 4.8.** The RLM client sent
  `temperature: 0.0` on every Messages call; `claude-sonnet-5` answers
  `400 temperature is deprecated for this model`, so `FLYCANON_RLM_*_MODEL`
  could not name a current model. `request_shape(model)` now classifies
  the id: Claude 4.6 and later (`claude-*-5*`, Opus 4.6/4.7/4.8, Sonnet
  4.6) get `thinking: {"type": "adaptive"}`, no sampling knobs, and a
  `max_tokens` floor of 8192 (thinking tokens count against the budget;
  the old 1500 tool-turn ceiling came back as `stop_reason: max_tokens`
  with no `tool_use`, which the session read as an empty plain-text
  answer); Haiku 4.5, Sonnet 4.5 and any id that does not parse keep
  the deterministic `temperature: 0.0` byte for byte. Price rows added
  for Sonnet 5, Opus 5, Opus 4.6/4.7; Opus 4.8 corrected from the old
  Opus tier (15/75) to 5/25.

### Docs + SDK

- README, QUICKSTART, `docs/payload-reference.md`, `docs/api-reference.md`,
  `docs/async-ingest.md`, `docs/security-model.md`, `docs/deployment.md`,
  `docs/eda-events.md`, `docs/conversations.md`, `docs/pipeline.md` and
  `env_template` describe the routes that exist (JSON `content_base64`
  intake, `?mode=async`, `/query/stream`, `/conversations/{id}/turn`,
  `/query/suggest`, `/ingest-jobs/{id}/stream?after_id=`), the new
  verbs, headers and settings, and the `no_answer` contract.
- The Python SDK is realigned with the served routes and bumped to
  `26.7.1` (see `sdks/python/CHANGELOG.md`).

## [26.7.0] - 2026-07-23

### Added

- **Agent-tier source replace.** `PUT /api/v1/agent/sources/{source_id}` (scope
  `agent.sources:ingest`, mandatory `Idempotency-Key`) re-ingests an existing
  source in place through the same pipeline as the user-tier PUT: chunks and
  dense vectors are replaced under the same `source_id`. `content_base64` is
  required; replays dedup under a route-specific scope.
- **Agent-tier source delete.** `DELETE /api/v1/agent/sources/{source_id}`
  (scope `agent.sources:ingest`, mandatory `Idempotency-Key`, `204`) removes a
  source within the tenant/workspace scope: BM25 rows and dense vectors are
  purged, chunk rows and the source row are deleted, an audit entry is recorded
  and a `SourceRemoved` EDA event is published. Object-store originals are not
  touched. A retried DELETE with the same key replays the original `204`.

### Changed

- **Single-source version.** `__version__` (and the version reported by
  `pyfly_application` / `GET /api/v1/version`) is now derived from the
  installed package metadata via `importlib.metadata`, so `pyproject.toml`
  is the only place a release bump touches.

## [26.6.19] - 2026-06-30

### Fixed

- **RLM empty-answer bug.** When the CodeAct loop exhausted its iteration
  budget without calling `final()`, the engine returned an empty string flagged
  as a valid answer (`no_answer=false`) that callers could not detect. A blank
  result is now surfaced as `no_answer=true` with an explanatory note, and the
  out-of-iterations fallback re-asks the model with no tools so a diverged run
  must emit text instead of nothing.
- **CodeAct truncation divergence.** A long answer synthesised into a REPL
  variable looked cut off when printed (the 4000-char stdout cap is display
  only), so the model spent every remaining turn re-asking for "the missing
  parts" and never called `final()`. The system prompt now states that a
  variable is held in full even when its printout looks truncated and that the
  built answer should be submitted rather than reassembled.
- **Actuator/admin stayed on the app port.** pyfly v26.06 splits actuator +
  admin onto a dedicated management port (9090) by default; flycanon collapses
  them back onto the app port (8500) via `pyfly.management.server.port` so
  `/actuator/*` health probes and `/admin` remain reachable on the single
  business port.

### Added

- **Per-request `extended_reasoning`** (`AnswerRequest.extended_reasoning`,
  default `false`) — runs the RLM engine at twice the configured
  `FLYCANON_RLM_MAX_ITERS` for a single hard request, without a global default
  bump. RAG ignores it.
- **Self-consistency guard** (`FLYCANON_RLM_SELF_CONSISTENCY`, default `1` =
  off). When `>1`, the non-streaming answer path runs the engine N times in
  parallel and an LLM selector returns the most-grounded answer; token usage of
  all runs plus the selector is merged.
- **CodeAct turn logging + convergence warnings** — a per-turn DEBUG trace and
  a WARNING when the loop exhausts its budget without converging.

### Changed

- **Scoped RLM system prompt** — requires verifying every benchmark, threshold,
  and figure against the source documents and forbids stating a value not found
  in them.
- **pyfly bumped to v26.06.113.**

## [26.6.18] - 2026-06-18

### Added

- **RLM (Recursive Language Model) answer engine.** A code-driven CodeAct REPL
  that reasons over whole documents instead of retrieving chunks: it routes to
  the right source, reads it, and computes the answer in a sandboxed Python
  loop. New `FLYCANON_RLM_*` settings tune the root/sub/answer models
  (default `anthropic:claude-sonnet-4-6`), iteration budget, and depth.
- **Object-store originals.** A hexagonal `ObjectStore` port (LocalFs / S3) plus
  `FLYCANON_OBJECT_STORE_*` settings; ingest persists the original document and
  records `canon_sources.object_store_key` when `FLYCANON_STORE_ORIGINALS` is
  on (default), giving RLM a whole-document corpus.
- **Scalable corpus access.** The corpus loads lazily (only the filings the
  model actually reads are fetched) behind a tiered page cache — a thread-safe
  in-process LRU and an optional shared Redis layer (`FLYCANON_CORPUS_CACHE_*`),
  content-hash keyed so a re-ingest auto-invalidates.
- **Prompt caching** for the RLM loop (`FLYCANON_RLM_PROMPT_CACHE`, default on):
  the repeated system prompt is marked `cache_control: ephemeral`.

### Changed

- **RLM is now the default answer mode** (`FLYCANON_ANSWER_MODE=rlm`). It backs
  `/api/v1/query`, the SSE `/api/v1/query/stream` (a `status` frame then the
  `final` frame), and the agent-tier equivalents, with full filter parity.

### Deprecated

- **Hybrid-RAG answer mode** (`FLYCANON_ANSWER_MODE=rag`) is deprecated and
  slated for removal in a future release. When selected it logs a deprecation
  warning and returns an `X-Flycanon-Deprecation` response header. The raw
  `/api/v1/search` retrieval surface is unaffected.

## [26.5.9] - 2026-05-31

### Changed

- **Open-sourced under the Apache License 2.0.** Replaced the proprietary
  notice with the full Apache 2.0 `LICENSE` (root + both SDKs) and prepended
  the Apache 2.0 header to every source file. The copyright holder is now
  Firefly Software Foundation, and the repository is public.
- Set the OpenAPI `info.license`, the image `licenses` label, the README
  badge, and `pyproject` metadata to Apache-2.0.
- Realigned `__version__` with the packaged release version.

## [Unreleased] -- Multitenancy backbone

### Added -- multi-backend vector stores (26.5.8)

- **Pluggable dense backend.** `FLYCANON_VECTOR_STORE` now selects the dense
  projection backend: `pgvector` (default), `qdrant`, or `chroma`. The lexical
  BM25 half and RRF fusion always stay on Postgres. Qdrant/Chroma use the
  adapters that ship in `fireflyframework-agentic` (install `--extra qdrant` /
  `--extra chroma`); new `FLYCANON_QDRANT_*` / `FLYCANON_CHROMA_*` settings
  configure them.
- **Explicit, fail-loud scope contract.** Every dense backend is wrapped in the
  framework's `TenantScopedVectorStore`, which folds `(tenant_id, workspace_id)`
  into a canonical `t/<tenant>/w/<workspace>` namespace. The previous
  `inspect.signature` scope-probe (which could silently skip isolation on a
  scope-blind store) is gone; missing scope now fails loud.
- **pgvector moved upstream.** flycanon's bespoke pgvector adapter was replaced
  by the framework's generic `PgVectorVectorStore`; flycanon keeps a thin
  `RlsPgVectorVectorStore` subclass that adds namespace-keyed Postgres RLS via
  the adapter's `_prepare_session` hook. Requires `fireflyframework-agentic`
  >= 26.5.32. Migration `0014` retires the legacy column-shaped
  `canon_chunk_vectors` table (the adapter recreates the namespace-shaped table
  on boot; **re-index after upgrading** to repopulate the derived projection).
- **Vector purge on source delete.** `IndexService.remove_for_source` now purges
  the dense vectors for a deleted source's chunks (external stores have no FK
  cascade).

### Changed -- retrieval and intake internals (26.5.7)

- **Native per-format document intake.** Document intake runs on native
  per-format SourceLoaders: `XlsxLoader` (openpyxl), `PptxLoader`
  (python-pptx), `CsvLoader` (CSV/TSV, stdlib), `JsonLoader` (stdlib),
  `XmlLoader` (lxml), `RtfLoader` (striprtf) and `OdfLoader` (ODT/ODS/ODP,
  odfpy). The registry fallback is a plain-text `TextLoader`, so an
  unrecognised payload degrades to UTF-8 text. `striprtf` + `odfpy` are
  declared as direct deps.
- **Binary normalisation.** Binary normalisation runs through
  `fireflyframework_agentic.content.binary` (the unified normaliser shared
  with flydocs), wired in `CanonCoreConfiguration` from a `BinaryConfig`
  mapped off `CanonSettings` (`wrap_text_as_pdf=False` -- text passes
  through to the SourceLoaders; `email_render_header=True`). The
  `OfficeConverter` stays pluggable.
- **Hybrid retrieval primitives.** `StoredChunk`, `ChunkHit`,
  `reciprocal_rank_fusion` and `HybridRetriever` live in
  `core/services/retrieval/fusion.py`. `HybridRetriever` honours
  `FLYCANON_RETRIEVAL_RRF_K`.
- **Hybrid retrieval, pluggable dense half.** `corpus_factory` keeps BM25 on
  Postgres and routes the dense half to the configured backend (see *Added --
  multi-backend vector stores* above). _Previously pgvector-only._
- **Dependencies.** `fireflyframework-agentic` is pulled with the
  `[openai-embeddings,binary,vectorstores-pgvector]` extras; the `[binary]`
  extra provides pillow-heif, cairosvg, py7zr and extract-msg. Qdrant/Chroma
  client libraries come from the framework's `vectorstores-*` extras via
  flycanon's optional `qdrant` / `chroma` extras.

### Added -- Redis-backed adapters for rate-limit + idempotency

- **`RedisRateLimiter`** -- sliding-window per-token rate limiter
  using a Redis ZSET + Lua script (atomic across replicas). Opt-in
  via `FLYCANON_REDIS_URL` (`auto` picks Redis when the URL is set)
  or forced via `FLYCANON_RATE_LIMIT_BACKEND=redis`. Lives next to
  the in-memory `_RateLimiter` behind the new `RateLimiter`
  Protocol so `AgentTokenService` accepts either via constructor
  injection.
- **`RedisIdempotencyStore`** -- Redis-string-backed replay store
  with native TTL. Same env-var toggle
  (`FLYCANON_IDEMPOTENCY_BACKEND=redis` or `auto`+`redis_url`).
  Replaces the in-process LRU cap (`max_entries=100_000` on the
  in-memory variant) with native Redis TTL eviction for production
  scale.
- **`IdempotencyStore.lookup` / `record_response` are now async**
  to honour the Redis adapter's coroutine signature; the in-memory
  variant keeps the same dict-mutation body under `async def`.
  Helpers `check_idempotency_replay` / `store_idempotent_response`
  and every agent controller that calls them now `await` the
  store. The legacy sync `get` / `put` surface is unchanged so the
  workspace-scoped index tests keep working.
- **`RateLimiter` Protocol** -- new public surface in
  `core/services/auth/agent_token_service.py`. Both
  `_RateLimiter.consume`/`drop` and `RedisRateLimiter.consume`/`drop`
  are async; `AgentTokenService.verify` / `.revoke` await them.
- In-memory adapters remain the default when `redis_url` is absent
  / `FLYCANON_RATE_LIMIT_BACKEND` and `FLYCANON_IDEMPOTENCY_BACKEND`
  are `in_memory`. Behaviour wire-stable across the swap.

### Added -- agent-token rate limiting

- **`rate_limit_rpm` enforcement** -- `AgentTokenService.verify`
  now consults a per-token sliding-window counter (60s, keyed by
  `token_id`). Tokens that exceed their `rate_limit_rpm` budget get
  `429 rate_limit_exceeded` (new `RateLimitExceeded` exception);
  `rate_limit_rpm = None` (or `<= 0`) skips the check entirely so
  legacy tokens are unaffected. `revoke` drops the in-memory bucket
  so a re-mint that reuses the `token_id` starts fresh.
- **In-memory only / process-local** -- the bucket dict lives in
  the `AgentTokenService` instance behind a `threading.Lock`. This
  is intentional MVP posture, matching the rest of the service.
  A Redis-backed counter shared across replicas is available as
  a pluggable adapter (the `_RateLimiter` Protocol is the
  integration seam); exception class and status code are
  wire-stable across the swap.
- **New error code**: `rate_limit_exceeded` (429).

### Added -- workspace + multitenancy schema

- **`canon_workspaces` table** -- canonical store for workspace
  identity, status, scope, sme_roster, retention_days, jurisdiction.
  Migration `0008_workspaces`.
- **`(tenant_id, workspace_id)` columns** on every existing
  `canon_*` table (14 in total) -- NOT NULL with server default
  `'default'`. Existing rows backfilled to `'default'`/`'default'`.
  Composite `(tenant_id, workspace_id)` indexes added for
  workspace-scoped queries.
- **`Workspace` SQLAlchemy entity** + **`WorkspaceStatus` enum**
  + 4 DTOs (`WorkspaceCreate`, `WorkspaceUpdate`, `WorkspaceSpec`,
  `WorkspaceSummary`).
- **`WorkspaceRepository`** with CRUD operations (insert, get,
  list_for_tenant, update, close).
- **`flycanon.web.conventions` module** -- 90 tests covering RFC 7807
  envelope, FastAPI dependency, exception hierarchy, idempotency
  primitives, tenant-safe HTTP client. Wired into controllers (see
  BREAKING section below).

### Added -- embeddings hardening

- **Migration 0009** -- `canon_chunks` re-embed drift index swap:
  `(source_id, embedding_model)` -> `(tenant_id, workspace_id,
  embedding_model)`. Plus new composite
  `ix_canon_chunks_scope_source` for source fetches within a
  workspace.
- **Migration 0010** -- `canon_chunk_vectors` gains `tenant_id` +
  `workspace_id` columns with `'default'` server default, plus
  composite index `canon_chunk_vectors_scope`. Postgres-only;
  SQLite is a no-op.
- **`PgVectorVectorStore`** -- DDL creates scope columns from
  day one; `search()` filters scope + bumps `hnsw.ef_search` to
  200 per-query via `SET LOCAL`; SQL-side widening via
  `LIMIT k * widening_factor` (default 5).
- **`PostgresCorpus.bm25_search`** -- filters `(tenant_id,
  workspace_id)` before `tsv @@ plainto_tsquery`. Global GIN on
  `tsv` is intersected with the composite btree cheaply.
- **`RetrievalService.search()`** -- fails closed
  (`MissingTenantContext`) when scope is missing; threads
  `tenant_id` + `workspace_id` through scope-bound proxies to
  the HybridRetriever.
- **`IndexService.replace_for_source()`** -- requires `tenant_id`
  + `workspace_id` kwargs with no default.
- **Tier-B partition admin** in
  `flycanon.core.services.retrieval.partition_admin`. Dormant
  by default. `promote_tenant_to_partition()` /
  `demote_tenant_from_partition()` for hot-tenant operators.

### BREAKING -- conventions adoption + controller wiring

- **Headers required everywhere.** Every `/api/v1/*` call (except
  `/api/v1/version`) requires `X-Tenant-Id` + `X-Workspace-Id`.
  Missing -> `400 missing_tenant_context`.
- **Error envelope.** `title` is human-readable; the `code` field
  carries the machine identifier; `type` URI base is
  `https://firefly.dev/problems/...`. Media type
  `application/problem+json`.
- **`/api/v1/jobs/*` -> `/api/v1/ingest-jobs/*`** -- 3 sub-routes
  renamed.
- **`actor` is audit metadata.** `actor` stays as audit metadata on
  every row; queries/groupings use `(tenant_id, workspace_id)`.
  Billing endpoints do not accept an `actor` Query param.
- **New `/api/v1/workspaces` CRUD** -- create/list/get/patch/close
  on `canon_workspaces`.
- **`canon_sources.content_sha256` unique constraint widened** to
  `(tenant_id, workspace_id, content_sha256)`. Same content can
  coexist in multiple workspaces.
- **Entity-level `'default'` defaults dropped** -- services pass
  real `tenant_id` + `workspace_id` from `TenantContext`. Migration
  `0011` drops the column-level `server_default` too.
- **RetrievalService scope threading.** `/api/v1/search`,
  `/api/v1/query`, and `/api/v1/query/stream` thread scope from the
  request headers into the retrieval layer.

### Added -- agent surface

- **Agent tokens**: new `canon_agent_tokens` table (migration
  `0012_agent_tokens`). Tokens are tenant-scoped, hashed at rest,
  carry optional `workspace_allowlist`, `scopes` list,
  `rate_limit_rpm`, and `expires_at`.
- **User-tier CRUD**: `POST /api/v1/agent-tokens` (mint -- returns
  the full secret ONCE), `GET /api/v1/agent-tokens` (list -- secrets
  redacted), `DELETE /api/v1/agent-tokens/{id}` (revoke).
- **Agent surface (X-Agent-Token-protected, 8 endpoints):**
  - `POST /api/v1/agent/sources` (scope `agent.sources:ingest`)
  - `GET /api/v1/agent/sources/{id}` (scope `agent.sources:read`)
  - `POST /api/v1/agent/query` (scope `agent.query:run`)
  - `POST /api/v1/agent/query/stream` (SSE; scope `agent.query:run`)
  - `POST /api/v1/agent/search` (scope `agent.query:run`)
  - `GET /api/v1/agent/knowledge/{id}` (scope `agent.knowledge:read`)
  - `GET /api/v1/agent/knowledge/{id}/provenance` (scope `agent.knowledge:read`)
  - `POST /api/v1/agent/candidates:propose` (scope `agent.candidates:propose`)
- **Mandatory `Idempotency-Key`** on agent-tier POSTs.
- **New error codes**: `missing_agent_token` (401),
  `invalid_agent_token` (403), `agent_token_expired` (403),
  `agent_workspace_not_in_allowlist` (403), `agent_scope_denied` (403),
  `agent_cannot_mint` (403).

### Security -- tenant lockdown

- **Workspace-scope enforcement on every read-by-id route.** A caller
  who guesses a resource UUID from another workspace in the same
  tenant gets `404 resource_not_found` instead of the foreign row.
  Affects both the user tier and the agent tier (the `/api/v1/agent/*`
  surface). Repositories, handlers, controllers, and CQRS queries
  thread `workspace_id` alongside `tenant_id`.
- **Postgres RLS on every `canon_*` table** (16 tables) -- migration
  `0013_rls_policies`. Defence-in-depth: even if a repository forgets
  a WHERE clause, RLS returns zero rows for the wrong scope. The
  migration is Postgres-only; SQLite is a no-op so unit tests stay
  green. The USING-only policies auto-derive `WITH CHECK`, so
  cross-scope **INSERTs** are also blocked (psycopg raises
  `InsufficientPrivilege` -- stronger than read-only filtering).
  Special-case tables: `canon_workspaces` matches `tenant_id` + `id`,
  `canon_agent_tokens` matches `tenant_id` only (tokens span
  workspaces), and `canon_chunk_vectors` is guarded by a runtime
  `DO`-block `IF EXISTS` check because it's created by `PgvectorStore`
  at boot rather than by Alembic.
- **Session GUC plumbing.** `flycanon.web.conventions.db` exposes
  `set_tenant_guc(session, ctx)` for explicit use, plus
  `install_tenant_guc_hook()` which registers a SQLAlchemy
  `after_begin` listener on the synchronous Session underneath every
  AsyncSession. The hook fires on every `build_engine()` in
  `models/repositories/_engine.py` (idempotent). Transactions opened
  outside a request context (workers, retention sweeps, migration
  runner) skip the GUCs cleanly so cross-workspace access keeps
  working under `BYPASSRLS`.
- **Deployment requirement.** Ops must provision (a) a `flycanon_admin`
  Postgres role with `BYPASSRLS` for migrations and cross-workspace
  workers (consolidation re-embed sweep, retention reaper, EDA
  ingest worker), and (b) a separate `flycanon_app` role **without
  superuser** for the request-path engine. `FORCE ROW LEVEL SECURITY`
  applies to the table OWNER but NOT to Postgres superusers, so a
  superuser-connected service would silently bypass the policy.
  Documented in `docs/architecture.md -> Row-level security`.
- **RLS integration coverage.** New
  `tests/integration/test_rls_isolation.py` boots a real Postgres +
  pgvector via testcontainers, runs migrations as a `BYPASSRLS`
  admin role, then exercises 11 scenarios as a non-bypass `app_user`:
  cross-workspace + cross-tenant reads, unset-GUC zero-rows, the
  `canon_workspaces` / `canon_agent_tokens` special cases, the
  runtime `canon_chunk_vectors` table, write-path INSERT rejection,
  multi-table GUC coherence, `SET LOCAL` transaction scoping, and
  the FORCE-vs-owner contract. Cleanly skipped when Docker is
  unavailable.

### Added -- workspace lifecycle events

- **`canon.workspaces.v1` topic** carries `WorkspaceCreated`,
  `WorkspaceUpdated`, `WorkspaceDeleted` events emitted by
  `workspaces_controller`. Lifecycle mapping: `POST /workspaces` ->
  `WorkspaceCreated`, `PATCH /workspaces/{id}` -> `WorkspaceUpdated`,
  `POST /workspaces/{id}:close` -> `WorkspaceDeleted` (semantic:
  workspace closed, not row deleted -- the row is preserved with
  `status=closed`).
- **`WorkspaceEventPublisher`** routes through the existing pyfly
  `EventPublisher` bean (same transport as the
  `flycanon.audit` / `flycanon.knowledge` / `flycanon.ingest` topics).
  Default backend is the Postgres outbox; flip
  `FLYCANON_EDA_ADAPTER` to `memory` / `redis` / `kafka` to swap.
- **Best-effort consistency.** A failed publish is logged and
  swallowed -- it does NOT roll back the mutation (durable truth is
  the workspace row in Postgres + the parallel
  `canon_audit_events` row). Concurrent mutations may emit events
  out of order; consumers reconcile via the workspace row's
  `updated_at` (last-write-wins). Schema docs:
  [docs/payload-reference.md -> Workspace lifecycle events](docs/payload-reference.md#workspace-lifecycle-events).

### Removed

- **Legacy `flycanon.web.problem_handlers`** -- superseded by
  `flycanon.web.conventions.register_exception_handlers`.
- **Legacy `flycanon.interfaces.dtos.error.ProblemDetails`** (plural)
  -- superseded by `flycanon.web.conventions.ProblemDetail` (singular).
- **Billing actor Query param + actor filter on cost queries** --
  partitioning moves to tenant/workspace.

### Pluggable adapters / external infra

- **Rate-limit + idempotency adapters.** The in-process
  `_TokenBucket` rate limiter and `InMemoryIdempotencyStore` are the
  shipped defaults; the Redis-backed `RedisRateLimiter` and
  `RedisIdempotencyStore` ship in this release as opt-in adapters
  (`FLYCANON_RATE_LIMIT_BACKEND=redis` /
  `FLYCANON_IDEMPOTENCY_BACKEND=redis`, `auto` picks Redis when
  `FLYCANON_REDIS_URL` is set). Exception classes and status codes
  are wire-stable across the swap. See the "Redis-backed adapters"
  block at the top of this release for the implementation details.
- **Workspace event transport.** The publisher rides on pyfly's
  Postgres outbox by default; flip `FLYCANON_EDA_ADAPTER` to
  `memory` / `redis` / `kafka` to swap. Operator chooses the
  transport adapter at deploy time; no code change required.
- **OpenTelemetry tracing export.** Spans are already emitted to
  pyfly's observability stack and W3C `traceparent` /
  `tracestate` headers propagate across the cross-service handoff.
  Export to an external collector (Jaeger / Tempo) is an ops
  choice driven by the `pyfly.tracing` configuration.
- **Read-replica routing.** Single-primary Postgres is the shipped
  topology. The request path stays on the primary; read-replica
  routing is on the platform roadmap, not blocked in code.

### Deliberately excluded by design (spec § 5.2)

These are NOT deferred -- they are rejected agent-tier endpoints.
The user-tier surface remains the only path:

- **Knowledge create/update via agent.** Agent callers must use
  `POST /api/v1/agent/candidates:propose` and let a user-tier
  reviewer accept.
- **Taxonomy / billing / stats agent endpoints.** Out of scope per
  spec section 5.2.

### Roadmap items

- **Embedding cache key.** A forward-looking optimisation; no cache
  exists yet. Tracked on the roadmap.
- **Load + pen-test.** External validation pass ("5k/50k/500k chunks
  across 10/100/1000 tenants" + pen-test RLS gates). Awaiting an
  external validation window.
