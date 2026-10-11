# Configurability

The exhaustive reference for every configuration key. All settings come from the JSON config
file (see [`config.json`](../config.json) for a complete example) loaded via viper. For a
guided first configuration, start with [Getting started](getting-started.md); for tuning in
production, see the [Operations guide](operations.md).

The config file itself is optional. If nothing exists at the default path (`./config.json`) the
service starts on its built-in defaults and logs a warning naming them — enough to try it, never
what a deployment wants. A `--config_file` you name explicitly must exist: pointing at a
configuration and being given the defaults instead would be worse than failing.

## Every key

Every key the service reads, its default, and where it is documented in full. A default of `—` means
the key is unset unless configured, and the section says what unset does. The table is generated from
the service's own key reads, so a key cannot be added without a row; regenerate it with
`HIPPOCAMPUS_UPDATE_CONFIG_INDEX=1 go test ./cmd/hippocampus -run TestConfigIndex`.

<!-- config-index:begin -->

| Key | Default | What it does | Documented in |
| --- | --- | --- | --- |
| `archive.directory` | — | Archive directory | [Transfer and archive](#transfer-and-archive) |
| `archive.scheduledExport.intervalHours` | — | Scheduled export every (hours) | [Scheduled export](#scheduled-export) |
| `archive.scheduledExport.keep` | `7` | Scheduled exports to keep | [Scheduled export](#scheduled-export) |
| `auth.activeKid` | — | Which of auth.signingKeys --mint-token signs with | [Authentication](#authentication) |
| `auth.audience` | — | Audience | [Authentication](#authentication) |
| `auth.enabled` | — | Deprecated alias for auth.method hmac, consulted only when auth.method is unset | [Authentication](#authentication) |
| `auth.groupsClaim` | `"groups"` | Groups claim | [Group scoping](#group-scoping) |
| `auth.issuer` | — | Issuer | [Authentication](#authentication) |
| `auth.jwksRefreshIntervalSeconds` | `300` | JWKS refresh (seconds) | [Authentication](#authentication) |
| `auth.jwksUrl` | — | JWKS URL | [Authentication](#authentication) |
| `auth.method` | — | Method | [Authentication](#authentication) |
| `auth.oauth2.audience` | — | The console sign-in's audience, when it differs from auth.audience | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.clientId` | — | Confidential client id | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.clientSecret` | — | Client secret | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.cookieDomain` | — | The session cookie's domain, for a console served across subdomains | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.cookieSecure` | — | Force the session cookie's Secure flag, behind a TLS-terminating proxy | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.enabled` | — | Server-side sign-in instead (confidential client) | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.issuer` | — | The console sign-in's issuer, when it differs from auth.issuer | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.postLogoutRedirectUrl` | — | Where the provider returns the browser after sign-out | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.redirectUrl` | — | Redirect URL | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.refreshTTLSeconds` | — | Refresh cookie lifetime | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.scopes` | — | Scopes | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.sessionTTLSeconds` | — | Console session lifetime | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.oauth2.successRedirectUrl` | — | Where a successful sign-in lands | [Server-side sign-in (auth.oauth2)](#server-side-sign-in-authoauth2) |
| `auth.readerRecallReinforces` | — | A reader's recall reinforces the memory | [Authentication](#authentication) |
| `auth.requireGroupScope` | — | Require every token to carry a group scope | [Group scoping](#group-scoping) |
| `auth.revocationFile` | — | Revocation file | [Authentication](#authentication) |
| `auth.revocationRefreshSeconds` | `30` | Revocation reload interval (seconds) | [Authentication](#authentication) |
| `auth.roleClaim` | `"roles"` | Role claim | [Authentication](#authentication) |
| `auth.roleMapping` | — | Role → tier mapping | [Authentication](#authentication) |
| `auth.signingKeys` | — | kid-tagged HMAC secrets, every one of which verifies, for rotation | [Authentication](#authentication) |
| `auth.signingSecret` | — | Signing secret | [Authentication](#authentication) |
| `auth.ui.audience` | — | The console's audience, when it differs from auth.audience | [Authentication](#authentication) |
| `auth.ui.clientId` | — | SPA client id | [Authentication](#authentication) |
| `auth.ui.issuer` | — | The console's issuer, when it differs from auth.issuer | [Authentication](#authentication) |
| `auth.ui.scopes` | — | SPA scopes | [Authentication](#authentication) |
| `bindAddress` | — | gRPC bind address | [gRPC server](#grpc-server) |
| `callbacks.allDeletions` | — | Report every deletion, not just decay | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.atRiskLimit` | `1000` | Warn about at most (memories) | [Being told _before_ a memory goes](#being-told-before-a-memory-goes) |
| `callbacks.atRiskMargin` | `0` | Warn this far above the threshold | [Being told _before_ a memory goes](#being-told-before-a-memory-goes) |
| `callbacks.backlogPolicy` | `"abandon"` | When the caps are reached | [When a forget-callback is an instruction, not a notification](#when-a-forget-callback-is-an-instruction-not-a-notification) |
| `callbacks.batchSize` | `100` | Deliveries one dispatcher pass claims | [Every callbacks key](#every-callbacks-key) |
| `callbacks.enabled` | — | Send callbacks | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.events.eventForgotten` | `true` | Report forgotten events | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.events.memoriesAtRisk` | `false` | Warn before forgetting | [Being told _before_ a memory goes](#being-told-before-a-memory-goes) |
| `callbacks.events.memoryForgotten` | `true` | Report forgotten memories | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.events.memoryWrites` | `false` | Report writes too (memory_stored, memory_updated) | [What a delivery carries](#what-a-delivery-carries) |
| `callbacks.events.sleepCompleted` | `true` | Report finished sleep cycles | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.includeBodies` | — | Include memory bodies | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.maxAgeHours` | `24` | Queue for at most (hours) | [Every callbacks key](#every-callbacks-key) |
| `callbacks.maxBodyBytes` | `65536` | Largest body to carry (bytes) | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.maxBytes` | — | Queue at most (bytes) | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.maxIdsPerDelivery` | `500` | Ids per cycle delivery | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.maxRows` | `1000000` | Queue at most (deliveries) | [When the receiver is down](#when-the-receiver-is-down) |
| `callbacks.retryBaseBackoffSeconds` | `1` | Base of a failing delivery's retry backoff | [Every callbacks key](#every-callbacks-key) |
| `callbacks.retryMaxBackoffSeconds` | `300` | Ceiling of a failing delivery's retry backoff | [Every callbacks key](#every-callbacks-key) |
| `callbacks.signingSecret` | — | Signing secret | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.timeoutSeconds` | `10` | Delivery timeout (seconds) | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.tls.caCertFile` | — | CA certificate file | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.tls.certFile` | — | Client certificate for mutual TLS to the receiver | [Every callbacks key](#every-callbacks-key) |
| `callbacks.tls.enabled` | — | Customise TLS for the receiver | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.tls.insecureSkipVerify` | — | Skip verifying the receiver's certificate (dev only) | [Every callbacks key](#every-callbacks-key) |
| `callbacks.tls.keyFile` | — | Its key | [Every callbacks key](#every-callbacks-key) |
| `callbacks.token` | — | Bearer token | [Outbound callbacks](#outbound-callbacks) |
| `callbacks.url` | — | Receiver URL | [Outbound callbacks](#outbound-callbacks) |
| `consolidation.aggressiveness` | `1` | Aggressiveness (a) | [consolidation: Consolidation algorithms](consolidation.md#consolidation-algorithms) |
| `consolidation.capacityBytes` | — | Capacity (bytes) | [consolidation: Capacity target](consolidation.md#capacity-target) |
| `consolidation.capacityBytesFloor` | — | Eviction floor (bytes) | [consolidation: Capacity target](consolidation.md#capacity-target) |
| `consolidation.capacityExternalBytes` | — | External capacity (bytes) | [External bytes](#external-bytes) |
| `consolidation.capacityExternalBytesFloor` | — | External eviction floor (bytes) | [External bytes](#external-bytes) |
| `consolidation.capacityMemories` | — | Capacity (memories) | [consolidation: Forgetting modes](consolidation.md#forgetting-modes) |
| `consolidation.capacityPressureExponent` | — | Pressure exponent | [consolidation: Recall and capacity pressure](consolidation.md#recall-and-capacity-pressure) |
| `consolidation.defaultEventSignificancePercentile` | — | …or a percentile of existing events | [consolidation: Percentile](consolidation.md#percentile) |
| `consolidation.defaultEventSignificanceValue` | — | Default event significance | [consolidation: Percentile](consolidation.md#percentile) |
| `consolidation.deletionThreshold` | `10` | Deletion threshold | [consolidation: Consolidation algorithms](consolidation.md#consolidation-algorithms) |
| `consolidation.enabled` | `true` | This instance consolidates (runs the sleep cycle) | [consolidation: Memory consolidation](consolidation.md#memory-consolidation) |
| `consolidation.linkRecallPropagation` | — | Spreading activation on recall | [consolidation: Spreading activation](consolidation.md#spreading-activation) |
| `consolidation.linkSignificanceWeight` | — | Link significance weight | [consolidation: Links](consolidation.md#links) |
| `consolidation.maximumRetentionInDays` | — | Maximum retention ceiling (days) | [consolidation: Maximum retention](consolidation.md#maximum-retention) |
| `consolidation.method` | `1` | Algorithm | [consolidation: Consolidation algorithms](consolidation.md#consolidation-algorithms) |
| `consolidation.minimumAgeInDays` | — | Minimum age before consolidation (days) | [consolidation: Consolidation algorithms](consolidation.md#consolidation-algorithms) |
| `consolidation.minimumRetentionInDays` | — | Hard retention floor (days) | [consolidation: Minimum retention](consolidation.md#minimum-retention) |
| `consolidation.recallSignificanceWeight` | — | Recall significance weight | [consolidation: Recall and capacity pressure](consolidation.md#recall-and-capacity-pressure) |
| `consolidation.significanceLevels.unusedRetentionInDays` | `7` | How long the significance registry keeps a value nothing carries | [api: The registry forgets too](api.md#the-registry-forgets-too) |
| `consolidation.standby` | — | Take over if the consolidator goes (standby) | [Server drivers](#server-drivers) |
| `consolidation.standbyPollSeconds` | — | Standby poll (seconds) | [Server drivers](#server-drivers) |
| `consolidation.summarisationMaxCandidates` | — | Maximum candidates cached | [consolidation: Summarisation](consolidation.md#summarisation) |
| `consolidation.summarisationMinAgeInDays` | — | Quiet for at least (days) | [consolidation: Summarisation](consolidation.md#summarisation) |
| `consolidation.summarisationMinMemories` | — | Minimum memories per event | [consolidation: Summarisation](consolidation.md#summarisation) |
| `consolidation.tombstones.enabled` | — | Record what is forgotten | [operations: What was forgotten — the forgotten log](operations.md#what-was-forgotten--the-forgotten-log) |
| `consolidation.tombstones.maxAgeInDays` | `30` | Keep for at most (days) | [operations: What was forgotten — the forgotten log](operations.md#what-was-forgotten--the-forgotten-log) |
| `consolidation.tombstones.maxBytes` | — | Keep at most (bytes) | [operations: What was forgotten — the forgotten log](operations.md#what-was-forgotten--the-forgotten-log) |
| `consolidation.tombstones.maxRows` | `100000` | Keep at most (records) | [operations: What was forgotten — the forgotten log](operations.md#what-was-forgotten--the-forgotten-log) |
| `consolidation.unitsOfAgeInDays` | `1` | Days per age unit | [consolidation: Consolidation algorithms](consolidation.md#consolidation-algorithms) |
| `consolidation.walTriggerBytes` | — | WAL trigger (bytes) | [consolidation: Checkpoint-triggered eviction](consolidation.md#checkpoint-triggered-eviction) |
| `event.minimumSignificance` | — | Minimum event significance accepted | [Minimum significance](#minimum-significance) |
| `gateway.bindAddress` | — | Gateway bind address | [gRPC server](#grpc-server) |
| `gateway.corsOrigins` | — | Allowed browser origins (CORS) | [Cross-origin requests (CORS)](#cross-origin-requests-cors) |
| `gateway.maxRequestBytes` | — | Max HTTP request body (bytes) | [HTTP gateway](#http-gateway) |
| `gateway.openapi.enabled` | `true` | Serve the OpenAPI description | [HTTP gateway](#http-gateway) |
| `gateway.port` | — | HTTP/JSON gateway port | [HTTP gateway](#http-gateway) |
| `keepalive.minTimeSeconds` | — | Keepalive minimum interval (seconds) | [gRPC server](#grpc-server) |
| `keepalive.permitWithoutStream` | — | Permit keepalive pings on idle connections | [gRPC server](#grpc-server) |
| `listing.countCacheSeconds` | `5` | Listing total cache (seconds) | [Listing totals](#listing-totals) |
| `llm.address` | `"http://localhost:11434"` | Ollama address | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.apiKey` | — | API key | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.autoSummarise` | — | Summarise candidates automatically each sleep cycle | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.embedding.address` | `"http://localhost:11434"` | Model server address | [Semantic search](#semantic-search) |
| `llm.embedding.apiKey` | — | API key | [Semantic search](#semantic-search) |
| `llm.embedding.batchSize` | `32` | Batch size | [Semantic search](#semantic-search) |
| `llm.embedding.dimensions` | `768` | Vector dimensions | [Semantic search](#semantic-search) |
| `llm.embedding.enabled` | — | Enable semantic search | [Semantic search](#semantic-search) |
| `llm.embedding.maxTextBytes` | — | Maximum text embedded (bytes) | [Semantic search](#semantic-search) |
| `llm.embedding.model` | `"nomic-embed-text"` | Embedding model | [Semantic search](#semantic-search) |
| `llm.embedding.provider` | `"ollama"` | Provider | [Semantic search](#semantic-search) |
| `llm.embedding.timeoutSeconds` | `30` | Timeout (seconds) | [Semantic search](#semantic-search) |
| `llm.enabled` | — | Enable the embedded LLM | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.maxMemories` | — | Maximum memories per prompt | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.model` | `"llama3.2"` | Model | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.promptCharLimit` | — | Prompt character limit | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.provider` | `"ollama"` | Provider | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.systemPrompt` | — | System prompt | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.temperature` | — | Temperature | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `llm.timeoutSeconds` | `120` | Generation timeout (seconds) | [Summarisation (embedded LLM)](#summarisation-embedded-llm) |
| `logging.json` | — | Structured JSON logs | [Logging](#logging) |
| `logging.level` | — | Log level | [Logging](#logging) |
| `maxConcurrentStreams` | — | Max concurrent streams | [gRPC server](#grpc-server) |
| `maxRecvMsgBytes` | — | Max gRPC receive size (bytes) | [gRPC server](#grpc-server) |
| `memory.limit.sizeBytes` | — | Maximum memory body (bytes) | [Memory size limit](#memory-size-limit) |
| `memory.minimumSignificance` | — | Minimum memory significance accepted | [Minimum significance](#minimum-significance) |
| `observability.metrics.enabled` | — | Enable metrics | [Observability](#observability) |
| `observability.metrics.exportIntervalSeconds` | — | Metrics export interval (seconds) | [Observability](#observability) |
| `observability.otlp.endpoint` | — | OTLP endpoint | [Observability](#observability) |
| `observability.otlp.insecure` | — | Plaintext to the collector | [Observability](#observability) |
| `observability.prometheus.bindAddress` | — | Metrics bind address | [Observability](#observability) |
| `observability.prometheus.enabled` | — | Serve /metrics for scraping | [Observability](#observability) |
| `observability.prometheus.path` | `"/metrics"` | Metrics path | [Observability](#observability) |
| `observability.prometheus.port` | `9464` | Metrics port | [Observability](#observability) |
| `observability.serviceName` | — | Service name | [Observability](#observability) |
| `observability.tracing.enabled` | — | Enable tracing | [Observability](#observability) |
| `observability.tracing.samplingRatio` | — | Sampling ratio | [Observability](#observability) |
| `opensearch.addresses` | — | Cluster addresses | [OpenSearch](#opensearch) |
| `opensearch.applyMaxAttempts` | — | Attempts at one index operation before it is dropped | [OpenSearch](#opensearch) |
| `opensearch.applyRetryBaseBackoffMillis` | — | Base of the index worker's jittered retry backoff | [OpenSearch](#opensearch) |
| `opensearch.applyTimeoutSeconds` | — | Bound on one index operation before it is retried | [OpenSearch](#opensearch) |
| `opensearch.closeDrainTimeoutSeconds` | — | How long shutdown waits for the index queue to drain | [OpenSearch](#opensearch) |
| `opensearch.enabled` | — | Enable OpenSearch | [OpenSearch](#opensearch) |
| `opensearch.index` | `"hippocampus-memories"` | Index name | [OpenSearch](#opensearch) |
| `opensearch.outbox.maxAgeHours` | `24` | Age cap on the queued index deletions | [OpenSearch](#opensearch) |
| `opensearch.outbox.maxBytes` | — | Byte cap on the queued index deletions | [The delete outbox](#the-delete-outbox) |
| `opensearch.outbox.maxRows` | `1000000` | Row cap on the queued index deletions | [OpenSearch](#opensearch) |
| `opensearch.password` | — | Password | [OpenSearch](#opensearch) |
| `opensearch.queueSize` | `1024` | Propagation queue size | [OpenSearch](#opensearch) |
| `opensearch.reconcileBatchSize` | `500` | Page size of the self-healing reconcile sweep | [OpenSearch](#opensearch) |
| `opensearch.reconcileIntervalSeconds` | `3600` | Reconciliation sweep (seconds) | [OpenSearch](#opensearch) |
| `opensearch.staleSweep` | `true` | Also remove index documents the store no longer holds | [OpenSearch](#opensearch) |
| `opensearch.tls.caCertFile` | — | CA certificate file | [OpenSearch](#opensearch) |
| `opensearch.tls.certFile` | — | Client certificate file | [OpenSearch](#opensearch) |
| `opensearch.tls.insecureSkipVerify` | — | Skip verifying the cluster's certificate (dev only) | [OpenSearch](#opensearch) |
| `opensearch.tls.keyFile` | — | Client key file | [OpenSearch](#opensearch) |
| `opensearch.username` | — | Username | [OpenSearch](#opensearch) |
| `rateLimit.clientIdleSeconds` | — | Caller idle window (seconds) | [Rate limiting](#rate-limiting) |
| `rateLimit.enabled` | — | Enable rate limiting | [Rate limiting](#rate-limiting) |
| `rateLimit.global.burst` | — | Instance-wide burst | [Rate limiting](#rate-limiting) |
| `rateLimit.global.requestsPerSecond` | — | Instance-wide sustained request rate | [Rate limiting](#rate-limiting) |
| `rateLimit.maxClients` | — | Tracked callers | [Rate limiting](#rate-limiting) |
| `rateLimit.perClient.burst` | — | Per-caller burst | [Rate limiting](#rate-limiting) |
| `rateLimit.perClient.requestsPerSecond` | — | Per-caller sustained request rate | [Rate limiting](#rate-limiting) |
| `rateLimit.tiers.<tier>.burst` | — | Burst for callers resolving to this tier | [Rate limiting](#rate-limiting) |
| `rateLimit.tiers.<tier>.requestsPerSecond` | — | Sustained rate for callers resolving to this tier (reader, writer, admin) | [Rate limiting](#rate-limiting) |
| `rateLimit.trustForwardedFor` | — | Trust X-Forwarded-For | [Rate limiting](#rate-limiting) |
| `readiness.cacheSeconds` | — | Readiness cache (seconds) | [Health and readiness](#health-and-readiness) |
| `readiness.pingTimeoutSeconds` | — | Readiness ping timeout (seconds) | [Health and readiness](#health-and-readiness) |
| `reflection.enabled` | — | Register gRPC server reflection; derived from auth.method when unset | [Server reflection](#server-reflection) |
| `s3.bucket` | — | The S3 bucket archives are written to; set this or archive.directory, not both | [Transfer and archive](#transfer-and-archive) |
| `s3.endpoint` | — | Endpoint | [Transfer and archive](#transfer-and-archive) |
| `s3.keyPrefix` | — | Key prefix | [Transfer and archive](#transfer-and-archive) |
| `s3.region` | — | Region | [Transfer and archive](#transfer-and-archive) |
| `s3.usePathStyle` | — | Path-style addressing | [Transfer and archive](#transfer-and-archive) |
| `search.contentIndex.enabled` | — | Keep the store's own content index | [Turning the store index off](#turning-the-store-index-off) |
| `search.recallWeight` | `0.2` | Recall weight | [Ranking](#ranking) |
| `search.significanceWeight` | `0.3` | Significance weight | [Ranking](#ranking) |
| `shutdown.timeoutSeconds` | `10` | Shutdown timeout (seconds) | [operations: Graceful shutdown](operations.md#graceful-shutdown) |
| `sleep.periodSeconds` | `3600` | Sleep cycle period (seconds) | [consolidation: Memory consolidation](consolidation.md#memory-consolidation) |
| `stats.intervalSeconds` | `300` | Stats interval (seconds) | [Stats](#stats) |
| `storage.compression.enabled` | `true` | Compress memory bodies | [Storage](#storage) |
| `storage.compression.minBytes` | `512` | Minimum body size (bytes) | [Storage](#storage) |
| `storage.directory` | `"./data"` | Data directory | [Storage](#storage) |
| `storage.driver` | `"sqlite"` | Driver | [Storage](#storage) |
| `storage.mysql.dsn` | — | MySQL DSN | [Storage](#storage) |
| `storage.pool.maxIdleConns` | — | Max idle connections | [Storage](#storage) |
| `storage.pool.maxOpenConns` | `25` | Max open connections | [Storage](#storage) |
| `storage.postgres.dsn` | — | PostgreSQL DSN | [Storage](#storage) |
| `storage.queryTimeoutSeconds` | `60` | Query timeout (seconds) | [Storage](#storage) |
| `tls.certFile` | — | Certificate file | [TLS](#tls) |
| `tls.clientCaFile` | — | Client CA bundle (mutual TLS) | [TLS](#tls) |
| `tls.enabled` | — | Serve TLS on both transports | [TLS](#tls) |
| `tls.keyFile` | — | Private key file | [TLS](#tls) |
| `tls.requireClientCert` | — | Require a client certificate | [TLS](#tls) |
| `topology.components` | — | Declared inbound components, each a name, kind and healthUrl | [Deployment topology](#deployment-topology) |
| `topology.enabled` | `true` | Enable the topology view | [Deployment topology](#deployment-topology) |
| `topology.heartbeatSeconds` | `30` | Peer heartbeat (seconds) | [Deployment topology](#deployment-topology) |
| `topology.minimumTier` | `"reader"` | Minimum tier | [Deployment topology](#deployment-topology) |
| `topology.probeIntervalSeconds` | `30` | Probe interval (seconds) | [Deployment topology](#deployment-topology) |
| `topology.probeTimeoutSeconds` | `2` | Probe timeout (seconds) | [Deployment topology](#deployment-topology) |
| `topology.probeTransferTarget` | — | Probe the transfer target | [Deployment topology](#deployment-topology) |
| `transfer.batchSize` | — | Records per batch | [Transfer and archive](#transfer-and-archive) |
| `transfer.maxBatchBytes` | — | Maximum batch bytes | [Transfer and archive](#transfer-and-archive) |
| `transfer.maxManifestRows` | — | Maximum manifest rows | [Transfer and archive](#transfer-and-archive) |
| `transfer.targetAddress` | — | Target address | [Transfer and archive](#transfer-and-archive) |
| `transfer.tls.caCertFile` | — | Target CA certificate | [Transfer and archive](#transfer-and-archive) |
| `transfer.tls.certFile` | — | Client certificate for mutual TLS to the transfer target | [Transfer and archive](#transfer-and-archive) |
| `transfer.tls.enabled` | — | TLS to the target | [Transfer and archive](#transfer-and-archive) |
| `transfer.tls.insecureSkipVerify` | — | Skip verifying the transfer target's certificate (dev only) | [Transfer and archive](#transfer-and-archive) |
| `transfer.tls.keyFile` | — | Its key | [Transfer and archive](#transfer-and-archive) |
| `transfer.token` | — | Bearer token for the target | [Transfer and archive](#transfer-and-archive) |

<!-- config-index:end -->

## Environment variable overrides

Any config key can be overridden by an environment variable named `HIPPOCAMPUS_<KEY>` with the
key's dots replaced by underscores and uppercased — so `auth.signingSecret` becomes
`HIPPOCAMPUS_AUTH_SIGNINGSECRET`, `storage.postgres.dsn` becomes `HIPPOCAMPUS_STORAGE_POSTGRES_DSN`,
`opensearch.password` becomes `HIPPOCAMPUS_OPENSEARCH_PASSWORD`, and `transfer.token` becomes
`HIPPOCAMPUS_TRANSFER_TOKEN`. This is the recommended way to supply secrets — inject them as
Docker/Kubernetes secrets rather than committing or baking them into `config.json`. Precedence is
**command-line flag > environment variable > config file > built-in default**, so an env var
overrides the file but an explicit flag still wins.

## Operational

### Logging

Logging is written to stdout via [logrus](https://github.com/sirupsen/logrus).

```json
"logging": {
    "level": "info",
    "json": false
}
```

- `logging.level` — the minimum severity emitted. One of `trace`, `debug`, `info`, `warn`,
  `error`, `fatal`, `panic` (case-insensitive; the first letter and a few aliases such as
  `verbose`→`debug` and `information`→`info` also work). Any unset or unrecognised value falls back
  to `info`. The service logs its effective level at startup. Most per-function entry/exit lines are
  at `trace`; a failing RPC is logged at `warn` (`info` for client-fault codes), so the default
  `info` level surfaces failures without the per-call noise.
- `logging.json` — when `true`, emit structured JSON (one object per line) instead of the default
  human-readable text formatter. Use JSON when shipping logs to a collector that parses fields
  (Loki, Elasticsearch, CloudWatch); leave it `false` for local development.

### Observability

OpenTelemetry tracing and metrics are optional and independently enabled through the
`observability` section of the configuration file. Both export over OTLP/gRPC.

```json
"observability": {
    "serviceName": "hippocampus",
    "tracing": {
        "enabled": false,
        "samplingRatio": 1.0
    },
    "metrics": {
        "enabled": false,
        "exportIntervalSeconds": 60
    },
    "otlp": {
        "endpoint": "localhost:4317",
        "insecure": true
    },
    "prometheus": {
        "enabled": false,
        "port": 9464,
        "bindAddress": "",
        "path": "/metrics"
    }
}
```

- `serviceName` — how this instance names itself in the telemetry (the semconv `service.name`
  resource attribute). Empty falls back to `hippocampus`, which is what every release before this
  key reported, so an existing configuration is unchanged.

  **Give every instance that shares a collector its own name.** The OTLP-to-Prometheus translation
  promotes only `service.name`, `service.version`, `job` and `instance` onto each series and puts
  every other resource attribute in `target_info`, so instances sharing a name publish *one* series
  per instrument between them: the value a dashboard or an alert rule reads is whichever instance
  exported last, flapping between them at the export interval. That makes the shipped rules in
  [`deploy/observability/`](../deploy/observability/README.md) unable to say which instance is at
  fault, and a per-store gauge such as `hippocampus_memories_count` meaningless. It matters most in
  exactly the topology this project documents as its scaling model — a consolidator plus N replicas
  over one Postgres (see [Horizontal scaling](operations.md#horizontal-scaling-with-replicas)) —
  and in any host running several independent stores against one collector.

- `tracing.samplingRatio` — the fraction of traces to sample (0.0–1.0). The sampler is
  parent-based, so sampling decisions propagated by callers are honoured; the ratio applies to
  traces started locally (each RPC without an incoming trace context, and each sleep cycle).
- `metrics.exportIntervalSeconds` — how often metrics are exported; 0 uses the SDK default.
- `otlp.endpoint` — the OTLP/gRPC collector endpoint. When empty, the standard
  `OTEL_EXPORTER_OTLP_*` environment variables apply, falling back to `localhost:4317`.
- `otlp.insecure` — use plaintext instead of TLS when connecting to the collector.

#### Prometheus scrape endpoint

`observability.prometheus.enabled` serves the same metrics in the Prometheus text format, for a
Prometheus to **pull**, instead of (or as well as) pushing them over OTLP. It is a second metric
reader on the same meter provider, not a second instrumentation path: every instrument, attribute
and alert expression is identical either way, and the series names are the ones the
OTLP-to-Prometheus translation produces — which is what the rule files under
[`deploy/observability/`](../deploy/observability/README.md) are written against.

It exists because the two are different collection models rather than two encodings of one setting.
A deployment with an OpenTelemetry collector pushes; a cluster running kube-prometheus-stack — the
overwhelmingly common cluster observability stack — scrapes, and without this would have to run a
collector purely as a protocol adapter in front of the service. Enabling both is a legitimate
migration state.

- `prometheus.enabled` — off by default. It works with `metrics.enabled` off, so a scrape-only
  deployment need not name a collector it does not have.
- `prometheus.port` — the listener's own port, **9464** by default (the conventional port for the
  OpenTelemetry Prometheus exporter). It must differ from `port` and `gateway.port`; the service
  refuses a collision at startup rather than letting whichever listener binds second fail.
- `prometheus.bindAddress` — empty binds every interface. This is the setting that makes the
  endpoint safe to enable: a scrape endpoint enumerates every instrument the process publishes —
  store size, capacity pressure, RPC rates — so on an instance reachable from outside, bind it to
  the interface the scraper is on.
- `prometheus.path` — `/metrics` by default.

The endpoint is deliberately **not** on the gateway. The gateway is the public surface, frequently
what an ingress exposes; a scrape endpoint there would be an information disclosure available to
every API caller, and putting it behind a token instead would put it out of reach of most scrapers.
A separate, separately bindable port is what lets it be open to the scraper and closed to everybody
else. It also keeps scrapes out of the `hippocampus.rpc.*` request rate, the same exclusion the
probes and the console assets already have.

The client-side daemons — the [event-source bridges](eventsource.md) and the
[ingestor](ingestor.md) — take the same option as a `--prometheus` flag, and serve it at `/metrics`
on the `--health-port` they already listen on rather than on a port of their own. Turning
`--health-port 0` off takes the metrics with it, which is logged.

Every RPC is traced (via the `otelgrpc` stats handler, which also records the standard
low-cardinality RPC metrics), and each sleep cycle produces its own trace with span events
marking the consolidation passes. Domain metrics cover stored/rejected/recalled/deleted
counts for memories and events, consolidation deletions, capacity evictions (row counts and the
estimated bytes reclaimed), a histogram of stored memory-body sizes, sleep cycle count
and duration, capacity pressure, the store's used bytes, gauges of the current event and
memory counts, the number of summarisation candidates found by the most recent sleep cycle, and
memories/summaries created via `ReplaceMemoriesWithSummary`. All metric attributes are bounded
(booleans or small enumerations) to keep cardinality low.

To view any of this locally without standing up a collector, every compose stack carries an
optional all-in-one `grafana/otel-lgtm` backend behind a compose `observability` profile:
`OBSERVABILITY=true docker compose --profile observability up` brings up Grafana on
`http://localhost:3000` and ships to it; the demo soak harness has the same switch
(`OBSERVABILITY=1 ./demo/run.sh`). Both are off by default, so a stack run without the profile
never attempts an export. See [Observability](operations.md#observability) in the operations guide.

#### Stats

The event/memory count gauges and the periodic stats log line share one cached count reading rather
than each running a full-table `COUNT`. `stats.intervalSeconds` (default **300**) sets both how
often the stats line is logged and the maximum age of that cached reading, so the underlying counts
run at most once per interval no matter how often metrics are exported. Set it to `0` to disable the
log line (the gauges still serve a cached count).

```json
"stats": {
    "intervalSeconds": 300
}
```

### HTTP gateway

Every RPC is also reachable as a JSON/HTTP endpoint, for clients that would rather not speak
gRPC. The gateway is **off unless a port is configured**; set `gateway.port` to enable an in-process
[grpc-gateway](https://github.com/grpc-ecosystem/grpc-gateway) reverse proxy (0 disables it).
**8080** is the conventional port, and every configuration in this repository — the root
`config.json`, the Docker and Kubernetes ones, the demo — uses it. Disabling it removes the web
console, the OpenAPI document, and the HTTP health probes along with the JSON API, so the service
logs a line at startup naming what is off when the port is 0. The gateway
calls straight into the same server instance gRPC uses, so there is no extra network hop, dial, or
serialisation round trip between the two. An OpenAPI/Swagger description of the mapping below is
served at `/v1/openapi.json` — see [Clients in other languages](clients.md) for generating a client
from it, or from the proto.

```json
"gateway": {
    "port": 8080,
    "maxRequestBytes": 8388608,
    "openapi": {
        "enabled": true
    },
    "corsOrigins": []
}
```

`gateway.maxRequestBytes` caps the size of a request body the gateway will read. A larger body is
answered `413` before a handler buffers it: at once when the body declares its length, and as soon
as the read overflows when it is chunked. **Left unset, it is derived** from the gRPC transport's
own limit: twice `maxRecvMsgBytes`, or twice grpc-go's 4 MiB (8 MiB) when that is 0. That way a
request is bounded on both transports. The cap is doubled because JSON carries every field name on
every record, so it runs larger than the protobuf encoding of the same request. Set it explicitly to
choose another ceiling, or to **0 for unbounded**, which was the previous default. Raise
`maxRecvMsgBytes` to raise both limits together. The gateway also bounds how long reading a whole
request may take (two minutes, beyond the 10-second header deadline), so a caller cannot hold a
connection open by trickling a body. TLS pins a **TLS 1.2 floor** on both listeners (see
[TLS](#tls)).

The JSON/HTTP mapping of every RPC - the route table, the filter semantics and the listing
behaviour - is in the [API reference](api.md).

#### The OpenAPI document

`gateway.openapi.enabled` (default **true**) serves the generated description of the mapping below
at `/v1/openapi.json`. Set it to `false` to serve nothing at that path; a client then generates from
`contract/hippocampus.proto`, or from a descriptor set built from it.

**It is served without a token, even when authentication is on.** That is deliberate, and it
reverses earlier behaviour. The document is generated from a proto published with the source, so
requiring a token to read it protected a file anybody can fetch from the repository — while breaking
every standard OpenAPI tool, none of which can authenticate the _initial_ spec fetch. Schema
confidentiality was never the property being defended; if you want nothing served there, the honest
request is the key above rather than an authentication check that stops only well-behaved clients.

Two consequences worth knowing. The response carries an `ETag` over the embedded document, so a
repeat fetch from a client that sends `If-None-Match` costs a `304` rather than ~150 KB. And unlike
the health probes and the console, the document **is** covered by the arrival
[rate limit](#rate-limiting): it needs no credentials and is the largest single response the gateway
produces, so it would otherwise be the cheapest bandwidth amplifier on the surface.

#### Cross-origin requests (CORS)

`gateway.corsOrigins` lists the browser origins permitted to call `/v1` from a page this gateway did
not serve. It is **empty by default**, which sends no CORS headers at all — so only pages served by
this gateway (the console) can call the API, exactly as before the key existed.

```json
"gateway": {
    "corsOrigins": ["http://localhost:8082"]
}
```

Each entry is an exact origin — `scheme://host[:port]`, `http` or `https`, with no path, query, or
trailing slash. A trailing slash never matches the `Origin` header a browser sends, so it is
rejected at startup rather than presenting as CORS mysteriously not working. `*` is **refused**: a
browser already declines to combine it with credentials, but this gateway fronts `Purge`, and
reaching for a wildcard is rarely the decision it actually represents. Name the origins.

`Access-Control-Allow-Credentials` is never sent. That is what keeps the console's `HttpOnly`
session cookie unusable from another origin — a browser will not attach it to a cross-origin request
without that header — so enabling this cannot turn a signed-in console session into ambient
authority for a hostile page. Bearer tokens still work, because a caller sends those explicitly.

Preflights are answered before authentication, rate limiting, and metrics: a preflight carries no
`Authorization` header by construction, and counting `OPTIONS` requests as RPCs would distort the
very rates the shipped alert rules read. The environment override splits on commas or whitespace,
so `HIPPOCAMPUS_GATEWAY_CORSORIGINS="http://a:8082,http://b:9000"` behaves the way it looks.

The main use is a browser API explorer you host separately — see
[Clients in other languages](clients.md) for the Swagger UI recipe.

### gRPC server

The gRPC server port is `port` (default **50051**). Both ports can be set on the command line —
`--port` and `--gateway-port` — which takes precedence over the config file:

```sh
hippocampus -c config.json --gateway-port 8080   # enable the gateway on the conventional port
hippocampus -c config.json --port 40000          # gRPC on a custom port; gateway stays off
```

Both listeners bind all interfaces by default. `bindAddress` (gRPC) and `gateway.bindAddress`
(HTTP) restrict the interface each binds to — set them to `127.0.0.1` to accept only loopback
traffic, e.g. behind a sidecar/mesh that terminates TLS and forwards over the loopback. Empty (the
default) preserves the all-interfaces behaviour.

To run several independent instances on one host, give each its own `port`, `gateway.port`, and
`storage.directory`/DSN — the defaults collide and the second to start fails to bind. See
[Running more than one instance on one host](operations.md#running-more-than-one-instance-on-one-host).

```json
"bindAddress": "",
"maxConcurrentStreams": 0,
"maxRecvMsgBytes": 0,
"keepalive": {
    "minTimeSeconds": 0,
    "permitWithoutStream": false
}
```

The gRPC transport has a few hardening knobs, all defaulting to grpc-go's own defaults when
unset — tolerable for trusted callers, worth setting if the gRPC port is exposed further.
`maxConcurrentStreams` caps the concurrent HTTP/2 streams one connection may open (0 keeps the
default). `keepalive.minTimeSeconds` is the minimum interval the server tolerates between a
client's keepalive pings before it terminates the connection (0 leaves grpc-go's policy), and
`keepalive.permitWithoutStream` allows those pings on an idle connection. `maxRecvMsgBytes`
(0 → grpc-go's 4 MiB default) raises the maximum receive-message size for larger
`ImportBatch`/single-memory payloads.

### Server reflection

gRPC [server reflection](https://grpc.io/docs/guides/reflection/) lets `grpcurl`, Postman, Insomnia
and every gRPC GUI discover the schema from a running instance rather than being handed
`contract/hippocampus.proto`. It is the gRPC counterpart of the gateway's `/v1/openapi.json`.

```json
"reflection": {
    "enabled": true
}
```

**The default is derived rather than fixed** — but not for the reason it once claimed. Earlier
versions of this section argued that reflection publishes the schema, and defaulted it off under
authentication on that basis. That argument does not hold here: `contract/hippocampus.proto` and the
generated `contract/hippocampus.swagger.json` are both published with the source, so anybody can
build a descriptor set without asking a running instance. Confidentiality is not available to be
defended, and `/v1/openapi.json` no longer pretends otherwise (see
[The OpenAPI document](#the-openapi-document)).

What remains is narrower and real. The reflection service is a **streaming** RPC, and every
interceptor in this service's chain is unary — so it reaches neither the auth interceptor nor
**either rate limiter**. It is the one surface on the gRPC port that is both unauthenticated and
unthrottled, and it answers requests by serving descriptors rather than by writing a fixed byte
slice. That is a small surface rather than a leak, and it is enough to keep the default following
the one setting that already distinguishes an instance serving its owner from one serving anybody
else:

| `auth.method`    | `reflection.enabled` unset |
| ---------------- | -------------------------- |
| `none` (default) | **on**                     |
| `hmac` / `idp`   | **off**                    |

Setting the key overrides the derivation in **both** directions — on for an authenticated instance
whose gRPC port is reachable only by trusted callers, off for an unauthenticated one that is not.
Whichever way it goes, the choice is logged at startup naming the reason, because "reflection is not
working" is otherwise indistinguishable from "the tool is pointed at the wrong thing".

With it off, a tool needs the contract instead — see
[Clients in other languages](clients.md#the-contract) for building a descriptor set from it. Note
that on any instance serving the gateway this is a smaller decision than it looks: the `/v1` surface
is documented at `/v1/openapi.json`, so turning reflection off while serving that document narrows
the unauthenticated surface without making the API any less discoverable.

### External bytes

A memory can carry `external_bytes`: the size of a payload it only **points at**, held in another
system — a trace in a column store, a blob in a bucket, a document in another index. It is
client-supplied and never interpreted here (the service does not fetch it, verify it, or know its
address), and it exists so decay can govern storage this store does not hold. Whatever the far end
is, it is the client's business; whether the payload is still worth keeping becomes this store's.

It is the third capacity axis. `consolidation.capacityExternalBytes` is the target it is held under
and `consolidation.capacityExternalBytesFloor` its hysteresis floor, read exactly as
`capacityBytes`/`capacityBytesFloor` are; the sum feeds capacity pressure alongside the row count and
the store's own bytes, and eviction reclaims against it as a second target. It is **never** folded
into `used_bytes`, which bounds this store's own disk — see
[the external capacity axis](consolidation.md#the-external-capacity-axis) for why that separation is
load-bearing rather than tidy.

Three properties at the API boundary:

- **Must be `>= 0`**, on both `StoreMemory` and `UpdateMemory`. A negative would understate the
  pressure every other row contributes to, since the axis is a sum across the store.
- **`0` on an update leaves the stored value unchanged**, exactly as `significance` does, so a
  partial update of any other field cannot silently zero it. There is deliberately no
  `clear_external_bytes` beside `clear_group` and `clear_metadata`: those exist because a memory can
  legitimately lose a label and keep its meaning, whereas a pointer-memory whose payload is gone is a
  memory to delete.
- **It is outside `memory.limit.sizeBytes`.** That limit bounds what this store holds, and this
  number measures what it does not.

It round-trips through `Export`/`Import`/`Transfer`, is reported per candidate by
`PreviewConsolidation`, and is 0 on every memory written before the column existed — so an upgraded
store behaves exactly as it did until something starts recording sizes.

**Nothing is deleted out there by this store.** It decides what should go and forgets its own record
of it; telling the far system to delete the payload is the `memory_forgotten`
[callback](#outbound-callbacks). Whether that delivery is a notification the queue's caps may discard
or an instruction they may not is `callbacks.backlogPolicy` — set it to `retain` or `stall` when the
receiver is the system holding the payloads, or a receiver outage that outlasts the caps orphans
every payload deleted during it. See [When a forget-callback is an instruction, not a
notification](#when-a-forget-callback-is-an-instruction-not-a-notification).

Even so, **leave the far end's own expiry configured as the outer bound**. Delivery is at-least-once
against a receiver that may be rebuilt, and a controller that has stopped running publishes no
instructions at all — an outer bound is the difference between a component that fails and one that
fails dangerously.

### Listing totals

`GetMemories` and `GetEvents` report a `total_count` beside the page. It is a second pass over the
same predicate with no limit, and since only `timestamp` ordering is index-backed it is now the
larger half of a list request — 32 ms against a page's 0.26 ms on a 100,000-memory store.

Two things reduce it, neither of them a setting:

- **A short first page needs no count at all.** If a page came back with fewer rows than it asked
  for, and no offset was given, it has already seen everything the filter matches — so its length
  _is_ the total, exactly.
- **The count no longer joins the significance registry** unless the filter asks something of
  significance, since it counts rows rather than reading their rank.

Beyond that the total is **cached**, per filter, for `listing.countCacheSeconds` (default `5`; `0`
counts every time):

```json
"listing": {
    "countCacheSeconds": 5
}
```

The trade is that a total can lag the page beside it by up to that long — the same eventual
consistency the [content-search index](#content-search) already has, and it cuts the other way too:
a client paging through results sees a **stable** total, where an exact one recomputed per page can
move underneath a traversal. The cache key covers every field of the filter **including the caller's
group scope**, so two callers scoped to different groups can never be served each other's total, and
it is bounded (256 entries, nearest-expiry evicted first) because a filter is caller-supplied and an
unbounded key space would be memory a caller controls.

Indexing the predicate instead was measured and rejected: an index that makes a group-scoped count
57× faster makes the scoped _page_ 181× slower by pulling the query planner off the listing index,
which is a net loss.

### Minimum significance

`memory.minimumSignificance` and `event.minimumSignificance` (both 0, admitting everything, by
default) set the significance below which a write is **quietly not retained**. Such a write is like a
brain that does not keep the insignificant: no error, an empty id, and `rejected: true` on the
response, so a client can tell it from a store that returned nothing. It is counted in
`hippocampus.memories.rejected` (and `.events.rejected`) with `reason="insignificant"`, because the
decay model working as designed is not a fault.

The gate applies only to an absolute, positive significance. Neither of the following is the
insignificant write it exists to drop:

- **An unranked create** (significance 0) is a deliberate "rank it later".
- **A placement** is a deliberate relative ranking.

`ImportBatch`, `Import` and `Transfer` are not gated either, because they move records that were
admitted once already and must arrive whole. A summary written by `ReplaceMemoriesWithSummary` or
`SummariseMemories` is the one write that is **refused** (`InvalidArgument`) rather than dropped below
the minimum: it replaces memories, and dropping it quietly would delete them for nothing.

### Memory size limit

`memory.limit.sizeBytes` (0, unlimited, by default) caps one memory: its body plus its serialised
metadata, in bytes, measured as the client sent them rather than as stored after compression. A
write over it is refused with `InvalidArgument`. It applies to every write that creates or edits a
memory - `StoreMemory`, each memory in a `StoreMemories` batch, `UpdateMemory`, and a summary - and,
like the significance minimum, not to `Import`, `ImportBatch` or `Transfer`, which carry records
admitted once already. Metadata counts toward it so that metadata cannot be a way around it; with the
limit unset, metadata still has its own 4 KiB cap. The payload a memory points at elsewhere
(`external_bytes`) is outside it - see [External bytes](#external-bytes).

```json
"memory": {
    "limit": {
        "sizeBytes": 65536
    }
}
```

### Rate limiting

Off by default. When `rateLimit.enabled` is set, requests are admitted through a hierarchy of token
buckets, and a request must have a token to spend at **every level that is configured** — a level
left at `0` requests per second imposes no limit at all, so the three are independently optional and
compose:

| Level      | Key                      | What it bounds                                                                                                    |
| ---------- | ------------------------ | ----------------------------------------------------------------------------------------------------------------- |
| **global** | `rateLimit.global`       | Everything the instance will serve, whoever is asking. The denial-of-service ceiling.                             |
| **tier**   | `rateLimit.tiers.<tier>` | All callers of one [authorisation tier](#authorisation) between them — "readers may poll, writers may not flood". |
| **client** | `rateLimit.perClient`    | One caller's own share, so a single client cannot consume the global allowance and starve everyone else.          |

```json
"rateLimit": {
    "enabled": true,
    "global":    { "requestsPerSecond": 500, "burst": 1000 },
    "perClient": { "requestsPerSecond": 20,  "burst": 40 },
    "tiers": {
        "reader": { "requestsPerSecond": 400, "burst": 800 },
        "writer": { "requestsPerSecond": 100, "burst": 200 }
    },
    "trustForwardedFor": false,
    "maxClients": 0,
    "clientIdleSeconds": 0
}
```

`requestsPerSecond` is the sustained rate and `burst` is how much of it may be spent at once; a
`burst` left at 0 means one second's worth of the rate (at least one request), and a `burst` set
without a rate is refused at startup, since a bucket that never refills would admit the burst once
and then reject for ever. **Both transports enforce the same buckets** — gRPC and the HTTP gateway
share one limiter, so a caller cannot double its allowance by using both.

Three things are worth knowing before setting a number:

- **The global ceiling is checked before the token is verified**; the per-tier and per-client levels
  necessarily after, because both need to know who is calling. That is what makes the global level
  the one that protects against an unauthenticated flood — but also the one that, when hit, refuses
  well-behaved callers along with the rest. Size it above your real peak and let the narrower levels
  do the shaping.
- **A request refused by a narrower level has still spent its global token.** The ceiling counts
  arrivals — the only thing a limit standing in front of identification can count — so a caller
  being throttled by its own bucket still consumes the instance's allowance. That is the reason for
  the sizing advice above rather than an oversight; between the tier and client levels, where both
  decisions are made together, a refusal _is_ refunded.
- **A tier with no rule is unlimited**, which is why the example leaves `admin` out: an operator
  answering an incident should not be queued behind a limit meant for application traffic. Per-tier
  limits need [authentication](#authentication) — a tier comes from a token's roles, so with
  `auth.method: none` no caller ever matches one.
- **Only the RPC surface is limited.** `/healthz`, `/readyz`, the console and its front-channel
  config, the login endpoints, and `/v1/openapi.json` are never throttled: rejecting a readiness
  probe under load would get the instance restarted rather than protected.

A refused request gets gRPC `ResourceExhausted` (a `retry-after` trailer, in seconds) or HTTP `429`
(a `Retry-After` header and a JSON body naming the level that refused). It is classified as a
_client_ fault in the [request metrics](operations.md#request-metrics-red), so your own protection
working never fires the server-error alert.

**Who is "a caller"** is the authenticated `client_id`, falling back to the token's `sub` and then to
the caller's address. With authentication off the address is all there is, which is per-host rather
than per-application — usable, but the reason per-client limits pair naturally with tokens.
`rateLimit.trustForwardedFor` makes the fallback read the rightmost `X-Forwarded-For` entry instead
of the connection's address, and is **off by default on purpose**: the header is caller-supplied, so
believing it on a directly reachable listener lets any caller mint itself an unlimited number of
buckets. Turn it on only when every request arrives through a proxy that writes the header, whether
it overwrites it or appends to it. The rightmost entry is the one that proxy wrote; anything to its
left came from the client. Behind a chain of proxies, the rightmost entry is the previous proxy, so
the chain is limited as one caller unless the outermost proxy overwrites the header. The entry must
be an IP address, with or without a port (the port is dropped); anything else is ignored and the
connection's own address is used, so a malformed or forged entry can neither mint a bucket nor reach
the log.

`rateLimit.maxClients` (0 → 10000) and `rateLimit.clientIdleSeconds` (0 → 300) bound the per-client
bucket table in size and age, so it cannot itself become the memory-exhaustion surface the feature
exists to prevent. The least recently seen caller is dropped first, which is the right order: a
caller being throttled is by definition the most recent, so it is never the one evicted.
`hippocampus.ratelimit.clients` reports how many are tracked — see
[Rate limiting](operations.md#rate-limiting) for what to watch.

A **request** is the unit, not a record: one `StoreMemories` or `ImportBatch` call spends one token
however many memories it carries. That is deliberate — the limiter exists to bound request rate and
concurrency, and the size of a call is already bounded by `maxRecvMsgBytes` and, for the batch
write, by its 500-memory cap. A deployment that needs to bound ingest _volume_ wants
`consolidation.capacityBytes` and the decay cycle, which is what actually decides how much this
store keeps.

### Health and readiness

The gateway serves the Kubernetes lifecycle endpoints, all always open (no token) so
orchestrators can reach them. Every other Hippocampus component that runs as a service serves the
same three paths (see [Operations](operations.md#ports)), so one probe definition fits all of them.

- `/livez` — **liveness**: the process is up. It never touches the database, so a slow or
  unreachable store does not make it fail; point a probe that _restarts_ the container here, and the
  startup probe too, so a transient dependency outage does not trigger a restart loop that cannot
  fix it. Its JSON body carries the running build's `version` (the same value `--version` prints),
  so an operator can tell what is deployed.
- `/readyz` — **readiness**: the process is up, the database answers a ping, and shutdown has not
  begun. Returns `200` when the store is reachable, `503` otherwise, and `503` with `"status":
  "shutting down"` from the moment the process receives `SIGTERM`. Point load-balancer / service
  readiness probes here so an instance whose database has become unreachable, or which is shutting
  down, is drained rather than kept in rotation while every RPC fails. The gRPC health service
  (`grpc.health.v1.Health`) reflects the same signal, flipping between `SERVING` and `NOT_SERVING`.
- `/healthz` — the same as `/livez`, under the older name. Kubernetes itself deprecated `/healthz`
  in favour of the split pair; it stays so a probe or script written against it keeps working.

```json
"readiness": {
    "pingTimeoutSeconds": 0,
    "cacheSeconds": 0
}
```

`readiness.pingTimeoutSeconds` bounds each database ping and `readiness.cacheSeconds` caches the
result so a burst of probes collapses to at most one ping per window; both fall back to internal
defaults (2 s and 3 s) when left at 0. The Docker image's `HEALTHCHECK` targets `/readyz`.

On Kubernetes, the shipped overlays (`deploy/k8s`) and the wizard's generated manifests use all
three probes: a `startupProbe` on `/livez` (so a slow schema migration is not killed by the
liveness probe), a `livenessProbe` on `/livez`, and a `readinessProbe` on `/readyz`. They also set a
5-second `preStop` sleep, so the pod keeps serving while its endpoint removal reaches every node
before `SIGTERM` arrives, and a `terminationGracePeriodSeconds` that covers the pause plus three
`shutdown.timeoutSeconds` phases. The native `sleep` action needs Kubernetes 1.30 or later, since
the image has no shell to run `sleep` in.

### Version

`hippocampus --version` prints the build identification and exits (before the config file is read).
The value comes from the Go module version plus the VCS revision/time the toolchain embeds at build
time, so it identifies the exact commit even for a `go build` from a working tree. The same string
is logged at startup, reported in the `/healthz` body, and set as the OTEL `service.version`
resource attribute when observability is enabled. The Docker image also carries an
`org.opencontainers.image.version` label (`--build-arg VERSION=<tag>`).

A client is told the same string by **`WhoAmI`**, in its `version` field. Everything above is
either a command line, a log, or an HTTP probe, so a gRPC-only client — the CLI, the MCP bridge, the
broker bridges, the ingestor — had no way to ask what it was talking to: `GetTopology`'s `self` node
carries it, but that view is optional (`topology.enabled`), tier-configurable, and refused outright
to a group-scoped caller. `WhoAmI` is reader-tier and always available.

### Deployment topology

`GetTopology` reports the deployment as one instance understands it: itself, the components it
dials, how they relate, and the last known health of each. It backs the console's **Deployment**
tab and `hippo topology`. On by default.

```json
"topology": {
  "enabled": true,
  "minimumTier": "reader",
  "probeIntervalSeconds": 30,
  "probeTimeoutSeconds": 2,
  "probeTransferTarget": false,
  "heartbeatSeconds": 30,
  "components": [
    { "name": "nats-bridge", "kind": "bridge", "healthUrl": "http://nats-bridge:8090" },
    { "name": "ingestor", "kind": "ingestor", "healthUrl": "http://ingestor:8090" }
  ]
}
```

**What it can and cannot know.** An instance knows three things: itself, whatever it dials
outward — the store, the search index, the summariser and embedder, the object store, the transfer
target, the identity provider, the OTLP endpoint — and, on a shared database, the peer instances it
finds registered there. Every other part of a real deployment **dials in**: the
[event-source bridges](eventsource.md), the [ingestor](ingestor.md), [MCP servers](mcp.md),
`hippo`. They hold an address for the service; the service holds nothing for them, and there is no
registry of them — this is a memory store, not a control plane. So every component in the response
carries a **source** saying how the instance came to know about it, and a client is expected to show
it. A sparse diagram means nothing has been declared, not that nothing is running.

**Peers on a shared store are discovered, not declared** (`postgres`/`mysql` only). Every instance
writes one row into an `instances` table every `heartbeatSeconds` (default 30, `0` disables both
halves) saying who it is, what it is running, and whether it consolidates; the same statement prunes
rows nobody has refreshed for four of _their own_ intervals. Every instance reads that table, so a
[horizontally scaled](operations.md#horizontal-scaling-with-replicas) deployment can finally name its own peers — with each
peer's version, its capability flags (search index, summariser, embedder, gateway), and how long
ago it last checked in. A peer's id is `hostname:port` and therefore deterministic, so a restart
replaces its own row rather than leaving a ghost; an instance that shuts down cleanly removes its
row immediately, and one that stops without saying so is reported `unreachable` for a window before
it disappears. Nothing acts on a peer's row — it is read to be displayed, and there is no RPC that
could do anything else with it.

That table is what makes two deployment-wide faults visible, both reported as **warnings** on the
response (shown above the diagram in the console, and above the listing in `hippo topology`):

- **No instance is consolidating.** Every instance came up with `consolidation.enabled: false`, so
  nothing is forgetting, evicting or summarising and the store simply grows — while each instance
  individually reports itself perfectly healthy, because it is. There is no component to show as
  red here: the fault _is_ the absent one. It is held back for the first minute of an instance's
  life, since a replica routinely starts before the consolidator during a rolling deployment.
- **More than one instance is consolidating.** The single-consolidator lock has been circumvented,
  or two tiers are pointed at different databases and each believes it is alone. The duplicates are
  named, and marked degraded on the diagram.

**SQLite keeps no registry**, and none of the above applies to it: that store is single-instance by
construction (the `hippocampus.lock` file lock enforces it), so the table would hold one row
restating what the process already knows — and SQLite's page-based capacity accounting would count
it, letting the record of the deployment raise capacity pressure and evict live memories to make
room for itself.

**Declaring the components that dial in.** `topology.components` is how the other half of a
deployment becomes visible. Each entry is a `name` (also its node id, so it must be unique), a
`kind` (`bridge`, `ingestor`, `mcp`, or `client` — it selects the shape drawn and nothing else),
and a `healthUrl`. A URL with no path gets `/readyz` appended, which is what the
[event-source bridges](eventsource.md) and the [ingestor](ingestor.md) already serve on their
`--health-port`; a URL carrying a path is used verbatim, for something behind a proxy.

Declaring a component needs **no change to the component itself**. Those binaries already serve the
shared health surface, and `/readyz` already returns a per-dependency breakdown naming which of
_their_ two ends is unreachable — so a bridge that cannot reach its broker reports exactly that,
rather than showing as an unexplained red box. A `503` is therefore reported as **degraded** (it
answered, and it is telling you why) where a refused connection is **unreachable**, and a `404` —
a declared URL that is simply wrong — is reported with its status code so the two are
distinguishable.

`healthUrl` is required: a component that cannot be probed adds nothing the config file does not
already say, while looking on the diagram exactly like a live one. At most
32 components may be declared, since each is an outbound request on every probe round. Nothing else
about a declared component reaches this instance — it is a label and an address to check, not a
registration, and removing the entry removes it entirely.

**Clients that call are observed, and need no configuration at all.** Where authentication is on,
each component presenting a verified token is added to the response under the `client_id` it
authenticated with, sourced `observed`. There is nothing to set: it is on wherever the view and
authentication both are. It reports the roles the token carried, whether it is group-scoped (never
_which_ groups — the view is reader-visible by default, and a group name is frequently a customer's),
how many calls it has made and when it last made one.

Four limits are deliberate, and each is the reason this source is listed last:

- **No health.** A call proves the client was alive at that moment, which is not what a probe
  proves — an idle client is not broken, and one that polls while its real work has stopped is not
  healthy. Observed components report `not checked`, permanently.
- **Nothing without authentication.** A caller is identified by its token and by nothing else,
  never by a source address (which names a proxy or a replaced pod) or a user agent (which is
  whatever the caller typed). With `auth.method: none` the `self` component says as much, so the
  empty inbound half is explained rather than merely empty.
- **Bounded at 32**, least-recently-seen first, because the key arrives in a token and an unbounded
  set would be memory a caller controls. The `self` component reports when the view is capped.
  For the same reason a `client_id` is never used as a metric attribute.
- **Held in memory, and never expired on a timer.** A restart clears the set; nothing else does. A
  component whose last call was hours ago stays on the diagram saying so, which is the report of the
  fault — one that had quietly vanished would be indistinguishable from one nobody ever ran.

Declaring and observing combine rather than compete: where a declared component's `name` matches an
observed `client_id`, the two are reported as **one** component carrying both its health and its
last call. That is the pair that separates a bridge which is up and writing from one which is up and
has written nothing.

**Health comes from a background prober, not from the request.** Statuses are refreshed every
`probeIntervalSeconds` and each probe is bounded by `probeTimeoutSeconds`; the response reports the
interval, and a polling client should pace itself by that rather than by a guess. Each component
also reports **when it was last checked**, so `unreachable` always reads as "when last asked". A
round runs a few probes at a time, so a full list of declared components still completes well inside
one interval.
Probing inside the RPC was rejected: it would make one console page open a connection to every
dependency, let a single hung one hang the request, and multiply both by the number of people
looking.

**Every component that can say which build it is, does.** The version shown on each component
comes from the most direct source available for it:

| Component | Version from |
| --- | --- |
| This instance (`self`) | its own build, as `--version` and `/healthz` report it |
| A peer on a shared store | the version it writes into its registry row |
| The primary store | the engine itself: `SQLite 3.x` (the library compiled in), `PostgreSQL 16.x`, `MySQL 8.x` |
| The OpenSearch index | the cluster's distribution and version number |
| An Ollama summariser or embedder | the server's `/api/version` |
| The transfer target (when probed) | its `WhoAmI` version, asked with the transfer token |
| A declared component | the `version` field of its `/readyz` body |
| An observed caller | the `hippocampus-client-version` header it sends |

The last row is also the fallback for a **declared** component that has no health port of its own
(an MCP bridge on stdio, say): when its `/readyz` reports no version, the one it sent as a caller is
used. Every client in this repository sends the header — `hippo`, the MCP bridge, the event-source
bridges, the ingestor, the object-storage agents, the Python client, the console, and an instance's
own `Transfer` — and the shared health server every one of those daemons uses reports its version on
`/readyz`. A client of your own can send it too; see [Clients](clients.md#reporting-a-client-version).

Some components have **no version to report**, and show none: an S3 bucket or archive directory, an
OpenAI-compatible provider (that API has no version endpoint), and the OTLP collector, identity
provider and callback receiver, which are never probed at all.

A version that costs a request of its own — the store's, the cluster's, Ollama's, the transfer
target's — is asked for on the first probe, again after any round that did not find the component
healthy (a restart is usually an upgrade), and otherwise every ten minutes, so the view does not
double the requests it makes to everything this instance depends on. A version that cannot be read
does not make a component unhealthy, and a component that goes unreachable keeps showing the last
version it reported, beside a status that already says the reading is not live.

A version reported by the far end — a caller's header or a `/readyz` body — is that component's own
**claim**, and is treated as one: anything that is not printable ASCII, or longer than 64 bytes, is
dropped rather than edited, and it is only ever displayed. It identifies nothing — a caller is still
identified by its token alone, for the reasons given above.

Two components are deliberately **never probed**. The OTLP collector, because export is
fire-and-forget and a probe would mean opening a second connection to learn something no exporter
acts on; and the identity provider, because the verifier already refreshes its key set on its own
schedule and a console poll must not become load on the organisation's IdP. Both report
`not checked` with the reason, rather than a green tick nobody established. The transfer target is
the third exception and is opt-in (`probeTransferTarget`, default `false`): its probe dials a remote
instance on a timer, using the same credentials and TLS trust options a real transfer would.

**Components that are switched off are included**, with a status of "not configured" and an
attribute naming the key that enables them. That is what answers "why is semantic search returning
nothing" — a greyed-out embedder reading `enable_with: llm.embedding.enabled` — and nothing
else
the service says answers it. The console hides them behind a toggle; `hippo topology --all` shows
them.

**No secret ever reaches the response.** Addresses are redacted to scheme, host, port and
database/bucket name: DSN credentials (URL, libpq keyword/value, and MySQL forms alike), signing
keys, and cluster passwords are stripped, in every tier, for every caller. The `self` component
reports an explicit allow-list of settings — the driver, the consolidation parameters, the
capacity
and retention figures, the auth method, whether TLS and rate limiting are on — never the whole
configuration.

`minimumTier` sets the tier required to call it (`reader` by default, see
[Authorisation](#authorisation)); it is the only per-RPC tier a deployment may change. Reader is
defensible precisely because of the redaction above — what the view exposes is the deployment's
shape rather than its contents — but a deployment where internal hostnames are themselves
sensitive
should raise it. A **group-scoped** caller is refused regardless of tier: there is no per-group
topology, so a scoped caller could only be shown infrastructure that is not theirs.

### Authentication

Every RPC — on both the native gRPC service and the HTTP gateway — can require a signed bearer
token. `auth.method` selects the scheme:

- `none` (the default) — no authentication, preserving the previous no-auth behaviour.
- `hmac` — tokens are signed and verified with shared HS256 secrets, minted by the service binary
  itself via `--mint-token`. HS256 is keyed directly with the raw secret, so use long, random
  values — at least 32 bytes (256 bits, matching the hash output); a shorter secret is
  brute-forceable and logs a startup warning. A single secret (`auth.signingSecret`) is the simplest
  form; `auth.signingKeys` holds several `kid`-identified secrets at once so one can be rotated in
  while tokens signed by another still verify (see [Key rotation](#key-rotation-hmac)), and
  `auth.revocationFile` cuts off individual tokens or clients without waiting out their TTL (see
  [Revocation](#revocation)).
- `idp` — tokens are issued by an external identity provider and verified as RS256 against the
  provider's published JWKS. `auth.jwksUrl` names the key-set endpoint directly, or `auth.issuer`
  alone resolves it via OIDC discovery (`<issuer>/.well-known/openid-configuration`). When
  `auth.issuer` is set it is also enforced against every token's `iss` claim, and
  `auth.audience`, when set, against `aud` — **set both**, or every token the provider signs
  verifies here, including tokens minted for other applications in the same tenant (the service
  warns at startup while either is unset; see [Security](security.md#authentication)). Keys are cached by `kid` and re-fetched every
  `auth.jwksRefreshIntervalSeconds` (300 by default); a token presenting an unknown `kid` forces
  one rate-limited early re-fetch, so a provider-side key rotation is picked up on first sight
  without restarting the service. The provider must be reachable at startup (the initial key
  fetch failing fails startup), but a later outage only stops key refreshes — cached keys keep
  verifying requests.

`auth.signingKeys` is a structured list (`[{ "kid": "...", "secret": "..." }]`) and so is
config-file-only — unlike `auth.signingSecret`, it cannot be injected through a single
`HIPPOCAMPUS_AUTH_*` environment variable.

The boolean `auth.enabled` from earlier releases remains as a deprecated alias: when
`auth.method` is unset, `auth.enabled: true` selects `hmac` (with a startup warning) and
`auth.enabled: false` selects `none`, so existing configs keep working unchanged.

```json
"auth": {
    "method": "none",
    "signingSecret": "",
    "signingKeys": [],
    "activeKid": "",
    "revocationFile": "",
    "revocationRefreshSeconds": 30,
    "jwksUrl": "",
    "issuer": "",
    "audience": "",
    "jwksRefreshIntervalSeconds": 300,
    "roleClaim": "roles",
    "roleMapping": {},
    "readerRecallReinforces": false,
    "ui": {
        "issuer": "",
        "clientId": "",
        "scopes": "openid profile",
        "audience": ""
    }
}
```

`auth.roleClaim`, `auth.roleMapping`, and `auth.readerRecallReinforces` drive
[authorisation](#authorisation) and are only consulted when authentication is enabled.

`auth.ui` is the **front-channel** configuration the embedded web console (`/ui`) reads — from the
unauthenticated `GET /ui/config` endpoint — to start a browser OIDC login under `auth.method: idp`.
It carries no secret: only the public single-page-app `clientId`, the `scopes` to request
(default `openid profile`), the `issuer` the browser runs OIDC discovery against (defaults to
`auth.issuer`), and an optional `audience`. The audience matters for providers whose access token is
opaque unless an API audience is requested — **Auth0** needs it set to the API identifier to mint a
verifiable JWT; **Keycloak** issues a JWT without it. The access token the flow returns is sent as
the `Authorization: Bearer` on every `/v1` call and verified exactly like any other `idp` token, so
the tier still comes from `auth.roleClaim`/`auth.roleMapping`. When `auth.method` is `none` or
`hmac`, `/ui/config` simply reports the method and the console falls back to its manual bearer-token
box.

```jsonc
"auth": {
  "method": "idp",
  "issuer": "https://idp.example.com/realms/hippocampus",
  "ui": {
    "clientId": "hippocampus-console",  // a PUBLIC single-page-app client, no secret
    "scopes": "openid profile",         // optional; this is the default
    "issuer": "",                       // optional: defaults to auth.issuer
    "audience": ""                      // optional: defaults to auth.audience
  }
}
```

Whichever it reports, the console uses it to decide what its **sign-in card** offers. Under `none` no
card is shown at all; otherwise the page opens on the card in place of the tabs — the token box under
`hmac`, a **Sign in** button under `idp` — and reveals the console only once `GET /v1/whoami` resolves
a role. The card returns whenever the session does not: after **Sign out**, on a token the service
refuses (401), and on one whose role grants no tier (403). A failure that is not credential-shaped —
a 503 while a purge runs, say — deliberately leaves the console up rather than inviting the
operator to replace a token that is perfectly good.

#### Server-side sign-in (`auth.oauth2`)

`auth.ui` above runs the OIDC Authorisation Code + PKCE flow **in the browser** as a public client
(no secret; the token lives in the page's `sessionStorage`). `auth.oauth2` is the alternative: the
**service itself** runs the flow as a **confidential client** — the code-for-token exchange happens
on the server with a client secret, and the resulting session rides an `HttpOnly` cookie the page
can never read. Prefer it when the identity provider requires a confidential client, or to keep the
token out of page-readable storage (mitigating token theft via XSS). It is available only under
`auth.method: idp`, and it does not change how tokens are _verified_ — the cookie carries the same
IdP access token, checked by the same `idp` verifier as a bearer header.

```jsonc
"auth": {
  "method": "idp",
  "issuer": "https://idp.example.com/realms/hippocampus",
  "audience": "hippocampus-api",              // API audience for the access token (as for idp)
  "roleClaim": "realm_access.roles",
  "oauth2": {
    "enabled": true,
    "clientId": "hippocampus-console",         // a CONFIDENTIAL client at the provider
    "clientSecret": "…",                       // inject via HIPPOCAMPUS_AUTH_OAUTH2_CLIENTSECRET
    "redirectUrl": "https://hippo.example.com/auth/callback",  // must be registered at the provider
    "scopes": "openid profile email offline_access",          // offline_access → a refresh token

    // all optional below here
    "issuer": "",                  // defaults to auth.issuer; set it where the login issuer differs from the API's
    "audience": "",                // defaults to auth.audience
    "cookieSecure": true,          // defaults to the redirectUrl scheme; set it behind a TLS-terminating proxy
    "cookieDomain": "",            // set it to serve the console across subdomains
    "successRedirectUrl": "/ui",   // where a completed login lands
    "postLogoutRedirectUrl": "",   // used only where the provider advertises end_session_endpoint
    "sessionTTLSeconds": 3600,     // session-cookie lifetime
    "refreshTTLSeconds": 604800    // refresh-cookie lifetime
  }
}
```

When enabled, the gateway serves four endpoints — `GET /auth/login` (start the flow),
`GET /auth/callback` (the provider's redirect target; exchanges the code, verifies the `id_token`
signature and `nonce`, sets the session cookie), `POST /auth/refresh` (swap the refresh cookie for a
fresh access token), and `GET /auth/logout` (clear the cookies and, when the provider advertises an
`end_session_endpoint`, RP-initiated logout) — all reachable without a token. The session cookie
(`hippo_session`) is `HttpOnly`, `SameSite=Lax`, and `Secure` (following the `redirectUrl` scheme
unless `cookieSecure` overrides); the refresh cookie is scoped to `/auth` so it is never sent to the
API. A state-changing `/v1` request authenticated by the session cookie must come from the gateway's
own origin and is otherwise refused with `403` — `SameSite=Lax` alone admits a same-site page on
another port or subdomain (see [the web console](security.md#the-web-console-ui)). `/ui/config` reports `loginMode: "server"`, and the console shows a **Sign in** button that
navigates to `/auth/login` instead of running the in-page flow. The `redirectUrl` **must** point at
the service's own `…/auth/callback` and be registered as an allowed redirect on the provider's
client. Because the client secret is a secret, inject it via
`HIPPOCAMPUS_AUTH_OAUTH2_CLIENTSECRET` rather than committing it. Serve the console over HTTPS
(directly or via a TLS-terminating proxy) so the `Secure` session cookie is not dropped.

#### Presenting a token

Whichever method is active, present the token as `Authorization: Bearer <token>` over HTTP, or
as an `authorization: Bearer <token>` metadata entry over gRPC — the same header value works
either way. A missing or invalid token gets `codes.Unauthenticated` from gRPC, or `401` (with a
`WWW-Authenticate: Bearer` header) from the HTTP gateway. The gRPC health service and the
gateway's `/healthz` are always reachable without a token, regardless of method, so orchestrator
liveness/readiness probes are never blocked. Both verifiers pin their signing algorithm
(`jwt.WithValidMethods` — HS256 for `hmac`, RS256 for `idp`), so a token can never select its
own verification algorithm, and both require an `exp` claim (`jwt.WithExpirationRequired`), so a
token minted without an expiry is rejected rather than being valid forever (`--mint-token` always
sets one).

Under `hmac` there is no client registry or admin RPC — issuing a token is a CLI operation on
the service binary itself:

```sh
hippocampus --mint-token --client-id my-client --role writer --ttl 24h -c config.json
```

This prints a signed token to **stdout** and exits without starting the server (or touching the
database); it also prints the token's `jti` (its unique id), client, and roles to **stderr**, so
`token=$(hippocampus --mint-token ...)` still captures only the token while an operator can record
the `jti` for later [revocation](#revocation). `--role` is **required** and names one or more
[authorisation](#authorisation) tiers — `reader`, `writer`, and/or `admin` (repeatable, or
comma-separated: `--role reader,writer`); a role-less token authorises nothing under the
default-closed policy, so minting one is refused. `--ttl` accepts any Go duration (`1h`, `24h`,
`720h`, ...); `--signing-secret` can override the config's secret for minting on a host that only
has the secret and not the full deployed config. When `auth.signingKeys` is configured, the token
is signed with `auth.activeKid` (or the first listed key) and stamped with that `kid`; `--kid`
overrides which key to use. Under `idp` the identity provider owns issuance, expiry, and
revocation, and `--mint-token` refuses to run.

Verification is written behind an interface (`auth.Verifier`) — `hmac` and `idp` are its two
implementations, and the interceptor/middleware call sites are identical for both.

The verified `client_id` is logged on every failing request (and, on the HTTP gateway, every
request), so a leaked token can be traced to the client it was issued to. What each token may _do_
is governed by [authorisation](#authorisation) below.

### Authorisation

When authentication is enabled, each RPC also requires a minimum **role tier**, carried in the
token's `roles` claim. The tiers nest — `reader` ⊂ `writer` ⊂ `admin` — so a higher tier can do
everything a lower one can:

| Tier     | May call                                                                                                                                                                                                                                                                                                                                     |
| -------- | -------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| `reader` | `GetEvents`, `GetEventById`, `GetMemories`, `SearchMemories`, `RecallMemories`, `GetMemoryLinks`, `GetEventLinks`, `GetSummarisationCandidates`, `ExplainConsolidation`, `GetConsolidationStatus`, `GetForgottenMemories`, `GetSignificanceLevels`, `WhoAmI`, `GetTopology`¹                                                                 |
| `writer` | everything `reader` can, plus `StoreEvent`, `UpdateEvent`, `EndEvent`, `UpdateEventSignificance`, `MergeEvents`, `DeleteEvent`, `StoreMemory`, `StoreMemories`, `UpdateMemory`, `DeleteMemories`, `LinkMemories`, `UnlinkMemories`, `LinkEvents`, `UnlinkEvents`, `ReplaceMemoriesWithSummary`, `SummariseMemories`, `Import`, `ImportBatch` |
| `admin`  | everything `writer` can, plus `Purge`, `Sleep`, `PreviewConsolidation`, `DeleteMemoriesByFilter`, `DeleteEventsByFilter`, `DeleteForgottenMemories`, `GetCallbackQueue`, `DeleteCallbackQueue`, `Export`, `Transfer`, `Clear`                                                                                                                |

The three forgetting-transparency reads — `ExplainConsolidation`, `GetConsolidationStatus` and
`GetForgottenMemories` — are all `reader`, while the dry run beside them is `admin`. What separates
the preview is not that it is revealing but that it is **unscoped**: it describes the whole store
and is refused outright to a group-scoped caller. The other three are not. The explanation answers
only about memory ids the caller supplies, which a reader can already fetch in full; the status
names no memory at all; and the forgotten log is filtered by the caller's scope, carries no bodies,
and reports the same `value`/`threshold` pair for memories that have gone that the explanation
reports for those still here. The one deployment where the log wants raising back to `admin` is one
handing `reader` tokens to untrusted clients while keeping a long `maxAgeInDays`: the log outlives
what it describes, so it leaves a trace of groups, sizes and timing that the live store would by
then have discarded. Emptying it (`DeleteForgottenMemories`) is `admin` either way — it is
destructive, and destructive on an audit record rather than on data the caller put there.

The [callback queue](#outbound-callbacks) pair are **both** `admin`, which is a different split from
the forgotten log's and rests on a different fact. The read is not the harmless half here: the queue
is a deployment-wide operational structure rather than a record of the caller's own data, its depth
describes the deployment's health rather than anybody's memories, and — the part that decides it —
it cannot be group-scoped at all. A queued delivery batches every memory one delete chunk removed,
and a chunk routinely spans groups, so there is no single group a predicate could select on. Both
are therefore refused outright to a group-scoped caller, on the same footing as the preview.

¹ `GetTopology` is the one RPC whose tier a deployment may change, via `topology.minimumTier`; the
table gives its default. See [Deployment topology](#deployment-topology). What is **not**
configurable is its refusal to a group-scoped caller, which is the same rule that governs the
preview: the answer cannot be partitioned, because there is no per-group topology.

**Linking is a write.** `LinkMemories`/`LinkEvents` and their unlink counterparts sit with the
`writer` set rather than with the reads they resemble, because a link raises the effective
significance of both ends and so changes what the store forgets; removing one lowers what it was
protecting. Reading an item's links (`GetMemoryLinks`/`GetEventLinks`) is `reader`, at the same tier
as reading the item itself — it returns ids the caller could already reach, and nothing about their
content.

`Export`/`Transfer` are
`admin` because they read the whole store out; `Import`/`ImportBatch` are
`writer` because they deliberately bypass the write-path validation `StoreMemory`/`StoreEvent`
enforce (body-size limit, future-timestamp clock-skew guard, minimum-significance gate) to restore
an archive faithfully. A caller whose token grants a tier below the RPC's requirement gets
`codes.PermissionDenied` from gRPC, or `403` from the HTTP gateway (distinct from the `401` an
_unauthenticated_ request gets). The same policy governs both transports from one table, so gRPC
and the gateway can never diverge.

Authorisation is **default-closed**: a token whose roles resolve to no known tier is denied every
RPC. Because tokens minted before this release carry no `roles` claim, **enabling a newer build
against existing tokens requires re-minting them with a `--role`** (or, under `idp`, adding roles
to the provider's token). With `auth.method: none` there is no authenticated principal, so
authorisation is off and every RPC is reachable, exactly as before.

Under `hmac`, `--mint-token --role` stamps the tier names (`reader`/`writer`/`admin`) directly.
Under `idp`, the provider supplies them: by default they are read from a top-level `roles` claim;
`auth.roleClaim` points at a differently-named claim when the provider uses one. The claim name is
resolved literally first — so a provider that namespaces roles under a URI-shaped key (Auth0's
`https://your-domain/roles`) matches as a top-level key — and, when no literal key exists, as a
dotted path through nested objects, so Keycloak's `realm_access.roles` also resolves.
`auth.roleMapping` translates a
provider's own group names onto the tiers, e.g. `{ "hippo-ops": "admin", "hippo-app": "writer" }`;
the tier names always map to themselves, so a mapping is only needed for other names.

`RecallMemories` and `SearchMemories` are `reader`-tier: recall is a read as far as _access_ goes,
even though it normally reinforces the memory (resets its decay clock, raises its recall count).
Whether a **reader** actually triggers that reinforcement is controlled globally by
`auth.readerRecallReinforces` (default `false`): left off, a reader's recall/search returns the
memories without the write side effect; turned on, readers reinforce like anyone else. `writer` and
`admin` callers always reinforce.

#### Key rotation (hmac)

`auth.signingKeys` lets several HS256 secrets be trusted at once, each tagged with a `kid` that is
written into the header of every token it signs. Because the verifier trusts _every_ listed key, a
new secret can be introduced and start signing while tokens signed by the previous secret keep
verifying — so a rotation never has a flag day where outstanding tokens are abruptly rejected. The
procedure:

1. Add the new key to `auth.signingKeys` and point `auth.activeKid` at it (keep the old key in the
   list); restart. New tokens are now signed with the new key; old tokens still verify.
2. Re-mint client tokens against the new key as they expire, or all at once.
3. Once no outstanding tokens are signed by the old key (they have expired or been re-minted),
   remove it from `auth.signingKeys` and restart.

`auth.signingSecret` and `auth.signingKeys` can be set together: `signingSecret` verifies tokens
that carry no `kid` (every token minted before rotation existed), while `signingKeys` verifies
`kid`-tagged ones — a convenient way to migrate an existing single-secret deployment onto keyed
rotation without invalidating its live tokens. A token whose `kid` names no configured key is
rejected.

#### Revocation

Two mechanisms cut a credential off before its TTL expires:

- **Rotate the signing secret** — changing `auth.signingSecret` (or removing a key from
  `auth.signingKeys`) invalidates every token signed by it at once. Coarse, but immediate.
- **A revocation file** (`auth.revocationFile`) — a JSON file, polled for changes every
  `auth.revocationRefreshSeconds` (30 by default), that revokes named tokens or clients without a
  restart and without affecting anyone else:

  ```json
  {
    "jtis": ["9fdec40d972eb3a4be7297c29ed95061"],
    "clients": [
      { "clientId": "decommissioned-batch-loader" },
      {
        "clientId": "rotated-web-console",
        "issuedBefore": "2026-07-01T00:00:00Z"
      }
    ]
  }
  ```

  `jtis` revokes individual tokens by the `jti` printed at mint time. A `clients` entry revokes
  every token for that `client_id`; adding `issuedBefore` (an RFC 3339 timestamp) revokes only
  tokens issued before it — the per-client rotation move: set the cutoff to now, then mint the
  client a fresh token. Changes take effect within `auth.revocationRefreshSeconds`, on both the
  gRPC service and the HTTP gateway. A named-but-unreadable or malformed file **fails startup** (so
  a typo can't silently revoke nothing); a bad file written _after_ startup is ignored with an
  error log, keeping the last good list in force. The check runs _after_ signature verification and
  works in front of `idp` as well as `hmac`, so a provider-issued token can be revoked locally even
  when the provider's own revocation lags.

### Group scoping

Authorisation tiers say what a caller may **do**. Group scoping says which records they may do it
**to**: a token may carry a `groups` claim naming the group labels (`Memory.group` / `Event.group`)
whose records it can read and write.

```json
"auth": {
    "groupsClaim": "groups",
    "requireGroupScope": false
}
```

Mint a scoped token with `--group` (repeatable or comma-separated):

```bash
hippocampus --mint-token --client-id sales-agent --role writer --group sales --ttl 24h
```

**It is off until tokens carry the claim.** An existing deployment is entirely unchanged: no schema
change, no migration, and a token with no `groups` claim behaves exactly as every token did before.

**An empty scope means the whole store.** That is the single most important thing to know about it —
an unscoped token is the _most_ privileged shape a token has, not the least. `auth.requireGroupScope`
turns the absence of a scope into a rejection, which is worth setting once a store is partitioned: an
identity provider misconfigured to stop emitting the claim would otherwise hand every caller
everything, and every request would succeed while doing it. Under `idp`, set `auth.groupsClaim` too
if the provider publishes the scope under another name (a dotted path reaches into a nested object,
exactly as `auth.roleClaim` does).

What changes for a scoped caller:

| Behaviour             | Effect                                                                                                               |
| --------------------- | -------------------------------------------------------------------------------------------------------------------- |
| Listing and searching | Narrowed to the scope, including `total_count`. Filtering by a group outside it returns an empty page, not an error. |
| Reads/writes by id    | A record outside the scope reports `NotFound` — never `PermissionDenied`, which would confirm it exists.             |
| Writes                | Stamped with the caller's group. A token holding several groups must name one; a token holding one has it filled in. |
| Moving a record       | A write may re-file within the scope but cannot push a record out of it (`clear_group` is refused).                  |
| Links                 | Both ends must be in scope. Edges reaching outside are dropped from responses rather than refused.                   |
| Export/Transfer/Clear | Walk only the caller's partition — which is also a useful per-group export.                                          |
| Forgotten log         | Filtered by the scope, so a bound caller reads and clears only its own partition's losses.                           |
| Purge/Sleep/Preview   | Refused. All three act on the whole store; see below.                                                                |

`WhoAmI` reports `groups` and `group_scoped`, so a client can adapt — read `group_scoped`, never
`len(groups)`, since an empty list means unscoped rather than scoped to nothing. The embedded console
shows the scope beside the role pill for exactly this reason: otherwise a scoped view looks like a
store that has lost most of its data.

**Three RPCs are refused to a scoped token.** `Purge` empties the store, `Sleep` runs the
store-global decay cycle, and `PreviewConsolidation` enumerates across every group by design. None
has a per-partition meaning under a shared capacity target, so each belongs to whoever runs the store
— and an unscoped token is what that operator holds. `ExplainConsolidation` is the group-scoped way
to ask where an individual memory stands.

**Import never trusts the group on the wire.** An archive is a file, so honouring the group written
in it would let a scoped caller place records in any partition by editing one. `Import`/`ImportBatch`
resolve the group from the verified claim instead: absent, the caller's sole group is stamped; if the
record names a group the token does not hold, the call is **refused** rather than silently re-filed.

An import is an upsert by id, so it is also refused if it names an id the store already holds in
another group (`ALREADY_EXISTS`, the answer a plain write with a colliding id gets), or a memory
whose `event_id` is another group's event (`NOT_FOUND`). Both are checked before anything is
written, so a refused batch leaves nothing behind. A link whose far end is outside the token's scope
is dropped, as `LinkMemories` drops one, rather than refused.

**An event can hold another group's memories**, if an unscoped or multi-group token attached them.
A scoped caller operating on their own event acts on their own memories of it and never on the
others: `DeleteEvent` and `DeleteEventsByFilter` with memories delete only the caller's, and
**detach** the rest (their `event_id` is cleared, since the event is going); `ReplaceMemoriesWithSummary`
and `SummariseMemories` replace only the caller's, and the summariser is never sent another group's
bodies. Every count in those responses covers the caller's memories only. A summary's own `group` is
stamped and checked exactly as a stored memory's is.

That matters for the embedded-ingestor pattern (a fleet of single-tenant edge instances transferring
into one centralised store). It works with no configuration at all when the edge's records carry no
group — they are stamped with the edge's own group on arrival — but an edge that sets group labels
locally will have its `Transfer` refused unless those labels match its token's scope. Either leave
`group` unset at the edge, or use the same label there as the transfer token carries.

**Pre-existing records carry no group** and are therefore invisible to a scoped token. Stamp them
before issuing scoped tokens against an existing store:

```sql
UPDATE memories SET group_name = 'default' WHERE group_name = '';
UPDATE events   SET group_name = 'default' WHERE group_name = '';
```

**This is a partition, not isolation** — see
[Group scoping and the trust boundary](security.md#group-scoping-and-the-trust-boundary) for what
it does and does not guarantee before relying on it.

### TLS

`tls.enabled` (`false` by default) turns on TLS for both the gRPC service and the HTTP gateway,
sharing one certificate/key pair and enforcing a **TLS 1.2 minimum** on both listeners (weaker
legacy protocol versions are refused):

```json
"tls": {
    "enabled": false,
    "certFile": "",
    "keyFile": "",
    "clientCaFile": "",
    "requireClientCert": false
}
```

Enabling authentication without `tls.enabled` logs a startup warning rather than refusing to
start — bearer tokens sent over plaintext are sniffable in transit, but some deployments
terminate TLS upstream (a reverse proxy or service mesh) rather than in the service itself, which
is a legitimate topology this doesn't try to prevent.

#### Mutual TLS

`tls.clientCaFile` names a PEM bundle of certificate authorities to verify **client** certificates
against, which turns on mutual TLS for both listeners. It is what the `certFile`/`keyFile` halves of
every client-side TLS block in this project — `opensearch.tls`, `transfer.tls`, `callbacks.tls`, the
MCP bridge, the `hippo` CLI, the event-source bridges — are for. Leave it empty (the default, and
what every release before this one did) and neither listener asks for a client certificate at all:
a client that offers one simply never sends it, and the handshake succeeds either way, which is the
failure mode this closes.

- `tls.clientCaFile` — the CA bundle. With it set, a client certificate that _is_ offered must
  verify against this bundle or the connection is refused. A client that offers none is still
  admitted, so the key is safe to turn on before every client has been issued a certificate.
- `tls.requireClientCert` — additionally refuse a connection that offers no certificate. It requires
  `tls.clientCaFile`: with no bundle nominated, Go verifies against the system roots, so "required"
  would admit any certificate any public CA has ever issued. The service refuses that combination at
  startup rather than accepting it.

Mutual TLS **composes with** the bearer-token authentication rather than replacing it, and the two
answer different questions: a certificate says which _process_ is connecting, a token says which
client it is acting as and at what tier. Nothing is derived from the certificate — no client id, no
role, no group scope — so [Authentication](#authentication) remains the single source of a caller's
authorisation.

One consequence worth planning for: `tls.requireClientCert` applies to the gateway's `/healthz` and
`/readyz` as well, because the handshake happens before the request has a path. An orchestrator's
probe must therefore carry a client certificate, or TLS must be terminated ahead of this listener.
The service logs a warning at startup when the two are combined.

### Storage

`storage.driver` selects the storage backend. The default, `sqlite`, is the embedded,
zero-dependency database every prior release used, stored in `storage.directory`. Setting it to
`postgres` stores everything in the PostgreSQL database named by `storage.postgres.dsn` instead,
and `mysql` in the MySQL database named by `storage.mysql.dsn` (go-sql-driver format, e.g.
`user:password@tcp(host:3306)/dbname`; the DSN must name a database schema):

```json
"storage": {
    "driver": "sqlite",
    "directory": "./data",
    "queryTimeoutSeconds": 60,
    "compression": {
        "enabled": true,
        "minBytes": 512
    },
    "pool": {
        "maxOpenConns": 25,
        "maxIdleConns": 0
    },
    "postgres": {
        "dsn": ""
    },
    "mysql": {
        "dsn": ""
    }
}
```

`storage.queryTimeoutSeconds` bounds how long any single statement or transaction may run (default
60; 0 leaves them unbounded). The default is comfortably above a full consolidation scan at the
benchmarked sizes, so a hung or unreachable database fails an operation after a bounded time instead
of blocking the request goroutine — and its pooled connection — indefinitely. Raise it above the
longest legitimate operation on a larger store, notably a full consolidation scan, or a sleep cycle
could be aborted mid-scan; set it to 0 to disable the bound (reasonable for embedded SQLite).
Within a sleep cycle the bound applies to each step on its own — a pass's scan, its delete
transaction, each per-event cleanup — never to the cycle as a whole.

On the `sqlite` driver `storage.directory` holds the database (`hippocampus.db` and its WAL
sidecars) plus a `hippocampus.lock` file. The service holds an exclusive operating system lock on
that file for as long as it runs, so a second process pointed at the same directory refuses to start
rather than run a second forgetting schedule over one store; there is no stale lock to clear, and
deleting the file releases nothing. See [The SQLite storage
lock](operations.md#the-sqlite-storage-lock).

#### Body compression

`storage.compression.enabled` (**default true**) stores memory bodies compressed. Storage is the
resource the whole service manages to, so what it buys is retention: the same
`consolidation.capacityBytes` target holds more memories, and forgetting starts later. What it costs
is CPU on every operation that touches a body — writes compress, and reads of the body
(`GetMemories`, `RecallMemories`, `SearchMemories`, export) decompress. Measured against the
database work it sits beside, that is about **2.4%** on a store-and-read round trip, against
savings of 4–8× on bodies that clear the size threshold; see
[Body compression](performance.md#body-compression) in the performance notes for the benchmarks.
The consolidation and eviction scans are unaffected: they read the covering index and never load a
body at all.

Set it to `false` for a workload that reads large pages of small, poorly-compressing bodies, where
the per-memory decompression multiplies without much storage to show for it.

The algorithm is gzip and is deliberately **not** configurable — a body written by one version of
the service has to stay readable by every later one, which a configurable algorithm would make a
matter of nobody ever changing the key. What is configurable is only whether new bodies are
compressed on the way in. (The compression _level_ is an encoder-side choice that any gzip reader
decodes regardless, so it carries no such commitment; the service uses the fastest one, which on
realistic bodies gives up almost no ratio.)

That setting can be changed at any point in a store's life. Each row records whether its own body
was compressed, and reads are driven entirely by that flag rather than by the current configuration,
so a store may hold a mix of both and every row still reads correctly. Turning compression on does
not rewrite the bodies already stored (they are compressed if and when they are next updated);
turning it off leaves every compressed row readable.

One consequence worth anticipating when it changes on an existing store: because the capacity target
counts stored bytes, the store's used figure — and with it the capacity pressure that scales the
deletion threshold — moves as new writes land under the new setting. Turning compression on makes a
store effectively larger, so it forgets **less** aggressively at the same `capacityBytes`; turning it
off does the reverse. Re-check `capacityBytes` against the behaviour you want after either change.

Three rules narrow what is actually compressed, so the feature cannot cost storage:

- Bodies below `storage.compression.minBytes` (default 512) are stored verbatim — small bodies
  compress poorly once gzip's own ~18-byte header and trailer are counted. A value below 64 is
  raised to it, since a smaller threshold only buys compression attempts that the next rule rejects.
- **Binary** memories are never compressed. Their bodies are client-encoded and as likely to be an
  already-compressed payload as anything else.
- A body that compression did not actually make smaller is stored verbatim. On incompressible
  content the worst case is therefore the CPU of the attempt, never a body that grew.

`UsedBytes` — and so the capacity target and eviction — accounts for what is really on disk, which
is the compressed size. Sizes seen elsewhere are the logical ones: the `memory.body_bytes` histogram
measures the body as the client sent it, and `memory.limit.sizeBytes` is likewise checked against the
body as submitted, not against its stored size.

Compression is confined to the storage layer. Everything above it — the RPCs, the OpenSearch index,
the summariser, and the export/archive format — sees plain bodies, so an archive is portable between
instances whatever either one's setting is; an import takes the receiving instance's policy.

#### Server drivers

`storage.pool.maxOpenConns` (default 25) and `storage.pool.maxIdleConns` (0 → defaults to
`maxOpenConns`) cap the connection pool on the `postgres`/`mysql` drivers, where `database/sql`
otherwise allows unlimited open connections and a burst of concurrent RPCs can exhaust the shared
database's connection slots. SQLite is always single-connection and ignores these. In a replicated
deployment keep the **sum** of `maxOpenConns` across every instance below the server's
`max_connections`, leaving headroom for the consolidator's instance-lock keepalive connection and
any superuser reserve — see [Operations](operations.md#connection-pool-sizing-server-drivers).

MySQL support requires MySQL 8.0.20 or later (the upserts use the `ON DUPLICATE KEY UPDATE` row
alias). One MySQL-specific bound: ids are `VARCHAR(255)` there (MySQL cannot index an unbounded
`TEXT` column), so client-supplied event and memory ids longer than 255 characters are rejected
by that driver; generated UUID ids are unaffected.

Exactly one instance may run consolidation against a given store. With SQLite that is one instance
full stop — the embedded database cannot be shared between processes, and a second one pointed at
the same `storage.directory` is refused at startup by [the storage
lock](operations.md#the-sqlite-storage-lock). With PostgreSQL or MySQL the
_consolidating_ instance takes a session-scoped advisory lock at startup (MySQL: a `GET_LOCK` lock
scoped to the schema name); a second instance that also has `consolidation.enabled: true` refuses
to start, rather than silently running concurrent consolidation cycles against shared data.
Additional instances with `consolidation.enabled: false` skip the lock and run alongside it as
read/write replicas — see [Deployment model](operations.md#deployment-model-one-consolidating-instance-per-store).
A replica with `consolidation.standby` set also polls the lock every
`consolidation.standbyPollSeconds` (15) and takes over consolidation when it wins, which is
automatic failover; startup refuses it on SQLite, which has no shared lock, and beside
`consolidation.enabled: true`.

Both capacity axes (`consolidation.capacityMemories` and `consolidation.capacityBytes`) work
with every driver, but the byte measure differs. SQLite reads the database's pages excluding
the freelist; the server drivers estimate the live rows directly (payload bytes plus the same
fixed per-row allowance eviction uses when estimating freed bytes), because no server file-size
measure ever shrinks after deletes — Postgres's autovacuum and InnoDB's purge make freed space
internally reusable without returning it to the filesystem, so a `pg_database_size()`-style
reading would sit at its high-water mark and keep eviction firing against a figure that cannot
drop. The estimate costs one scan of the two tables per sleep cycle, and only when a byte
capacity is configured. `consolidation.walTriggerBytes` remains SQLite-only (it measures the
on-disk WAL file, which has no server-driver counterpart) and is rejected at startup. There is
also no `Preserve` compaction step on the server drivers — their background reclamation already
handles dead rows continuously.

### Content search

Recall is normally by id, event, or time/significance range. `SearchMemories`
(`POST /v1/memories/search`) adds one more read path: it finds memories whose body matches a query,
most relevant first, optionally restricted to one event and/or one `group` label.

There are two backends, and **you get one without configuring anything, on every driver**:

| Backend     | When it is used                          | Drivers | Modes                                                                                        |
| ----------- | ---------------------------------------- | ------- | -------------------------------------------------------------------------------------------- |
| Store index | `opensearch.enabled` false (the default) | all     | Keyword. An index inside the same database — no cluster, no configuration.                   |
| OpenSearch  | `opensearch.enabled` true                | all     | Keyword, plus [semantic and hybrid](#semantic-search) when an embedding model is configured. |

A log line at startup reports which backend was selected. `SearchMemories` returns
`FAILED_PRECONDITION` only where neither is available, and `WhoAmI.search_modes` reports what a
deployment can actually serve, so a client can feature-detect rather than search-and-fail.

Both backends are strictly **secondary**: the primary store remains the system of record, results
are always re-read from it, and binary memories (`is_binary`) are never indexed by either. The index
is created and, on an existing store, populated at startup — upgrading needs no manual step.

On the server drivers it sits outside the [capacity target](consolidation.md#capacity-target), like the
forgotten log: it is derived data, and letting the record of what is searchable raise capacity
pressure would evict live memories to make room for it. On `sqlite` it cannot — page accounting
cannot exclude a table in the same file — so the index is inside `capacityBytes` there, and search
makes the same target hold fewer memories. Either way it is disk to size for.

#### Turning the store index off

```json
"search": {
    "contentIndex": {
        "enabled": true
    }
}
```

- `search.contentIndex.enabled` — whether this store keeps a content index of its own. **Derived
  when unset**: on with `opensearch.enabled` false, off with it true. Set it to override the
  derivation in either direction; a startup line reports the choice and its reason.

The default is derived because the two backends are alternatives and only one is selected. With
OpenSearch configured, the store's own index is written on every memory — inside the storage
boundary, before compression sees the body — and then read by nothing for the life of the store.

It is worth turning off because it is the **largest non-body cost the store carries**, on every
driver. Measured over 20,000 memories of log-shaped JSON: on `sqlite` it is 43–59% of the payload,
and at 4 KiB bodies the index is larger than the compressed bodies it indexes — the column gets
gzip, the index gets the plain text. On `postgres` the `tsvector` table with its GIN index is 22 MiB
against a 4.9 MiB payload. On `mysql`, where a `FULLTEXT` index is an index on a _column_, the table
holds a second uncompressed copy of every body: 40 MiB against 19.5 MiB.

Two things to know before setting it:

- **Disabling drops the index; it does not merely stop maintaining it.** An index that stops being
  written does not become empty, it becomes _wrong_ — it would go on answering from a subset that
  shrinks with every consolidation cycle, and a search silently returning some of the matches is
  worse than one that refuses. With it dropped, `SearchMemories` answers `FAILED_PRECONDITION` and
  `WhoAmI.search_modes` reports the absence, so a client feature-detects rather than search-and-fails.
- **Re-enabling rebuilds it automatically**, on the next startup, by the same path a store written
  before content search existed takes. On a large store that is one full pass over `memories` during
  startup. `--backfill-search` is not needed.

Turning it off with `opensearch.enabled` also false is a coherent choice — a store nobody searches
by content — and is warned about at startup rather than refused, since `SearchMemories` will then
reject every call.

#### Semantic search

Keyword search finds memories that used your words. Semantic search finds memories that meant what
you meant — a search for "deployment problem" surfaces one that only ever said "the rollout broke".

It needs two things keyword search does not, and **neither implies the other**: an embedding model
to turn text into vectors, and OpenSearch's k-NN index to store and search them. The store's own
index has no equivalent on any driver — on `sqlite`, giving it vectors would mean either a cgo
extension (costing the pure-Go build every deployment target depends on) or a scan whose cost grows
with the store; on `postgres`, `pgvector` could do it, but vectors would then have to live in the
primary store, reversing a deliberate capacity decision, so it is a separate question rather than
part of the keyword work. Semantic search is therefore an OpenSearch capability today, on every
driver.

```json
"llm": {
    "embedding": {
        "enabled": false,
        "provider": "ollama",
        "address": "http://localhost:11434",
        "apiKey": "",
        "model": "nomic-embed-text",
        "dimensions": 768,
        "timeoutSeconds": 30,
        "batchSize": 32
    }
}
```

- `llm.embedding.enabled` — off by default. Startup **fails** if this is on without
  `opensearch.enabled`: the vectors would have nowhere to go, so every write would pay for an
  embedding nothing could ever search.
- `llm.embedding.provider` — `ollama` (the default, Ollama's native `/api/embed`) or `openai` (any
  endpoint speaking the OpenAI embeddings API). It is **separate from `llm.provider`**: nothing
  requires the two halves to share an endpoint, and generating against a hosted model while
  embedding against a local Ollama is both reasonable and much cheaper. See
  [Model providers](#model-providers).
- `llm.embedding.address` — the base URL. Under the `openai` provider it is taken exactly as given
  and normally ends in the version path (`https://api.openai.com/v1`); startup refuses an `openai`
  provider still pointing at the Ollama default.
- `llm.embedding.apiKey` — sent as a bearer token when set. Injectable as
  `HIPPOCAMPUS_LLM_EMBEDDING_APIKEY`, and it should be: see [Environment variable overrides](#environment-variable-overrides).
- `llm.embedding.model` — must be an embedding model, not a generation model. It may share a
  server with the [summariser](#summarisation-embedded-llm).
- `llm.embedding.dimensions` — must match the model (`nomic-embed-text` 768, `all-minilm` 384,
  `mxbai-embed-large` 1024, `text-embedding-3-small` 1536). A mismatch is rejected with both numbers
  named. Under the `openai` provider it is also **sent** as the API's optional `dimensions`
  parameter, which the Matryoshka-trained models honour by truncating their output — so an index
  created at 768 can be matched without changing model. A model that ignores the parameter returns
  its native width and the mismatch check catches it.
- `llm.embedding.maxTextBytes` — how much of a body is embedded, defaulted rather than unbounded
  because an embedding model has a context window and a long body would otherwise be refused by it.
  A longer body is truncated on a rune boundary, so **only its opening is searchable by meaning**
  while all of it stays searchable by keyword. Raise it for a store of long documents, within
  whatever the model accepts.
- `llm.embedding.timeoutSeconds` / `llm.embedding.batchSize` — bound one call and how many texts go
  in it. Batching matters for `--backfill-search`, where one request per memory would be dominated
  by round trips.

Choose a mode per search with `SearchMemories`' `mode` field — `keyword` (the default, so existing
callers are unchanged), `semantic`, or `hybrid`. **`WhoAmI` reports which modes the deployment can
serve**, so a client can adapt rather than discover an unavailable one by having a search rejected.

**Hybrid is usually the best of the three.** Semantic search alone misses exact terms — error
codes, identifiers, names — and keyword search alone misses paraphrase. Hybrid runs both and fuses
their _rankings_ (not their scores, which are a BM25 relevance and a cosine similarity and share no
scale), so a memory found by both routes outranks one found by only one.

**Semantic search has no relevance cutoff.** k-NN returns the _nearest_ `limit` memories, not the
ones above some similarity bar, so a semantic search of a small store returns almost everything —
correctly ordered, but with no "no matches" answer the way keyword search gives one. Use `hybrid`,
or a smaller `limit`, where that matters.

Three further consequences worth knowing before enabling it:

- **The model server is on the write path.** Bodies are embedded as they are stored, so a slow one
  adds latency to every write. A failure costs that memory its vector, never the memory itself —
  it stays stored and keyword-searchable, and a rebuild can supply the vector later.
- **Vectors are not kept in the primary store**, only in the index. At 768 dimensions an embedding
  is ~3 KiB per memory, which would compete for the capacity [compression](#body-compression)
  exists to save. The trade is that rebuilding the index **re-embeds** rather than re-reads, so
  `--backfill-search` then needs the model server up.
- **The reconciliation sweep re-embeds what it heals.** It must, or it would replace documents with
  vectorless copies and silently strip them from semantic search. Since it asks the index which
  documents are actually missing before writing anything, that cost is now paid for the absences
  rather than for the whole store on every pass — it used to re-embed every memory, every sweep. A
  document that is present but *vectorless* (indexed while the model server was down) is not healed
  by the sweep; `--backfill-search --reindex` is what covers that.

**Enabling it on an existing OpenSearch deployment requires a rebuild.** `index.knn` is a static
setting fixed at index creation, so an index built before semantic search cannot gain a vector
field in place. The service detects this at startup and says so; run
`--backfill-search --reindex` to rebuild. The same applies to changing the model or its dimensions.

#### Ranking

A search engine ranks by how well the text matched. This store knows two things a search engine
does not — how significant each memory is, and how often it has been recalled — and by default it
uses them, so that among memories that matched about equally well the ones the store rates higher
come back first.

```json
"search": {
    "significanceWeight": 0.3,
    "recallWeight": 0.2
}
```

- `search.significanceWeight` (default **0.3**) — how much a memory's significance promotes it.
- `search.recallWeight` (default **0.2**) — how much being recalled often promotes it. Recall
  counts are damped before use, so the difference between never recalled and recalled twice counts
  for far more than the difference between 500 and 1000 — which matches how recall counts actually
  distribute.
- Set **both to 0** for pure text-relevance order.

**Relevance still leads.** The three signals are scaled against the strongest in the result set and
combined, with relevance weighted 1 — so at the default weights significance and recall reorder
near-equal matches rather than displace a clearly better one. Raising a weight above 1 inverts
that; a negative weight deliberately demotes.

The ranking is applied by the service, above whichever backend served the query, so both backends
order results identically and significance and recall are read from the primary store at query
time — always current, never a stale copy propagated into an index.

One consequence is worth knowing: the backend applies the limit, so re-ranking only sees the
candidates the backend already chose. The service asks for several times the requested number when
ranking is active, giving a significant memory ranked just outside your page room to be promoted
into it, but a memory the text match ranked far down cannot be rescued by significance alone.

A **reinforcing** search (`reinforce: true`) reinforces exactly the memories it returns, never the
wider candidate set — the extra candidates are read but never recalled, so searching does not reset
the decay clock on memories you were not shown.

#### The store's own index

The default, on **every** driver. Matching is an OR over the query's words — the same semantics as
the OpenSearch backend's, so moving between the two changes scale, not results.

It is one feature with three implementations, and the differences are worth knowing before choosing
a driver:

| Driver | Index | Second copy of the body? | Notes |
| ---------- | ----------------------------------- | ------------------------ | -------------------------------------------------------------------------------------------------------- -|
| `sqlite` | FTS5 virtual table, contentless | No | No cgo and no extra dependency: `modernc.org/sqlite` is built with FTS5. |
| `postgres` | `tsvector` table under a GIN index | No | Text search configuration `simple`: no stemming, no stopwords. |
| `mysql` | `FULLTEXT` index over a text column | **Yes** | A `FULLTEXT` index indexes a column, so the index table holds an uncompressed copy of every indexed body. |

Two MySQL server settings show through and have no counterpart on the other two: a token shorter
than [`innodb_ft_min_token_size`](https://dev.mysql.com/doc/refman/8.4/en/innodb-parameters.html)
(3 by default) matches nothing, and InnoDB's built-in stopword list drops about three dozen common
English words. Both are server-level settings rather than anything this schema states.

Query text is treated as **words, not as a query language**, on every driver: it is split into bare
alphanumeric tokens, each quoted as a literal, and the tokens OR-ed. So FTS5's operators (`AND`,
`NEAR`, `*`, `column:`), `tsquery`'s (`&`, `|`, `!`) and MySQL's boolean-mode ones (`+`, `-`, `~`)
are all neutralised rather than honoured: no input is a syntax error and none can reach into the
query's structure. Ranking still favours memories matching more of the words.

Relevance is each engine's own measure (bm25, `ts_rank`, InnoDB's boolean relevance), normalised so
that a higher score is always a better match. The **order** is comparable between drivers; the
magnitudes are not.

Only the first 512 KiB of a body is indexed, on every driver — a limit one of them enforces natively,
applied to all three so that what is findable is a property of the store rather than of the driver
it happens to run on.

What differs from OpenSearch, and mostly in this backend's favour:

- **It cannot go stale.** The index is maintained inside the write itself, not by an asynchronous
  worker, so there is no propagation queue to overflow and no reconciliation sweep to wait for. A
  memory is findable as soon as `StoreMemory` returns.
- **Deletes cannot drift.** They are handled by the storage engine — a trigger on `sqlite`, a
  cascading foreign key on the server drivers — so every path that removes a memory (consolidation,
  eviction, purge, summary replacement) is covered by construction, in the same transaction.
- **No second copy of your content**, on two of the three, and none of it outside the primary store.
  `sqlite` and `postgres` hold an inverted index — the words, without their order or punctuation —
  rather than the bodies, so unlike an OpenSearch deployment there is no second system holding your
  text. Size is a weaker claim than it sounds: for short bodies a `tsvector` is not much smaller
  than the text it came from, so budget disk for the index on any driver.
- **Upgrades populate it automatically.** A database written before this existed gains the index on
  the next startup, and it is filled from the memories already stored — no backfill step.
- It has no [semantic search](#semantic-search), which needs vectors and an engine that can search
  them, and on `sqlite` it is bounded by the single instance where OpenSearch scales independently.

The one drift it can suffer is an index write that failed and was logged rather than failing its
memory, leaving a memory stored but unfindable.
[`--backfill-search`](#backfill-and-reindex) rebuilds the index to repair that; with no OpenSearch
configured, that flag rebuilds this index instead. It **writes to the database**, so stop the
service first.

#### OpenSearch

**Enabling on a store that already has data:** the index starts empty and nothing already stored is
retroactively indexed, so existing memories stay unsearchable until they are re-indexed. Run a
one-time [`--backfill-search`](#backfill-and-reindex) to populate it immediately; on the
consolidating instance the [self-healing sweep](#self-healing-reconciliation) also fills it within
one `reconcileIntervalSeconds`, but backfill is instant.

```json
"opensearch": {
    "enabled": false,
    "addresses": ["http://localhost:9200"],
    "username": "",
    "password": "",
    "index": "hippocampus-memories",
    "queueSize": 1024,
    "reconcileIntervalSeconds": 3600,
    "reconcileBatchSize": 500,
    "staleSweep": true,
    "outbox": {
        "maxRows": 1000000,
        "maxAgeHours": 24
    },
    "applyTimeoutSeconds": 0,
    "applyMaxAttempts": 0,
    "applyRetryBaseBackoffMillis": 0,
    "closeDrainTimeoutSeconds": 0,
    "tls": {
        "caCertFile": "",
        "certFile": "",
        "keyFile": "",
        "insecureSkipVerify": false
    }
}
```

The index worker's retry/drain behaviour is tunable, each defaulting (0) to a built-in value:
`applyTimeoutSeconds` bounds one operation against the cluster (default 10s), `applyMaxAttempts`
caps retries of a transient failure before dropping (default 4), `applyRetryBaseBackoffMillis` is
the wait before the second attempt, doubling with jitter thereafter (default 250ms), and
`closeDrainTimeoutSeconds` bounds how long shutdown waits for the queue to drain (default 5s). Raise
them for a slower cluster where the defaults drop too many operations before the
[reconciliation sweep](#self-healing-reconciliation) heals them.

```sh
curl -X POST http://localhost:8080/v1/memories/search \
    -H 'Content-Type: application/json' \
    -d '{"query": "quarterly forecast", "limit": 5, "reinforce": true}'
```

OpenSearch is strictly a **secondary index** — the primary store remains the system of record
for every existence, consolidation, and recall decision:

- Writes and deletes (including the sleep cycle's consolidation and eviction, purges, event
  merges, and summarisation) propagate to the index asynchronously and best-effort: an
  unreachable or lagging cluster never fails or slows a primary operation. The worker retries a
  transient cluster failure a few times with backoff before giving up, so a brief blip does not
  lose a write. A full propagation queue (`opensearch.queueSize`, 1024) still drops operations rather
  than blocking — but see [Self-healing](#self-healing-reconciliation) below, which recovers anything
  dropped. Each drop is counted on `hippocampus.search.dropped` with a `reason` of `queue_full` or
  `apply_failed`; the log line is a summary every 30 seconds rather than one line per drop, which at
  the rate this actually fires was measured filling a 4 GB journal with one repeated sentence. Sizing
  the queue on evidence, and why a bigger one is usually not the answer, is in
  [Running the OpenSearch content index](operations.md#running-the-opensearch-content-index).
- Search results are always re-read from the primary store; ids the index returns that the
  primary no longer holds are silently dropped. A stale index can therefore miss recent writes
  (indexing is asynchronous on top of OpenSearch's ~1s near-real-time refresh) or carry leftover
  documents, but it can never fabricate a result.
- By default finding a memory does not reinforce it — exploratory search must not distort the
  decay model. Setting `reinforce` on the request routes the matches through recall instead,
  resetting their decay clocks and raising their effective significance, exactly as
  `RecallMemories` does.
- Binary memories (`is_binary`) are never indexed; their bodies are opaque.
- With `opensearch.enabled` false (the default) every driver falls back to
  [the store's own index](#the-stores-own-index), which is keyword-only.

The index is fully rebuildable from the primary store (re-storing memories re-indexes them), so
losing it costs search availability, nothing more.
Try it with `docker compose -f deploy/compose/docker-compose.opensearch.yaml up --build` (security disabled —
demo only). Integration tests run against any disposable cluster via
`HIPPOCAMPUS_TEST_OPENSEARCH_URL=http://localhost:9200 go test ./search`.

#### Securing the connection

The bodies of non-binary memories are indexed into OpenSearch as searchable text, so a
content-search deployment holds a **second plaintext copy** of that content outside the primary
store. Treat the cluster as needing the same protection as the primary store, not less.

- **Authentication.** Set `opensearch.username`/`opensearch.password` for a cluster running the
  security plugin. Inject the password as a secret rather than committing it: the environment
  variable `HIPPOCAMPUS_OPENSEARCH_PASSWORD` overrides `opensearch.password` (see
  [Environment variable overrides](#environment-variable-overrides)).
- **Transport encryption.** Give `opensearch.addresses` an `https://` URL. With no `tls` block the
  server certificate is verified against the host's system certificate pool. The optional
  `opensearch.tls` block configures the rest:
  - `caCertFile` — a PEM bundle of certificate authorities to trust for the server certificate, in
    place of the system pool. Set this to trust a cluster serving a certificate signed by a private
    CA, **including OpenSearch's own security plugin, which bootstraps self-signed certificates by
    default**. This is the production-correct alternative to disabling verification.
  - `certFile` / `keyFile` — a client certificate and key for mutual TLS; set both or neither.
  - `insecureSkipVerify` — disables server certificate verification entirely. It logs a startup
    warning and is a **development-only** escape hatch for self-signed certificates; prefer
    `caCertFile` in production, where an unverified connection offers no protection against
    interception.

  A malformed `tls` block (an unreadable or empty CA bundle, a half-configured client certificate
  pair, an unloadable key) fails startup rather than silently downgrading security. The same block
  applies to the `--backfill-search` CLI mode.

For a secured reference stack — security plugin enabled, HTTPS, credentials via the environment —
use `docker compose -f deploy/compose/docker-compose.opensearch-secured.yaml up --build` (it uses
`insecureSkipVerify` only because the demo image's certificates are self-signed; the file's header
comment explains the `caCertFile` swap for production).

#### Self-healing reconciliation

Because propagation is asynchronous, a document can still go missing — an operation dropped under
queue overflow, lost to a crash before the worker drained, or missed while the cluster was
unreachable long enough to exhaust the worker's retries. Rather than leave that gap open until an
operator runs a manual backfill, the **consolidating instance** runs a periodic reconciliation
sweep. For each page of memories it asks the index which of those ids it does **not** hold, in one
request, and writes only those. It is controlled by two keys:

- `opensearch.reconcileIntervalSeconds` (default `3600`) — how often a sweep runs; the interval is
  measured from the end of one sweep to the start of the next. `0` (or negative) disables it.
- `opensearch.reconcileBatchSize` (default `500`) — how many memories each page reads, and how many
  ids one presence probe asks about; the sweep pauses briefly between pages.

**Asking first is what makes the sweep affordable**, and it writes nothing at all against a healthy
index. Re-indexing every memory unconditionally — which is what it used to do — cost three things
that all grew with the store: it became the dominant producer on the very queue it exists to
compensate for, so live writes were the operations dropped to make room for re-writes of documents
already present; with semantic search on it re-embedded the entire store on every pass; and in Lucene
a re-index is a delete plus an insert **even when the document is byte-identical**, so an hourly sweep
tombstoned the whole index once an hour. `hippocampus.search.documents_healed` counts what it
now writes, which is the first direct measure of how much is being lost in propagation. See
[Running the OpenSearch content index](operations.md#running-the-opensearch-content-index) for the
deleted-document accounting that follows from all this.

The sweep runs only on the instance with `consolidation.enabled: true` (the single owner of index
maintenance), so replicas never duplicate it, and it starts a short while after launch so a sparse
index is healed soon after a restart rather than a whole interval later. It runs for the **OpenSearch
backend only**: the [store's own content index](#content-search) is maintained inside the primary
write, so nothing there can be dropped and there is nothing to reconcile.

It runs in **both directions**. The forward pass above heals _missing_ documents. The **stale pass**
enumerates the index and removes documents whose memory the primary store no longer holds:

- `opensearch.staleSweep` (default `true`) — set `false` to run the forward pass only.

The stale pass shares `reconcileBatchSize` and the same pacing, and removes only what the primary
store says is gone — so the two directions converge rather than fight (the forward pass indexes
anything the stale pass should not have removed). Turning it off leaves stale documents to
`--backfill-search --reindex`, as before.

#### The delete outbox

A stale document was once merely wasted space: search results are re-verified against the primary
store, so a caller never sees one. That stops being true at volume. Propagation to OpenSearch is a
bounded queue that **drops on overflow**, and while a dropped _index_ operation is self-correcting —
the memory still exists, so the sweep above re-indexes it — a dropped _delete_ is not, because
nothing afterwards knows the document should have gone. Under any sustained write rate above the
queue's drain rate the index diverges permanently. A live deployment was measured holding twenty-one
documents for every row the store actually had.

Enlarging `queueSize` does not fix it: every queue is finite, and the loss happens at the enqueue
boundary, so the dropped operation never entered the queue to be made durable.

So a deletion is recorded in the **same transaction as the memory delete itself**, in a
`search_outbox` table, and a worker on the consolidating instance drains it — claiming rows, applying
the deletions synchronously (bypassing the lossy queue), and only then removing them. A crash between
the two replays the deletion rather than losing it; re-deleting a document that is already gone is a
no-op. This is not a new guarantee for the product so much as parity: the built-in SQLite FTS backend
has always had it, because its deletes are an `AFTER DELETE` trigger inside the same transaction.

The queue is enabled automatically whenever OpenSearch is the active backend, and bounded by two
keys:

- `opensearch.outbox.maxRows` (default `1000000`) — the newest N queued deletions are kept.
- `opensearch.outbox.maxAgeHours` (default `24`) — queued deletions older than this are discarded.
  Hours rather than days, deliberately: this queue is meant to drain in seconds, so a day of backlog
  is already an outage.
- `opensearch.outbox.maxBytes` (default `0`, no bound) — the same bound stated in the unit a disk is
  sized in. These rows are fixed width (an id, a timestamp and a surrogate key, charged 75 bytes on
  SQLite, 120 on PostgreSQL and 185 on MySQL), so this converts to a row cap exactly and the tighter
  of the two wins; the row cap above is already roughly 75, 120 or 185 MB. It is not defaulted
  because it would be that same bound said twice.

Reaching either cap logs a warning and increments `hippocampus.search.outbox.abandoned`; what is
discarded becomes the stale pass's job to find. Watch `hippocampus.search.outbox_depth` — sustained
growth is the index failing to keep up, which the old in-memory queue had no way to report at all.

Like the [callback queue](#when-the-receiver-is-down), the outbox is **excluded from the capacity
target**, and for the same reason: it grows precisely when deletions are backing up, so counting it
would raise capacity pressure and evict live memories to make room for the record of memories
already deleted. It is not excluded from the disk — at the default `maxRows` a stuck index can hold
a million queued rows that eviction will never notice — so budget for it alongside `capacityBytes`.
See [The capacity target bounds the memories, not the
database](operations.md#the-capacity-target-bounds-the-memories-not-the-database).

#### Backfill and reindex

The reconciliation sweep above heals a missing document on its own, but two cases still want an
immediate, synchronous rebuild: enabling `opensearch.enabled` on an existing database (the whole
index is empty and you do not want to wait for a sweep), and clearing _stale_ documents the sweep
deliberately leaves behind. The backfill CLI mode covers both:

```sh
hippocampus --backfill-search -c config.json            # index every non-binary memory
hippocampus --backfill-search --reindex -c config.json  # delete and recreate the index first
```

Like `--mint-token`, this runs and exits without starting the server. It streams every non-binary
memory from the primary store in id-keyed batches (`--backfill-batch-size`, default 500) and
indexes each one synchronously, keyed by id — runs are idempotent (each write overwrites the same
document) and abort on the first error, so a failed run is simply rerun. `--reindex` deletes and
recreates the index before backfilling, which also removes stale documents for memories the
primary store no longer holds; without it, existing documents are left in place and overwritten.

The tool may run alongside a live service instance: it opens the store read-only, so SQLite's WAL
admits it as a cross-process reader without taking [the storage
lock](operations.md#the-sqlite-storage-lock), and the Postgres open skips the single-instance
advisory lock. The one caveat to
a live run is that a memory deleted by the service mid-backfill can be re-indexed after its
deletion propagated, leaving a stale document — harmless for reads (results are re-verified
against the primary store) and cleared by the next `--reindex` run.

**Without OpenSearch**, the same flag rebuilds
[the store's own index](#the-stores-own-index) instead — on every driver — and behaves differently
in two ways that matter. It is rarely needed: that index is populated automatically at startup and
maintained inside every write, so reach for it only when a memory is stored but not findable, which
means an index write failed and was logged. And it **writes to the service's own database**, so
unlike the OpenSearch backfill it must not be run beside a live instance: stop the service first. On
the `sqlite` driver that is enforced — it opens read-write and so takes [the storage
lock](operations.md#the-sqlite-storage-lock), refusing to start while a service holds it. On the
server drivers it is not, and the consequence is not corruption but a window in which the index has
been emptied and not yet refilled, during which a live instance answers searches with less than it
holds. `--reindex` and `--backfill-batch-size` do not apply; the rebuild always clears and
repopulates.

### Summarisation (embedded LLM)

By default summaries are authored by the client (`ReplaceMemoriesWithSummary`, see
[Summarisation](consolidation.md#summarisation)). Enabling the optional embedded LLM lets the
service author them itself: the `SummariseMemories` RPC (`POST /v1/events/{event_id}/summarise`)
reads an event's memories, generates a summary via the model, and replaces them with it; and
`llm.autoSummarise` makes the sleep cycle do the same for each scan candidate. Off by default; when
disabled `SummariseMemories` returns `FAILED_PRECONDITION` and auto-summarisation is a no-op. The
summariser is the one component that reads memory content, and it sends memory bodies to whichever
model server is configured — see the
[security guide](security.md#where-memory-content-can-leave-the-process).

```json
"llm": {
    "enabled": false,
    "provider": "ollama",
    "address": "http://localhost:11434",
    "apiKey": "",
    "model": "llama3.2",
    "autoSummarise": false,
    "timeoutSeconds": 120,
    "maxMemories": 200,
    "promptCharLimit": 32000,
    "systemPrompt": "",
    "temperature": 0
}
```

`enabled`/`provider`/`address`/`model` are the core settings; the rest have sensible defaults
(`maxMemories` and `promptCharLimit` bound the prompt so a large event cannot overrun a small model's
context; `systemPrompt` empty uses a built-in memory-consolidation instruction; `temperature` 0 uses
the model default and is omitted from the request entirely, which the models that reject an explicit
temperature require). Binary memories are excluded from the prompt (their bodies are opaque). Deploy
Ollama with the optional `ollama` compose profile (see `docker-compose.yaml`), with the configured
model pulled (`docker compose exec ollama ollama pull <model>`). For the full behaviour, see
[Summarisation → Embedded LLM (Ollama)](consolidation.md#embedded-llm-ollama).

#### Model providers

`llm.provider` and `llm.embedding.provider` select which client is built. They are independent, and
each defaults to `ollama`.

| Provider | Endpoint                                             | Use it for                                                                                                                                                  |
| -------- | ---------------------------------------------------- | ----------------------------------------------------------------------------------------------------------------------------------------------------------- |
| `ollama` | `{address}/api/generate`, `{address}/api/embed`      | A local [Ollama](https://github.com/ollama/ollama), the default                                                                                             |
| `openai` | `{address}/chat/completions`, `{address}/embeddings` | OpenAI, Azure OpenAI, vLLM, llama.cpp's server, LiteLLM, OpenRouter, a Bedrock or Anthropic gateway, a corporate proxy — and Ollama, which serves `/v1` too |

The `openai` provider exists because the constraint is not "you must run Ollama": it is that **a
deployment that already has a sanctioned model endpoint could not use it**, and would have had to
stand up a second, unsanctioned inference server beside the memory store to summarise anything. That
is the case `deploy/compose/docker-compose.corporate.yaml` is otherwise written for.

Three things to know about `address` under the `openai` provider:

- **It is taken exactly as given**, so it normally ends in the version path —
  `https://api.openai.com/v1`, `https://openrouter.ai/api/v1`, `http://localhost:11434/v1` for
  Ollama's own compatible API. That is the `base_url` convention every OpenAI SDK uses, which is what
  an operator already has to hand; a `/v1` guessed on the end here would break every gateway that
  mounts the API somewhere else.
- **Startup refuses an `openai` provider left on the Ollama default address.** The defaults describe
  the default provider, so an unfilled address would point at an Ollama port and answer 404 to every
  call — which reads as a model server that is up and refusing rather than as a setting nobody
  filled in.
- **`apiKey` is sent as a bearer token, and is honoured by the `ollama` provider too** rather than
  ignored there, because an Ollama behind an authenticating proxy is a real deployment. A rejected
  key is reported as an outright failure naming the setting, not as a degraded dependency: it will
  fail every call.

Both keys are secrets and belong in the environment rather than the file —
`HIPPOCAMPUS_LLM_APIKEY` and `HIPPOCAMPUS_LLM_EMBEDDING_APIKEY`, see [Environment variable overrides](#environment-variable-overrides).

> **Renamed in v0.42.0.** This block was `ollama.*`; it is now `llm.*`, key for key. The old names
> are still read — each is copied onto its replacement at startup, with one `WARN` naming every
> legacy key still in use, and `--check-config` reports them too — but they are deprecated and will
> be removed. An explicit `llm.*` value always wins over the legacy one, so the two can be set
> together while a deployment migrates. The block was renamed because it stopped being about Ollama:
> `ollama.address` naming an Azure endpoint reads as a mistake, and an operator looking for how to
> point the service at their own gateway would not have thought to look under it.

### Outbound callbacks

Everything else the service offers about forgetting is **pull**: `PreviewConsolidation` asks what
would go, `ExplainConsolidation` where one memory stands, `GetConsolidationStatus` when the next
cycle is due, and `GetForgottenMemories` what went. Each needs a client to be asking. Callbacks are
the push half — the service tells a configured HTTP endpoint that it has forgotten something, or
that a sleep cycle has finished — so a system that treats Hippocampus as its forgetting front-half
(an archive tier, a cache to invalidate, an index elsewhere) learns about a deletion instead of
discovering it by asking for a record and finding nothing.

Off by default. Enabling it needs a URL and nothing else:

```json
"callbacks": {
    "enabled": true,
    "url": "https://receiver.example.com/hippocampus",
    "token": "",
    "signingSecret": "",
    "timeoutSeconds": 10,
    "allDeletions": false,
    "includeBodies": false,
    "maxBodyBytes": 65536,
    "maxIdsPerDelivery": 500,
    "maxBytes": 0,
    "events": {
        "memoryForgotten": true,
        "eventForgotten": true,
        "sleepCompleted": true
    },
    "tls": {
        "enabled": false,
        "caCertFile": ""
    }
}
```

#### It is backed by a persisted queue, and that is the point

A delivery is recorded **in the same database transaction as the deletion that produced it**, and a
background worker sends it afterwards. There is no in-memory queue and so no boundary at which a
notification can be dropped; a crash between the deletion and the delivery replays on restart, and a
receiver that is down for an hour is an hour of table growth rather than an hour of silent loss.

That matters more here than anywhere else in the service, because a callback about a deletion cannot
be reconstructed after the fact. Every other thing the service tells the outside world can be asked
for again. Once a memory is gone, a notification nobody received is simply lost.

Delivery is therefore **at-least-once**: a delivery is removed from the queue only once the receiver
has returned a 2xx, so a response that never arrives means the delivery is sent again. Receivers
should be idempotent. `cycle_id` and the chunk numbering are what let one recognise a repeat.

#### What a delivery carries

A POST of JSON, one per batch — a consolidation chunk that removed five hundred memories is **one**
request, not five hundred:

```json
{
  "kind": "memory_forgotten",
  "cause": "consolidation",
  "queued_at": 1788476468760678000,
  "cycle_id": 1788476468000000000,
  "items": [
    {
      "id": "m-1",
      "event_id": "e-1",
      "group": "svc-a",
      "significance": 3,
      "bytes": 118
    }
  ]
}
```

`kind` is one of `memory_forgotten`, `event_forgotten`, `sleep_completed` or `memories_at_risk`, and
with `callbacks.events.memoryWrites` also `memory_stored` and `memory_updated` (see below).
`cause` is why: `consolidation`, `eviction` or `expiry` (the three forgetting passes), or — only
with `allDeletions` — `client`, `clear`, `cascade`, `summary_replace` or `purge`. `cycle_id` groups
every delivery one sleep cycle produced, including its warning and its completion, so a receiver can
assemble a whole cycle without keeping state.

A `sleep_completed` delivery adds a `cycle` object (the trigger, the counts, the bytes freed, whether
it succeeded) and carries the ids the cycle forgot, **chunked** at `maxIdsPerDelivery` with `chunk`
and `chunks` numbering them from 1 — a cycle that forgets ten thousand memories must not become one
unbounded request. Every chunk repeats the `cycle` summary, so a receiver that misses one still knows
what the cycle did. An item whose `id` and `event_id` are the same names an event rather than a
memory.

#### Being told _before_ a memory goes

`memory_forgotten` arrives too late to act on: by the time a receiver reads it, the memory it might
have wanted to summarise, archive elsewhere or recall is gone. `memories_at_risk` is the kind that
speaks first. It is raised at the **top** of a sleep cycle, from the same scan `PreviewConsolidation`
runs, and describes what the store is about to lose — the push counterpart to
`GetSummarisationCandidates`, which does exactly this for events.

```json
{
  "kind": "memories_at_risk",
  "cause": "consolidation",
  "queued_at": 1788476468760678000,
  "cycle_id": 1788476468000000000,
  "chunk": 1,
  "chunks": 1,
  "at_risk": {
    "consolidating": 412,
    "evicting": 0,
    "events": 7,
    "bytes": 918273,
    "threshold": 0.31,
    "at_risk_threshold": 0.3875,
    "capacity_pressure": 1.03
  },
  "items": [
    {
      "id": "m-1",
      "event_id": "e-1",
      "group": "svc-a",
      "significance": 3,
      "bytes": 118,
      "value": 0.12
    }
  ]
}
```

It is **off by default** (`callbacks.events.memoriesAtRisk`), against the grain of the other three,
and for one reason: it is the only kind that costs a scan rather than riding on work already being
done. Turning it on runs a consolidation preview at the top of every cycle — a used-bytes reading, a
memory count and a full pass over the memories table with a sort, which is roughly what the cycle
itself pays.

`callbacks.atRiskMargin` is what makes it **actionable rather than merely earlier**. At its default
of 0 the warning covers exactly what the cycle now starting will take — which arrives while that
cycle is taking it, and the queue drains asynchronously afterwards. A margin raises the bar the scan
selects on, so the delivery also carries memories that are still _above_ the threshold and
approaching it: at `0.25` a receiver hears about everything within a quarter of the bar, which is a
cycle or more of notice. The delivery reports **both** thresholds and each item its `value`, so the
two populations are told apart by comparison rather than by guessing — an item under `threshold` is
going now, one between `threshold` and `at_risk_threshold` is a warning with time left on it.

Items are ordered **lowest value first**, so a list truncated at `callbacks.atRiskLimit` (1000, the
preview's own cap) is still the memories closest to going; `at_risk.truncated` says when that
happened. Deliveries are grouped by `cause` and chunked at `maxIdsPerDelivery` within each group, so
a receiver reassembles on `(cycle_id, cause)`. The grouping is not cosmetic: a memory going to
`consolidation` has decayed past the bar and a recall will save it, while one going to `eviction` is
still above the bar and is being taken to make room — which a recall may not save, and which an
operator fixes by raising the capacity.

Two things it deliberately is not. It carries **no bodies**, whatever `includeBodies` says, because
the scan behind it never reads one and does not need to — the memory is still there to fetch. And it
is **not a veto**. Acting on it by recalling a memory races the pass that is about to delete it, and
that race is already safe in your favour: the delete re-checks the recall clock inside its own
transaction, so a recall landing mid-cycle protects its memory. That is a property worth knowing, not
a guarantee — a receiver that was down misses the window entirely, and nothing waits for one. A cycle
with nothing at risk sends nothing at all; the per-cycle heartbeat is `sleep_completed`.

#### Which deletions speak

By default only the two decay paths — consolidation and eviction. That is the narrow default on
purpose: a client that called `DeleteMemories` already knows the memory is gone, and `Clear` is the
second half of a move the caller initiated. `callbacks.allDeletions` widens the feed to every
deletion, each tagged with its `cause` so a receiver can filter rather than guess.

`callbacks.events.memoryForgotten`/`eventForgotten`/`sleepCompleted` switch off a kind entirely. They
default **on**, since the feature as a whole is off — an operator who has configured a URL wants the
callbacks, and needing to then enable each one would be a second switch for one decision. Turning one
off stops the rows being written, which is cheaper than writing them for a receiver to discard.

`callbacks.events.memoryWrites` (off by default) adds the change stream for writes. Each memory
created (`memory_stored`) or changed (`memory_updated`) is one delivery, carrying the memory as it now
stands, with its body under `callbacks.includeBodies`. A system that mirrors the store learned every
deletion through callbacks and no creation, so it could only clean up, never follow. Each delivery
is queued **inside the write's own transaction**: a write that commits always has its delivery, and
one that fails never does. It is off by default because it puts a queue row on every write. These
kinds are notifications, so the queue's caps trim them under every `backlogPolicy`. Recalls are not
reported, being reinforcement rather than a change of content, and nor are `Import`/`ImportBatch`,
being data movement.

#### Bodies

`includeBodies` adds each memory's body to its item. It is off by default and costs a body read per
forgotten memory plus real space in the queue — the consolidation scans deliberately never touch the
body column, and this is the one thing that makes them touch it (only for the handful of rows being
deleted, by primary key, so the scans themselves are unaffected).

A body over `maxBodyBytes` (64 KiB by default) is **omitted and flagged**, never truncated: the item
carries `"body_omitted": true` with no `body`. A receiver cannot tell a truncated body from a whole
one, which makes truncation worse than omission.

#### Authenticating the receiver

`callbacks.token` is sent as `Authorization: Bearer`. `callbacks.signingSecret` additionally signs
each delivery: `X-Hippocampus-Timestamp` carries a UnixNano instant and `X-Hippocampus-Signature`
carries `sha256=` plus the hex HMAC-SHA256 of `<timestamp>.<body>` under the secret. The timestamp is
inside the signature rather than beside it, so a captured delivery cannot be replayed with a fresh
one; a receiver that cares about replay rejects a timestamp that is too old. Both are secrets and
both are injectable as `HIPPOCAMPUS_CALLBACKS_TOKEN` / `HIPPOCAMPUS_CALLBACKS_SIGNINGSECRET`.

`callbacks.tls` accepts the same trust options as [`opensearch.tls`](#securing-the-connection) for an
`https://` receiver serving a private-CA or mutual-TLS certificate. `callbacks.tls.enabled: false`
switches the whole block off, with a warning at startup if it still carries anything. Left unset,
the block applies whenever it is set, so a configuration that names a `caCertFile` needs nothing
more. Redirects are **never followed** —
a redirect would forward the bearer token and the signature to whatever host the endpoint named — and
are reported as a failed delivery.

#### When the receiver is down

A failed delivery is deferred, not dropped: its attempt count rises and its next attempt moves out on
a jittered exponential backoff from `retryBaseBackoffSeconds` (1) to `retryMaxBackoffSeconds` (300).
Nothing is abandoned on an attempt count. The only thing that removes an undelivered delivery is the
queue's own bounds — `maxRows` (1,000,000) and `maxAgeHours` (24) — and passing them is logged at
**Warn** and counted (`hippocampus.callbacks.abandoned`), because unlike a dropped search-index
deletion there is no sweep behind this queue: an abandoned callback is a notification nobody will
ever receive. The one other way out is a delivery whose stored payload cannot be decoded. No retry
can send it, so it is removed when claimed, logged at **Error** with the kind, cause, cycle and item
count that survive, and counted in the same metric. Left in place, it would be claimed on every
pass, and under a retaining `backlogPolicy` it would never be removed at all.

The queue is **excluded from the capacity target**, which is not tidiness. It grows precisely when a
receiver is down, and it can carry memory bodies; counted as stored bytes it would raise capacity
pressure and evict live memories to make room for the news that memories were evicted. It is not
excluded from the disk — see [The capacity target bounds the memories, not the
database](operations.md#the-capacity-target-bounds-the-memories-not-the-database).

Which is why `callbacks.maxRows` is not enough on its own, and `callbacks.maxBytes` exists. A row
here is a whole delivery: up to `maxIdsPerDelivery` items, each of which may carry a body up to
`maxBodyBytes` under `includeBodies`. So the row cap bounds this queue somewhere between a few
hundred megabytes of bare ids and a figure with no useful ceiling, while the other two excluded
tables have fixed-width rows whose row caps genuinely are byte caps. `maxBytes` is measured against
the rendered payloads themselves — a `payload_bytes` column written at insert, so applying it costs
no scan of the queue — and the newest delivery is never abandoned for it, since a delivery larger
than the whole cap would otherwise be discarded the moment it was queued and the queue would deliver
nothing for the life of that configuration. That case is logged at Warn.

It is **not defaulted**, unlike `maxRows` and `maxAgeHours` beside it. Reaching it discards
notifications nobody will ever receive, and how many bytes of those a deployment can afford is a
property of its disk rather than of this service. Setting `includeBodies` without it is warned about
at startup, that being the arrangement in which nothing bounds the queue's size at all.

Watch `hippocampus.callbacks.queue_depth` — a rising depth with a non-zero
`hippocampus.callbacks.delivered{outcome="failed"}` rate is a receiver that is refusing; a deep queue
with no attempts is one the dispatcher has not reached yet. Both shipped alert rules cover this.

#### When a forget-callback is an instruction, not a notification

Everything above is right for a **notification**. A receiver that has been unreachable for a day is
not helped by a day-old summary of a cycle, so discarding it costs nothing that was not already lost.

A `memory_forgotten` callback is a different thing whenever the receiver is the system holding what
the memory pointed at (see [the external capacity axis](consolidation.md#the-external-capacity-axis)). It is an **instruction**
about a payload this store does not hold and cannot see, and discarding it leaves that payload
orphaned in the far system permanently. The leak is monotonic, silent, and grows precisely with how
well the decay cycle is working.

`callbacks.backlogPolicy` decides who absorbs a receiver outage that outlasts the queue's caps. There
is no answer that costs nothing:

| Value     | What happens at the caps                                                          | Who pays                                             |
| :-------- | :-------------------------------------------------------------------------------- | :--------------------------------------------------- |
| `abandon` | The oldest undelivered deliveries are discarded, deletions included. The default. | The far system, in orphaned payloads                 |
| `retain`  | The two deletion kinds are exempt from the caps and the queue keeps them.         | This disk, in a queue nothing trims                  |
| `stall`   | As `retain`, and the two decay passes stop until the backlog is back under them.  | The workload, in a store that has stopped forgetting |

The other kinds — `sleep_completed`, `memories_at_risk` and the write stream's `memory_stored` and
`memory_updated` — are capped under every policy. They are notifications rather than instructions,
and holding them would be holding rows for their own sake.

Under `stall` the caps stop trimming and start **gating**: once the retained backlog is past
`maxRows`, `maxBytes` or `maxAgeHours`, `consolidate()` and `evict()` do not run. The cycle still
scans for summarisation candidates, still trims the forgotten log and still compacts; what it does
not do is forget. Every stalled cycle logs at Warn, counts
`hippocampus.forgetting.stalls`, sets `stalled` and `stalled_reason` on the cycle report
(`GetConsolidationStatus`, and the console's Now tab), and — for the party that can actually end it —
carries both on the `sleep_completed` delivery the receiver will read when it comes back. A store
that has stopped forgetting will grow past its capacity target, which is the point: it is the loudest
thing a store like this can say, and it is reversible, while an orphan in somebody else's bucket is
not.

`stall` with none of the three caps set is **refused at startup**. Nothing would ever be trimmed and
nothing would ever stall, which is unbounded growth chosen by an operator who asked for the opposite.

A client's own `DeleteMemories` still deletes under every policy. The caller already knows what they
asked for, and failing somebody's request over a receiver outage they have nothing to do with would
be the wrong party paying again.

**Keep the forgotten log on** under `retain` or `stall` — it is the pull path behind the push one.
`GetForgottenMemories` records the same deletions, in order, behind a keyset cursor, so a receiver
that was rebuilt (or whose queue an operator emptied with `DeleteCallbackQueue`) pages back to its
own cursor and catches up. Deleting an object that is already gone is a no-op, so replaying more than
was missed is harmless — which is what makes at-least-once the right guarantee here. Without it, a
delivery that never lands is unrecoverable however carefully the queue holds it, and startup warns
about the combination. It is also worth leaving the far system's own expiry configured as the outer
bound: a controller that has died then degrades to the far end's flat policy rather than to unbounded
growth.

#### Inspecting and emptying the queue

`GET /v1/callbacks/queue` (`GetCallbackQueue`) reports the depth, the oldest queued instant, and a
page of pending deliveries with their attempt counts and next-attempt deadlines. It never returns a
delivery's payload — a queued delivery may carry memory bodies, and this is a view of a backlog
rather than a second way to read the store.

`POST /v1/callbacks/queue/delete` (`DeleteCallbackQueue`) discards pending deliveries, either
`{"all": true}` or `{"before_time": <UnixNano>}`. One of the two is **required**, so an empty request
can never be read as "discard everything". It exists because the automatic bounds stop applying the
moment callbacks are turned off: disabling the feature leaves what was already queued in place rather
than destroying it, so discarding those deliveries has to be an explicit act. It is a real discard —
a deleted delivery is a notification that will never be sent.

Both are `admin` and both are refused to a group-scoped caller; see
[Authorisation](#authorisation) for why.

`WhoAmI` reports **`callbacks_enabled`** alongside its other deployment flags, so a client can tell
the two states an empty queue has: nothing waiting to be delivered, and nothing that will ever be
delivered. They render identically otherwise, which is the same argument `tombstones_enabled` was
added for.

#### Where it runs

Only on the instance that consolidates (`consolidation.enabled`). A replica neither records nor
dispatches: forgetting happens on the consolidator, and a replica's own deletions are
client-initiated ones the client already knows about — recording them on every replica would multiply
a widened feed by the replica count with nothing to drain it. The queue is shared, so one owner
drains it.

#### The sink is HTTP, and only HTTP

There is one implementation, and it POSTs. A deployment whose event bus is NATS, Kafka, MQTT or
RabbitMQ receives these deliveries by running a small HTTP-to-broker shim in front of it, not by
configuring a broker here.

That is deliberate rather than pending. A webhook is the one receiver every deployment can already
run, the shim is a few dozen lines against a client the deployment is running anyway, and the broker
clients this repository does ship live in `integrations/eventsource` — a separate module the root
deliberately does not import, which is exactly why they cost the service nothing. Pulling four
broker dependency trees into its build to save some deployments a shim would charge every deployment
for it. Those bridges also run the other way: they consume from a broker and write memories, which is
the inbound half and shares nothing with this.

Two things a shim wants to know, both properties of the queue rather than of the sink. It should
answer 2xx only once the delivery is on the broker, because a 2xx confirms the delivery and it is
then discarded — anything else is news the queue believes it delivered. And delivery is
**at-least-once**: a receiver that publishes and then fails to answer is retried with the same body,
and nothing on the wire identifies a delivery, so a shim needing exactly-once deduplicates on a hash
of the body. The signature header cannot serve as that key — it covers a timestamp taken per attempt,
so a retry of an identical body signs differently.

#### Every callbacks key

| Key                                 | Default   | What it does                                                                                    |
| ----------------------------------- | --------- | ----------------------------------------------------------------------------------------------- |
| `callbacks.enabled`                 | `false`   | The feature switch. Off, nothing is queued and nothing is sent.                                 |
| `callbacks.url`                     | —         | The endpoint each delivery is POSTed to. Required when enabled; startup fails without it.       |
| `callbacks.token`                   | `""`      | Sent as `Authorization: Bearer`. Secret.                                                        |
| `callbacks.signingSecret`           | `""`      | Keys the HMAC signature header. Secret; use at least 32 random bytes.                           |
| `callbacks.timeoutSeconds`          | `10`      | Bounds one delivery attempt.                                                                    |
| `callbacks.allDeletions`            | `false`   | Widen the feed from the two decay paths to every deletion.                                      |
| `callbacks.includeBodies`           | `false`   | Carry each memory's body. Costs a body read per forgotten memory and space in the queue.        |
| `callbacks.maxBodyBytes`            | `65536`   | Caps one carried body; over it the body is omitted and flagged. 0 removes the cap.              |
| `callbacks.maxIdsPerDelivery`       | `500`     | Bounds one chunk of a cycle delivery, at-risk or completed.                                     |
| `callbacks.events.memoryForgotten`  | `true`    | Record memory-deletion callbacks.                                                               |
| `callbacks.events.eventForgotten`   | `true`    | Record event-deletion callbacks.                                                                |
| `callbacks.events.sleepCompleted`   | `true`    | Record sleep-cycle completion callbacks.                                                        |
| `callbacks.events.memoriesAtRisk`   | `false`   | Warn at the top of a cycle about what it is about to forget. Costs a preview scan per cycle.    |
| `callbacks.events.memoryWrites`     | `false`   | Report each memory created or changed (`memory_stored`/`memory_updated`): the change stream.    |
| `callbacks.atRiskLimit`             | `1000`    | How many at-risk memories one cycle reports, lowest value first. Capped at 1000.                |
| `callbacks.atRiskMargin`            | `0`       | Raises the threshold the at-risk scan selects on, so the warning arrives with notice on it.     |
| `callbacks.backlogPolicy`           | `abandon` | What happens to an undelivered **deletion** callback at the caps: `abandon`, `retain`, `stall`. |
| `callbacks.maxRows`                 | `1000000` | Queue row cap. Passing it abandons the oldest undelivered deliveries. 0 removes the bound.      |
| `callbacks.maxBytes`                | `0`       | Queue byte cap, measured against the stored payloads. 0 removes the bound. See below.           |
| `callbacks.maxAgeHours`             | `24`      | Queue age cap, applied alongside the row cap. 0 removes the bound.                              |
| `callbacks.batchSize`               | `100`     | How many deliveries one dispatch pass claims.                                                   |
| `callbacks.retryBaseBackoffSeconds` | `1`       | First retry delay; doubles per attempt, jittered.                                               |
| `callbacks.retryMaxBackoffSeconds`  | `300`     | Ceiling on that backoff.                                                                        |
| `callbacks.tls.enabled`             | unset     | `false` ignores the block; `true` applies it; unset, it applies whatever the block carries.     |
| `callbacks.tls.caCertFile`          | `""`      | PEM CA bundle trusted in place of the system pool.                                              |
| `callbacks.tls.certFile`            | `""`      | Client certificate for mutual TLS; set with `callbacks.tls.keyFile` or neither.                 |
| `callbacks.tls.keyFile`             | `""`      | The matching key.                                                                               |
| `callbacks.tls.insecureSkipVerify`  | `false`   | Dev-only: disables certificate verification.                                                    |

### Transfer and archive

An embedded (e.g. IoT) instance can periodically move its whole store to a centralised
instance, either directly over gRPC or through S3 when the two are never connected at the same
time. Both paths preserve full state — original timestamps, recall history, significance,
groups, summary flags, event ids and the link graph — so the centralised store's decay sees
true ages: this is a data migration, not a re-store. Both are move-semantics by manifest: each
run captures a point-in-time snapshot and records exactly what it captured (ids plus recall
state); the paired **clear** then deletes precisely those records, re-verified live, so a memory
written or recalled mid-run survives to the next run. No watermark state is kept — the store
itself is the watermark.

- `Export` (`POST /v1/export`) streams every event and memory into a gzip-compressed archive
  object in S3 and returns a `manifest_id` and the `object_key`; `{"clear": true}` deletes the
  captured records in the same call once the upload has succeeded.
- `Import` (`POST /v1/import`, body `{"object_key": "..."}`) streams an archive from S3 into the
  store, upserting by id — re-importing the same archive is idempotent. Imported non-binary
  memories are indexed into the optional content-search index.
- `Transfer` (`POST /v1/transfer`) sends the same records directly to the centralised instance's
  `ImportBatch` RPC (`transfer.targetAddress`), with the same `clear` flag and manifest.
- `Clear` (`POST /v1/clear`, body `{"manifest_id": "..."}`) is the deferred second half of a
  two-phase move: export/transfer first, verify at the receiving end, then clear. Manifests are
  held in memory only (the last 8) — after a restart the records are simply recaptured by the
  next run. They are held by the instance that produced them, which the Export/Transfer response
  names as `instance_id`; behind a load balancer, send the `Clear` to that instance.

`Export` and `Transfer` both take an optional **`memories` selection** to move part of the store
instead of all of it: one group, one tier, one time range, anything a predicate can name.
It carries the same sixteen fields as `DeleteMemoriesByFilter`, built by the same code, so
`GetMemories` with those fields is the dry run of what the archive will hold. The events carried
are those the selected memories belong to, plus every event in the selection's `group` when it
names one, so a group's empty events travel with it. With `clear` set, only what was selected is
deleted, and an event survives the clear while it still holds a memory the selection did not take.
An absent or empty selection is the whole store, as before. `transfer.maxManifestRows` bounds what
a selection captures rather than the size of the store. A selection composes with a group-scoped
token's scope and never widens it. This is "export, verify, delete" for one group:

```json
POST /v1/export
{"memories": {"group": "acme"}, "clear": false}
```

then verify the archive, then `DeleteMemoriesByFilter` with the same `group`, or the same export
again with `"clear": true`.

```json
"archive": {
    "directory": ""
},
"s3": {
    "bucket": "my-archive-bucket",
    "region": "ap-southeast-2",
    "endpoint": "",
    "usePathStyle": false,
    "keyPrefix": "hippocampus/"
},
"transfer": {
    "targetAddress": "central.example.com:50051",
    "token": "",
    "tls": {
        "enabled": false,
        "caCertFile": "",
        "certFile": "",
        "keyFile": "",
        "insecureSkipVerify": false
    },
    "batchSize": 500,
    "maxBatchBytes": 0,
    "maxManifestRows": 0
}
```

`Export`/`Import` need an object store, and there are two: a local directory
(`archive.directory`) or S3 (`s3.bucket`). **Configure one, not both** — the service refuses to
start with both set, since the two disagree about where the archives went and that is discovered
when one is needed.

`archive.directory` is the simpler of the two, and exists because the archive format is the only
representation that preserves a store's full state — timestamps, recall history, groups, summary
flags, links — and requiring a bucket put the offline backup of a store that is _designed to
forget_ behind infrastructure it does not otherwise need. The directory is created if it is
missing; each archive is written to a temporary file and renamed into place, so an export
interrupted half way leaves nothing rather than a truncated file that `Import` would accept and
then fail part way through. `Import`'s `object_key` is validated against the directory: a key that
is absolute, or that carries a `..` segment, is refused rather than reinterpreted. Point it at a
directory a backup takes, or at a mounted volume. Nothing prunes the archives `Export` writes when
called; only the scheduled ones below are rotated.

#### Scheduled export

```json
"archive": {
  "directory": "/var/backups/hippocampus",
  "scheduledExport": { "intervalHours": 24, "keep": 7 }
}
```

`archive.scheduledExport.intervalHours` (0, the default, disables it) takes an `Export` of the whole
store on a schedule, and `archive.scheduledExport.keep` (default 7; 0 keeps every one) is how many
of them to keep, the oldest deleted after each new one is written. It needs an archive store, and
startup refuses the setting without one. The archives are written under their own `scheduled/` key
prefix (after `s3.keyPrefix`), and **only that prefix is ever pruned**, so a manual `Export` is never
deleted by the rotation.

It runs on the consolidating instance only, so replicas of one store do not each export it. The
schedule is read back from the archives already there: after a restart the next export is one
interval after the newest, or immediately if that has passed — never a fresh export on every
restart, and never a full interval's wait from scratch. A failed export is retried within 15
minutes. `hippocampus.export.scheduled.last_success` and `hippocampus.export.scheduled.interval` are
published while it runs, and the shipped `HippocampusScheduledExportStale` alert fires when the last
success is more than two intervals old.

S3 credentials come from the standard AWS chain (environment variables, shared config, instance
roles); `s3.endpoint` and `s3.usePathStyle` support S3-compatible stores such as MinIO. With
neither `archive.directory` nor `s3.bucket` configured, `Export`/`Import` fail with
`FAILED_PRECONDITION`; with no `transfer.targetAddress`, so does `Transfer`. `s3.keyPrefix` applies
to both backends — under a directory it is a subdirectory. `transfer.token` is sent as the bearer token to
the centralised instance when its [authentication](#authentication) is enabled, and
`transfer.tls.enabled` dials it over TLS. `transfer.batchSize` sets both the pagination page size and
the archive/ImportBatch batch size.

`transfer.tls` accepts the same trust options as [`opensearch.tls`](#securing-the-connection), so a
transfer to a target serving a private-CA or mutual-TLS certificate can verify it:
`caCertFile` is a PEM CA bundle trusted in place of the system pool, `certFile`/`keyFile` are a
client certificate/key pair for mutual TLS (set both or neither), and `insecureSkipVerify` is a
dev-only escape hatch that disables verification. With `enabled: true` and none of the trust options
set, the connection verifies against the system certificate pool. The legacy scalar form
`"tls": true` still works as a shorthand for `{ "enabled": true }`.

`transfer.maxBatchBytes` (0 → an internal 3 MiB default) additionally bounds each `ImportBatch`
message's serialised size during a `Transfer`: a page of large memory bodies is split into
byte-bounded sub-batches so no message overflows the receiver's gRPC max-receive-message size
(otherwise the transfer fails permanently, every retry hitting the same oversized deterministic
page). A single memory larger than the budget is sent alone. If your bodies can exceed the default
4 MiB gRPC frame, raise the receiving instance's `maxRecvMsgBytes` (top-level, 0 → grpc-go's 4 MiB
default) so it accepts them.

`transfer.maxManifestRows` (0 → unlimited, the default) caps how many records a single
`Export`/`Transfer` may capture into its in-memory manifest. Each captured memory holds its id plus
its recall-state snapshot, so an unbounded manifest over a very large store can grow to gigabytes
and OOM the instance. When set, a store larger than the cap is refused with `FAILED_PRECONDITION`
_before_ any upload, and the operator segments the transfer (e.g. by `group`) or raises the cap. The
manifest exists so a later `Clear` can delete exactly what was captured; a deployment that never
uses `Clear` can leave the cap low.

The sleep cycle keeps running during a capture: a record consolidated mid-export simply doesn't
matter (its clear becomes a no-op), and one consolidated at the centralised end after import is
the destination's own decay policy at work.
