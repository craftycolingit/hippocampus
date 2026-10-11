# Changelog

All notable changes to Hippocampus are recorded here. The format follows
[Keep a Changelog](https://keepachangelog.com/en/1.1.0/), and versions follow
[semantic versioning](https://semver.org/spec/v2.0.0.html).

Each entry is a few lines: what changed, who it affects, and a link to the documentation that
explains it. The reasoning belongs in that documentation. Older entries predate this rule and
run longer.

## Compatibility

**Hippocampus is pre-1.0.** Under semver that permits a breaking change in any minor release, and
several have shipped. Until 1.0, read the **Breaking** section of every release you skip over.

What each version number covers:

- **The gRPC contract** (`contract/hippocampus.proto`) and the `/v1` JSON gateway it generates.
  Compatibility here is enforced mechanically: the `proto-breaking` CI job runs `buf breaking`
  against the previous release tag, so an accidental field renumbering or a removed RPC fails the
  build rather than shipping. A deliberate break is listed under **Breaking** below. The job always
  runs and always reports, but its verdict is advisory in the two cases where the version number
  already permits a break — a pre-1.0 baseline, or a major increment declared in the `[Unreleased]`
  heading (see [RELEASE.md](RELEASE.md#compatibility)) — so the report is worth reading even when
  the build is green.
- **Configuration keys, and the values they accept.** A removed or renamed key is a breaking change,
  and a new key always carries a default that preserves the previous behaviour, so an existing
  `config.json` keeps working. **Narrowing the accepted range of an existing key is a breaking
  change too**: a value the previous release ran on and this one refuses at startup stops a service
  that was working, which is the same outcome as removing the key it is set on. Tightening a
  validation rule reads like a fix — 0.41.0's deletion-threshold check was filed under **Fixed** —
  but it belongs under **Breaking**, naming which values are no longer accepted and what to set
  instead. There is no mechanical gate for this the way `proto-breaking` gates the contract; the
  release pre-flight asks the question instead (see
  [RELEASE.md](RELEASE.md#local-pre-flight)), and `hippocampus --check-config` is how a deployment
  can answer it for its own configuration before the upgrade rather than during it. A key being
  **renamed with the old name still read** is not a break while both work — the release that stops
  honouring the old name is, and it is that release which lists it under **Breaking**.
  `--check-config` reports the deprecated keys a configuration still uses, so the deployments a
  future removal will affect can be found before it happens rather than after.
- **The stored database.** Schema additions are migrated in place on startup, so a store written by
  an older version opens on a newer one. Downgrading is not supported, and since 0.39.0 that is
  enforced rather than merely stated: a store records its schema version, and a build that does not
  understand it refuses to open rather than serving a shape it only partly knows.
- **The archive format** (`Export`/`Import`) is versioned in its own header, independently of the
  release version.

Not covered: the embedded web console, the demo stack, the Grafana dashboard, and anything under
`docs/`. Each integration under `integrations/` (the MCP bridge, the `hippo` CLI, the event-source
bridges, the ingestor, the object-storage agents and the `hippocampus-client` Python package) is
released from this same tag and tracks the service. For the Python package that coupling is stronger
than convention — its stubs are generated from the contract during the build, and its version is
stamped from the tag, so `hippocampus-client==X.Y.Z` is the client of `vX.Y.Z`'s contract by
construction. (It is not yet uploaded to PyPI; until it is, install it from the tag itself, which
carries the same contract but reports its version as `0.0.0.dev0` — see
[the Python client](docs/python.md).)

Three subprojects have **their own repositories and their own version lines**, and a release here
makes no promise about them: the [Obsidian plugin][obsidian-repo], the [LlamaIndex
adapter][llamaindex-repo] and the [OpenTelemetry collector][otel-repo]. Each takes a versioned
dependency on this module and is told about a release by a `repository_dispatch`, so each states for
itself which service version it was built against.

## [Unreleased]

### Added

- **Kubernetes lifecycle endpoints on every component.** The service, broker bridges, ingestor,
  object gateway and reaper, configuration wizard, and the MCP bridge's HTTP transport (which had no
  probes) serve `/livez`, `/readyz` and `/healthz` (now an alias of `/livez`). `/readyz` fails from
  `SIGTERM` on. See [Health and readiness](docs/configuration.md#health-and-readiness).

### Changed

- **The Kubernetes manifests probe `/livez`** for startup and liveness, pause 5 s in a `preStop`
  `sleep`, and allow 45 s to terminate, in the overlays and the wizard's output. The `sleep` action
  needs Kubernetes 1.30+. See [deploy/k8s](deploy/k8s/README.md).

## [0.52.1] - 2026-10-10

### Changed

- **A duplicate create is counted, not warned.** Re-storing an id the store already holds still
  returns `AlreadyExists`, but logs at debug and counts as `reason="duplicate"` on
  `hippocampus.memories.rejected` / `.events.rejected`. A feed bridge re-sending what it holds no
  longer floods the log. See [the instrument table](docs/operations.md).

### Fixed

- **A caller cancelling mid-create no longer logs a masked error.** The lost links (best-effort, as
  before) were reported at error as `sql: transaction has already been committed or rolled back`;
  they now name the cancellation and log at debug.

### Security

- **Built with Go 1.27.2 and `golang.org/x/net` v0.60.0** across all six modules, for the
  `net/http`, HTTP/2, `crypto/tls`, `net/textproto` and `html/template` advisories GO-2026-6599 to
  GO-2026-6617. `scripts/govulncheck.sh` now prints each finding's summary and fixing version.
  golangci-lint moves to v2.14.0, the first release that reads Go 1.27.2's export data.

## [0.52.0] - 2026-10-08

### Added

- **[Troubleshooting](docs/troubleshooting.md), a [port map](docs/operations.md#ports),
  [`CONTRIBUTING.md`](CONTRIBUTING.md) and a [Compose README](deploy/compose/README.md).** The flags
  of the broker bridges and the object-storage agents are now documented in full, and a test per
  command keeps them so.

- **An asyncio Python client, one dialling package, and runnable examples.**
  - **`AsyncHippocampus`** (with `connect_async`) is the Python client over `grpc.aio`: the same
    methods, arguments and return values, awaited. Both clients come from one set of method
    definitions, so neither can drift from the other. Writing it found that an asyncio failure
    surfaced as an untyped `ServiceError`, because `AioRpcError` is not a `grpc.Call`; errors now
    translate from either.
  - **A root `dial` package** is the one connection to the service, carrying the token, the OIDC
    client-credentials grant, the TLS trust block, the version header and caller-supplied
    interceptors. The broker bridges, the ingestor, the object-storage agents, the MCP bridge and
    the `hippo` CLI all use it, where each had its own copy and only the bridges had the OIDC grant.
  - **`examples/`** holds a Go quickstart, an asyncio agent loop and a curl walk-through of the
    gateway. CI runs them as contract smoke tests.
- **Three API gaps closed.**
  - **`SearchMemories` pages and takes time bounds.** `offset` (at most 1000) pages through the
    ranked matches, and `timestamp_min`/`timestamp_max` bound when the matches were stored, applied
    inside the index on both backends. `GetMemories` had both and search had neither, so a client
    could read no further than the first page.
  - **A change stream for writes.** `callbacks.events.memoryWrites` (off by default) adds
    `memory_stored` and `memory_updated` deliveries on the existing durable queue, each queued inside
    the write's own transaction and carrying the memory as it now stands. Before this, callbacks
    reported forgetting only, so a mirror of the store learned of every deletion and no creation.
  - **Events can be selected by description.** `description_contains` on `GetEvents` and
    `DeleteEventsByFilter`, `name_contains`'s counterpart.
  - All three are in the CLI, the Python client and the MCP bridge where those carry the RPC.
- **Kubernetes manifests closer to production.**
  - A `mysql` overlay: one consolidator and N replicas over a bundled MySQL 8.4, the postgres
    overlay's shape.
  - A default-deny `NetworkPolicy` in the base, with the allowances the service needs: DNS, its own
    namespace and any namespace labelled `hippocampus.fastbean-au/client`, scraping from one labelled
    `hippocampus.fastbean-au/scrape`, and the bundled database from Hippocampus alone.
  - `examples/` holds an `ExternalSecret` that replaces the demo secret, and an `Ingress` for the
    gateway.
  - A new `k8s` CI job builds every overlay and validates it with kubeconform.
  - **Upgrading:** a client in another namespace needs that namespace labelled, and egress to
    anything outside the cluster needs a policy of its own; `deploy/k8s/README.md` says which.

- **Running a shared store at scale: failover, an audit trail, certificate rotation.**
  - **Automatic consolidator failover.** `consolidation.standby` (with `consolidation.enabled:
    false`, on postgres or mysql) makes a replica poll the single-consolidator lock every
    `consolidation.standbyPollSeconds` (15) and take over the sleep cycle and every
    consolidator-only worker when it wins. Run every instance as a standby, and the first to poll
    after a consolidator dies takes over. Before this, a store whose consolidator had died never
    forgot until somebody restarted a replica with the flag flipped.
  - **An audit trail.** Every call to an administrative mutation (`Purge`, `Sleep`, both predicate
    deletes, `DeleteForgottenMemories`, `DeleteCallbackQueue`, `Export`, `Transfer`, `Clear`) leaves
    one Info line with `audit=true`, the caller's `client_id`, the outcome, the request and the
    result, on both transports, refused attempts included. Before this, they were logged at Trace if
    at all.
  - **TLS certificates reload.** The serving certificate is re-read within a minute of its files
    changing, so a cert-manager or ACME renewal needs no restart, and a half-written pair is ignored
    until it reads cleanly. `hippocampus.tls.certificate_not_after` reports the expiry, and a new
    `HippocampusTLSCertificateExpiring` alert (thirty-one rules now) fires within 14 days of it and
    past it.
  - **Export manifests name their instance.** `ExportResponse`/`TransferResponse` gain
    `instance_id`, the instance holding the manifest in memory. A `Clear` that reaches another
    replica is refused naming itself, rather than reporting the manifest unknown.
- **Fuzz targets, and a property test for the decay curves.**
  - Native fuzz targets cover metadata filter keys, search tokens, the archive reader, archive key
    resolution, endpoint redaction, reported versions and the object-storage id mapping. Their seeds
    run in every `go test`, and a new nightly `Fuzz` workflow fuzzes each for three minutes.
  - A property test checks that every decay method yields a finite value that never rises with age
    and never falls as significance rises. The `days_until_forgotten` bisection depends on those
    properties.
- **Every Go module is scanned for reachable known vulnerabilities.** `scripts/govulncheck.sh`, run
  by a new `govulncheck` CI job, runs govulncheck over the root module and the five under
  `integrations/` (which a root `./...` never reaches) and fails on any symbol-level finding not on a
  short list of reviewed exceptions. An exception has to say why it does not apply, and one that is
  no longer reported fails the run, so the list cannot outlive the dependency it was for. The list
  is empty: GO-2026-6443 was excepted until the advisory was revised on 2026-10-06 to count grpc-go
  v1.84.0 as fixed.

- **Read memories by id without reinforcing them.** `GetMemoriesRequest` gains `ids` (up to 200).
  `RecallMemories` was the only by-id read that returned a body, and recalling resets the decay
  clock, so inspecting a memory — an operator checking a record, a subject-access lookup, a sync job
  — made it more durable. The ids go through the listing's own predicate, so they compose with every
  other filter and the group scope applies to them unchanged: an id the store does not hold, or one
  outside the caller's scope, is simply absent from the page. Reachable as `hippo memory list --id`,
  `get_memories(ids=...)` in the Python client, and the `ids` argument of the MCP bridge's
  `list_memories`, which gives a model a way to look at what it holds without keeping it alive.
- **A maximum retention: `consolidation.maximumRetentionInDays`.** A ceiling, where every other rule
  in the store is a judgement of value: a memory stored longer ago than this is deleted by the next
  sleep cycle whatever its value and however recently it was recalled. Recall resets the decay clock,
  so before this a memory read often enough was never forgotten and a storage-limitation or
  log-retention policy had no setting. It is measured from creation, runs first in the cycle, and
  overrides `minimumRetentionInDays` (startup refuses a maximum at or below it). Off by default.
  Expiry is a forget rule (`FORGET_RULE_EXPIRY`) and a callback cause (`expiry`) of its own, counted
  as `memories_expired`/`events_expired` in the cycle report and `hippocampus.memories.expired`;
  `PreviewConsolidation` predicts it and `ExplainConsolidation` reports `days_until_expiry`. The
  object-storage reaper acts on it by default, and the console, the CLI and the config wizard all
  know it.
- **An online backup for SQLite: `hippocampus --backup <path>`.** Writes a consistent copy of the
  store and exits, safely beside a running instance: it opens the store read-only, takes no lock,
  and uses `VACUUM INTO`, which reads one snapshot and writes a single compacted file. The docs used
  to say "copy the file", which in WAL mode silently loses every write not yet checkpointed. An
  existing destination is refused, and the server drivers are pointed at `pg_dump`/`mysqldump`.
- **Scheduled exports: `archive.scheduledExport.intervalHours` and `.keep`.** The consolidating
  instance takes a full `Export` on a schedule and keeps the newest `keep` (default 7), deleting
  only archives under its own `scheduled/` prefix, so a manual export is never rotated away. The
  schedule survives restarts by being read back from the archives already present, a failure is
  retried within 15 minutes, and startup refuses the setting with no archive store to write to.
  Published as `hippocampus.export.scheduled.last_success`/`.interval`, with a shipped
  `HippocampusScheduledExportStale` alert (thirty rules now). Both object stores gained list and
  delete for the rotation.
- **Export or transfer part of a store.** `ExportRequest` and `TransferRequest` gain `memories`, a
  `MemorySelection` carrying the same sixteen selecting fields as `DeleteMemoriesByFilter` and built
  by the same code, so `GetMemories` with those fields is the dry run. The archive holds the
  selected memories and their events, plus every event in the selection's `group` when it names
  one; with `clear` only what was selected is deleted. Before this, exporting one group needed a
  token scoped to it, and moving part of a store meant moving all of it — so "export, verify,
  delete" for one group could not be expressed with the predicate deletion that does the delete
  half. An absent or empty selection is the whole store, as before. Reachable as `hippo export`/
  `hippo transfer` with `memory delete-by-filter`'s flags, and as
  `export(selection=Hippocampus.memory_selection(...))` in the Python client.

### Changed

- **`hippocampus.New` takes a `Config`.** The service package reads no configuration of its own;
  `cmd/hippocampus/serverconfig.go` builds it from viper. Anything constructing a server directly
  passes one. See [CONTRIBUTING.md](CONTRIBUTING.md#adding-a-configuration-key).
- **CI lints.** A `lint` job runs golangci-lint, staticcheck included, as `hooks/pre-commit` does.
  Kafka joins MQTT and RabbitMQ as a broker the bridge tests run against, and the console's DOM
  layer now has tests of its own.

- **The design record moved to [`docs/design/`](docs/design/README.md).** `CLAUDE.md` is now a
  short guide: commands, a package map, and the invariants with the tests that enforce them. The
  checklists for adding an RPC or a config key live once, in [`CONTRIBUTING.md`](CONTRIBUTING.md).

- **Every message and field in the contract is documented.** 161 messages and fields had no
  comment, mostly on the export, import and clear surface, and comments are what reach every
  generated client and the OpenAPI document. A test now requires a comment on each new message and
  field. Export, Import and the deployment view's object-store node no longer say "S3" alone,
  because `archive.directory` is the other backend. The export comment, which had attached itself
  to `MemorySelection` in the OpenAPI document, is back on `ExportRequest`.

- **The configuration reference now lists every key, and the API has its own page.**
  - **`docs/configuration.md` opens with an index of every key the service reads**: its default, one
    line on what it does, and the section documenting it. The page called itself exhaustive while 25
    keys - every core decay key among them, with `sleep.periodSeconds` and `shutdown.timeoutSeconds`
    - had no entry on it. The index is generated from the service's own key reads, so a new key
    cannot be added without a row, and a row cannot be generated for a key no section documents.
  - **Entries that were missing everywhere are written**: `consolidation.linkRecallPropagation`
    ([Spreading activation](docs/consolidation.md#spreading-activation)),
    `memory.minimumSignificance`/`event.minimumSignificance`
    ([Minimum significance](docs/configuration.md#minimum-significance)), `memory.limit.sizeBytes`
    ([Memory size limit](docs/configuration.md#memory-size-limit)), and the age unit and minimum age
    behind every decay curve (`consolidation.unitsOfAgeInDays`, `consolidation.minimumAgeInDays`).
  - **The route table and the filter, sorting and metadata semantics moved to
    [`docs/api.md`](docs/api.md)**, the API reference. Links to the old anchors were updated.
  - **Sections that had run together are separated**: the six decay methods, recall reinforcement
    and capacity pressure no longer sit under "Links"; the gRPC server settings no longer sit under
    CORS; the server-driver notes no longer sit under body compression; and the deprecated
    `auth.enabled` alias moved from the OAuth2 sign-in section to Authentication. The empty
    `## Functional` heading is gone.

- **The Kubernetes overlays pin the image to a release** through kustomize's `images:` stanza,
  instead of running `:latest`. A node that pulled afresh could run a newer build than its peers, and
  a newer build migrates the schema forward, after which a rollback is refused. `scripts/release.sh`
  moves the pin as it cuts each release.
- **The HTTP gateway bounds request bodies by default.** `gateway.maxRequestBytes` was opt-in, so
  any caller could stream a body of any size into the gateway, while the same request over gRPC
  stopped at 4 MiB. Left unset, it is now derived from the gRPC transport's own limit: twice
  `maxRecvMsgBytes`, or 8 MiB at grpc-go's default. The cap is doubled because JSON runs larger than
  protobuf. An explicit `0` still means unbounded. Reading a whole request is now bounded at two
  minutes (a `ReadTimeout` beside the existing header deadline), so a trickled body cannot hold a
  connection open. An oversized body is answered `413`, as the docs always said; it had been
  answered `400`, because the gateway turns a failed body read into InvalidArgument. **Upgrading:**
  a gateway client sending bodies over 8 MiB (a large `ImportBatch` file through
  `hippo --transport http import-batch`) needs `gateway.maxRequestBytes` raised, or `0`, or the gRPC
  transport. The config wizard writes the derived value out explicitly.

- **A release is dispatched only to the satellites it changes something for.** `notify-satellites`
  now asks `scripts/family-status.py --dispatch-targets` which satellites' consumed paths (a new
  per-repository `SURFACE` table: the OpenAPI document, `contract/`, `types/`, the Python client)
  moved between the pin on their `main` and the release tag, and tells only those. A patch touching
  none of them — v0.51.1 was console-only — no longer opens four pull requests re-pinning an
  identical contract, republishes `hippocampus-gen`'s images, or raises the Obsidian plugin's
  declared minimum service version. The weekly status report judges a pin stale by the same test,
  and `family_test.go` requires every dispatched satellite to declare a surface whose paths exist.

- **A satellite the release cannot reach now fails the release run.** `notify-satellites` still
  tries every satellite, but a failed dispatch is now an error, and the job exits non-zero once
  they have all been tried. It used to be a warning on a green run: `hippocampus-gen` was refused
  with a 403 on 0.50.0, 0.51.0 and 0.51.1 (the dispatch token's repository list did not include
  it) and nothing showed until the weekly status report found its pin three releases behind.

### Fixed

- **A forwarded address is parsed before it is trusted.** With `rateLimit.trustForwardedFor` on, the
  rightmost `X-Forwarded-For` entry was used verbatim as the rate-limit bucket key and logged as
  the throttled principal, so a malformed entry could forge a log field. It must now be an IP
  address, and a port on it is dropped; anything else falls back to the connection's address. See
  [Rate limiting](docs/configuration.md#rate-limiting).

- **The pre-commit hook's install hint named golangci-lint v1.** It now names the v2 release the
  hook and CI run.

- **Getting started's authentication steps work.** They set no signing secret and minted a token
  without `--role`, which `--mint-token` refuses. See [Enabling
  authentication](docs/getting-started.md#enabling-authentication).
- **`SearchMemories` names the right switch when search is off.** It said the storage driver had no
  content search; it now names `search.contentIndex.enabled` and `opensearch.enabled`.

- **Six smaller hardening fixes.**
  - **Webhook paths are no longer shown.** The deployment view and the startup log line showed a
    callback or other `http(s)` URL with its path, and a webhook's secret is routinely its path. Such
    addresses now show the scheme and host only; a database URL still shows its database name.
  - **The rate limiter keys on the rightmost `X-Forwarded-For` entry** under
    `rateLimit.trustForwardedFor`. That is the entry the proxy wrote. The leftmost is the client's to
    choose, and rotating it bought a fresh bucket per request behind any proxy that appends.
  - **The Bluesky bridge recalls only post URIs.** It recalled whatever a like's or reply's subject
    named, so anyone on Bluesky could keep any guessable id in the store alive through the bridge's
    unscoped writer token.
  - **The compose stacks publish on loopback.** Every published port now binds
    `${PUBLISH_ADDRESS:-127.0.0.1}`. Published ports bypass a host firewall such as `ufw`, and these
    stacks run with auth off. The service also warns at startup when `auth.method` is `none` and a
    listener binds beyond loopback. **Upgrading:** set `PUBLISH_ADDRESS=0.0.0.0` to reach a stack
    from another machine.
  - **The object gateway's proxy mode serves objects inert**, with `X-Content-Type-Options: nosniff`
    and `Content-Security-Policy: sandbox`, since the bucket's writer chose the content type.
  - **The id namespace is documented as a scope crossing.** A scoped writer naming an id another
    group holds is answered `ALREADY_EXISTS`, which confirms the id exists. `scope.go` and the
    security guide now say so, and what to do about it.
- **The deployment view no longer shows part of a database password in three address shapes.**
  `GetTopology` is reader-visible by default, and what made that safe was that every address had its
  credentials stripped. Fuzzing that redaction found three shapes where they were not:
  - a libpq keyword DSN with an `@` anywhere in it (`password=p@ss`), which showed the text after
    the `@`;
  - a MySQL DSN whose password contains a `/`, which showed the whole `user:password`;
  - a URL whose password contains an unencoded `/` or `?`, which `url.Parse` reads into the path or
    the query.

  The redaction now recognises a keyword DSN by its first field. When an address is not
  recognised, or a URL parses with the userinfo misplaced, it drops everything up to the last `@`.
- **Deleting an event is one transaction, and the ingestor never drains a memory it did not judge.**
  - **`DeleteEvent`:** it took the event in one transaction and its memories in another. A failure
    between the two left memories naming an event that no longer existed, and a retry answered
    `NotFound` with nothing left to finish.
  - **`DeleteEventsByFilter`:** it could delete an event that had gained a memory after it was
    cleared. Its batch delete now takes only events that hold nothing.
  - **The ingestor's drain:** it re-read an event's memory count and then deleted the event with its
    memories. A memory landing between the two was deleted without ever being judged. The drain now
    deletes the memories it judged, by id, and then the event with a new
    `DeleteEventRequest.if_empty`. The edge refuses that delete while a late memory holds the event,
    so the next pass judges the late memory. `if_empty` is also reachable as
    `hippo event delete --if-empty` and as `delete_event(if_empty=True)` in the Python client.
- **Three concurrency fixes in the preview, explain and shutdown paths.**
  - A `PreviewConsolidation` or `ExplainConsolidation` snapshot read the default event significance
    while a sleep cycle could be writing it, a data race.
  - Concurrent previews and explain refreshes share one scan, but that scan ran on the first caller's
    context. One closed console tab therefore failed every other viewer's request. The scan now
    belongs to the server, bounded at five minutes, and each caller can still give up on its own.
  - On a forced shutdown, the database could close beneath a sleep cycle an RPC had started. `Stop`
    now waits for a cycle in flight, and refuses to start a new one.
- **`callbacks.tls.enabled: false` now turns the callback TLS block off.** The key was documented and
  offered by the config wizard, but never read. A block switched off with `insecureSkipVerify` still
  set therefore kept skipping certificate verification. Left unset, the block still applies whenever
  it carries anything, so existing configurations are unchanged. `docs/operations.md` also named
  `opensearch.applyTimeout`, which is `opensearch.applyTimeoutSeconds`. A new guard requires every
  configuration key the documentation names to be one the service reads. Writing it fixed the guard's
  own JSON reader, which nested every later key in an example under an object opened and closed on
  one line.
- **A callback whose stored payload cannot be decoded no longer wedges the queue.** The dispatcher
  skipped such a row without removing it, so it was claimed again on every pass. With a batch of them
  at the head of the queue, nothing behind them was ever sent. Under `abandon` the age cap eventually
  cleared them. Under `retain` and `stall` the caps exempt `memory_forgotten` rows, so the queue
  stuck for good, and under `stall` forgetting stopped with it. Such a row is now removed when
  claimed, logged at Error with the kind, cause, cycle and item count that survive, and counted in
  `hippocampus.callbacks.abandoned`.
- **The MCP bridge's HTTP transport no longer hands its service token to the network.**
  `--http-address` defaulted to `:8090` with no inbound authentication, and the compose `mcp`
  profile published the port on every host interface. Anyone who could reach it therefore acted
  with the bridge's own token, normally a writer's, including `delete_memories`. The default is now
  `127.0.0.1:8090`. A new `--http-token` (`HIPPOCAMPUS_MCP_HTTP_TOKEN`) makes every request present
  it. With no token, a non-loopback address is refused at startup unless
  `--allow-unauthenticated-http` says the exposure is deliberate. The compose profile publishes on
  the host's loopback only and passes `MCP_HTTP_TOKEN` through when set. **Upgrading:** a bridge
  started with `--http-address :8090` and no token now refuses to start. Add `--http-token`, or
  `--allow-unauthenticated-http` where the network is itself the boundary.
- **A group-scoped token can no longer take over another group's records through an import.**
  `Import` and `ImportBatch` upsert by id, and stamped the caller's group on each incoming row
  without checking whose row that id already named — so a writer scoped to one group could
  overwrite a record in another by naming its id, which also moved it into their own partition and
  made it theirs to read. Both now refuse an id held in another group (`ALREADY_EXISTS`) and a memory
  whose `event_id` is another group's event (`NOT_FOUND`), checked before anything is written, and
  drop link far ends outside the token's scope as `LinkMemories` does. Unscoped imports, which is
  every deployment not using group scoping, are unchanged.
- **A deletion by `significance_extremum` no longer deletes past the tier it names.**
  `DeleteMemoriesByFilter` and `DeleteEventsByFilter` evaluated the extremum afresh for every
  batch, so once the lowest (or highest) tier was gone the next one became the extremum, and the
  call ran on until nothing the rest of the filter selected was left. The listing — the documented
  dry run — showed one tier, and the deletion took everything. The extremum is now resolved once
  when the call starts and that one tier is deleted, including the unranked tier (significance 0).
- **The Kafka bridge no longer loses a message whose store failed.** After a failed store it backed
  off and fetched again, but a kafka-go group reader has already moved past the message by then, so
  the next fetch returned the following one — and committing that committed the partition past the
  failed message too. Whenever the service blipped, the message in flight was dropped despite the
  documented at-least-once guarantee. The bridge now retries the same message until it is stored,
  fetching nothing past it; a message that can never be stored holds its partition, with a Warn line
  per attempt, as RabbitMQ's requeue already does.
- **A group-scoped caller's event-wide operations no longer reach another group's memories.** An
  event can hold memories of several groups when an unscoped or multi-group token attached them, and
  `DeleteEvent`, `DeleteEventsByFilter`, `ReplaceMemoriesWithSummary` and `SummariseMemories` acted
  on every memory of an in-scope event — deleting another group's, sending its bodies to the
  summariser (and so back to the caller inside the summary), and reporting counts that included it.
  They now act on the caller's own memories only; another group's are detached from a deleted event
  rather than deleted. `ReplaceMemoriesWithSummary` also no longer lets a scoped caller file the
  summary in a group outside their scope. Unscoped callers are unchanged.
- **`memories_consolidated` is set only on an event that actually lost a memory.** The evented
  consolidation pass set it on every event it scanned and did not delete, so after one cycle it was
  on practically every event in the store. The sweep that deletes a flagged, empty event regardless
  of value therefore deleted a valuable event as soon as its memories left by another route (a
  client delete, a move, a predicate delete). **Existing stores keep the flags already set**: after
  upgrading, clear them on every event that still holds memories, with the service stopped —

  ```sql
  UPDATE events SET memories_consolidated = FALSE
  WHERE memories_consolidated = TRUE
    AND EXISTS (SELECT 1 FROM memories WHERE memories.event_id = events.id);
  ```

  The statement is the same on all three drivers; see
  [Consolidation](docs/consolidation.md) for what it does to an event that genuinely lost some of
  its memories. Running it before upgrading achieves nothing, since the old pass flags every event
  again on its next cycle.
- **A memory of very high significance is no longer the first to be forgotten.** A memory's value
  added its own significance and its event's as 32-bit integers, so two significances summing past
  2,147,483,647 wrapped to a negative value: below every deletion threshold, and first in line for
  eviction. The two are now added as floating point. Preview, explain and the forgotten log, which
  report the same value, were wrong in the same way and are fixed with it.
- **The object-reaper no longer deletes objects whose pointer-memory could never be registered.**
  The keymap bounded a `<bucket>/<key>` id at MySQL's 255-character column, but the service refuses
  any id over 128 bytes, so an object whose id fell between the two was treated as manageable,
  could never be registered by its producer, read as forgotten, and was deleted by an armed sweep
  after `--sweep-min-age`. The keymap's bound is now the service's own (`types.MaxIdBytes`, counted
  in bytes), so such objects are unmappable: skipped by the tap and never deleted. An id in that range
  registered through `ImportBatch`, which does not apply the length check, is now unmappable too and
  is left alone rather than reinforced.
- **`SearchMemories` caps its page at 200, as `GetMemories` does.** It was the one listing RPC with
  no bound on `limit`, so a single call — from a reader, or from anyone on an instance with
  `auth.method: none` — could return every matching memory with its body in one response, and a
  reinforcing one could reset the decay clock on all of them. A larger `limit` is now clamped to 200
  rather than refused, and the ranking over-fetch multiplies the clamped value. A caller relying on
  more than 200 results per search gets 200.
- **The object-reaper no longer deletes on an instruction it cannot trust.** With `--delete` set and
  neither `--callback-token` nor `--callback-secret`, its callback endpoint accepted a deletion from
  anything that could reach it, with only a warning at startup; it now refuses to start unless
  `--allow-unauthenticated-callbacks` is passed. And the push and catch-up paths now ask the store
  which memories it still holds before deleting, as the sweep already did, so neither a forged
  delivery nor a stale one — an object re-uploaded and re-registered under the same key since — can
  delete a live object. Such ids are counted as `outcome="held"`; a store that cannot be asked makes
  the push path answer `5xx` so the delivery is replayed.
- **A console signed in through the server-side login is no longer open to forged writes from
  same-site pages.** The session cookie was protected only by `SameSite=Lax`, which stops cross-site
  requests but not a page on another port of the same host or on a sibling subdomain; such a page
  could send a plain-text `POST /v1/purge` that arrived with the signed-in admin's cookie and was
  decoded as JSON. A state-changing request authenticated by the session cookie must now come from
  the gateway's own origin, or it is refused with `403`. Reads, and requests carrying a bearer
  `Authorization` header, are unaffected.
- **The security guide no longer denies two features the service has.** `docs/security.md`'s "what
  the service does not do" said there was no server-side mutual TLS and that no gRPC reflection
  service was registered, and `SECURITY.md` repeated the first; both shipped (`tls.clientCaFile`,
  `reflection.enabled`). The list now states the real limits instead — identity never comes from a
  client certificate, and reflection cannot be put behind a token — and a test fails if either
  denial returns while the service still reads the key that proves the feature exists.
- **The first-run pages no longer say nothing is forgotten until `Sleep` is called.**
  `docs/getting-started.md` and `docs/install.md` described an instance on the built-in defaults as
  having no automatic consolidation cycle; it has run one hourly, against a deletion threshold of
  10, since those defaults were made functional. Both pages now say so and how to turn it off
  (`sleep.periodSeconds: 0`), `docs/consolidation.md` states the default, and a test reads the
  default from the code and fails if either page denies the cycle while it runs.
- **The ingestor no longer stalls behind events it cannot drain.** A pass re-read the first page of
  completed events and stopped as soon as that page held nothing new, so once `--page-size` (100)
  events had been left on the edge — over `--max-event-memories`, a failing `set` mutation or
  promotion, a drain re-check mismatch — every later pass saw only those, and nothing behind them was
  promoted or dropped again while the edge kept filling. The pass now pages past the events it
  leaves behind.
- **`storage.queryTimeoutSeconds` now bounds each step of a consolidation pass, as documented,
  rather than the whole pass.** Each of the four passes took one deadline at the start and reused it
  for its scan, its delete transaction and every per-event cleanup, so on a store large enough for
  the scan to take most of the timeout, the cleanups after it failed with "context deadline
  exceeded" on every cycle — one log line per event, and the cycle reported as failed. The deadline
  now covers the scan alone, and each later operation gets its own.
- **The docs no longer tell you to `pip install` packages that are not on PyPI.** `hippocampus-client`
  and `llama-index-memory-hippocampus` are built and verified on every release but have never been
  uploaded, so the advertised `pip install` failed on a new user's first command. The Python pages
  now give the install from a release tag, which works (the package reports its version as
  `0.0.0.dev0` that way), and `docs/llamaindex.md` gives the one route that currently installs the
  adapter, since its `hippocampus-client>=0.43` requirement cannot be met by a tag install.
- **The security guide names every route memory content leaves by, and every secret.** Its list of
  where bodies leave the process omitted semantic search, which sends every indexed body (and every
  semantic query) to the embedding provider, and `callbacks.includeBodies`; its secrets table omitted
  both model API keys and both callback credentials, and abbreviated the MySQL DSN's variable. Both
  are now complete, a test fails if a credential-named key the service reads has no row in that
  table, and the hardening checklist gains the six controls the guide documents elsewhere (mTLS,
  reflection, the metrics bind address, `topology.minimumTier`, CORS and the OpenAPI document, and
  `auth.readerRecallReinforces`).
## [0.51.1] - 2026-10-05

### Changed

- **The deployment view's labels now explain themselves.** Each component's status and source are
  chips with a tooltip saying what the label means and, for a status, why it holds for that node —
  the server's own `status_detail`, or for an unprobed node its `probing` reason ("export is
  fire-and-forget"). A collapsible legend above the components lists every label, for readers a
  tooltip never reaches. Only the status chip is coloured; the source is neutral and the version
  keeps its monospace chip.

### Fixed

- **"not checked" no longer appears twice on an unprobed component.** The freshness label repeated
  what the status already said; it is now shown only for a status that a check actually produced.

## [0.51.0] - 2026-10-04

### Added

- **Every component on the deployment view now shows its version, wherever it has one to give**
  (TODO-2 item 134). `TopologyNode.version` has been in the contract since the view shipped, but only
  two kinds of node ever filled it: the instance answering and its peers on a shared store. Everything
  else was drawn with no version, which left "which build is that bridge running" a question for
  somebody with a shell on its host.

  The view now asks. The primary store reports its engine's version (`SQLite 3.x`, `PostgreSQL 16.x`,
  `MySQL 8.x`), OpenSearch its distribution and number, an Ollama summariser or embedder its server
  version, and an opted-in transfer target the version its `WhoAmI` reports. Those are requests of
  their own, so the prober asks for them on the first round, after any round that found the
  component unhealthy, and otherwise every ten minutes, rather than doubling what it sends to every
  dependency. A version that cannot be read is not a failure, and an unreachable component keeps
  showing the last version it reported.

  The components that dial **in** get theirs two ways. The shared health server now reports
  `version` on `/readyz` as well as `/healthz`, so a declared component's version arrives with the
  probe that already runs. And a new optional request header, `hippocampus-client-version`
  (`contract.ClientVersionHeader`), lets any client say which build it is; the service shows it on
  that client's observed node, or on its declared node when that node has no health port of its own.
  Every client in this repository now sends it — `hippo` on both transports, the MCP bridge, the five
  event-source bridges, the ingestor, both object-storage agents, the Python client, the console, and
  an instance's own `Transfer`. A reported version is a claim and treated as one: kept only if it is
  printable ASCII of at most 64 bytes, and only ever displayed.

  The console also puts a component's version in its diagram box's tooltip. An S3 bucket, an
  archive directory, an OpenAI-compatible provider, the OTLP collector, the identity provider and the
  callback receiver have no version to report, and show none.

## [0.50.0] - 2026-10-04

### Added

- **`scripts/family-status.py`, and a release that the satellites finish** — the release workflow has
  dispatched its tag to the three satellite repositories since 0.48.0, and each opens a pull request
  re-pinning what it tracks of this one. That pull request was where the machinery stopped: it merged
  to `main` and nothing tagged, nothing published, and nothing anywhere reported the gap. At 0.49.0
  all three were carrying **two** unreleased service bumps.

  The number they carried was also false. `hippocampus-llamaindex` and `hippocampus-otel-collector`
  both declare that their version line continues this one's — which is what makes
  `hippocampus-otel-collector v0.48.0` mean "the collector built against service v0.48.0" — and cut
  by hand it meant nothing of the kind: both `v0.48.0` tags were pushed before their v0.48.0 bump
  merged, so both pin service `v0.47.0`. A version claiming a correspondence it does not have is
  worse than no version, because nothing about it looks wrong.

  Three things close that. (1) Each of those two repositories gained a **`release-on-bump`** workflow
  that fires when a raised pin lands on `main`, re-runs its tests, derives the tag **from the pin**,
  tags it and dispatches its own `Release` — so the claim is true by construction, the way
  `hippocampus-client X.Y.Z` is by construction the client of `vX.Y.Z`'s contract. Merging the bump
  pull request remains the human act of consent, and the tests are re-run on `main` rather than
  trusted from that pull request, whose verification is `continue-on-error` by design.
  (2) `scripts/family-status.py` reports the whole family's position — latest release, the service
  version pinned at that release and on `main`, and how many commits no release carries — with
  `--check` for a non-zero exit when anything is outstanding. (3) A weekly **`family-status`**
  workflow runs it and keeps one standing issue open, reopened and closed rather than one issue per
  run, so a missed release costs a week rather than seven of them.

  `hippocampus-gen` joined the dispatch at the same time, with a bump workflow of its own. It was
  the family's cautionary tale — pinned at v0.36.1, eleven releases behind, cited in every other
  satellite's bump workflow as what happens without one — and the last repository here tracking the
  contract with nothing to raise it. It has no release to cut (its five generator images publish
  from `main` on push, so merging the bump is the release) and no CI workflow, which makes that
  bump the only build its new pin gets.

  `hippocampus-obsidian` is deliberately left manual: its tag is a user-facing plugin version on
  Obsidian's community registry and its bump raises the minimum service version the plugin declares,
  so releasing it is a judgement call rather than a mechanical consequence. It is also judged on
  what a release would **ship** rather than on how many commits are unreleased — a re-vendored
  contract changes nothing a user installs, and reporting it as work awaiting a release leaves that
  line permanently red, which is how a report stops being read. Proving that nothing shipped needs a
  complete comparison, so a truncated file list or a bundled runtime dependency reports instead of
  going quiet. `RELEASE.md` gains the
  check as a closing step, and `cmd/hippocampus/family_test.go` holds the status script's repository
  table against the dispatch loop in both directions — a satellite in the loop and not the table is
  one whose staleness nobody is told about.

- **MySQL now reports what the store really occupies.** 0.49.0's storage footprint
  (`hippocampus.disk_bytes`, `GetConsolidationStatus.footprint`) and the ancillary tables'
  `disk_bytes` reported nothing on MySQL. `information_schema.TABLES` serves relation sizes from a
  cache that `information_schema_stats_expiry` refreshes at most once a day, and a stale size
  presented as the disk is worse than no size. The measurement now pins one connection, sets that
  variable to 0 for its own session and puts it back afterwards. A server refusing the variable
  fails the reading, not the store. The reading is `DATA_LENGTH + INDEX_LENGTH + DATA_FREE` per
  table, with the secondary indexes as one total. MySQL's per-index sizes need a grant an
  application user does not normally have, so `hippocampus.index_bytes` and
  `HippocampusIndexBloated` stay PostgreSQL-only, and the console's card shows one row per table.
  `HippocampusStoreDiskFarAboveEstimate` now applies to MySQL as well.

  InnoDB's gap is a different shape from PostgreSQL's, and
  [docs/operations.md](docs/operations.md#index-bloat-on-the-server-drivers) now says so. Its
  B-trees stay dense under churn, and what forgetting frees is held as tablespace free space that
  it reuses. Measured under repeated insert-and-forget rounds, that free space levelled off at
  13.6 MB rather than growing. It is a high-water mark that `OPTIMIZE TABLE` returns, not a daily
  job.

- **The Grafana alert rules are now provisioned into a real Grafana on every push.**
  `scripts/check-grafana-alerts.sh`, run by the new `grafana-alerts` CI job, boots the same
  `grafana/otel-lgtm` image the compose stacks run, with the rule file mounted where they mount it.
  It fails unless Grafana starts, holds exactly the rules `prometheus-alerts.yaml` declares, and
  evaluates each one cleanly. `alerts_test.go` holds the two rule files and the README to each other,
  but three copies can agree on something Grafana refuses, which is how the over-long uid below
  shipped. Run against that uid, the script fails with Grafana's own `UID is longer than 40 symbols`;
  run against an unparseable expression, it names the rule and the parse error.

### Changed

- **The Kubernetes Postgres overlay runs `postgres:18-alpine`**, the major the compose files moved to.
  **On a volume that already holds a cluster this is a data migration, not an image bump**: 18
  cannot read what 17 wrote, and the pod crash-loops on `database files are incompatible with
server version` until the data is dumped and restored. `deploy/k8s/README.md` gains the procedure.
  The overlay deliberately keeps its explicit `PGDATA` rather than taking 18's layout. Tested
  against a 17 volume, 18's default layout found its own subdirectory empty and initialised a new
  cluster beside the old one, so the service would have started on an empty store with no error
  anywhere. Keeping `PGDATA` fixed turns the same mistake into a refusal. The config wizard's
  generated compose file, the CI and release workflows' test databases, and the overlay's
  `wait-for-postgres` init containers move to 18 with it. The `db` conformance suite passes on 18.

- **The configuration wizard's starting points are use cases, not deployment shapes** (TODO-2
  item 131). The five it had — local, single VM, scaled, edge, archive — mostly restated the
  deployment-target tiles beneath them, covered two of the five use cases `docs/use-cases.md`
  describes, and three of them tripped the wizard's own checks: "scaled" ran OpenSearch to answer
  keyword searches every driver answers itself, "archive" configured a store with no capacity bound,
  and "archive" again set a minimum age its own retention floor made meaningless. There are now
  seven — **Agent / assistant memory**, **Personal knowledge (Obsidian)**, **Operational & audit
  history**, **Edge / device telemetry**, **Retention controller**, **Shared service, many teams**
  and **Trying it out** — each saying who it suits, naming what only the operator can supply (a DSN,
  an issuer, a receiver URL), and linking to the section of `docs/use-cases.md` that explains its
  values. That page gains a "who it suits" and a "wizard starting point" for every use case.
  `cmd/config-wizard/wizardtest` is new: it **executes** the wizard's script under `node:vm` (nothing
  to install, like the console's tests) and fails on any starting point raising an error or a
  warning it has not declared, on a value its field would not accept, and on a starting point and a
  use-cases section that do not name each other. A browser holding one of the old starting points
  in `localStorage` keeps its answers; only the tile highlight is lost.

### Fixed

- **The configuration wizard told a store bounded only by `consolidation.capacityExternalBytes` that
  it was unbounded.** The "no capacity axis" warning asked about two of the three, so the one
  configuration that sets only the external axis — a retention controller — was warned that it
  would grow until the disk ran out. The service's own decay-only check already counted all three.
- **The configuration wizard advised an unauthenticated instance to bind to loopback after it had.**
  The "Authentication is off" warning ends "Bind to loopback or set auth.method", and fired whatever
  the bind addresses were. It is now quiet when the gRPC listener is on loopback and the gateway is
  either off or on loopback too.
- **The Postgres and corporate compose stacks would not start on `postgres:18-alpine`.** Both
  mounted their volume at `/var/lib/postgresql/data`, which every image up to 17 expected and
  which 18 **refuses outright**: from that release the official image keeps the cluster in a
  major-version-specific subdirectory (`/var/lib/postgresql/18/docker`) so that `pg_upgrade --link`
  can see both versions under one mount, and it exits non-zero when `.../data` is a mount of its own
  rather than quietly initialising a cluster the volume would not persist. The weekly image bump to
  `18-alpine` therefore broke the `docker` CI job and both stacks at once — the container exited
  within half a second and the service behind `depends_on` never started. Both now mount at
  `/var/lib/postgresql`.

  An existing `postgres-data` volume holding a pre-18 cluster is still refused after this change,
  and deliberately so: that is a `pg_upgrade`, not a restart. Either run one with both versions
  available, or dump and reload — a store that forgets is not one to discard a volume from by
  accident.

- **One alert rule's uid was too long for Grafana, and the cost of that is the whole Grafana.**
  `hippocampus-store-disk-far-above-estimate`, shipped in 0.49.0 with the storage-footprint alert, is
  41 characters; Grafana's provisioning validation refuses a uid over 40 (`UID is longer than 40
symbols`), the alerting provisioner then fails to start, and **a failed provisioner takes the whole
  server down** - so one over-long uid cost every rule in the file plus Grafana itself, which exits
  rather than serving without them. Renamed to `hippocampus-disk-far-above-estimate` (35), and
  `TestGrafanaAlertRulesAreWellFormed` now holds every uid to the limit. Three of the remaining
  twenty-eight sit at 38 and 39 characters, so the guard is not theoretical.

  It survived review because nothing in the YAML looks wrong and the file had never been provisioned
  anywhere that would have noticed: the drift guard checked the wiring Grafana needs (dangling
  conditions, datasource uids, no-data policy) but not the identifiers, and this project's own demo
  had never mounted the file at all. Found by mounting it.

- **The shipped alert rules name the wrong store when a Prometheus holds more than one.** Every
  expression aggregated with a bare `sum()`/`max()` over the whole datasource, and the files' own
  headers told the reader to add `by (job)` themselves if that was not their deployment. That advice
  went untaken on this project's own public demo, which runs five independent stores into one
  collector — and what it costs is not the dilution it was described as. Measured there,
  `HippocampusStoreDiskFarAboveEstimate` evaluated to `max(disk_bytes) / max(used_bytes)` = one
  store's disk over a **different** store's estimate, a ratio belonging to neither (4.3 against the
  4.9 the affected store actually had); and `HippocampusStoreOverCapacity`, being
  `max(used) > max(capacity)`, could not fire for a small store standing behind a larger one's
  target.

  All twenty-nine rules now aggregate `by (service_name)` — `observability.serviceName`, added in
  0.48.0, which names the **store** rather than the process: replicas of one store share an OTEL
  `service.name` and re-aggregate into a single alert, exactly as before, while separate stores stay
  separate. Give each store its own `observability.serviceName` (an unset one falls back to
  `hippocampus`, which merges them again).

  Two rules needed more than a grouping key. `HippocampusStoreGrowing` now compares against
  `consolidated or evicted` rather than `consolidated + evicted`, because a store with no capacity
  target publishes no evicted series at all and `+` dropped that store from the comparison
  entirely — which is precisely the decay-only deployment the rule exists for. And
  `HippocampusConsolidatorAbsent` asks its question twice: `absent_over_time` only fires when the
  metric leaves the whole deployment, so it could never fire with more than one store reporting, and
  even with one it missed a consolidator that is up but wedged — the counter is still there, it has
  simply stopped advancing. A `count` over stores whose success counter has not advanced in an hour
  covers that. What neither half catches is one store's instance disappearing while others still
  report: its series go stale and drop out, which needs an inventory of what _should_ be reporting
  that Prometheus does not have and a liveness probe does.

- **Two capacity alerts fired on stores too small for their ratio to mean anything.**
  `HippocampusStoreDiskFarAboveEstimate` (disk over 4x the estimate) and `HippocampusIndexBloated`
  (over 512 bytes an index entry) are right for a store whose own rows dominate its file. They are
  meaningless for a nearly empty one, whose few megabytes of catalogue and empty-index pages divide
  into a large ratio. Measured on the demo with every rule evaluating, the disk alert sat pending at
  13.2x on a 403 KB estimate and 8.9x on 835 KB, against 4.5x on 151 MB, and the last is the only one
  that meant anything. The index alert fired on a 2,000-memory store. Both now carry an absolute
  floor, 64 MiB of database and 16 MiB of index, rather than a higher ratio, which would have hidden
  the large store too. A promtool test of the measured figures fires on the large store alone.

- **`docs/operations.md` said eighteen alert rules ship where twenty-nine do**, a fourth copy of a
  count that nothing executed. It is now held by `TestOperationsRuleCountIsCurrent`, alongside the
  guards already covering `CLAUDE.md` and `deploy/observability/README.md`.

## [0.49.0] - 2026-09-21

### Added

- **The ancillary storage report says which cap is actually in force, and what the disk really
  holds.** `GetConsolidationStatus`'s `ancillary` block gains four fields per table —
  `binding_limit` (`rows`, `bytes`, `age` or `none`), `limit_rows` (the effective row cap: the
  tighter of the configured row cap and whatever `maxBytes` resolves to at this driver's per-row
  allowance), `limit_age_seconds`, and `oldest_at` — plus `disk_bytes`, what the engine reports the
  relation really occupies, space it has not reclaimed included. The console's Deployment tab shows
  all of it, and the service logs the binding when it changes. The caps were independent bounds with
  no precedence between them, and which one acted depended on how fast the store was forgetting: a
  forgotten log configured `maxRows: 100000` with `maxAgeInDays: 30`, on a store forgetting 19,000
  memories a day, held **five days** of the thirty it had been asked for — both caps enforced,
  neither violated, and nothing anywhere that said so.

- **What the store really occupies on disk, reported beside what its accounting counts
  (PostgreSQL).** `used_bytes` is a live-row estimate on the server drivers and stays one — eviction
  driven by a file-size measure would chase a reading that never drops after a delete — so nothing
  compared the estimate with the disk. On a high-churn store the two diverge by most of an order of
  magnitude: a measured instance reported 153 MB against a 160 MB `capacityBytes` while holding an
  892 MB database, of which 687 MB was indexes on `memories` and 533 MB was the covering index alone,
  at 5% average leaf density. `VACUUM` marks a B-tree page a delete emptied as reusable and never
  repacks it, so **a store that forgets is a store whose indexes bloat**, without bound, as a direct
  cost of the thing the service exists to do.

  Three gauges — `hippocampus.disk_bytes`, and `hippocampus.index_bytes` /
  `hippocampus.index_entries` by `table` and `index` — plus a `footprint` block on
  `GetConsolidationStatus` carrying the same figures with the cycle's own estimate beside them.
  Measured once per cycle from the catalogue, so it costs a handful of round trips and reads no
  rows; `pgstatindex`'s `avg_leaf_density` is deliberately not taken, since it reads every page of
  the index. Two alerts ship with it (`HippocampusStoreDiskFarAboveEstimate`,
  `HippocampusIndexBloated`) and the cycle logs the ratio when it crosses, naming the index costing
  the most per entry. The console's Deployment tab shows it below the ancillary card, one row per
  index largest first.

  **The service does not act on any of it.** `REINDEX INDEX CONCURRENTLY` is online but is still a
  maintenance decision, and a memory store that rebuilds its own indexes on a timer surprises its
  operator at the moment it is already under pressure.
  [docs/operations.md](docs/operations.md#index-bloat-on-the-server-drivers) carries the runbook and
  the cadence the measurement justifies, which is **daily**: the reindexed instance above was back
  from 151 MB to 634 MB nine hours later. SQLite reports nothing because page accounting already
  counts every index inside the capacity target; MySQL reports nothing because
  `information_schema` serves relation sizes from a cache refreshed at most once a day, and a stale
  figure presented as what the disk holds is worse than none.

- **Three instruments for the OpenSearch apply queue and the sweep that backs it up.**
  `hippocampus.search.queue_depth` and `hippocampus.search.queue_capacity` are the pair
  `opensearch.queueSize` is tuned on — a queue that is spiky and near zero between bursts is one a
  larger size fixes, while one pinned at capacity is being outrun and no size will help, and nothing
  previously distinguished the two. `hippocampus.search.documents_healed` counts what the
  reconciliation sweep had to write, which is the first direct measure of how much propagation is
  actually losing. `hippocampus.search.dropped` gains a `reason` attribute (`queue_full` or
  `apply_failed`), because the two have unrelated remedies: one is a rate, the other is a cluster.

- **`consolidation.significanceLevels.unusedRetentionInDays`** (default 7) — how long the
  significance registry keeps a value nothing carries any more, before the sleep cycle reaps it. 0
  keeps every value the store has ever seen, which is what previous releases did. Two instruments
  come with it: `hippocampus.significance_levels` (the registry's size, published whether or not
  anything is being reaped) and `hippocampus.significance_levels.reaped`.

### Changed

- **The search-index reconciliation sweep asks the index what it holds before writing anything.**
  For each page of memories it sends one `_mget` and indexes only the ids that came back missing, so a
  healthy index costs one request per page and no writes at all. It used to re-index every live memory
  on every pass, which cost three things that all grew with the store: it was the dominant producer on
  the very queue it exists to compensate for, so live writes were the operations dropped to make room
  for re-writes of documents already present; with semantic search on it re-embedded the entire store
  every pass; and in Lucene a re-index is a delete plus an insert **even when the document is
  byte-identical**, so an hourly sweep tombstoned the whole index once an hour. One live deployment
  held 921,741 deleted documents against 147,496 live ones, 341 MB that a force-merge took to 215 MB.

  A failed probe now indexes nothing rather than falling back to indexing the page: a probe fails for
  the same reasons a write does, so the fallback would offer a full page of writes at exactly the
  moment nothing can be applied. The next sweep asks again. One thing the sweep no longer heals is a
  document that is present but missing its embedding vector — `--backfill-search --reindex` covers
  that — since comparing vectors would mean fetching ~3 KiB per memory per pass.

  The sweep also no longer runs at all against the store's own content index, which maintains itself
  inside the primary write and has nothing to reconcile. Every deployment on the default content index
  was paging its entire store every hour to call a no-op on each row.

- **The dropped-index-operation warning is now one summary every 30 seconds** naming the total and the
  breakdown by reason and operation, rather than one line per drop. Measured on a live deployment, the
  per-drop line ran at 113,377 in thirty minutes — 63 a second — filling a 4 GB systemd journal with
  one repeated sentence and rotating away everything else the service had to say. A warning that fires
  63 times a second is not a warning. The metric still counts every drop; a counter loses nothing to
  aggregation, and the summary states more than any single line it replaces.

- **`hippocampus.ancillary_bytes` and `ancillary.total_bytes` now report what the engine is
  holding** rather than what the rows would occupy compacted, where the driver can say — a catalogue
  lookup on PostgreSQL; unchanged on SQLite, where a page a prune frees returns to the freelist
  `used_bytes` already excludes and the two figures are the same, and on MySQL, whose
  `information_schema` sizes are cached for a day by default and so would report yesterday's. On
  PostgreSQL under steady churn the difference is around a factor of two, and
  [`HippocampusAncillaryStorageHigh`](deploy/observability/README.md) was reading the estimate. Each table's `bytes` still carries the structural figure, which is what the byte caps are
  enforced against and what `used_bytes` excludes — deliberately, since a cap that grew with a
  table's dead rows would prune harder, leave more dead rows, and prune harder again.

### Fixed

- **A replica no longer refuses to start because the consolidator was mid-cycle.** On PostgreSQL and
  MySQL the content index is kept in step with a foreign key, and the backfill that populates it on
  first sight — enabling the index, or upgrading into it — reads the memories a page at a time with
  nothing holding them still. A memory deleted between the page that read it and the insert that
  indexed it violated that foreign key, and because the backfill is a schema migration's work the
  error failed the migration, which failed the **open**: the service did not start. The window is
  widest exactly where it matters, since a backfill over a large store takes a long time and that is
  when a consolidation cycle is most likely to land inside one.

  Both server dialects now resolve the id through a `SELECT` over `memories` in the insert itself,
  which is the shape SQLite's has always had. A memory that is gone matches no row, so the write is
  a no-op rather than an error — and the right one, that being the index state the cascade would
  have left had the delete landed a moment later. The read and the insert are one statement, so
  there is no interleaving left to lose.

- **The significance registry no longer grows without bound.** It gains a row per distinct
  significance value ever written and, until now, lost one only to a `Purge` — which made it the one
  table in the store that grew with the store's **history** rather than its contents. A producer
  writing varied significance left a level behind for every value it had ever used, long after the
  last memory carrying that value was forgotten; one live deployment held 29,001 levels against
  211,657 memories, in neither `used_bytes` nor the ancillary report.

  The sleep cycle now reaps levels nothing carries, after `unusedRetentionInDays`. The window is
  there because the registry is the scale `SignificancePlacement` positions against and
  `GetSignificanceLevels` reports — a value carried by nothing today is not necessarily one a client
  has finished with — so **`GetSignificanceLevels` can now return fewer values than it used to** on
  a store whose scale includes values that have been out of use for over a week. Set
  `unusedRetentionInDays` to 0 for the previous behaviour.

  A level is marked on the cycle that first finds it unused and removed only by a later one, rather
  than deleted on sight. That is not tidiness: a level is handed out _before_ anything references
  it, and there is no foreign key, so deleting one in that window would leave a memory pointing at a
  level that no longer exists — which every read resolves to unranked, silently costing that memory
  its significance in a store that decides what to forget by significance.

- **The forgotten log's and the delete outbox's per-row allowances are now per driver, and
  measured.** One flat 192 bytes a tombstone and 96 an outbox row served all three drivers; measured
  against real relations after a compaction, a tombstone costs 165 bytes on SQLite, 255 on
  PostgreSQL and 345 on MySQL, and an outbox row 75 / 120 / 185. The figure is reported to an
  operator, read by an alert, and used to convert `maxBytes` into a row cap, so it was understating
  the log and admitting more rows than the byte cap said on the two server drivers.
  `TestAncillaryAllowancesMatchRealStorage` now holds all six to real disk on all three drivers, in
  the mould of `TestRowOverheadMatchesRealStorage`.

## [0.48.0] - 2026-09-20

### Added

- **`observability.serviceName`** — what this instance calls itself in the telemetry (the semconv
  `service.name` resource attribute). Empty falls back to `hippocampus`, which is what every
  previous release reported, so an existing configuration is unchanged.

  It exists because the service was the one component that could not set it. `observability.Config`
  has carried the field since the package was promoted out of `cmd/hippocampus`, and the ingestor
  and the object-storage agents both set it; `cmd/hippocampus` never did, and no key reached it, so
  every Hippocampus instance everywhere reported as `hippocampus`.

  That is invisible on one instance and destroys the metrics on several. The OTLP-to-Prometheus
  translation promotes only `service.name`, `service.version`, `job` and `instance` onto each series
  and puts every other resource attribute in `target_info`, so instances sharing a name publish
  **one series per instrument between them** — the value a dashboard or an alert rule reads is
  whichever instance exported last, flapping at the export interval. Found on a host running five
  independent stores against one collector, where `hippocampus_memories_count` had exactly two
  series (differing only by the `has_event` attribute) and alternated between a store holding 617
  memories and one holding 127,959. The shipped rules in `deploy/observability/` cannot attribute a
  fault under that, and a store that stopped forgetting would not have shown up at all.

  It matters in the topology this project documents as its scaling model — one consolidator plus N
  replicas over a shared Postgres — as much as on a host running several separate stores. Set it per
  instance wherever more than one reports to the same collector.

  The viper reads it needs moved into `observabilityConfigFromViper`, in the same mould as
  `hmacConfigFromViper`: the reads stay in `main.go` and what they produce is a plain struct a test
  can assert on.

## [0.47.1] - 2026-09-13

### Changed

- **Three subprojects moved to their own repositories**: the Obsidian plugin, the LlamaIndex adapter
  and the OpenTelemetry collector exporter. Nothing about the service changed; what changed is where
  those clients are developed and released.

  The rule used to be "one release train, plus Obsidian". It is now that a subproject stays here if
  it tracks **this** contract, and leaves if it tracks somebody else's release train. By that test
  the `hippo` CLI stays (it changes with the contract in two commits out of three), the Python client
  stays (its stubs are generated from `contract/hippocampus.proto` at build time), and the MCP bridge
  stays (its tool surface is a security statement held to the contract by tests) — while the plugin
  hand-writes its wire types and imports nothing from here, the adapter tracks `llama-index-core` and
  depends on the published client, and the collector tracks twelve collector modules on a dual-series
  fortnightly cadence.

  The plugin's case was decided by distribution rather than by cadence: Obsidian's community registry
  lists a repository whose **root** holds `manifest.json`, which a monorepo cannot offer, so the
  plugin could not be listed from here at all.

  | Was                       | Now                                                   |
  | ------------------------- | ----------------------------------------------------- |
  | `integrations/obsidian`   | [fastbean-au/hippocampus-obsidian][obsidian-repo]     |
  | `integrations/llamaindex` | [fastbean-au/hippocampus-llamaindex][llamaindex-repo] |
  | `integrations/otel`       | [fastbean-au/hippocampus-otel-collector][otel-repo]   |

  For consumers: the plugin's releases continue from `0.3.0` in its own repository (BRAT cannot
  follow the move — remove it and re-add `fastbean-au/hippocampus-obsidian`), and
  `ghcr.io/fastbean-au/hippocampus-otel-collector` is the same package published from its new home,
  so existing pins keep resolving. The collector exporter's Go import path changed to
  `github.com/fastbean-au/hippocampus-otel-collector/hippocampusexporter`, which matters only if you
  reference it from your own OCB manifest.

- The release workflow gained a `notify-satellites` job, which tells each satellite repository that a
  release exists so it can re-pin what it tracks and report whether it still builds against it. A
  satellite nobody tells drifts silently — `hippocampus-gen` has sat eleven releases behind its pinned
  version for exactly that reason.

## [0.47.0] - 2026-09-12

### Added

- **The object-storage agents: decay as a retention controller over a bucket.** The retention-
  controller mode — the payload stays where it is, Hippocampus holds one pointer-memory per record
  and decides what survives — has had its parts in place since 0.45.0 and nothing to carry the
  decisions out. Two new commands in a new module, `integrations/objectstore`, close the loop against
  S3 (and MinIO, and anything S3-compatible):

  `hippocampus-object-gateway` is the **tap**. It fronts the bucket and reinforces the pointer-memory
  behind every object it serves, which is what keeps recall reinforcement — the one input no expiry
  policy has — reaching a store that never sees the reads. By default it presigns and answers 302, so
  no payload byte passes through it; `--mode proxy` streams instead and forwards `Range` requests. A
  `POST /recall` endpoint takes keys from a chokepoint you already have, for a deployment that does
  not want a new one on the request path.

  `hippocampus-object-reaper` is the **actuator**. It deletes the object behind a memory that has been
  forgotten, by three paths that back each other up: the `memory_forgotten` callback as the cycle
  runs, the forgotten log read back over a window at startup, and a reverse sweep of the bucket. It
  does **not** delete by default — without `--delete` every deletion is selected, counted and logged
  and none is carried out, which is the state to compare against whatever flat expiry it is replacing
  before a decay model becomes authoritative over data the store cannot see.

  Both hold no state at all, and one decision is what buys that: a pointer-memory's id is
  `<bucket>/<key>`. The tap reinforces a derived id without asking whether the memory exists (a recall
  that matches nothing is a no-op) and the reaper turns a forgotten id back into the object it named.
  A hash would have been the obvious choice and is the wrong one — the forgotten log carries ids and
  deliberately never bodies, so an agent catching up after an outage would be unable to name a single
  object.

  Three of the guards are worth stating because they are what makes an agent that deletes other
  people's data safe to run: the sweep never judges an object younger than `--sweep-min-age` (24h,
  and not disableable, or it would race every producer write); it **stops** rather than deleting
  anything if the store cannot be asked what it holds; and `--causes` defaults to the decay paths
  only, so an Export's `clear` (a move) and a `Purge` (an operator resetting the store) never reach
  the bucket.

  Both publish `hippocampus.objectstore.*` metrics and serve `/healthz`+`/readyz`, with three new
  alert rules in both shipped rule files. The tap's hit rate is among them: the ids it recalls are
  derived, so a producer writing memories under any other scheme reinforces nothing, silently and
  forever — `HippocampusObjectTapNotReinforcing` and a Warn line are the only things that would ever
  notice. Images are published per agent and both binaries are on the release. See
  [`docs/objectstore.md`](docs/objectstore.md).

- **`callbacks.backlogPolicy` — a forget-callback can now be an instruction rather than a
  notification.** The outbound queue was built for notifications, and its caps are right for one: a
  receiver that has been unreachable for a day is not helped by a day-old summary of a cycle. A
  `memory_forgotten` callback is a different thing whenever the receiver is the system holding what
  the memory pointed at (`Memory.external_bytes`) — it is an instruction to delete a payload this
  store cannot see, and discarding it orphans that payload permanently, in a leak that is monotonic,
  silent, and grows precisely with how well the decay cycle is working.

  The new key decides who absorbs a receiver outage that outlasts the caps. `abandon` (the default,
  and exactly today's behaviour) discards the oldest deliveries, and the far system pays in orphans.
  `retain` exempts the two deletion kinds from the caps, and this disk pays in a queue nothing trims.
  `stall` is `retain` plus a bound: past the caps the sleep cycle's consolidation and eviction passes
  do not run, and the workload pays in a store that has stopped forgetting until the receiver is
  fixed. The `sleep_completed` and `memories_at_risk` kinds stay capped under every policy — both are
  worthless once stale. `stall` with none of `callbacks.maxRows`/`maxAgeHours`/`maxBytes` set is
  refused at startup, since nothing would ever be trimmed and nothing would ever stall.

  A stalled cycle is reported rather than left to be inferred from its zeroes: `CycleReport` gains
  `stalled` and `stalled_reason` (so `GetConsolidationStatus`, `hippo status` and the console's Now
  tab all say so), a Warn line is logged every cycle, `hippocampus.forgetting.stalls` counts them,
  the new `HippocampusForgettingStalled` alert rule ships in both rule files, and the flag travels on
  the `sleep_completed` delivery itself — the receiver being the one party that can end the stall.
  Two startup warnings frame the choice: a retaining policy without the forgotten log (which is the
  catch-up path a rebuilt receiver pages back through), and an external capacity target still on
  `abandon`.

### Documentation

- **A documentation index and an install page, and a README that points at both.** The two guide
  tables in `README.md` had become the only map of `docs/`, which made the front page longer than
  the thing a first-time reader actually wants from it — how to install this. The index moved to
  [`docs/README.md`](docs/README.md), where GitHub serves it on browsing the directory, and is
  arranged by what a reader is trying to do rather than alphabetically; it covers the deployment
  artefacts under `deploy/` and the subprojects under `integrations/` as well as the guides, neither
  of which the README's tables reached. The five install routes — Homebrew, the `.deb`/`.rpm`
  packages, the GHCR images plus the Compose and Kustomize artefacts, the release binaries, and a
  build from source — were spread across `getting-started.md` and `operations.md` with only the
  demo-stack clone on the front page; they are now one page,
  [`docs/install.md`](docs/install.md), a command each, with `getting-started.md` deferring to it
  rather than carrying an abridged copy. The README keeps one install command and four links.
- **The retention-controller deployment mode is written down.** `docs/use-cases.md` described four
  topologies, all of which assume this store holds the data. The mode where it does not — one
  pointer-memory per external record, `external_bytes` carrying the payload's size,
  `consolidation.capacityExternalBytes` as the axis pressure is measured on, and a
  `memory_forgotten` callback doing the deleting — had shipped across three releases with its parts
  documented separately and the shape they make never stated. It is now a deployment mode beside the
  others, including what it gives up (recall reinforcement goes dark until a tap is wired, and
  wiring one is per-integration), which actuators suit it (buckets yes, column stores no), the
  `days_until_forgotten` escape hatch for the ones that do not, and what has to be true before it is
  authoritative over data the store cannot see.
- **The documentation pages dropped their decorations.** Every guide link in `README.md` and the new
  index carried a leading emoji, and seven pages under `docs/` opened with the same gopher image
  between the title and the first sentence. Both are gone, and the README's prose was loosened —
  contractions, shorter sentences — since a front page that reads like a specification is a poor
  advertisement for one.

- **Two pages still said the forget-callback could not be relied on.** `docs/configuration.md` and
  `docs/consolidation.md` both closed their external-capacity sections with "a best-effort
  notification rather than a guaranteed instruction — until that gap is closed", which
  `callbacks.backlogPolicy` closed above. Both now name the setting and say which value a deployment
  holding payloads elsewhere wants; both keep the advice to leave the far end's own expiry
  configured as the outer bound, which is true for a different reason — a controller that has
  stopped running publishes no instructions at all.

### Fixed

- **Empty events no longer accumulate forever.** Two independent halves met in one place, and the
  measurement is what found it: the two public demo stores configured to forget on the capacity
  target alone (`consolidation.deletionThreshold: 0` with a positive `capacityBytes`) were each
  carrying tens of thousands of events holding no memories — 36% and 35% of their event tables —
  spread back over days, while the three stores with a positive threshold carried none at all.

  The first half is the bare-event pass. Its query selects exactly the orphan set, and then gates
  each row on the value function: every decay method is a non-negative significance over a positive
  age, and the threshold is `deletionThreshold × pressure`, so with the threshold at 0 the bound is
  0 however pressure scales it and nothing is ever below it. The pass ran every cycle, scanned every
  orphan, and deleted none of them. The second half is that eviction reaches an event only through a
  memory it is deleting, so an event stranded with no memories can never enter an eviction pass
  again — which makes any failure of eviction's own empty-event cleanup permanent (the 0.44.0 upgrade
  produced 9,965 of that error on one store inside a minute).

  An empty event is now swept rather than valued in two cases, both subject to
  `consolidation.minimumRetentionInDays`, which overrides them as it overrides the capacity target.
  **Any mode:** an event the decay machinery emptied — carrying `memories_consolidated` and holding
  nothing — is deleted whatever its own value, because that deletion was already decided: the store
  deletes an event as a pass takes its last memory, whatever the event is worth, so one still
  standing is a cascade that did not happen (its last memory left by a route that does not cascade,
  or the cascade failed and flagged the event instead). **Capacity target only:** every event holding
  no memories is swept, because value-based consolidation is off there and nothing else would ever
  reach them; orphan events are counted toward neither the byte estimate nor the eviction pool, so a
  store could sit exactly on its capacity target with a third of its event table unreachable.

  Everywhere else an empty event still has to decay past the threshold like anything else.
  `PreviewConsolidation` reports the swept events, since it evaluates through the same decision.

  **Expect one large cycle after the upgrade** on a store that has been accumulating them: the
  backlog is swept in a single pass, one transaction per event, and the two demo stores are carrying
  around 19,500 and 15,000. `hippocampus_events_consolidated_total{has_memories="false"}` steps by
  the whole backlog once and then settles, and that cycle's duration steps with it.

## [0.46.0] - 2026-09-10

### Added

- **The three tables outside the capacity target can now be bounded in bytes, not only in rows.**
  `consolidation.tombstones.maxBytes`, `opensearch.outbox.maxBytes` and `callbacks.maxBytes` join
  the row and age caps already on each; all three default to 0, which is unbounded, so nothing
  changes for an existing configuration. 0.44.0 made what these tables hold visible
  (`hippocampus.ancillary_bytes`, the console's Deployment tab, an alert rule); this is the half
  that lets an operator do something about it, and the half that lets a disk be sized in one unit
  rather than three.

  For the forgotten log and the search outbox this is convenience: their rows are fixed width, so
  the row cap already **is** a byte cap — roughly 19 MB and 96 MB at the defaults — and `maxBytes`
  is the same bound stated in the unit a disk is sized in, converted exactly, with the tighter of
  the two winning.

  **The callback queue is the one that needed it.** A row there is a whole delivery: up to
  `callbacks.maxIdsPerDelivery` items (500), each of which may carry a memory body up to
  `callbacks.maxBodyBytes` (64 KiB) under `callbacks.includeBodies`. `callbacks.maxRows` therefore
  bounded it somewhere between a few hundred megabytes of bare ids and a figure with no useful
  ceiling — and on the embedded driver the queue and the store are the same file, so a receiver that
  was down while a large cycle ran grew the disk while capacity pressure stayed exactly where it
  was. The one number an operator is told to watch read green while the resource it exists to
  protect was going.

  Applying that cap costs no scan of the payloads: `callback_queue` gains a `payload_bytes` column,
  written at insert where the size is already known, added in place on the next startup like every
  other column migration and backfilled from the rows already queued. The same column makes the
  **reported** figure a measurement rather than an estimate — a delivery carrying five hundred
  memory bodies and one carrying five hundred bare ids are the same row to a count, and two orders
  of magnitude apart on disk — so what the console shows, what eviction ignores and what gets
  trimmed are one figure rather than three.

  Two properties worth knowing. Reaching a byte cap **discards rows**, exactly as a row cap does: an
  abandoned callback is a notification nobody will ever receive. And the newest callback delivery is
  never abandoned for the cap — a delivery larger than the whole cap would otherwise be discarded
  the instant it was queued, for the life of that configuration, so the bound you actually get is
  `maxBytes` plus at most one delivery, and that case is logged at Warn naming the keys to lower.
  None of the three is defaulted, because how much of this a deployment can afford is a property of
  its disk rather than of the service, and a cap that discards data should be chosen rather than
  inherited. What stands in for a default is a startup warning where the shape is dangerous:
  `callbacks.includeBodies` with no `callbacks.maxBytes`.

  `GetConsolidationStatus`'s `ancillary` block reports each table's `limit_bytes` beside its size,
  and the console's Deployment tab renders the pair — a byte count with nothing to read it against
  cannot distinguish a queue that is filling from one that is about to start discarding.

- **The configuration wizard now flags combinations that start cleanly and then do not do what they
  look like they do.** Its checks had covered the two easy classes — what the service refuses at
  startup, and what a single key gets wrong on its own — and neither catches a configuration in
  which every value is individually valid and the combination is not. The one that prompted this:
  OpenSearch enabled with no embedding model, which stands up a cluster to answer keyword searches
  the store already answers on its own, in the same transaction as the write, on every driver.
  Fourteen new checks in that class, each naming the case where the pairing is deliberate rather
  than simply refusing it: a store with nothing to trigger a consolidation cycle; sleep-cycle
  settings (the forgotten log, the summarisation scan, automatic summarisation) on a replica, where
  they are silently inert; a `minimumAgeInDays` shorter than the retention floor that covers it; a
  `defaultEventSignificanceValue` beside a non-zero percentile that overrides it; retention against
  a capacity target it can hold a store permanently above; a loopback bind address under the Compose
  and Kubernetes targets, where nothing outside the container can reach it; a query timeout below a
  consolidation scan; both content indexes maintained while only one is read; no content index at
  all; a transfer target with no object store. Four more mirror startup refusals the wizard did not
  yet know about — semantic search without OpenSearch, an `openai` provider left on the Ollama
  default address (both blocks), and a Prometheus scrape port already taken by the gRPC or gateway
  listener.

  Issues are now sorted by severity on the step pages and the review screen, so a startup refusal
  cannot sit below three notes about things that are merely worth knowing.

### Documentation

- **The callback sink is HTTP and only HTTP, and `docs/configuration.md` now says so.** A deployment
  whose event bus is NATS, Kafka, MQTT or RabbitMQ receives these deliveries through a small
  HTTP-to-broker shim, not by configuring a broker here — which is deliberate rather than pending,
  the broker clients this repository ships living in a separate module the service's own build does
  not import. The note also states the two things such a shim needs to know: a 2xx confirms a
  delivery and discards it, and redelivery carries the same body with nothing on the wire
  identifying it, so exactly-once means deduplicating on a hash of the body.

### Fixed

- **The wizard refused a valid configuration and mis-gated one check.** A non-positive
  `consolidation.deletionThreshold` is rescued by `consolidation.capacityExternalBytes` exactly as
  it is by `consolidation.capacityBytes` — the service has accepted that pairing since the external
  axis landed — but the wizard reported it as an error, so a retention controller over storage held
  elsewhere could not be built here without ignoring a red banner. The automatic-summarisation
  check also read `llm.autoSummarise` without first asking whether the LLM was enabled, so it could
  fire on a value left behind by a setting since turned off and never written to the config file.
  The external capacity axis also gains the two checks its byte-axis counterpart already had, its
  floor being the one the service does **not** refuse: a floor at or above its target is silently
  replaced by the target, so the configuration reads as though it has hysteresis and has none.

## [0.45.0] - 2026-09-10

### Breaking

- **`consolidation.capacityBytes` now regulates a figure three to five times larger on `postgres`
  and `mysql`, and somewhat larger on `sqlite`. Re-derive your capacity target from real disk before
  upgrading.** The key is unchanged, the values it accepts are unchanged, and no configuration
  becomes invalid — but the number it is compared against has moved, so a store sitting comfortably
  under its target today can be over it on the first cycle after the upgrade, and that cycle will
  evict hard.

  What was wrong: the store estimates its live size as each row's stored payload plus a per-row
  allowance for everything else the row costs. That allowance was a single 256-byte constant shared
  by all three drivers, unchanged since the initial commit, while the columns it allowed for grew, a
  second index was added, the covering index was widened twice and the content index arrived. Its doc
  comment had always claimed to cover "the remaining columns and the index entries"; it had never
  been measured against either. Measured over 10,000 memories, the Postgres row alone costs 400 bytes
  and the MySQL row 1,050, and neither figure included the content index — 11 to 40 MiB of it — at
  all. The result was a capacity target regulating a figure **3.0x to 5.0x smaller than the disk**,
  on the one setting an operator is told to size a volume from.

  What replaces it: a measured allowance per dialect, in two parts — a per-row cost, and the content
  index's share, which is itself a per-row cost plus a term proportional to the body, because an
  inverted index necessarily grows with the text it indexes. A flat allowance cannot express that,
  which is why the obvious "bigger constant" is not what shipped. Against real relation sizes, across
  bodies from 64 bytes to four kilobytes, both index modes and compression both ways, the estimate now
  lands within about 10% on all three drivers.

  The estimate deliberately remains an estimate. Asking the server for its relation sizes would be
  more accurate and quite wrong: no file-size measure on either server shrinks after a `DELETE`, so
  eviction would chase a figure that cannot drop and would drain the store trying.

  **What to do.** If `consolidation.capacityBytes` is unset or zero, nothing changes — there is no
  byte target. If it is set, it was very probably derived from what the disk was doing rather than
  from the store's own reported figure, in which case it is now roughly right and may need no change.
  If it was derived from `hippocampus.used_bytes` or the console's capacity meter, multiply it by
  three to five on the server drivers before upgrading. Either way the service now says so at
  startup: a store already over its target logs a warning naming both figures, before the first cycle
  runs.

### Changed

- **`memories` gains an `indexed_bytes` column**, added in place on the next startup like every other
  column migration; no action is needed and an older store opens unchanged. It records how much of
  each memory's plain body the content index holds — nothing for a binary memory, which is never
  indexed — because that figure cannot be recovered afterwards: the stored body may be compressed,
  and the index is fed the body before compression happens. Measured, a content index is the same
  size to within a byte whether the bodies beside it were compressed or not, so an estimate scaled
  off the stored length under-counts it by exactly what compression saved — which on the shipped
  default configuration (compression on, the store's own content index on) was about a quarter.
  Memories written before the column exists have no recorded figure and fall back to their stored
  length, which is exact for an uncompressed row and low for a compressed one, so an upgraded store
  estimates no worse than it did and every row written since is right.

- **`hippocampus.used_bytes`, the capacity meter, `PreviewConsolidation`'s byte totals,
  `RetainedStats` and eviction's estimate of what a deletion frees all move together**, being four
  readings of the one figure above. `ForgetCandidate.bytes` is unchanged: it reports the memory's
  stored payload, as it always did.
- **The store's own content index now moves capacity pressure on the server drivers.** It was inside
  the target on `sqlite` (page accounting cannot exclude a table in its own file) and outside it on
  `postgres` and `mysql`; it is now allowed for on all three, so turning
  `search.contentIndex.enabled` off frees measurable headroom rather than only disk.

### Added

- **A test that holds the per-row allowances to real disk.** `TestRowOverheadMatchesRealStorage`
  writes a known number of memories of a known size on each driver — in both index modes, and with
  bodies stored compressed as well as plain — and fails if the estimate falls outside a band of what
  the server reports it is really holding. The compressed cases are the ones that matter most: every
  uncompressed case passed while the default configuration was being under-counted by a quarter. It is a band
  rather than a value because page fill and allocation granularity move a few per cent between runs,
  and a test that failed on that would be turned off rather than read. The MySQL case needs
  `HIPPOCAMPUS_TEST_MYSQL_ADMIN_DSN` as well as the usual DSN: a `FULLTEXT` index's auxiliary tables
  are tablespaces of their own, visible only to a connection with the `PROCESS` privilege, and they
  are a large part of what that index costs.

## [0.44.0] - 2026-09-10

### Added

- **The store's own content index can be turned off, and is by default where OpenSearch answers
  every search.** `search.contentIndex.enabled` is **derived when unset** — on with
  `opensearch.enabled` false, off with it true — and overridable in either direction, the same
  treatment `reflection.enabled` gets. A startup line reports the choice and its reason.

  It exists because that index was not optional. Only one search backend is ever selected, so on an
  OpenSearch deployment the store's own index was written for every memory — inside the storage
  boundary, before compression sees the body — and then read by nothing for the life of the store.
  Measured over 20,000 memories of log-shaped JSON it is the **largest non-body cost the store
  carries** on every driver: 43–59% of the payload on `sqlite`, where at 4 KiB bodies the index is
  larger than the compressed bodies it indexes; 22 MiB against a 4.9 MiB payload on `postgres`; and
  on `mysql`, where a `FULLTEXT` index is an index on a _column_, a second uncompressed copy of every
  body — 40 MiB against 19.5 MiB.

  Disabling **drops** the index rather than ceasing to maintain it. An index that stops being written
  does not become empty, it becomes wrong — it would go on answering from a subset that shrinks with
  every consolidation cycle, and a search that silently returns some of the matches is worse than one
  that refuses. Dropped, `SearchMemories` answers `FAILED_PRECONDITION` and `WhoAmI.search_modes`
  reports the absence, so a client feature-detects rather than search-and-fails. Re-enabling needs
  nothing: the index is recreated and repopulated on the next startup by the same path a store
  written before content search existed takes.

  The setting deliberately does **not** gate the schema migration that carries the index, which is
  recorded either way. Gating it would move a store's schema version up and down as the key changed,
  and a build meeting the higher of the two would refuse — with `ErrSchemaTooNew` — to open a store it
  understands perfectly.

- **The storage the capacity target cannot see is now reported.** The forgotten log, the search
  outbox and the callback queue are excluded from `hippocampus.used_bytes` deliberately — the record
  of what was deleted must never be the reason live memories are evicted, and the outbox is the sharp
  version of that, since it grows precisely when deletions are backing up. The exclusion is
  unchanged. What was missing was any way to see how large the excluded part had grown.

  On the embedded driver those three tables share the store's own database file, so a receiver that
  is down while a large cycle runs grows that file, capacity pressure stays exactly where it was, and
  the one number an operator is told to watch reports headroom right up to a full disk — where the
  failure is not "it forgot too little", it is every write failing at once.

  `GetConsolidationStatus` now carries an `ancillary` block: total bytes, and per table the row
  count, the estimated bytes and whether anything is still recording into it. The new
  `hippocampus.ancillary_bytes` gauge publishes the same figures, labelled by `component`, and a
  `HippocampusAncillaryStorageHigh` rule ships in both rule files, firing when the three together
  exceed a quarter of `consolidation.capacityBytes`. The console's Deployment tab shows the reading
  under the callback queue, and the bundled Grafana dashboard has a panel for it.

  Three things worth knowing about the figure. It is the **same** one the capacity target subtracts,
  so what is shown and what eviction ignores cannot disagree. It is a row count times a flat per-row
  allowance rather than a measurement, because summing the stored payloads would put a scan of the
  queue on the path that exists to bound the store — and it is taken **once per sleep cycle** rather
  than per request, so the block reports `measured_at` and a client should read it as a reading with
  an age rather than a live figure. And a component reporting `enabled: false` beside a row count is
  a table switched off that still holds what it wrote: disabling any of the three stops the writing
  _and_ the trimming.

  Nothing here caps or trims on the figure. The callback queue remains the one whose rows have no
  fixed size — a delivery carries up to `callbacks.maxIdsPerDelivery` items, and memory bodies under
  `callbacks.includeBodies` — so `callbacks.maxRows` bounds its bytes only loosely, and a byte cap is
  still to come.

### Changed

- **An OpenSearch deployment drops its store-side content index on the next startup**, following the
  new derived default above. That is the reclaimed storage the change is for, and it is reversible by
  setting `search.contentIndex.enabled` true. The shipped `docker-compose.opensearch*.yaml` stacks
  are affected: they keep working, with search answered by OpenSearch as before.
- **The web console's guided tour and card blurbs were rewritten in a plainer, contracted voice.**
  The tour is offered unprompted on a first visit, so it is the one piece of writing here aimed at
  somebody who has not decided to concentrate yet; the reference register it was written in made an
  unusual idea sound harder than it is. Same content, same figures, fewer clauses. The console is
  not covered by the version number.

### Fixed

- The configuration wizard described built-in keyword search as a SQLite-only feature. It has been
  available on every driver since 0.42.0.

## [0.43.0] - 2026-09-09

### Added

- **An external capacity axis, so decay can govern storage this store does not hold.** Every capacity
  measure the service had was about its own disk, which meant the one control it has that an
  age-based expiry does not — capacity pressure, a _budget_ that tightens when a traffic spike
  threatens it, rather than an _age_ that hopes the resulting volume fits — could only be applied to
  data it was storing. A memory can now carry `external_bytes`: the size of a payload it only
  **points at**, in a column store, a bucket, or another index. It is client-supplied and never
  interpreted here — the service does not fetch it, verify it, or know its address.

  `consolidation.capacityExternalBytes` is the target that payload is held under, with
  `consolidation.capacityExternalBytesFloor` as its hysteresis floor, read exactly as
  `capacityBytes`/`capacityBytesFloor` are. The sum joins capacity pressure as a **third**
  utilisation beside the row count and the store's own bytes, and eviction gains a second target: one
  pass, deleting least-valuable-first until each axis that is over has been brought back, so a store
  under its byte target and over its external one still evicts. Two decisions are load-bearing. It is
  never folded into `used_bytes` — that figure bounds this store's own disk and is the exact
  complement of eviction's freed-bytes estimate, so counting a payload held elsewhere there would
  make eviction chase bytes that deleting a memory does not return. And eviction's **accumulator**
  changed while its **sort** did not: ordering by value per byte is a different product, one where
  forgetting means "worst value density first" rather than "least valuable first", and that should
  not arrive as a side effect of an accounting change.

  Reported by `PreviewConsolidation` (per candidate, plus the axis totals),
  `ExplainConsolidation`, `CycleReport.external_bytes_freed`, and four instruments —
  `hippocampus.external_bytes`, `hippocampus.capacity_external_bytes`,
  `hippocampus.retained_external_bytes` and `hippocampus.external_bytes.evicted`. New in the `hippo`
  CLI as `--external-bytes` and in the Python client as `Memory.external_bytes`; deliberately not on
  the MCP tool surface, which is about memories a model writes rather than payloads it manages.

  The axis costs nothing when it is off, which is the default: `external_bytes` is 0 on every memory
  written before the column existed, and the sum behind the utilisation is only measured when a
  target is configured. Upgrading is automatic and needs nothing: the column is added in place and the
  covering index is rebuilt to carry it — which is schema **migration 15**, so a store opened by this
  release records a version an earlier build does not understand and that build will refuse to open
  it, the ordinary no-downgrade rule. The rebuild is the one thing worth planning for on a large
  store, since it is a full index build on `memories` during startup. `external_bytes` is in that
  index although no per-row decision reads it: the axis is an aggregate, and on SQLite a row is stored
  inline, so summing the column off the base table would read every page holding a **body** — the cost
  the covering index exists to avoid — once per cycle, forever.

  Note what this release does **not** do: the store decides what should go and
  forgets its own record of it, but telling the far system to delete the payload is the
  `memory_forgotten` callback, which is a best-effort notification rather than a guaranteed
  instruction — so leave the far end's own expiry configured as the outer bound.

- **Deletion by predicate: `DeleteMemoriesByFilter` and `DeleteEventsByFilter`.** The deletion
  surface was `DeleteMemories` (by id), `DeleteEvent` (one event), `Purge` (everything, refused to a
  group-scoped caller) and `Clear` (exactly what a prior `Export`/`Transfer` captured) — there was no
  predicate anywhere. Removing one group's records therefore meant exporting it to an object store
  with `clear`, or transferring it to a second live instance with `clear`, or paging `GetMemories`
  and deleting by id while the store changed underneath, and then deleting the emptied events one at
  a time because nothing deleted events by predicate at all. Group scoping is the documented
  soft-partition story for a tenant, and "hard isolation is one instance per tenant" answers
  isolation rather than deletion; the deployments that took the soft partition still have to remove a
  partition eventually.

  Both take the selecting fields of the listing beside them (`GetMemories`/`GetEvents`) — not
  ordering, not pagination — and **the service builds one predicate for the pair**, so the listing is
  the dry run and its `total_count` is what the deletion removes. Both are `admin` tier and both are
  scoped, so a group-bound admin token drains its own partition and reaches no further. A request
  carrying **no filter is refused** rather than read as "everything": that operation is `Purge`.
  `max_deletions` bounds one call and the response's `complete` reports whether anything still
  matches. `DeleteMemoriesByFilter.delete_empty_events` also removes the events a deletion left with
  no memories at all; `DeleteEventsByFilter.delete_memories` decides whether an event's memories go
  with it or survive with no event, exactly as `DeleteEvent.memories` does.

  There is deliberately no `dry_run` flag — authorisation is per-RPC, so a flag on a destructive call
  could never be tiered apart from it, which is the reasoning that made `PreviewConsolidation` its
  own RPC rather than a flag on `Sleep`. The dry run is the listing, at `reader` tier. Reaching the
  storage layer, the deletion is the ordinary one: ids are resolved in batches and deleted through
  the existing by-id chokepoint, so links are pruned, the search index's delete is queued in the same
  transaction, and callbacks behave exactly as they do for `DeleteMemories`. New in the `hippo` CLI
  as `memory delete-by-filter`/`event delete-by-filter` (both requiring `--yes`) and in the Python
  client as `delete_memories_by_filter`/`delete_events_by_filter`; deliberately **not** on the MCP
  tool surface, which lets a model act on records it can name and never on a set it can only
  describe.

- **A published Python client: `pip install hippocampus-client`.** Every language other than Go
  generated its own client, and `docs/clients.md` opened by saying so and then spent a page on how
  to do it — the right document to have and the wrong thing to need. The product's thesis is agent
  memory and the agent ecosystem is written in Python, so that is the one worth publishing.

  It covers **every RPC the contract declares**, unlike the MCP bridge, whose surface is curated for
  a model rather than a program; a drift guard fails the build if the contract grows an RPC the
  client has no method for, in both directions. The memory and event surface returns dataclasses,
  and the operator surface — topology, the consolidation preview and explanation, the forgotten log,
  the callback queue, transfer — returns its protobuf message unchanged, on the reasoning that what
  an application touches daily is worth an ergonomic type and what an operator reads occasionally is
  better served by the message whose field comments are the documentation.

  Most of what the wrapper is for is the four encodings that catch every new client at least once:
  UnixNano `int64` timestamps become aware `datetime`s, a zero timestamp becomes `None` (so "never
  recalled" and "not yet ended" are absences rather than 1970), the tri-state `Bool` filters become
  `Optional[bool]`, and `"key=value"` metadata filters become a `dict`. The three behaviours that
  are the product rather than faults are pushed into the types: a rejected-for-insignificance write
  returns a falsey `Stored` rather than raising, a batch reports per record, and `recall_memories`
  is documented as the write it is.

  **The stubs are generated from `contract/hippocampus.proto` at build time and are not committed.**
  A committed copy would be a second copy of the contract, free to drift from it, which is the
  failure a published client package invites. The release workflow stamps the tag into the package
  version and publishes from that same tag, so `hippocampus-client==X.Y.Z` is by construction the
  client generated from `vX.Y.Z`'s contract.

  One thing found on the way, and corrected in `docs/clients.md`, which had it wrong: the
  protoc-gen-openapiv2 annotations are _not_ free of runtime consequence in every language.
  `protoc` writes an import of them into the generated Python module, and that package exists on no
  index — so a client generated by following that page's own recipe installed cleanly and raised
  `ModuleNotFoundError` on first import. Stripping the option before generating is the fix.

  See `docs/python.md`. Item 64, and item 100.4's sharpening of why it matters.

- **A LlamaIndex adapter: `pip install llama-index-memory-hippocampus`.** The client's other half.
  Being callable from Python is not the same as being an agent's memory, and the distance between
  the two is one framework adapter — `HippocampusMemoryBlock`, a long-term memory block that writes
  each turn to a store and retrieves from it by relevance.

  **Retrieval recalls what it returns**, and a recall here is a write: it resets the memory's decay
  clock and raises its effective significance. So a fact the agent keeps reaching for is reinforced
  by the act of being used, and one it never retrieves decays out. That is the whole retention
  policy — the adapter carries no eviction, no cap and no TTL of its own, because the store already
  has all three and they are now driven by what the agent actually did.

  LlamaIndex was chosen over the OpenAI Agents SDK's `Session` and over LangChain, and not on
  audience. **A conversation transcript has a structural invariant a forgetting store breaks**: the
  item list handed back to the model must be well-formed, a tool call needs its matching tool
  result, those are two memories with two significances, and a consolidation cycle will eventually
  take one of them. It is fixable by pinning a turn into one event and leaning on
  `minimumRetentionInDays` — but the fix is precisely a constraint on forgetting, so the adapter
  would have demonstrated the thesis by suppressing it. A long-term memory block has no such
  invariant: facts folded into a prompt by relevance are _supposed_ to thin out, and nothing is
  corrupted when a low-value one goes.

  Two decisions in it are specific to this store rather than to the framework. The role and session
  id go in **metadata, never the body** — a body is what the content index tokenises, so the
  framework's own `<message role='user'>` wrapper would put `message`, `role` and `user` into the
  index for every memory, three terms that match everything and rank nothing. And the search mode
  is **resolved once from `who_am_i()`**, richest first, because a mode with no backend is refused
  per call: a block configured for one would fail every retrieval for the life of the process while
  looking like a retrieval bug.

  The block holds a four-call protocol rather than the whole client, which is what keeps an agent's
  memory away from `Purge` and `Clear` — the same line the event-source bridges draw, and held at
  four by a test. See `docs/llamaindex.md`. Item 108.2.

- **`StoreMemories`: a validated batch write.** A producer holding a batch of unrelated memories had
  two options and both were wrong. Loop `StoreMemory` and spend a round trip, an interceptor chain,
  a rate-limit token and a transaction on every record — which is what the broker bridges and the
  OpenTelemetry logs exporter did, the latter on a batch `exporterhelper` had already assembled for
  it. Or use `ImportBatch` and give up the write path: it is a full-state upsert by id that
  deliberately carries no defaulting, no minimum-significance gate and no clock-skew guard, so
  re-sending a live id silently rolls its recall count back to whatever the sender last knew.

  `POST /v1/memories/batch` takes up to 500 memories and applies **exactly** the validation,
  defaulting, group stamping and minimum-significance gate `StoreMemory` applies — per memory, in
  its own transaction. That is the whole design: a partial success is the useful answer to a
  producer that cannot re-author a record it did not write, and one transaction over 500 records
  would hold a write lock across 500 significance resolutions. The response carries one result per
  memory, positionally, each with the gRPC code that memory would have earned on its own, so a
  caller can tell a permanent rejection from a retryable one without parsing a message. The call
  itself fails only for a batch-level fault: no memories, more than the cap, or a cancelled context.

  It is not `ImportBatch`: nothing is upserted, and a memory naming an id the store already holds
  fails `ALREADY_EXISTS` in its own result rather than replacing a live row. The 500 cap is the page
  size `Transfer` already sends `ImportBatch` in, so a producer that batches for one of the two
  batch writes has the right number for both. `writer` tier, group-scoped per memory, and reachable
  as `hippo memory store-batch --file`.

  One thing to know before pointing a high-volume producer at it: the rate limiter's unit is a
  request, so a 500-memory call spends one token, exactly as `ImportBatch` always has. What bounds
  how much such a producer keeps is `consolidation.capacityBytes` and the decay cycle.

- **The OpenTelemetry logs exporter records attributes, and writes in batches.** It mapped severity,
  body, timestamp and `service.name` and discarded everything else — so `trace_id`, `span_id`,
  `k8s.pod.name`, `http.status_code`, `error.type`, everything that makes a log record queryable,
  stopped at the boundary. Memory metadata and the metadata filters shipped two weeks after the
  exporter did and nothing revisited it.

  Four selections now feed a memory's metadata, each overriding the last on a shared key: fixed
  `metadata` labels, `trace_metadata` (**on by default**), the named `metadata_from` attributes, and
  everything under `metadata_prefix` with the prefix stripped. Attributes resolve record → scope →
  resource, most specific winning. `trace_metadata` is the one with no counterpart in the broker
  bridges and the reason to default it on: correlating a memory that survived the decay cycle back
  to the trace that produced it is why a log pipeline would choose this store, and `GetMemories`
  filters on metadata — an id not written cannot be recovered later.

  Keys are normalised to the service's charset, so semantic-convention names pass through as
  themselves. A label exceeding the service's metadata bounds is dropped and logged at debug rather
  than sent and refused, because the record is not at fault; a **fixed** label that could never fit
  is refused at startup instead.

  The exporter also stores one collector batch per `StoreMemories` call rather than one call per
  record, splitting at the service's cap. A transport failure is still handed back for retry; a
  per-memory failure is not, because some of the batch landed and a fresh memory mints a new id on
  every send — the exception being a call in which nothing landed and every failure was transient.
  Pointed at a service predating `StoreMemories`, it notices the `Unimplemented` once, says so, and
  falls back to the per-record path.

- **The broker bridges write a page in one call.** A Bluesky feed poll is about a hundred posts and
  each was its own RPC; the polled path and `HandleEvent`'s already-exists fallback now use
  `StoreMemories`, in chunks of a hundred, with the same `Unimplemented` fallback the exporter has.

  Nothing about how a page is judged changed, and that is the point: the batch RPC answers per
  memory, which is exactly the reading the bridges already applied a call at a time — a memory the
  store already holds is a success (re-reading a ranked feed hands back the same posts, and an
  upsert would roll back reinforcement), a memory naming an event the store no longer holds is
  skipped, and anything else fails the page. A batch write that reported one status for the whole
  page would have reintroduced the stall that tolerance exists to prevent: a polled source returns
  the same page every read, so a single unwritable memory aborting the page means every memory after
  it is never written, on every poll, forever.

  One behavioural note for anyone who has tuned it: `--call-timeout` bounds a **call**, and a call is
  now up to a hundred memories rather than one.

- **Content search on `postgres` and `mysql`.** `SearchMemories` now works without an OpenSearch
  cluster on every storage driver, not just `sqlite`. There is nothing to configure and nothing to
  run alongside: the index lives in the same database as the memories, is created at startup, and is
  populated from what is already stored — so an existing store gains a working search on the first
  restart after upgrading, with no backfill step.

  This closes a defect in a deployment recipe this repository ships. `deploy/k8s/overlays/postgres`
  and `deploy/compose/docker-compose.postgres.yaml` are what the documentation points a production
  reader at, and both produce an instance whose `SearchMemories` failed `FAILED_PRECONDITION` —
  precisely the fault the store's own index was added to fix in 0.36.0, moved one deployment model
  along. The 2026-08-05 decision that recorded OpenSearch as a reasonable prerequisite for a
  centralised deployment said to revisit it if such a deployment turned up that would not run
  OpenSearch. One had, in this repository.

  What each driver uses, and the one asymmetry worth knowing before choosing: `sqlite` keeps its
  FTS5 index unchanged, `postgres` keeps a `tsvector` table under a GIN index, and `mysql` keeps a
  `FULLTEXT` index — which, because a `FULLTEXT` index indexes a **column**, means the MySQL index
  holds a second, uncompressed copy of every indexed body. The other two hold only an inverted
  index — a privacy property more than a size one, since for short bodies a `tsvector` is about as
  large as the text it came from. On the server drivers the index sits outside
  `consolidation.capacityBytes`, like the forgotten log: it is derived data, and letting the record
  of what is searchable raise capacity pressure would evict live memories to make room for it. On
  `sqlite` it is inside the target, as it always has been — page accounting cannot exclude a table
  in the same file.

  Two MySQL server settings show through and have no counterpart on the other two: a token shorter
  than `innodb_ft_min_token_size` (3 by default) matches nothing, and InnoDB's stopword list drops
  about three dozen common English words.

  Deletion cannot drift on any driver, because no call site performs it: the SQLite index is kept in
  step by a trigger and the server indexes by a foreign key with `ON DELETE CASCADE`, so
  consolidation, eviction, `Purge` and the rest retire an index entry in the same transaction that
  removes the memory. Query text is still never passed through to the engine — it is split into bare
  alphanumeric tokens, each quoted as a literal and the tokens OR-ed, so all three of these query
  languages are disarmed the same way. Relevance is each engine's own measure, normalised so a
  higher score is always a better match; the order is comparable between drivers, the magnitudes are
  not. Only the first 512 KiB of a body is indexed, on every driver — one of them enforces such a
  limit natively, and applying it to all three keeps what is findable a property of the store rather
  than of the driver.

  `--backfill-search` without OpenSearch now rebuilds the index on any driver rather than refusing
  on two of them. `WhoAmI.search_modes` needed no change and already reports the truth.

  The server drivers' index is schema migration 14, so a `postgres` or `mysql` store opened by this
  release records a version an earlier build does not understand and that build will refuse to open
  it — the ordinary no-downgrade rule, stated here because the migration is the first one those
  drivers have gained since the version gate landed. Nothing is required to upgrade.

  Semantic search is unchanged and still needs OpenSearch on every driver. `pgvector` would give a
  Postgres deployment semantic search with no cluster beside it, but the vectors would have to live
  in the primary store, which reverses a deliberate capacity decision — a separate question, argued
  separately.

- **A filesystem object store for `Export`/`Import`.** The archive format is the only thing that
  preserves a store's full state — timestamps, recall history, groups, summary flags and links —
  and until now the only way to reach it was S3: `main.go` built an object store only when
  `s3.bucket` was set, so on every other deployment `Export` and `Import` failed
  `FAILED_PRECONDITION`. That put the offline backup, the air-gapped move, and the archive somebody
  keeps _because the store is designed to forget_ behind standing up a bucket or a MinIO, on a
  product whose default deployment is one static binary and a directory.

  Set **`archive.directory`** and archives are written there instead. The directory is created if
  it is missing, and `s3.keyPrefix` still applies — under a directory it is a subdirectory.
  `s3.bucket` and `archive.directory` are mutually exclusive: a configuration setting both is
  refused at startup (and by `--check-config`) rather than resolved by precedence, since the two
  disagree about where the archives went and that is found out when one is needed.

  Two things it does that S3 gave for free. A write is atomic — the archive streams into a
  temporary file and is renamed into place, so an export interrupted half way leaves nothing rather
  than a truncated file, which `Import` would otherwise accept as an archive and fail part way
  through having already upserted what it read. And an object key is validated rather than
  sanitised: `Import` takes its `object_key` straight from the request, so over a filesystem it is
  a caller-supplied path, and a key that is absolute or carries a `..` segment is **refused** — the
  usual anchor-and-clean would instead answer a request for `../../etc/passwd` with the contents of
  some other file. The deployment topology view reports which backend is in use and probes the
  directory like any other dependency.

- **`UpdateEvent`: an event's name, description, group and metadata are editable at last.** The
  storage layer has always carried a full partial update for events, written as `db.UpdateMemory`'s
  mirror and commented as one. The contract exposed **two** of its seven fields, through `EndEvent`
  and `UpdateEventSignificance`, and nothing reached the other five — so an event created with a
  typo'd name kept it until it was forgotten, metadata could be attached only at creation, and a
  group-scoped caller had no way to re-file an event at all while `UpdateMemory` let them re-file a
  memory.

  That this was an oversight rather than a boundary is written into the contract itself:
  `Event.clear_metadata` and `Event.clear_group` are documented as "on UpdateEvent, ...", and
  `Event.metadata` as having "replace-wholesale semantics on update" — three field comments naming a
  method that did not exist. The console had written an apology for it, populating four editable
  fields and then silently discarding them.

  `PATCH /v1/events/{id}` takes an `Event` and is shaped exactly like `UpdateMemory`, including that
  a `group` on an update **moves** the record and is checked against a scoped caller's scope rather
  than defaulted. `EndEvent` and `UpdateEventSignificance` stay: each carries semantics this does
  not (a defaulted end time, a placement-only change), and both are already in every client.

- **Four filters that bring the event listing level with the memory one.** `GetEvents` gains
  `ended`, `name_contains`, `linked_to` and `links`, and `GetEventById` gains `links`.

  `ended` is the tri-state `Bool` that answers "what is still running?", which no bound could:
  an open event stores `time_end` of `0`, and `0` is every numeric bound's "no bound" value. It is
  the pairing `recalled` and `time_recalled_max` already have on the memory side, arriving with the
  fix below for the same reason they did.

  `name_contains` closes a real retrieval hole. `EventFilter` carried time, significance, group and
  metadata and **no name predicate of any kind**, while both search backends index memories only —
  so in a store whose events are routinely named after their content (a thread named from its
  opening post, an hourly event named per service, a chapter), the only way to find "the thread
  about the election" was to page every event there was. It is a substring match, case-insensitive
  on all three drivers and unindexed exactly as `group` and `metadata` are; full-text over event
  names is a much larger piece of work and is not started here.

  `linked_to` and `links` mirror `GetMemories`' two link parameters, closing the last gap the link
  graph left: the event half had no listing-level read.

- **`GetSignificanceLevels`: the significance registry can be read.** `SignificancePlacement` lets a
  client rank an item _between_ two existing values, and `significance_extremum` lets it ask for the
  highest or lowest — but nothing listed the values in use, so a client using placement was choosing
  anchors it could not see. `GET /v1/significance/levels` returns them ascending, bounded and paged;
  two **adjacent** values in the list are the situation placement exists to open a gap for.

  It is `reader` tier and answered in full to a group-scoped caller. One registry ranks memories and
  events alike, so a value names no record and there is no per-group scale to partition — and the
  decay maths a scoped caller's memories are subject to runs on this one.

- **`WhoAmI` reports the service's version and whether callbacks are configured.** `--version`
  prints the build, the startup log names it and `/healthz` returns it, and every one of those is
  unreachable from a gRPC client: the CLI, the MCP bridge, the five broker bridges and the ingestor
  could learn it only from `GetTopology`'s `self` node, which is optional, tier-configurable and
  refused outright to a group-scoped caller. `version` on `WhoAmI` is none of those things.

  `callbacks_enabled` joins it for `tombstones_enabled`'s argument exactly: `GetCallbackQueue` on a
  deployment with no sink returns the same empty page as one whose queue is simply drained, and only
  the first is worth hiding a control for.

- **The clients caught up with the contract, in one sweep.** Batch A above added RPCs; this is the
  half that makes them reachable, together with two gaps the clients had of their own.

  **`hippo`** gains `event update` (the full partial update, with `--clear-group`/`--clear-metadata`)
  and `significance levels`, plus `--ended`, `--name-contains`, `--linked-to` and `--links` on
  `event list` and `--links` on `event get`. `hippo whoami` now prints the service's version and
  whether callbacks are configured. Shell completion picks all of it up from the same registry, so
  nothing had to be told twice.

  **The MCP bridge** gains nine tools and goes from thirteen to twenty-two. Four are the event
  surface it never had — `update_event`, `get_event`, and the three event-link tools, while all
  three memory-link tools were already registered — and `list_events` gains `ended`,
  `name_contains` and `linked_to`. The other four are introspection: `significance_levels`,
  `explain_consolidation`, `consolidation_status` and `whoami`.

  Those four are the point. An LLM host using this as its memory had **no way to ask the one
  question the store exists to answer**: is this memory about to go, and how long has it got?
  `explain_consolidation` answers it per memory, in time to `recall_memories` on what matters. The
  inclusion follows the curated surface's existing rule rather than bending it — all four are
  `reader` and none of them _enumerates_, which is exactly what still keeps `PreviewConsolidation`
  off the bridge. And `whoami` was already being missed: `search_memories` offers `semantic` and
  `hybrid`, and without `search_modes` a model could only discover that a deployment serves neither
  by having a search rejected — which is what that field exists to prevent.

  **The console** can now edit an event. Its form had four inputs it populated from the event and
  then silently discarded, under a hint reading "Only significance and end-time are updatable via
  the API"; `UpdateEvent` retires both. The Events filter gains **Name contains** and **State**, and
  the header shows the service version.

- **A callback-queue card on the console's Deployment tab.** `GetCallbackQueue` was in the contract,
  the CLI and the Grafana dashboard, and nowhere in the operator window that has a Now tab, a Decay
  tab and a Deployment tab. It shows depth, the age of the oldest delivery and the worst attempt
  count — read as one sentence, because depth alone says nothing: 400 waiting is a backlog or a busy
  cycle depending on how old the oldest one is, and a delivery on its ninth attempt is a receiver
  refusing rather than one that is slow.

  It sits on the Deployment tab because it describes a _dependency_ rather than the store's
  contents, and it is gated on `callbacks_enabled` as well as `admin` — with no sink configured the
  RPC answers with an empty page rather than refusing, which reads exactly like a queue that is
  keeping up. Discarding deliveries is deliberately not offered: an abandoned delivery is a
  notification nobody will ever receive, which is an act for a terminal.

- **A Prometheus scrape endpoint.** `observability.prometheus.enabled` serves the metrics for a
  Prometheus to **pull**, at `observability.prometheus.path` (`/metrics`) on
  `observability.prometheus.port` (**9464**), instead of only pushing them over OTLP/gRPC to a
  collector. The event-source bridges and the ingestor take the same option as `--prometheus`, and
  serve it on the `--health-port` they already listen on.

  This repository has shipped twenty-two Prometheus alert rules since 0.42.0 and nothing that could
  get the series to a Prometheus. The rule file is documented as something to load with
  `rule_files:` or lift into a `PrometheusRule`, both of which presuppose a Prometheus that already
  has the metrics; `deploy/k8s/README.md` told the reader to name "your collector's OTLP/gRPC
  address", which is an assumption about their cluster rather than a deployment. The overwhelmingly
  common cluster observability stack is kube-prometheus-stack, which scrapes — so a deployment on it
  had to run an OpenTelemetry collector purely as a protocol adapter in front of this service. The
  one place it worked was the demo, because `grafana/otel-lgtm` bundles a collector, which is why
  the gap was never felt here.

  It is a second metric **reader**, not a second instrumentation path: every instrument, attribute
  and alert expression is unchanged, and push and scrape are independent in both directions — a
  scrape-only deployment need not name a collector it does not have, and running both is a
  legitimate migration state. The exporter's name-translation strategy is pinned rather than left to
  its default, which follows a global setting in `prometheus/common` that would otherwise leave the
  dots in the instrument names on some builds; a test holds the served names against the shipped
  alert expressions.

  The endpoint gets a **listener of its own** and is never on the gateway. The gateway is the public
  surface and frequently what an ingress exposes, so a scrape endpoint there would hand every API
  caller the store's size, its capacity pressure and its RPC rates, while putting it behind a token
  instead would put it out of reach of most scrapers. It is unauthenticated by design and carries no
  ids, no group names and no memory content — but it is still operational, so
  `observability.prometheus.bindAddress` restricts the interface it binds. Keeping it off the
  gateway also settles the other requirement for free: a scrape never reaches
  `httpMetricsMiddleware`, so it cannot appear in `hippocampus.rpc.*`'s own request rate, the same
  exclusion the probes and console assets already had.

  Both Kubernetes overlays ship with it **on** and annotated for scraping, with a named `metrics`
  port on the Service for a prometheus-operator `ServiceMonitor` (given in `deploy/k8s/README.md`,
  not applied — it is a CRD half the target clusters do not have). Every compose stack publishes
  `9464` and takes `PROMETHEUS=true`.

- **Mutual TLS on both listeners.** `tls.clientCaFile` names a CA bundle to verify **client**
  certificates against, and `tls.requireClientCert` makes offering one mandatory. Both default off,
  so nothing changes for a deployment that does not ask.

  Every outbound connection this project makes has carried a `certFile`/`keyFile` pair for mutual
  TLS — `opensearch.tls`, `transfer.tls`, `callbacks.tls`, the MCP bridge, the `hippo` CLI and the
  event-source bridges, six implementations of one block — while `loadServerTLS` set only
  `Certificates` and `MinVersion`. No listener here ever requested a client certificate, so all six
  could only be used against somebody else's terminator, and the way that fails is silent: a client
  configured to present a certificate to a server that never asks completes the handshake and simply
  never sends it.

  It **composes with** the bearer-token authentication rather than replacing it. A certificate says
  which _process_ is connecting; a token says which client it is acting as and at what tier. Nothing
  is derived from the certificate — no client id, no role, no group scope — because authorisation
  having a second source that silently outranked the first would be worse than having none.

  Two refusals worth knowing. `tls.requireClientCert` without `tls.clientCaFile` is rejected at
  startup: with no bundle nominated Go verifies against the system roots, so "required" would admit
  any certificate any public CA has ever issued. And requiring a certificate covers the gateway's
  `/healthz` and `/readyz` too, since the handshake precedes the request — the service warns about
  it, and an orchestrator's probe needs a certificate or TLS terminated ahead of the listener.

- **Generation and embedding against any OpenAI-compatible endpoint.** `summarise.Summariser` and
  `embed.Embedder` were clean interfaces with one implementation each, and both were hardwired to
  Ollama's _native_ API — `POST {address}/api/generate` and `POST {address}/api/embed`, neither
  sending a credential, with no key for one in the configuration. The consequence was not "you must
  run Ollama": it was that **a deployment that already had an LLM could not use it**. OpenAI, Azure
  OpenAI, vLLM, llama.cpp's server, LiteLLM, OpenRouter, a Bedrock or Anthropic gateway, and any
  corporate gateway fronting a model with a key and an audit trail were all out — so an organisation
  with a sanctioned endpoint would have had to stand up a second, unsanctioned inference server
  beside the memory store to use `SummariseMemories` or semantic search at all.

  `llm.provider` and `llm.embedding.provider` now select the client: `ollama` (the default,
  unchanged) or `openai`, which speaks `POST {address}/chat/completions` and
  `POST {address}/embeddings` and covers every endpoint above — including Ollama, which serves `/v1`
  as well. `llm.apiKey`/`llm.embedding.apiKey` are sent as a bearer token, injectable as
  `HIPPOCAMPUS_LLM_APIKEY`/`HIPPOCAMPUS_LLM_EMBEDDING_APIKEY`, and are honoured by the `ollama`
  provider too rather than ignored there — an Ollama behind an authenticating proxy is a real
  deployment, and dropping the key would have presented as an unexplained 401.

  The two halves stay independent: nothing requires the summariser and the embedder to share a
  provider, an address or a key, and generating against a hosted model while embedding against a
  local Ollama is both reasonable and much cheaper.

  Four details worth knowing. `address` is taken **exactly as given** under the `openai` provider,
  so it normally ends in the version path (`https://api.openai.com/v1`) — that is the `base_url`
  convention every OpenAI SDK uses, and guessing a `/v1` here would break every gateway that mounts
  the API elsewhere; startup **refuses** an `openai` provider still on the Ollama default address,
  which would otherwise answer 404 to every call and read as a model server that is up and refusing.
  The prompt bounds (`maxMemories`, `promptCharLimit`) and the embedding truncation are shared by
  both clients rather than reimplemented per provider, because how much of the store leaves the
  process is a property of the service and not of whichever client is configured. A zero
  `temperature` is now **omitted** from the request rather than sent as `0`, which the models that
  reject an explicit temperature require. And `llm.embedding.dimensions` is additionally _sent_ as
  the API's optional `dimensions` parameter, which the Matryoshka-trained models honour by
  truncating — so an index created at 768 can be matched without changing model, while a model that
  ignores it returns its native width and the existing mismatch check catches it.

  A rejected API key is reported as an outright failure naming the setting rather than as a degraded
  dependency, in both the call path and the topology probe: it will fail every call, and it is the
  single most likely thing to be wrong about a hosted endpoint. The probe is otherwise more
  forgiving than the Ollama one — `/models` is the part of the OpenAI surface a compatible endpoint
  is free not to implement, so a 404 there reports healthy rather than claiming a fault nobody can
  fix.

- **A callback that speaks before a memory goes: `memories_at_risk`.** Every other thing the callback
  surface reports has already happened, and `memory_forgotten` is the one that matters: by the time a
  receiver reads it, the memory it might have wanted to summarise, archive elsewhere or recall is
  gone. The new kind is raised at the **top** of a sleep cycle, from the same scan
  `PreviewConsolidation` runs, and describes what the store is about to lose — the push counterpart to
  `GetSummarisationCandidates`, which has always done exactly this for events. It shares the cycle's
  id with the `memory_forgotten` and `sleep_completed` deliveries that follow, so a receiver can match
  what it was warned about against what actually went.

  `callbacks.atRiskMargin` is what makes it actionable rather than merely earlier, and is the part
  worth setting deliberately. At its default of `0` the warning covers exactly what the cycle now
  starting will take — which arrives while that cycle is taking it. A margin raises the bar the scan
  selects on, so the delivery also carries memories still _above_ the threshold and approaching it: at
  `0.25`, everything within a quarter of the bar, which is a cycle or more of notice. Both thresholds
  are reported and each item carries its computed `value`, so the two populations are told apart by
  comparison rather than by guessing.

  It is **off by default**, against the grain of the other three kinds, and for one reason: it is the
  only one that costs a scan rather than riding on work already being done. Turning it on runs a
  consolidation preview at the top of every cycle, which is roughly what the cycle itself pays.

  Two things it deliberately is not. It carries **no bodies**, whatever `includeBodies` says — the
  scan behind it never reads one, and does not need to, the memory still being there to fetch. And it
  is **not a veto**: acting on it by recalling a memory races the pass about to delete it, and that
  race is already safe in your favour, because the delete re-checks the recall clock inside its own
  transaction. That is a property worth knowing rather than a guarantee — a receiver that was down
  misses the window, and nothing waits for one. A cycle with nothing at risk sends nothing; the
  per-cycle heartbeat is still `sleep_completed`.

  Deliveries are grouped by `cause` and chunked within each group, so a receiver reassembles on
  `(cycle_id, cause)`. That grouping is not cosmetic: a memory going to `consolidation` has decayed
  past the bar and a recall will save it, while one going to `eviction` is still above the bar and is
  being taken to make room — which a recall may not save, and which an operator fixes by raising the
  capacity. Visible in `hippo callbacks queue --kind memories-at-risk` and in the console's callback
  card. Item 28, open since the beginning, and item 102.1.

- **The Obsidian plugin mirrors the vault's `[[wikilinks]]`.** It called memories, events and
  summarisation candidates and never `/v1/memories/{id}/links`, so a synced vault became a set of
  **isolated** memories. That is not a missing feature so much as a mismatch of premises: Obsidian's
  entire model is wikilinks, and Hippocampus raises the effective significance of **both** ends of a
  link — so a heavily-linked note is exactly the note the decay model should keep, and the plugin was
  throwing away the one signal the vault had that the store most wanted.

  A synced note's links now become links between the memories, on the manual command as well as the
  automatic sync, and **Sync folder now** does it in two passes — store every note, then resolve
  every note's links — because a vault always contains a link whose target is written later. Link
  resolution is Obsidian's own, so shortest-path names, relative paths and folder notes behave as
  they do in the editor, embeds count, and a wikilink inside a code fence does not. A link to a note
  that does not exist yet is ignored silently, that being ordinary Obsidian rather than an error.

  Deleting a wikilink **removes** the edge, or the graph would only ever grow and a note nothing
  links to any more would stay propped up by edges describing a vault that no longer exists. The one
  exception is an edge the note at the other end also declares: unlinking removes a pair in both
  directions, so removing it would silently delete somebody else's link until that note happened to
  be synced again.

  On by default, costing one read per synced note and a write only when the links have changed; the
  weight each edge carries is configurable and damped by the service, so raising it does far less
  than it looks like it should. Item 100.2.

### Changed

- **The `ollama.*` configuration block is now `llm.*`.** Key for key, with no change in meaning. It
  was renamed because it had stopped being about Ollama: `ollama.address` naming an Azure endpoint
  reads as a mistake, and an operator looking for how to point the service at their own gateway would
  not have thought to look under it.

  **The old names still work.** Each is copied onto its replacement at startup, so an existing
  `config.json` needs no edit; an explicit `llm.*` value always wins over the legacy one, so the two
  can be set together while a deployment migrates. Using any of them logs one `WARN` naming every
  legacy key still in force, and `hippocampus --check-config` reports them in a new `deprecated`
  field (which does **not** affect its exit status — the configuration is valid). They are
  deprecated and will be removed in a later release.

  The affected keys are `enabled`, `address`, `model`, `timeoutSeconds`, `maxMemories`,
  `promptCharLimit`, `systemPrompt`, `temperature`, `autoSummarise`, and the whole `embedding.*`
  sub-block — `ollama.embedding.model` becomes `llm.embedding.model`, and so on.

  The deployment topology view names the configured provider rather than always saying "Ollama", and
  carries it as a new `provider` attribute on both model-server nodes.

### Fixed

- **`time_end_max` matched every event that had not ended.** An open event stores `time_end` of `0`
  and the filter applied a plain `time_end <= ?`, so "events that ended before Friday" returned
  everything still running as well. The memory side treats the identical situation as a trap and
  guards it twice over — `time_recalled_max` excludes the never-recalled, and `recalled` is the
  tri-state that asks about them instead — and `GetEventsRequest.order_by` already warned about the
  same zero for the `time_end` ordering, so the value had been reasoned about for the sort and not
  for the filter.

  Both `time_end` bounds now ask only about events that have ended. **This changes what an existing
  filter returns**: a caller passing `time_end_max` today gets open events back and will stop. It is
  filed here rather than under **Breaking** because no caller can be relying on "ended before X"
  meaning "ended before X, or not at all" — but it is a behaviour change to a shipped field, and
  `ended: FALSE` is what now asks the question the old behaviour answered by accident.

- **`UpdateMemory`'s contract comment omitted `metadata`.** It listed the fields an update writes as
  "significance, body, event_id, group, time_stamp"; `metadata` is written too, and `clear_metadata`
  honoured, as both the CLI and the MCP bridge already expose.

- **`deploy/observability/README.md` had drifted by six alert rules.** It said sixteen rules in two
  groups, ten of them about the service; twenty-two ship, sixteen of them about the service. The six
  missing from its table arrived with the delete outbox and the callback queue
  (`HippocampusStoreGrowing`, `HippocampusSearchOutboxBacklog`, `HippocampusSearchOutboxAbandoning`,
  `HippocampusCallbackQueueBacklog`, `HippocampusCallbackDeliveriesFailing`,
  `HippocampusCallbacksAbandoning`) — so the page an operator reads before deploying the rules did
  not mention the alerts covering the two queues that can discard data.

  The rules themselves were never wrong; the guard that holds the two rule files to each other
  simply had no opinion about the README. It does now: a rule that ships without a row, a row naming
  a rule that does not ship, a severity that disagrees with the rule file, an order that no longer
  matches it, or a count stated in the prose that has gone stale all fail
  `cmd/hippocampus/alerts_test.go`.

## [0.42.0] - 2026-09-06

### Added

- **`--check-config`: validate a configuration without starting the service.** A validation rule is
  only ever written against the configurations its author can see, and the deployments it breaks are
  the ones they cannot — which is exactly how 0.41.0's deletion-threshold check shipped past every
  configuration in this repository and stopped two instances on the public demo from starting. The
  validation already existed; what was missing was any way to run it _without_ starting, so the
  answer arrived from a crash loop rather than from a deploy pipeline.

  `hippocampus --check-config -c config.json` runs the same checks a real start runs, reports what
  is wrong, and exits — touching no store, no network and no identity provider, so it is safe in a
  build step or beside a live instance. `--output json` renders the same report for a script;
  `status` is the field to branch on and the exit status carries the same verdict, so a pipeline
  need not parse anything to gate on it.

  Two decisions carry it. It checks the **resolved** configuration rather than the file, because
  viper's precedence is flag > env > file > default and a `config.json` that is sound alone can be
  invalid once a container's `HIPPOCAMPUS_*` overrides land — so the report names which file it read
  and whether it fell back to the built-in defaults, since a check that passes against defaults says
  nothing about the file you meant to hand it. And it reports **every** problem rather than the
  first: `validateConfig` is now a thin wrapper over a `configProblems() []error`, because a
  pre-flight tool surfacing one fault per run sends an operator around the restart loop once per
  mistake. Startup gains the same list for free — a configuration with three mistakes now names
  three.

  `TestShippedConfigsAreValid` is the other half, and the one that would have caught 0.41.0: it runs
  the same validation over every configuration file in the repository, found by glob so a new one is
  covered without anybody remembering to add it, with a companion test pinning that all three
  storage drivers stay represented among them.

- **A guided tour in the embedded web console.** The console has seven tabs of numbers and assumes
  the premise behind all of them. Everything that makes this store interesting is a _relationship_
  between those numbers — significance against age, recall resetting the decay clock, capacity
  pressure lifting the threshold, an event ending with its last memory — and not one of them is
  visible in any single panel, so a first-time visitor to the public demo had no path through it.

  A **Tour** control in the header walks through those relationships, pointing at the panel that
  shows each. It runs unprompted on a first visit (remembered in the browser, so it is offered once)
  and is reachable from the header for every visit after that — for a public demo the honest answer
  is both, since most visitors arrive exactly once.

  Three decisions carry it. It runs over the **live** console rather than a seeded read-only story:
  each stop opens the tab it is about, primes the table it points at if nothing has loaded one, and
  quotes this store's own figures — read at the moment the stop opens, and every stop still reads as
  a complete thought when a figure has not arrived, because the demo's store moves under the reader.
  It is **filtered by capability**: a replica has no cycle to describe, a `reader` no dry run, a
  store with the forgotten log off nothing in the feed, and pointing at a panel that is not there
  would teach that the console is broken. And it is **hand-rolled**, in `lib.js` plus a thin DOM
  layer in `app.js`, because the console carries no bundler and no dependencies and is served under
  a CSP with no `unsafe-inline` — a tour library injecting inline styles or handlers would be
  blocked silently.

  The step table, the capability filter and the placement arithmetic are pure and tested under
  `node --test`; two new drift guards pin that every stop points at an element, a tab and a loader
  that actually exist, alongside the existing ones for the action table.

- **A callbacks row on the bundled Grafana dashboard**: queue depth, delivery rate by kind and
  outcome with the abandon rate beside it, and delivery duration. The callback queue shipped in
  0.41.0 with instruments and three alert rules but nothing to look at between "fine" and "paging
  somebody" — and a persisted queue against somebody else's endpoint is exactly the thing whose
  normal shape you want to know before it goes wrong. The delivery-duration panel is the early one:
  a receiver in trouble slows down before the depth moves, and long before `callbacks.timeoutSeconds`
  turns it into a failure.

### Changed

- **The compatibility promise now covers the values a configuration key accepts, not only the key.**
  The **Compatibility** section above was written entirely about keys — removed, renamed, added —
  and said nothing about the accepted _range_ of a key that stayed exactly where it was. So
  0.41.0's deletion-threshold check was filed under **Fixed**, which is where tightening a
  validation rule looks like it belongs, and the release that could not start two demo instances
  announced itself as a fix. Refusing input a previous version accepted is a break; it is now
  written down as one, and the release pre-flight asks the question directly — _does this release
  reject any configuration the last one accepted?_ — because unlike the contract, which the
  `proto-breaking` job compares against the previous tag mechanically, there is no automatic answer
  for configuration and probably cannot be one.

### Fixed

- **The console's Decay tab rendered empty if you had listed memories first.** The tab loads its
  snapshot the first time it is opened, guarded on whether one had ever been seen — but the memory
  and search tables' per-row _value_ column writes that same variable, from a call that renders
  nothing on the Decay tab. So listing memories and then opening Decay found the guard already
  satisfied, and the tab stood at "Nothing loaded yet" with Refresh as the only way out of it. Two
  different questions had come to share one variable; the guard now asks whether the tab has been
  drawn, set where it is actually drawn. Found by the guided tour above, which walks that exact
  path.

- **`--schema-version --output json` emitted a log line above the document when no config file
  existed.** The mode points logging at stderr before rendering, precisely so a script can parse
  stdout — but the "no configuration file, starting on built-in defaults" warning is logged before
  the mode is dispatched at all, so on a host configured entirely through `HIPPOCAMPUS_*`
  environment variables the JSON was preceded by a Warn line and could not be parsed. The warning
  now sits below every CLI mode that renders to stdout, and above `--backfill-search`, which renders
  nothing and does want to say which store it is about to spend an hour on.

- **0.41.0 refused a working configuration: forgetting on the capacity target alone.** The new
  `consolidation.deletionThreshold` check rejected any non-positive value at startup, on the
  reasoning that switching value-based consolidation off has no legitimate use because
  `consolidation.enabled` and a non-positive `sleep.periodSeconds` are both already a way to disable
  forgetting. Neither is equivalent: both also disable **eviction**, and a store with a byte capacity
  and no deletion threshold is a coherent, deliberate mode — nothing is forgotten while it is under
  its target, and once it crosses, the lowest-value memories go until it is back at the floor. A
  memory is kept for as long as the store has room for it. Two instances on the public demo were
  configured exactly that way and could not start on 0.41.0.

  The threshold is now refused only when nothing else would forget anything either — which is the
  silent no-op the check exists to catch — and accepted when `consolidation.capacityBytes` gives
  eviction something to reclaim against. `capacityMemories` deliberately does not rescue it: a row
  capacity only scales the pressure that scales the threshold, scaling a non-positive threshold
  leaves it non-positive, and nothing evicts on the row count, so that pairing really does forget
  nothing. The error message now names the alternative rather than only the rule.

  `logForgettingMode` gains the third mode it was missing, so the startup line says `forgetting mode:
capacity target only` rather than describing a decay curve that is not running, and the
  configuration wizard mirrors the same relaxation — a warning where it used to be an error.
  `docs/consolidation.md`'s **Forgetting modes** section and `docs/operations.md`'s sizing half both
  cover three modes now instead of two, including what the mode gives up: `days_until_forgotten` is
  `-1` for every memory, correctly, and `hippocampus_memories_consolidated_total` stays at zero, so
  an alert comparing arrivals against removals has to look at eviction.

## [0.41.0] - 2026-09-05

### Added

- **Outbound callbacks, backed by a persisted queue.** Everything the service offered about
  forgetting was pull — `PreviewConsolidation`, `ExplainConsolidation`, `GetConsolidationStatus`,
  `GetForgottenMemories` all require a client to be asking. With `callbacks.enabled` and a
  `callbacks.url` the service now POSTs JSON to that endpoint when it forgets memories or events and
  when a sleep cycle finishes, so a system downstream of the store learns about a deletion instead of
  discovering it by asking for a record and finding nothing. Off by default.

  A delivery is recorded in the **same database transaction as the deletion that produced it** and
  sent by a background worker, so there is no boundary at which a notification can be dropped: a
  receiver that is down is a backlog rather than a silent loss, and a crash between the deletion and
  the delivery replays on restart. That matters more here than for the search-index outbox it is
  modelled on, because a callback about a deletion cannot be reconstructed afterwards — once the
  memory is gone, nothing re-derives the notification. Delivery is at-least-once; receivers should be
  idempotent, and the `cycle_id` and chunk numbering are what let one recognise a repeat.

  A delivery is a **batch**: one consolidation chunk that removed five hundred memories is one
  request, not five hundred, and a sleep-cycle completion's id list is chunked at
  `callbacks.maxIdsPerDelivery`. Only the two decay paths speak by default —
  `callbacks.allDeletions` widens the feed to client deletes, clears, cascades, summary replacements
  and purges, each tagged with its cause. `callbacks.includeBodies` adds memory bodies, capped by
  `callbacks.maxBodyBytes`; a body over the cap is **omitted and flagged**, never truncated.
  `callbacks.token` and `callbacks.signingSecret` authenticate deliveries (bearer token, and an
  HMAC-SHA256 signature over the timestamp and body); `callbacks.tls` accepts the same trust options
  as `opensearch.tls`, and redirects are never followed.

  A failed delivery is deferred on a jittered exponential backoff rather than dropped, and nothing is
  abandoned on an attempt count — only the queue's own `maxRows`/`maxAgeHours` bounds remove an
  undelivered delivery, which is logged at Warn and counted. The queue is excluded from the capacity
  target, since it grows precisely when a receiver is down and can carry bodies; counting it would
  evict live memories to make room for the news that memories were evicted.

  New RPCs `GetCallbackQueue` (`GET /v1/callbacks/queue`) and `DeleteCallbackQueue`
  (`POST /v1/callbacks/queue/delete`), both `admin`, both refused to a group-scoped caller — a
  delivery batches memories across groups, so there is nothing to scope it by. `hippo callbacks
queue` and `hippo callbacks clear` are the CLI half. Four metrics
  (`hippocampus.callbacks.queue_depth`/`.delivered`/`.abandoned`/`.delivery.duration`), three shipped
  alert rules, a config-wizard card, and a `Callback receiver` node in `GetTopology` — never probed,
  since it is a third party's endpoint and the delivery metrics answer better. See
  [Outbound callbacks](docs/configuration.md#outbound-callbacks).

### Fixed

- **The built-in defaults forgot nothing at all.** Running with no `config.json` on the default path
  is a supported mode, and `validateConfig` refuses the four keys that are fatal at zero — but
  `consolidation.deletionThreshold` and `sleep.periodSeconds` were neither defaulted nor refused, so
  both read as 0. A zero threshold makes the consolidation comparison `value < 0`, which no positive
  value satisfies, so consolidation was a complete no-op; a zero period disabled the timed cycle that
  would have run it. `go run ./cmd/hippocampus` on a fresh clone therefore produced a memory service
  that started, validated, served, and never forgot, announcing it only in a passing Info line. Both
  are now defaulted to the values the repo's own `config.json` carries (10 and 3600), as is
  `consolidation.enabled`, whose `SetDefault` lived in `run()` rather than beside the other startup
  defaults and so could not be asserted with them.

  A configured `consolidation.deletionThreshold` of 0 or less is now **refused at startup** rather
  than accepted, on the same reasoning as the existing method-3 aggressiveness check: it silently
  disables value-based consolidation, and there is no "disable forgetting" idiom it takes away, since
  `consolidation.enabled` and a non-positive `sleep.periodSeconds` are both already that. An unset key
  still falls back to the default, so the key stays optional.

### Changed

- **Decay-only is a first-class forgetting mode.** A store with no capacity target on either axis is
  a deliberate configuration, not a capacity target somebody forgot to set: forgetting runs on the
  value threshold alone, so a memory's lifetime stays a function of its own significance rather than
  of the aggregate write rate, and `days_until_forgotten` is a prediction rather than an estimate.
  `docs/consolidation.md` gains a **Forgetting modes** section naming the open-loop/closed-loop trade,
  the sizing formula that lets a decay-only deployment be provisioned in advance, and the two things
  the mode does not bound (an actively recalled working set, and very durable memories);
  `docs/operations.md` gains the operational half. The service now **logs which mode it resolved** at
  startup, so the choice is a declaration rather than an absence.

  Two supporting changes. `hippocampus.used_bytes` is published in **both** modes — it was recorded
  only inside the eviction gate, which meant the one number an operator of an unbounded store needs
  was precisely the one never emitted, since a capacity-bounded store's size is pinned and pressure is
  the interesting series while a decay-only store's size is the output of the loop. The measurement is
  best-effort without a capacity target (where it feeds only the gauge) and still fails the cycle with
  one (where it _is_ the eviction decision). And a new `HippocampusStoreGrowing` alert ships in both
  rule files, comparing arrival against removal rather than level, because every capacity rule is
  inert in this mode and `capacity_pressure` is flat at exactly 1.0.

  Also written down, because a row capacity reads like a cap and is not one: `capacityMemories`
  scales the pressure that scales the threshold and **nothing evicts on it** — eviction is gated on
  `capacityBytes` alone. Every shipped configuration sets a row capacity and leaves the byte capacity
  at 0, so this is the mode most deployments are actually in.

- The schema is at **version 13**: the callback queue adds one table (`callback_queue`), migrated in
  place on startup like every addition before it.
- **The capacity target's boundaries are written down.** `consolidation.capacityBytes` counts the
  memories, the events and the link graph and nothing else — every feature that keeps its own table
  (the forgotten log, the search delete outbox, the callback queue, the peer registry) is
  deliberately excluded from it, because each grows precisely when something is wrong and counting
  it would evict live memories to make room for the record of memories being evicted. That was true
  in the code and stated feature-by-feature at best, so a disk sized from `capacityBytes` alone was
  undersized by whatever those tables' own caps allow — two of which default to a million rows.
  `docs/operations.md` now has one section listing them with their bounds, the outbox section in
  `docs/configuration.md` says what the callback queue's already did, and the configuration wizard
  raises the same note against the capacity fields naming whichever of them the current selections
  have enabled. The same section records the case that runs the other way: on SQLite the
  content-search index lives in the database file and _is_ counted, so search costs capacity there
  and nothing on the server drivers.

## [0.40.1] - 2026-09-03

### Added

- **`scripts/cleanup.sh`** — reclaims the disk a build, test, demo or soak run leaves behind. By
  default it removes only what costs nothing to recreate (the gitignored `demo/` output, stray
  module binaries, coverage profiles, dangling image layers, orphaned anonymous container volumes)
  and then trims the podman VM disk; `--images`/`--build-cache`/`--trunk` clear caches that cost a
  re-download, so they are opt-in, and `--dry-run` lists everything first. The trim is the reason
  this is a script: on macOS the podman machine's disk is a sparse file, so a prune frees space
  inside the guest and returns none of it to the host until `fstrim` runs inside the VM. It refuses
  to touch `~/.hippocampus` and the Go module cache, and selects volumes by `dangling=true` plus an
  anonymous name so the test databases and named compose state are never candidates.

### Fixed

- **The OTEL collector image builds again.** 0.40.0's dependency bump moved the collector manifest
  and the exporter module to OpenTelemetry Collector 0.160.0 but left the collector `Dockerfile`
  installing OCB 0.157.0, which its own comment requires to track `otelcol_version`. A builder
  generates a distribution against the API of its own release, so the skewed pair failed to compile
  (`go.opentelemetry.io/collector/confmap/xconfmap`) and the multi-arch image build failed.

## [0.40.0] - 2026-09-03

### Security

- **`google.golang.org/grpc` 1.82.1 → 1.83.2, closing an unauthenticated remote OOM against the gRPC
  listener** ([GHSA-vp52-pcj8-j9qc](https://github.com/grpc/grpc-go/security/advisories/GHSA-vp52-pcj8-j9qc),
  CVE-2026-84304, high). A caller could open a stream and fragment its payload into millions of tiny
  HTTP/2 DATA frames. Each fragment carries its own tracking and queue-allocation overhead, so a
  payload sitting well inside the configured connection and stream flow-control windows could still
  inflate the heap until the process panicked or was killed; multiplexing streams multiplies it.

  Three things about the exposure are worth stating plainly, because none of them are obvious from
  the advisory title. It is **pre-authentication**: the frames are consumed by the transport before
  any interceptor runs, so `auth.method`, the authoriser and the group scope are all downstream of
  it, and an instance requiring a signed token was exactly as reachable as one that did not. It is
  the **gRPC listener** specifically (`bindAddress`, 50051 by default) and not the `/v1` gateway,
  which is served by `net/http`. And the gRPC hardening keys do not cover it — `maxRecvMsgBytes`
  bounds an assembled message rather than the frames it arrives in, and `maxConcurrentStreams` only
  reduces the multiplier. The fix is entirely in the dependency, so running this build is the whole
  of the action; no configuration changes.

  **The version to look for is 1.83.1, not 1.83.0.** grpc-go lists the change that actually closes
  this under _Performance_ in its own notes ("restrict memory overhead of buffering small data
  frames"), while the _Security_ heading of the same pair of releases carries the `xds/rbac` fixes —
  so checking for "the release with the security section" finds 1.83.0, which is still affected. The
  mitigation is receive-buffer compaction, on by default, with
  `GRPC_GO_EXPERIMENTAL_ENABLE_RECEIVE_BUFFER_COMPACTION=false` as an upstream escape hatch that
  should not be needed here.

  Updated in **every** module — the service and all five under `integrations/`. Only the service
  ships a listener, so the rest is consistency rather than exposure. Dependabot reached five of the
  six; `integrations/cli` was left on 1.82.1 and, because it `replace`s the root module, its recorded
  requirements then disagreed with the root's and `go build` refused the module outright. That was
  the `cli` CI job's failure, and it is the shape to watch for: this repository has **no
  `.github/dependabot.yml`**, so which modules get a PR is whatever GitHub infers rather than
  anything declared. The other advisories fixed in the same releases are all `xds/rbac`, which
  nothing here reaches: there is no xDS anywhere in the module graph.

### Added

- **A Dependabot configuration, covering all six Go modules as one coupled set.** There was none, and
  the absence was not neutral: security updates run from the repository's settings and need no
  config, while **version updates require the file** and so had never run at all. Which modules the
  security updates reached was therefore inferred from the dependency graph rather than declared —
  and the inference missed `integrations/cli`, which is what turned that CI job red while every
  other job stayed green.

  The shape follows from the `replace` directives. Each integration module replaces the root, so a
  module left behind does not merely lag — its recorded requirements disagree with the root's and
  `go build` refuses it outright. The six are one dependency set that has to move together, so the
  `gomod` entry lists all six under `directories` with `group-by: dependency-name`, which offers a
  shared dependency as **one pull request spanning every module** rather than one per module.

  Two limits are worth stating rather than discovering. `group-by` applies to **version** updates
  only — a security update is still opened per directory, which is exactly the case that broke the
  build, so a batch of those wants merging together. And a config file can itself go stale, so
  `TestDependabotCoversEveryGoModule` compares it against the modules actually on disk: a seventh
  module added without a line in that file fails the build instead of being quietly skipped.
  `npm` (the Obsidian plugin), `github-actions` and `docker` (the base images every published image
  is built on) are covered too; `cmd/hippocampus/webuitest` is deliberately not, having no
  dependencies to update.

### Changed

- **Go 1.27 across every build.** All six modules move their `go` directive to 1.27.0 and all four
  Dockerfiles move to `golang:1.27-alpine`. The workflows need no change: every `setup-go` step
  already reads `go-version-file`, so CI follows the module it builds.

  The directives had already drifted apart — `eventsource`, `ingestor` and `hippocampusexporter`
  were pulled to 1.26.0 by their own dependencies while the other three sat at 1.25.9, and the
  Dockerfiles were still on `golang:1.25-alpine`, one line below what three of the modules required.
  That combination builds only because `GOTOOLCHAIN` is unpinned and the image quietly downloads a
  newer toolchain mid-build. Moving all six together is the state the `replace` directives want
  anyway: a main module's `go` directive must be at least its dependencies', so the five modules
  that replace the root can never sit below it.

  **This forces golangci-lint to v2.** v1 cannot lint Go 1.27 at all — it fails with `export data
version 4 is greater than maximum supported version 2`, and rebuilding it under the new toolchain
  does not help, because the limit is in the `x/tools` it vendors. v2's defaults then flagged six
  pre-existing `defer x.Close()` calls in tests, now written as
  `defer func() { _ = x.Close() }()` — the idiom the rest of the repository already uses. Nothing
  outside test files changed. Note the linter is a local tool: it runs from `hooks/pre-commit` and
  no CI job invokes it, so this is a requirement on a contributor's machine rather than on the build.

- **Every module's dependencies updated to current.** The Go modules, the OpenTelemetry Collector
  manifest and the Obsidian plugin were all moved to the latest release of everything they depend
  on. Three of those upgrades needed code changes rather than a version bump, and the first two
  arrived with nothing in the version number or the import path to announce themselves — `go get -u`
  took both and reported success:

  - **`opensearch-go/v4` 4.6.0 → 4.7.3 double-encoded every document id.** 4.7.0 moved request-path
    construction behind a builder that percent-encodes each segment, which is exactly what
    `documentId` had been doing by hand — so ids were escaped twice, and the cluster stored each
    document under an id nothing would ever address again. Every memory the Bluesky bridge writes is
    an `at://` URI, so this was the common case, and its failure is silent: writes land somewhere
    unreachable and deletes match nothing. The helper is gone and the raw id is passed through, which
    is now correct precisely because the SDK escapes. The same release also made
    `MappingGetResp.Indices` an accessor and renamed `IndicesRefreshReq.Indices` to `Index`; those
    two at least fail to compile.
  - **`gobwas/glob` 0.2.3 → 1.0.0 removed `glob.Glob`** while keeping the same import path, so the
    upgrade broke `collector/confmap`, which still requires 0.2.3. It is pinned back in
    `integrations/otel/hippocampusexporter`.
  - **TypeScript 7 removed `baseUrl` and `moduleResolution: node`.** The Obsidian plugin's
    `tsconfig.json` moves to `moduleResolution: bundler` — the algorithm matching how esbuild
    actually bundles it — and declares `types: ["node"]`, which that resolution mode no longer
    infers. `baseUrl` was doing nothing: every import in the plugin is relative or a bare package.

  Also: the OpenTelemetry Collector manifest moves 0.157.0 → 0.160.0, which the exporter's own
  dependencies had already outgrown, and the OCB binary it names is now a separate module
  (`go install go.opentelemetry.io/collector/cmd/builder@latest`). The service's `go` directive rises
  to 1.25.9 because `opensearch-go` requires it.

## [0.39.0] - 2026-09-02

### Fixed

- **Spreading activation was silently inert on PostgreSQL.** `linkRecallPropagation` advances the
  decay clock of a recalled memory's linked neighbours by a fraction of their age. The UPDATE
  applying that fraction bound it as a float into an expression whose other operand was a `BIGINT`
  column, so PostgreSQL inferred the parameter as `bigint` too and `0.5` arrived as `0` — every
  neighbour's clock advanced by nothing, on every recall, with no error anywhere. SQLite and MySQL
  were unaffected. The fraction is now applied as an integer ratio, which no dialect can misinfer
  and which needed no `CAST` (whose target type was itself dialect-specific). A deployment on
  PostgreSQL that configured `consolidation.linkRecallPropagation` was getting none of it, and its
  linked memories decayed as though unlinked.

### Added

- **The database schema is versioned, and downgrades are refused.** A `schema_migrations` table
  records which of an ordered, named migration list a store has run, and the version it is at is
  logged on every startup. Opening a store recorded at a version the running build does not declare
  now fails with a message naming both versions and what to do about it, instead of serving a schema
  the binary only partly understands — the failure mode "downgrading is not supported" described but
  nothing prevented. The read-only tool opens (`--backfill-search`) apply the same gate, tolerating
  the ledger being absent so a store written before this release is still backfillable.

  The ledger records rather than decides: every migration still runs on every startup, because each
  detects its own completion. That is what makes it safe to add to an existing store — there is no
  baselining step to get wrong — and it keeps the property that a store whose index was dropped, or
  restored from a partial backup, is repaired on the next open. Verified against every released
  schema fixture back to v0.4.0 on all three dialects.

- **`hippocampus --schema-version`** prints a store's recorded schema version, its applied migrations
  with timestamps, and what an upgrade would do — without starting the server, taking a lock, or
  running any DDL, so it is safe beside a live instance. It exits non-zero when the store is newer
  than the binary reading it.

  It answers the question the startup log line cannot: after a refused downgrade the store will not
  start, so a log line is no use. It deliberately bypasses the version gate rather than going through
  the read-only opens, which would refuse the very store you are asking about.

  `--output json` renders the same report for a script, with a `status` field
  (`current`/`behind`/`ahead`) as the thing to branch on. The report goes to stdout and every
  diagnostic to stderr, so the JSON stays parseable on the `ahead` path — where the process both
  renders the report and then fails.

### Changed

- **One schema, one initialiser.** The three per-driver schema initialisers are now a single ordered
  migration list; what separated them was three dialect _capabilities_, not three procedures. The
  schema-fixture drift guard reads that declared list rather than parsing the Go AST of whatever the
  init functions happened to call, which removed about 150 lines of test machinery.

- **The schema-upgrade fixtures had no entry for the current schema band.** `search_outbox` shipped
  in 0.38.0 and the newest fixture was v0.37.0, so the schema every deployment in the field is
  actually running had never been migrated by a test. A v0.38.3 fixture is now generated for all
  three drivers — and it is the most valuable one in the set, being the last release that recorded no
  schema version and therefore the upgrade every real store is about to perform. Two stale
  declarations were corrected alongside it (v0.37.0 was annotated as a no-op control, and the
  outbox's fixture was attributed to v0.34.0). `RELEASE.md` now requires regenerating fixtures when a
  release changes the schema: the existing guard cannot catch the newest band having none, which is
  exactly what had happened.

- **All SQL-dialect knowledge now lives in one file.** `db/dialect.go` holds a table with one row per
  dialect — column types, expression fragments, capability flags — plus the few helpers whose
  difference is structural rather than lexical (the upsert form, index management, the registry
  lock). The 39 driver branches previously spread across 13 files are down to 5 across 2, and a
  build-time guard refuses a new one anywhere else. Most visibly, the `events` and `memories` schema
  is now written **once** instead of three times: the copies differed only in column types, so
  keeping them apart risked a column being added to one dialect and forgotten in another — a store
  that opens, serves, and is missing a field on exactly one backend. No stored schema changes; a
  database written by any earlier version opens unchanged.

- **The `db` test suite now runs against all three dialects.** `HIPPOCAMPUS_TEST_DIALECT` re-points
  the suite's shared store constructor at PostgreSQL or MySQL, so the same ~190 tests execute on
  each; CI runs all three. Previously only 18 of the 74 `db.Store` methods had any server-driver
  coverage at all, which left dialect-specific code in the link graph, the forgotten log, the search
  outbox, `PreviewConsolidation` and `RetainedStats` with no test that had ever run the branch — the
  first run of the new suite found the PostgreSQL bug above. `addColumnIfMissing` now probes
  correctly on all three dialects rather than being a syntax error on the one it is not called from.

## [0.38.3] - 2026-08-29

### Fixed

- **Every duration histogram was unreadable, and one shipped alert fired permanently because of
  it.** `hippocampus.rpc.duration`, `hippocampus.sleep.duration`,
  `hippocampus.client.rpc.duration`, `hippocampus.bridge.message.duration` and
  `hippocampus.ingestor.pass.duration` all record **seconds**, but none declared bucket boundaries,
  so all five took the OpenTelemetry SDK's defaults — which are shaped for **milliseconds**
  (`0, 5, 10, 25 … 10000`). The first finite bucket is therefore five seconds, coarser than every
  observation a healthy deployment makes, so every observation landed in one bucket and
  `histogram_quantile` interpolated across it. Measured on a live instance: the shipped
  `HippocampusRequestLatencyHigh` expression returned a p95 of **4.75 s** against a real mean RPC
  duration of **0.44 ms**. That alert fires above 1 s, so it fired on any instance serving traffic,
  and no amount of the service getting faster could ever have cleared it. All five instruments now
  carry explicit boundaries from `observability/histogram.go` — a latency ladder starting below a
  millisecond, and a longer one for periodic passes (a sleep cycle, an ingestor pass) that reaches
  ten minutes. The same expression now returns **0.56 ms**. Found by the new soak harness, which
  needed a trustworthy sleep-cycle quantile of its own.

### Added

- **The soak report judges the sleep cycle on its mean, not a p95.** A 95th percentile is the wrong
  statistic for this sample size rather than merely a noisy one: at the demo's 120-second sleep
  period a window holds about eight cycles, so the quantile lands on a histogram bucket boundary by
  construction. On the 2026-08-31 MySQL soak that produced a perfectly bimodal series — twelve
  readings at 0.24s, twenty at 0.38–0.46s, nothing between — and a "+56% slower" warning on a cycle
  whose true mean moved from 0.1494s to 0.1578s, or +5.6%, across three hours. The p95 is still
  sampled and stored, but no longer judged.
- **The soak report no longer reaches verdicts its evidence cannot support.** Three checks were
  producing warnings on a demonstrably healthy four-hour run: a memory series that rose and then sat
  perfectly flat for two hours was reported as "growing" (window medians can see that something
  moved, not that the moving stopped); the sleep-cycle trend spanned the store filling from empty,
  reporting expected scaling as a 150.9% regression; and eviction was judged on the final sample, so
  a store correctly sawtoothing around its target failed whenever a run ended mid-tooth. Now a
  plateau is recognised as one, the cycle is measured only at constant load (the same run reads
  +31.4%), and eviction is judged on whether it ever brings the store back under. Each relaxation is
  paired with a test proving the real fault is still caught — `demo/soak/report_test.py`.
- **Soak runs tighten `consolidation.capacityBytes` to 70 MB** (`--capacity-bytes` to override). The
  demo's own 200 MB target sits above the load generator's equilibrium, so `evict()` never ran at
  all across a full four-hour soak.
- **`demo/soak.sh --observe-only`** — samples a deployment that is already running rather than
  launching one, with the same checks and the same report. Includes `--selector` for scoping to one
  instance, and an attribution check that detects metrics collapsing across several instances (a
  monotonic counter running backwards) and reports the affected checks as UNKNOWN rather than
  producing a confident, false verdict.
- **`demo/soak.sh` — a bounded, self-sampling soak harness** (TODO item 20). Runs the service under
  the demo generator for a set number of hours, samples goroutines, RSS, sleep-cycle duration,
  capacity convergence, the search outbox and the index/store document ratio on a timer, and writes
  a report that reaches a verdict per check rather than leaving one to be inferred from a clean log.
  It drives `demo/run.sh` rather than duplicating its orchestration, defaults to a **SQLite +
  OpenSearch** profile (the only one that exercises item 84's delete outbox and reverse sweep, which
  had no soak path at all before this), stops itself on a disk-space floor, and reports `UNKNOWN`
  rather than passing when a check's data is missing. Output lands in `demo/soak-runs/` (gitignored).
- **`hippocampus.runtime.goroutines`, `hippocampus.runtime.heap_bytes` and
  `hippocampus.runtime.memory_bytes`** — process-health gauges published by every binary that calls
  `observability.Init` (the service, the ingestor, the broker bridges). Attribute-free, so trivially
  low-cardinality. The goroutine count is the one that earns its place: a leak is what a long-running
  deployment actually suffers and the only failure a clean log will never show, and until now there
  was no way to read it from outside the process.

## [0.38.2] - 2026-08-28

### Fixed

- **The stale-document sweep no longer silently skips most of the index.** The enumeration sorts on
  the mapped `timestamp`, and OpenSearch early-terminates a numeric sort using the field's point
  index — so the page it returns is _not_ the true lowest-N but a non-exhaustive sample spread across
  the range. The cursor then advances past the highest timestamp it saw, and everything the
  optimisation skipped is skipped by the sweep too, reported as a completed pass. Measured on the
  production index: one page of 500 spanned a window holding 1,472,040 documents, and a full walk
  terminated after 208,023 of 2,086,990.

  The query now sets `track_total_hits`, the documented control for that optimisation. It costs
  ~66ms per page against ~8ms, which is free in practice since the sweep already paces itself at
  200ms between pages.

  Worth knowing: the fault is **not deterministic**. It depends on segment structure as well as index
  size — the same build swept one 2M-document index exhaustively while skipping 90% of its twin — so
  a sweep appearing to work is not evidence that it does. It did not reproduce at 60,000 documents
  nor at 400,000, so there is no test for it at any size a suite can afford; the query shape is
  pinned instead, and the reasoning recorded with it.

## [0.38.1] - 2026-08-28

### Fixed

- **Search-index deletes are one bulk request per batch, not one round trip per document.** Found in
  production immediately after v0.38.0 shipped, which is the only place it could be found — it needs
  a backlog to appear at all. `applyTimeout` bounds _one_ operation (10s by default), but the delete
  path looped N sequential round trips inside that single budget. That held up while every caller
  passed a handful of ids at a time; v0.38.0's outbox drain and stale sweep both pass a page (500) at
  a time, and against 4.4M stale documents a batch could not finish before its own deadline. Each
  sweep pass then aborted and **restarted from the top of the index**, so the sweep thrashed rather
  than converged — around 200 deletes/sec, and hours of load, for work that should take one pass.

  A batch is now a single `_bulk` request, and the synchronous path scales its deadline by chunk
  count rather than assuming one round trip. A per-item 404 is still success — the document was never
  indexed, so there is nothing to remove — but that now has to be read per _item_, since `_bulk`
  answers 200 for the request as a whole.

  One trap worth recording: the bulk body must carry the **raw** id, never `documentId()`'s
  URL-escaped form. That helper exists only to survive path interpolation, and the server
  percent-decodes a path before storing `_id`, so an escaped id in a JSON body addresses a document
  that was never stored under that name. Every memory the Bluesky bridge writes is an `at://` URI, so
  this is the common case rather than a corner.

## [0.38.0] - 2026-08-27

### Fixed

- **The OpenSearch index no longer accumulates stale documents under sustained write load.**
  Propagation to OpenSearch is an asynchronous bounded queue that drops on overflow, and the two
  kinds of dropped operation were not equivalent: a dropped _index_ self-heals, because the memory
  still exists for the reconciliation sweep to re-index, while a dropped _delete_ was permanent —
  nothing afterwards knew the document should have gone. Under any write rate above the queue's
  drain rate the index therefore diverged from the store forever. Measured on a live deployment:
  **4.38 million documents against 211,657 rows**, 20.7x, growing about 700 MB/day, with 25,056
  operations dropped in thirty minutes. Enlarging `opensearch.queueSize` never fixed this — every
  queue is finite, and the loss happens at the enqueue boundary, so the dropped operation never
  entered the queue at all.

  Deletions are now recorded in a **`search_outbox` table, in the same transaction as the memory
  delete itself**, and drained by a worker on the consolidating instance: claim, apply
  synchronously, then confirm, so a crash between the two replays the deletion rather than losing
  it. There is no boundary at which it can be dropped. This is parity rather than a new guarantee —
  the built-in SQLite FTS backend has always had it, its deletes being an `AFTER DELETE` trigger
  inside the same transaction. Backpressure now shows up as table growth, bounded by
  `opensearch.outbox.maxRows` / `opensearch.outbox.maxAgeHours` and visible as
  `hippocampus.search.outbox_depth`, instead of as silent divergence.

  The table is created on all three drivers and migrated in place on startup, so an existing store
  needs no manual step. Nothing is queued unless OpenSearch is the active backend.

### Added

- **The reconciliation sweep now runs in both directions.** It has always healed _missing_
  documents; it now also enumerates the index and removes documents whose memory the primary store
  no longer holds — the job that previously required a manual `--backfill-search --reindex` that
  nothing scheduled and no operator was told they needed. This is the backstop for whatever the
  outbox above cannot see: deletions abandoned at the caps, divergence predating the outbox, and any
  future bug that leaves a document behind. The two directions converge rather than fight, since the
  stale pass removes only what the primary store says is gone.

  New key `opensearch.staleSweep` (default `true`) turns the reverse half off. The pass shares
  `opensearch.reconcileBatchSize` and the existing pacing, and enumerates on the mapped `timestamp`
  field rather than `_id` — sorting on `_id` costs heap fielddata proportional to the index (~26
  bytes per document), which is the wrong property for a sweep whose whole purpose is bounding
  resource use.

- Four instruments for the above: `hippocampus.search.outbox_depth`,
  `hippocampus.search.outbox.applied`, `hippocampus.search.outbox.abandoned`, and
  `hippocampus.search.stale_documents_removed`.

## [0.37.0] - 2026-08-24

### Fixed

- **Deadlocks between concurrent recall and eviction on PostgreSQL.** Several statements mutate a
  _set_ of memory rows in one transaction — recall's `UPDATE`, spreading activation's `UPDATE`, the
  link-significance recompute, and the delete chokepoint's `DELETE` — and each took its ids in
  whatever order its caller produced: recall from the request, spreading activation from the link
  graph, eviction from a scan sorted by computed value. Two transactions holding overlapping sets in
  different orders deadlock, and Postgres resolves that by killing one of them. Observed in the wild
  at four deadlocks in four and a half minutes under a concurrent write/recall load: one surfaced to
  the caller as `Internal`, and one **failed an eviction pass**, leaving the store over its capacity
  target for that cycle. All six such statements now take their ids in one global order
  (`db/lockorder.go`). SQLite cannot exhibit this — it has a single writer — so the guard test is
  PostgreSQL-gated like its neighbours, but the ordering is unconditional. Triggering it needed
  `consolidation.linkRecallPropagation` above 0.

  **That ordering was necessary and not sufficient**, which a hardened reproduction then showed. A
  second class survived it: the delete paths take `memories → memory_links → memories` (links can
  only be pruned once the delete has revealed which ids passed the recall-race guard) while link
  creation takes `memory_links → memories`. Opposite _table_ orders deadlock however carefully the
  ids within each table are ordered, and the prune genuinely cannot move earlier. So the transient is
  now retried instead: `isRetryableWriteError` learned PostgreSQL's class-40 SQLSTATEs (`40P01`,
  `40001`) — it had been MySQL-only, on the reasoning that Postgres "does not deadlock a single
  INSERT", true of one statement and not of these transactions — and a new `withTxRetry` replays a
  whole transaction from `BEGIN`, since a deadlock aborts the transaction rather than the statement
  and retrying one statement inside an aborted transaction achieves nothing. Applied to the four
  transactions that take both tables. Deadlocks still occur under heavy contention; they no longer
  reach the caller or abandon an eviction.

### Added

- **[Retention quality](docs/retention.md) — a measured answer to "what does forgetting cost you?"**
  A trace-driven benchmark that replays an agent workload, fitted to a real corpus of 3,274
  references across 77 sessions, into a live instance and scores the survivors against the standard
  cache-replacement baselines (LRU, LFU, FIFO, static priority, random) at the same store size. It
  reports two question kinds separately, because averaging them hides which one a policy is bad at:
  _next-touch_ ("what will be looked up next", which recency answers almost by definition) and
  _must-keep_ ("what matters regardless of access"). The result: **every access-based policy is
  statistically indistinguishable from random on must-keep** — LRU 20.2% against random's 19.9% —
  while Hippocampus scores 27.6% at the same store size and +11.1 points over LRU at a larger one.
  Three checks against circularity are documented, including a noise sweep in which the advantage
  correctly collapses to nothing. The harness lives in the companion `hippocampus-gen` repository.

- **Guidance on choosing significance values ([Consolidation](docs/consolidation.md#choosing-significance-values)),
  and the wizard help to match.** Every one of the six decay methods divides significance by a
  function of age, so significance is compared as a **ratio** and never as a difference. Three
  consequences that were nowhere written down: tier schemes should be spread geometrically
  (1,000 / 3,000 / 10,000 / 30,000, not 1,000 / 2,000 / 3,000 / 4,000) or the top tiers are the ones
  the store can least tell apart; the **span** between the smallest and largest significance in use
  — not the magnitude of the numbers — is what decides how far significance can outweigh age; and
  `linkSignificanceWeight`/`recallSignificanceWeight` are **added in significance units**, so the
  same weight of 1.0 is worth about 9% of the top of a 1–100 scale and about 0.03% of a 1,000–30,000
  one. `deletionThreshold` moves with the scale for the same reason, while capacity eviction does
  not, since it ranks candidates against each other rather than against a threshold. No behaviour
  changed; this documents behaviour that was already there and is surprising.

- **A storage-layout section in [Consolidation](docs/consolidation.md#what-a-sleep-cycle-reads):
  what a sleep cycle actually reads.** A `memories` row banded into decay inputs, flags and payload,
  with a diagram of which pass touches which band — deliberately not an entity-relationship diagram,
  since the relationships in this schema are the guessable part and the interesting part is what the
  consolidation scans decline to read. It gathers the four facts that were previously only in code
  comments: the covering index is why a cycle's cost tracks the number of memories rather than their
  size; `significance_level_id` is an id into the shared registry, translated in Go so the scans
  never join it; `link_significance` is denormalised into the row (and the index) so connectedness
  can be priced without joining the link graph; and eviction, the one pass that leaves the index,
  reads `length(body)` and never the content. It also states what `UsedBytes` excludes and why — the
  record of what was evicted must never become the reason something else is evicted.
- **A drift guard over that section's column table** (`db/schemadocs_test.go`). The table claims
  both the row's shape and which six columns are in the covering index, so it is held to
  `memoryStoredColumns` and `coveringIndexColumns` in both directions — a column added to the
  schema, or one joining or leaving the index, now fails the build rather than leaving the page
  describing a row the service stopped having. The same shape as the four existing documentation
  guards.

## [0.36.1] - 2026-08-22

### Fixed

- **A startup failure while registering the HTTP gateway left the gRPC listener bound.** The gRPC
  server is already serving by the point the gateway's handler registration runs, so returning
  straight out of `run` leaked the listener and the open database for the life of the process. The
  service binary turns the error into an exit, which hid it; anything calling `run` in-process did
  not. It now stops the readiness updater, the gRPC server and the store before returning.

## [0.36.0] - 2026-08-22

### Added

- **Cross-origin access for browser clients — `gateway.corsOrigins`.** A list of exact origins
  (`scheme://host[:port]`) permitted to call `/v1` from a page this gateway did not serve. **Empty by
  default**, which sends no CORS headers at all, so an existing deployment is unchanged. `*` is
  refused and a trailing slash is rejected at startup — it would never match the `Origin` header a
  browser sends, and so would present as CORS mysteriously not working rather than as a
  misconfiguration. `Access-Control-Allow-Credentials` is **never** sent, which is what keeps the
  console's `HttpOnly` session cookie unusable from another origin; bearer tokens still work, because
  a caller sends those explicitly. Preflights are answered outside authentication (they carry no
  `Authorization` header by construction), outside the rate limiter (a throttled preflight is an
  opaque browser failure rather than a legible 429), and outside the RPC metrics (`OPTIONS` routes to
  no RPC, so counting them would push `rpc="unknown"` into the series the shipped alert rules read).
  The allow header is set **before** the request is served, so a 401, 429 or 503 from further in
  still carries it and the browser can show the caller the real status.
- **A Swagger UI compose profile.** `docker compose --profile swagger up --build` serves a browser
  form over the JSON API on `:8082`. It is pointed at the running gateway rather than at a copy of
  the document, which is what makes "Try it out" work: the generated document declares no `host`, and
  Swagger UI resolves each operation against the origin that served the spec. See
  [docs/clients.md](docs/clients.md).
- **The contract declares how to authenticate.** `hippocampus.proto` now carries an
  `openapiv2_swagger` option with a bearer `securityDefinitions` entry, so the generated OpenAPI
  document gives a browser API explorer an Authorize box that attaches the token to every call. This
  is additive annotation consumed by the OpenAPI generator: **no message, method, or wire format
  changes**, and `buf breaking` is clean. The `protoc-gen-openapiv2` option protos are vendored under
  `contract/protoc-gen-openapiv2/options/` alongside the existing `google/api` copies, so pointing an
  include path at `contract/` still resolves everything.
- **`gateway.openapi.enabled`** (default **true**) removes the `/v1/openapi.json` route entirely for
  a deployment that wants nothing served there.

### Changed

- **`/v1/openapi.json` is served without a token, even when authentication is enabled.** This
  reverses earlier behaviour, and the reasoning it rested on. The document is generated from a proto
  published with the source, so requiring a token protected a file anybody can fetch from the
  repository — while breaking every standard OpenAPI tool, none of which can authenticate the
  _initial_ spec fetch. Schema confidentiality was never the property being defended; a deployment
  that wants nothing there now says so with `gateway.openapi.enabled` instead.
- **The OpenAPI document is now covered by the arrival rate limit,** and carries an `ETag` so a
  repeat fetch is a `304`. It is served without credentials and is the largest single response the
  gateway produces, so leaving it outside the ceiling made it the cheapest bandwidth amplifier on the
  surface. It stays **out** of the RPC metrics, which describe the service's work rather than its
  documentation — the two path predicates now differ deliberately, and a test pins that they do.
- **`reflection.enabled`'s derived default is unchanged, but its rationale is corrected** in the code
  and in [docs/configuration.md](docs/configuration.md#server-reflection). The old argument — that
  reflection publishes the schema — does not hold for a contract published with the source. What
  actually justifies the default is narrower: reflection is a **streaming** RPC and every interceptor
  in the chain is unary, so it reaches neither the auth interceptor nor either rate limiter, making
  it the one surface on the gRPC port that is both unauthenticated and unthrottled.

### Fixed

- **A stale claim in [docs/getting-started.md](docs/getting-started.md)** that the service registers
  no gRPC reflection service. It has registered one by default on an unauthenticated instance since
  `reflection.enabled` landed, so `-proto` has not been mandatory there for some time.

### Compatibility

- `/v1/openapi.json` **returns `200` without a token under `auth.method` `hmac`/`idp`, where it
  previously returned `401`.** Anything relying on that endpoint being closed should set
  `gateway.openapi.enabled: false`, which removes it outright.
- That endpoint is now subject to the arrival rate limit. A deployment fetching it in a tight loop
  under a low `rateLimit.global` ceiling may now see `429`s where it previously did not.

## [0.35.1] - 2026-08-20

### Changed

- **The console's links panel is a drill-down, like an opened event.** Clicking **Links** on a row
  used to throw you onto the Memories tab and open a card under that tab's list — answering a
  question about the record in front of you by navigating away from it, and, from inside an opened
  event, leaving the memories you were reading for a memories list you had not asked for. The panel
  now replaces the list it was opened from, on the tab you were on, with a **Back** button that names
  where it goes ("Back to event" from inside one). This also fixes an event's links being
  unreachable: the card lives on the Memories tab, so opening it for an event switched to the Events
  tab and showed nothing at all.

### Fixed

- **A long name in the deployment diagram wraps instead of running outside its box.** A node's name
  is a bridge's `--name`, a peer's `host:port` or an observed caller's `client_id`, and telling two
  of them apart is what the inbound column is for — so the name wraps and the box grows to hold it
  rather than being truncated like the address beneath it. It breaks at the separators the
  identifiers actually carry (`-`, `.`, `/`, `:`, `_`), since a wrapper that only knew about spaces
  would treat `hippocampus-bluesky-bridge-worldnews` as one unbreakable word.

## [0.35.0] - 2026-08-19

### Added

- **Alert rules for the components that dial an instance — the `hippocampus-clients` rule group.**
  Six rules, in both
  [`deploy/observability/prometheus-alerts.yaml`](deploy/observability/prometheus-alerts.yaml) and
  its provisioned Grafana counterpart: a bridge whose stream is nearly all records the store already
  had, a bridge that is up and consuming nothing, a bridge failing to store what it consumes, a
  client whose token is being refused, a stalled ingestor pass, and an ingestor rule erroring rather
  than matching. Until now the shipped rules covered the service only, and the bridges and the
  ingestor — separate processes, each already exporting metrics — had none.

  The first two exist because of a real outage: a Bluesky bridge on the public demo spent hours
  re-presenting one record it could never store, at a cursor that never moved. The process was up,
  its `/healthz` answered, the store kept filling from a second goroutine, and nothing was being
  reinforced — the one thing that demo exists to show. It was found by hand. `outcome="exists"`
  dominating `stored`, and no stream at all, are the two shapes that failure has in metrics.

  What they cannot do bounds the design: **a bridge that has exited publishes nothing, and nothing is
  exactly what a deployment running no bridge publishes too**, so `HippocampusBridgeNotConsuming`
  fires only while a bridge is up and idle. Noticing a process being gone is the other half of this,
  and it is `topology.components` — the declared-component prober, which reads the `/readyz` those
  binaries already serve.

  `HippocampusClientTokenRejected` is the silent one, and the only rule in either file matching on a
  status code rather than an outcome: a component authenticating with a static token keeps running
  perfectly after it expires, failing every write for as long as the process lives, and the
  service-side error rate calls that a _client_ fault because that is what it is.

  Two things came with them. The drift guard now reads the instrument declarations in
  `integrations/eventsource` and `integrations/ingestor` as **files** rather than imports, so a
  root-module test can hold rules about metrics the root module deliberately does not depend on. And
  a constraint that was implicit is now written down: the Grafana copy thresholds each rule at
  `gt 0`, so an expression must return a **positive** number while it should be firing — a rule whose
  firing value is zero is correct in Prometheus and silent in Grafana.

- **A client-side row on the bundled Grafana dashboard**, collapsed by default since its panels are
  empty unless a bridge or the ingestor is running with `--metrics`: bridge messages by outcome,
  bridge reinforcement (`reinforced` against `missing`, the most informative number a reinforcing
  bridge produces), client RPC failures by endpoint and code, and ingestor pass staleness.

- **gRPC server reflection — `reflection.enabled`.** `grpcurl`, Postman, Insomnia and every gRPC GUI
  could not discover the schema from a running instance; each had to be handed
  `contract/hippocampus.proto` or a descriptor set built from it, which is a step at exactly the
  moment somebody is deciding whether this is worth their afternoon. HTTP callers already had the
  equivalent in `/v1/openapi.json`.

  The default is **derived rather than fixed**, because reflection publishes the full method and
  message set to anything that can open a socket, and does so before authentication — it is a
  streaming RPC, so it never reaches the unary auth interceptor. It is therefore **on when
  `auth.method` is `none`** (the local and demo case the friction is entirely about) and **off under
  `hmac` or `idp`**. Setting `reflection.enabled` overrides that in both directions, and whichever
  way it goes the choice is logged at startup naming the reason — "reflection is not working" being
  otherwise indistinguishable from "the tool is pointed at the wrong thing".

- **A security policy — [`SECURITY.md`](SECURITY.md).** There was no way to report a vulnerability
  privately and no statement of what was in scope. It names GitHub's private vulnerability reporting
  as the channel, states that the latest release is the supported one (pre-1.0, no backport
  branches), puts the public demo out of scope while asking that the underlying issue be reported
  here, and lists the documented behaviours that are **not** vulnerabilities — the off-by-default
  posture, the deliberately insecure demo Compose stacks, `Import` bypassing write-path validation,
  soft group scoping, and the console hiding controls it does not enforce. Each of those is still
  worth a report if the documented boundary can be shown being crossed.
- **A security guide of its own — [`docs/security.md`](docs/security.md).** Security was a bullet
  list at the end of the operations guide, which put the one topic a reader most needs before
  exposing a port behind everything about sizing and backups. It is now a page: what is off by
  default and what to turn on, authentication with key rotation and revocation, the role tiers,
  group scoping and the trust boundary, transport and gateway hardening, and the console's actual
  boundary (its hidden controls are a convenience — the server enforces every tier).

  Three sections are new rather than moved. **Where memory content can leave the process** names the
  four features that let bodies out — the embedded LLM, the OpenSearch index (which holds a copy of
  every indexed body, where the built-in FTS5 index is contentless and holds none), export/transfer,
  and what the forgotten log deliberately does not record. **What the service does not do** states
  plainly that there is no encryption at rest, no per-record ACLs, no mutual TLS on the listeners,
  and no separate audit log, each being a thing an operator might otherwise assume. And a
  **hardening pass** lists the ten steps in the order they matter.

- **Associative recall reached the CLI and the console.** `hippo memory recall --include-linked` and
  `hippo memory search --include-linked`, and a checkbox on the console's search panel, return the
  memories one hop from each result — an associative recall that is never itself reinforced. The
  field existed on both RPCs and had been reachable only from the MCP bridge.
- **`end_event` on the MCP bridge.** It could create events and never close one, so every event a
  model opened stored an end time of 0 — which sorts as the oldest-ended rather than the most
  recent, and reads as open forever.
- **Time filters on the MCP bridge's listings** — `stored_after`/`stored_before` on `list_memories`,
  and the four start/end bounds on `list_events`. They take RFC3339 timestamps rather than the
  UnixNano the RPCs use: a model can write a date but cannot reliably arrive at a nanosecond epoch,
  and a bound wrong by three orders of magnitude returns a plausible-looking empty page rather than
  an error.
- **The configuration wizard offers the topology settings and `listing.countCacheSeconds`**, which
  is to say the two most recent features it had silently missed.
- **A guide for the web console — [`docs/console.md`](docs/console.md).** The console is the first
  thing a new instance shows and it had no page of its own: how to reach it was a paragraph in
  getting-started, its boundary a section in the security guide, and its tabs described nowhere. The
  page covers reaching it, what each `auth.method` offers at sign-in, what each of the six tabs
  answers and which RPCs it answers with, and the three things worth knowing — that it computes no
  decay maths of its own, that its filters are a deliberate subset of the RPCs', and that it is not
  covered by the version number.
- **The complete instrument list, in [Operations](docs/operations.md#every-instrument-the-service-exports).**
  The observability section listed the metrics worth alerting on, which is a curated dozen; eighteen
  instruments were named nowhere at all, so a series arriving on a dashboard had no definition to
  look up. Every instrument the service exports is now a row with its type and attributes, alongside
  the three things the shape of that list says: which metrics exist only under OpenSearch, which are
  published only when the setting behind them is on, and that the gauges are recorded once per sleep
  cycle rather than per scrape.
- **Four drift guards over the documentation's copies of in-code tables**
  (`cmd/hippocampus/docsurface_test.go`, `auth/authzdocs_test.go`,
  `integrations/cli/docs_test.go`). Each documentation table that mirrors a table in the code is now
  held to it in both directions: instrument names against the declarations (a dotted name written
  with an underscore returns no series rather than an error), the RPC-to-route table against the
  `google.api.http` annotations, the role-tier table against `auth`'s `policies`, and the `hippo`
  command tables against the command registry. They are the same shape as the existing
  configuration-key and alert-rule guards, and each of the four found something on its first run.

### Changed

- **The Bluesky demo declares its own bridge.** `demo/config.bluesky.json` now lists the bridge under
  `topology.components`, so `demo/bluesky.sh` puts it on the console's **Deployment** tab and probes
  the `/readyz` it was already serving on `--health-port`. That is the half of the wedged-bridge
  problem the metrics cannot cover: a process that has gone publishes nothing.
- **The bridge message and memory counters describe `exists`.** Both instrument descriptions still
  listed the outcomes as they were before that value was added, so a dashboard built from the metric
  metadata would not have mentioned the one worth watching.

- **The README is a landing page again.** Following the shortening in 0.33.2, four sections moved
  out rather than being trimmed further: _Worth knowing before you start_ to
  [Use cases](docs/use-cases.md) (where "where it fits and where it does not" already lives), the
  quick start to [Getting started](docs/getting-started.md) (which gains the demo stack as its
  fastest look, and Homebrew beside the build), _Around the service_ folded into a single
  **Documentation** section with the guide index, and the security section down to what a landing
  page should carry — that it is all off by default — pointing at the new guide. 171 lines → 132.
- **[Operations](docs/operations.md) keeps both moved sections as pointers**, so every existing link
  to `#security` and `#group-scoping-and-the-trust-boundary` still resolves, including the ones in
  this changelog's own history.

### Fixed

- **A traces-only deployment reported its OTLP collector as disabled.** `GetTopology` read
  `observability.traces.enabled`, a key nothing sets — the service reads
  `observability.tracing.enabled` everywhere else — so with tracing on and metrics off the
  Deployment tab showed the collector greyed out while spans were being exported to it, and the
  `enable_with` hint it carried named the misspelled key. Nothing caught it because both topology
  tests enable metrics, which made the node appear for the other half of the condition.
- **Two documents said content search needs OpenSearch.** `docs/mcp.md`'s notes (contradicting its
  own tool table) and `docs/obsidian.md`'s feature list both predate the built-in SQL backend, and
  told a reader on the default `sqlite` driver that search was unavailable to them.
- **Five metric names in the operations guide were spelled with underscores where the instrument has
  dots** — `hippocampus.sleep_duration`, `hippocampus.memories_evicted`, `hippocampus.events_evicted`,
  `hippocampus.bytes_evicted` and `hippocampus.memory_body_bytes`. A query built from any of them
  returns no series and no error, which is the worst way for documentation to be wrong.
- **`SearchMemories` and `GetConsolidationStatus` were missing from the HTTP route table**, so two
  of the endpoints a reader is most likely to want — content search, and when the next cycle runs —
  could be reached only by reading the proto or a running instance's OpenAPI document.
- **The role-tier table omitted all six link RPCs.** `GetMemoryLinks`/`GetEventLinks` are `reader`
  and the four link writes are `writer`, but the table listed none of them and read as complete, so
  the tier needed to maintain the link graph was not written down anywhere. The table now says so,
  with the reason linking is a write: a link raises the effective significance of both ends, and so
  changes what the store forgets.
- **`hippo status` was undocumented.** The command shipped with `GetConsolidationStatus` and never
  reached the CLI guide's tables, which is to say the one question an operator asks a forgetting
  store from a terminal — when does it next forget — had no documented answer there.
- **Getting started described a sign-in field that no longer exists.** It told a reader to paste a
  bearer token into a box at the top right; the console has opened on a sign-in card standing in
  place of the tabs since 0.33.0, and the header carries only **Sign out**.
- **The event-source bridges' broker credentials were undocumented**, along with their OTLP export
  flags. There was no way to learn from the documentation that `--nats-password` or `--mqtt-username`
  existed, that broker transport security is the URL scheme's business (`tls://`, `ssl://`,
  `amqps://`) rather than a flag's, or that Kafka has no SASL support at all. The environment-variable
  form is now stated exactly, since the prefix is _added_ to the flag name: `--nats-password` reads
  `HIPPOCAMPUS_NATS_NATS_PASSWORD`, and the shorter `HIPPOCAMPUS_NATS_TOKEN` is not the NATS token
  but the Hippocampus one.
- **The ingestor's flag table gained the six flags it lacked**, including `--max-batch-bytes`, which
  bounds a single `ImportBatch` to the target.

### Breaking

- **`GetMemories` and `GetEvents` now default to `order_by: "timestamp"`, not `"significance"`.** A
  client that named no ordering gets the most recent first rather than the most significant first;
  one that named `significance` explicitly is unaffected. The old default could not be served by any
  index — `significance` is the registry's rank, reached through a join, so it is not a column of
  either table — which made the ordering a client gets when it expresses no preference the one
  ordering guaranteed to scan and sort the whole result set. It is also the better default on its own
  terms: "the most recent" is what a listing usually means, where significance-ordered returns the
  same head of the list until something more significant is written. The embedded console's sort
  selectors now open on it to match, and so do the MCP bridge's `list_memories`/`list_events` tool
  schemas — a `jsonschema` description is what a model reads to decide whether to send `order_by` at
  all, so one still naming `significance` as the default is not a stale comment but a wrong page.

### Changed

- **A listing index, and a listing that stops counting when it does not have to.** A page of fifty
  memories cost a full scan and a temp B-tree sort of everything the filter matched — 84 ms out of
  100,000 rows on SQLite, 106 ms on PostgreSQL — because the only index on `memories` leads on
  `event_id` and can therefore only be scanned, never sought. `idx_memories_listing_v1`
  (`timestamp DESC, id ASC`) matches the ordering clause column for column, which takes the same
  page to **0.16 ms and, more usefully, makes it flat**: 0.163 ms at 10,000 rows and 0.164 ms at
  100,000, because it walks fifty index entries instead of sorting the store. It is created on
  startup like the covering index, so an existing database gains it on next start, and it costs
  nothing measurable on write (65.4 µs against 65.9 µs per stored memory).

  The directions are load-bearing, not decoration: a plain `(timestamp)` index does **not** match a
  mixed-direction ordering, and is not merely useless — the planner takes it, walks it, and looks
  each row up by rowid, which is **8.5× slower than having no index at all** (2.2× on PostgreSQL).

  `TotalCount` was then the whole cost of a listing, being a second pass with no limit. It is now
  skipped entirely where the answer is already known — a first page that came back short has seen
  everything the filter matches, so its length _is_ the total, exactly rather than approximately —
  and where it is still needed it no longer joins the significance registry for a figure that
  discards it.

  What remains is cached per filter for `listing.countCacheSeconds` (default `5`; `0` counts every
  time), so a repeated listing stops recomputing it. The total can therefore lag the page beside it
  by up to that long — the same eventual consistency the content-search index already has — and it
  cuts the other way too: a client paging through results sees a **stable** total, where an exact one
  recomputed per page can move underneath a traversal. The key covers every field of the filter
  including the caller's group scope, so two callers scoped differently can never be served each
  other's total, and the cache is bounded because a filter is caller-supplied.

  Indexing the predicate instead was measured and rejected: an index making a group-scoped count 57×
  faster makes the scoped page 181× slower, by pulling the planner off the listing index.

  The skip now also covers a short page at a **positive** offset, which is the last page of every
  traversal: `OFFSET` skipped exactly that many matching rows to reach a window that then ran out, so
  the total is the offset plus what came back — exact, on the same terms as the offset-0 form. An
  _empty_ page at an offset is the one short page that must still count, since it bounds the total
  from above and a bound is not an answer.

  `Purge` and `Clear` now drop the cache rather than letting it lapse. Ordinary writes deliberately
  do not: invalidating per write would empty the cache continuously in exactly the deployments large
  enough for the count to cost anything. These two are different in kind — they move the total by
  orders of magnitude in one call, and a caller mid-traversal when the store went away would
  otherwise be shown the pre-purge figure by a page it had already loaded past.

### Security

- **An `idp` deployment is warned when it verifies nothing but a token's signature.** `iss` and `aud`
  are enforced only when `auth.issuer`/`auth.audience` are configured, so a deployment naming just a
  JWKS URL accepted **every** token that provider signed — including one minted for a different
  application in the same tenant, whose tier was then resolved from whatever `roles` claim it
  carried. Nothing said so: the reference described the mechanism ("when set") and left the
  consequence to the reader, where the two analogous risks — a short signing secret, auth without
  TLS — both warn at startup.

  It now warns too, once per unset claim, and the consequence is stated in
  [Security](docs/security.md#authentication) and [Configurability](docs/configuration.md). A
  warning rather than a refusal, matching those precedents: a single-purpose IdP whose tokens are
  only ever this service's is a legitimate deployment, and nothing here can tell the two apart. No
  configuration change is required, and none of this alters how a token that names the right
  audience is verified.

### Fixed

- **Five broken documentation anchors**, found by a link check over every relative link and heading
  in the repository's markdown: three copies of a `demo/README.md` heading anchor that assumed a `.`
  becomes a hyphen (it is dropped), and two in [Ingestor](docs/ingestor.md) naming headings that no
  longer exist.

## [0.34.0] - 2026-08-18

### Added

- **A deployment topology view: `GetTopology`, the console's Deployment tab, and `hippo topology`.**
  An instance now reports what it is attached to — itself, its store, the search index, the
  summariser and embedder, the object store, the transfer target, the identity provider and the OTLP
  endpoint — with the last known health of each and the configuration behind it. A dependency that
  is quietly broken (an OpenSearch cluster refusing writes, an Ollama server that never pulled its
  model, an S3 bucket the credentials cannot see) previously surfaced only when the operation that
  needed it failed; all three now show as a status with the reason beside it.

  What it reports is deliberately bounded by what an instance can honestly know: itself, and
  whatever it dials. Everything else in a deployment connects _to_ it and it holds no address for
  any of them, so every component carries a **source** and a sparse view reads as "nothing has been
  declared" rather than "nothing is running". It is read-only, and there is no counterpart that acts
  on another component — a registry would make a memory store into a control plane.

  Health comes from a background prober on `topology.probeIntervalSeconds` rather than from the
  request, and each component reports when it was last checked, so one console page never opens a
  connection to every dependency at once and a hung dependency cannot hang the RPC. Two components
  are never probed and say so: the OTLP collector (export is fire-and-forget) and the identity
  provider (a console poll must not become load on somebody's IdP). The transfer target is opt-in.

  Every address is redacted server-side — DSN credentials in all three forms, cluster passwords,
  signing material — which is what makes the default `reader` tier defensible.
  `topology.minimumTier`
  is the one per-RPC tier a deployment may configure; a group-scoped caller is refused regardless,
  since there is no per-group topology to answer with. New `topology.*` config block, all of it
  defaulted. See [Deployment topology](docs/configuration.md#deployment-topology).

- **Declared components in the topology view (`topology.components`).** The half of a deployment an
  instance cannot discover — the broker bridges, the ingestor, MCP servers, any other client —
  can now be listed, and each is probed and drawn as part of the deployment, with its edge
  pointing **inward**, because that is the direction the connection is opened in.

  It needs no change to the components themselves: the bridges and the ingestor already serve
  `/readyz`, and that endpoint already reports a per-dependency breakdown, so a declared bridge that
  cannot reach its broker now says so where before it would have been an unexplained red box. A
  `503` is reported as degraded (it answered, and it named the reason), a refused connection as
  unreachable, and a `404` — a `healthUrl` that is simply wrong — with its status code, so all
  three are told apart. The list is capped at 32 and every entry is validated at startup; the
  probe round now runs a few probes at a time so a full list still completes inside one interval.

- **Peer discovery on a shared store, and the warnings it makes possible
  (`topology.heartbeatSeconds`).** A horizontally scaled deployment — one consolidator plus N
  replicas over a shared `postgres`/`mysql` database — could not name its own peers: the
  single-consolidator advisory lock proves only that _somebody_ holds it, not who, and nothing at
  all about how many replicas are attached. Each instance now registers one row in an `instances`
  table every `heartbeatSeconds` (default 30, `0` disables it), so every instance can report its
  peers with their version, their role, their capability flags (search index, summariser, embedder,
  gateway) and how long ago each last checked in. The id is `hostname:port` and therefore
  deterministic, so a restart replaces its own row rather than leaving a ghost to age out; a clean
  shutdown removes the row immediately, and an instance that stops without saying so is reported
  unreachable for a window before it disappears.

  That registry is what makes two deployment-wide faults visible, both reported as **warnings** on
  the response — shown above the diagram in the console, printed first by `hippo topology`, and
  logged at `WARN` when they appear and at `INFO` when they clear. **No instance is consolidating**:
  every one came up with `consolidation.enabled: false`, so nothing forgets, nothing evicts and the
  store simply grows, while each instance individually reports itself perfectly healthy — because it
  is. There was no component to show as red for that, since the fault _is_ the absent one. And the
  reverse, **more than one instance consolidating**, which is what a circumvented lock or two tiers
  pointed at different databases looks like from inside. A stale row is never counted toward either,
  so a replacement correctly taking over is not reported as a duplicate.

  SQLite keeps no registry and creates no table: that store is single-instance by construction, and
  its page-based capacity accounting would let the record of the deployment raise capacity pressure
  and evict live memories to make room for itself. `GetTopologyResponse` gains a `warnings` field
  (additive).

- **Observed callers in the topology view.** Where authentication is on, a client that presents a
  verified token is now drawn from the `client_id` it authenticated with, reporting the roles that
  token carried, whether it is group-scoped, how many calls it has made and when it last made one.
  There is nothing to configure: it is on wherever the view and authentication both are. It closes
  the last gap in the inbound half of a deployment — until now a component that dialled in was
  invisible unless an operator remembered to declare it.

  Declaring and observing combine rather than compete. Where a declared component's `name` matches
  an observed `client_id`, the two are reported as **one** component carrying both its health and
  its last call — the pair that separates a bridge which is up and writing from a bridge which is up
  and has written nothing, which nothing in the view could distinguish before.

  Four limits are deliberate. An observed component carries **no health** and reports `not checked`
  permanently, because a call proves the client was alive at that instant and not that it is
  working. It reports **nothing when authentication is off**, since a caller is identified by its
  token and never by a source address or a user agent — and the `self` component says so, so the
  empty inbound half is explained rather than merely empty. The set is **bounded at 32**, least
  recently seen evicted first, because the key arrives in a token and an unbounded one would be
  memory a caller controls; for the same reason a `client_id` is never used as a metric attribute.
  And entries are **never expired on a timer** — a component whose last call was hours ago stays on
  the diagram saying so, which is the report of the fault, where one that had quietly vanished would
  be indistinguishable from one nobody ever ran. No contract change.

## [0.33.2] - 2026-08-16

### Changed

- **A much shorter README.** It had grown into a second copy of the documentation — every
  integration, every deployment target, and the security surface each explained in full — so the
  things a reader arrives for were buried. It is now a landing page: what the service is, the live
  demo, one quick start, a table of the components around the service, and the documentation index.
  Everything it used to explain in place is in `docs/`, and what was only ever in the README moved
  there rather than being dropped — the **Docker Compose stacks and the Kubernetes overlays** (a new
  _Containers and Kubernetes_ section in [Operations](docs/operations.md), which had no Kubernetes
  coverage at all), the **hosted demo instances** and what each shows
  ([Demonstrations](docs/demonstrations.md)), the **Homebrew formulae** for the two client binaries
  ([CLI](docs/cli.md), [MCP](docs/mcp.md)), and the note that storage errors are masked behind gRPC
  status codes ([Operations · Security](docs/operations.md#security)).
- **The hosted Bluesky demo is listed, and led with.** Neither the README nor
  [Demonstrations](docs/demonstrations.md) mentioned it, though it is the first console on the demo
  site and the only one running on live data nobody staged — headlines arriving from a curated news
  feed, all at one significance, with real engagement the sole differentiator between what survives
  and what decays.

- **Opening an event in the console is now a drill-down rather than a card stacked on top of the
  list.** An event and its memories used to appear above the events list, the filter and the create
  form — so the thing you had asked for arrived with a page of controls beneath it that no longer
  applied to what was on screen, and on a long list it was easy to miss that anything had opened at
  all. The Events tab now shows one thing at a time: the list, or one event. A **Back** button is the
  way out, and it names where it goes, because an event id is a link in four tables across three
  tabs and returning to the events list is wrong for the three-quarters of them that were not opened
  from it — following an event from a memory row lands you back on Memories, with the results you
  had. Clicking a tab in the nav leaves the drill-down as well, so arriving at Events by hand always
  finds the list. Each row also carries an explicit **Open ›** button beside its other actions: every
  other thing a row can do to an event was already a button, and the one that navigates was the one
  that did not look like a control.

### Fixed

- **The Bluesky bridge no longer asks the service to link a post to itself.** A feed generator hands
  back the same page on every poll, and the topic-linking path was reached again for every post it
  had already related — by which point that post was in the term index and so came back as its own
  strongest match. Each poll therefore produced one rejected `LinkMemories` call per already-seen
  post, filling the bridge's log with `InvalidArgument … link N links memory to itself` while the
  posts themselves stored fine. The lookup and the index insert are now one locked operation that
  reports nothing for a post already indexed, which closes the ordering race behind it as well: the
  poll loop and the firehose consumer both reach that code, and either could index a post between
  the other's lookup and insert. A post already related is simply not related again — nothing is
  lost, since a link's significance counts for both of its ends, so a related post arriving later
  builds the edge from its own end.

- **A results table's column headings now stay put while its rows scroll.** Listing a page of
  memories, or a wide set of search hits, scrolled the headings off the top after the first few
  rows, and from there a column of bare numbers said nothing about which column it was. Each table
  now scrolls within its own bounded height with its heading row pinned above it — including the
  pinned actions column's corner, which holds both edges at once — so the headings are in view for
  every row.

## [0.33.1] - 2026-08-16

### Fixed

- **Opening an event no longer throws you onto the Search tab.** The event drill-down — an event's
  details and every memory attached to it — was rendered on the Search tab, so clicking an event's
  name in the events list navigated away from the Events tab and showed those memories above a query
  form that had nothing to do with them. An event's memories are not a search result. The card now
  lives on the **Events** tab, at the top, and opening an event from anywhere (the events list, a
  memory's event id, a link, the candidates list) lands there. A search no longer closes an open
  event either: the two are on different tabs now, so doing so would reach across and discard
  something the user had opened.
- **A memory body no longer runs off the side of the card.** The free-text row spanned every column
  including the pinned actions column, and was as wide as the _table_ rather than as wide as the
  visible scroll area — so on any table wide enough to scroll (two monospace id columns and four
  buttons, which is most window sizes) the right-hand end of every body was outside the card, with
  the pinned buttons painted over what was left. Reading a memory meant scrolling a table sideways.
  The row now stops one column short, with the pinned column continuing beside it, and the text is
  pinned to the left of the scroll viewport and sized against it, so it stays whole and in place
  while the columns scroll past.

### Changed

- **The Events tab has List and Summarise modes.** Summarisation candidates were a second card
  stacked permanently below the events list, under a filter that did not apply to them, with a
  Refresh button in its header that overlapped the text explaining what the list was. They are now
  the second mode of the tab's control card: **List** is the filter you write, **Summarise** is the
  list the sleep cycle wrote for you, and each shows its own results card. Selecting Summarise does
  not load anything — the candidates are a snapshot the cycle refreshes, so loading them stays a
  deliberate act with its own button.

- **Reading the forgotten log is now `reader`-tier, not `admin`.** `GetForgottenMemories` was
  assigned `admin` on the grounds that it enumerates ids, groups and significances across the store
  — but `GetMemories` does that at `reader`, with the bodies as well, so enumeration was never what
  separated the two tiers. What separates `PreviewConsolidation`, which the log was placed beside,
  is that it is _unscoped_: it describes the whole store and is refused outright to a group-scoped
  caller. The log is not. A tombstone carries its memory's group, so both its RPCs are scope
  filtered, and a scoped caller reads exactly their own partition's losses — the same records they
  could have read in full, with bodies, while those memories were alive. It reports the `value` and
  `threshold` pair that `ExplainConsolidation` already serves at `reader`, and it carries no bodies.
  This puts all three forgetting-transparency reads (`ExplainConsolidation`,
  `GetConsolidationStatus`, `GetForgottenMemories`) at one tier.

  `DeleteForgottenMemories` is unchanged and stays `admin`: it is destructive, and destructive on an
  audit record rather than on data the caller put there.

  This widens access, so no client breaks — but it is security-relevant, and a token that is refused
  today will be allowed after upgrading. The case for keeping the read at `admin`, if it applies to
  your deployment: the log outlives what it describes, so a long
  `consolidation.tombstones.maxAgeInDays` leaves a trace of groups, sizes and timing that the live
  store would by then have discarded. Where `reader` tokens go to clients you would not trust with
  that history, keep the log short.

  In the console this moves the **Now** tab's forgetting feed and the **Decay** tab's log panel into
  view for every caller — a writer could not previously see that their own memories had been
  forgotten — while the panel's _Clear the log_ button remains administrator-only.

## [0.33.0] - 2026-08-16

_Covers every change since v0.23.0. The releases between it and v0.33.0
shipped without their entries being rolled out of `[Unreleased]`, so the changes below are
recorded together rather than attributed to the release each shipped in._

### Breaking

- **Event relationships became links, and the contribution is now damped.** Memory-to-memory links
  and event-to-event relationships turned out to be the same mechanism, so they are now one:
  the `Link` message, the `link_significance` aggregate, and one weight. Four separate breaks:
  - **Contract.** `Relationship` → `Link` (its `event_id` field → `id`); `Event.relationships` →
    `Event.links`; `Event.relationship_significance` → `Event.link_significance`. Field numbers and
    types are unchanged, so the wire format is identical — only the names break. Generated clients
    must be regenerated. `buf breaking` reports the removal of the `Relationship` message (the field
    renames are not wire-breaking and it does not flag them); that report is expected.
  - **Configuration.** `consolidation.relationshipSignificanceWeight` →
    `consolidation.linkSignificanceWeight`. The old key is not read; there is no alias.
  - **Behaviour — the weight now means something different, and must be re-tuned.** The
    contribution changed from `weight × total` to `weight × ln(1 + total)`. A relationship total of
    1,280,000 at weight 0.1 used to contribute 128,000; it now contributes about 1.4. **Every
    configured weight is effectively a no-op until re-tuned.** The damping is what stops any number
    of links making an item unforgettable and defeating the capacity bound — see
    [Links](docs/consolidation.md#links). `ExplainConsolidation` reports each memory's link
    significance beside its damped contribution, which is the quickest way to pick a new value;
    the config wizard's decay preview mirrors the new maths.
  - **Stored schema.** Event relationships moved from the `events.relationships` JSON column to an
    `event_links` table, alongside the new `memory_links`. **No data is migrated**: the legacy
    columns are dropped on first startup and the graph starts empty. This is deliberate — a
    half-migration that silently reinterpreted significances under the new damped maths would be
    worse than starting clean. Re-create any event relationships you rely on via `LinkEvents`.
  - Also of note: an event's links no longer round-trip through `StoreEvent`/`UpdateEvent`. They
    are rows in their own table, edited through the link RPCs, so a create or partial update
    carrying links leaves the existing graph alone rather than replacing it. The `hippo` CLI's
    `--relationship` flag is renamed `--link` to match.

- **The proto package is now `hippocampus.v1`, was `proto`.** Taken deliberately, and now rather
  than after 1.0, so that a future v2 of the contract can be served beside v1 instead of replacing
  it — a namespace with no version in it leaves no room to do that, and the rename only gets more
  expensive as more clients are generated.
  - gRPC method paths change from `/proto.Hippocampus/<Method>` to
    `/hippocampus.v1.Hippocampus/<Method>`. Anything naming a method in full — a grpcurl
    invocation, a service-mesh route, an authorisation policy outside Hippocampus, a metrics
    relabelling rule — must be updated.
  - Generated clients must be regenerated. The Go package is unaffected (`option go_package` is
    unchanged, so it remains `contract`), as are the Go type names.
  - `/v1` gateway paths, JSON field names, and request/response bodies are **unchanged**. An HTTP
    client — including the Obsidian plugin — needs no change.
  - The OpenAPI document's schema names change (`protoMemory` → `v1Memory`, and so on). Generated
    OpenAPI clients must be regenerated; the paths and payloads they call are the same.
  - Stored data is unaffected: neither the database nor the archive format records the proto
    package.

### Added

- **A "Now" tab: the console's landing view, and the store's premise made live.** The console opened
  on an empty Search tab and said nothing about forgetting, so a store quietly consolidating every
  two minutes looked exactly like a store doing nothing. Now leads with how many memories are held,
  what the last cycle forgot, a countdown to the next, a capacity meter showing whichever axis is
  actually binding, and a feed of what has just gone. It computes no decay maths of its own — every
  figure is served — and it degrades in place rather than vanishing: a replica explains that its
  store is consolidated elsewhere, a reader sees everything but the forgetting feed and the Sleep
  control, and a store not recording tombstones says which config key would start it.
- **`GetConsolidationStatus`** (`GET /v1/consolidation/status`, `hippo status`) — when the next
  consolidation cycle is due, whether one is running, and what the last one did (counts for each of
  the two decay paths, bytes reclaimed, duration, and what triggered it). It completes the
  forgetting-transparency set: the dry run says what would go, `ExplainConsolidation` where a memory
  stands, the forgotten log what went, and none of the three said **when**.
  - **Reader tier**, because it names no stored record and returns counts rather than ids — the same
    grounds on which `ExplainConsolidation` already serves a reader the store's used bytes and
    memory count.
  - **It does not refuse on a read/write replica**, unlike `Sleep`, `PreviewConsolidation` and
    `ExplainConsolidation`. Reporting `consolidation_enabled: false` _is_ the answer there; refusing
    would leave a client unable to tell a replica from a consolidator whose cycle had died, which is
    the distinction the RPC exists to make.
  - It reports `snapshot_ttl_seconds` so a polling client paces its `ExplainConsolidation` calls
    from the server's own cache rather than from a guess.
- **Event links are reachable from the console.** `LinkEvents`/`UnlinkEvents`/`GetEventLinks` had no
  UI at all while memories had a full links card, even though the two are one mechanism. One card
  now serves both.
- **Event metadata is settable, filterable and visible in the console** — a metadata field on the
  create form, a metadata filter on the listing, and the same key=value pills the memories table
  already rendered. `Event.metadata` and `GetEventsRequest.metadata` had existed server-side
  throughout.
- **The forgotten log pages**, by keyset (`after_seq`/`next_seq`, which the RPC already returned),
  so a log longer than one screen is readable rather than truncated at the limit.
- **`scripts/release.sh`** — cuts a release: runs the pre-flight, rolls `[Unreleased]` into a dated
  version section, rewrites both link references, commits and tags. It deliberately does not push,
  and it refuses to tag when the changelog is not in the state a release needs — including when its
  newest version heading is not the current tag, which is how seventeen releases came to ship with
  their entries still under `[Unreleased]`. See [RELEASE.md](RELEASE.md#cut-the-release).

- **`WhoAmI` reports `consolidation_enabled` and `tombstones_enabled`**, so a client can tell a
  consolidator from a replica and a recording store from a silent one without probing. The first is
  the deployment property behind a family of refusals — `Sleep`, `PreviewConsolidation` and
  `ExplainConsolidation` are all `FailedPrecondition` where `consolidation.enabled` is false, because
  a replica's store is consolidated by another instance under _that_ instance's configuration. The
  second exists for the opposite reason: `GetForgottenMemories` does not refuse when the log is off,
  it answers with an empty page, and "nothing was written down" is indistinguishable from "nothing
  has been forgotten" without being told which. Both are reported on the authenticated and the
  unauthenticated path, like `search_modes` and `summariser_enabled`; `hippo whoami` prints them.
- **The forgotten log: an optional record of what each cycle deleted, and why.** Off by default
  (`consolidation.tombstones.enabled`). When on, every memory the two decay paths delete leaves one
  record carrying its id, group, event, significance, stored size, the computed `value` and the
  `threshold` it was measured against, which rule took it, and when. `GetForgottenMemories`
  (`GET /v1/memories/forgotten`, `hippo forgotten list`) reads it; `DeleteForgottenMemories`
  (`POST /v1/memories/forgotten/delete`, `hippo forgotten clear`) empties it. Both are `admin`, and
  both honour group scoping as a predicate, so a scoped token reads and clears only its own
  partition's losses. This completes the forgetting-transparency trio: the dry run says what would
  go, `ExplainConsolidation` says where a memory stands, and this is the only one that can speak
  about a memory that is no longer there. See
  [the forgotten log](docs/operations.md#what-was-forgotten--the-forgotten-log).
  - **Bodies are never kept.** A record says a memory was forgotten, not what it said; this is
    deliberately not an undelete.
  - **It records forgetting, not deletion.** `Clear` (which deletes memories an `Export`/`Transfer`
    has already moved) and the client-initiated deletes write nothing — nothing was lost in those
    cases, and a log claiming otherwise would be worse than none.
  - **Turning it off deletes nothing.** Disabling stops the writing _and_ the automatic trimming, so
    what was recorded stays readable; emptying the log is always an explicit request. The threshold
    is recorded per record rather than inferred because it moves with capacity pressure — a value
    from last month means nothing measured against today's threshold.
  - **Bounded by default so the feature cannot eat the store it describes.**
    `consolidation.tombstones.maxRows` (100,000) and `maxAgeInDays` (30) are applied at the end of
    each cycle; either can be set to 0 to remove that bound, which is warned about at startup. The
    log is excluded from the store's measured size, so it never raises capacity pressure or
    triggers eviction. Two metrics come with it: `hippocampus.tombstones` and
    `hippocampus.tombstones.deleted`.
  - The console's **Decay** tab shows the log beside the dry run, for an administrator. It is
    deliberately not on the MCP surface, alongside the other admin RPCs.

- **The memory and event listings sort on more than two columns, in either direction.** `order_by`
  previously accepted `significance` or `timestamp` and always sorted descending. It now names any
  of seven columns per listing — memories add `time_recalled`, `recall_count`, `link_significance`,
  `group` and `id`; events add `time_end`, `name`, `link_significance`, `group` and `id` — and a new
  `order_dir` (`SORT_DIRECTION_ASC`/`SORT_DIRECTION_DESC`) reverses any of them. Existing callers are
  unchanged: both fields default to what these listings did before.
  - An omitted `order_dir` means each column's **natural** direction rather than ascending —
    descending for the magnitude and time columns, ascending for the lexical ones (`id`, `group`,
    an event's `name`) — since alphabetical is the only reading of a name anyone wants first.
  - Reversing applies to the tiebreakers too, so `ASC` is the exact reverse of `DESC`; every
    ordering still ends in an id tiebreaker, so offset paging stays stable.
  - A never-recalled memory (`time_recalled` 0) and an unended event (`time_end` 0) sort as the
    least recent rather than dropping out of the page: an ordering that silently filtered would be
    the more surprising behaviour, and `recalled`/`time_end_min` ask that question directly.
  - An unaccepted `order_by` is now rejected with `InvalidArgument` listing the accepted values,
    where it previously surfaced as `Unknown` (a 500 over the gateway). The other range validations
    on those two RPCs are unchanged.
  - Reachable as `hippo memory list --order-by … --order-dir …` (and `hippo event list`), with
    per-command shell completion, and as `order_by`/`order_dir` on the MCP bridge's `list_memories`
    and `list_events`. The embedded console gains a Sort by/Direction pair on both filter forms and
    clickable column headers on both tables.
- **`GetEvents` can report each event's memory count without transferring the memories.** A new
  opt-in `GetEventsRequest.memory_counts` populates a read-only `Event.memory_count` from one
  aggregate query that reads no bodies at all. Previously the only way to say how much an event held
  was `memories: true`, which fetches every body on the page to count them. It is opt-in because it
  is a second query per page, separate from `memories` rather than derived from it, and counted
  within the caller's group scope exactly as the nested memories are filtered. Reachable as
  `hippo event list --memory-counts`; the embedded console's events table now always asks for it.
- **`GetSummarisationCandidates` reports `scan_enabled`.** An empty candidate list means one of two
  opposite things — nothing is due yet, or this instance does not scan at all (the threshold is 0, or
  it is a replica and runs no sleep cycle) — and only one of them is worth waiting on. A client
  presenting an empty list should branch on the flag, not on the list. The `hippo` CLI prints the
  configuration it would need; the MCP bridge projects it; the console renders a different empty
  state for each.
- **`GetEventById` can report the memory count too** (`memory_counts`), mirroring `GetEvents`.
  Reachable as `hippo event get --memory-counts`. The MCP bridge's `list_events` now always asks for
  counts (and still never for bodies).
- **`WhoAmI` reports `summariser_enabled`.** Whether the embedded LLM (`ollama.enabled`) is
  configured, so a client can offer service-authored summarisation only where `SummariseMemories`
  will serve rather than discovering its absence through a `FAILED_PRECONDITION` — the same
  deployment-property reporting as `search_modes`, and on the same terms.
- **A Bluesky firehose bridge, and with it engagement-as-recall.** `integrations/eventsource` gains a
  fifth adapter (`cmd/bluesky`) that consumes
  [Jetstream](https://github.com/bluesky-social/jetstream), the public JSON projection of the atproto
  firehose. It is the first bridge that _reinforces_ as well as writes: a post becomes a memory, and
  the likes, reposts and replies that follow it become `RecallMemories` calls against that post — so
  every post arrives with the same significance and only what people came back to survives.
  - **It needs no state.** A memory's id _is_ the post's `at://` URI, and a like names its target by
    that same URI, so reinforcing is a call rather than a lookup. A like for a post the bridge never
    ingested, or one the store has already forgotten, costs one `UPDATE` matching no rows. The same
    identity makes replay idempotent, which is what the cursor-gated at-least-once loop relies on.
  - **The bridge's token must be unscoped and writer-tier.** A group-scoped token makes the service
    scope-check ids before recalling them, turning an id it does not hold into `NotFound` for the
    whole batch; a reader-tier token gets a non-reinforcing read unless `auth.readerRecallReinforces`
    is set. Both are absorbed, so a misconfiguration degrades to "reinforcement stops working"
    rather than "the bridge stops consuming".
  - `--events thread` opens an event per thread root, `--honour-deletes` (**on by default**) maps an
    upstream deletion onto a memory deletion — decay is about significance, deletion is about
    consent — and `--dids`/`--langs` narrow the stream. Recalls are batched and deliberately
    best-effort: a lost like decays a memory slightly sooner, it does not make it wrong.
  - Ships as `ghcr.io/fastbean-au/hippocampus-bluesky-bridge` and a per-OS/arch release binary, like
    the other four. A demo is in `demo/bluesky.sh`. See
    [docs/eventsource.md](docs/eventsource.md#bluesky-the-firehose-bridge).
- **The Bluesky bridge can relate posts to each other, with no NLP.** `--topic-links` extracts topic
  terms from a post's link-card URL — a news URL's path is a slug someone wrote by hand, already
  tokenised on hyphens and chosen editorially — and relates posts sharing at least two of them,
  ignoring terms common enough to be section names rather than topics. Measured against a live news
  feed it relates about a quarter of posts, and the matches are cross-outlet. This is what makes
  `consolidation.linkRecallPropagation` do anything: with links, a like on one outlet's coverage
  pulls the others back from the threshold too, and `linkSignificanceWeight` makes a cluster of
  coverage more durable than a lone post. Links are issued **after** the write rather than attached
  to it, because a link target must exist and in a store whose job is forgetting, attaching them to
  the create would let a neighbour consolidated a minute ago fail the write itself; a backfill is the
  exception, attaching them to its `ImportBatch` whose second pass resolves intra-batch targets.

- **The Bluesky bridge can take its posts from a curated feed.** `--feed at://…` reads an atproto
  feed generator over HTTP instead of the firehose, while engagement keeps arriving on Jetstream —
  the feed decides what is worth storing, the firehose reports what people did with it, and the two
  meet by `at://` URI with no correlation state. It trades volume for legibility (tens of posts an
  hour rather than tens a second, every one of them readable), which suits a hosted demo where the
  firehose suits a local one. `--feed-backfill` seeds the store from the whole feed at startup, and
  `--feed-seed-recalls` carries each backfilled post's observed engagement across as a **damped**
  recall count — `round(log1p(likes + reposts))` — because those likes happened before the bridge was
  watching and the firehose will never report them. The damping matters: effective significance rises
  linearly with recall count, so a raw five-thousand-like count would make one post unforgettable
  forever. Seeding is the only write that uses `ImportBatch`, which is the one RPC that carries
  recall history, and it happens once; polling uses `StoreMemory` and treats `AlreadyExists` as
  "already have it", so re-reading the feed needs no bookmark and never rolls back live
  reinforcement.

- **The Bluesky bridge can capture the conversation around a feed's posts, not just the posts.** In
  feed mode a firehose post was reinforcement and nothing else, which left `--events thread` holding
  events of one memory. Two new flags widen that, independently:
  - `--capture-replies` stores a post that **replies to a thread the bridge holds**, matching on the
    thread root first (so it matches however deep the reply sits) and its parent after. With
    `--events thread` the feed's post opens the event and the public's replies become memories in it
    — the post-as-event, responses-as-memories shape. A captured reply still reinforces its parent;
    capture adds a memory rather than replacing the engagement.
  - `--feed-authors` stores a post by **any account the feed has surfaced**, so the accounts a feed
    is made of are followed rather than only the posts that feed picked. The DIDs are derived from
    the feed itself on each read, so there is no account list to maintain.

  `--capture-significance` ranks a captured post below the feed's own (a reply is worth keeping
  without being worth as much as the post it answers; without it they compete for the same capacity),
  and captured posts are deliberately **not** topic-linked, since a reply carries no link card and its
  body is conversation rather than an editorially written slug.

  Both indexes are bounded, in-memory and best-effort (`--capture-index-size`, `--feed-authors-max`);
  the capture index holds only what the feed produced, never the replies captured through it, so one
  busy thread cannot evict the posts every other thread is matched on. Neither works under `--dids`,
  because Jetstream's `wantedDids` selects on the repository a record was written **in** and a reply
  lives in the replier's — the same reason `--dids` beside `--feed` receives no engagement at all.
  All three combinations are now warned about at startup, having previously presented as a feed
  nobody appeared to be interacting with rather than as anything failing.

- **The event-sourcing bridges can authenticate with OIDC client-credentials.** `--oidc-issuer`
  (or `--oidc-token-url`) plus `--oidc-client-id`/`--oidc-client-secret` make a bridge mint and
  refresh its own access tokens instead of carrying a `--token` that eventually expires — at which
  point the bridge does not stop, it keeps consuming and fails every write with `Unauthenticated`,
  silently, for as long as it is left running. Setting a client id selects the grant over a static
  token. Configuration is validated at startup but discovery is deferred to the first RPC, so a
  typo fails immediately while an IdP that happens to be unreachable does not stop a supervised
  bridge coming up; a token that cannot be obtained fails the RPC rather than sending none, so on an
  at-least-once broker the message is redelivered. Flag names match the showcase generators', so one
  realm configures both.

- **The event-sourcing bridge core gained `Recall`, `Forget`, `EnsureEvent` and `HandleEvent`.** The
  client seam widened from one RPC to four named ones (`StoreMemory`, `StoreEvent`,
  `RecallMemories`, `DeleteMemories`), which is still a guard rather than the whole generated
  client: `Dial` hands back everything, so that unexported interface is the only thing standing
  between an adapter and `Purge`. `Handle`'s behaviour is unchanged, so the existing four adapters
  are untouched. Three new metrics come with it — `hippocampus.bridge.recalls`,
  `hippocampus.bridge.events` and `hippocampus.bridge.recall.batch_size` — where the `missing`
  recall outcome is the informative one: an id the store no longer holds is the decay model having
  already done its job, and its ratio to `reinforced` is the most useful number a reinforcing bridge
  produces.

- **The ingestor and the four broker bridges are instrumented.** Both were long-running daemons with
  no metrics and nothing to probe, which made their worst failure mode — stalling silently — look
  exactly like being idle. Each now serves `/healthz` and `/readyz` and exports OTEL metrics over
  OTLP/gRPC, sharing one implementation with the service via a new root-module `observability`
  package (`cmd/hippocampus/observability.go` promoted, not copied).
  - **Health surfaces.** `--health-port` (**8090 by default**, 0 disables) serves `/healthz`
    (liveness, never fails while the process runs) and `/readyz` (whether the Hippocampus instance
    can actually serve, checked via the token-free gRPC health service and named per dependency, so
    a failing probe says _which_ end is down).
    **This is a change of network surface**: these binaries previously listened on nothing at all.
    Set `--health-port 0` to keep that, and give each process its own port when several run on one
    host.
  - **Metrics.** `hippocampus.ingestor.*` (events by outcome and rule, memories, orphans, rule
    errors, pass duration, and `seconds_since_last_pass`), `hippocampus.bridge.*` (messages and
    memories by broker and outcome, message duration, body bytes), and `hippocampus.client.rpc.*`
    (client-side RED metrics emitted by everything that dials the service, tagged by endpoint).
    `outcome` is multi-valued rather than a success bool throughout, so an event a rule deliberately
    dropped, or a memory the service declined for insignificance, never shares a series with a
    failure.
  - **Tenancy is `--metrics-group`**, a per-process label stamped on both the OTEL resource and each
    metric — the duplication avoids a `target_info` join in every query, and costs nothing because
    the value is fixed for the process's lifetime. It is deliberately **not** read from each record:
    a bridge derives a memory's group from the message subject by default, so a per-record label
    would be unbounded. Note that no service metric carries a group; this is the client side only.
- **An ingestor: stage data at the edge, promote only what earns it.** A new
  `integrations/ingestor` module and `hippocampus-ingestor` binary that watches an edge instance for
  **completed** events, judges each against a [CEL](https://cel.dev) rules file, and either promotes
  it to a central instance, promotes it after reducing it, or drops it — draining the edge either
  way. It is a client of two instances, not a service feature: the edge is a stock, unmodified
  `hippocampus`. Documented in [Ingestor](docs/ingestor.md).
  - **It holds no state.** `ImportBatch` is a full-state upsert by id, so promote-then-drain is
    at-least-once against an idempotent receiver and a crash between the two re-promotes identical
    rows. There is no cursor and no bookmark: the edge store _is_ the queue, and what it holds is
    exactly what has not been judged yet.
  - **Judgement happens at event completion, not at ingest**, which is what makes a rule change
    reach in-flight data: an event still open when the rules reload is judged by the new ones. The
    file is re-read on an mtime change, a bad initial load fails startup, and a bad reload keeps the
    last good ruleset — the same contract as `auth.revocationFile`.
  - **A `promote` rule may reduce first**: `keepTopN`/`minSignificance` choose what crosses (the
    rest are still drained), or `summarise` calls `SummariseMemories` on the edge, which needs
    `ollama.enabled` there and fails the event loudly if it is absent.
  - **A `promote` rule may also rewrite what crosses.** A `set` block carries CEL expressions for
    `significance`, `group`, `metadata` (and `name`/`description` on the event), evaluated per event
    and per memory, so the edge can **re-rank** what it admits rather than only admit it —
    significance being the number the central store's whole decay model runs on. Only the promoted
    copy is touched, never the edge, which is drained regardless. The mutation runs **before** any
    reduction, so `keepTopN` ranks by the score the rule just set; values are bounds-checked against
    what the target would accept (a bad one fails the event loudly and leaves it on the edge rather
    than promoting it at a weight the file rejected); and `metadata` is **merged** over what the
    record carries, since CEL has no map union and stamping one provenance label is the common case.
  - **An edge must be configured not to forget.** Default consolidation settings will evict the
    memories of an event before the rules ever see it; set `consolidation.minimumRetentionInDays`
    above the longest an event stays open. See the docs — this is the one thing to get right.
- **`GetMemories` can filter by event.** New `event_id` and `has_event` fields on
  `GetMemoriesRequest`, exposed as `hippo memory list --event/--has-event` and on the MCP bridge's
  `list_memories`. Previously the only way to read an event's memories was `GetEventById` with
  `memories: true`, which returns every one of them in a single message and overruns the receive
  frame on a large event; this composes with `limit`/`offset` and every other filter. `has_event`
  exists alongside it because an event-less memory stores an empty `event_id`, which is also that
  filter's "no bound" value — the same reason `recalled` exists alongside `recall_count_max`.
- **Group scoping — a token can be restricted to particular `group` labels.** Authorisation tiers say
  what a caller may do; nothing said which records they may do it to, so any writer in a shared store
  could read and delete every other team's memories. A token may now carry a `groups` claim naming
  the group labels whose records it can reach. New keys `auth.groupsClaim` (default `groups`, for an
  identity provider that names the claim differently) and `auth.requireGroupScope`; `--mint-token`
  gains `--group`; `WhoAmI` gains `groups` and `group_scoped`, which the console, the `hippo` CLI and
  the config wizard all surface. Documented under
  [Group scoping](docs/configuration.md#group-scoping).
  - **Inert until tokens carry the claim, so every existing deployment is unchanged.** There is no
    schema change, no migration, no index rebuild and no OpenSearch reindex: the scope is the
    existing `group_name` column, which is already in the covering index, both search backends and
    the archive. An unscoped token behaves exactly as every token did before.
  - **An empty scope means the whole store**, so an unscoped token is the _most_ privileged shape a
    token has, not the least. `auth.requireGroupScope` turns its absence into a rejection — worth
    setting once a store is partitioned, since a provider that stops emitting the claim would
    otherwise hand every caller everything while every request succeeded.
  - For a scoped caller: listings, searches and their `total_count` are narrowed; records outside the
    scope report `NotFound` rather than `PermissionDenied` (which would confirm they exist); writes
    are stamped with the caller's group, and cannot be moved out of it; both ends of a link must be
    in scope, with edges reaching outside dropped from responses; `Export`/`Transfer`/`Clear` walk
    only that partition; and `Purge`, `Sleep` and `PreviewConsolidation` are refused, all three
    acting on the whole store.
  - **Pre-existing records carry no group and are invisible to a scoped token.** Stamp them with an
    `UPDATE` before issuing scoped tokens against an existing store — see the documentation.
  - **It is a soft partition, not isolation**, and the difference is documented at
    [the trust boundary](docs/operations.md#group-scoping-and-the-trust-boundary). The decay dynamics
    stay store-global, so a busy group still affects what another forgets and there is no per-group
    capacity target; `link_significance` is a scope-blind aggregate, so a cross-group link raises an
    item's significance regardless of who can read the other end. Hard isolation remains one instance
    per tenant. The reasoning, and what a full tenant model would have cost, is recorded as TODO 60.1.

- **Event-source bridges: `--subject-metadata-key`.** Records the broker subject/topic as a metadata
  label as well as (or instead of) using it as the group. Empty by default, so an existing bridge is
  unchanged. It exists because `--group-from-subject` is on by default and a group-scoped token may
  only write the groups it holds — the two are mutually exclusive, and without this the subject had
  nowhere else to go. Pair `--group <token's label> --group-from-subject=false
--subject-metadata-key subject` to keep the routing information as a filterable label. See
  [Event sourcing](docs/eventsource.md).

- **Memory and event metadata — tags and key-value attributes.** `group` was the only classification
  on a memory, one freeform 128-character string doing the work of several dimensions at once, so
  applications either packed a delimited string into it or buried the classification in the body.
  `Memory` and `Event` now carry a `map<string, string> metadata` alongside it, filterable on
  `GetMemories`, `GetEvents`, and `SearchMemories`. Documented under
  [Metadata](docs/api.md#metadata).
  - **Bounded, and the bounds are constants rather than configuration**: 32 keys, 64-byte keys
    matching `[A-Za-z0-9][A-Za-z0-9._:/-]{0,63}`, 512-byte values, 4096 bytes serialised in total.
    Unbounded metadata is a body by another name, so the serialised size **counts toward
    `memory.limit.sizeBytes`** and toward the store's byte accounting — it contributes to capacity
    pressure and to what eviction reclaims, rather than escaping both.
  - **Filters are repeated `key=value` strings, not a map**, because `GetMemories`/`GetEvents` are
    HTTP `GET` routes and a map cannot be bound from a query string. Every pair must match. On
    `SearchMemories` the filter is applied inside the index, like `group`, so it narrows the
    candidates ranking sees rather than trimming an already-truncated page. The predicates are
    **unindexed**, exactly as the `group` filter is.
  - **Stored as a nullable JSON column** on all three drivers, added in place on first startup.
    Nullable rather than defaulting to `''` deliberately: SQLite's `json_extract` raises "malformed
    JSON" on an empty string, so an `''`-defaulted column would make the first metadata-filtered
    query fail against every row written before the upgrade. Round-trips through
    `Export`/`Import`/`Transfer`.
  - Exposed on the `hippo` CLI (`--metadata k=v`, repeatable), the MCP bridge (`store_memory`,
    `update_memory`, `create_event`, and the three list/search tools), the web console, the
    event-source bridges (an explicit header allowlist or prefix, never copy-all), and the Obsidian
    plugin (named frontmatter keys plus fixed labels).
  - Metadata is **never** emitted as a metric, span, or log attribute — it is client-supplied and
    unbounded in cardinality.

- **`clear_metadata` and `clear_group` on `UpdateMemory`/`UpdateEvent`.** Every updatable field
  reads its zero value as "leave unchanged", and an absent map is indistinguishable from an empty
  one on the wire, so neither metadata nor a group label could be removed once set — only replaced.
  These two write-only flags close that gap. Metadata otherwise **replaces** the stored map
  wholesale on update; there is no per-key merge.

- **Recall-state filters on `GetMemories`** — `recalled`, `recall_count_min`/`_max`,
  `time_recalled_min`/`_max`, `is_summary`, and `is_binary`, over columns the store already
  maintained but never exposed. `recalled`, `is_summary` and `is_binary` are the tri-state `Bool`
  rather than plain booleans, since an unset proto3 `bool` and an explicit `false` are the same
  value on the wire. `recalled=FALSE` is what answers "what have I never recalled?" — the count
  range cannot, because `0` means "no bound" everywhere in this API. `time_recalled_min`/`_max` ask
  only about memories that have been recalled, so an upper bound does not sweep in every
  never-recalled memory (whose `time_recalled` is `0`).

- **Memory-to-memory links** — an associative graph over memories, the on-thesis capability the
  service had been missing. A link is directed, carries its own significance, and raises the
  effective significance of **both** ends with diminishing returns, so a well-connected memory
  decays more slowly. Three parts:
  - `LinkMemories` / `UnlinkMemories` / `GetMemoryLinks`, and the same three for events
    (`LinkEvents` / `UnlinkEvents` / `GetEventLinks`). Both ends must exist — links cannot dangle —
    and a link is removed automatically when either end is forgotten.
  - **Spreading activation**: `consolidation.linkRecallPropagation` (0–1, default 0 = off) advances
    a recalled memory's direct neighbours' decay clocks a fraction of the way to now, so recalling
    one thing keeps its associates alive. Their recall counts are never touched, so ranking and the
    recall term keep their existing meaning.
  - **Associative retrieval**: `include_linked` on `RecallMemories` and `SearchMemories`, and a
    `linked_to` filter on `GetMemories`, all one hop.

  Exposed on the `hippo` CLI (`memory link|unlink|links`, `event link|unlink|links`), the MCP bridge
  (`link_memories`, `unlink_memories`, `get_memory_links`), and the web console's memory table.
  Links round-trip through `Export`/`Import`/`Transfer`; the import applies them in a second pass
  once every row exists, so a link whose target appears later in the archive is not lost.

- `CHANGELOG.md` (this file), backfilled over every release, and the compatibility policy above.
- A `proto-breaking` CI job running `buf breaking` on `contract/hippocampus.proto` against the
  previous release tag (`contract/buf.yaml`), so an accidental contract break fails CI.
- `PreviewConsolidation` — a read-only dry run of a sleep cycle (`GET /v1/sleep/preview`,
  `hippo sleep --dry-run`) reporting what would be forgotten and deleting nothing.
- `ExplainConsolidation` — per-memory decay transparency: computed value, the pressure-scaled
  threshold, the retention/minimum-age overrides, days until forgotten, and the current decay
  curve. The web console gained a **Decay** tab that renders it and computes no decay maths of its
  own.
- Built-in content search on the SQLite driver, via an FTS5 index maintained inside the primary
  write. `SearchMemories` now works out of the box on the default deployment instead of failing
  closed when OpenSearch is not configured.
- Semantic and hybrid search (`SearchMemories`' `mode`) over an OpenSearch k-NN index, with a text
  embedder (`ollama.embedding.*`). OpenSearch-only; keyword remains the default, so existing
  callers are unchanged.
- Search ranking that blends a memory's significance and recall count with relevance
  (`search.significanceWeight`, `search.recallWeight`).
- RPC-level RED metrics — `hippocampus.rpc.requests` and `hippocampus.rpc.duration`, on both the
  gRPC and gateway transports — plus a **Requests (RED)** row on the dashboard.
- Shipped alert rules: `deploy/observability/prometheus-alerts.yaml` (portable Prometheus) and the
  same ten rules as Grafana-managed rules provisioned into the compose observability profile.
- Rate limiting (`rateLimit.*`, off by default): a hierarchy of token buckets — an instance-wide
  ceiling, one bucket per authorisation tier, one per caller — of which a request must pass every
  level that has a rate. Both transports share the buckets. The global ceiling is enforced ahead of
  token verification; the tier and client levels after it, since both need to know who is calling. A
  refused request gets `ResourceExhausted`/`429` with a retry-after, counted by
  `hippocampus.ratelimit.rejected` and classified as a client fault so the server-error alert does
  not fire on your own protection working.
- `docs/clients.md` — how to generate a client in a language other than Go, from either the proto or
  the OpenAPI document, with the API behaviour (quiet rejection, recall-is-a-write, int64-as-string)
  a generated stub does not convey. No packages are published for other languages yet.

- An inter-process storage lock on the `sqlite` driver: a `hippocampus.lock` file in
  `storage.directory`, held exclusively for the process lifetime. A second instance pointed at the
  same directory now refuses to start, naming the holder, instead of silently running a second
  forgetting schedule against one store. Read-only opens (`--backfill-search` against OpenSearch, an
  operator's `sqlite3` shell) take no lock and are unaffected.

### Changed

- **The embedded console is now four files rather than one, and is served under a strict
  Content-Security-Policy.** `index.html`, `styles.css`, `app.js` and `lib.js` — still no bundler
  and no build step, still embedded in the binary. The split is what makes
  `script-src 'self'; style-src 'self'` without `unsafe-inline` possible: every handler is a
  `data-act` attribute routed through one table, and every dynamic style goes through the CSSOM.
  An injected inline `<script>` no longer executes, which is the shape the console's one stored
  XSS took.
  - It is also what makes the JavaScript testable. `cmd/hippocampus/webuitest` runs `lib.js` under
    node's built-in test runner with **no dependencies** — no lockfile, no `node_modules` in a Go
    source tree — alongside drift guards pairing every control with a handler, every lib function
    with its import, and every embedded asset with a route and both middleware allow-lists.
  - The console's assets are revalidated by ETag rather than never cached, so a navigation costs
    two 304s instead of re-transferring them; the entry document stays `no-store`.
- **Controls disable themselves while their own request is in flight**, and a progress bar reports
  the requests no control started. Previously only sign-in did.
- **Search results gained "Show more" rather than pagination**, deliberately. `SearchMemories`
  over-fetches and then truncates, so a second page is a separately ranked query whose candidate set
  can differ — and a _reinforcing_ search recalls exactly the page it returns, so paging would
  reinforce a second set of memories, resetting their decay clocks, as a side effect of navigating a
  list. Re-running with a larger limit keeps it one query, one ranking, one reinforcement set.

- First run after a clone no longer needs a config file: an absent `./config.json` starts the
  service on built-in defaults (a `--config_file` given explicitly must still exist).
- **A memory's body (and an event's description) now gets a row of its own** in the web console's
  tables, spanning the width beneath the record's metadata, rather than competing for width as a
  column — where a single long unbreakable neighbour left it wrapping one word per line. Ids in the
  tables are middle-truncated with the full value on the tooltip and behind a copy button.
- The web console presents a **sign-in card in place of the console** when authentication is on and
  no session has resolved — on first load, after **Sign out**, and when a token is refused. The
  header's always-present bearer-token box is gone; the token is entered on the card instead. Purely
  a console change: the server enforced (and still enforces) authorisation on every RPC regardless of
  what the page shows.
- **The web console shows compact ages instead of absolute datetimes**, with the exact timestamp on
  the tooltip. Age since the last recall is what every consolidation method actually runs on, so it
  is the number that says whether a row is near being forgotten; it is also the narrowest form of the
  widest column in those tables.
- **Summarise buttons in the console's event view** — one calling `ReplaceMemoriesWithSummary` with
  text you write, one calling `SummariseMemories` and shown only where the embedded LLM is
  configured. Both confirm first, naming how many memories go. They live in the event view rather
  than on an events-list row because the operation replaces every memory of the event, and that is
  the one place the console shows what is about to go.
- Tidied the console's memory filter: the timestamp from/to controls are a matched pair on a row of
  their own.
- **The console hides controls this deployment cannot serve**, extending what it already did for the
  search-mode picker and the LLM summarise button. On a replica the whole Decay tab is absent — nav
  button included — along with the tables' per-row Value column and the summarisation-candidates
  card, since every one of them is served by an RPC a replica refuses; the forgotten-log panel
  appears only where `consolidation.tombstones.enabled` is set. An operator seeing no Decay tab is
  looking at a replica.
- **The console's create and filter cards are full width** on the Memories and Events tabs, matching
  the search card, instead of sharing a half-width two-column grid.
- **Enter runs the card it is typed in** on the Search, Memories and Events tabs — search, create,
  filter, and add-link. None of those cards is a `<form>`, so Enter previously did nothing and every
  field had to be left by hand to reach its button. A memory body and an event description still
  take Enter as a newline, and the two destructive forms (the summary that replaces an event's
  memories, and clearing the forgotten log) are deliberately left out.
- **The console's cards no longer name the endpoint they call.** Each blurb says what the card does
  and stops there; a reader after the API has `/v1/openapi.json`. What stays in `<code>` is what an
  operator would have to change — the config keys, and the `--mint-token` invocation.
- **An opened event now stands first on the console's Search tab** and is scrolled to, rather than
  appearing between the search form and the results — it arrives by navigation from another tab, so
  it has nothing to do with the query it was sitting under. The links panel is scrolled to for the
  same reason.
- **A table row's action buttons stay inside the card at any width**, pinned to the right edge of the
  scroll container while the rest of the row scrolls beneath them. These tables have a min-content
  width that no styling removes, so a narrow-enough viewport scrolls them — and what went out of view
  was always the buttons, being last.
- **A summarisation-candidates card on the console's Events tab** — the scan's list, refreshed on
  demand, with each event opening into the view the summarise buttons are in.

### Fixed

- **A group-scoped administrator was shown no forgotten log**, though the service serves them one.
  `GetForgottenMemories` is scope-filtered rather than refused to a scoped caller — a tombstone
  carries its memory's group, so a scoped admin sees exactly their own partition's losses — but the
  console gated it on a capability that folded "unscoped" into "is an admin", the test that
  `PreviewConsolidation` genuinely needs. The two are now separate, and the console hides only what
  the service will actually refuse.
- **`formatBytes` reported an unknown figure as `0 B`.** `Number(value || 0)` folded `NaN` to zero
  before the guard that existed to catch it, so a missing byte count read as a fact about the store
  rather than as a missing number. Absent (an unset field, genuinely zero) and unknown are now
  distinguished.
- **A status poll arriving during startup could report "no timed cycle" on an instance that has
  one** — the sleep timer is created inside its own goroutine, leaving a window before it was
  scheduled. The next-cycle time is now recorded before the goroutine launches.

- **A Bluesky bridge wedged permanently on a record the store already held.** Every adapter acks
  after the write, so a redelivery re-presents a memory that was already stored — and with the id
  derived from the upstream record, that is a duplicate rather than a second copy. `Store.Handle`
  returned the resulting `AlreadyExists` as an error, so the adapter was told a frame it could never
  store had not been handled: it retried, dropped the connection, resumed from the same cursor, and
  was handed the same record again. The hosted demo sat in that loop for hours, reading nothing after
  the poisonous frame and so reinforcing nothing at all. `Handle` now counts it as handled, reported
  as `hippocampus.bridge.messages{outcome="exists"}` — success, but distinct from `stored`, since a
  bridge whose whole stream is duplicates is doing nothing. The Bluesky consume loop additionally
  **skips** a frame the service can never accept (`InvalidArgument`, `AlreadyExists`,
  `Unimplemented`, `OutOfRange`) instead of replaying it; every other code, including the
  `FailedPrecondition` of an event consolidated mid-write, keeps its replay.
- **A thread's opening post was missing from the thread**, in two places. In the bridge core, a
  nested memory carries no `event_id` of its own (the service stamps the event's on it), so
  `HandleEvent`'s already-exists fallback — which stores them individually — wrote them with no
  event at all; the very case that fallback exists for, a post arriving after a reply has opened its
  event, produced a thread without its own opening post. In the Bluesky feed path, a post that was
  not a reply opened no thread at all under `--events thread` (only the firehose path did), so its
  event appeared later, opened by a captured reply, holding every reply except the post they
  answered. Both now stamp the event they belong to; a feed post's own thread is named from its
  text.
- **The console's scroll-to-top did nothing under `prefers-reduced-motion: reduce`.** Chrome does
  not shorten a `behavior: "smooth"` scroll when reduced motion is requested — it drops it — so
  editing a memory or an event from a row left the page exactly where it was, for precisely the
  reader who most needs it to have moved. The behaviour is now chosen from the media query.
- **Summarising through either RPC left the event in the candidate cache**, so
  `GetSummarisationCandidates` went on offering an event the service had just condensed until the
  next sleep cycle refreshed the scan. Only the auto-summarisation path pruned; the pruning now lives
  at the chokepoint both paths share.
- **Opening an event in the web console destroyed the search results.** The event view was written
  into the search results panel, and an event id is clickable in all three tables — so opening one
  from the Events or Memories tab silently replaced a search that had been run, and returning to the
  Search tab found that single event in place of the results. The event now has a card of its own.

- **A Bluesky feed poll stalled permanently on the first reply in a page.** Under `--events thread`
  the Transformer puts a reply's memory in its thread root's event, and the service refuses a memory
  naming an event it does not hold — but only the firehose path ever opened that event, never the
  feed path. The refusal then aborted the write of the whole page, so every post after the reply went
  unwritten; since a poll returns the same page each time, the next tick stopped at the same post and
  the store never grew past it. Two fixes: the feed path now opens a reply's thread before writing
  it, as the firehose path always has, and a batch write **skips** a memory whose event is missing
  rather than aborting on it (counted as `hippocampus.bridge.memories{outcome="orphaned"}`).

- **A Bluesky feed backfill failed permanently if the IdP was still booting.** The startup seed ran
  once, with no retry, so a bridge starting alongside its identity provider could not mint a token,
  logged one warning, and ran unseeded until somebody restarted it — which any stack bounce could
  cause. The seed is now retried past a cold start (eight attempts over about four minutes) before
  giving up and leaving the store to fill from live polling.

- **The `/v1` gateway returned `404` for any id containing a `/`.** Every by-id path — `GET`/`PATCH`
  a memory or event, the link endpoints, `EndEvent`, `UpdateEventSignificance`, the two summary
  routes — failed for an id the caller had percent-encoded correctly, because the gateway matched
  routes against the already-unescaped path: a `%2F` inside an id had by then become a real
  separator and split the id across path segments. Ids are caller-chosen and full of slashes in
  practice (an `at://` URI is what the event-source bridges write), so this took out most of the web
  console's row actions on any Bluesky-sourced store, and the same calls from the `hippo` CLI's HTTP
  transport and the Obsidian plugin. The gRPC surface was never affected. No client change is
  needed: an id must be encoded as one path segment, as those clients already did.

- **The OpenSearch index dropped every memory whose id contains a `/`.** The document id went into
  the `/<index>/_doc/<id>` request path unescaped, so an `at://` URI became six path segments and
  the cluster answered `no handler found for uri ... and method [PUT]`. Indexing and deleting missed
  alike: nothing failed visibly on the write path, the index simply stayed empty of those memories
  and `SearchMemories` returned nothing for them — which on a Bluesky-sourced store is nearly
  everything, since the bridge ids each memory by the post's `at://` URI. The id is now
  path-escaped; it is still stored and returned by the cluster in its original form, so hits still
  name a memory the primary store can be asked for and no reindex is needed beyond re-indexing the
  memories that never landed (`--backfill-search`). The one shape escaping cannot survive — a
  cluster address carrying a path prefix, where the client library rebuilds the path from its
  decoded form — is now warned about at startup. This is the same class of fault as the gateway
  `404` above, in a different layer.

- **A bridge truncating a body with `--max-body-bytes` could produce a message that never delivered.**
  The truncation sliced raw bytes, so a multi-byte character straddling the budget was cut in half
  and the memory failed to _marshal_ (`string field contains invalid UTF-8`) before it ever reached
  the service. Because the fault was in the message rather than the service, redelivery could not
  clear it: on an at-least-once broker it was a poison message nacked and retried forever. The cut
  now backs up to a rune boundary. Affected all bridges, on any non-ASCII payload; found by running
  the new Bluesky bridge, whose posts are full of emoji, against the live firehose.

## [0.23.0] - 2026-08-05

### Added

- Optional compression of memory bodies (`storage.compression`, on by default). Compression lives
  entirely at the storage boundary, the decision is recorded per row so the setting is safe to
  change on a live store, and a body is kept compressed only when it actually came out smaller.

## [0.22.0] - 2026-08-05

### Added

- A browser-based configuration and deployment wizard (`cmd/config-wizard`) that builds a
  `config.json`, an environment file for the secret-typed keys, and Compose/Kubernetes/systemd/
  launchd artefacts entirely in the browser.

## [0.21.0] - 2026-08-05

### Added

- Homebrew installation via the `fastbean-au/homebrew-tap` formulae, auto-bumped on release.
- Native systemd deployment with `.deb`/`.rpm` packaging.
- A macOS launchd LaunchAgent.

### Changed

- `docker/` moved to `deploy/compose/`.

## [0.20.0] - 2026-08-04

### Added

- The `hippo` command-line client (`integrations/cli`), covering the full RPC surface over either
  transport.
- Kubernetes kick-start manifests (`deploy/k8s`, Kustomize base plus SQLite and Postgres overlays).

### Changed

- The MCP bridge moved to `integrations/mcp` and became its own Go module, keeping its dependency
  tree out of the root build.

### Fixed

- Broker-readiness gating in the event-source CI job.

## [0.19.0] - 2026-08-03

### Added

- Event-sourcing broker bridges for NATS, MQTT, RabbitMQ, and Kafka
  (`integrations/eventsource`), each consuming from a broker and storing every message as a memory.

### Fixed

- Integration docs: port alignment and container networking.

## [0.18.0] - 2026-08-01

### Changed

- Australian English throughout the repo, in documentation _and_ code — identifiers, config keys,
  proto fields, and metric names. Protocol and standard-library terms (the `Authorization` header,
  `codes.Canceled`, and so on) are untouched.
- Multi-arch container builds, and OCI support alongside Docker.
- The hosted showcase moved to the separate `hippocampus-demo-site` repository.

## [0.17.0] - 2026-07-28

### Added

- Optional embedded-LLM summarisation (`ollama.*`, off by default): the `SummariseMemories` RPC
  generates and replaces in one call, and `ollama.autoSummarise` does the same for the sleep
  cycle's candidates.

## [0.16.0] - 2026-07-28

### Added

- Server-side OIDC login (`auth.oauth2`) for SSO, as a confidential client.
- A lite showcase stack sized for a GCP e2-micro, and a phased walkthrough for it.

## [0.15.0] - 2026-07-27

### Added

- OIDC Authorization Code + PKCE login in the web console, with front-channel configuration served
  at `/ui/config`.
- Showcase compose stacks with Keycloak realm provisioning, and a GCP deployment runbook.

### Fixed

- IdP role claims are resolved literally before being resolved as a nested path.

## [0.14.3] - 2026-07-26

### Added

- `update_memory` and `delete_memories` on the MCP bridge.

## [0.14.2] - 2026-07-26

### Fixed

- A minor bug in the search response.

## [0.14.1] - 2026-07-26

### Added

- The `WhoAmI` RPC, reporting the caller's effective authorisation tier, and a role-aware web
  console that hides the controls the caller may not use.

## [0.14.0] - 2026-07-26

### Added

- Role-based authorisation: a `reader` ⊂ `writer` ⊂ `admin` tier hierarchy with one policy table
  enforced identically on both transports.
- A release workflow for the Obsidian plugin, and OTEL collector image plus plugin assets published
  on release.

## [0.13.0] - 2026-07-25

### Changed

- The integrations became first-class components, each with its own build, tests, and release
  artefacts.

## [0.12.0] - 2026-07-25

### Added

- An Obsidian plugin (`integrations/obsidian`) using Hippocampus as a vault memory layer over the
  `/v1` gateway.

### Changed

- `otel/` moved under `integrations/`.

## [0.11.0] - 2026-07-24

### Added

- An OpenTelemetry Collector logs exporter that turns each log record into a `StoreMemory` call.

## [0.10.1] - 2026-07-23

### Fixed

- The MCP bridge's release packaging.

## [0.10.0] - 2026-07-23

### Added

- `hippocampus-mcp`, a Model Context Protocol server bridging an LLM host to a running instance,
  with its own image and release binaries.

## [0.9.2] - 2026-07-22

### Changed

- Test coverage, and a README layout fix.

## [0.9.1] - 2026-07-22

### Changed

- An overhauled README, and observability on by default in the demo script.

## [0.9.0] - 2026-07-21

### Added

- An extremum option on `GetMemories`, mirroring `GetEvents`.

## [0.8.1] - 2026-07-20

### Changed

- `run()` extracted from `main()` so the serve lifecycle is covered by tests.

## [0.8.0] - 2026-07-20

### Added

- A default query timeout at the storage layer (`storage.queryTimeoutSeconds`).

### Changed

- A hardened security surface and a broadened set of configurable keys, from the production
  readiness review.

### Fixed

- Correctness fixes across the sleep cycle and the RPC surface.

## [0.7.0] - 2026-07-19

### Added

- An optional extremum on `GetEvents`, returning the events at the highest significance.
- TLS configuration for the OpenSearch connection, plus a secured reference deployment.

## [0.6.1] - 2026-07-18

### Fixed

- A failing MySQL test.

## [0.6.0] - 2026-07-18

### Added

- `consolidation.minimumRetentionInDays` — a hard retention floor that neither value-based
  consolidation nor capacity eviction may take a memory inside.

## [0.5.0] - 2026-07-18

### Added

- Relative significance placement: rank a memory or event between two existing values rather than
  choosing a number.

## [0.4.0] - 2026-07-18

### Added

- Self-healing content search: the index worker retries transient cluster failures, and the
  consolidating instance runs a periodic reconciliation sweep.

### Fixed

- MySQL write deadlocks are retried, and exhausted conflicts map to `Aborted` so clients re-issue
  rather than read a lost write.

## [0.3.0] - 2026-07-17

### Added

- Throughput-sweep tooling and a high-throughput performance write-up.

### Fixed

- `autoSleep` livelock: with `consolidation.walTriggerBytes` set, the timed sleep cycle never fired.
- The demo generator's burst clock-skew overflow, and an event-not-found mapping to `NotFound`.

## [0.2.1] - 2026-07-17

### Added

- A demonstrations guide.

### Fixed

- The pre-commit hook, hardened.

## [0.2.0] - 2026-07-16

### Added

- HMAC signing-key rotation, and token/client revocation via a reloadable revocation list.

### Changed

- `context.Context` threaded through `db.Store`, so an RPC's deadline and cancellation reach the
  driver.

## [0.1.0] - 2026-07-16

The first tagged release. Hippocampus was already feature-complete at this point: memories and
events with significance-based decay, the six consolidation algorithms, the sleep cycle with
capacity eviction and summarisation candidates, SQLite/PostgreSQL/MySQL storage, the gRPC service
with its `/v1` gateway, optional JWT auth and TLS, the OpenSearch secondary index, the archive and
transfer RPCs, the embedded web console, and OTEL tracing and metrics.

This release added the delivery and production-readiness layer around it:

### Added

- A tag-driven release workflow publishing to GHCR, and `RELEASE.md`.
- Version identification (`--version`, the `/healthz` body, the OTEL `service.version` attribute).
- Per-request logging, stats caching, and bounded transfer manifests.
- Connection-pool limits, byte-aware `Transfer` batching, and `HIPPOCAMPUS_*` environment overrides
  for secrets.
- An otel-lgtm observability profile with a provisioned dashboard, and bytes-evicted and body-size
  metrics.

### Fixed

- A stored XSS in the embedded web console, plus auth, TLS, and gateway hardening.

[obsidian-repo]: https://github.com/fastbean-au/hippocampus-obsidian
[llamaindex-repo]: https://github.com/fastbean-au/hippocampus-llamaindex
[otel-repo]: https://github.com/fastbean-au/hippocampus-otel-collector
[Unreleased]: https://github.com/fastbean-au/hippocampus/compare/v0.52.1...HEAD
[0.52.1]: https://github.com/fastbean-au/hippocampus/compare/v0.52.0...v0.52.1
[0.52.0]: https://github.com/fastbean-au/hippocampus/compare/v0.51.1...v0.52.0
[0.51.1]: https://github.com/fastbean-au/hippocampus/compare/v0.51.0...v0.51.1
[0.51.0]: https://github.com/fastbean-au/hippocampus/compare/v0.50.0...v0.51.0
[0.50.0]: https://github.com/fastbean-au/hippocampus/compare/v0.49.0...v0.50.0
[0.49.0]: https://github.com/fastbean-au/hippocampus/compare/v0.48.0...v0.49.0
[0.48.0]: https://github.com/fastbean-au/hippocampus/compare/v0.47.1...v0.48.0
[0.47.1]: https://github.com/fastbean-au/hippocampus/compare/v0.47.0...v0.47.1
[0.47.0]: https://github.com/fastbean-au/hippocampus/compare/v0.46.0...v0.47.0
[0.46.0]: https://github.com/fastbean-au/hippocampus/compare/v0.45.0...v0.46.0
[0.45.0]: https://github.com/fastbean-au/hippocampus/compare/v0.44.0...v0.45.0
[0.44.0]: https://github.com/fastbean-au/hippocampus/compare/v0.43.0...v0.44.0
[0.43.0]: https://github.com/fastbean-au/hippocampus/compare/v0.42.0...v0.43.0
[0.42.0]: https://github.com/fastbean-au/hippocampus/compare/v0.41.0...v0.42.0
[0.41.0]: https://github.com/fastbean-au/hippocampus/compare/v0.40.1...v0.41.0
[0.40.1]: https://github.com/fastbean-au/hippocampus/compare/v0.40.0...v0.40.1
[0.40.0]: https://github.com/fastbean-au/hippocampus/compare/v0.39.0...v0.40.0
[0.39.0]: https://github.com/fastbean-au/hippocampus/compare/v0.38.3...v0.39.0
[0.38.3]: https://github.com/fastbean-au/hippocampus/compare/v0.38.2...v0.38.3
[0.38.2]: https://github.com/fastbean-au/hippocampus/compare/v0.38.1...v0.38.2
[0.38.1]: https://github.com/fastbean-au/hippocampus/compare/v0.38.0...v0.38.1
[0.38.0]: https://github.com/fastbean-au/hippocampus/compare/v0.37.0...v0.38.0
[0.37.0]: https://github.com/fastbean-au/hippocampus/compare/v0.36.1...v0.37.0
[0.36.1]: https://github.com/fastbean-au/hippocampus/compare/v0.36.0...v0.36.1
[0.36.0]: https://github.com/fastbean-au/hippocampus/compare/v0.35.1...v0.36.0
[0.35.1]: https://github.com/fastbean-au/hippocampus/compare/v0.35.0...v0.35.1
[0.35.0]: https://github.com/fastbean-au/hippocampus/compare/v0.34.0...v0.35.0
[0.34.0]: https://github.com/fastbean-au/hippocampus/compare/v0.33.2...v0.34.0
[0.33.2]: https://github.com/fastbean-au/hippocampus/compare/v0.33.1...v0.33.2
[0.33.1]: https://github.com/fastbean-au/hippocampus/compare/v0.33.0...v0.33.1
[0.33.0]: https://github.com/fastbean-au/hippocampus/compare/v0.23.0...v0.33.0
[0.23.0]: https://github.com/fastbean-au/hippocampus/compare/v0.22.0...v0.23.0
[0.22.0]: https://github.com/fastbean-au/hippocampus/compare/v0.21.0...v0.22.0
[0.21.0]: https://github.com/fastbean-au/hippocampus/compare/v0.20.0...v0.21.0
[0.20.0]: https://github.com/fastbean-au/hippocampus/compare/v0.19.0...v0.20.0
[0.19.0]: https://github.com/fastbean-au/hippocampus/compare/v0.18.0...v0.19.0
[0.18.0]: https://github.com/fastbean-au/hippocampus/compare/v0.17.0...v0.18.0
[0.17.0]: https://github.com/fastbean-au/hippocampus/compare/v0.16.0...v0.17.0
[0.16.0]: https://github.com/fastbean-au/hippocampus/compare/v0.15.0...v0.16.0
[0.15.0]: https://github.com/fastbean-au/hippocampus/compare/v0.14.3...v0.15.0
[0.14.3]: https://github.com/fastbean-au/hippocampus/compare/v0.14.2...v0.14.3
[0.14.2]: https://github.com/fastbean-au/hippocampus/compare/v0.14.1...v0.14.2
[0.14.1]: https://github.com/fastbean-au/hippocampus/compare/v0.14.0...v0.14.1
[0.14.0]: https://github.com/fastbean-au/hippocampus/compare/v0.13.0...v0.14.0
[0.13.0]: https://github.com/fastbean-au/hippocampus/compare/v0.12.0...v0.13.0
[0.12.0]: https://github.com/fastbean-au/hippocampus/compare/v0.11.0...v0.12.0
[0.11.0]: https://github.com/fastbean-au/hippocampus/compare/v0.10.1...v0.11.0
[0.10.1]: https://github.com/fastbean-au/hippocampus/compare/v0.10.0...v0.10.1
[0.10.0]: https://github.com/fastbean-au/hippocampus/compare/v0.9.2...v0.10.0
[0.9.2]: https://github.com/fastbean-au/hippocampus/compare/v0.9.1...v0.9.2
[0.9.1]: https://github.com/fastbean-au/hippocampus/compare/v0.9.0...v0.9.1
[0.9.0]: https://github.com/fastbean-au/hippocampus/compare/v0.8.1...v0.9.0
[0.8.1]: https://github.com/fastbean-au/hippocampus/compare/v0.8.0...v0.8.1
[0.8.0]: https://github.com/fastbean-au/hippocampus/compare/v0.7.0...v0.8.0
[0.7.0]: https://github.com/fastbean-au/hippocampus/compare/v0.6.1...v0.7.0
[0.6.1]: https://github.com/fastbean-au/hippocampus/compare/v0.6.0...v0.6.1
[0.6.0]: https://github.com/fastbean-au/hippocampus/compare/v0.5.0...v0.6.0
[0.5.0]: https://github.com/fastbean-au/hippocampus/compare/v0.4.0...v0.5.0
[0.4.0]: https://github.com/fastbean-au/hippocampus/compare/v0.3.0...v0.4.0
[0.3.0]: https://github.com/fastbean-au/hippocampus/compare/v0.2.1...v0.3.0
[0.2.1]: https://github.com/fastbean-au/hippocampus/compare/v0.2.0...v0.2.1
[0.2.0]: https://github.com/fastbean-au/hippocampus/compare/v0.1.0...v0.2.0
[0.1.0]: https://github.com/fastbean-au/hippocampus/releases/tag/v0.1.0
