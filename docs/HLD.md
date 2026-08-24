# Tandem — High-Level Design

**Version:** 1.0  
**Status:** Draft  
**License:** Apache 2.0

---

## 1. Purpose & Scope

Tandem is a Java library that implements the **Transactional Outbox Pattern**, providing reliable, causally-ordered event delivery from a relational database to Apache Kafka — without external CDC infrastructure, Kafka Connect, or two-phase commit.

**In scope:**
- Atomic insertion of outbox messages within existing domain transactions
- Sharded, at-least-once relay from the outbox table to Kafka topics
- CloudEvents (CNCF) as the standard publication envelope (§4.8)
- Per-aggregate happens-before ordering
- Optional cross-aggregate causal ordering via per-aggregate Lamport clocks (opt-in; see §9)
- Idempotent replay for failed or historical messages
- Port-based operational monitoring (`TandemMetrics`; optional Micrometer adapter)
- Optional Spring Boot autoconfiguration with four usage tiers (plain, template, annotation, Spring application events)

**Out of scope:**
- Consumer-side deduplication (responsibility of consuming services)
- Schema registry / Avro / Protobuf serialization (pluggable, not built-in)
- Strict global total ordering across aggregates (only causal — happens-before — ordering is offered, opt-in)
- Vector-clock concurrency *detection* (Lamport clocks order causally but cannot detect concurrency)

### 1.1 Design philosophy — Pareto's Law

Tandem optimises for the **80%**: a service backed by PostgreSQL/MySQL and Kafka that needs reliable, ordered event delivery. For that majority, Tandem must be a near-drop-in — add the dependency, create the table, insert in your existing transaction. Everything the common case needs (per-aggregate ordering, failover, monitoring, replay) works out of the box with sensible defaults.

The hard **20%** — extreme scale, cross-aggregate global causal ordering, exotic datastores, massive analytical fan-out — is served **without taxing the 80%**:

- **Complexity is opt-in, never imposed.** Causal ordering is off by default; Spring is optional; the engine adapters and benchmark harness are separate modules. The simple path stays simple.
- **Sensible defaults over configuration.** The common case should need almost no tuning (`N = cores × 2`, 60s lease, exponential backoff, JSON payload).
- **Provide the key, don't reinvent the engine.** For the 20% that needs a stream processor or exotic ordering, Tandem integrates (Flink / Kafka Streams adapters, the Lamport key) rather than re-implementing those systems.
- **Scope discipline.** A feature that would complicate the 80% path to serve a fraction of the 20% is pushed out of scope or into an optional module — not folded into the core.

**Decision rule:** if a proposed feature makes the common case harder, slower, or more confusing in order to serve a minority case, it does not belong in the core path — make it opt-in, an adapter, or out of scope.

### 1.2 Architecture — Hexagonal (Ports & Adapters)

Where a component has a clear functional core with at least one port and one adapter, Tandem uses the **Hexagonal (Ports & Adapters)** architecture. The core holds the pure logic and *defines* the ports (interfaces); technology-specific modules are *adapters* that implement them. The invariant: **adapters depend on the core; the core never depends on an adapter.** This is already the shape of Tandem's modules:

| Hexagonal role | Tandem |
|---|---|
| Functional core | `tandem-core` — models, contracts, pure logic (Lamport merge, status state machine); zero external runtime deps |
| Ports (defined by the core) | `OutboxRepository` (persistence), `OutboxDispatcher` (publish), `PayloadSerializer`, `TopicRouter`, `CausalContext`, `TracePropagator` (default no-op), `TandemMetrics` (default no-op) |
| Driven (outbound) adapters | `tandem-jdbc` (JDBC persistence), `tandem-kafka` (Kafka publish), `tandem-test` `InMemoryOutbox` (in-memory persistence) |
| Driving (inbound) adapters | `tandem-spring-producer` usage tiers (template, annotation, Spring events); `tandem-admin` REST layer over `AdminService` |
| Observability / consumer-side adapters | `tandem-micrometer` (metrics), `tandem-tracing-otel` (trace capture), `tandem-kafka-streams`, `tandem-flink` |

Two consequences:

- **Testability** (a primary payoff): the core is exercised against the in-memory adapter (`InMemoryOutbox`) with no database, matching the no-mocks testing approach.
- **Pragmatic boundary** (Pareto, §1.1): apply hexagonal only where a real core/port/adapter split exists. Do not impose port-and-adapter ceremony on modules with no swappable boundary (e.g. the BOM, the benchmark harness) — that would be complexity for its own sake.

### 1.3 Minimal client footprint

The part of Tandem the **client application must import** — the **write-side** (the outbox INSERT; §3.2) — must carry the **minimum possible external dependencies, ideally none**.

- `tandem-core` already has **zero runtime dependencies** and stays that way.
- The write-side built on it (core + the JDBC insert in `tandem-jdbc`) must not drag in heavy transitive libraries: **no Kafka client, no CloudEvents SDK, no tracing library, no mandatory JSON binding, and no Spring unless the user opts into a Spring tier.** JDBC itself is the JDK's `java.sql` (not an external dependency); the client supplies the `DataSource`.
- Everything that *requires* an external dependency — the Kafka client, the CloudEvents SDK (§4.8), tracing adapters (§7.1), stream-processing adapters (§9) — lives on the **relay / optional side**, never on the client path.
- Where the write-side genuinely needs a library (e.g. JSON serialization of the payload), prefer the **client's already-present one** (a `provided`/optional dependency) or a **pluggable SPI with no forced default**, rather than bundling a heavy transitive tree.

**Why:** the client must not inherit Tandem's delivery-side dependencies, which would risk version conflicts with its own libraries (dependency hell) and bloat its artifact. This reinforces the split deployment topology (§3.2) and the zero-dependency-core rule, and is a hard constraint on every write-side LLD.

### 1.4 Backward & forward compatibility — every contract, not just the API

Tandem exposes several long-lived contracts: the **REST Admin API**, the **DB schema**
(`tandem_*` tables), and the **published Kafka messages** (the CloudEvents envelope + headers).
All must evolve with **both** backward and forward compatibility — and there is a *structural*
reason this is non-negotiable: the **split deployment topology (§3.2)** lets the client
write-side, the relay, and the Admin API run as **independently-deployed components at
different Tandem versions, sharing the same database and event stream**. A rolling upgrade
therefore *always* has mixed versions reading and writing the same contracts.

- **Backward compatibility (producers/writers evolve additively).** New optional columns,
  optional request/response fields, endpoints, or CloudEvents extension attributes — **never**
  a removal, rename, type change, newly-required field, narrowed range, or changed identifier
  (error `type` slug, event `type`). Breaking changes are a new major version (DB: a versioned
  migration with a transition window; REST: `/v2`).
- **Forward compatibility (readers are tolerant).** An older component reading a newer contract
  must not break on the unknown:
  - **SQL:** select **named columns, never `SELECT *`**; tolerate extra columns; new columns are
    nullable or defaulted.
  - **Kafka / CloudEvents:** ignore unknown headers and extension attributes; `type` /
    `partitionkey` semantics stay stable.
  - **REST:** tolerant readers (ignore unknown fields and enum values); schemas stay open.
- **Over-strict validation is the enemy of forward compatibility** — `SELECT *`,
  `additionalProperties: false`, closed enums that reject unknown values, or strict envelope
  parsing each break a reader the moment the contract grows. This directly shapes the schema
  migration strategy (Q7).

---

## 2. Problem Statement

### 2.1 The Double Write Problem

Writing a state change to a relational database *and* publishing an event to Kafka are two independent I/O operations with no shared transaction coordinator. The naive approach:

```
BEGIN TX
  UPDATE aggregate ...
COMMIT TX
producer.send(event)          ← crash here → event lost
```

Or reversed:

```
producer.send(event)          ← crash here → event sent but DB not updated
BEGIN TX
  UPDATE aggregate ...
COMMIT TX
```

Both orderings produce permanent divergence between database state and the event stream.

### 2.2 Why 2PC Is Not the Answer

Distributed two-phase commit (XA transactions) is theoretically correct but impractical:
- Kafka's producer does not support XA
- 2PC is a distributed availability risk: one slow participant blocks all
- Most JDBC connection pools and ORMs do not support XA in production configurations

### 2.3 The Outbox Solution

The outbox pattern eliminates the dual-write by making the event write part of the same local transaction as the domain mutation:

```
BEGIN TX
  UPDATE aggregate SET version = version + 1 WHERE id = ? FOR UPDATE
  INSERT INTO tandem_outbox (aggregate_id, seq, payload, ...) VALUES (...)
COMMIT TX                        ← both or neither, guaranteed by DB ACID
```

A separate **relay** process reads committed outbox rows and publishes them to Kafka. If the relay crashes after publishing but before marking the row `DONE`, it republishes on restart — a **duplicate**, not a divergence. Consumers handle duplicates (idempotent processing or deduplication on `(aggregate_id, seq)`).

### 2.4 Why the pattern is under-adopted (and where Tandem fits)

The outbox is essential for one specific class of service: those whose emitted events drive *other services' state* (sagas, inventory, payments — anywhere a lost or phantom event causes divergence). It is *not* needed for best-effort eventing (analytics, notifications, cache invalidation). Yet even where it is needed, adoption is low — for mostly avoidable reasons:

- **The risk is invisible and deferred.** The naive `save(); publish();` works ~99.9% of the time; divergence appears only on partial failure and is usually misdiagnosed as a fluke. The cost of skipping the outbox is probabilistic and late; the cost of building it is upfront and certain — so teams under-invest.
- **"Idempotent consumers" are mistaken for the guarantee.** Deduplication handles *duplicates*; it does nothing about *lost events / divergence*, which is the actual double-write failure. Teams feel covered by a mechanism for a different problem.
- **It looks trivial but is full of traps.** "Write a row and poll it" hides `SKIP LOCKED` contention, ordering, mark-DONE-only-after-ack, producer reordering, poison messages, and lease failover. Naive versions appear to work; the bugs surface rarely and are hard to attribute.
- **No lightweight, correct, standard library.** The space is fragmented into heavy CDC (Debezium), heavier opinionated frameworks (Eventuate Tram), weak-ordering Spring-only options (Spring Modulith), or DIY. No framework ships it on by default, so there is no paved road.
- **The "serious" answer is operationally heavy.** Robustness got associated with log-based CDC + Kafka Connect — a separate distributed system — so teams defer the heavy solution and, with it, the pattern entirely.
- **Defaults teach the anti-pattern.** Nearly every "Spring + Kafka" tutorial shows the double-write in the same method. Most teams learn the outbox only after being burned.

**Tandem's wedge:** the avoidable reasons above — no lightweight library, CDC too heavy, DIY traps, no paved road — are exactly what a small, correct, infrastructure-free library addresses. Tandem does not reinvent the pattern; it makes the right thing the easy thing for a team that already has a relational database and Kafka and wants neither a Connect cluster nor a pile of subtle bugs.

---

## 3. Architecture Overview

```
┌─────────────────────────────────────────────────────────────────────┐
│                        Application Process                          │
│                                                                     │
│  ┌──────────────┐   same TX   ┌──────────────────────────────────┐  │
│  │  Domain Code │────────────▶│  outbox table (PostgreSQL)       │  │
│  │  (aggregate  │             │  id, aggregate_id, seq, payload, │  │
│  │   mutation)  │             │  status, locked_by, ...          │  │
│  └──────────────┘             └────────────────┬─────────────────┘  │
│                                                │                    │
│  ┌─────────────────────────────────────────────▼─────────────────┐  │
│  │               WorkerPool  (tandem-jdbc)                        │  │
│  │                                                                │  │
│  │  Worker A      Worker B      Worker C    ...                   │  │
│  │  (buckets 0..)  (buckets ..)  (buckets ..)                     │  │
│  │                                                                │  │
│  │  Aggregates → fixed virtual buckets (by hash);                 │  │
│  │  each bucket owned by one worker → its rows ORDER BY id        │  │
│  │                                                                │  │
│  └────────────────────────────┬───────────────────────────────────┘  │
│                               │                                     │
│  ┌────────────────────────────▼───────────────────────────────────┐  │
│  │               KafkaRelay  (tandem-kafka)                       │  │
│  │                                                                │  │
│  │  producer.send(topic, key=aggregate_id, value=payload)         │  │
│  │  await ack (acks=all, enable.idempotence=true)                 │  │
│  │  UPDATE tandem_outbox SET status=DONE                                 │  │
│  └────────────────────────────┬───────────────────────────────────┘  │
└───────────────────────────────┼─────────────────────────────────────┘
                                │
                    ┌───────────▼───────────┐
                    │    Apache Kafka        │
                    │  (partitioned by       │
                    │   aggregate_id key)    │
                    └───────────────────────┘
```

> **This diagram shows the embedded topology** — the relay runs in the same process as the client. The relay (and the Admin API) can also run as **standalone processes**; only the write-side (the outbox INSERT) must run inside the client. See §3.2.

### 3.1 Module Dependency Graph

```
tandem-core             zero external runtime deps; defines models + ports
tandem-jdbc   ──▶ core   JDBC adapter: outbox INSERT + polling/lease/cleanup (NO Kafka)
tandem-kafka  ──▶ core   Kafka publish adapter (implements the OutboxDispatcher port)

# Spring autoconfig — split by role so the client can avoid Kafka (§3.2); no aggregator
tandem-spring-producer  ──▶ tandem-jdbc                  write-side tiers (client; NO Kafka)
tandem-spring-relay     ──▶ tandem-jdbc + tandem-kafka   relay autoconfig
tandem-relay (runnable) ──▶ tandem-spring-relay          prebuilt standalone relay app

tandem-bom              version alignment only, no code
tandem-test   ──▶ core   (+ optional tandem-jdbc/kafka)

# Optional causal-ordering adapters (see §9)
tandem-kafka-streams ──▶ core   (Kafka Streams TimestampExtractor for the Lamport header)
tandem-flink         ──▶ core   (Flink TimestampAssigner/WatermarkStrategy for the Lamport header)
```

`tandem-core` is the only module with zero external runtime dependencies. All other modules depend on it.

`tandem-spring-producer` (the client's write-side module) provides four optional usage tiers, from lowest to highest abstraction:

| Tier | API | How it works |
|---|---|---|
| **Plain** | Inject `OutboxRepository`, call `.insert()` inside `@Transactional` | No Spring magic; full user control |
| **Template** | `TransactionalOutboxTemplate.execute(supplier)` | Wraps transaction + insert in one call; explicit and testable |
| **Annotation** | `@TransactionalOutbox(aggregateType = "Order")` on a `@Transactional` method | AOP intercept: extracts pending events from the return value after the method completes, then inserts them into the outbox within the same transaction |
| **Spring events** | `ApplicationEventPublisher.publishEvent(event)` inside `@Transactional` | Tandem's in-transaction listener maps each published event to an `OutboxMessage` and inserts it within the *same* transaction |

All four tiers are optional conveniences on top of the core library. Users choose the style that fits their codebase.

#### Annotation tier — constraints and conventions

`@TransactionalOutbox` is a **composed annotation**: it is itself meta-annotated with `@Transactional`, so a transaction is always guaranteed without requiring the user to add both annotations. It exposes all the same attributes as `@Transactional` (`propagation`, `isolation`, `timeout`, `readOnly`, `rollbackFor`, `noRollbackFor`), each aliased via `@AliasFor` to the corresponding `@Transactional` attribute. Users retain full transaction control within the annotation tier.

The annotation tier requires a domain-side convention for event extraction and `seq` assignment:

- **Event extraction:** the aggregate returned by the method must implement `TandemAggregate` (a `tandem-core` interface, analogous to Spring Data's `@DomainEvents`), exposing pending `OutboxMessage` instances. The AOP aspect collects them after the method returns, still within the open transaction.
- **`seq` source:** the `seq` per-aggregate sequence number must originate from the aggregate's `version` field. The annotation cannot invent it — the aggregate is responsible for assigning `seq` before returning.

#### Spring-events tier — constraints and conventions

The domain publishes ordinary Spring application events (`ApplicationEventPublisher.publishEvent(...)`) inside its own `@Transactional` method; Tandem listens and writes them to the outbox. This gives the Spring Modulith-style ergonomics **with** Tandem's strong per-aggregate ordering. The correctness rules:

- **The listener must run *inside* the transaction.** Tandem registers a **synchronous** `@EventListener` (which runs inline, in the publisher's thread and transaction) — **not** `@TransactionalEventListener(phase = AFTER_COMMIT)`, whose default phase runs *after* commit and would insert into the outbox in a separate transaction, breaking atomicity. This is the single most important constraint of this tier.
- **Fail-fast if no transaction.** A synchronous listener fires even with no active transaction, which would insert under autocommit and lose atomicity. The listener therefore asserts an active transaction (`TransactionSynchronizationManager.isActualTransactionActive()`) and throws if absent — never a silent insert, and never a silent drop.
- **Event → `OutboxMessage` mapping.** A published object that already is an `OutboxMessage` is inserted directly; otherwise Tandem looks up a registered `OutboxEventMapper<T>` (an SPI) to convert it. The listener is **scoped to exactly those handleable types** (`OutboxMessage` plus every type with a registered mapper), so framework and unrelated events are never intercepted — registering a mapper *is* how an event opts into the outbox. A published event with no mapper is simply ignored, following Spring's own "no listener, no-op" event-bus semantics; this does not weaken delivery guarantees, which apply once a row is in the outbox (LLD-spring-producer §5).
- **`seq` source:** unchanged — the event must carry the `seq` taken from the aggregate's `version`. Tandem never invents it.

### 3.2 Deployment topology & coordination mode — write-side in the client, relay embeddable or standalone, single or lease-coordinated

Because the database is Tandem's coordination point, only one thing *must* run inside the client application: the **write-side** (the outbox INSERT), because it participates in the domain transaction. Everything else — polling, publishing to Kafka, marking `DONE`, lease/failover, retry/backoff, poison handling, and table housekeeping/cleanup — is DB-coordinated and can run **embedded in the client or as a fully standalone process**.

| Component | Where it can run | Needs |
|---|---|---|
| Write-side (outbox INSERT) | **Client only** (in the domain transaction) | DB; core + JDBC; **no Kafka** |
| Relay (poll, publish, mark DONE, lease, retry, poison, cleanup) | Embedded in the client **or** standalone | DB + Kafka |
| Admin API (§7.2) | Embedded **or** standalone | DB (relay control mediated via DB) |

**Two orthogonal axes.** A relay deployment is described by *two independent* choices — **where** the relay process runs and **how** multiple relay instances coordinate bucket ownership. They compose freely; do not conflate them.

**Axis 1 — deployment location (where the relay runs):**

- **Embedded (default — Pareto 80%).** The relay runs in-process in the client app: one deployable, simplest setup. The client depends on Kafka because it hosts the relay — fine for the common case.
- **Split (opt-in — robustness / isolation).** The relay runs as its own deployable, pointed at the client's outbox DB and Kafka. Benefits:
  - **Dependency isolation** — the client depends only on the write-side (`tandem-spring-producer` → core + JDBC), with **no Kafka client** or its transitive tree, avoiding version conflicts with the app's own libraries.
  - **Physical separation / robustness** — relay and client have independent lifecycles, scaling, and failure domains: the client scales for request load, the relay for outbox throughput; a relay crash or GC pause does not touch request handling.
  - **No runtime coupling** — relay and client communicate only through the outbox DB. The sole shared contract is the DB *schema* (versioned), exactly as for the Admin API (§7.2).

**Axis 2 — coordination mode (how concurrent relay instances share buckets):**

- **`SINGLE` (default).** The relay instance owns **all** `B` buckets in-process; no coordination table. Correct **only when exactly one relay instance** runs against the outbox. Zero extra cost — the Pareto default.
- **`LEASE` (opt-in — multi-instance).** Bucket ownership is **partitioned across instances via the `tandem_bucket_lease` table** (§4.3): each bucket is owned by one instance under a renewable lease, a dead instance's leases expire and survivors reclaim them. Instances also **self-register their presence** (`tandem_relay_member`) so the fair-share split rebalances on a plain scale-up, not just on failover (§4.3, LLD-jdbc §3.2). Correct for **any number** of concurrent relay instances. Requires the lease + member tables and a unique `instanceId` per instance.

> **Why coordination is a *declared* static option, not auto-detected.** An instance cannot reliably discover "am I one of several?" without the very `tandem_bucket_lease` table that `LEASE` provides — the detection is circular. So the operator **declares** the mode (`tandem.relay.coordination`). `LEASE` with a single instance degrades gracefully (one owner claims all `B` buckets), so turning it on "to be safe" is cheap; but `SINGLE` stays the zero-cost default so the 80% pay nothing.

**Combinations (both axes compose):**

| Deployment × Coordination | When to use |
|---|---|
| **Embedded + `SINGLE`** | The Pareto default: one client deployable, a **single** instance hosting the relay. |
| **Embedded + `LEASE`** | The client app is scaled to **N replicas** with the relay co-located — each replica hosts a relay instance and they partition buckets safely. Without `LEASE`, N embedded relays would each own all buckets: correctness (ordering, no double-claim) still holds via the DB, but every instance re-scans every bucket — wasted DB load and amplified duplicate windows, no throughput gain. `LEASE` removes the overlap. |
| **Split + `LEASE`** | The standalone relay scaled out to multiple processes for outbox throughput. |
| **Split + `SINGLE`** | A single dedicated relay process (isolation without horizontal scale). |

> **Running more than one relay instance without `LEASE` is a misconfiguration, not a corruption.** Per-aggregate ordering and single-claim exclusivity are carried by `status = IN_FLIGHT` + `FOR UPDATE SKIP LOCKED` at the row (§4.3, §6), *not* by bucket ownership, so multiple `SINGLE` instances never reorder or double-claim a row — they merely all poll every bucket, multiplying DB work for no gain. `LEASE` is the correct answer whenever more than one relay instance runs.

The relay is **fully domain-agnostic**: it reads rows (`aggregate_id`, `aggregate_type`, serialized `payload`, `headers`) and ships them to Kafka (topic from `aggregate_type`, key = `aggregate_id`, value = payload bytes, headers copied). It never deserializes domain types, so it needs nothing from the client's code.

**Module support.** To let the client avoid the Kafka dependency, the Spring write-side autoconfig is separated from the relay autoconfig (see the module graph in §3.1 and LLD-base):

- `tandem-spring-producer` — write-side tiers + autoconfig (JDBC only, **no Kafka**) → used by the client; the only module the write-side needs in the split topology.
- `tandem-spring-relay` — relay autoconfig (JDBC + Kafka).
- `tandem-relay` — a prebuilt **standalone runnable** relay (Spring Boot app / container over `tandem-spring-relay`): point it at DB + Kafka and run.

The modules split by **role only** (write-side vs. relay), not by Spring Boot generation, and there is **no all-in-one aggregator**: an application that both writes and hosts an embedded relay declares both modules, which costs one dependency line and keeps the published surface at two artifacts. The reasoning is in [LLD-spring-config.md](LLD-spring-config.md) §1 (resolves Q21).

Ordering and all delivery guarantees are **identical regardless of topology** — they are properties of the DB, the hash-sharding, and the Kafka config, not of where the relay process runs.

---

## 4. Key Architectural Decisions

### 4.1 Per-Aggregate Ordering, Not Global

**Decision:** Events are ordered within an `aggregate_id`, not across all aggregates.

**Rationale:** Global total ordering requires serializing all writes through a single sequence — this destroys parallel throughput and is unnecessary. Two events on `Order#42` must be ordered; events on `Order#42` and `Customer#7` have no causal relationship and can be processed concurrently. This maps directly to Kafka's partition-key model.

**Implication:** Cross-aggregate ordering is not provided by default. Consumers that need it can enable the optional Lamport-clock capability (see §9) or implement their own correlation logic.

### 4.2 Ordering Established at Write Time

**Decision:** The `seq` per-aggregate sequence number is assigned inside the domain transaction, not by the relay.

**Rationale:** The relay cannot reconstruct an order that was never imposed at the source. The only correct place to serialize per-aggregate writes is where the aggregate mutation happens.

**`seq` is a per-aggregate monotonic sequence number**, equivalent to an event-sourcing stream revision or a Kafka per-partition offset. It is monotonically increasing within a single aggregate and has no defined relationship across aggregates. The aggregate owns and advances it — Tandem reads and preserves it. The `UNIQUE(aggregate_id, seq)` constraint is a safety net against bugs, not the source of ordering.

**Opt-in, per message: Tandem assigns the number instead**, for an aggregate that has no version to take it from — adoption otherwise reaches into the domain schema rather than only adding the `tandem_*` tables. A message built with `managedSeq()` omits the column and a database sequence supplies the value ([HLD-managed-seq.md](HLD-managed-seq.md) §4.1): no extra statement, no lock, nothing added to the caller's transaction. It changes no guarantee — `seq` is not the relay's ordering key, and everything below about commit order applies unchanged — only what `seq` *means* to a consumer, which becomes Tandem's counter rather than the aggregate's version. The default stays app-assigned.

**Opt-in, per message, independent of the above: Tandem can also serialize the writers instead of relying on the domain's own lock.** A message built with `lockedWrite()` makes the write-side adapter take a transaction-scoped `pg_advisory_xact_lock` on the aggregate before its insert ([HLD-managed-seq.md](HLD-managed-seq.md) §4.2): a concurrent writer to the same aggregate blocks until the first commits, turning the precondition below from something the application must satisfy unverified into something Tandem enforces. It costs one statement on the write and makes concurrent writers to one aggregate wait — a real behavioral change, opted into explicitly. Neither `seq` form requires it and neither excludes it.

**Mechanism:**
```sql
-- Domain transaction
SELECT * FROM aggregates WHERE id = ? FOR UPDATE   -- pessimistic lock
-- or: optimistic lock with version field + retry on conflict
INSERT INTO tandem_outbox (aggregate_id, seq = version + 1, ...)
-- UNIQUE(aggregate_id, seq) constraint is the safety net
```

> **With an ORM, the `version` must be the *flushed* one.** `seq = version + 1` is correct only if the version has actually advanced by the time the outbox row is built. Hibernate increments `@Version` at **flush**, and a Tandem write-side tier runs inside the caller's transaction — which is the whole point — so by default it observes the *pre-increment* value. Two mutations in one transaction then produce the **same** `seq` and the business transaction aborts on `UNIQUE(aggregate_id, seq)`; a mutation that dirties no persistent field advances no version at all, so the *next* transaction reuses the `seq`. This is a property of the ORM's flush timing, not of any one tier — it holds identically for the annotation, Template, application-events and plain-repository paths, so no choice of tier avoids it. Either build the outbox row after an explicit flush, or take `seq` from a source that advances per *event* — which is what `managedSeq()` does: [HLD-managed-seq.md](HLD-managed-seq.md) §3.2 has the measurements, §4.1 the mechanism.

> **Hard precondition (not optional).** The per-aggregate write lock above must serialize writes so that, within an aggregate, **commit order = `seq` order = `id` order**. Without it, a lower-`seq` row can become *durable* after a higher-`seq` one (the relay polls committed rows, so it would publish them out of order — and no relay model can repair an ordering defect baked into the data). See [q8-worker-model-decision.md](q8-worker-model-decision.md) (E1).

> **The lock only serializes if it is taken before the outbox insert — and with an ORM, by default, it is not.** Measured against a real Hibernate application: the domain `UPDATE` is deferred to **flush**, while every write-side tier runs earlier, inside the caller's transaction, so the outbox row is inserted **first** and the aggregate's row lock is taken too late to serialize anything. Two concurrent writers both insert, and the one that inserted first can still commit second — the reorder below, in an application whose locking looks correct. Flushing before the outbox row is built reverses the order and the lock does its job: the second writer blocks on the aggregate's row until the first commits (with `@Version` it then fails its optimistic check, which is a normal retryable outcome, not a reorder). **So the explicit flush of the first blockquote above is not only about the `seq` value — it is also what makes the write lock real.** Without it `@Version` does not protect the order either; it merely fails the *earlier* writer at commit, discarding that transaction's outbox row along with it.

> **No flush helps when concurrent writers never touch the same row.** Two transactions that only insert *children* of the aggregate — order lines, an appended collection — share no row to lock, so they reorder even with an explicit flush. There the serialization has to come from somewhere else: an explicit `SELECT … FOR UPDATE` on the aggregate row, an aggregate boundary drawn so that concurrent writers do meet on one row, or `lockedWrite()` above, which needs no shared row at all — its lock is keyed on the aggregate id.

> **And the table never shows it.** Measured, and pinned by `CommitOrderReorderIT` (`tandem-jdbc`): two concurrent writers on one aggregate, the lower-`seq` row inserted first but committed second, publish as `[2, 1]`. Neither guard fires — `UNIQUE(aggregate_id, seq)` sees two *different* values, and the head-of-chain `NOT EXISTS` cannot see an uncommitted row at all. The result is **identical at `bucketCount` 1 and 256**: a single bucket serializes the *relay*, not the *writes*, and one aggregate always hashes to one bucket (§4.3), so `B` is structurally irrelevant here. Silent *in the data*, that is: the relay witnesses the publication order and reports it as `tandem.outbox.order_violation.count` (§7, §8). That signal under-reports and never over-reports — a relay restart or an LRU eviction loses the watermark — so a non-zero value is always a real violation, while zero is not proof of absence.

### 4.3 Bucket-Sharded Relay Preserves Ordering

**Decision:** Aggregates are partitioned into a **fixed, large number of virtual buckets** (`B`, e.g. 256), computed **in Java** by `tandem-jdbc` at insert: `bucket = Math.floorMod(fnv1a64(aggregate_id), B)` — a 64-bit FNV-1a hash over the UTF-8 bytes of `aggregate_id`, reduced with `Math.floorMod` (always non-negative, overflow-free even for the minimum hash value, and works for any `B`). `B` is fixed once and **never changed**. Each bucket is owned by **exactly one worker at a time**; a worker owns a subset of buckets. All events of an aggregate fall in the same bucket → the same worker → published in `id` order. There is **no per-aggregate lock** — exclusivity is *structural* (by partitioning), so it cannot be lost to a non-fencing lock.

> **Why the hash is computed in Java, not in SQL.** The `bucket` is stored on the row at insert, and `B` is immutable, so an aggregate's events must *always* hash to the same bucket. A DB-side hash (`hashtextextended` / `CRC32`) ties that value to one engine's hash implementation: a **major Postgres upgrade** (no cross-version stability guarantee) or a **DB-engine migration** could change the hash for new rows and split an aggregate across buckets — the exact reorder hazard B5 guards against. A fixed, portable Java hash (FNV-1a) is identical across engines and versions, so the bucket is stable for the life of the data. It also lets `InMemoryOutbox` (the in-memory test adapter) compute the *same* bucket as the real database.

**Instance → bucket assignment (the coordination mode, §3.2 axis 2):**
- **`SINGLE` (single relay instance):** the instance owns **all** `B` buckets; its N worker threads split them in-process (`bucket % workerCount`). No coordination table, no lock; coverage is all-or-nothing (process liveness). Correct only when exactly one relay instance runs.
- **`LEASE` (multi-instance):** instances claim bucket ownership via a **`tandem_bucket_lease` table** — each bucket is a row owned under a renewable lease; a dead instance's lease expires and another instance claims the bucket, so **coverage self-heals**. Instances additionally **self-register presence** in `tandem_relay_member`, and the fair-share divisor counts live members rather than bucket owners — so a newly-scaled-up instance that starts with zero buckets is still visible to the incumbent, which releases its excess and the fleet rebalances (without this, an incumbent holding every bucket would never see the newcomer and starve it — LLD-jdbc §3.2). Within an instance, its owned buckets are still split across its worker threads (`bucket % workerCount`). Ownership is queryable (the Admin API reads it for relay status) and needs no per-worker dedicated connection. A brief membership-change window where two instances transiently own a bucket is rare and harmless (head-of-chain + `SKIP LOCKED` → at most a duplicate, never a reorder; §6). `LEASE` is available in **either** deployment location — co-located in a horizontally-scaled client (embedded) or across standalone relay processes (§3.2).

Because `B` is fixed, **changing the worker count never requires a schema migration** — only the bucket→worker assignment changes.

**Rationale:** Structural exclusivity removes the per-aggregate lock fragility (no new-insert race, no fencing concern) and makes the failure mode **loud**: an uncovered bucket simply stalls and `lag.age_seconds` climbs (alertable). For a library whose primary contract is ordering, *fewer silent ways to reorder* is the decisive property.

**Kafka partition alignment:** key = `aggregate_id` closes the full ordering chain: DB write lock → outbox `seq` → bucket → worker → Kafka partition.

**Prior art.** Virtual-bucket sharding is a long-established distributed-systems pattern, not a Tandem invention:
- **Consistent hashing with virtual nodes** — a fixed, large set of virtual partitions mapped onto physical nodes, so membership changes reassign buckets without reshuffling data. Canonically described in *Dynamo: Amazon's Highly Available Key-value Store* (DeCandia et al., SOSP 2007); used by Cassandra, Riak, and Hazelcast (which defaults to 271 partitions).
- **Single-owner partitions with rebalance** — exactly one owner per partition at a time, reassigned on membership change — as in **Apache Kafka consumer groups** (partition assignment) and **Akka/Pekko Cluster Sharding** (per-entity ordering via shard ownership).

Tandem applies the pattern to *outbox-table polling* (a bucket is an internal relay partition) and keeps the assignment **in the database** (a `tandem_bucket_lease` table) rather than in an external coordinator (§3.2).

> Per-aggregate dynamic claim (opaque UUID workers, advisory lock per aggregate) was analysed in [q8-worker-model-decision.md](q8-worker-model-decision.md) and **not chosen**: more elastic, but its ordering correctness is condition-dependent and lock-based, with *silent* failure modes. Single-leader sequential relay (Eventuate-style) was also rejected — it forgoes the parallelism that is Tandem's reason for existing.

### 4.4 Idempotent Kafka Producer Required

**Decision:** The Kafka producer must be configured with `enable.idempotence=true` and `acks=all`.

**Rationale:** With `max.in.flight.requests.per.connection > 1` (the default), retried batches can be reordered even from a single thread. Idempotent producer mode prevents this at the cost of a sequence number per partition.

**Alternative:** `max.in.flight.requests.per.connection=1` also prevents reordering but halves throughput on high-latency connections.

**Enforcement:** Tandem sets these as defaults and **fails fast** (`TandemConfigurationException` at startup) if the user overrides them to unsafe values (`acks=0/1`, idempotence off, `max.in.flight > 5`) — the no-loss and ordering guarantees depend on them (LLD-kafka §1).

### 4.5 Mark DONE Only After Kafka Ack

**Decision:** `status=DONE` is written to the database only after receiving a successful producer ack from Kafka (`acks=all`).

**Rationale:** The failure modes are asymmetric:
- Mark DONE before ack, then Kafka unavailable → **event permanently lost**
- Mark DONE after ack, relay crashes before marking → **duplicate on restart**, recoverable

Duplicates are a known, managed outcome. Data loss is not.

### 4.6 Poison Messages Block the Aggregate, Not the Relay

**Decision:** If an event fails after N retry attempts, its `status` is set to `FAILED`. The relay stops processing subsequent events for that `aggregate_id` until the failed message is resolved.

**Rationale:** Skipping a failed message and publishing the next would violate happens-before for that aggregate. The ordering invariant is the primary contract of the library; it must not be silently broken under error conditions.

**Operator path:** Failed messages are visible via metrics (`tandem.outbox.failed.count`) and can be replayed or manually resolved.

### 4.7 Immutable Rows, Deferred Cleanup

**Decision:** Outbox rows are never deleted by the relay. Successful rows are marked `DONE`; cleanup runs as a separate batch job or via table partitioning on `created_at`.

**Rationale:**
- Row-by-row `DELETE` under high write rates causes table bloat and index churn
- Immutable rows make replay trivial: reset `status=PENDING, attempts=0`
- Audit trail is preserved for the retention window (recommended: 7–30 days)

### 4.8 CloudEvents as the Publication Format

**Decision:** The relay publishes to Kafka using the **CloudEvents 1.0** (CNCF) envelope as the default standard, in **binary content mode** (attributes → Kafka `ce_*` headers, payload → message body). Structured mode is optional; a **raw passthrough** mode remains as an escape hatch.

**Rationale:** A standard envelope is interoperable with the CNCF ecosystem (Knative, brokers, tracing tooling) and exposes consistent metadata (`id`, `source`, `type`, `subject`, `time`) for routing/filtering without deserializing the payload — decoupling consumers from Tandem-internal shapes. CloudEvents' `partitionkey` extension and `subject` map cleanly onto `aggregate_id`, so per-aggregate ordering is unchanged (Kafka key stays `aggregate_id`).

**Where it lives:** CloudEvents formatting is a **relay-side** concern in `tandem-kafka` (via `io.cloudevents:cloudevents-kafka`). Consistent with the deployment topology (§3.2), the **client / write-side does not depend on CloudEvents** — it only captures the event `type`; the relay builds the CloudEvent from the stored row + configuration. Topic routing (`aggregate_type` → topic) and payload serialization (`PayloadSerializer` → `data`) are orthogonal and unchanged.

Full mapping, content modes, Tandem extensions (`seq` / `lamport` / `causationid`), **event versioning** (the version lives in the CloudEvents `type` as a `.v{n}` suffix, never in the topic; §1.4 compatibility applies), and schema impact: [HLD-cloudevents.md](HLD-cloudevents.md).

---

## 5. Data Model

### 5.1 Outbox Table (PostgreSQL)

**The authoritative definition is the Liquibase changelog** at `schema/postgres/changelog/`, from
which the flat `schema/postgres/tandem-baseline.sql` an operator applies is generated (LLD-jdbc §6);
Tandem ships the changelog and does not run migrations itself. What follows is a **deliberate
excerpt**, not a copy: the columns that carry a design decision, so the rest of this document can
refer to them. Everything else — delivery state, and the operator-facing columns — is elided here and
explained in §5.2. A full transcription would only drift, as it silently did twice before this note
existed.

```sql
CREATE TABLE tandem_outbox (
    id              BIGINT GENERATED ALWAYS AS IDENTITY PRIMARY KEY,
    aggregate_id    VARCHAR(255) NOT NULL,   -- Kafka message key; the ordering scope
    aggregate_type  VARCHAR(255) NOT NULL,   -- routes to the Kafka topic (§5.2)
    bucket          SMALLINT     NOT NULL,   -- Math.floorMod(fnv1a64(aggregate_id), B), computed in Java; §4.3
    seq             BIGINT       NOT NULL,   -- per-aggregate causal sequence
    payload         JSONB        NOT NULL,   -- BYTEA when a binary serializer is used (§5.2)
    status          SMALLINT     NOT NULL DEFAULT 0,
    -- 0 = PENDING, 1 = IN_FLIGHT, 2 = DONE, 3 = FAILED, 4 = DISCARDED
    -- … plus type, headers, the delivery-state columns (locked_by, locked_until, attempts,
    -- replays, last_error, next_attempt_at, created_at) and the operator-facing
    -- discard_reason / correlation_id — all of them described in §5.2
    UNIQUE (aggregate_id, seq)               -- the per-aggregate ordering safety net (§4.2)
);
```

**Indexes.** All but one are **partial**, which is the design decision worth recording: each serves a
query the relay or the metrics tick runs constantly, and restricting it to the relevant status keeps
it small even as `DONE` rows accumulate between cleanup passes.

| Index | Serves | Restricted to |
|---|---|---|
| `idx_tandem_outbox_dispatch` | the bucket poll, by bucket then id | `PENDING` |
| `idx_tandem_outbox_aggregate` | the head-of-chain / poison check per aggregate (§6, E2) | `PENDING`, `IN_FLIGHT`, `FAILED` |
| `idx_tandem_outbox_inflight` | the ~5 s lease-reclaim over expired leases | `IN_FLIGHT` |
| `idx_tandem_outbox_failed` | the metrics tick's `failed.count` and `blocked.count` readings | `FAILED` |
| `idx_tandem_outbox_correlation` | the Admin API's incident-time search by correlation id | *(not partial — see below)* |

The correlation index is deliberately **not** partial and not an expression index over `headers`,
even though `(correlation_id) WHERE correlation_id IS NOT NULL` would be smaller: a plain B-tree on a
real column ports to MySQL 8 unchanged, where partial and expression indexes are unavailable and
would need a generated-column workaround (§5.4, LLD-jdbc §5).

### 5.2 Column Semantics

| Column | Purpose |
|---|---|
| `id` | Auto-increment surrogate; used as global tie-break for `ORDER BY` in relay |
| `aggregate_id` | Business identity of the aggregate; Kafka message key |
| `aggregate_type` | Routes to Kafka topic — `kebab-case(aggregate_type)` + suffix `-topic` by default (e.g. `Order` → `order-topic`); see LLD-kafka §5 |
| `type` | CloudEvents `type` — the event type (e.g. `com.acme.order.placed`); captured at produce time, mapped to the CloudEvent at publish (§4.8) |
| `bucket` | Virtual bucket `Math.floorMod(fnv1a64(aggregate_id), B)`, computed **in Java** by `tandem-jdbc` at insert (engine-independent; §4.3); the unit of worker ownership. All events of an aggregate share a bucket |
| `seq` | Per-aggregate causal sequence number; enforced by `UNIQUE(aggregate_id, seq)` |
| `payload` | Event data. The core treats it as `byte[]` produced by a pluggable `PayloadSerializer` (no JSON library forced on the client, §1.3). Stored as `JSONB` by default (readable/inspectable); `BYTEA` when a binary serializer (Avro/Protobuf) is used. Becomes CloudEvents `data`. |
| `headers` | Optional Kafka headers (e.g. `correlation-id`, `traceparent`); merged alongside the CloudEvents `ce_*` headers |
| `status` | State machine: `PENDING → IN_FLIGHT → DONE` / `FAILED`; `FAILED → DISCARDED` (admin only). See §5.3 |
| `locked_by` | Worker identity (e.g. `worker-0@hostname`); enables lease-based failover |
| `locked_until` | Lease expiry timestamp; if elapsed, another worker can reclaim the row |
| `attempts` | Publish attempts in the **current** delivery round; used for backoff and max-retry threshold. Reset by a replay — for the lifetime count of operator replays see `replays` |
| `replays` | How many times an operator has replayed this row, `0` if never. Survives a replay (unlike `attempts`), giving the audit trail on the row and letting the relay tell a replay from a write-side ordering violation (§8) |
| `last_error` | Error message from the last failed attempt; operational diagnostics. Read by nothing functional — only by the operator through the Admin API, which is why a replay keeps it (§8) |
| `next_attempt_at` | Earliest timestamp for the next retry (exponential backoff) |
| `created_at` | Insertion timestamp; used for lag age metrics and partition cleanup |
| `discard_reason` | Operator-supplied reason recorded when the Admin API discards a `FAILED` row (HLD-admin-api §6.1). Distinct from `last_error`, which stays the original delivery failure — the two answer different questions and neither overwrites the other |
| `correlation_id` | Searchable copy of `headers['correlation-id']`, in its own indexed column so the list view can return it without reading the JSONB (HLD-tracing §4). `headers` stays the source of truth for what reaches Kafka. `NULL` for rows written with tracing off. Bounded length on purpose: the value typically arrives from outside the application, so it is untrusted input and must not widen an index without limit |

### 5.3 Status State Machine

```
         ┌─────────┐
         │ PENDING │  (status = 0)
         └────┬────┘
              │ worker acquires lease
              ▼
         ┌──────────┐
         │ IN_FLIGHT│  (status = 1)
         └────┬─────┘
              │                      │ attempts < max_attempts
     ack OK   │                      ▼
              │              ┌───────────────┐
              │  error ──────▶  backoff wait │
              │              └───────┬───────┘
              │                      │ next_attempt_at elapsed
              │                      ▼
              │              ┌─────────┐
              │ attempts=max ▶  FAILED │  (status = 3)
              │              └────┬────┘
              │                   │  ↑ blocks aggregate processing
              │                   │  admin discard (acknowledged ordering break)
              │                   ▼
              │              ┌───────────┐
              │              │ DISCARDED │  (status = 4)
              │              └───────────┘
              │                   ↑ not polled, does NOT block the aggregate
              ▼
         ┌──────┐
         │ DONE │  (status = 2)
         └──────┘
              │ cleanup job (batch delete or partition drop)
              ▼
           (gone)
```

`DISCARDED` (4) is reachable **only** via the Admin API discard operation on a `FAILED` row,
with an explicit ordering-break acknowledgement (HLD-admin-api). A discarded row is never
polled and is **not** counted by the head-of-chain check (§6, statuses 0/1/3), so it unblocks
the aggregate. It is otherwise immutable (subject to the same cleanup/retention as `DONE`).

**Replay edges (not drawn above):** `ReplayService` / the Admin API can reset a `DONE` (2) or
`FAILED` (3) row back to `PENDING` (0) — `DONE → PENDING` and `FAILED → PENDING` — clearing
`attempts` / `last_error` / `next_attempt_at` (§8). These are the only backward transitions;
`DISCARDED` is terminal and is never replayed.

### 5.4 MySQL Considerations

MySQL 8 supports `SKIP LOCKED`, and the `bucket` is computed in Java (§4.3), so it is identical on MySQL with no DB-specific hash function. The type mappings are mechanical: `GENERATED ALWAYS AS IDENTITY` → `BIGINT AUTO_INCREMENT`, `JSONB` → `JSON`, `TIMESTAMPTZ` → `DATETIME(3)`/`TIMESTAMP(3)`, and partial indexes are unsupported (replaced by a full index with `status` as the leading column).

Two differences are architectural rather than mechanical. Both were established by experiment against MySQL 8.4; [LLD-jdbc §5](LLD-jdbc.md) specifies the port in full, including the measurements. First, MySQL has no `UPDATE … RETURNING`, so the claim cannot remain the single atomic statement it is on PostgreSQL — it becomes a locking `SELECT` plus an `UPDATE` inside one explicit transaction, the only operation in the design that spans more than one statement (Q9). Second, **the relay must run at `READ COMMITTED`**: under MySQL's `REPEATABLE READ` default the claim's head-of-chain check takes a lock on every row it examines, across all buckets rather than the worker's own, and four workers measured **37% slower than one** — negative scaling, with no deadlock, no timeout and no error to reveal it. PostgreSQL defaults to `READ COMMITTED`, which is why this requirement has been invisible so far: it is a property Tandem has always relied on, not a concession made for MySQL.

### 5.5 The Other Tables Tandem Owns

`tandem_outbox` is the one every deployment revolves around, but it is not the only table Tandem
creates. The boundary matters as much as the contents: **Tandem writes only its own `tandem_*`
tables and never a domain table** (§9 records the same rule for the causal-ordering clock).

| Table | Present when | Purpose |
|---|---|---|
| `tandem_outbox` | always | §5.1 |
| `tandem_meta` | always | Cross-cutting key/value settings and state, keyed by name |
| `tandem_bucket_lease` | `LEASE` coordination only | Per-bucket ownership under a renewable lease (§3.2, §4.3) |
| `tandem_relay_member` | `LEASE` coordination only | Relay-instance presence, so the fair-share split rebalances on a plain scale-up and not only on failover (§4.3) |
| `tandem_aggregate_clock` | *(never — §9 is designed, not implemented; no clock table ships today)* | Lamport clock store, kept in a `tandem_*` table rather than on the client's aggregate row (§9) |

**`tandem_meta` holds three keys today** — `bucket_count` (the single value the write-side and the
relay must agree on), `relay_paused` (the whole-relay desired state the Admin API writes and every
instance re-reads on its control tick), and `coordination` (`SINGLE` or `LEASE`, written by the relay
at startup so the Admin API knows which per-bucket endpoints this deployment can answer). They share
one key/value table rather than getting dedicated ones for a specific reason: **it is the only place
a `SINGLE`-mode deployment can be reached at all.** `tandem_bucket_lease` exists only under `LEASE`,
so a pause stored there would never reach a `SINGLE` relay — and a new table per setting would either
duplicate this one or repeat that same mistake. The same table also carries the relay's
liveness heartbeat, which is what lets the Admin API report a dead relay under either coordination
mode (§7). It is deliberately **not** seeded: the bucket-count guard writes the row on first
startup from whatever the operator configured, so a fresh database with a non-default `B` is correct
without anyone editing the schema — unlike the lease table, whose row count must equal `B` and is
therefore seeded.

---

## 6. End-to-End Flow

The flow below is shown as a single sequence for clarity. The boundary after `COMMIT TX` is the DB: the **write-side** (application thread) and the **relay** communicate only through committed outbox rows, so the relay portion runs either embedded in the client or as a standalone process (§3.2) with no change to the steps.

```
[Application Thread]
    │
    ├── BEGIN TX (existing domain transaction)
    ├── SELECT * FROM aggregates WHERE id=? FOR UPDATE    ← serialize writes per aggregate
    ├── UPDATE aggregates SET version = version+1, ...
    ├── INSERT INTO tandem_outbox
    │       (aggregate_id, aggregate_type, type, bucket, seq=version+1, payload, headers)
    │       -- bucket is computed by tandem-jdbc; the client never sees it
    └── COMMIT TX
              │
              │  (committed row is now visible to relay)
              ▼
[WorkerPool — each worker owns a subset of the fixed virtual buckets (§4.3)]
    │
    ├── Poll loop — claims back-to-back while work remains; sleeps pollInterval (e.g. 100ms,
    │   ±20% jitter) only when a claim is empty (idle backoff, NOT a per-batch throttle;
    │   §3.1 LLD-jdbc). A cycle that throws backs off exponentially instead.
    │
    ├── Poll this worker's buckets for the HEAD of each aggregate's pending chain
    │   (E2 — never leapfrog a not-yet-DONE earlier row; this also subsumes the poison gate):
    │   SELECT id, aggregate_id, aggregate_type, type, seq, payload, headers
    │     FROM tandem_outbox o
    │    WHERE o.bucket IN (:my_buckets)
    │      AND o.status = 0
    │      AND (o.next_attempt_at IS NULL OR o.next_attempt_at <= now())
    │      AND NOT EXISTS (                          -- only the earliest unfinished row per aggregate
    │          SELECT 1 FROM tandem_outbox e
    │           WHERE e.aggregate_id = o.aggregate_id
    │             AND e.id < o.id
    │             AND e.status IN (0, 1, 3) )        -- PENDING / IN_FLIGHT / FAILED
    │    ORDER BY o.id
    │    FOR UPDATE SKIP LOCKED                      -- guards the brief slot-handoff window
    │    LIMIT :batch_size
    │
    ├── UPDATE tandem_outbox SET status = 1 (IN_FLIGHT), locked_by = '<worker>',
    │       locked_until = now() + :lease_duration   WHERE id IN (...)
    │
    ▼
[KafkaRelay]
    ├── The claimed batch is ONE row per aggregate (heads) → independent rows.
    │   Dispatch them with OVERLAPPING in-flight sends on one ASYNC producer
    │   (up to batch_size in flight = the per-shard concurrency window, §10):
    │     -- wrap each row as a CloudEvent (binary mode) → ce_* headers + body (§4.8)
    │     future = producer.send(                       ← async; ack on producer I/O thread
    │       topic    = TopicRouter.topicFor(record),     ← default: kebab(aggregate_type)+suffix
    │       key      = aggregate_id,                    ← = CloudEvents partitionkey
    │       value    = payload,                         ← CloudEvents data (body)
    │       headers  = ce_id, ce_source, ce_type, ce_subject, ... + headers
    │     )                                             ← acks=all, enable.idempotence
    │
    ├── On each ack (success): collect id → batched UPDATE … SET status=2 (DONE)
    │
    ├── On each failure:
    │     attempts++
    │     If attempts < max_attempts: status=0 (PENDING), next_attempt_at = now()+backoff
    │     Else:                       status=3 (FAILED)   ← this aggregate is now blocked
    │
    └── Per-aggregate order is STRUCTURAL, not an inner loop: the head-of-chain claim keeps
        at most one row per aggregate in flight, and seq(N+1) only becomes a claimable head
        once seq(N) is DONE (E6). A failed/retrying row stays non-DONE, so the aggregate's
        later rows stay blocked next cycle (E2/Q10) — the aggregate stops with no explicit
        break, and the worker keeps its bucket ownership.
```

### 6.1 Lease Failover

If a worker crashes while holding `IN_FLIGHT` rows, the lease expiry (`locked_until`) allows recovery:

```sql
-- Lease reclaim job (runs periodically, e.g. every 5s)
UPDATE tandem_outbox
   SET status = 0, locked_by = NULL, locked_until = NULL
 WHERE status = 1
   AND locked_until < now();
```

This ensures at-least-once delivery even across worker crashes, at the cost of potential duplicates for the reclaimed batch.

---

## 7. Monitoring

Metrics are emitted through a **`TandemMetrics` port** (`tandem-core`, **no-op by default**) so
that core and `tandem-jdbc` never depend on a metrics library. The optional **`tandem-micrometer`**
adapter binds the port to a Micrometer `MeterRegistry`; it is wired only where the relay runs, so
the client write-side never inherits Micrometer (§1.3). The measurements below are the port's:

| Metric | Type | Description | Priority |
|---|---|---|---|
| `tandem.outbox.lag.count` | Gauge | Number of rows with `status=PENDING` | High |
| `tandem.outbox.lag.age_seconds` | Gauge | Age of the oldest PENDING row in seconds | **Critical** |
| `tandem.outbox.published` | Counter | Rows transitioned to `status=DONE`, cumulative — a throughput *rate* is a query the TSDB derives (e.g. Prometheus `rate()`), not something Tandem computes, hence no `.rate` suffix on a plain counter | High |
| `tandem.outbox.publish.latency` | Timer (histogram) | Time from a row's `created_at` to its Kafka ack, one sample per successfully published row — the runtime-verifiable approximation of the §10 NFR "relay latency" KPI (`COMMIT` → ack, p50 < 200 ms / p99 < 1 s at normal load). Approximation, not exact: `created_at` is set at `INSERT`, not `COMMIT` (a caller transaction that does more work after the outbox insert makes this an upper bound, never an underestimate), and the two ends are read from different clocks — the database's and the relay's — so a persistent skew between them shows up as a constant offset, not noise. Published as a **percentile histogram**, not a client-computed percentile: percentiles cannot be averaged across relay instances, but a TSDB (e.g. Prometheus `histogram_quantile()`) derives a correct multi-instance p95/p99 from the published buckets | **Critical** |
| `tandem.outbox.failed.count` | Gauge | Rows with `status=FAILED` **right now** — a live count, read the same way as `lag.count`, not a tally of failure events (a row can leave `FAILED` via an operator's `DISCARDED` transition, and this must reflect that) | High |
| `tandem.outbox.blocked.count` | Gauge | PENDING rows sitting behind a `FAILED` row of the same aggregate — waiting, but unclaimable until an operator resolves the head. Counted by `lag.count` as well, deliberately: they are undelivered events, and a backlog gauge that hid them would read healthy while an aggregate is entirely stalled. Reported separately because the two situations demand opposite responses — see the alerting rules below | High |
| `tandem.outbox.order_violation.count` | Counter | Cumulative events published with a `seq` **lower** than one already published for the same aggregate — the symptom of a violated write-side ordering precondition (§4.2, §8). Operator replays are excluded at the source (the relay checks the row's `replays`), so a non-zero value always means writers to one aggregate are not serialised, never that someone ran a recovery action. **It under-reports heavily: a zero reading is not evidence the precondition held** — see the note below the table before relying on it. Opt out with `orderViolationDetection = false` | **Critical** |
| `tandem.outbox.retry.count` | Counter | Cumulative retry attempts | Medium |
| `tandem.outbox.lease_expired.count` | Counter | Rows reclaimed from expired leases (proxy for worker crashes) | Medium |
| `tandem.outbox.workers.active` | Gauge | Number of active relay workers (thread alive; does **not** imply making progress — pair with `workers.cycle_age_seconds`) | Medium |
| `tandem.outbox.workers.cycle_age_seconds` | Gauge | Seconds since the least-recently-progressed live worker last completed a claim cycle, 0 when no worker is alive (LLD-jdbc §3.8). Read in-process from the worker pool itself, never the database — the direct signal for "running but not making progress": `workers.active` alone cannot distinguish a working worker from one merely alive but stuck (e.g. blocked in a database call that never returns) | High |
| `tandem.outbox.bucket.uncovered` | Gauge | Buckets with PENDING rows but no live owner (coverage stall); derived from `tandem_bucket_lease`, so reported under the **`LEASE`** coordination mode (§3.2) — standalone, or embedded-with-`LEASE`. Under `SINGLE` there is no lease table; supervised worker-thread restart (LLD-jdbc §3.1) keeps coverage and `lag.age_seconds` is the backstop | High |
| `tandem.relay.config.invalid` | Gauge | Set to 1 (tagged `check`) when a startup config invariant is violated — e.g. `rowLease ≤ delivery.timeout.ms`; the relay then fail-fasts (§12, LLD-jdbc §3.5). Registered like any other gauge, with one accepted gap: it is set once, immediately before the process aborts, so a pull-based scraper (Prometheus) can race the process exit and never read it. The relay's own `ERROR` log line at the same call site is the durable channel for this specific case; the metric still helps a continuous-poll backend or a sidecar that reads the registry directly | High |

> **What `order_violation.count` can and cannot tell an operator.** It is detected in-process at
> publish time because it is undetectable afterwards: a violation leaves the rows in the table in
> perfect order, `id` ascending with `seq`, so no query over `tandem_outbox` can find it later. That
> also bounds what the counter sees, in three ways — the first of which is the most common and is not
> a matter of lost state:
> 1. **Both commits inside one poll cycle → invisible by construction.** If the next claim finds both
>    rows already committed, the head-of-chain gate publishes them in ascending `id` order regardless
>    of which committed first, so nothing ever reaches a claim result to flag. The identical write-side
>    race is *visible* only when a claim happens to run inside the window between the two commits —
>    narrower than one `pollInterval` (default 100 ms). Faster transactions are therefore *more* likely
>    to hide the defect, not less. [HLD-managed-seq.md](HLD-managed-seq.md) §3.3 works the example.
> 2. **A relay restart** loses every watermark, since they live only in memory.
> 3. **LRU eviction** past the 4096 most-recently-published aggregates of a worker loses that
>    aggregate's watermark.
>
> So the counter **under-reports and never over-reports**: a non-zero reading is always a real
> violation, worth an incident; a zero reading proves nothing. **There is no runtime signal that
> confirms the precondition holds** — that has to be established statically, by checking that
> concurrent writers to one aggregate actually serialise: that the domain write is flushed *before* the
> outbox insert (§4.2), and that concurrent writers contend on a shared row at all rather than only on
> children of the aggregate. Do not treat a long-running zero as verification.

**Alerting guidance:**
- `lag.age_seconds` > threshold (e.g. 60s) **and `blocked.count` == 0** → relay is stalled or
  under-provisioned. **The second half of that condition is not optional.** A `FAILED` row blocks its
  aggregate's chain permanently, and every row behind it stays `PENDING`, so a *single* terminal
  failure pins `lag.count` above zero for good and makes `lag.age_seconds` climb linearly, for ever,
  while the relay delivers every other aggregate perfectly. Without the `blocked.count` qualifier this
  rule latches on after the first poison message and never clears again — it stops being a signal.
  Measured, not theorised: after one poisoned aggregate a demo run finished with 12 744 rows `DONE`,
  1 `FAILED`, and 109 `PENDING` — all 109 behind that one failure, with the age gauge past three
  minutes and still rising at one second per second.
- `blocked.count` > 0 → **not** a relay problem: an aggregate is stalled behind a failure and needs a
  replay or a `DISCARDED` decision. Pair it with `failed.count`, which says how many heads are stuck;
  `blocked.count` says how much traffic is queued behind them, which is what decides the urgency.
- **`lag.*` stale or absent → alert on that too.** The lag gauges are read *by the relay*, on a
  periodic reading (`metricsInterval`, default 10s). A relay that is down therefore does not report
  a growing backlog — it reports **nothing**, and the gauges freeze at their last value or disappear
  entirely, while the backlog keeps growing unseen. The one failure this signal cannot cover on its
  own is the one where the whole relay is gone, so an operator must also alert on the *absence* of a
  fresh reading (a staleness / `absent()` rule), not only on a high value. Under `LEASE` a surviving
  peer keeps reporting and `bucket.uncovered` covers the partial case; with a single relay there is
  no such witness. A lag reading computed **outside** the relay — the Admin API (§7.2), which queries
  the same table — is the natural complement, and the reason not to treat these gauges as sufficient.
- **A burst shorter than `metricsInterval` is invisible by design.** The reading is periodic, not
  event-driven, so a backlog that builds and drains between two readings never appears. The gauges
  are a trend and alerting signal, not a diagnostic trace; lower the interval where finer resolution
  is worth the cost. That cost is not flat: `count(*)` uses the partial index on `status = 0`, but
  `min(created_at)` is not indexed, so the query is proportional to the backlog — most expensive
  exactly when the backlog is large.
- **`order_violation.count` > 0 → a write-side bug, and the alert never clears on its own.** Unlike every
  other signal here this one does not describe the relay's health at all: the relay behaved correctly and
  is telling you that two writers to one aggregate ran concurrently, which §4.2 forbids. Nothing in Tandem
  can repair it and no amount of waiting helps — the events for that aggregate have already been consumed
  out of order. Alert on any increase, and note that the counter is cumulative for the life of the process,
  so the actionable rule is on `increase(...)` over a window rather than on the absolute value. The
  identifiers needed to find the aggregate are in the `ERROR` the relay logs alongside it; the metric
  alone says only that it happened. **This rule catches violations, it does not rule them out** — per
  the note above the counter under-reports by construction, so a quiet alert is not a green light on
  the write side.
- `failed.count` > 0 → manual intervention required
- `lease_expired.count` growing rapidly → workers are crashing; investigate JVM health
- `workers.cycle_age_seconds` > threshold (e.g. 60s) → a worker is alive but not progressing (stuck
  claim/dispatch iteration); this reads directly in-process, never the database, so unlike every other
  gauge here it keeps reporting even while `tandem_outbox` itself is unreachable — useful signal on
  its own for exactly the failure mode the others are blind to

**Telling the four "the backlog is growing" cases apart.** A rising backlog has four very different
causes, and the metrics separate them only when read together — the value alone is not enough:

| | `lag.age_seconds` | `published` | `workers.active` | `workers.cycle_age_seconds` | `blocked.count` |
|---|---|---|---|---|---|
| **Relay absent** — not started yet, disabled, or dead | series **absent or frozen** | absent | absent | absent | absent |
| **Relay stalled** — running but not making progress | present, **climbing** | ≈ 0 | > 0 | **climbing** | 0 |
| **Relay under-provisioned** — working flat out, losing | present, **climbing** | high, saturated | > 0 | ≈ 0 | 0 |
| **Aggregate blocked** — relay healthy, one chain stuck behind a failure | present, **climbing** | normal | > 0 | ≈ 0 | **> 0** |

The middle two separate cleanly, because throughput and backlog age are independent signals: an age
that climbs *while the relay publishes at full rate* means too little relay for the load, whereas an
age that climbs while nothing is published means the relay is wedged (broker unreachable, DB
contention, buckets uncovered). **`workers.cycle_age_seconds` reaches the same conclusion more
directly**, without needing that correlation: an under-provisioned worker is still completing claim
cycles (it is busy, just outpaced), so the gauge stays near zero, while a genuinely stalled worker —
blocked in a database call, a broker handshake that never completes, a poison iteration that always
throws before finishing — stops advancing it entirely. It is also the one gauge in this table that
`workers.active` cannot substitute for: a thread stuck inside a blocking call is still alive.

The last one is the case `lag.age_seconds` alone cannot express at all, and the reason
`blocked.count` exists: the age climbs exactly as it does under a genuine stall, but throughput is
normal and nothing about the relay is wrong. It never resolves on its own, either — unlike the other
three, waiting does not help, because no relay will ever claim a row behind a `FAILED` head.

The first case is different in kind: it is diagnosed from the **presence** of the series, never from
its value, and presence is ambiguous — a missing series equally means the relay has not started yet,
was disabled (`tandem.relay.enabled=false`), refused to start on a failed invariant, has no metrics
adapter wired at all, or the whole application is down. Two correlations disambiguate it: the
application's own liveness signal, and `tandem.relay.config.invalid`, which is recorded **once at
startup even on the failure path**, before the relay aborts — so it is present exactly in the
"refused to start" case and absent in the others. The startup window itself is narrow by design: the
first reading is taken when the relay starts, not one `metricsInterval` later, so a healthy
just-started relay does not masquerade as an absent one.

**Detecting an absent relay from outside the process no longer depends on the coordination mode
(§3.2) — resolved via the Admin API (`docs/open-questions-lld.md` Q30, HLD-admin-api §4.1).**
Originally, only `LEASE`'s `tandem_relay_member` gave an external observer any liveness signal:
under `SINGLE` nothing in the database recorded that a relay was ever supposed to exist, so "no
relay running" and "no relay ever configured" were indistinguishable from the data alone. Every
relay instance now heartbeats a shared `tandem_meta` row on its existing maintenance cadence,
under **both** coordination modes — `GET /relay/status` reports `state: DOWN` once that heartbeat
goes stale, independent of the relay process being reachable at all (a standalone admin computing
this from the database needs no in-process witness). Application-level liveness is still the
faster, in-process signal for the local case (`WorkerPool.status()`, above) — the Admin API's
`DOWN` is for an external observer with no other way to tell.

### 7.1 Trace & Correlation Propagation (optional, off by default)

Tandem can propagate distributed-tracing and correlation identifiers across the
asynchronous outbox boundary, so a consumed event traces back to the business operation
that produced it. The outbox makes this non-trivial: the event is *produced* in the domain
transaction (trace context live) but *physically sent* later by the relay (context gone).
Propagation is therefore split into **capture at produce time** and **propagate at publish
time**.

Design highlights (full design: [HLD-tracing.md](HLD-tracing.md)):

- **Reuses the existing `headers` column** — the captured W3C `traceparent` / `tracestate`
  and a configurable `correlation-id` are merged into `headers`. Since the relay already
  publishes `headers` as Kafka headers (§6), basic propagation needs **no relay change and
  no tracing library in the core/relay** — they just carry the opaque standard strings.
- **Standard interop.** Emitting the W3C `traceparent` means any OpenTelemetry-instrumented
  consumer continues the trace automatically.
- **Hexagonal (§1.2).** Port `TracePropagator` in `tandem-core`, default
  `NoOpTracePropagator`; capture happens at the `JdbcOutboxRepository.insert` chokepoint so
  **all four usage tiers** get it transparently. Opt-in adapters: Micrometer Tracing (auto
  in `tandem-spring-producer`) and OpenTelemetry (optional `tandem-tracing-otel`).
- **Off by default, zero cost when off.** Guarded capture — no context lookup, no
  allocation, nothing added to `headers` when disabled.
- **Instrumented mode is per record, and only where work happened.** The optional relay-side span is
  emitted **one per outbox record**, parented to that record's own captured context — a claimed
  batch is a fan-in of unrelated traces, so no single parent for it is correct — and never for a
  poll that claimed nothing. Span attributes carry the same structural identifiers as logs, never
  payloads (HLD-tracing.md §6.1–§6.4).
- `correlation_id` is distinct from the `causation_id` of §9.

### 7.2 Admin API (optional, off by default)

An optional REST operations layer over the outbox (the *sends*), plus relay control. Built
**API-first**: the OpenAPI contract ([admin-api.openapi.yaml](admin-api.openapi.yaml)) is the
source of truth, defined and reviewed before implementation; full design in
[HLD-admin-api.md](HLD-admin-api.md).

- **Operations.** Outbox: health summary, message search, single-message detail, single and
  bulk replay (with `dryRun`), discard (with explicit ordering-break acknowledgement).
  Relay: status, pause/resume (whole or per shard).
- **Off by default + security is the host's job.** Not exposed unless `tandem.admin.enabled`
  is set; Tandem ships the endpoints, not the authentication — the OpenAPI declares the
  expected `bearerAuth` / `apiKeyAuth` schemes but wiring real auth is the application's
  responsibility.
- **Hexagonal (§1.2).** Operations are framework-agnostic use cases (`AdminService`),
  delegating to existing `OutboxRepository` / `ReplayService`; REST is a driving adapter in
  the optional `tandem-admin` module (depends only on
  `tandem-core` + `tandem-jdbc`, never on the client's domain). The future Admin Web UI
  (out of scope) consumes this same contract.
- **Deployable embedded or fully standalone.** Because the DB is Tandem's coordination point,
  the Admin API needs only access to the client's outbox database — **no runtime dependency
  on the client service**. Reads, replay, and discard are pure DB operations (the relay reacts
  to DB state on its next poll); relay pause/resume/status is mediated through DB control /
  heartbeat tables so even that stays DB-only. The only coupling is a shared DB *schema*
  contract, not a runtime service dependency. Full detail in §4 of [HLD-admin-api.md](HLD-admin-api.md).

---

## 8. Replay

Replay resets DONE or FAILED rows back to PENDING, causing the relay to re-process and re-publish them. Safe because:
1. The event itself is immutable — replay rewrites only *delivery* state (`status`, `attempts`, the lease, the retry schedule); `payload`, `headers`, `seq` and the aggregate identity are never touched, and rows are never deleted during normal operation
2. The same worker handles the same aggregate, preserving order
3. Consumers must be idempotent on `(aggregate_id, seq)` — replay is an expected, documented scenario

```sql
-- Replay a specific aggregate, optional ID range
UPDATE tandem_outbox
   SET status = 0, attempts = 0, replays = replays + 1,
       next_attempt_at = NULL, locked_by = NULL, locked_until = NULL
 WHERE aggregate_id = ?
   AND id BETWEEN :from_id AND :to_id
   AND status IN (2, 3);   -- DONE or FAILED

-- Replay all FAILED rows for an aggregate type
UPDATE tandem_outbox
   SET status = 0, attempts = 0, replays = replays + 1,
       next_attempt_at = NULL, locked_by = NULL, locked_until = NULL
 WHERE aggregate_type = ?
   AND status = 3;
```

> **`last_error` deliberately survives a replay.** Every other field above is reset because delivery
> needs it: `attempts = 0` restores the retry budget (without it a row at `maxAttempts` returns to
> `FAILED` on its first retriable failure), `next_attempt_at` and the lease columns make the row
> claimable again. `last_error` is required by nothing — no functional path branches on it; it is
> written by the relay and read only by the Admin API, i.e. by the operator. Clearing it would delete
> the answer to *"why did this fail?"* for the very person who just replayed the row to fix it, and
> for good if the replay succeeds. A `PENDING` row carrying a `last_error` is not a new state shape
> either — it is exactly what a retriable failure already produces (§7).

> **`replays` records that the replay happened.** The Admin API exists in part because replay mutates
> delivery state and therefore needs an **audit trail** (HLD-admin-api §4) — but that trail used to be
> a single log line in a separate process, so the row an operator actually inspects said nothing. A
> replayed row and one that was never replayed were byte-identical. `replays` is that promise kept, on
> the row itself: it counts operator replays for the **lifetime** of the row, where `attempts` is only
> the budget of the current delivery round and must reset. It is counted rather than flagged because
> "replayed twice" is a materially different story from "replayed once" when reconstructing an
> incident. Additive and `NOT NULL DEFAULT 0`, so existing rows read as never-replayed with no
> backfill; **the relay's claim query does not select it**, so a relay older than the column keeps
> working against a migrated database unchanged (§1.4).
>
> This is also what makes a write-side ordering violation distinguishable from a legitimate replay, and
> it is what the relay's detector runs on. The relay notices that it published an aggregate's events in
> non-ascending `seq` order, but the two causes present identically on the row — so a detector reading
> `seq` alone would raise an incident during the very replay an operator is running to recover from one.
> With `replays` on the row it disambiguates: on `seq < the last seq published for that aggregate`, a
> single primary-key lookup of `replays` separates a replayed row (suppress) from a genuine regression
> (`ERROR` + `tandem.outbox.order_violation.count`, §7). Two constraints, both easy to get wrong: the
> watermark is **not lowered** for a suppressed row, or a later genuine regression would go unseen; and
> `replays > 0` suppresses that row permanently, since a row that has been replayed is no longer a
> reliable witness to the original write order. An equal `seq` is a redelivery, not a regression, and is
> never reported. Full mechanics — where the check runs, and why it is bounded — in LLD-jdbc §3.9.

Tandem exposes a `ReplayService` API (in `tandem-core`) that wraps these queries with parameter validation.

---

## 9. Cross-Aggregate Causal Ordering (Optional)

> **Status: designed, not implemented.** What ships today is a handful of published-but-inert declarations (a port, a pure merge function, a nullable field, two header names) and **no way to enable any of it** — no flag, no column, no clock table, no engine adapter. Full design, and the inventory of what exists versus what is missing: [HLD-causal-ordering.md](HLD-causal-ordering.md) (start at §0).

By default Tandem orders events only within an aggregate (`seq`). Some consumers need to apply events from *different* aggregates in an order that never shows an effect before its cause — a materialized view folding several aggregates into one global timeline being the canonical case. For those, the design adds an **opt-in** per-aggregate **Lamport clock** producing a total order consistent with cross-aggregate causality.

**What it would guarantee:** if event A happened-before event B (across any aggregates), then `lamport(A) < lamport(B)`. The converse does **not** hold — Lamport values cannot *detect* concurrency, only impose a causally-consistent order. Strict global total ordering and vector-clock concurrency detection are out of scope.

### 9.1 `seq` vs `lamport`

| | `seq` | `lamport` |
|---|---|---|
| Scope | Single aggregate | Across all aggregates |
| Purpose | Order within one aggregate | Causally-consistent global order |
| Owner | The aggregate (its `version`) | Tandem (managed clock) |
| Presence | Always | Only when causal ordering is enabled |
| Comparable across aggregates? | No | Yes |

The two coexist: `seq` keeps enforcing per-aggregate order and the `UNIQUE(aggregate_id, seq)` safety net; `lamport` is an additional, optional ordering key.

### 9.2 The architectural decisions

Everything else — the merge mechanism, the consumer's buffering burden, the engine landscape, and the future `tandem-projection` inbox — is in [HLD-causal-ordering.md](HLD-causal-ordering.md). Only the decisions that bind the rest of this document are recorded here:

- **The clock lives in a `tandem_*` table**, never on the client's aggregate row (design §3.1). A `lamport_clock` column on a domain table was rejected: it would intrude on the client's schema *and* force Tandem to write tables it does not own. The boundary holds — Tandem writes only `tandem_outbox`, `tandem_aggregate_clock`, `tandem_bucket_lease`, `tandem_meta`.
- **Ship (a) clock + propagation and (b) the engine adapters together** (design §7). (a) alone writes a number into a Kafka header that no consumer can act on, so it delivers nothing on its own — "implement causal ordering" therefore includes two new modules, `tandem-kafka-streams` and `tandem-flink`.
- **Tandem supplies the ordering key, never the reordering engine** (§1.1). No mainstream stream processor does *causal* reordering from an application clock; they do *event-time* reordering, and the adapters simply feed them the Lamport value in place of a timestamp. That is correct for ordering but breaks every time-based semantic of those engines — windows, grace periods, retention.
- **Delivery semantics are unchanged.** At-least-once still holds and consumers must still deduplicate on `(aggregate_id, seq)`; a causal clock orders events, it does not deliver them.

## 10. Non-Functional Requirements

> The throughput and latency targets are verified by the load-testing plan: [HLD-load-testing.md](HLD-load-testing.md). That plan also flags refinements these targets need to be testable (a hardware baseline, a reference payload size, latency percentiles beyond the median, and precise definitions of "normal load" and "sustained").

All throughput/latency targets are stated against the **reference baseline** (single host ≥ 8 cores / ≥ 32 GB / NVMe, PostgreSQL 16, single KRaft broker co-located, `N=8`, `batch_size=100`, **1 KB JSON payload**, `acks=all` + `enable.idempotence=true`) defined in [HLD-load-testing.md](HLD-load-testing.md) §5. The numbers are meaningless detached from that baseline.

| Requirement | Target |
|---|---|
| Throughput | Sustain ≥ 10k events/s **per shard** (≈80k/s aggregate at `N=8`) on the reference baseline, where *sustained* = rate held ≥ 10 min with `lag.age_seconds` flat (not growing) **and `blocked.count` == 0** — a run containing even one terminally failed row makes the age climb for ever regardless of throughput, so the flatness criterion is only meaningful with nothing blocked (§7) |
| Relay latency — median | `COMMIT` → Kafka ack **p50 < 200 ms** at *normal load* (≈50% of measured sustainable max). Runtime-verifiable via the `tandem.outbox.publish.latency` metric (§7) — an `INSERT`→ack approximation of this `COMMIT`→ack target, not an exact measurement of it |
| Relay latency — tail | `COMMIT` → Kafka ack **p99 < 1 s** at normal load. Same metric and caveat as above |
| Ordering guarantee | Strict per-aggregate, best-effort cross-aggregate; **zero per-aggregate ordering violations** under all load scenarios |
| Delivery semantics | At-least-once; consumers must be idempotent; **zero lost events** under all load scenarios |
| Java compatibility | Java 17+ (LTS) |
| DB compatibility | PostgreSQL 13+ (primary), MySQL 8.0+ (secondary) |
| Kafka compatibility | Kafka client 3.x |
| Spring Boot | **3.x and 4.x** autoconfiguration (see §10.1); usable without Spring |
| Dependency footprint | `tandem-core` zero runtime deps; the client-imported write-side carries minimal/ideally-zero external deps (§1.3); no mandatory Spring dependency |

### 10.1 Spring Boot 3.x / 4.x compatibility strategy

The Spring modules (`tandem-spring-producer`, `tandem-spring-relay`) must support both Spring Boot generations. They share everything Tandem relies on: the autoconfiguration import mechanism (`META-INF/spring/org.springframework.boot.autoconfigure.AutoConfiguration.imports`), the Jakarta (`jakarta.*`) namespace, the `@AutoConfiguration` / `@ConditionalOn…` annotations, `@ConfigurationProperties` binding, and the core AOP / `@Transactional` model (including the composed-annotation + `@AliasFor` used by `@TransactionalOutbox`). They differ in the underlying Spring Framework (6.x for Boot 3, 7.x for Boot 4); both keep a **Java 17** baseline, matching Tandem.

**Resolved strategy — a single artifact per module on the common API subset.** Each Spring module is **one jar**, compiled against the lowest supported generation (Boot 3.x / Framework 6.x) with Spring declared `compileOnly` (Gradle) / `provided` (Maven) so no Spring version is propagated to the consumer. The consumer's own starter/BOM supplies Boot 3.x **or** 4.x, and the JVM binds Tandem's symbolic references at class-load time. This is sound because every Spring symbol Tandem references exists with an identical binary signature in both Framework 6.x and 7.x; if a later generation breaks one, the failure is loud (`NoSuchMethodError` / `NoClassDefFoundError`), not silent. The full mechanism is in [LLD-spring-config.md](LLD-spring-config.md) §1.1.

**CI obligation — a version matrix, in the build.** Because one artifact claims dual-generation support, it is tested against **at least one Boot 3.x line and one Boot 4.x line** — a green single-version build does not prove dual-generation compatibility. The matrix lives in the build itself (Gradle JVM Test Suites: lightweight `ApplicationContextRunner` tests run against both generations under `./gradlew check`), with the heavier Testcontainers smoke run once on the baseline; specified in [LLD-spring-config.md](LLD-spring-config.md) §1.2.

**Fallback, if a real incompatibility surfaces.** Only then split the version-agnostic logic into `tandem-spring-core` and ship thin `-boot3` / `-boot4` modules over it. This is the escape hatch, not the plan: it doubles the published Spring surface and protects no invariant until an incompatibility is actually observed.

---

## 11. Comparison with Alternatives

Tandem is positioned in the gap between a hand-rolled outbox (correct, but you build and maintain everything) and Debezium/CDC (powerful, but a separate distributed system to operate). The full per-alternative analysis — Debezium, Eventuate Tram, Spring Modulith, hand-rolled outbox, plus the stream processors Kafka Streams and Flink as complements rather than alternatives — including trade-offs and a "when *not* to choose Tandem" section, is in the companion note: [comparison.md](comparison.md).

---

## 12. Open Decisions

| Area | Options | Notes |
|---|---|---|
| Virtual bucket count `B` | Fixed, large (default 256); **never changed after first deploy** | Unit of worker ownership; decouples worker count from the schema (§4.3) |
| Workers per instance | Configurable; default = `Runtime.availableProcessors() * 2` | Each owns `B / workers` of the instance's buckets; instance→bucket assignment follows the coordination mode — `SINGLE` (all buckets in-process) or `LEASE` (`tandem_bucket_lease` table), §3.2/§4.3 |
| Coordination mode | `SINGLE` (default) or `LEASE`; **statically declared**, not auto-detected | `SINGLE` = one relay instance owns all buckets (zero cost); `LEASE` = lease-partitioned ownership for **any** number of concurrent instances (embedded-multi-replica or standalone). §3.2 |
| Lease duration (`rowLease`) | Configurable; default = 60s | Hard invariant **`rowLease > delivery.timeout.ms`** (default = 2×); relay fail-fasts otherwise with a formula-bearing exception/log/metric (LLD-jdbc §3.5) |
| Backoff strategy | Exponential with jitter; max attempts configurable | Default: base 1s, multiplier 2, max 10 attempts |
| ~~Topic routing~~ | **Resolved:** `kebab-case(aggregate_type)` + suffix `-topic` (configurable, no pluralization); override via custom `TopicRouter` or a static map (LLD-kafka §5) | |
| Payload serialization | JSON default; Avro/Protobuf via pluggable `PayloadSerializer` | |
| ~~`@TransactionalOutbox` event extraction~~ | **Resolved (Q22):** `TandemAggregate` — the aspect reads `pendingOutboxMessages()` off the returned aggregate (single or `Iterable`); the optional `aggregateType` attribute becomes a fail-fast guard (LLD-spring-producer §4) | |
| ~~Spring-events tier event mapping~~ | **Resolved (Q22):** both — a published `OutboxMessage` is inserted directly, otherwise a registered `OutboxEventMapper<T>` SPI maps it; the synchronous listener is scoped to those types and fails fast without an active transaction (LLD-spring-producer §5) | |
| ~~Lamport clock store~~ | **Resolved:** Tandem-managed `tandem_aggregate_clock` table (clean boundary — Tandem never writes domain tables); atomic upsert serializes the per-aggregate advance (HLD-causal-ordering.md §3.1) | |
| ~~Spring Boot dual-version packaging~~ | **Resolved:** a **single artifact per module** on the common 6.x/7.x API, Spring `compileOnly`, validated by an in-build Boot 3.x/4.x test matrix; `-boot3`/`-boot4` split kept only as a fallback if a real incompatibility surfaces (§10.1, LLD-spring-config §1.1/§1.2) | |
| ~~Trace propagation enablement~~ | **Resolved:** explicit flag (`tandem.tracing.enabled`, default `false`); never auto-enabled by a tracing adapter's mere classpath presence (HLD-tracing.md §9) | |
| ~~Correlation-id source~~ | **Resolved:** both — an MDC key (default) and an explicit `TandemContext` API (HLD-tracing.md §9) | |
| Admin API spec ↔ code binding | Generate server stubs from the OpenAPI at build time vs. hand-write + validate against the spec in CI | API-first either way (§7.2) |
| Admin API discard semantics | Hard skip (ordering break, acknowledged) vs. discard + tombstone/compensation | Only relevant when the Admin API is enabled |
| ~~Producer/relay packaging (split topology)~~ | **Resolved:** split by role into `tandem-spring-producer` / `tandem-spring-relay`, no all-in-one aggregator — structural (the producer cannot pull Kafka transitively) rather than convention-based (a single module with an optional Kafka dep + conditional relay autoconfig would rest the invariant on every conditional staying correct) (§3.2, LLD-spring-config §1) | |
| ~~CloudEvents `id` / `source` / event versioning~~ | **Resolved:** `id` = outbox `id`; `source` = a single configured URI (`tandem.kafka.source`); event **version lives in the `type`** (`.v{n}`), topic stays version-agnostic; optional `dataschema` from header/config (HLD-cloudevents §7–§8, LLD-kafka §3/§6) | Content mode (binary), raw escape hatch, and `type` column also decided (§4.8) |
| CloudEvents trace header naming | Bare `traceparent` / `tracestate` vs. `ce_`-prefixed — **deferred** until tracing (`tandem-tracing-otel`) lands; tracing is off in the basic round | Only affects the (optional) trace extension (§7.1, HLD-cloudevents §8) |
| ~~Write-side payload serializer dependency~~ | **Resolved (Q22):** an optional Jackson `PayloadSerializer`, auto-configured only when Jackson is on the classpath (`@ConditionalOnClass`) and never forced; the `byte[]` path always works dependency-free, and an object payload without a serializer fails fast (LLD-spring-producer §2) | |
