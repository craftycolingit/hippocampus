# Operations & deployment guide

This guide covers running Hippocampus in production: the deployment model, choosing and sizing a
storage backend, capacity tuning, backup and migration, shutdown, observability, and security. For
the exhaustive list of configuration keys see
[Configurability](configuration.md#configurability); for a first run see
[Getting started](getting-started.md).

## Deployment model: one consolidating instance per store

Exactly one running process may run **consolidation** against a given store at a time, because
decay, capacity pressure, and eviction are global dynamics over the whole store. The primary scaling
model is therefore **one instance per store** (per tenant, per subsystem, per device) — not multiple
instances over one database. On the server drivers, that store can instead be shared by one
consolidating instance plus read/write replicas; see
[Horizontal scaling with replicas](#horizontal-scaling-with-replicas) below.

Single ownership is enforced at startup, and a second _consolidating_ instance pointed at the same
store fails fast:

| Driver     | Store                                    | Exclusion mechanism                                                      |
| ---------- | ---------------------------------------- | ------------------------------------------------------------------------ |
| `sqlite`   | one database file in `storage.directory` | an exclusive OS lock on `hippocampus.lock` held for the process lifetime |
| `postgres` | the database named in the DSN            | a session-scoped `pg_advisory_lock` held for the process lifetime        |
| `mysql`    | the schema named in the DSN              | a session-scoped `GET_LOCK` held for the process lifetime                |

### The SQLite storage lock

SQLite's WAL mode deliberately permits several processes to write one database file, so nothing in
the storage engine itself would stop a second instance from running its own decay and eviction
schedule against the same store. A file-backed `sqlite` open therefore takes an exclusive operating
system lock (`flock` on Linux/macOS, `LockFileEx` on Windows) on a `hippocampus.lock` file beside the
database, and a second process pointed at the same `storage.directory` refuses to start, naming the
holder:

```text
another hippocampus instance already holds the storage lock on './data'
(held by pid 41207 host arrakis since 2026-08-06T05:59:08Z) - the sqlite driver is
single-instance, so give this instance its own storage.directory or move the store to the
postgres/mysql driver, which supports one consolidating instance plus replicas
```

Four things are worth knowing about it:

- **There is no stale lock to clear.** The lock is held by the kernel for as long as the process has
  the file open, so it is released the instant that process exits — including a `SIGKILL`, an OOM
  kill, or a crash. The file is left behind and still names the dead process; that text is
  diagnostics for the error message above and never the lock itself, so it can be ignored (and is
  emptied on a clean shutdown). **Never delete `hippocampus.lock` to "release" a lock** — it does
  nothing, and it removes the diagnostics.
- **It applies to every `sqlite` instance, not only consolidating ones.** SQLite cannot be shared
  between instances at all; `consolidation.enabled: false` on this driver means only that the one
  instance never consolidates, not that a second may join it. Sharing one store between instances
  requires `postgres` or `mysql` — see [Horizontal scaling with
  replicas](#horizontal-scaling-with-replicas).
- **Read-only tooling is exempt.** `--backfill-search` against an OpenSearch index, and an operator's
  `sqlite3` shell, open the database read-only, take no lock, and are unaffected by one being held —
  which is what keeps them safe to run beside a live service. The `--backfill-search` rebuild of the
  _SQLite_ content index is the exception: it writes to the service's own database, so it opens
  read-write, takes the lock, and now fails loudly instead of writing underneath a running instance.
- **It guards a directory, not a host.** Two instances with different `storage.directory` values do
  not contend; see [Running more than one instance on one
  host](#running-more-than-one-instance-on-one-host). A network filesystem is a poor place for a
  SQLite store for reasons that predate this lock, but note that the lock is only as reliable as
  that filesystem's lock support.

### Horizontal scaling with replicas

When a single store is too large for one instance, a `postgres`/`mysql` database can be shared:
start exactly one instance with `consolidation.enabled: true` (the default — it takes the lock above
and runs every sleep cycle) and any number of additional instances with `consolidation.enabled:
false`. A replica opens the shared database **without** the lock, serves the full read/write RPC and
HTTP surface, and never consolidates (the manual `Sleep` RPC returns `FailedPrecondition`). Because
only the one consolidating instance forgets, replicas cannot race it over the global decay/eviction
state.

Operational notes:

- Start the consolidating instance first so it owns schema creation and any in-place migration; the
  replicas assume the schema already exists. They are safe if you do not: the migration run takes a
  cross-instance lock, so instances starting together queue rather than racing one another's
  `ALTER TABLE`. Starting the consolidator first simply avoids the wait.
- Put a load balancer in front of all instances and route reads and writes to any of them. The one
  exception is the deferred `Clear` of an `Export` or `Transfer`: its manifest lives in the memory
  of the instance that produced it, whose id the response returns as `instance_id`. Send the
  `Clear` there, or use the RPC's own `clear` flag, which needs no second call. A `Clear` that
  reaches another instance is refused naming that instance.
- **Failover is a standby.** An instance with `consolidation.standby: true` (and
  `consolidation.enabled: false`) serves as a replica and asks for the consolidator lock every
  `consolidation.standbyPollSeconds` (15). When it wins, because the consolidator's session ended
  with its process, it starts the sleep cycle and everything only a consolidator runs: the search
  reconcile and outbox drain, callback dispatch and scheduled exports. It logs the takeover at `WARN`.
  **Run every instance as a standby** and the first to poll after a consolidator dies takes over,
  with no instance configured as the leader. An instance configured with `consolidation.enabled:
  true` and restarted after a standby took over would instead find the lock held and refuse to
  start. A promoted instance stays the consolidator for the life of its process.
- Without standbys the assignment is static. If the consolidating instance dies, **promote** a
  replica by restarting it with `consolidation.enabled: true`; it takes the now-free lock. Run
  every instance under a supervisor so a fail-stop is followed by a restart.
- SQLite cannot be shared, so `consolidation.enabled: false` there is not a scaling replica — it just
  yields an instance that never consolidates. Startup logs a warning to that effect.
- Each instance registers itself in the shared database every `topology.heartbeatSeconds`, so every
  instance can name its peers and report which of them holds the consolidator role
  (`hippo topology`, the console's **Deployment** tab). That is also what makes the failure mode
  this section's first paragraph invites — **every** instance started with
  `consolidation.enabled: false`, so nothing ever forgets and the store grows without bound — visible
  rather than silent: it is reported as a warning on the topology response and logged at `WARN`. The
  same registry reports the opposite fault, two instances claiming the role, which is what a broken
  lock or two tiers pointed at different databases looks like. See
  [Deployment topology](configuration.md#deployment-topology).
- Promoting a replica is therefore checkable: after the restart, `hippo topology` against any
  instance should name exactly one consolidator, and the promoted instance's own store node should
  report the lock as held by it.

### The instance-lock keepalive (server drivers)

The Postgres/MySQL lock lives on a dedicated pinned connection. Because both lock kinds are
session-scoped, anything that kills that session (a failover, a network reset, a connection-pooler
idle policy, MySQL's `wait_timeout`) would silently release the lock while the service kept running —
inviting a second instance to start and corrupt shared data. To prevent that, the service runs a
**keepalive**: every 60 seconds it pings the lock connection. The ping doubles as activity that keeps
the session from being reaped in the first place; if the session has died anyway, the service
attempts exactly one reacquisition and, if it cannot retake the lock, **exits immediately**
(`log.Fatal`) rather than run without it.

**Operational implication:** if a Postgres/MySQL-backed instance exits with a log line like
_"lost the single-instance lock and could not reacquire it"_, that is the safety mechanism working —
another instance holds the lock, or the database is unreachable. Investigate why the lock session
died (failover, network, an idle-timeout that outpaced the keepalive) and restart once the cause is
resolved. Run under a supervisor (systemd, Kubernetes, Docker restart policy) so a fail-stop is
followed by a clean restart.

## Validating a configuration before it starts

`--check-config` runs the service's own startup validation, reports everything wrong with the
configuration, and exits — without opening the store, dialling anything, or starting a server:

```sh
hippocampus --check-config -c config.json
```

```text
config:  config.json
driver:  postgres
status:  valid
```

On a bad configuration it reports **every** problem rather than the first, because a pre-flight tool
that surfaces one fault per run sends you around the restart loop once per mistake:

```text
config:  config.json
driver:  sqlite
status:  INVALID - 3 problem(s); the service would refuse to start

  - consolidation.unitsOfAgeInDays must be greater than 0, got 0
  - consolidation.method must be between 1 and 6, got 9
  - storage.directory must be set for storage.driver 'sqlite' (an empty directory selects the test-only in-memory database)
```

The exit status carries the verdict, so a deploy pipeline can gate on it without parsing anything,
and `--output json` renders the same report for one that wants the detail:

```sh
hippocampus --check-config --output json -c config.json
```

```json
{
  "status": "valid",
  "config_file": "config.json",
  "defaulted": false,
  "driver": "postgres",
  "problems": []
}
```

`status` is the field to branch on — `valid` or `invalid`. `problems` is always an array, never
`null`. `defaulted` is `true` when no configuration file was found at all, which is worth checking
in a pipeline: running on the built-in defaults is supported, so it passes validation, and a check
that passes says nothing about the file you meant to hand it.

Two things make it worth running rather than trusting the file to be right:

- **It checks the configuration the service would actually resolve**, not the file. viper's
  precedence is flag, then environment, then file, then default, so a `config.json` that is sound on
  its own can still be invalid once a container's `HIPPOCAMPUS_*` overrides are applied — and a key
  the file omits is checked at whatever the built-in default is. Run it in the environment the
  service will run in.
- **It is what catches a validation rule that tightened underneath you.** Rules are added between
  releases; 0.41.0 added one that a working, deliberate configuration did not satisfy. Upgrading a
  deployment is a good moment to run this against the new binary before the old container is
  replaced.

It touches no store and no network, so it is safe anywhere — beside a live instance, or in a build
step that has neither.

## Running as a service

The binary is a foreground process: it runs until it receives `SIGINT`/`SIGTERM`, then shuts down
gracefully (see [Graceful shutdown](#graceful-shutdown)). For anything past a manual run, put it
under a process supervisor that restarts it on failure and starts it at boot — the same supervision
the sections above assume. Point the supervisor's liveness check at `GET /livez` (`/healthz` is the
same endpoint under its older name). The examples
below run the compiled binary directly; the containerised path is instead a
[Compose stack or Kubernetes overlay](#containers-and-kubernetes).

On macOS or Linux the quickest supervised setup is Homebrew — `brew install
fastbean-au/tap/hippocampus` then `brew services start hippocampus`, which generates and manages the
launchd/systemd definition for you (the manual equivalents below are for a non-Homebrew install, or
when you want the full systemd hardening). The tap also carries the two client binaries, which need
no supervision: `fastbean-au/tap/hippocampus-cli` (the [`hippo` CLI](cli.md)) and
`fastbean-au/tap/hippocampus-mcp` (the [MCP bridge](mcp.md)). The service formula installs a default
embedded-SQLite config that is preserved across upgrades; see the
[tap repo](https://github.com/fastbean-au/homebrew-tap).

### macOS (launchd)

The repo ships a ready-to-use per-user LaunchAgent and macOS config under
[`deploy/launchd/`](../deploy/launchd/) (see its README for the install/manage commands). The
annotated version below shows the shape:

```xml
<?xml version="1.0" encoding="UTF-8"?>
<!DOCTYPE plist PUBLIC "-//Apple//DTD PLIST 1.0//EN" "http://www.apple.com/DTDs/PropertyList-1.0.dtd">
<plist version="1.0">
<dict>
    <key>Label</key>             <string>au.example.hippocampus</string>
    <key>ProgramArguments</key>
    <array>
        <string>/usr/local/bin/hippocampus</string>
        <string>-c</string>
        <string>/opt/hippocampus/config.json</string>
    </array>
    <key>RunAtLoad</key>         <true/>
    <key>KeepAlive</key>         <true/>
    <key>ProcessType</key>      <string>Background</string>
    <key>StandardOutPath</key>  <string>/opt/hippocampus/logs/out.log</string>
    <key>StandardErrorPath</key><string>/opt/hippocampus/logs/err.log</string>
</dict>
</plist>
```

`RunAtLoad` starts it at login and `KeepAlive` restarts it if it exits. Manage it with:

```sh
launchctl bootstrap gui/$(id -u) ~/Library/LaunchAgents/au.example.hippocampus.plist  # load + start
launchctl kickstart -k gui/$(id -u)/au.example.hippocampus                            # restart after upgrade/config change
launchctl bootout   gui/$(id -u) ~/Library/LaunchAgents/au.example.hippocampus.plist  # stop + unload
```

### Linux (systemd)

The release publishes `.deb`/`.rpm` packages (built from [`deploy/nfpm/`](../deploy/nfpm/)) that
install the binary, a hardened unit, and a default config in one step — the recommended path:

```sh
sudo dpkg -i hippocampus_<version>_amd64.deb      # Debian/Ubuntu
sudo rpm -i  hippocampus-<version>.x86_64.rpm     # RHEL/Fedora/SUSE

sudoedit /etc/hippocampus/config.json             # review before first start
sudo systemctl enable --now hippocampus
```

The package never auto-enables the service (you review the config first) and marks the config a
conffile, so your edits survive upgrades. The shipped unit
([`deploy/systemd/hippocampus.service`](../deploy/systemd/hippocampus.service)) runs under a
transient unprivileged user (`DynamicUser`, with `StateDirectory` owning `/var/lib/hippocampus`) and
carries the full sandbox — dropped capabilities, `NoNewPrivileges`, `ProtectSystem=strict`, private
tmp/devices, a `@system-service` syscall filter — the systemd counterpart to the k8s pod
`securityContext`. See [`deploy/systemd/README.md`](../deploy/systemd/README.md).

To install by hand instead, or on a distro without the packages, a minimal unit at
`/etc/systemd/system/hippocampus.service` is enough to get started (the shipped unit adds the
hardening above):

```ini
[Unit]
Description=Hippocampus
After=network-online.target
Wants=network-online.target

[Service]
ExecStart=/usr/local/bin/hippocampus -c /etc/hippocampus/config.json
Restart=on-failure
RestartSec=5
User=hippocampus
Group=hippocampus

[Install]
WantedBy=multi-user.target
```

`systemctl enable --now hippocampus` starts it and enables it at boot; `systemctl restart
hippocampus` after an upgrade. Run it as a dedicated unprivileged user that owns
`storage.directory`. If the store is on a server driver or an external content-search cluster, order
the unit after that dependency (`After=`) so it does not start before its backing service is
reachable.

### Running more than one instance on one host

Several independent stores can run side by side on one machine — each is its own process owning its
own store (a demo instance beside a personal one, say). This is orthogonal to the
single-consolidator rule above, which concerns two instances sharing _one_ store; here each instance
owns a _separate_ store. Give **each its own `storage.directory` (SQLite) or DSN, its own `port`, and
its own `gateway.port`**: the defaults (`50051`/`8080`) collide, and the second instance to start
fails to bind the port. An external content-search cluster likewise needs a distinct
`opensearch.index` (or a separate cluster) per instance so their documents do not intermingle.

### Ports

Every listener in the project and its default. Two defaults are shared by more than one component,
so two of these on one host need one of them moved:

- **8090** is the default of the MCP bridge's HTTP transport and of the health port of the broker
  bridges, the ingestor and the object gateway.
- **8091** is the default of the configuration wizard and of the object reaper's health port.

| Port   | Component                                                          | Serves                                                    | Set with                                  |
| :----- | :----------------------------------------------------------------- | :-------------------------------------------------------- | :---------------------------------------- |
| `50051` | the service                                                       | gRPC                                                      | `port`, `--port`                          |
| `8080` | the service                                                        | the JSON gateway, `/ui`, `/livez`, `/readyz`, `/healthz` (off unless set; 8080 is the convention every shipped config uses) | `gateway.port`, `--gateway-port` |
| `9464` | the service                                                        | `/metrics` for Prometheus, when `observability.prometheus.enabled` | `observability.prometheus.port`   |
| `8090` | [MCP bridge](mcp.md) (`--transport http`)                          | the streamable-HTTP MCP endpoint, on loopback by default, and `/livez`, `/readyz`, `/healthz` | `--http-address`                          |
| `8090` | [broker bridges](eventsource.md), [ingestor](ingestor.md)          | `/livez`, `/readyz`, `/healthz`, and `/metrics` with `--prometheus` | `--health-port`                           |
| `8088` | [object gateway](objectstore.md)                                   | the object routes                                         | `--listen-port`                           |
| `8090` | object gateway                                                     | `/livez`, `/readyz`, `/healthz`, `/metrics`               | `--health-port`                           |
| `8089` | object reaper                                                      | the callback endpoint                                     | `--listen-port`                           |
| `8091` | object reaper                                                      | `/livez`, `/readyz`, `/healthz`, `/metrics`               | `--health-port`                           |
| `8091` | [configuration wizard](config-wizard.md)                           | the wizard, and `/livez`, `/readyz`, `/healthz`           | `--port`                                  |
| `8082` | Swagger UI (compose `swagger` profile)                             | the API explorer                                          | the compose file                          |
| `3000`, `4317` | `grafana/otel-lgtm` (compose `observability` profile)      | Grafana, and the OTLP collector                           | the compose file                          |

Every compose file publishes on `127.0.0.1` unless `PUBLISH_ADDRESS` says otherwise, since a
published port bypasses a host firewall.

## Containers and Kubernetes

### Docker Compose

The repository ships a Compose stack per storage driver, plus two that add the OpenSearch
content-search index. All of them build the image from the repo's multi-stage
[`Dockerfile`](../Dockerfile) (statically linked, CGO disabled, non-root) and expose `50051` (gRPC)
and `8080` (HTTP gateway). The per-stack configs sit beside each file in
[`deploy/compose/`](../deploy/compose/); the image's baked-in default is
`deploy/compose/config.sqlite.json`.

| Stack                                                               | Command                                                                              |
| ------------------------------------------------------------------- | ------------------------------------------------------------------------------------ |
| Embedded SQLite, database in a named volume (the default)           | `docker compose up --build`                                                          |
| PostgreSQL                                                          | `docker compose -f deploy/compose/docker-compose.postgres.yaml up --build`           |
| MySQL                                                               | `docker compose -f deploy/compose/docker-compose.mysql.yaml up --build`              |
| SQLite + OpenSearch content search (security disabled — demo only)  | `docker compose -f deploy/compose/docker-compose.opensearch.yaml up --build`         |
| The same with the OpenSearch security plugin (HTTPS + basic auth)   | `docker compose -f deploy/compose/docker-compose.opensearch-secured.yaml up --build` |
| PostgreSQL + OpenSearch + an OTEL collector (the "corporate" stack) | `docker compose -f deploy/compose/docker-compose.corporate.yaml up --build`          |

Three opt-in Compose profiles layer onto them, all off by default:

- **`observability`** — an all-in-one `grafana/otel-lgtm` service (Grafana on `:3000`, OTLP on
  `:4317`) with the [Hippocampus dashboard and alert rules](#alert-rules) provisioned in. The
  service's metrics/traces are wired to it by `HIPPOCAMPUS_OBSERVABILITY_*` env overrides gated on
  the same variable, so nothing is exported (and no export failure is logged) unless the collector
  is up: `OBSERVABILITY=true docker compose --profile observability up --build`.
- **`ollama`** — the embedded [LLM summariser](consolidation.md#embedded-llm-ollama) beside the
  service: `LLM=true docker compose --profile ollama up --build`, then
  `docker compose exec ollama ollama pull llama3.2` once to fetch a model. Only needed for the
  default `ollama` provider — `LLM=true LLM_PROVIDER=openai LLM_ADDRESS=https://…/v1` points the
  service at a model endpoint you already run and needs no profile at all (see
  [Model providers](configuration.md#model-providers)).
- **`mcp`** (SQLite stack only) — an [MCP-over-HTTP endpoint](mcp.md) on `:8090` that dials the
  service over the Compose network: `docker compose --profile mcp up --build`. It is
  unauthenticated, like the rest of that demo stack; the common local pattern is instead the stdio
  transport spawned by the MCP host.

These stacks are demonstration-shaped — no auth, no TLS, and a bundled database — so treat them as a
starting point rather than a deployment. For anything long-running, give the service a `restart:`
policy so a [fail-stop](#deployment-model-one-consolidating-instance-per-store) is followed by a
clean restart, and point the healthcheck at `/livez` (or `/readyz`, as the image's own does).

### Kubernetes

[`deploy/k8s/`](../deploy/k8s/) carries plain [Kustomize](https://kubectl.docs.kubernetes.io/references/kustomize/)
manifests — no Helm, nothing beyond `kubectl` — with one overlay per deployment model:

```sh
# Embedded SQLite: one StatefulSet (1 replica) + a PersistentVolumeClaim
kubectl apply -k deploy/k8s/overlays/sqlite

# Centralised: one consolidator Deployment + N replica Deployments over a shared PostgreSQL
kubectl apply -k deploy/k8s/overlays/postgres
```

Both build on a shared `base/` (namespace, a token-less `ServiceAccount`, and the client-facing
`Service`), take their `config.json` through a content-hashed `configMapGenerator` so an edit rolls
the pods, and receive secrets (the DSN, the signing key) and the consolidator/replica split as
`HIPPOCAMPUS_*` env overrides rather than baked into the ConfigMap. Pods run non-root with a
read-only root filesystem — the counterpart to the shipped systemd unit's sandbox — and probe
`/livez` (startup and liveness) and `/readyz` (readiness, database-aware and failing from `SIGTERM`
on), with a 5-second `preStop` sleep so a rollout drops no requests while the endpoint removal
propagates. See [Health and readiness](configuration.md#health-and-readiness).

The workload kinds differ for the reason the [deployment
model](#deployment-model-one-consolidating-instance-per-store) gives: the SQLite overlay is a
`StatefulSet` pinned at one replica because a second pod sharing the volume would fail on the
storage lock, while the Postgres overlay scales its replica Deployment freely and leaves
consolidation to the single consolidator. Neither overlay ships an `Ingress` — expose the ports
through whatever the cluster already uses. See [`deploy/k8s/README.md`](../deploy/k8s/README.md).

## Choosing a storage driver

Set `storage.driver` to `sqlite` (default), `postgres`, or `mysql`. All three are pure Go, so the
binary is statically linked with CGO disabled.

|                                    | SQLite                        | Postgres                        | MySQL (8.0.20+)             |
| ---------------------------------- | ----------------------------- | ------------------------------- | --------------------------- |
| Best for                           | embedded / edge / single-node | centralised, server-managed     | centralised, server-managed |
| Dependencies                       | none (one file)               | a Postgres server               | a MySQL server              |
| Durability                         | WAL mode, immediate           | server-managed                  | server-managed              |
| Instances per store                | one (lockfile)                | one consolidator + replicas     | one consolidator + replicas |
| `consolidation.capacityBytes`      | yes                           | yes                             | yes                         |
| `consolidation.walTriggerBytes`    | yes                           | rejected at startup             | rejected at startup         |
| On-disk footprint for large bodies | uncompressed                  | **TOAST-compressed** (smallest) | uncompressed (largest)      |

`walTriggerBytes` is SQLite-only — it measures SQLite's on-disk WAL file, which the server drivers
have no equivalent of; they reject the setting at startup rather than silently ignore it.

## Sizing and capacity tuning

### Decay-only: no capacity target at all

Leaving both `consolidation.capacityBytes` and `consolidation.capacityMemories` at 0 is a supported
and deliberate configuration, not an omission — see
[Forgetting modes](consolidation.md#forgetting-modes) for the model. The store then forgets on the
deletion threshold alone, its size is an emergent property rather than a setting, and every memory's
lifetime stays a function of its own significance rather than of the aggregate write rate. The
service names the mode it resolved in a startup line, so which one is in force is never a matter of
inference:

```text
forgetting mode: decay-only - memories are forgotten on the deletion threshold alone
(threshold 10, method 1, aggressiveness 1); the store's size is not bounded by
configuration, so watch hippocampus.used_bytes
```

Operationally the mode inverts which instrument matters. A capacity-bounded store's size is pinned
by construction, so `hippocampus_capacity_pressure` is what you watch — it says how hard the store is
working to stay inside its target. In decay-only that series is flat at exactly 1.0 and carries no
information, while **size is the output of the loop** and therefore the thing to watch.
`hippocampus_used_bytes` is published in both modes for this reason, and `hippo memory explain`
reports `used_bytes` and `memory_count` on every call.

The alert to run is `HippocampusStoreGrowing`, which compares arrival against removal rather than
level:

```promql
sum(rate(hippocampus_memories_stored_total[1h]))
  > sum(rate(hippocampus_memories_consolidated_total[1h]))
    + sum(rate(hippocampus_memories_evicted_total[1h]))
```

Sustained, that means the decay settings do not forget as fast as the store is being written to. Three
responses, in the order worth trying:

1. **Check it is not simply a burst.** Decay-only has no transient control: a spike is absorbed at
   full size and stays until it ages out on its own schedule. Six hours of growth after a one-off
   import is the mechanism working.
2. **Strengthen the decay** if the growth is structural — raise `consolidation.deletionThreshold`
   (remembering it moves with your significance scale), raise `consolidation.aggressiveness`, or lower
   `consolidation.unitsOfAgeInDays` to compress the clock. `hippo sleep --dry-run` shows what the
   change would forget before you commit to it.
3. **Set a capacity target** if the store's size is a hard constraint rather than a budget. That is
   the closed-loop mode, and the trade it makes is that retention then depends on the aggregate write
   rate rather than on each memory's own significance.

Two things decay-only does not bound, both by design: an actively recalled working set never ages out
(every recall resets the clock and adds to effective significance), and a high significance against a
low `aggressiveness` produces lifetimes with no practical end. Both are floors under the store's size
that no decay setting reaches.

### Capacity target only: the store as a fixed-size buffer

The mirror image of decay-only is a positive `consolidation.capacityBytes` with
`consolidation.deletionThreshold` at or below 0. Value-based consolidation is switched off, nothing
is forgotten while the store is under its target, and once it crosses, eviction takes the
lowest-value memories down to the floor. The value function still chooses _which_ memories go; it no
longer chooses when. The startup line names it:

```text
forgetting mode: capacity target only - value-based consolidation is off (deletion threshold 0),
so nothing is forgotten until the store passes 160000000 bytes; eviction then reclaims the
lowest-value memories down to a floor of 144000000
```

Reach for it when the store is a buffer of the most valuable recent material rather than a set of
records with individual lifetimes — a working set for an agent, say, where "keep as much as fits" is
the actual requirement and any lifetime derived from significance would be arbitrary. What you give
up is prediction: `days_until_forgotten` reports `-1` for every memory, correctly, because nothing
crosses a threshold and how long a memory survives depends entirely on what is written after it.

Empty events are the one thing this mode still deletes on its own. Eviction's pool is memories, so an
event whose last memory is evicted would be left behind with nothing to value it against and no pass
that could ever reach it again — which is how two demo stores on this mode came to be carrying tens of
thousands of them, more than a third of their event tables, invisible to the capacity target
(`UsedBytes` estimates live memory rows). A cycle therefore sweeps every event holding no memories
while the threshold is off, subject to `consolidation.minimumRetentionInDays` like everything else.

Two further operational consequences. `hippocampus_memories_consolidated_total` sits at zero
permanently, so any alert comparing it against arrivals — `HippocampusStoreGrowing` among them —
needs eviction to be the term it looks at. And `consolidation.minimumRetentionInDays` becomes the one thing that can
defeat the target, since retention overrides the capacity bound: set it too high in this mode and
eviction has nothing left it is allowed to reclaim. Watch `hippocampus_memories_retained` against
`hippocampus_memories_count` for that, which is the pairing those gauges exist for.

Note that `consolidation.capacityMemories` cannot stand in for `capacityBytes` here — a row capacity
only scales the pressure that scales the threshold, and nothing evicts on the row count, so the
combination forgets nothing and is refused at startup.

### `capacityBytes` is measured on _stored logical_ bytes

The byte-capacity target (`consolidation.capacityBytes`, with hysteresis floor
`consolidation.capacityBytesFloor` — see [Capacity target](consolidation.md#capacity-target)) is
compared against the store's **live logical size**, not the physical file size:

- **SQLite** — database pages excluding the freelist (the size the file would have after a full
  vacuum).
- **Postgres / MySQL** — an estimate summed from the live rows themselves: each row's payload
  (`octet_length`) plus a per-row allowance for what the row costs beyond it — the row header, the
  columns the payload sum does not measure, this row's entries in the primary key and the two
  secondary indexes, and its share of the [content index](configuration.md#content-search) where the
  store keeps one. The allowance is measured per dialect rather than assumed, and held to real
  relation sizes by a test. This is deliberately _not_ a file-size measure: neither server returns
  space to the filesystem after `DELETE` (they reuse it internally), so a file-size reading would
  plateau at its high-water mark and make eviction chase a figure that can never drop.

  **It is an estimate, and it is not the disk.** Measured against real relation sizes across bodies
  from 64 bytes to four kilobytes, both index modes and compression both ways, it lands within about
  10% — which is close enough to size a disk from with headroom, and not close enough to treat as a
  quota. Before 0.45.0 it was not close at all: one 256-byte constant served all three drivers and
  under-counted server-driver disk by three to five times.

Three consequences for sizing:

1. The figure counts each body **as the service stored it**. With
   [`storage.compression.enabled`](configuration.md#body-compression) on — the default — a compressed
   body counts at its compressed size on all three drivers, so the saving shows up directly as
   headroom: the same `capacityBytes` holds several times more memories, and eviction starts later.
   Turning compression off makes the figure the body as the client sent it, which will make an
   existing store's used bytes appear to jump as new writes land uncompressed.
2. Postgres additionally TOAST-compresses large values on disk beneath `octet_length`, so its
   **physical** file can be smaller again than the figure eviction targets; MySQL/InnoDB does not, so
   its physical footprint is roughly the counted figure. For the same data with service-side
   compression off, expect the MySQL on-disk footprint to be **several times** the Postgres one.
3. Budget disk and memory against the **physical** footprint of your chosen driver, but tune
   `capacityBytes` against the counted size.

### The capacity target bounds the memories, not the database

The counted figure is the memories, the events and the link graph — and nothing else. Several
optional features keep their own tables in the same store, and those tables are **deliberately
outside** the target: each grows precisely when something is going wrong, so counting it would raise
capacity pressure and evict live memories to make room for the record of memories being evicted.
They are excluded from the capacity target; they are not excluded from the disk.

The tables the target _does_ count are also not excluded from the disk in the way their estimate
implies — on the server drivers `used_bytes` describes a compacted store, and a store that forgets
never stays compacted. See [index bloat on the server
drivers](#index-bloat-on-the-server-drivers).

| Feature                                                                  | Table                 | Bounded by                                                                             | Default cap                              |
| ------------------------------------------------------------------------ | --------------------- | -------------------------------------------------------------------------------------- | ---------------------------------------- |
| [Forgotten log](#what-was-forgotten--the-forgotten-log)                  | `memory_tombstones`   | `consolidation.tombstones.maxRows` / `.maxBytes` / `.maxAgeInDays`, trimmed each cycle | 100,000 rows or 30 days (feature is off) |
| [Delete outbox](configuration.md#the-delete-outbox)                      | `search_outbox`       | `opensearch.outbox.maxRows` / `.maxBytes` / `.maxAgeHours`                             | 1,000,000 rows or 24 hours               |
| [Deletion callbacks](#being-told-what-was-forgotten--outbound-callbacks) | `callback_queue`      | `callbacks.maxRows` / `.maxBytes` / `.maxAgeHours`                                     | 1,000,000 rows or 24 hours               |
| [Peer registry](#seeing-the-deployment) (server drivers)                 | `instances`           | one row per live instance, each pruned against its own heartbeat interval              | negligible                               |
| [Significance registry](api.md#the-registry-forgets-too)       | `significance_levels` | `consolidation.significanceLevels.unusedRetentionInDays`, reaped each cycle            | 7 days after a value falls out of use    |

The significance registry is the odd one out and is listed here for one reason: it is the only table
that grew with the store's **history** rather than its contents, gaining a row per distinct
significance value ever written and losing one only to a `Purge`. It is counted inside the target on
the embedded driver (page accounting cannot exclude a table in the same file) and outside it on the
server drivers (which count memory, event and link rows explicitly), so on neither was its growth
something an operator could act on. The reap is what bounds it; see
[the registry forgets too](api.md#the-registry-forgets-too), and
`hippocampus.significance_levels` for its size.

Setting a bound to 0 removes it, which is supported — the forgotten log and the callback queue both
warn at startup when every one of their bounds is gone — but an unbounded table here grows until the
disk stops it, and eviction will never notice. **Size the disk for `capacityBytes` plus the caps of
whatever you have enabled**, not for `capacityBytes` alone.

#### Sizing the three, in bytes

Each of them takes a `maxBytes` beside its row cap, all three unset by default. What that buys
differs by table, and the difference is worth knowing before setting one:

- **The forgotten log and the delete outbox have fixed-width rows**, so their row caps are already
  byte caps. What a row costs differs per driver — a tombstone measures **165 B** on SQLite, **255 B**
  on PostgreSQL and **345 B** on MySQL, an outbox row **75 / 120 / 185 B** — so the 100,000-row
  default log is roughly **17 / 26 / 35 MB** and the 1,000,000-row default outbox **75 / 120 /
  185 MB**. `maxBytes` there is the same bound stated in the unit a disk is sized in, converted at
  the driver's own allowance, and reaching it trims exactly as the row cap does; where both are set,
  the tighter wins.
- **The callback queue's rows have no fixed size**, and that is the case the key exists for. A
  delivery carries up to `callbacks.maxIdsPerDelivery` items (500), each of which may carry a memory
  body up to `callbacks.maxBodyBytes` (64 KiB) under `callbacks.includeBodies` — so
  `callbacks.maxRows` bounds the queue anywhere between a few hundred megabytes of bare ids and a
  figure with no useful ceiling. `callbacks.maxBytes` is measured against the rendered payloads
  themselves (a `payload_bytes` column written at insert, so no scan of the queue is needed), which
  is the only thing that actually bounds it.

Two properties to know. **Reaching a byte cap discards rows, exactly as a row cap does** — an
abandoned callback is a notification nobody will ever receive, an abandoned outbox row is a stale
index document left for the reverse sweep, and an abandoned tombstone is the oldest end of a record.
And **the newest callback delivery is never abandoned for the byte cap**: a single delivery larger
than the whole cap would otherwise be discarded the instant it was queued, for the life of that
configuration, so the bound you actually get is `maxBytes` plus at most one delivery, and that case
is logged at Warn naming the keys to lower.

None of the three is defaulted, because how much of this a deployment can afford is a property of
its disk rather than of the service, and a byte cap discards data. What stands in for a default is a
startup warning where the shape is dangerous — `callbacks.includeBodies` with no `callbacks.maxBytes`
is the one that matters, since it is the arrangement in which nothing bounds the queue's size at all.

**These tables are reported.** `hippocampus.ancillary_bytes` carries what each of them holds,
labelled by `component` (`forgotten_log`, `search_outbox`, `callback_queue`), measured once per sleep
cycle; sum over the label for the figure to add to `capacityBytes` when sizing a disk. The console's
Deployment tab shows the same reading under the callback queue, and `hippo consolidation status`
carries it as the response's `ancillary` block — where each table also reports its caps, so the
figure has the bound it is approaching beside it rather than standing alone. The shipped alert
[`HippocampusAncillaryStorageHigh`](../deploy/observability/README.md) fires when the three together
exceed a quarter of `capacityBytes`.

Four things to know about the figure. There are **two byte columns and they answer different
questions**. `bytes` is the table's _structural_ size — its rows and indexes compacted — computed for
the two fixed-width tables as a row count times a per-row allowance rather than measured, since
scanning them to add up what their count already says would put a cost on the path that exists to
bound the store; the callback queue is the exception, and its bytes are summed from a size recorded
at insert, a count there saying nothing about a row that may carry five hundred memory bodies.
`disk_bytes` is what the engine says the relation is _really_ holding, including space it has not
reclaimed — a catalogue lookup (`pg_total_relation_size`) on **PostgreSQL**, and `0` on
**SQLite**, because there is nothing to report: a page a prune frees returns to the freelist
`used_bytes` already excludes, so `bytes` is the whole truth there. On **MySQL** it is read from `information_schema.TABLES` with the session's `information_schema_stats_expiry` at 0. The
default cache would answer with whatever the table was the last time anything looked, which is exactly
wrong for a queue that started growing this morning. It includes the table's `DATA_FREE`, which is
where InnoDB keeps the space a prune emptied (see [index bloat on the server
drivers](#index-bloat-on-the-server-drivers)). On PostgreSQL under steady churn `disk_bytes`
is routinely around twice `bytes`, and that gap is the reading: it is disk no other figure this
service publishes can see. The metric and the response's `total_bytes` carry the larger of the two,
because sizing a disk is a question about what the engine is holding.

`bytes` is the **same** figure the capacity target subtracts and the same one `maxBytes` is enforced
against, so what eviction ignores and what gets trimmed cannot be two different numbers. That
deliberately excludes the unreclaimed part: a cap that grew with a table's dead rows would prune
harder, leave more dead rows, and prune harder again.

Each table also reports **which of its caps is actually in force** (`binding_limit`: `rows`, `bytes`,
`age` or `none`), its effective row cap (`limit_rows` — the tighter of the row cap and whatever
`maxBytes` resolves to at this driver's allowance) and how far back it reaches (`oldest_at`). This
exists because the caps are independent bounds with no precedence between them, and which one binds
depends on how fast the store is forgetting — a rate you cannot see when choosing them. A log
configured `maxRows: 100000` with `maxAgeInDays: 30` on a store forgetting 19,000 memories a day
holds **five days**, not thirty: both caps are enforced, neither is violated, and nothing else in any
reading says so. `binding_limit` of `rows` or `bytes` while an age cap is also set is that state; the
console flags it, and the service logs it at Warn when the binding changes (at Info when the cap
acting is the one that was asked for).

And a component reporting `enabled: false` beside a row count is a table
that has been switched off and still holds what it wrote: disabling any of the three stops the
writing _and_ the trimming, so those rows stay until `DeleteForgottenMemories` or
`DeleteCallbackQueue` discards them.

One thing runs the other way. On **SQLite** the [content search](configuration.md#content-search)
index (`memories_fts`) lives in the same database file and page accounting counts it, so the same
`capacityBytes` holds fewer memories and eviction starts sooner than it would with search unused.
The index is contentless — an inverted index, not a second copy of the bodies — so the overhead is a
fraction of the text, but it is real and it is inside the target. The server drivers keep the same
index and the same table name, and since 0.45.0 their live-row estimate allows for it too — so
enabling or disabling the store's own content index moves capacity pressure on every driver rather
than on one. On **MySQL** that allowance is much the largest of the three, because a `FULLTEXT` index
is an index on a column and so holds an uncompressed copy of every indexed body: the store's estimate
of a memory there is its body twice over plus a kilobyte, against roughly its body plus half again on
the other two.

### MySQL: size the InnoDB buffer pool to the working set

This is the single most important MySQL tuning knob for Hippocampus. In a soak test, the default
`innodb_buffer_pool_size` of **128 MB** against a ~**300 MB** on-disk dataset drove ~24 % of page
reads to disk and pushed read-query p95 latency from ~20 ms to ~500 ms — while writes stayed fast.
Raising the buffer pool to hold the working set restored read p95 to ~60 ms (in line with SQLite and
Postgres).

**Size `innodb_buffer_pool_size` at or above the physical dataset size.** Because InnoDB does not
compress, that physical size is close to the counted logical size — so budget the buffer pool
against `capacityBytes` (plus index and overhead headroom), not against a Postgres-sized footprint.
It can be resized online (`SET GLOBAL innodb_buffer_pool_size = …`) without a restart.

[`storage.compression.enabled`](configuration.md#body-compression) is the other lever here, and the
reason it is on by default matters most on MySQL: it shrinks the bodies InnoDB stores, so the same
buffer pool covers a several-times-larger store. It is the closest MySQL gets to Postgres' TOAST
behaviour, trading a little CPU for I/O that is far more expensive here. Leave it on before reaching
for a bigger buffer pool.

### Postgres

Autovacuum keeps pace with heavy delete churn out of the box — ensure it is enabled (the default)
and not throttled below the delete rate. What it does **not** do is repack the indexes, and on a
store that forgets by design that is the one thing this driver needs scheduled maintenance for.

### Index bloat on the server drivers

This is the most important operational fact about running Hippocampus on PostgreSQL, and it is not
a misconfiguration: **a store that forgets is a store whose indexes bloat, without bound, as a
direct cost of the thing the service exists to do.**

`VACUUM` marks a B-tree page that a delete emptied as reusable; it never repacks it. A store keyed
on a UUID, writing steadily and deleting most of what it writes, essentially never refills a page it
emptied — so the index grows with what the store has _forgotten_ rather than with what it _holds_.
A measured instance:

| figure                                    |    reading |
| ----------------------------------------- | ---------: |
| `used_bytes` (the store's own accounting) |     153 MB |
| `consolidation.capacityBytes`             |     160 MB |
| `pg_database_size`                        | **892 MB** |
| …of which heap                            |      78 MB |
| …of which indexes on `memories`           |     687 MB |
| …of which `idx_memories_consolidation_v3` |     533 MB |

That index was at 5.03% average leaf density with 20,183 deleted pages. The heap was never the
problem and autovacuum was keeping up: 17,145 runs and 18,000 dead tuples. A single
`REINDEX INDEX CONCURRENTLY` took it from 533 MB to 13 MB in under a second.

Two things follow that a runbook has to get right.

**The cadence is daily, not occasional.** Re-measured nine hours after that reindex, the same store
was back from 151 MB to 634 MB, that one index from 13 MB to 393 MB — about 52 MB an hour. A
schedule that says "when it gets large" describes a job nobody runs often enough.

**It is not a large-store phenomenon.** Bloat tracks churn, not row count. A store holding 1,011
memories in a 1,320 kB heap was carrying a 3.5 MB listing index: 3,581 bytes for each entry, 2.7
times its own heap. A store small enough that nobody would think to look at it is proportionally the
worst affected.

#### What the service reports, and what it deliberately does not do

`used_bytes` is a live-row estimate on the server drivers and **that decision stands** — a file-size
measure never shrinks after a delete on PostgreSQL, so eviction driven by one would chase a figure
that cannot drop, evicting live memories every cycle while the reading never moves (see
[`capacityBytes` is measured on stored logical bytes](#capacitybytes-is-measured-on-stored-logical-bytes)).
The estimate is not wrong; it describes a _compacted_ store. What was missing was any comparison
between it and the disk, so the service now reports one:

- **`hippocampus.disk_bytes`** — what the engine says the tables inside the capacity target really
  occupy. Read it _against_ `used_bytes`; the **ratio** is the finding. On the instance above it was
  5.8.
- **`hippocampus.index_bytes`** and **`hippocampus.index_entries`**, by `table` and `index` — divide
  one by the other. The widest key in this store is a 37-character id and seven numeric columns, so
  an entry costing tens of bytes is healthy and one costing hundreds is air. Packed, the three
  indexes on `memories` come to about 217 bytes a row; on the instance above they came to 3,380.
- The same figures ride `GetConsolidationStatus` as its `footprint` block, so `hippo consolidation
status` shows them without a metrics stack, and the console's Deployment tab renders them as a
  per-index table below the ancillary card.

All of it is measured once per sleep cycle from the catalogue — `pg_total_relation_size`,
`pg_relation_size`, `pg_class.reltuples` — which costs a handful of round trips and reads no rows.
The authoritative figure, `pgstatindex`'s `avg_leaf_density`, is deliberately **not** taken: it reads
every page of the index, which is not a cost to pay once a cycle on the index this is about, and it
needs an extension a managed instance may not have. Bytes against entries says the same thing for
free.

**SQLite has nothing to report** — page accounting already counts every index inside the capacity
target, so the same `capacityBytes` simply holds fewer memories.

**MySQL reports per table, and its gap has a different shape.** The reading comes from
`information_schema.TABLES` (`DATA_LENGTH + INDEX_LENGTH + DATA_FREE`), which serves sizes from a
cache that `information_schema_stats_expiry` refreshes at most once a day by default — read as it
stands, it reported a ten-thousand-row table at 16 KiB. So the measurement pins one connection, sets
that variable to 0 for its own session, and puts it back afterwards. The variable needs no privilege.
The setting is scoped to the measurement rather than put in the DSN, so a server that refuses it
fails only the reading and never the store's connections. What it can't give is a per-index
breakdown: those sizes live in `mysql.innodb_index_stats`, which an application user is normally not
granted. `hippocampus.index_bytes` is therefore not published on MySQL, `HippocampusIndexBloated`
never fires there, and the console shows one row per table.

InnoDB does not bloat the way PostgreSQL does. It merges a page that a purge leaves under half full
and returns emptied pages to the tablespace, so its B-trees stay dense; what forgetting frees shows
up as `DATA_FREE`, which the table reuses for new rows and keeps on disk. Measured: six rounds of
inserting 30,000 rows and deleting the oldest 27,000 held `DATA_LENGTH` at 2.1 MB and `INDEX_LENGTH`
at 1 MB for 3,000 rows, while `DATA_FREE` levelled off at 13.6 MB. That is a **high-water mark, not
growth without bound**, so MySQL has no daily job. `OPTIMIZE TABLE memories` (an online rebuild for
InnoDB) gives the space back when the peak it records will not recur. `DATA_FREE` assumes each table
has its own tablespace, which is the default and how this store creates them. On a server with
`innodb_file_per_table` off it reports the shared tablespace's free space against every table and
over-reads.

**The service will not reindex itself.** `REINDEX INDEX CONCURRENTLY` is online, but it is still a
maintenance decision — it needs disk headroom for a second copy of the index, it can fail and leave
an invalid index behind, and a memory store that starts rebuilding indexes on a timer is a store
that surprises its operator at the moment it is already under pressure. `Preserve()` is a no-op on
both server drivers and stays one.

#### The maintenance job

On PostgreSQL, run this daily against a store under sustained write load. It is online: readers and writers are not
blocked, and each index takes seconds to minutes.

```sql
-- What is actually bloated, largest first. Needs no extension.
SELECT i.relname                                   AS index,
       pg_size_pretty(pg_relation_size(i.oid))     AS size,
       GREATEST(i.reltuples, 0)::bigint            AS entries,
       round(pg_relation_size(i.oid) / NULLIF(GREATEST(i.reltuples, 0), 0)) AS bytes_per_entry
FROM pg_index x
JOIN pg_class i ON i.oid = x.indexrelid
JOIN pg_class c ON c.oid = x.indrelid
WHERE c.relname IN ('memories', 'events', 'memory_links', 'event_links', 'memories_fts')
ORDER BY pg_relation_size(i.oid) DESC;
```

```bash
# Rebuild everything on the two tables that churn. Online; safe beside a live service.
psql "$DSN" -c 'REINDEX TABLE CONCURRENTLY memories'
psql "$DSN" -c 'REINDEX TABLE CONCURRENTLY memories_fts'
```

Two cautions. A `REINDEX ... CONCURRENTLY` that is interrupted leaves an **invalid** index behind
(`SELECT indexrelid::regclass FROM pg_index WHERE NOT indisvalid`) — drop it and run again; the
original is still in place and still being used, so nothing is broken meanwhile. And it needs room
for a second copy of the largest index while it runs, which on a bloated one is the _bloated_ size,
not the packed one.

#### A major-version upgrade is a reindex too

A Postgres cluster one major wrote cannot be read by the next, so moving majors on a self-run
Postgres means a dump and a restore. `pg_upgrade --link` avoids that, but it needs both majors'
binaries in one place, which the official alpine images do not carry. The bundled Kubernetes
Postgres has the
[procedure written out](../deploy/k8s/README.md#upgrading-the-bundled-postgres-across-a-major-version),
including why that manifest fails loudly rather than starting an empty cluster beside the old one.

The restore rebuilds every B-tree packed, which makes it the most complete reindex this store gets.
Measured on the demo's 17 → 18 move, two stores of 663 MB and 664 MB came back at 118 MB and 128 MB,
and the volume went from 2.2 GB to 577 MB. **It does not stay that way.** Five days later the larger
store's disk-to-estimate ratio was back to 4.5x, which is the daily cadence above confirmed from the
other direction. A dump and restore resets the bloat. It is not a substitute for the job.

The shipped alerts [`HippocampusStoreDiskFarAboveEstimate` and
`HippocampusIndexBloated`](../deploy/observability/README.md) fire on the two halves of this: the
database holding more than four times what the accounting counts, and any single index spending more
than 512 bytes an entry. The content index is excluded from the second — its entries are a `tsvector`
that grows with the bodies it indexes, so its cost per entry is a property of the stored text rather
than a number with a right answer. Each also carries an absolute floor (64 MiB of database, 16 MiB of
index), because a nearly empty store's catalogue and empty-index pages make its ratio large for no
reason worth acting on; a store under those sizes can still be reindexed, it is just never paged for.

### Sleep cadence vs. write rate

`sleep.periodSeconds` sets how often consolidation and eviction run. Growth _between_ cycles is
unbounded, so under a high sustained write rate the store can overshoot `capacityBytes` before the
next cycle. Options: shorten `sleep.periodSeconds`, or (SQLite only) set
`consolidation.walTriggerBytes` to force an out-of-cycle checkpoint when the WAL outgrows a bound.
A non-positive `sleep.periodSeconds` disables timed cycles entirely — a supported mode for an
import-only or manually-driven instance.

If you set a [minimum retention](consolidation.md#minimum-retention) floor
(`consolidation.minimumRetentionInDays`), note that it **overrides** `capacityBytes`: eviction will
not delete data inside the retention window, so a retained working set larger than `capacityBytes`
holds the store above the target by design. Size `capacityBytes` (and the physical disk/buffer-pool
budget above) to fit `minimumRetentionInDays × peak write rate`, or the store can grow past the
capacity target until retained data ages out.

### Previewing what would be forgotten

Tuning consolidation means choosing between six methods crossed with `aggressiveness`,
`deletionThreshold`, `unitsOfAgeInDays`, `capacityPressureExponent` and two significance weights —
and the only feedback used to be the data that had already gone. `PreviewConsolidation` closes that
loop: it reports what a cycle **would** forget, against your store and your configuration, and
deletes nothing.

```bash
hippo sleep --dry-run              # what would go
hippo sleep --dry-run --limit 500  # ...detailing more of it
```

It answers three questions:

- **How much.** `memories_consolidated`, `memories_evicted`, `events_deleted` and `bytes_freed` are
  always complete counts, whatever `--limit` is set to.
- **Which, and why.** A bounded sample of individual memories — id, group, event, significance, the
  computed `value`, the `threshold` it was compared against, and the `rule` that claimed it. The
  sample is ordered least-valuable-first, so a truncated one shows the memories furthest past the
  threshold rather than an arbitrary slice. `rule` separates the three paths, which have different
  answers: `CONSOLIDATION` means the memory decayed below the threshold (tune the decay settings),
  `EVICTION` means it was still valuable enough to keep and went only because the store is over
  `capacityBytes` (raise the capacity, or store less), and `EXPIRY` means it was older than
  `consolidation.maximumRetentionInDays`, whatever its value (that one is policy, not tuning).
- **Against what.** `capacity_pressure`, the scaled `deletion_threshold`, `used_bytes` and
  `capacity_bytes` — the inputs the decisions were made against, so the numbers can be read
  alongside the configuration that produced them.

**`memories_retained` / `retained_bytes` are the figures to watch** if you have set a retention
floor. They count what is currently inside the retention window and therefore exempt from _both_
paths. Because retention overrides the capacity target (above), `retained_bytes` approaching
`capacity_bytes` is the early warning that the target is becoming unreachable — eviction will run,
find nothing it is allowed to delete, and leave the store over its capacity. That is visible here
before it becomes a disk problem. The same pair is exported continuously as the
`hippocampus.retained_bytes` / `hippocampus.memories.retained`
[metrics](#observability), so you can alert on it rather than only discover it by asking.

Three properties worth knowing. The preview applies the cycle's own ordering — consolidation runs
first, so its memories are excluded from the eviction pool and their bytes are already reclaimed
before eviction is considered, and each memory therefore appears once under the rule that would
actually claim it. It deliberately does **not** join an in-flight cycle: a preview that attached
itself to a running `Sleep` would be describing a run that was at that moment deleting. The cost is
that a cycle can start while the preview scans, so a preview describes the store as it was — which
is why it reports the inputs it decided against.

And **concurrent previews share one scan.** Calls arriving while a preview is already running join
it rather than each starting a scan of their own, keyed on the sample size (so a caller asking for
more rows is never handed a shorter list). This matters most on the `sqlite` driver, whose
connection pool is a single connection by design: without it, a client polling the preview could
crowd out the sleep cycle's own queries. It cannot block a cycle from _starting_ — the preview
shares no lock with the cycle — but it does contend for that connection, bounded by
`storage.queryTimeoutSeconds`. One consequence: if the caller whose scan the others joined
disconnects, the callers waiting on it see that cancellation and should retry.

Bodies are never returned; a dry run reports what would be lost, and is not a way to read the
store. It is `admin`-tier for the same reason `Export` is: it enumerates ids, groups and
significances from across the whole store.

### Where a memory stands

A dry run answers "what goes next". `ExplainConsolidation` answers the other half — "where does
_this_ memory stand, and how long has it got" — for memories you already have in hand:

```bash
hippo memory explain --id abc123 --id def456
hippo memory explain --curve-significance 40        # no ids: just the curve and the current inputs
```

Per memory it reports the `value` the decay algorithm gives it, the `threshold` that value is
measured against, its `effective_significance` (its own significance plus its event's, the weighted
damped link contributions and the weighted recall count — the number the decay actually acts on),
and `days_until_forgotten`: how long it has at today's threshold and pressure, assuming it is not
recalled again. Two flags override the value comparison and are reported separately, because a
memory far below the threshold that is nonetheless safe is otherwise baffling: `retained` (inside
`minimumRetentionInDays`, so neither path may take it) and `below_minimum_age` (younger than
`minimumAgeInDays`, so value-based consolidation is deferred).

With `--curve-significance` it also returns the **decay curve** for that significance — sampled from
the same code that makes the decisions, so a plot of it cannot drift from what the service will do —
along with the age at which the curve crosses the threshold. Left unbounded, the span is chosen to
show that crossing rather than an arbitrary window.

Unlike the preview it enumerates nothing, so it needs only the `reader` tier. Bodies are never
returned. The decision inputs it reports (capacity pressure, used bytes) are refreshed periodically
rather than per call — both cost a scan, and this is asked far more often — so they can lag a cycle
that has just finished by a few seconds. And, like the preview, it is refused on a replica
(`consolidation.enabled: false`), whose configuration is not the one its store is consolidated
under.

The embedded console's **Decay** tab is this RPC: a value column in the memory and search tables
(with what is due now, what is held by retention, and how long the rest have), the current capacity
pressure and threshold, and the plotted curve. Clicking a memory's value plots that memory's own
curve. For an administrator the same tab also runs the dry run above.

### What was forgotten — the forgotten log

The dry run says what would go and the explanation says where a memory stands; both speak only
about memories that are still there. The **forgotten log** is the third and it is the only one that
can speak about a memory that is not: one record per memory a cycle actually deleted, kept in the
store beside the memories that survived.

It is optional and off by default:

```json
"consolidation": {
  "tombstones": {
    "enabled": true,
    "maxRows": 100000,
    "maxBytes": 0,
    "maxAgeInDays": 30
  }
}
```

```bash
hippo forgotten list                                     # the most recent page
hippo forgotten list --memory-id abc123                  # did this memory exist, and when did it go
hippo forgotten list --rule eviction --group ingest      # only what went to meet the byte capacity
hippo forgotten clear --before 2026-07-01T00:00:00Z      # or --all
```

Each record carries the memory's id, group, event, significance, stored size, the `value` the decay
algorithm gave it and the `threshold` it was measured against **at that moment**, the `rule` that
took it, its creation and recall timestamps, and when it went. (For an `EXPIRY` record `value` and
`threshold` are 0, since neither was the reason.) The threshold is recorded per record
rather than inferred, because it moves with capacity pressure: without it a value from last month
means nothing today.

**Bodies are never kept.** A tombstone records that a memory was forgotten, not what it said; this
is not an undelete, and building one on top of it is a different feature entirely.

Five things to know before turning it on.

- **It records forgetting, not deletion.** The two decay paths write records; `Clear` (which
  deletes memories an `Export`/`Transfer` has already moved elsewhere) and the client-initiated
  deletes (`DeleteMemories`, `DeleteEvent --memories`, summary replacement) do not. Nothing was
  lost in those cases, and a log claiming otherwise would be worse than no log.
- **It is bounded, and the bounds matter.** The log lives in the store it describes, so an
  unbounded one would slowly consume the headroom that drives forgetting. `maxRows`, `maxBytes` and
  `maxAgeInDays` are applied at the end of every cycle and a record past any of them is trimmed;
  setting all three to 0 removes the bounds, which is supported and warned about at startup. A
  tombstone is a fixed-width row, so `maxBytes` is the row cap in another unit — 165 bytes a row on
  SQLite, 255 on PostgreSQL, 345 on MySQL — and where both are set the tighter wins. The log is
  excluded from the store's measured size, so it never raises capacity pressure or triggers
  eviction — but it does still occupy disk, and is one of the tables [the disk budget has to cover
  on top of `capacityBytes`](#the-capacity-target-bounds-the-memories-not-the-database).
- **The row cap will usually be the one that binds, and it is not the one you meant.** These bounds
  have no precedence between them: which one acts depends on how fast the store is forgetting, and
  at 19,000 memories a day a 100,000-row cap is five days of history whatever `maxAgeInDays` says.
  `GetConsolidationStatus` reports each table's `binding_limit` and how far back it actually reaches,
  the console's Deployment tab shows it, and the service logs a Warn when a row or byte cap is what
  holds a log that also has an age cap set. **If a retention window is the point, raise `maxRows`
  until the age cap is the one binding** — and budget the disk for it.
- **Turning it off does not delete anything.** Disabling stops the writing _and_ the trimming, so
  what was already recorded stays readable. Emptying the log is always an explicit request
  (`hippo forgotten clear`, `POST /v1/memories/forgotten/delete`) — a configuration change must
  never destroy a record somebody kept. The one exception is `Purge`, which empties everything by
  definition.
- **Recording is part of the delete.** A record that cannot be written fails that batch of
  deletions rather than letting the memories go unrecorded; the cycle reports the failure and the
  memories are reconsidered next time.

**Reading the log is `reader`-tier; emptying it is `admin`.** Both honour group scoping as a
predicate — a tombstone carries its memory's group — so a group-scoped token sees, and can clear,
only its own partition's losses. That is what separates the log from the dry run beside it, which is
refused to a scoped caller outright: the log speaks only about records that were already the
caller's, it carries no bodies, and the `value`/`threshold` pair it reports is what
`ExplainConsolidation` already serves at `reader` for the memories still here. Emptying it stays
`admin` because that is destructive, and destructive on an audit record rather than on data the
caller put there.

One case argues for raising the read back to `admin`, and is worth checking against your deployment:
the log outlives what it describes, so a long `maxAgeInDays` leaves a trace of groups, sizes and
timing that the live store would by then have discarded. If `reader` tokens go to clients you would
not trust with that history, keep the log short or move the RPC up a tier.

Two metrics come with it: `hippocampus.tombstones` (records held, measured each cycle) and
`hippocampus.tombstones.deleted` (records removed, by whether it was a manual clear or the caps).
What was forgotten and by which rule is already reported by `hippocampus.memories.consolidated` and
`hippocampus.memories.evicted`.

The console's **Decay** tab shows the log beside the dry run — the log to any caller, the dry run
and the log's Clear button to an administrator — and the **Now** tab carries a short feed of the
most recent losses.

### Being told what was forgotten — outbound callbacks

The log above, the dry run and the status RPC are all things a client has to **ask** for.
[Outbound callbacks](configuration.md#outbound-callbacks) are the other direction: with
`callbacks.enabled` and a `callbacks.url`, the service POSTs JSON to that endpoint when it forgets
memories or events and when a sleep cycle finishes, so a system downstream of the store learns about
a deletion instead of discovering it by asking for a record and finding nothing.

There is a fourth kind, `memories_at_risk`, which is the only one that speaks **before** the fact:
raised at the top of a cycle, it names what that cycle is about to forget, so a receiver can act
while the memories are still there. It is off by default because it is the only kind that costs a
scan — enabling `callbacks.events.memoriesAtRisk` runs a consolidation preview on every cycle,
roughly doubling what a cycle costs — and `callbacks.atRiskMargin` is what buys a receiver enough
notice to be worth having. See [Being told _before_ a memory
goes](configuration.md#being-told-before-a-memory-goes).

Operationally the thing to know is that it is backed by a **persisted queue**, not a fire-and-forget
call. A delivery is written in the same transaction as the deletion that produced it, so a receiver
that is down becomes a backlog rather than a silent loss, and a restart mid-backlog replays. Delivery
is at-least-once; receivers must be idempotent, and the `cycle_id` plus chunk numbering are what let
one recognise a repeat.

That makes the backlog the thing to watch. `hippocampus.callbacks.queue_depth` rising alongside a
non-zero `hippocampus.callbacks.delivered{outcome="failed"}` rate is a receiver that is refusing;
`hippo callbacks queue` shows the same thing per delivery, with the attempt count and next-attempt
deadline that separate a queue which is draining from one that is stuck. Three shipped alert rules
cover it. The escalation is `hippocampus.callbacks.abandoned`, and it is worse than its search-index
namesake: there is no sweep behind this queue, so a delivery discarded at
`callbacks.maxRows`/`maxAgeHours` is a notification nobody will ever receive. It is logged at Warn
for deployments without a metrics stack. It also counts a delivery whose stored payload could not be
decoded, which is removed when claimed and logged at Error. That is corruption rather than an outage,
and the log line names what was lost.

The queue is excluded from the capacity target — it grows precisely when a receiver is down, and it
can carry memory bodies, so counting it would evict live memories to make room for the news that
memories were evicted — but it is **not** excluded from the [disk
budget](#the-capacity-target-bounds-the-memories-not-the-database). `hippo callbacks clear` discards
pending deliveries when a receiver is gone for good; it requires `--before` or `--all`.

Whether abandoning is acceptable at all depends on what the receiver is. If it is the system holding
the payloads this store's memories point at, a discarded `memory_forgotten` is an orphaned object out
there rather than a gap in a feed, and `callbacks.backlogPolicy` is how a deployment says so — see
[When a forget-callback is an instruction, not a
notification](configuration.md#when-a-forget-callback-is-an-instruction-not-a-notification).
Operationally the one to know is `stall`: past the caps the cycle stops forgetting rather than
discarding, which shows up as `hippocampus.forgetting.stalls` climbing, a Warn line on every cycle, a
`stalled` cycle report in `hippo status` and the console's Now tab, and — because nothing is being
reclaimed — capacity pressure and `used_bytes` rising past the target. Treat it as a receiver outage
with a deadline attached: the store is holding its own growth open until somebody fixes the far end.

## Seeing the deployment

`hippo topology`, and the console's **Deployment** tab, report the deployment as one instance
understands it: itself, the components it dials, how they relate, and the last known health of each.
The configuration is under
[Deployment topology](configuration.md#deployment-topology); what matters operationally is what the
answer does and does not cover.

**It is one instance's view, not a survey.** An instance knows itself, whatever it dials outward,
and — on a shared `postgres`/`mysql` store — the peers it finds registered there. Everything else in
a deployment connects _to_ it: the event-source bridges, the ingestor, MCP servers, `hippo` itself,
none of which it holds an address for. Every component reported therefore carries a **source**, and
a short list means nothing has been declared rather than nothing is running. This is deliberate: the
alternative is a registry of clients, and that makes a memory store into a control plane. Nothing in
this view can act on another component, and nothing is planned to.

**Declare the components that dial in.** The inbound half becomes visible by listing it under
`topology.components` (see [Deployment topology](configuration.md#deployment-topology)) — and it
costs nothing on the other side, because the bridges and the ingestor already serve the health
surface it probes. Their `/readyz` reports a per-dependency breakdown, so a declared bridge that
cannot reach its broker says so on the diagram, and one that cannot reach _this service_ says that
instead. Those two look identical from outside and have entirely different owners, which is most of
the value of declaring them at all.

An edge to a declared component points **inward**, because that is the direction the connection is
opened in: the bridge holds an address for the service, not the reverse. Every other edge in the
view runs outward.

**Clients that call are shown as they call.** Where authentication is on, a component that presents
a verified token is drawn from the `client_id` it authenticated with, sourced `observed`. This needs
no configuration and names real clients — but it is the weakest of the five sources, and
deliberately so:

- It carries **no health**, permanently. A call proves the client was alive at that instant, which
  is not what a probe proves: an idle client is not broken, and a client that polls while its real
  work has stopped is not healthy. Observed components therefore report as unchecked, with the
  moment of their last call beside them.
- It reports **nothing when authentication is off**, since a caller is identified by its token and
  by nothing else — never by a source address, which names a proxy or a pod that has since been
  replaced. The `self` component says so, so an empty inbound column is not left to be read as
  "nothing is calling".
- The set is **capped** (32) and the least recently seen entry is dropped when it fills; it is held
  in memory, so a restart clears it. Entries are never expired on a timer: a bridge whose last call
  was six hours ago is more useful on the diagram than an absence would be, because the absence is
  indistinguishable from a component nobody ever configured.

Declaring a component and observing it are complementary, and they combine: where a declared
component's name matches an observed `client_id`, the two are shown as **one** component carrying
both its health and its last call. That pair separates the case nothing else here can — a bridge
that is up and writing from a bridge that is up and has written nothing.

What it does answer, and answers well:

- **Which of these two addresses is the consolidator.** The `self` component reports its role, and
  on the server drivers the store reports which side of the single-consolidator lock this instance
  is on — and names every instance sharing it, so the answer holds whichever one you asked.
- **Is anything consolidating at all.** A shared store whose instances all came up as replicas
  forgets nothing and grows without bound while every instance reports itself healthy. It is
  reported here as a **warning**, above the components, because the fault is the absent instance and
  there is no component to colour red. So is the reverse — two instances claiming the role — which is
  what a broken lock, or two tiers pointed at different databases, looks like from inside.
- **Which instances are running what.** Each peer reports its version and whether it has the search
  index, the summariser, the embedder and the gateway — so a replica that came up missing one is
  visible as such, which it otherwise is not: it behaves exactly as its own configuration says it
  should.
- **Is a dependency quietly broken.** A failed OpenSearch write is best-effort and logged; a missing
  Ollama model fails nothing until the first summarisation; an unreachable S3 bucket surfaces on the
  first `Export`. All three show here as a status with the reason beside it, before anyone runs the
  operation that would otherwise discover them.
- **Why is an optional feature doing nothing.** Components that are switched off are listed with the
  config key that would enable them (`hippo topology --all`, or the console's toggle).
- **Is a declared bridge writing, and if not, whose problem is it.** A degraded component names the
  end it cannot reach; an unreachable one is not answering at all; a `404` is a `healthUrl` that is
  wrong rather than a component that is down.
- **Who is actually calling this instance, and who is being refused.** An observed component lists
  the roles its token carried and whether it is group-scoped. A client calling constantly and being
  refused constantly looks exactly like a healthy one everywhere else; here its roles row says
  `none`, which is what a token resolving to no known tier gets.

Three cautions. Statuses come from a **background prober**, so every one is a snapshot and each
component reports when it was last checked — `unreachable` means "when last asked", not "now". Two
components are never probed at all, for reasons given in the configuration guide: the OTLP
collector, and the identity provider. They report as unchecked rather than as healthy. And a peer is
not probed either — this instance holds no address it could dial one on. What its row proves is that
it was writing to the shared store recently, which is the property that actually matters about a
peer: one that has stopped writing has stopped serving from here whether or not its port answers.

## Running the OpenSearch content index

Only under `opensearch.enabled` — the built-in content index (`search.contentIndex`, the default on
every driver) is maintained inside the primary write and has none of what follows. See
[Content search](configuration.md#content-search) for the keys.

Two things about this index are unusual, and both follow from what the store is for rather than from
how it is configured.

### The index is fed by a queue that drops, and that is the design

Every index write, delete and event move is handed to a bounded in-memory queue
(`opensearch.queueSize`, 1024) drained by **one** worker. One worker is a correctness property, not a
limit: the delete-then-index pair a summary replacement emits must never be reordered. When the queue
is full the operation is **dropped rather than blocking the caller** — a store must not stop accepting
memories because a secondary index is behind — and the reconciliation sweep is what puts the index
back in step afterwards.

So a non-zero `hippocampus.search.dropped` is not by itself a fault. What it means depends on the
`reason` attribute, and the two have unrelated remedies:

| `reason`       | What it says                                                   | What to do                                                                             |
| -------------- | -------------------------------------------------------------- | -------------------------------------------------------------------------------------- |
| `queue_full`   | This service is offering work faster than one worker drains it | Compare `queue_depth` against `queue_capacity` (below)                                 |
| `apply_failed` | The cluster refused or did not answer, on every retry          | The cluster's problem: check its health, then `applyTimeoutSeconds`/`applyMaxAttempts` |

**`queueSize` is not the answer to a sustained `queue_full` rate.** A bounded queue absorbs _bursts_;
it cannot absorb a rate mismatch, and raising it past what the worker can drain only moves the drop
later and costs memory in the meantime. The two cases are distinguishable, which is what
`queue_depth` is for: a queue absorbing bursts is spiky and near zero between them, and widening it
helps; a queue **pinned at capacity** is being outrun, and no size helps. Utilisation is
`hippocampus_search_queue_depth / hippocampus_search_queue_capacity` — the capacity is exported so a
dashboard need not carry its own copy of the configuration.

When the queue is genuinely being outrun, the levers are the write rate, `opensearch.applyTimeoutSeconds`
(a shorter timeout fails a stuck round trip sooner, so the worker moves on), and the cluster's own
ingest latency, which is what a single-document-per-request worker is bounded by.

The drop **log line is aggregated**: one summary every 30 seconds naming the total and the breakdown
by reason and operation, not one line per drop. The per-drop warning was measured at 113,377 lines in
thirty minutes on a live deployment — 63 a second, filling a 4 GB journal with one repeated sentence
and rotating away everything else the service had to say. The metric still counts every single drop;
a counter loses nothing to aggregation, and a log line read by a person repeats nothing useful after
the first.

### The sweep asks before it writes

`opensearch.reconcileIntervalSeconds` (3600) sets how often the consolidating instance reconciles the
index against the store, in both directions:

- **Forward** — for each page of memories, one `_mget` asks which ids the index does **not** hold, and
  only those are written. `hippocampus.search.documents_healed` counts them, and it is the
  number that says how much is actually being lost between the store and the cluster. A healthy index
  costs one request per page and writes nothing at all.
- **Backward** — `opensearch.staleSweep` (on) enumerates the index and removes documents whose memory
  the store no longer holds, counted by `hippocampus.search.stale_documents_removed`.

The forward pass asks first because re-indexing unconditionally — which is what it used to do — costs
three things that all scale with the store. It made the sweep the dominant producer on the queue it
exists to compensate for, so live writes were the operations dropped to make room for re-writes of
documents already present. With semantic search on it re-embedded every memory in the store on every
pass. And in Lucene a re-index is a delete plus an insert **even when the document is byte-identical**,
so an hourly sweep tombstoned the whole index once an hour — see below.

One thing the sweep deliberately does not heal: a document that is present but missing its embedding
vector, indexed while the model server was down. It heals _absences_; comparing vectors would mean
fetching ~3 KiB per memory per pass to find a case `--backfill-search --reindex` already covers.

### Deleted documents accumulate, because this store deletes by design

Lucene does not remove a deleted document; it marks it, and the space comes back only when the
segment holding it is merged. Every other index is fed by a system that mostly appends, so the
default merge policy is tuned for that. **This one is fed by a store whose whole purpose is
forgetting**: every consolidation, every eviction, and every summary replacement deletes documents,
at whatever rate the decay settings dictate, indefinitely.

The result is an index whose deleted fraction reaches a steady state well above what merging clears.
Measured on live deployments: 147,496 live documents against **921,741 deleted** (341 MB), and — on an
index whose store had almost entirely turned over — 813 live against **533,861 deleted**, 99.85%
tombstoned in 313 MB. A `_forcemerge` took the two to 215 MB and 57 MB.

Check the deleted fraction rather than assuming it:

```bash
curl -s 'http://opensearch:9200/_cat/indices/hippocampus-memories?v&h=index,docs.count,docs.deleted,store.size'
```

Two remedies, and the first is the one to reach for:

- **Merge away the deletions, on a schedule.** `only_expunge_deletes` merges just the segments holding
  them, so it is far cheaper than a full force-merge and safe to run beside live traffic (it is still
  I/O, so run it off-peak):

  ```bash
  curl -sX POST 'http://opensearch:9200/hippocampus-memories/_forcemerge?only_expunge_deletes=true'
  ```

  Daily is a reasonable starting point; a store turning over faster than it grows wants it more often.
  Do **not** force-merge to a single segment (`max_num_segments=1`) on an index that is still being
  written — that produces one very large segment which future deletions can then never get out of.

- **Make the merge policy expunge sooner.** `index.merge.policy.deletes_pct_allowed` (default 20,
  minimum 5) is the deleted fraction above which OpenSearch will merge for the sake of the deletions
  alone. Lowering it trades continuous merge I/O for a smaller index:

  ```bash
  curl -sX PUT 'http://opensearch:9200/hippocampus-memories/_settings' \
    -H 'Content-Type: application/json' \
    -d '{"index.merge.policy.deletes_pct_allowed": 8}'
  ```

Rebuilding is the third option and rarely the right one: `--backfill-search --reindex` deletes the
index and repopulates it from the store, which does clear every tombstone, but it re-embeds every
memory if semantic search is on and leaves searches answering from an incomplete index while it runs.

## Backup, restore, and migration

Three approaches, which combine:

- **`hippocampus --backup <path>` (SQLite).** Writes a consistent copy of the store to `<path>` and
  exits, **safely beside a running instance**: it opens the store read-only, takes no lock, and uses
  SQLite's `VACUUM INTO`, which reads one snapshot and writes a single compacted file with no `-wal`
  sidecar. Do **not** copy `hippocampus.db` by hand while the service runs: in WAL mode the recent
  writes are in the `-wal` file until a checkpoint, so a copy of the main file alone silently loses
  them. The destination must not exist — a backup never overwrites the previous one. To restore,
  stop the service and put the copy in place as `hippocampus.db` in `storage.directory`.
- **Server tools (PostgreSQL, MySQL).** Use `pg_dump`, `mysqldump`, or your provider's snapshots.
  `--backup` refuses these drivers and says so: their own tools understand their transactions, roles
  and replication, and the service does not imitate them.
- **The archive** — any driver. `Export` writes the whole store as a gzip, length-delimited proto
  archive to the configured archive store (`archive.directory` or `s3.bucket`); `Import` reads one
  back; `Transfer` streams the store straight into another instance's `ImportBatch`; `Clear` deletes
  exactly what a prior `Export`/`Transfer` captured. Archives preserve full state (timestamps, recall
  history, groups, summary flags, links), are idempotent by id, and are the one format that moves
  between drivers. **`archive.scheduledExport.intervalHours`** takes one on a schedule and keeps the
  newest `archive.scheduledExport.keep` — see
  [Scheduled export](configuration.md#scheduled-export), and alert on
  `HippocampusScheduledExportStale`, since a backup nobody notices failing is worse than none.

What none of these reaches is an archive or backup already written: erasing a group, or a person's
records, removes them from the store and leaves them in every backup taken before. Keeping backups
on a bounded rotation is what bounds how long erased data survives in them.

**Driver migration** (e.g. SQLite → Postgres) uses the same path: `Export` from the source, `Import`
into a fresh target. Record ids compare byte-for-byte across all three drivers, so identity is
preserved across the move.

### Schema versions, upgrades, and rollback

The store carries a schema version, recorded in a `schema_migrations` table and logged on every
startup:

```text
database schema at version 12 (postgres)
```

To read it from a store that is **not** running — which, after a refused downgrade, is the situation
you are in:

```sh
hippocampus --schema-version -c config.json
```

```text
dialect:   postgres
version:   11
supported: 12
status:    current - nothing pending; the newer versions this build declares do not apply to this dialect

applied migrations:
  1   core_tables                2026-09-01 03:50:38Z
  2   core_columns               2026-09-01 03:50:38Z
  ...
```

It takes no lock and runs no DDL, so it is safe to run beside a live instance, and it exits non-zero
when the store is newer than the binary reading it — which is what a deployment script should gate
on. A store recorded _below_ this build's newest version is not necessarily behind: a migration that
only applies to one dialect is never recorded on the others, so the `status` line, not the numbers,
is what says whether anything is pending.

`--output json` renders the same report for a script:

```sh
hippocampus --schema-version --output json -c config.json
```

```json
{
  "dialect": "sqlite",
  "status": "current",
  "version": 12,
  "supported": 12,
  "has_ledger": true,
  "pending": [],
  "applied": [
    {
      "version": 1,
      "name": "core_tables",
      "applied_at": "2026-09-01T05:47:43Z"
    }
  ]
}
```

`status` is the field to branch on — `current`, `behind` or `ahead` — and it accounts for the
dialect-gated case the two version numbers cannot. `has_ledger` is `false` for a store written
before schema versions existed, which is what separates its `"version": 0` from a real version zero
that no release ever wrote. `pending` and `applied` are always arrays, never `null`, and an
`applied_at` the store never recorded is `null` rather than a date in year one.

The report goes to stdout and every diagnostic to stderr, so the JSON stays parseable even on the
`ahead` path, where the process also exits non-zero:

```sh
if ! hippocampus --schema-version --output json -c config.json > report.json 2> error.log; then
  jq -r .status report.json # "ahead" - do not start this build against this store
fi
```

Upgrading is automatic and needs no step of yours: a newer build applies whatever migrations the
store has not seen, in order, and logs what it is doing.

```text
upgrading the database schema from version 10 to 12
database schema at version 12 (postgres)
```

**Rolling back to an older build is refused**, rather than silently allowed. A store recorded at a
version the running build does not know about fails to open:

```text
database schema is newer than this build supports: the store records schema version 14, and this
build understands up to 12. It was written by a newer Hippocampus; downgrading is not supported
(see CHANGELOG.md). Run the newer version against it, or restore a backup taken before the upgrade
```

That is the message an aborted upgrade produces, and the two ways out are the ones it names: put the
newer build back, or restore the backup you took first. **Take one before upgrading** — the older
binary cannot open the store afterwards, so the backup is the only rollback there is.

On a shared store the migration run takes a cross-instance lock, so several instances starting
together queue rather than racing; the first to arrive migrates and the rest find the work done.

The read-only tooling (`--backfill-search`) applies the same version check, and tolerates a store
written before versions were recorded at all.

## Graceful shutdown

On `SIGINT`/`SIGTERM` the service shuts down in order: report not-ready (`/readyz` answers `503`
`shutting down` and the gRPC health status turns `NOT_SERVING`), stop the HTTP gateway, drain in-flight gRPC
calls (`GracefulStop`, bounded by `shutdown.timeoutSeconds` — default 10 s — so a stuck call cannot
hang shutdown, e.g. a long `Export`/`Transfer` gets to finish), stop the background sleep loop and
stats ticker (waiting for any in-flight sleep cycle to drain), flush observability, then close the
database — which releases the Postgres/MySQL instance lock. A supervised restart can then start a
fresh instance immediately. `shutdown.timeoutSeconds` bounds each of the gateway-drain, gRPC
graceful-stop, and observability-flush phases; raise it for a slower store whose in-flight work
legitimately needs longer to finish.

Under Kubernetes, `SIGTERM` and the endpoint removal happen at the same time, so a pod that shut its
listeners at once would refuse the requests still being routed to it until every node caught up.
The shipped manifests close that window with a `preStop` sleep of 5 seconds ahead of the signal, and
a `terminationGracePeriodSeconds` covering the sleep plus three `shutdown.timeoutSeconds` phases;
raise the grace period with the timeout. The client-side components follow the same order: `/readyz`
fails from `SIGTERM` on while they finish their in-flight work.

## Observability

OpenTelemetry tracing and metrics are optional (see
[Observability](configuration.md#observability)). Traces are exported over OTLP/gRPC. Metrics reach
a backend by either or both of two routes — pushed over OTLP/gRPC, or served for a Prometheus to
scrape — and which of them you use changes nothing else on this page: the instruments, their
attributes, and every alert expression below are identical either way.

### Getting the metrics out: push or scrape

- **`observability.metrics.enabled`** installs the OTLP/gRPC exporter, which pushes to the collector
  at `observability.otlp.endpoint` on `observability.metrics.exportIntervalSeconds`. This is the
  route the bundled `grafana/otel-lgtm` profile uses, and the one to take if you already run an
  OpenTelemetry collector.
- **`observability.prometheus.enabled`** serves the same metrics in the Prometheus text format at
  `observability.prometheus.path` (default `/metrics`) on `observability.prometheus.port` (default
  **9464**), for Prometheus to pull. Take this route on a cluster running kube-prometheus-stack, or
  anywhere a Prometheus already exists: without it that deployment has to run an OpenTelemetry
  collector purely as a protocol adapter. The Kubernetes overlays under `deploy/k8s/` ship with it
  on, annotated for scraping.

The endpoint is on a **listener of its own**, not the gateway, and that is a deliberate constraint
rather than an implementation detail. The gateway is the public surface — the JSON API, the console,
the OpenAPI document — and frequently what an ingress exposes; a scrape endpoint there would hand
every API caller the store's size, its capacity pressure and its RPC rates, while putting it behind
a token instead would put it out of reach of most scrapers. `observability.prometheus.bindAddress`
restricts the interface it binds, which is what to set on an instance reachable from outside its own
network. Scrapes never appear in `hippocampus.rpc.*` for the same reason the probes do not: they do
not pass through the gateway at all.

Traces have no scrape equivalent, so a deployment that wants them needs a collector however its
metrics travel.

The [client-side components](#client-side-components) take the same choice as a `--prometheus` flag
and serve `/metrics` on the `--health-port` they already listen on, rather than a port of their own.

### Request metrics (RED)

Two instruments describe the request surface itself, and are what an SLO is built on:

- **`hippocampus.rpc.requests`** — a counter of RPCs served. Rate and error rate both come from it.
- **`hippocampus.rpc.duration`** — a histogram of server-side duration in seconds.

Both carry the same four low-cardinality attributes, so a rate and a latency quantile for the same
slice of traffic are filtered identically:

| Attribute   | Values                                | Notes                                                                                                                                    |
| ----------- | ------------------------------------- | ---------------------------------------------------------------------------------------------------------------------------------------- |
| `transport` | `grpc`, `http`                        | The gateway is instrumented separately, since it calls the service directly and never runs the gRPC interceptor chain.                   |
| `rpc`       | the bare RPC name, e.g. `StoreMemory` | Named identically on both transports, so one query sums a call across them. `unknown` for a request rejected before routing.             |
| `code`      | a gRPC code name, or an HTTP status   | The transport's own code. The gateway maps several gRPC codes onto one status, so it reports the status rather than a guessed-back code. |
| `outcome`   | `ok`, `client_error`, `server_error`  | The uniform classification across transports — see below.                                                                                |

`outcome` is three-valued rather than a success flag on purpose. A client sending malformed or
unauthorised requests is not the service failing, so **alert on `outcome="server_error"`**; a rising
`client_error` rate is worth looking at but is usually a caller to talk to, not a page.

Two scoping decisions worth knowing:

- **Only the RPC surface is counted.** The health and readiness probes, the console and its
  front-channel config, the login endpoints, and the static OpenAPI document are excluded — a
  probe's steady tick in the denominator would make every error-rate query meaningless.
- **A request rejected before it could be routed** — a bad token, an oversized body, an unmatched
  path — is counted with `rpc="unknown"`. It is deliberately not named from its path: a path carries
  memory and event ids, and so unbounded metric cardinality.

A recovered panic is _not_ counted here (the request unwinds with no status to classify); it appears
as `hippocampus.panics_recovered` instead, which is the metric to alert on for that case.

### Alert rules

The alert set is shipped, not just described: `deploy/observability/prometheus-alerts.yaml` is a
Prometheus rule file covering the failures below, ready to load with `rule_files:`, lift into a
prometheus-operator `PrometheusRule` `spec:`, or `mimirtool rules load`. Sixteen rules in two
groups, each with a `description` saying what to do about it and a `runbook_url` back into this
document.

Every expression is written against the series names the OTLP-to-Prometheus translation produces,
which is what the scrape endpoint above serves as well — a collector in between is optional, not
assumed. (The exporter's translation strategy is pinned rather than left to its default, since the
default follows a global setting in `prometheus/common` that would otherwise leave the dots in the
instrument names; `TestScrapeNamesMatchTheAlertRules` holds the two together.)

`hippocampus` is the service: server error rate, request latency, sleep-cycle failures, no
consolidator at all, capacity pressure, over capacity, retention consuming the capacity target,
rate-limit rejections, search-index drops, and recovered panics.

`hippocampus-clients` is the components that _dial_ it — see
[Client-side components](#client-side-components) below for what those nine ask and why.

Three things to know before deploying them, and the file repeats each at the rule it applies to:

- **The thresholds are starting points.** The 1% error ratio and the 1s p95 budget are whatever your
  SLO says they are; the capacity thresholds depend on `consolidation.capacityPressureExponent`.
- **A rule for a feature you have not configured stays silent rather than broken.** The capacity,
  retention, and search rules read metrics the service only publishes when the corresponding setting
  is on, and an expression over an absent metric returns nothing.
- **Every expression aggregates `by (service_name)`** — `observability.serviceName`, which names the
  store rather than the process: replicas of one store share a name and re-aggregate into one alert
  ([the one-instance-per-store model](#deployment-model-one-consolidating-instance-per-store)),
  while separate stores sharing one Prometheus stay separate. Give each store its own
  `observability.serviceName`, or an alert will name the wrong one.

The one rule that is _about_ absence is `HippocampusConsolidatorAbsent`, and it is how the
[instance-lock keepalive](#the-instance-lock-keepalive-server-drivers) exiting the consolidator
becomes visible: a process that has exited publishes nothing, so no counter of failures can catch
it, and the question has to be asked the other way round — has a cycle completed for this store in
the last hour. Keep that window comfortably above `sleep.periodSeconds`. It asks in PromQL rather
than through an alerting engine's no-data policy, so Prometheus and Grafana answer it identically,
and it asks twice: `absent_over_time` for the metric vanishing from the whole deployment, and a
`count` over stores whose success counter has not advanced for a consolidator that is up but
wedged — which `absent_over_time` cannot see, the counter still being there. What neither half
catches is one store's instance disappearing while others still report: its series simply go stale
and drop out. That needs an inventory of what _should_ be reporting, which Prometheus does not have
and a liveness probe does.

The same thirty-one rules are provisioned into the bundled Grafana below, so the demo stack alerts as
well as draws; see [deploy/observability/README.md](../deploy/observability/README.md). Neither file
provisions a contact point — where alerts should be delivered is deployment-specific.

Writing a new rule has one constraint that is not obvious from the Prometheus file: the Grafana copy
thresholds each rule's query at `gt 0`, so an expression must return a **positive number** while it
should be firing. A rule whose firing value is zero evaluates correctly in Prometheus and is silent
in Grafana.

### Domain metrics

Metrics worth alerting on in production:

- `hippocampus.capacity_pressure` and `hippocampus.used_bytes` — how full the store is; sustained
  high pressure means eviction is doing heavy work and the store is at its bound.
  `hippocampus.capacity_bytes` carries the configured target alongside it, so an alert can compare
  the two without hard-coding the limit in the query.
- **`hippocampus.retained_bytes` against `hippocampus.capacity_bytes` — the one to alert on if you
  set a retention floor.** Retention _overrides_ the capacity target, so once retained bytes reach
  the capacity the store cannot be brought back under it however hard eviction runs; eviction will
  keep running, find nothing it is allowed to delete, and the store will grow until the retained
  data ages out. `hippocampus.memories.retained` is the same measure as a count. Both are recorded
  once per sleep cycle, and **only when both `consolidation.minimumRetentionInDays` and
  `consolidation.capacityBytes` are set** — the pair costs one aggregate scan per cycle and means
  nothing without a capacity target to be measured against, so nothing else pays for it. The
  service also logs a warning when retained bytes reach the capacity, for deployments not running a
  metrics stack.
- `hippocampus.external_bytes` against `hippocampus.capacity_external_bytes` — the same pair for the
  [external capacity axis](consolidation.md#the-external-capacity-axis), the payload this store only
  points at. Published only when `consolidation.capacityExternalBytes` is set, because the sum is not
  otherwise measured; `hippocampus.retained_external_bytes` is retention's hold on that axis, and
  carries the same warning for the same reason. Note that `used_bytes` and `external_bytes` measure
  different resources and are never comparable with each other.
- `hippocampus.sleeps` (with the `success` attribute) and `hippocampus.sleep.duration` — a run of
  `success=false`, or a duration climbing toward `sleep.periodSeconds`, signals trouble.
- `hippocampus.memories.evicted` / `hippocampus.events.evicted` — eviction volume per cycle, with
  `hippocampus.bytes.evicted` the estimated bytes reclaimed (how much has been reaped).
- `hippocampus.export.scheduled.last_success` / `hippocampus.export.scheduled.interval` — when the
  last scheduled export completed, and how often one is meant to; the staleness alert compares them.
- `hippocampus.memories.expired` — memories taken for being older than
  `consolidation.maximumRetentionInDays`, measured from when they were stored.
- `hippocampus.memory.body_bytes` — a histogram of stored memory-body sizes (how much data each
  write carries); the sum tracks ingest volume and the distribution surfaces outlier blobs.
- The `hippocampus.memories.count` / `hippocampus.events.count` gauges — store growth.
- `hippocampus.panics_recovered` (by `transport`) — a gRPC or gateway handler panicked and was
  recovered (the request got `Internal`/`500` and the process survived); any non-zero value is a
  bug worth investigating.

### Every instrument the service exports

The list above is what to alert on. This is everything, for building a dashboard or reading an
unfamiliar series name off one. Names are as OTLP carries them; a Prometheus-backed datasource
renames each on ingest, replacing the dots with underscores and suffixing counters with `_total` and
histograms with `_bucket`/`_sum`/`_count` (`hippocampus.sleeps` is queried as
`hippocampus_sleeps_total`, `hippocampus.sleep.duration` as `hippocampus_sleep_duration_seconds`).

Every attribute here is bounded to a handful of values — a bool, a small closed enum, or the RPC
name. **Nothing carries an id, a group, a client id, or anything else a caller controls**, which is
what makes the whole set safe to keep at full resolution.

| Metric                                       | Type          | Attributes                            | What it counts                                                                                                         |
| -------------------------------------------- | ------------- | ------------------------------------- | ---------------------------------------------------------------------------------------------------------------------- |
| `hippocampus.rpc.requests`                   | counter       | `transport`, `rpc`, `code`, `outcome` | RPCs served — see [Request metrics](#request-metrics-red)                                                              |
| `hippocampus.rpc.duration`                   | histogram (s) | as above                              | Server-side duration of the same calls                                                                                 |
| `hippocampus.panics_recovered`               | counter       | `transport`                           | Handler panics caught by the recovery middleware                                                                       |
| `hippocampus.ratelimit.rejected`             | counter       | `transport`, `scope`                  | Requests refused by the [rate limiter](#rate-limiting)                                                                 |
| `hippocampus.ratelimit.clients`              | gauge         |                                       | Principals currently holding a per-client bucket                                                                       |
| `hippocampus.tls.certificate_not_after`      | gauge         |                                       | Unix seconds at which the serving certificate expires — see [Certificate rotation](#certificate-rotation)              |
| `hippocampus.memories.stored`                | counter       |                                       | Memories accepted and written                                                                                          |
| `hippocampus.memories.rejected`              | counter       | `reason` (`invalid`/`insignificant`/`duplicate`) | Writes refused — `insignificant` is the decay model working and `duplicate` an id already held, neither a fault |
| `hippocampus.memories.recalled`              | counter       |                                       | Memories reinforced by `RecallMemories` or a reinforcing search                                                        |
| `hippocampus.memories.deleted`               | counter       |                                       | Memories deleted by a client, not by decay                                                                             |
| `hippocampus.memories.consolidated`          | counter       | `has_event`                           | Memories forgotten by the sleep cycle                                                                                  |
| `hippocampus.memories.evicted`               | counter       |                                       | Memories deleted to meet the capacity target                                                                           |
| `hippocampus.memories.searched`              | counter       | `reinforce`                           | Memories returned by content search, by whether the search reinforced them                                             |
| `hippocampus.memories.summarised`            | counter       |                                       | Memories replaced by a summary                                                                                         |
| `hippocampus.memories.count`                 | gauge         | `has_event`                           | Memories currently stored                                                                                              |
| `hippocampus.memories.retained`              | gauge         |                                       | Memories inside the retention window, exempt from both decay paths                                                     |
| `hippocampus.memory.body_bytes`              | histogram     |                                       | Size of each accepted memory body                                                                                      |
| `hippocampus.bytes.evicted`                  | counter       |                                       | Estimated bytes reclaimed by eviction                                                                                  |
| `hippocampus.external_bytes.evicted`         | counter       |                                       | External payload bytes eviction released elsewhere                                                                     |
| `hippocampus.retained_bytes`                 | gauge         |                                       | Stored bytes held by the retention window                                                                              |
| `hippocampus.retained_external_bytes`        | gauge         |                                       | External payload bytes held by the retention window                                                                    |
| `hippocampus.events.stored`                  | counter       |                                       | Events accepted and written                                                                                            |
| `hippocampus.events.rejected`                | counter       | `reason`                              | Event writes refused, classified as memories are                                                                       |
| `hippocampus.events.deleted`                 | counter       |                                       | Events deleted by a client                                                                                             |
| `hippocampus.events.merged`                  | counter       |                                       | `MergeEvents` calls that moved memories                                                                                |
| `hippocampus.events.consolidated`            | counter       | `has_memories`                        | Events forgotten by the sleep cycle                                                                                    |
| `hippocampus.events.evicted`                 | counter       |                                       | Events dropped because eviction took their last memory                                                                 |
| `hippocampus.events.count`                   | gauge         |                                       | Events currently stored                                                                                                |
| `hippocampus.sleeps`                         | counter       | `success`                             | Sleep cycles run                                                                                                       |
| `hippocampus.sleep.duration`                 | histogram (s) |                                       | How long a full cycle took                                                                                             |
| `hippocampus.capacity_pressure`              | gauge         |                                       | The threshold multiplier the last cycle computed                                                                       |
| `hippocampus.used_bytes`                     | gauge         |                                       | Bytes the store occupies (only with a byte capacity set)                                                               |
| `hippocampus.capacity_bytes`                 | gauge         |                                       | The configured target, so a query need not hard-code it                                                                |
| `hippocampus.external_bytes`                 | gauge         |                                       | Payload the store points at elsewhere (only with an external capacity set)                                             |
| `hippocampus.capacity_external_bytes`        | gauge         |                                       | The configured external target, alongside `external_bytes`                                                             |
| `hippocampus.ancillary_bytes`                | gauge         | `component`                           | Estimated bytes in the tables _outside_ the capacity target — the forgotten log, the search outbox, the callback queue |
| `hippocampus.disk_bytes`                     | gauge         |                                       | What the engine says the counted tables _really_ occupy — read against `used_bytes` (PostgreSQL, MySQL)                |
| `hippocampus.index_bytes`                    | gauge         | `table`, `index`                      | Bytes one index really occupies (PostgreSQL only)                                                                      |
| `hippocampus.index_entries`                  | gauge         | `table`, `index`                      | Entries that index holds — divide `index_bytes` by it (PostgreSQL only)                                                |
| `hippocampus.purges`                         | counter       | `success`                             | `Purge` calls                                                                                                          |
| `hippocampus.tombstones`                     | gauge         |                                       | Records held by the [forgotten log](#what-was-forgotten--the-forgotten-log)                                            |
| `hippocampus.tombstones.deleted`             | counter       | `manual`                              | Forgotten-log records removed, by request or by the caps                                                               |
| `hippocampus.significance_levels`            | gauge         |                                       | Distinct significance values the registry holds, measured each cycle                                                   |
| `hippocampus.significance_levels.reaped`     | counter       |                                       | Registry levels removed after carrying nothing for longer than the retention window                                    |
| `hippocampus.summarisation_candidates`       | gauge         |                                       | Events the last scan flagged as worth condensing                                                                       |
| `hippocampus.summaries.created`              | counter       |                                       | Summary memories written                                                                                               |
| `hippocampus.summarisations`                 | counter       | `success`                             | Embedded-LLM generation calls                                                                                          |
| `hippocampus.exports`                        | counter       | `success`                             | `Export` runs                                                                                                          |
| `hippocampus.imports`                        | counter       | `success`                             | `Import`/`ImportBatch` runs                                                                                            |
| `hippocampus.transfers`                      | counter       | `success`                             | `Transfer` runs                                                                                                        |
| `hippocampus.records.exported`               | counter       | `kind` (`event`/`memory`)             | Rows written to an archive or streamed to a target                                                                     |
| `hippocampus.records.imported`               | counter       | `kind`                                | Rows ingested                                                                                                          |
| `hippocampus.records.cleared`                | counter       | `kind`                                | Rows deleted by a manifest-scoped clear                                                                                |
| `hippocampus.search.indexed`                 | counter       | `success`                             | Documents written to the OpenSearch index                                                                              |
| `hippocampus.search.deleted`                 | counter       | `success`                             | Deletes applied to it                                                                                                  |
| `hippocampus.search.dropped`                 | counter       | `op`, `reason`                        | Index operations abandoned — `reason` is `queue_full` or `apply_failed`                                                |
| `hippocampus.search.queue_depth`             | gauge         |                                       | Operations queued for the apply worker — what `opensearch.queueSize` is tuned on                                       |
| `hippocampus.search.queue_capacity`          | gauge         |                                       | `opensearch.queueSize`, exported so utilisation need not hard-code it                                                  |
| `hippocampus.search.outbox_depth`            | gauge         |                                       | Index deletions recorded but not yet applied — the backpressure signal                                                 |
| `hippocampus.search.outbox.applied`          | counter       |                                       | Queued deletions drained and accepted by the index                                                                     |
| `hippocampus.search.outbox.abandoned`        | counter       |                                       | Queued deletions discarded at the caps, left to the stale sweep                                                        |
| `hippocampus.search.stale_documents_removed` | counter       |                                       | Documents the sweep removed because the store no longer holds the memory                                               |
| `hippocampus.search.documents_healed`        | counter       |                                       | Documents the sweep wrote because the index did not hold a memory the store does                                       |
| `hippocampus.search.queries`                 | counter       | `success`                             | Content searches served by it                                                                                          |
| `hippocampus.callbacks.queue_depth`          | gauge         |                                       | [Callback](configuration.md#outbound-callbacks) deliveries recorded but not yet accepted — the backpressure signal     |
| `hippocampus.callbacks.delivered`            | counter       | `kind`, `outcome`                     | Callback delivery attempts, by what they were about and whether they landed                                            |
| `hippocampus.callbacks.abandoned`            | counter       |                                       | Queued callbacks discarded at the caps or undecodable — unlike an index deletion, nothing recovers these               |
| `hippocampus.callbacks.delivery.duration`    | histogram (s) | `outcome`                             | How long one delivery attempt took                                                                                     |
| `hippocampus.forgetting.stalls`              | counter       | `reason`                              | Sleep cycles whose decay passes were held off — the store has stopped forgetting                                       |

Three things the shape of this list says. The **`search.*` instruments exist only under
`opensearch.enabled`** — the built-in content index runs inside the primary write and has no queue to
drop from and no sweep to run, so `hippocampus.search.dropped` staying absent is the healthy state on
a default deployment rather than a gap. **`used_bytes`, `capacity_bytes`, `memories.retained`,
`retained_bytes` and `tombstones` are published only when the setting behind each is on**, which is
what lets an alert over them stay silent rather than broken on a store that does not use them. And
the **gauges are recorded once per sleep cycle**, not on a scrape interval: between cycles they
report the last cycle's answer, so a scrape faster than `sleep.periodSeconds` sees a step function
and not a smooth line.

### Client-side components

The [ingestor](ingestor.md#observability), the [broker bridges](eventsource.md#observability) and the
[object-storage agents](objectstore.md) are separate processes that dial a Hippocampus instance, and
they are instrumented on the same model:
`--metrics` exports over OTLP/gRPC, `--prometheus` serves the same metrics for scraping, and
`--health-port` (**8090 by default**) serves `/livez` (liveness, also as `/healthz`) and `/readyz`
(whether the instance they write to can actually serve, and not shutting down). The scrape endpoint rides on that same health port at
`/metrics` rather than taking one of its own — these are processes already asking for one
operational port they did not previously need, and everything served there is the same kind of
thing. Turning `--health-port 0` off therefore takes the metrics with it, which is logged. Both
surfaces are documented in full on those pages; three things are worth knowing at the operations
level.

- **`hippocampus.client.rpc.requests` / `.duration`** are the client-side RED metrics, emitted by
  every component that dials the service, with an `endpoint` attribute (`source`/`target` for the
  ingestor, `hippocampus` for a bridge). `outcome` is classified exactly as the service classifies
  its own, so "the error rate" means one thing on both sides of the connection.
- **`hippocampus.ingestor.seconds_since_last_pass` is the staleness signal.** Every other metric
  these components emit is a counter, and a counter that stops advancing is indistinguishable from a
  component with nothing to do; this one rises on its own whether the loop is stalled, deadlocked or
  dead. Alert on it rather than on the absence of promotions.
- **Tenancy is `--metrics-group`**, a per-process label — the resource attribute `hippocampus.group`,
  which a Prometheus-backed datasource carries as the label `hippocampus_group` — stamped on both the
  resource and each metric (the duplication is what avoids a `target_info` join in every query). It is deliberately never read
  off the records: a bridge derives a memory's group from the message subject by default, so a
  per-record label would be unbounded.

These components have their own group in the shipped alert rules, `hippocampus-clients`, and it
exists because of an outage. A Bluesky bridge on the public demo spent hours re-presenting one record
it could never store, at a cursor that never moved: the process was up, its `/healthz` answered, the
store kept filling from a second goroutine, and nothing was being reinforced. It was found by hand.
Nine rules:

| Alert                                 | Fires when                                                        | Severity |
| ------------------------------------- | ----------------------------------------------------------------- | -------- |
| `HippocampusBridgeDuplicateStream`    | over 80% of a bridge's messages are records the store already had | warning  |
| `HippocampusBridgeNotConsuming`       | a bridge is publishing metrics and handling no messages at all    | warning  |
| `HippocampusBridgeWriteFailing`       | over 5% of a bridge's messages fail to transform or store         | critical |
| `HippocampusClientTokenRejected`      | a client's calls are refused `Unauthenticated`/`PermissionDenied` | critical |
| `HippocampusIngestorPassStale`        | no ingestor pass has completed in fifteen minutes                 | critical |
| `HippocampusIngestorRuleErrors`       | an ingestor rule is erroring rather than matching                 | warning  |
| `HippocampusObjectTapNotReinforcing`  | every object read reinforces a memory the store does not hold     | warning  |
| `HippocampusObjectDeletionsFailing`   | the reaper cannot delete the objects behind forgotten memories    | critical |
| `HippocampusObjectDeliveriesRejected` | the reaper is answering forget-callbacks with a 5xx               | warning  |

Two of them are about the same thing from opposite sides. `outcome="exists"` means the store already
held what the message carried — a success, since there is nothing to redeliver, but not work, so a
bridge whose whole stream is duplicates is running and adding nothing. That is what a replayed
subscription, a cursor that has stopped advancing, or a broker redelivering a backlog all look like
from here; the routine duplicates of a _polled_ source are deliberately not counted, so a feed poller
re-reading the same page every minute does not trip it. `HippocampusBridgeNotConsuming` asks the
opposite question, and is a rate rather than an `absent_over_time` for a reason that bounds what
these rules can do at all:

> **A bridge that has exited cannot be alerted on from its own metrics.** It publishes nothing, and
> nothing is exactly what a deployment running no bridge publishes too. So that rule fires only while
> a bridge is up and idle, and the half that notices a process being _gone_ is
> [`topology.components`](#seeing-the-deployment) — declare each bridge and the ingestor there, and
> the service probes the `/readyz` they already serve.

`HippocampusClientTokenRejected` is the silent one, and the only rule in either file that matches on
a status code rather than an outcome: a component authenticating with a static token keeps running
perfectly after that token expires, failing every write for as long as the process lives, and the
service-side error rate calls that a _client_ fault because that is what it is. Against an
IdP-backed service, use the client-credentials grant (`--oidc-client-id`) so the component mints and
refreshes its own tokens.

The last three are the [object-storage agents](objectstore.md), and the first of them is the same
class of fault as the Bluesky outage above — something running perfectly and achieving nothing. The
gateway reinforces a memory id **derived** from the object key, so if the pointer-memories were
written under any other scheme every recall lands on nothing; and a recall that lands on nothing is
by design a no-op, indistinguishable from a memory the store has already forgotten. Nothing errors.
`HippocampusObjectTapNotReinforcing` watches the hit rate for exactly that, and the agent logs the
same finding at Warn every five minutes.

The other two are about the actuator, where a failure is not a lost notification but an orphaned
payload: the far system keeps holding data nothing will ever mention again, and the leak grows
precisely with how well the decay cycle is working. `HippocampusObjectDeletionsFailing` is usually
credentials that cannot delete from the bucket, which no amount of retrying fixes.
`HippocampusObjectDeliveriesRejected` means the agent is answering deliveries with a 5xx — correct
behaviour, since that is what makes the service replay them, but a sustained rate backs up the
callback queue, and what happens then is
[`callbacks.backlogPolicy`](configuration.md#outbound-callbacks)'s to decide.

The same series are on the bundled Grafana dashboard, in a **Client-side components** row that is
collapsed by default — the panels are empty unless something is running with `--metrics`.

For local viewing (evaluation, soak testing, dashboard work) every compose stack carries an
optional all-in-one `grafana/otel-lgtm` collector (Grafana + Prometheus + Tempo + Loki) behind a
compose `observability` profile — off by default, so a stack run without it never attempts an
export or logs a failure. Start it and tell the service to ship to it in one command:

```sh
OBSERVABILITY=true docker compose --profile observability up --build
```

Grafana is then at `http://localhost:3000`, opening on a pre-built **Hippocampus** dashboard
(provisioned from `deploy/compose/observability/`, set as the home page) that charts request rate,
error rate and latency (overall and per RPC), then ingest, forgetting (consolidation/eviction volume
and bytes reclaimed), capacity/used-bytes, and sleep-cycle duration from the metrics above. The alert
rules above are provisioned with it (as Grafana-managed rules, since Grafana cannot read a Prometheus
rule file), so firing rules appear under **Alerting → Alert rules**; nothing is notified, as the demo
stack has nowhere to send it. The demo soak harness has the same switch: `OBSERVABILITY=1 ./demo/run.sh`
launches the collector (via docker or podman) with the same dashboard and rules and points the
service at it — note that the demo deliberately runs its store at the capacity cap, so the capacity
alerts firing during a soak is them working. Metrics stay off unless the collector is present,
which is what keeps a plain run quiet — enabling export without a reachable OTLP endpoint is the
only thing that produces export-failure log lines.

Even with observability off, failing requests are visible in the logs at the default `info` level:
a failing RPC logs at Warn (Info for client-fault codes such as `NotFound`/`InvalidArgument`) with
the method, status code, duration, and error, and the HTTP gateway logs `5xx` responses at Warn
(all requests at Debug). Set `stats.intervalSeconds` (default 300; 0 disables) to control the
periodic event/memory count log line.

Identify the running build with `hippocampus --version`, the `version:` line at startup, or the
`version` field in the `GET /livez` (or `/healthz`) body — all report the module version plus the VCS
revision/time embedded at build time. When observability is on, the same version is the OTEL
`service.version` resource attribute.

Health surfaces are unauthenticated and always reachable: the gRPC `grpc.health.v1.Health` service
and the gateway's `GET /livez` (**liveness** — process up, never touches the database; `/healthz` is
the same endpoint under its older name) and `GET /readyz` (**readiness** — also pings the store,
`503` when it is unreachable or once shutdown has begun, and mirrored by the gRPC serving status).
Point a startup and a restart/liveness probe at `/livez` and a load-balancer/readiness probe at
`/readyz` — see [Health and readiness](configuration.md#health-and-readiness). On the server
drivers, review `storage.queryTimeoutSeconds` (see below) so a hung database fails operations
promptly instead of tying up request goroutines and pooled connections.

### Bounding query time on the server drivers

`storage.queryTimeoutSeconds` (default 60; 0 = off) bounds every statement and transaction. The
default is comfortably above a full consolidation scan at the benchmarked sizes, so it protects
against a network partition, storage stall, or lock pileup — any of which can otherwise block a
request goroutine, and its pooled connection, indefinitely, eventually wedging the instance — while
leaving normal operations untouched. Raise it above the longest legitimate operation on a larger
store: the full-store consolidation scan is the tallest pole, so time a sleep cycle on a
representative store and leave generous headroom, or a cycle may be aborted mid-scan. Set it to 0 to
disable the bound entirely (reasonable for embedded SQLite, where a local file rarely hangs).

This server-owned bound is independent of, and complementary to, the caller's own context: an RPC's
deadline or a client that hangs up now propagates all the way to the database driver, so the
server-side work for an abandoned request is aborted rather than run to completion. Whichever bound
fires first — the client's deadline or `queryTimeoutSeconds` — ends the operation. The sleep cycle
is deliberately server-owned (it is not tied to the `Sleep` RPC's deadline), so a manual `Sleep`
call returning does not cut a consolidation short.

### Connection pool sizing (server drivers)

`storage.pool.maxOpenConns` (default 25) and `storage.pool.maxIdleConns` (0 → defaults to
`maxOpenConns`) cap the `database/sql` connection pool on the Postgres/MySQL drivers. Without a cap
`database/sql` opens unlimited connections, so a burst of concurrent RPCs can exhaust the server's
connection slots — one hot replica then starves every other instance, and the consolidator's
instance-lock keepalive, into `too many connections` errors. SQLite is single-connection and ignores
these settings.

Size the pool per instance, then check the fleet total: the **sum of `maxOpenConns` across every
instance** sharing the database must stay below the server's `max_connections`, with headroom for
the consolidator's pinned keepalive connection and any superuser/monitoring reserve. For example,
with Postgres's default `max_connections` of 100 and five instances, 25 each already reaches the
ceiling — lower `maxOpenConns` or raise `max_connections`. Keep `maxIdleConns` at (or near)
`maxOpenConns` so steady load reuses connections instead of churning them open and closed.

## Rate limiting

Off by default; [Rate limiting](configuration.md#rate-limiting) has the keys. Three levels of token
bucket — an instance-wide ceiling, one bucket per authorisation tier, one per caller — of which a
request must pass every level that has a rate. Both transports share the buckets, so a caller cannot
double its allowance by switching between gRPC and the gateway.

**What to set first.** The two that earn their keep on almost any exposed deployment are the global
ceiling and the per-client rule. The ceiling is a survivability bound: it is checked _before_ the
bearer token is verified, so it is the only level that can bound a flood of requests carrying junk
tokens (with an identity provider, that is an RS256 verify per request the service would otherwise
pay). The per-client rule is the fairness one, and is what stops a single misbehaving integration
consuming the ceiling and taking everyone else's service with it. Per-tier limits are the tuning
layer on top — worth setting once you know which class of caller is the noisy one, and best left
off `admin`, so an operator answering an incident is not queued behind a limit meant for
application traffic.

**Sizing.** Start from observed peak on `hippocampus.rpc.requests` and leave real headroom above it:
a global ceiling that bites refuses well-behaved callers along with the rest, which is the one
failure mode of this feature that looks like an outage. The per-client rule can be much tighter,
since it only ever affects the caller that exceeded it. Bursts matter more than they look: a client
that batches its writes needs a burst that covers a batch, or it will be throttled at a rate it is
nowhere near on average.

One consequence to hold in mind while sizing: a request the per-client rule refuses has already
spent a token from the global ceiling, because the ceiling is checked first and counts arrivals. A
single flooding client can therefore exhaust the instance's allowance even while every one of its
own requests is being refused — which is another way of saying the ceiling is a survivability bound
and not a fair-share allocator. (Between the tier and client levels, where both decisions are made
together, a refusal _is_ refunded.)

**Watching it.** `hippocampus.ratelimit.rejected` counts refusals by `transport` and by `scope`
(`global` / `tier` / `client`) — the scope is the whole diagnosis, since `client` is a caller to
talk to and `global` is a limit to raise or an instance to scale out. The shipped
`HippocampusRateLimitRejecting` alert fires on a sustained rejection rate.
`hippocampus.ratelimit.clients` reports how many callers currently hold a bucket; sitting at
`rateLimit.maxClients` means the table is churning — either the deployment has more callers than the
cap allows for, or something is minting identities — and a churning table hands each evicted caller
a fresh full bucket on its next request. Raise the cap.

**What is never limited**: `/healthz`, `/readyz`, the console and its front-channel config, the
login endpoints, and `/v1/openapi.json`. Throttling a readiness probe under load would get the
instance restarted rather than protected.

**Identity, and the proxy caveat.** A caller is its authenticated `client_id` (then the token's
`sub`, then its address). With authentication off, or for an unauthenticated request, the address is
all there is — per-host rather than per-application. Behind a reverse proxy every request arrives
from the proxy's address, which collapses every caller into one bucket; `rateLimit.trustForwardedFor`
is the fix, and is **off by default** because believing a caller-supplied header on a directly
reachable listener lets any caller mint itself an unlimited number of buckets. Set it only when a
proxy you control overwrites `X-Forwarded-For` rather than appending to it.

## Group scoping and the trust boundary

**A shared store is a shared trust domain by default.** `group` is a label, not an access control:
every token that can read can read everything until tokens are bound to groups. Binding them
([group scoping](configuration.md#group-scoping)) is a **soft** partition — records are scoped, but
the decay dynamics stay store-global, so one group's write volume still influences what another
forgets. Hard isolation is one instance per tenant.

Which of the two you need, and the four specific things soft partitioning does not give you, are in
**[Security · Group scoping and the trust boundary](security.md#group-scoping-and-the-trust-boundary)**.

### Removing a group's records

`DeleteMemoriesByFilter` and `DeleteEventsByFilter` (`hippo memory delete-by-filter` /
`hippo event delete-by-filter`) delete by predicate rather than by id, which is what offboarding a
group needs — the alternative is paging the listing and deleting by id while the store changes
underneath, and then deleting the emptied events one at a time.

Both take the same filters their listings take, and the service builds **one** predicate for the
pair, so the listing is the dry run:

```bash
hippo memory list --group acme --limit 1                                  # total_count is what would go
hippo export --group acme                                                 # their copy, if owed
hippo memory delete-by-filter --group acme --delete-empty-events --yes
hippo event delete-by-filter --group acme --delete-memories --yes
```

Four things worth knowing:

- **An empty filter is refused**, not read as "everything". That operation is `Purge`, which is a
  different RPC and is refused to a group-scoped token entirely.
- **`--max-deletions` bounds one call**, and the response's `complete` says whether anything still
  matches — so a large partition can be worked through in steps, checking after each.
- **The deletion is the ordinary one**: links are pruned, the search index is updated in the same
  transaction the rows go in, and callbacks fire exactly as they do for a delete by id. It writes no
  forgotten-log tombstone, for the same reason `DeleteMemories` does not — a client that asked for a
  deletion already knows.
- **Emptied events are opt-in.** Without `--delete-empty-events` an event whose memories all went
  stays until a decay cycle collects it; an event that still holds a memory is never touched either
  way.

## Security

Authentication, TLS and rate limiting are **off by default**, and nothing here turns itself on — so
any deployment reachable beyond localhost needs a deliberate pass over
**[the security guide](security.md)**. It covers authentication and key rotation, the role tiers,
group scoping, transport and gateway hardening, the console's boundary, where memory content can
leave the process, what the service does not do (no encryption at rest), and a hardening checklist
to work down.

Two operational notes belong here rather than there:

- [Rate limiting](#rate-limiting) is documented above, with its bucket hierarchy and tuning — the
  security guide only says to turn it on.
- [Seeing the deployment](#seeing-the-deployment) is where the topology view's redaction is
  described in context; the security guide records only that every address it reports is redacted.

### Certificate rotation

With `tls.enabled`, both listeners serve the certificate at `tls.certFile`/`tls.keyFile`, read
again whenever either file changes, checked once a minute. A renewal by cert-manager, an ACME client
or anything else that rewrites those files is picked up without a restart. The log says
`reloaded the rotated TLS certificate` with the new expiry. A pair caught half-written, with the
certificate renewed and the key not yet, is logged and ignored, and the previous certificate keeps
serving until both files read cleanly. The client CA bundle (`tls.clientCaFile`) is read only at
startup.

`hippocampus.tls.certificate_not_after` reports the serving certificate's expiry in unix seconds.
The shipped `HippocampusTLSCertificateExpiring` alert fires when it is within 14 days, and keeps
firing past expiry. The service renews nothing itself, so that alert means the renewal pipeline has
stopped writing the files. Check the issuer, and that it writes to the path `tls.certFile` names.

### The audit trail

Every call to an administrative mutation leaves one Info line carrying `audit=true`. The audited
RPCs are those the policy table puts at the `admin` tier and that are not reads: `Purge`, `Sleep`,
`DeleteMemoriesByFilter`, `DeleteEventsByFilter`, `DeleteForgottenMemories`, `DeleteCallbackQueue`,
`Export`, `Transfer` and `Clear`. Each line names:

- `rpc`, and `client_id` (`none` without auth);
- `outcome`, the gRPC code;
- `request`, the call's own JSON (its filter, manifest id or object key);
- on success, `response`, with what was removed or moved.

A refused or failed attempt is recorded as well as a success. The lines go wherever the service's
log goes, so ship them somewhere the people they audit cannot edit. A new administrative RPC joins
the trail by being declared in the policy table, since a test fails until it is audited.
