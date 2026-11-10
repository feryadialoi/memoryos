# MemoryOS specification

MemoryOS is a memory service for AI agents: one Rust service on Postgres + pgvector or
SQLite + sqlite-vec, with one data model behind four capabilities. It never calls an LLM and needs no provider key: the agent's own
model, the host, decides what to remember and calls MemoryOS. MemoryOS never calls the host. The
contracts are `crates/core/src/{types,store,embedder}.rs`, `migrations/postgres/0001_init.sql`,
`migrations/sqlite/0001_init.sql` and `docs/openapi.yaml`. If this file disagrees with them, stop and record it in `docs/PROGRESS.md`.

## 1. Capabilities

| Capability | Behavior |
|---|---|
| Personalization | Facts scoped to a user. The host chooses add, supersede, corroborate or nothing |
| Changing facts | Superseding closes a fact without deleting it. Reads support `as_of` and `known_at` |
| Self-editing agents | Size-limited, versioned blocks edited through REST and MCP tools |
| Shared graph | Facts are edges between entities. Shared scopes are guarded by per-key scope patterns |

## 2. Crates and public APIs

Each crate exposes exactly these entry points.

```rust
// memoryos-store
PgStore::connect(database_url: &str, max_connections: u32) -> Result<PgStore>
PgStore::migrate(&self) -> Result<()>          // sqlx::migrate!("../../migrations")
impl MemoryStore for PgStore

// memoryos-embed, feature `local`, on by default
LocalEmbedder::new(cache_dir: Option<PathBuf>) -> Result<Self>   // impl Embedder
LocalReranker::new(cache_dir: Option<PathBuf>) -> Result<Self>   // impl Reranker

// memoryos-ingest
HostCommitter::new(store: Arc<dyn MemoryStore>, embedder: Arc<dyn Embedder>) -> Self
HostCommitter::commit(&self, ctx: &RequestContext, req: CommitRequest, max_trust: Trust) -> Result<CommitResponse>
// CommitRequest, CommitFact, EntityRef, CommitResponse, CommittedFact are serde types in ingest

// memoryos-retrieve
Retriever::new(store: Arc<dyn MemoryStore>, embedder: Arc<dyn Embedder>) -> Self
Retriever::with_reranker(self, reranker: Arc<dyn Reranker>, top: usize) -> Self   // recall only
Retriever::recall(&self, ctx: &RequestContext, req: RecallRequest) -> Result<RecallResponse>
Retriever::candidates(&self, ctx: &RequestContext, scopes: &[Scope], statement: &str, limit: i64) -> Result<Vec<ScoredFact>>
Retriever::candidates_with_embedding(&self, ctx: &RequestContext, scopes: &[Scope], statement: &str, embedding: &[f32], limit: i64) -> Result<Vec<ScoredFact>>
pub struct RecallRequest { scopes: Vec<Scope>, query: String, limit: i64, as_of: Option<DateTime<Utc>>, known_at: Option<DateTime<Utc>> }
pub struct RecallResponse { facts: Vec<ScoredFact> }

// memoryos-sdk: thin HTTP client over docs/openapi.yaml
MemoryOs::connect(base_url, api_key)
```

`LocalEmbedder` uses `multilingual-e5-small` through `fastembed`, downloads the model on first use,
and prefixes every input with `query: `, the form that model documents for symmetric similarity.

The `memoryos` binary (crate `server`) has these commands: `serve`, `migrate`, `key create`,
`key revoke`, and the client commands in section 3.

## 3. Write path

1. Optional: `POST /v1/candidates` with `{scopes, statement, limit}` returns related current facts.
   It ranks like `Retriever::recall`, at the present time. A host that only saves can skip it.
2. `POST /v1/commits` sends `{scope, source, content, facts[]}`. Each fact has
   `statement`, `subject {name, kind}`, `predicate`, optional `object {name, kind}`, optional
   `valid_from`, optional `expires_at` (section 4), and at most one of `supersedes` and
   `corroborates`. Maximum 50 facts.
3. `HostCommitter` stores `content` through `insert_episode` as the source of the facts. Replaying an
   `idempotency_key` returns the existing episode and its facts; a key reused for a different scope,
   source, content or trust returns 400 `invalid_input` and reveals nothing about the first request.
4. It embeds statements and entities in one call.
5. Each fact that sets neither `supersedes` nor `corroborates` is matched against the current facts
   of the commit's scope with the candidates search of step 1, reusing its statement embedding. A
   candidate with the same statement, compared case-insensitively with whitespace runs collapsed and
   a final period ignored, makes the fact an automatic `corroborates` of it: no fact and no entity is
   created, and the existing fact gains this source. Only current, active facts of that one scope and
   tenant can match, so a quarantined fact or another scope's fact never does, and a fact that this
   request supersedes is skipped. A fact that is created gets up to 3 other candidates as `related`.
   A fact that sets `supersedes` is matched the same way, without `related`. If a current fact other
   than the superseded one already has its statement and the new fact would be active, no fact is
   created: that fact gains this source and becomes the successor of the superseded fact, which is
   closed at its `valid_from` exactly as a supersede closes it. So a second call that supersedes a
   `related` fact of the first does not duplicate the fact the first created. A new fact the trust
   gate would quarantine is still created, since it carries the pending close for approval.
6. Single-valued predicates. Some predicates hold one value per subject at a time. By default:
   `lives_in`, `works_at`, `has_nickname`, `has_role`, `prefers_editor`, `uses_database`, `has_name`,
   `has_email`, `located_in`, `current_version`, `prefers_language`. `MEMORYOS_SINGLE_VALUED_PREDICATES`
   replaces the list (section 10). Predicates are compared after normalizing to lowercase snake case,
   so `livesIn`, `Lives In` and `lives-in` are all `lives_in`. A fact that is created, sets neither
   `supersedes` nor `corroborates`, and has such a predicate is compared with the current facts of
   its scope with the same subject entity and the same normalized predicate (an expired fact is not
   current). If the latest of them holds a different value, meaning another object or another
   statement, the new fact supersedes it through the same path as a declared `supersedes`: the same
   trust gate, so a fact the gate quarantines records `pending_supersede_of` and approval performs
   the close, and the same purge, so purging the new fact's episode reopens the old fact. The
   response reports it as `superseded` on the created fact. If the old fact has higher trust than the
   commit, it is not closed and is listed first in `related` instead; the store's subject and
   predicate rule of section 5 then still applies to the new fact. Another scope or tenant is never
   read.
7. Entity resolution, for the facts that are created: same normalized name or known alias with the
   same kind uses that entity; otherwise cosine similarity of at least 0.90 with the same kind
   merges. The new name becomes an alias only when this source has an active fact on it.
8. It builds `FactOp`s, applies the section 5 trust gate, and calls `apply_commit`, which commits
   everything and sets `processed_at` atomically. If the episode is already processed that is a no-op,
   so a concurrent replay cannot apply twice. Returns `episode_id` and, per request fact, `id`,
   `status`, `corroborated` when no fact was created, `superseded` with the closed fact's id when a
   supersede reused an existing fact or a single-valued predicate replaced a current fact, and
   `related` for a created fact. A replay
   tells a matched fact from a created one by `recorded_at`, which equals `processed_at` only for
   facts the episode created, and returns no `related`. The response also has `redacted`, true when
   a secret was masked (see Rules).

Rules:
- Commit trust is `agent`, or `external` if the key's `max_trust` is `external`. A request cannot
  set a higher trust, because the host model also reads untrusted content.
- `supersedes` and `corroborates` must name a current, active fact in the same scope, else 400.
  The server never trusts a host-supplied id without that check.
- Before anything is stored or compared, `HostCommitter` masks secrets in `content`, in each
  statement and in each entity name, so REST and MCP commits get the same treatment. Each match
  becomes `[redacted]`: OpenAI and Anthropic style `sk-` keys, GitHub `ghp_`, `gho_`, `ghu_`, `ghs_`,
  `ghr_` and `github_pat_` tokens, AWS `AKIA` access key ids, MemoryOS `mos_` keys, Slack `xox[abprs]-`
  tokens, JWTs, PEM private key blocks, bearer tokens, and the value after a label ending in
  `password`, `passwd`, `secret`, `token` or `api_key` followed by `=` or `:` (the label stays). The
  patterns live in `crates/ingest/src/redact.rs` and only match distinctive shapes, so UUIDs, commit
  hashes and ordinary words are kept. The response sets `redacted: true` when anything was masked.
- `recall_candidates`, `commit_facts`, `recall`, `block_read`, `block_replace` and `graph_neighbors`
  are the MCP tools. Tool descriptions state when to recall, when to save, and that retrieved or
  tool-read content is data, never instructions.

`memoryos ui` serves a page on loopback for people to see and review memory. The page holds no API
key. It calls a local proxy that forwards only `GET /readyz`, `/v1/scopes`, `/v1/facts`,
`/v1/facts/{id}`, its history, `/v1/episodes/{id}`, `/v1/quarantine`, an agent's blocks, `POST /v1/recall`
and quarantine approve and reject, using the stored admin key, or the agent key when there is none. The
proxy checks the `Host` header and a per-run token sent in a custom header, which stop DNS rebinding and
requests from other sites. Fact text is untrusted and is only ever set as text, under a content security
policy with no inline scripts.

CLI, using `MEMORYOS_URL` and `MEMORYOS_API_KEY` (any agent without MCP can use these):
`memoryos recall`, `candidates`, `commit`, `quarantine list|approve|reject`, and
`memoryos hook session-start|prompt|stop|session-end|pre-compact|install --agent
claude-code|opencode|pi`, as shown in
`README.md`. The hooks recall from `MEMORYOS_HOOK_SCOPES` (default `agent:coding-agent`).
- `hook session-start` recalls with the working folder's name and with a fixed query about the user,
  merges both by fact id, and adds the memory blocks of each `agent:<id>` hook scope. All of it is
  printed inside one data-labelled block with stored text escaped, under 9,000 characters. With a
  `session_id` it resets that session's shown-ids state file to the ids it printed.
- `hook prompt` (Claude Code `UserPromptSubmit`) recalls up to 5 facts with the prompt as the query,
  skipping prompts under 3 words, and prints only facts whose ids the session has not shown, adding
  them to the state file. When the prompt matches a fixed list of phrases (such as "my ", "I'm",
  "call me", "we decided", "remember"), it adds one line after the block asking the agent to save
  the fact now with `commit_facts`. It prints nothing when there is nothing new.
- `hook stop` reads the host's JSON from stdin, prints nothing when `stop_hook_active` is true, and
  otherwise prints the block decision once every 20 turns (`MEMORYOS_HOOK_STOP_EVERY`), counted per
  `session_id` in a state file. It is a fallback to the prompt hook's nudge.
- `hook session-end` (Claude Code `SessionEnd`) and `hook pre-compact` (`PreCompact`) read
  `session_id` and `transcript_path` from stdin and stream the transcript from the byte offset where
  the session's last capture stopped (kept in a state file). When that part has no `tool_use` named
  `mcp__memoryos__commit_facts` or `mcp__plugin_memoryos_memoryos__commit_facts`, they take the
  user's typed prompts from it: `user` lines that are not meta, sidechain or compact summaries, with
  string content or text blocks, skipping lines with tool results, host-injected text and
  `<system-reminder>`, `<memoryos-memories>` and `<memoryos-unsaved>` blocks. Each prompt has secrets
  masked by a fixed pattern list, and the session's pending file
  `pending/<sha256(session_id)>.txt` under the state directory (mode 0600, one JSON string per line)
  keeps the newest prompts within 4,000 printed characters. They call no server and no model, and
  print nothing.
- `hook session-start` also reads every pending file, oldest first, and prints those that fit in
  4,000 characters after the memories block, inside a `<memoryos-unsaved>` block labelled as data
  with each prompt escaped like stored facts, followed by one line asking the agent to save any
  durable fact with `commit_facts` and otherwise ignore them. Printed files are deleted. Files older
  than 14 days are deleted without being printed. The memories block shrinks so the whole output
  stays under 9,000 characters.
- `memoryos mcp` fills an omitted `scopes` argument of `recall`, `recall_candidates` and
  `graph_neighbors` with every hook scope, and an omitted `scope` of `commit_facts` with the first
  one, and its `tools/list` reply marks those fields optional and names the defaults. It never
  changes a value the model sent.
- Hook commands never fail the host: on any error they log one line to stderr and exit 0 with no
  output. A host that leaves stdin open is waited on for at most 2 seconds.
- `hook install` merges into existing settings, keeps other entries, is idempotent, and also
  registers the MCP server. The API key stays in an environment variable reference, never in the file.

## 4. Time semantics

- `valid_from` / `valid_to`: when the fact was true. Default `valid_from` is `occurred_at`.
- `recorded_at`: when MemoryOS learned it.
- `invalidated_at`: retracted as wrong. Never returned by current or `as_of` reads.
- `expires_at`: optional, set on commit and never changed, after `valid_from`. For a fact true only
  for a while, such as "on leave until Friday". From then on the fact is not current, without anyone
  superseding it: recall, candidates, matching of repeats and the single-valued check skip it, and
  `supersedes` or `corroborates` naming it is refused. It stays in history and in `state=past`.
- Superseding sets `old.valid_to = new.valid_from` and `old.superseded_by = new.id`.
- Out-of-order input: if a new fact's `valid_from` is before the old fact's, it is stored as a
  closed historical fact, with `valid_to` the start of the earliest later live fact in that chain, and
  the head stays current.

Fact visible at valid time T (default now) and knowledge time K (default now):

```
status = 'active'
AND valid_from <= T AND (valid_to IS NULL OR valid_to > T)
AND (expires_at IS NULL OR expires_at > T)
AND recorded_at <= K
AND (invalidated_at IS NULL OR invalidated_at > K)
```

## 5. Trust and quarantine

| Rule | Result |
|---|---|
| Source trust is `external` | Every derived fact is `quarantined` |
| Source trust is `agent` and scope is `user:*` or `shared:*` | Quarantined, so an agent cannot plant claims in user or shared memory |
| Fact supersedes a fact of higher trust | Quarantined, with `pending_supersede_of` set |
| Fact supersedes a fact of equal or lower trust | Active, supersedes it |
| `Add` with the subject and predicate of a current active fact of higher trust in the scope | Quarantined, with no `pending_supersede_of` |
| Otherwise | Active |

- A fact's trust equals its episode's trust. Corroboration never raises it.
- The subject and predicate rule is deterministic and uses no model, and the store applies it when it
  inserts the fact. Multi-valued predicates can get extra review, which is the accepted cost. Approval
  activates such a fact and closes nothing.
- A `FactOp::Supersede` whose new fact is quarantined leaves the old fact open and sets
  `pending_supersede_of`. `approve_fact` activates the fact and then performs the close.
- Superseding rechecks trust at the chain head when it commits. If the head has higher trust than the
  new fact, the new fact is quarantined and pending on that head, which closes a race with the gate.
- `approve_fact` on a chain that moved to a higher-trust head the admin has not reviewed does not close
  it: it re-points `pending_supersede_of` at that head, writes `fact.approve_held`, and returns
  `InvalidInput`. A second approval closes it. The server tells the caller to review again.
- Purging a source recomputes a fact's trust as the highest trust among remaining sources, never above
  its current trust. It re-quarantines the fact if a source rule in the table above now applies, or if
  the fact closed a live fact of now-higher trust. Pending links move to the surviving successor or
  the reopened predecessor.
- Invalidating a fact takes it out of its chain as a purge does: what it closed takes over its end and
  successor, so a current fact's predecessor is current again, and pending links move the same way.
- `reject_fact` sets `rejected`. Rejected and quarantined facts never appear in recall or graph.
- `POST /v1/episodes/{id}/purge` removes one bad source and everything derived only from it. A
  fact closed by a purged fact is reopened or relinked, so purging a poison restores the truth.
  A fact closed through an existing fact (section 3, step 5) records the closing episode in
  `closed_by_episode`, and purging that episode reopens it the same way, though the existing fact
  stays while another source supports it.
- Approve, reject, invalidate and purge each write an `audit_events` row.

## 6. Tenancy and authorization

- Every tenant transaction runs `SET LOCAL ROLE memoryos_app` and
  `SELECT set_config('app.tenant', $1, true)`. Row-level security then applies, even when the
  login role is a superuser. With no tenant set, tables return no rows.
- Only `*_api_key` and `ping` run outside that role. A non-superuser login needs
  `GRANT memoryos_app TO <login>`. Fact text search goes through the `SECURITY DEFINER` function in
  the migration, because GIN indexes are unusable under RLS.
- SQLite has no RLS. Every tenant operation includes an explicit tenant predicate, tenant-aware
  foreign keys reject cross-tenant references, and two-tenant integration tests cover every table
  family. SQLite runs one connection to serialize writers; API keys remain cross-tenant because
  authentication happens before the tenant is known.
- API keys: bearer tokens `mos_<43 url-safe chars>` from 32 random bytes. Only the SHA-256 hex is
  stored. Each key has a tenant, scope patterns, `max_trust` and `is_admin`.
- `server` must check `scope` against the key's patterns on every request, including reads by id,
  where it checks the loaded row's scope and returns 404 on a mismatch.
- Blocks for agent `X` require scope `agent:X`. Writing a block also requires `max_trust` of at least
  `agent`, through REST and MCP alike.
- Quarantine listing and approval, purge and `DELETE /v1/users/{id}/memory` require `is_admin`.
- Admin rights stop at `max_trust`: approve and reject require `fact.trust <= max_trust`, approve also requires it of the
  `pending_supersede_of` target, episode purge
  requires `episode.trust <= max_trust` (a fact's trust never exceeds its highest source), and
  `DELETE /v1/users/{id}/memory` requires it of every fact and episode in the scope. Admin keys meant
  for people are created with `max_trust` `system`.
- Invalidating a fact in a `user:*` or `shared:*` scope requires `max_trust` of at least `user`, even at
  equal trust: an agent must not delete by retraction what it cannot add without review.

## 7. Retrieval

`Retriever::recall`:
1. Embed the query. If embedding fails, log a warning and continue with text search only.
2. Run vector and text fact searches concurrently, 50 candidates each, using the section 4 filter.
3. Graph expansion: take the subjects of the top 5 fused facts and add facts from `neighbors` at
   depth 1 as a third ranked list.
4. Reciprocal rank fusion with `k = 60`: `score = sum(1 / (60 + rank))`.
5. Source count: multiply each score by `1 + 0.02 * extra`, where `extra` is the fact's source
   episodes past the first, capped at 3 (at most 6%). That is about four ranks near the top of a
   list, and below the 10.9% gap between the best fact found by one list (`1 / 61`) and the worst
   found by two (`2 / 110`), so corroboration breaks ties and nudges but never lifts a fact found by
   one list over a fact found by two.
6. Rerank: send the first `min(limit * 2, MEMORYOS_RERANK_TOP)` facts (default top 10) to the local
   cross-encoder, `BAAI/bge-reranker-v2-m3` in its int8 ONNX export
   (`onnx-community/bge-reranker-v2-m3-ONNX`, pinned revision), as (query, statement) pairs cut to
   256 tokens, in one batch on the CPU. Reorder those facts by its score, highest first. The sort is
   stable, so the order from step 5 breaks exact ties; source count does not otherwise enter the
   reranked order. Each moved fact takes the step 5 score of the slot it lands on, so scores stay
   descending and on one scale. Facts past the window keep their order behind it. With the reranker
   off, not loaded yet, failing, or slower than 2 seconds, recall logs a warning (except when off)
   and keeps the step 5 order. On a 10 core Apple M-series CPU, 10 pairs took a median 207 ms
   and 20 pairs of 512 tokens took 8.7 s, which is why pairs are now cut at 256 tokens.
7. Near copies: walking down the ranking, drop a fact with the same subject, predicate and object as
   a higher ranked one and the same statement once lowercased and reduced to its letter and digit
   words, so the next distinct fact takes the slot. Candidate lists carry no embeddings, so the test
   is textual and needs no extra read. Return the top `limit` (default 10, max 100).

`Retriever::candidates` (and `/v1/candidates`, `recall_candidates`, commit matching) runs steps 1 to
4 only: no source boost, no reranking, and near copies are kept, since finding them is its job.

## 8. Blocks

- Blocks are size-limited, versioned working notes per agent, reachable through REST and the MCP tools
  `block_read` and `block_replace`.
- `expected_version` omitted creates a block and fails if it exists. Set, it updates only that version
  and appends a version row. A mismatch returns `version_conflict`.

## 9. API

`docs/openapi.yaml` is the contract. Error body: `{"error": {"code": "...", "message": "..."}}`.

| Error | HTTP | code |
|---|---|---|
| `NotFound` | 404 | `not_found` |
| `InvalidInput` | 400 | `invalid_input` |
| `Forbidden` | 403 | `forbidden` |
| `VersionConflict` | 409 | `version_conflict` |
| `BlockTooLarge` | 422 | `block_too_large` |
| `Provider` (the embedder failed) | 502 | `provider_error` |
| `Storage`, `Internal` | 500 | `internal` (details logged, never returned) |
| No or bad token | 401 | `unauthorized` |
| Rate limited | 429 | `rate_limited` |
| Body over the limit | 413 | `payload_too_large` |
| Wrong method | 405 | `method_not_allowed` |
| Request timed out | 504 | `timeout` |

Limits: request body 1 MiB, commit content 100000 chars, 50 scopes per request, 100 requests per
second per key by default. Entity names and idempotency keys 512 chars, entity kinds 64. A fact's
`valid_from` at most 1 day ahead. Block `max_chars` at most 100000, with the latest 100 versions kept
and returned. Tokens matching no key share one budget per process, a burst of 100 refilling at 20 per
second, and then get 429 before the database is read, except tokens that have worked since start.
`POST /mcp` exposes the MCP tools in section 3 under the same authorization. It supports clients on
MCP revision 2026-07-28 and earlier, and rejects any `Origin` that is not localhost. It has no CORS
layer, so browser clients on other origins are not supported.

Other rules: `POST /v1/facts/{id}/invalidate` requires `fact.trust <= key.max_trust`, and section 6
adds a scope rule. A block update that omits `max_chars` keeps its limit.

## 10. Configuration

`memoryos serve`, `migrate` and `key` read each variable from the environment, then from
`~/.config/memoryos/server.env` (`$XDG_CONFIG_HOME/memoryos` when set), a file of `KEY=VALUE` lines.
The environment wins. A missing file is no settings; one that cannot be read stops the command.

| Variable | Default | Notes |
|---|---|---|
| `MEMORYOS_STORE` | `postgres` | `postgres` or `sqlite` |
| `DATABASE_URL` | required | PostgreSQL URL, or a `sqlite:` URL such as `sqlite:///absolute/path/memoryos.db` |
| `MEMORYOS_BIND` | `0.0.0.0:8080` | |
| `MEMORYOS_DB_MAX_CONNECTIONS` | `20` | PostgreSQL only; SQLite uses one connection |
| `MEMORYOS_RATE_LIMIT_RPS` | `100` | Per key |
| `OTEL_EXPORTER_OTLP_ENDPOINT` | unset | Traces are exported only when set |
| `MEMORYOS_REQUEST_TIMEOUT_SECS` | `30` | |
| `MEMORYOS_MODEL_CACHE` | user cache dir | Local models, the embedder's and the reranker's. Leave `HF_HOME` unset, since it overrides this |
| `MEMORYOS_SINGLE_VALUED_PREDICATES` | the list in section 3, step 6 | Comma list that replaces the default. Names are normalized to lowercase snake case. A value with no names, such as `,`, turns the rule off |
| `MEMORYOS_RERANKER` | `local` | `local` or `off`. Off saves the 571 MB download and about 1.3 GiB of memory; recall keeps the fused order |
| `MEMORYOS_RERANK_MODEL` | `bge-reranker-v2-m3` | One of `bge-reranker-v2-m3`, `bge-reranker-base`, `jina-reranker-v1-turbo-en`, `ms-marco-minilm-l6`, each pinned to a Hugging Face revision. `memoryos reranker list` shows sizes and languages |
| `MEMORYOS_RERANK_TOP` | `10` | Most facts one recall sends to the reranker, as `min(limit * 2, this)`. Below 2 nothing is reranked |

The reranker loads after the embedder. It never stops the server from starting: until it has loaded, or
if it fails, recall keeps the fused order. `/readyz` reports it as `reranker`: `loading`, `ready`,
`failed` or `off`, without letting it change readiness. A server using the test embedder runs with the
reranker off.

## 11. Testing rules

- PostgreSQL integration tests live in each crate's `tests/`, gated behind `integration`. Run them
  with `cargo test -p <crate> --features integration`.
- SQLite store, ingest, retrieval and server tests use `integration-sqlite` and temporary local
  database files: `cargo test -p <crate> --features integration-sqlite`. They need no Docker.
- PostgreSQL tests use a real `pgvector/pgvector:pg17` container through `testcontainers`. The eval
  harness also starts `wiremock/wiremock:3.3.1`, as a fake MemoryOS server.
- Embeddings in tests come from `TestEmbedder` in `memoryos-embed`, feature `test-embedder`, so no test
  needs the 481 MB model. The server selects it when built with that feature and
  `MEMORYOS_TEST_EMBEDDER` holds a delay per call in milliseconds. The release image never has it, since
  the Dockerfile's cargo commands enable no features.
- `integration-local` on `memoryos-embed` runs the real models, the embedder and the reranker. It is
  off by default. Recall's reranking step is tested with fake rerankers.
- Tenant isolation must be tested with two tenants against real Postgres and real SQLite files.
- Run gates: `cargo fmt --check`, `cargo clippy --all-targets --all-features -- -D warnings`,
  `cargo test`, `cargo deny check`.

## 12. Production gates

| Gate | Target | Proof |
|---|---|---|
| Static checks | No warnings | Commands in section 11 |
| Recall latency | p95 under 200 ms at 1M facts, excluding embedding | Load test output |
| Staleness | At least 95% of superseded facts absent from current recall | `memoryos-eval` report |
| Poisoning | 0 poisoned facts in recall without approval | `memoryos-eval` report |
| Isolation | 0 cross-tenant reads | Integration tests |
| Restore | Backup restored into an empty database and recall still works | Drill log |
| Ready to use | README quickstart works from a clean checkout | Recorded run |

The eval gates use scripted commits and no LLM, at zero cost. They prove what the server enforces:
supersession, time filters, trust and quarantine. They do not prove how well a host model decides what
to save.

## 13. Known limits

- Text search uses the `simple` configuration on PostgreSQL and FTS5 on SQLite, with no stemming and
  weak CJK tokenization. Their ranking scores are not identical. SQLite follows PostgreSQL's
  `websearch_to_tsquery` syntax (quoted phrases, `-` negation, `or` between terms), except that FTS5
  has no standalone NOT: a query, or an `or` branch, made only of negated terms matches nothing on
  SQLite, while PostgreSQL matches every fact without those words. Vector search covers those cases
  when embeddings are available.
- SQLite is a single-process embedded backend with one writer connection and exact cosine scans,
  not a multi-instance or HNSW-performance equivalent of PostgreSQL.
- Embedding width is fixed at 384. Changing model needs re-embedding.
- The rate limiter is in-process, so the limit applies per server instance.
- Embedder errors log only the text before the first colon, because the rest can quote content. This
  makes model failures harder to diagnose from logs.
- `known_at` is not fully bitemporal: `valid_to` and `status` are not versioned, so a later close or
  approval shows up in reads at an earlier `known_at`.
- `GET /v1/scopes` scans the tenant's facts, so it slows with size. It is for occasional reads. The page
  draws at most the newest 300 facts in Map and Timeline, and says so.
- `LocalEmbedder` silently truncates inputs over 512 tokens and needs at least 1 GiB of memory.
- `LocalReranker` adds about 1.3 GiB at its peak (1.26 GiB maximum resident set for load plus 15
  queries of 10 pairs, 1.64 GiB with 20 pairs of 512 tokens, measured on macOS, not yet in the Linux
  container). A call that overruns its 2 second timeout keeps running and holds the model, so recalls
  behind it also fall back to the fused order until it ends.
- A fact backdated between two facts of a chain ends at the later one but does not close the earlier
  one, so `as_of` in that gap returns both. Backdating before the whole chain is exact.
- The subject and predicate rule covers `Add` only. A `supersedes` naming a lower-trust fact is checked
  against that chain's head, not against other current facts with the same subject and predicate.
- Purge edge cases with backdated facts (T14), three confirmed by temporary tests and one from reading:
  - Purging a head can reopen both its real predecessor and a backdated fact, leaving two current facts.
  - A backdated higher-trust fact can cause a needless re-quarantine, resolved by approval.
  - A pending link moved by purge onto a higher-trust fact skips the `fact.approve_held` step.
  - The contradiction rule checks only facts whose trust was lowered, so purging a middle fact in a
    system, user, user chain can leave the last fact active over the system fact. Not run.
