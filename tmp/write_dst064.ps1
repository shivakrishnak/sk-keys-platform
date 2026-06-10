Set-Location "c:\ASK\MyWorkspace\sk-keys"
$base = "dictionary\tier-5-distributed-architecture\DST-distributed-systems"

$newContent = @'
---
id: DST-064
title: Read Repair
category: Distributed Systems
tier: tier-5-distributed-architecture
folder: DST-distributed-systems
difficulty: ★★☆
depends_on: DST-063
related: DST-063, DST-065
tags:
  - distributed
  - architecture
  - pattern
  - intermediate
  - performance
status: complete
version: 1
layout: default
parent: "Distributed Systems"
grand_parent: "Technical Dictionary"
nav_order: 64
permalink: /distributed-systems/read-repair/
---

# DST-064 - Read Repair

⚡ TL;DR - Read Repair is the mechanism by which a distributed database detects and corrects inconsistent replica values during a read operation — the coordinator compares responses from multiple replicas and writes the most recent value back to any stale replicas.

| Metadata | | |
|:---|:---|:---|
| **Depends on:** | DST-063 | |
| **Related:** | DST-063, DST-065 | |

---

### 🔥 The Problem This Solves

**WORLD WITHOUT IT:**
Cassandra writes with `QUORUM` consistency. 3 replicas (A, B, C). Node B is briefly slow and misses a write (acknowledged by A and C — quorum satisfied). For the next hour: B serves reads with the old value. With Read Repair: the next `QUORUM` read that goes through B will detect the stale value and repair B automatically, in the background, without any manual intervention. Without Read Repair: B continues serving stale data until the next Anti-Entropy repair cycle (possibly days or weeks away).

**THE BREAKING POINT:**
In eventually consistent systems, replicas diverge continuously — not just during major failures. Every missed write (due to brief network hiccup, slow node, or replication lag) creates a window of inconsistency. Without a lightweight repair mechanism triggered by normal reads: the system relies entirely on Anti-Entropy (a heavyweight, scheduled background process) to converge. For frequently accessed data: this is too slow. Read Repair is the lightweight, reactive, inline repair that keeps hot data consistent without waiting for the next scheduled repair cycle.

**THE INVENTION MOMENT:**
Read Repair was formalized in the Dynamo paper (Amazon, 2007) and implemented as a first-class feature in Cassandra. The key insight: every quorum read ALREADY compares values from multiple replicas. If the coordinator is already doing the comparison: it costs almost nothing extra to send a repair write to the stale replica. The repair is piggybacked on the read — no additional round trips needed.

**EVOLUTION:**
2007: Amazon Dynamo describes read repair as part of its replica management. 2008: Cassandra implements `read_repair_chance` (probability-based async read repair). 2009-2015: Cassandra adds `dc_local_read_repair_chance` (local datacenter repair separately tunable). 2019: Cassandra 4.0 deprecates `read_repair_chance` (probabilistic) in favor of deterministic read repair with `FULL` consistency. Today: Read Repair is a standard feature in all eventually consistent distributed databases (Cassandra, DynamoDB, Riak, ScyllaDB).

---

### 📘 Textbook Definition

**Read Repair** is a self-healing mechanism in distributed databases where inconsistencies between replicas are detected and corrected during the normal read path. When a coordinator reads from multiple replicas (e.g., quorum read): it compares the responses. If a replica returns a stale value (lower timestamp or missing version): the coordinator sends a write with the current (most recent) value to that stale replica. Two variants: **Foreground (synchronous) Read Repair:** repair completes before the response is returned to the client. Higher latency but stronger consistency guarantee (once client receives value, all queried replicas are consistent). **Background (asynchronous) Read Repair:** client receives response immediately; repair write is sent to stale replica asynchronously. Lower latency but brief window of inconsistency on the stale replica. **Coverage:** Read Repair only fixes keys that are actively read. Cold keys (rarely or never read) are not repaired by Read Repair — that's Anti-Entropy's (DST-063) responsibility.

---

### ⏱️ Understand It in 30 Seconds

**One line:** During a quorum read, the coordinator already compares multiple replica responses — if any replica is stale, it writes the correct value back to that replica as a by-product of the read.

> Read Repair is like asking three waiters what the day's special is. Two say "salmon" and one says "chicken" (yesterday's special, stale). You get salmon (quorum agreement). As the head waiter relays the order: they also tell the mistaken waiter "today's special is salmon, not chicken." The correction happened automatically, inline with the customer's request — no manager intervention needed, no scheduled meeting to correct the mistake.

**One insight:** Read Repair is opportunistic consistency repair — every quorum read is both a data retrieval AND a consistency check. The correction is almost free because the comparison was happening anyway.

---

### 🔩 First Principles Explanation

**CORE INVARIANTS:**
1. **Quorum reads already compare multiple replicas.** For a quorum read (RF=3, R=2): the coordinator reads from 2 replicas and compares. If both have the same value: quorum is satisfied. If they differ: the coordinator must pick the "correct" value (LWW: higher timestamp wins). Read Repair reuses this comparison result — if one replica had a lower timestamp, it's stale. Sending it the correct value costs one async write.
2. **Read Repair probability is configurable (Cassandra).** `read_repair_chance = 0.1` means: for every 10 quorum reads, 1 triggers a Read Repair check against ALL replicas (not just the quorum-contacted replicas). This allows repairs to spread to replicas not contacted by every read. Probability can be 0.0 (no background repair) to 1.0 (repair on every read — highest consistency, highest latency).
3. **Read Repair is reactive, not proactive.** A key that's never read is never repaired by Read Repair. Cold keys (archival data, old records) may be stale indefinitely — only Anti-Entropy (DST-063) covers them.
4. **Sync vs async trade-off is latency vs consistency.** Synchronous Read Repair: stale replica is repaired BEFORE client response. Client reads always see fully repaired state. Cost: read latency includes repair write time (1 extra round trip). Asynchronous: client responds immediately, repair is background. Cost: brief window where the stale replica is still stale (milliseconds to seconds for the repair write to complete).

**DERIVED DESIGN:**
```
Quorum Read (RF=3, R=2):
  Coordinator sends read to Replica A and Replica B
  A returns: {value="Alice", ts=1000}
  B returns: {value="Alice_OLD", ts=900} <- stale

  Coordinator decision:
    LWW: A's ts=1000 > B's ts=900 -> A's value wins
    Return "Alice" to client

  Read Repair (async):
    Coordinator sends write to B:
      {key, value="Alice", ts=1000}
    B updates: {value="Alice", ts=1000} <- repaired
    Client has received response already

  Result: B now consistent with A
  Next read from B: returns "Alice" (repaired)

read_repair_chance (Cassandra):
  On every read: with probability p (default 0.1):
    Also read from ALL replicas (not just quorum)
    Repair any stale replicas found
  Purpose: repair replicas not contacted by regular reads
  Cost: extra read I/O (1 in 10 reads contacts all replicas)
```

**THE TRADE-OFFS:**
**Gain:** Hot data stays consistent automatically. No manual intervention. Repair latency proportional to read frequency (frequently read keys repaired frequently). Works inline with normal operation.
**Cost:** Async repair: brief stale window (milliseconds to seconds). Sync repair: higher read latency. Probability-based repair: not 100% guaranteed (some reads may not trigger repair). Coverage: cold data not covered.

**ESSENTIAL vs ACCIDENTAL COMPLEXITY:**
**Essential:** A quorum read MUST compare replica responses. Any comparison that finds a stale replica could repair it — the essential insight of Read Repair.
**Accidental:** Probability configuration, sync/async toggle, DC-local vs cross-DC repair.

---

### 🧪 Thought Experiment

**SETUP:** Cassandra cluster. A `user_profiles` table with a `last_login` timestamp. 3 replicas. RF=3. Node B briefly drops a write to `user_id=42` due to a 50ms network hiccup. The write succeeds on A and C (quorum satisfied). B still has `last_login = "2024-01-01"` while A and C have `last_login = "2024-06-15"`.

**Without Read Repair:**
- User 42 logs in weekly. Each login is a write to A and C (B still missing).
- Reads: application reads from A and C (quorum) — always returns "2024-06-15" (correct). B is never consulted because quorum is satisfied by A+C.
- After 6 months: B still has "2024-01-01" for user 42.
- Now A fails. Reads go to B and C. B returns stale "2024-01-01". C returns correct "2024-12-15". Quorum of 2: coordinator returns "2024-12-15" (C wins by timestamp). B is still stale.
- B continues serving stale data until next Anti-Entropy repair (scheduled for next Sunday).

**With Read Repair:**
- First read after the missed write: coordinator reads A and B (quorum). A returns "2024-06-15". B returns "2024-01-01". Read Repair: coordinator sends write to B: `last_login="2024-06-15"`. B is repaired within 50ms of the first post-miss read.
- Next read can safely use B: B is consistent.

**THE INSIGHT:** Read Repair converts the next read into a combined "read + repair" operation. The repair happens automatically, proportional to read frequency. Frequently accessed keys stay consistent. The only gap: keys that are never read.

---

### 🧠 Mental Model / Analogy

> Read Repair is like a teacher grading tests who also silently corrects the answer sheet while grading. When a student submits a test (read request): the teacher compares it against the answer key (quorum). If the answer sheet has an outdated answer key (stale replica): the teacher also quietly corrects the answer key copy for next time, without telling the student it was wrong. The correction happens inline with the grading process — no extra "correction review meeting" needed. Only tests that are submitted get their answer keys corrected. Tests that are never submitted (cold data): the stale answer key persists until a scheduled "answer key audit" (Anti-Entropy).

**Mapping:**
- **Student's test** -> client read request
- **Answer key** -> replica's stored value
- **Outdated answer key** -> stale replica (missed a write)
- **Teacher comparing with correct key** -> coordinator comparing quorum responses
- **Silently correcting the outdated key** -> Read Repair write to stale replica
- **Submitted tests only** -> only read-accessed keys are repaired
- **Scheduled audit** -> Anti-Entropy repair

Where this analogy breaks down: Read Repair in distributed databases has probability-based triggering — not every read triggers a full repair check. The teacher analogy implies 100% correction on every read, which is not always the case (configurable via `read_repair_chance`).

---

### 📶 Gradual Depth - Four Levels

**Level 1 - What it is (anyone can understand):**
When a database reads from multiple copies of the same data (for reliability), it automatically checks if all copies agree. If one copy is out of date, it updates that copy quietly in the background. The user gets the correct answer, and the outdated copy is fixed — automatically, without any manual intervention.

**Level 2 - How to use it (junior developer):**
In Cassandra: `read_repair_chance` is per-table, default varies by Cassandra version. Set it in the table schema:
```
CREATE TABLE user_profiles (...) WITH
  read_repair_chance = 0.1         -- 10% of reads trigger repair
  AND dc_local_read_repair_chance = 0.1;  -- local DC only
```
For consistency-critical tables: increase to 0.5 or 1.0. For performance-critical tables: decrease to 0.0 (rely on Anti-Entropy only). Use `CONSISTENCY ALL` reads to force repair on every read (higher latency but strongest consistency). Monitor repairs: `nodetool tpstats | grep ReadRepairStage`.

**Level 3 - How it works (mid-level engineer):**
Cassandra Read Repair internal flow:
```
1. Client: SELECT * FROM users WHERE id=42
   USING CONSISTENCY QUORUM

2. Coordinator picks token range -> identify replicas
   Replicas: A, B, C (RF=3). QUORUM = 2.

3. Read from A and B (first 2 available):
   A: {value="Alice", ts=1000}
   B: {value="Alice_OLD", ts=900}

4. LWW resolution: A wins (ts=1000)
   Return "Alice" to client

5. Read Repair (background):
   Coordinator sends MutationTask to B:
     INSERT INTO users (id, name, ts)
     VALUES (42, 'Alice', 1000)
     USING TIMESTAMP 1000
   B updates its replica

6. [Optional: read_repair_chance check]
   With prob 0.1: also read from C
   If C is stale: repair C too
```

**Level 4 - Why it was designed this way (senior/staff):**
The read_repair_chance probability design reflects a performance/consistency trade-off. At `chance=1.0`: every read contacts ALL replicas and repairs all stale ones. This is essentially `CONSISTENCY ALL` — maximum consistency but highest latency (wait for slowest replica). For most workloads: a 10% chance provides good eventual consistency for hot keys without significant latency overhead. The probability controls the "repair rate" for any given key: a key read 100 times/day with chance=0.1 has an expected 10 repair checks/day — sufficient to keep it consistent. A key read once/week has 0.1 expected repair checks/week — effectively no Read Repair. This is intentional: infrequently read data relies on Anti-Entropy (DST-063) for repair. The probability-based design decouples repair frequency from read frequency, allowing operators to tune the consistency/performance trade-off per table based on their application's actual read patterns.

**Expert Thinking Cues:**
- "Cassandra reads are slow and `nodetool tpstats` shows high ReadRepairStage pending" -> Read Repair is triggered too frequently. Check `read_repair_chance` on hot tables — if set to 1.0 (repair on every read), reduce to 0.1. Also check if recent Anti-Entropy repair ran — post-repair, replicas should be consistent so Read Repair triggers should decrease. High ReadRepairStage = replicas diverged significantly (maybe repair hasn't run in weeks).
- "After a Cassandra node replacement, reads return correct data but P99 latency spiked" -> New node started serving reads but has incomplete data. Read Repair is triggered on every access (all reads find divergences on the new node). New node needs `nodetool repair` — until repair completes, every read that hits the new node triggers a repair write. This is expected behavior. The latency will normalize after repair completes.
- "Our read_repair_chance=0.0 but we still see Read Repair in nodetool stats" -> Cassandra 4.0+ changed behavior: even with `read_repair_chance=0.0`, Cassandra still performs "speculative retry" which can trigger repair. Also: coordinator-side repairs happen for `CONSISTENCY ALL` or `LOCAL_QUORUM` reads regardless of read_repair_chance. Check if the table uses FULL consistency or if the application is explicitly requesting stronger consistency.

---

### ⚙️ How It Works (Mechanism)

**Async vs Sync Read Repair:**
```
ASYNC (default in Cassandra):
Client   Coordinator   Replica A   Replica B (stale)
  |           |             |            |
  |-READ----->|             |            |
  |           |--read------>|            |
  |           |--read------------------->|
  |           |<-{v=10,ts=1000}          |
  |           |<---{v=5,ts=900}          |
  |           | [compare: A wins]        |
  |<-v=10-----|             |            |
  |           |--repair write----------->|
  |           |             |         [B updated]
(client returned before B repaired)

SYNC (CONSISTENCY FULL or read_repair_chance=1.0 trigger):
Client   Coordinator   Replica A   Replica B (stale)
  |           |             |            |
  |-READ----->|             |            |
  |           |--read------>|            |
  |           |--read------------------->|
  |           |<-{v=10,ts=1000}          |
  |           |<---{v=5,ts=900}          |
  |           | [compare: A wins]        |
  |           |--repair write----------->|
  |           |<--ack--------------------|
  |<-v=10-----|
(client waits until B is repaired)
```

---

### 🔄 The Complete Picture - End-to-End Flow

**MISSED WRITE -> READ -> REPAIR -> CONSISTENCY:**

```
Client  Coord  Replica-A  Replica-B  Replica-C
  |       |       |    [B misses write]   |
  |       |--W--->|        |              |
  |       |       | (quorum: A+C write)   |
  |       |--W--->|        |         ---->|
  |       |       |        |              |
  |       |<--ack-|        |              |
  |<-ack--|       |        |              |
  |       |       |        |   <- YOU ARE HERE (next READ)
  |-READ->|       |        |              |
  |       |--R--->|        |              |
  |       |--R------------>|              |
  |       |<-{v=new,ts=100}|              |
  |       |<--{v=old,ts=90}|              |
  |       |[A wins: ts=100]|              |
  |<-v=new|       |        |              |
  |       |--repair write->|              |
  |       |        | [B now consistent]   |
```

**WHAT CHANGES AT SCALE:**
At high read rates (10,000 QPS on a table with `read_repair_chance=0.1`): 1,000 Read Repair writes/second. On a cluster where many replicas are stale (post-partition): this becomes 1,000 repair writes/second. Each repair write is small (single key) but at 1,000/second: disk I/O on stale replicas may be impacted. Tune: reduce `read_repair_chance` to 0.01 on very high-read tables and rely on frequent Anti-Entropy repair instead.

---

### 💻 Code Example

**BAD - Read without consistency consideration (no repair):**
```java
// BAD: reads at CONSISTENCY ONE -- no Read Repair
// Only reads from one replica, no comparison possible
// Stale data returned, no repair triggered
// High throughput but potentially stale for minutes/hours

CqlSession session = CqlSession.builder().build();
ResultSet rs = session.execute(
    "SELECT * FROM users WHERE id = 42"
    // Default consistency: ONE (one replica response)
    // No comparison = no Read Repair possible
    // Stale replica may serve this read indefinitely
);
```

**GOOD - Read with quorum consistency (enables Read Repair):**
```java
// GOOD: read at QUORUM + understand Read Repair behavior
// Coordinator compares multiple replicas
// Automatically repairs stale replicas in background

CqlSession session = CqlSession.builder().build();

// QUORUM read: compares 2 of 3 replicas
// Triggers async Read Repair on stale replica
ResultSet rs = session.execute(
    SimpleStatement.builder(
        "SELECT * FROM users WHERE id = ?")
        .addPositionalValue(42)
        .setConsistencyLevel(ConsistencyLevel.QUORUM)
        .build()
);
// Result: most recent value; stale replica repaired async

// For critical data: LOCAL_QUORUM (same DC quorum)
// Lower latency than QUORUM (no cross-DC round trip)
ResultSet rs2 = session.execute(
    SimpleStatement.builder(
        "SELECT * FROM users WHERE id = ?")
        .addPositionalValue(42)
        .setConsistencyLevel(ConsistencyLevel.LOCAL_QUORUM)
        .build()
);

// Schema-level Read Repair tuning:
// CREATE TABLE users (...) WITH
//   read_repair_chance = 0.1  -- 10% of reads trigger repair
//   AND dc_local_read_repair_chance = 0.1;

// Monitor Read Repair activity:
// nodetool tpstats | grep ReadRepairStage
// ReadRepairStage -- should not have high pending count
// If pending > 100: Read Repair is backlogged (replicas very stale)

// How to verify Read Repair works:
// 1. Write to table with CONSISTENCY ONE (replicate to 1 only)
// 2. Disable write to other replicas (nodetool disablegossip)
// 3. Read at QUORUM from primary replica (gets new value)
// 4. Re-enable gossip: nodetool enablegossip
// 5. Read at LOCAL_ONE from stale replica
//    -> should return new value (read repair applied it)
```

---

### ⚖️ Comparison Table

| | Read Repair | Anti-Entropy | Hinted Handoff |
|:---|:---|:---|:---|
| Trigger | Read operation (reactive) | Scheduled background | Write with unavailable replica |
| Coverage | Read-accessed keys only | ALL keys (proactive) | Recent missed writes |
| Latency impact | Minor (async) / significant (sync) | None (background) | Minor (hint storage) |
| Rate control | `read_repair_chance` (0-1.0) | Schedule + throttle | `hinted_handoff_throttle` |
| Cold data repair | No | Yes | No (hint window only) |
| When sufficient | Hot OLTP data | All cases (backstop) | Short-term unavailability |

---

### ⚠️ Common Misconceptions

| Misconception | Reality |
|:---|:---|
| "Read Repair ensures strong consistency" | Read Repair provides EVENTUAL consistency for read-accessed data, not strong consistency. After a missed write: the stale replica serves stale data until a quorum read triggers repair. The repair happens AFTER the client receives the response (async) or adds latency (sync). Strong consistency requires ALL replicas to agree BEFORE the write is acknowledged — Read Repair is a post-hoc correction, not a consistency guarantee at write time. For strong consistency: use `CONSISTENCY ALL` for writes AND reads. |
| "read_repair_chance=1.0 provides strong consistency" | `read_repair_chance=1.0` means: 100% of reads trigger an additional check against ALL replicas (not just quorum). This is expensive (reads ALL replicas on every access) but still only provides eventual consistency. Between the time a stale value is read and the repair is applied: there's still a window of inconsistency. For strong consistency: use `CONSISTENCY ALL` for both writes and reads (all replicas must acknowledge before write is complete). |
| "Read Repair replaces the need for Anti-Entropy" | Read Repair and Anti-Entropy are COMPLEMENTARY. Read Repair handles hot (frequently read) data — ensuring active keys stay consistent. Anti-Entropy (DST-063) handles cold data, long-term divergences, and provides the complete consistency guarantee. In practice: a typical time-series database has 90%+ of its keys "cold" (read < once/month). Without Anti-Entropy: 90%+ of data may be stale indefinitely. Read Repair alone cannot substitute for Anti-Entropy. |
| "Read Repair is free — it's just comparing values that were already fetched" | Read Repair is NOT free. Async repair generates a write operation to the stale replica (disk I/O + network). Sync repair adds a round-trip to the read latency. Probabilistic repair (read_repair_chance < 1.0) adds extra reads (ALL replicas, not just quorum). At high read rates: Read Repair creates significant background write traffic. For tables with high write rates AND high read rates: the repair traffic can be substantial. Monitor `nodetool tpstats` for ReadRepairStage backlog. |

---

### 🚨 Failure Modes & Diagnosis

**Failure Mode 1: Read Repair Amplification Causes Write Storm**

**Symptom:** A Cassandra cluster serves a high-traffic e-commerce catalog (50,000 reads/second on product table). After a 10-minute network partition (100,000 keys missed writes): Read Repair triggers on every post-partition read. ReadRepairStage queue grows to 50,000 pending repairs. Write throughput doubles temporarily (50,000 product reads + 50,000 repair writes). Disk I/O on stale replicas saturates. Read latency spikes from 5ms to 500ms (disk I/O contention between reads and repair writes).
**Root Cause:** High read rate × significant divergence = high repair write rate. When many keys are diverged simultaneously (after partition heals): all reads find divergences and trigger repairs. Write amplification = (reads/sec) × (read_repair_chance) × (stale fraction). At 50,000 reads/sec, chance=0.1, 100% stale fraction: 5,000 repair writes/second. These compete with production reads.
**Diagnostic:**
```bash
# Check ReadRepairStage queue depth:
nodetool tpstats | grep -A3 "ReadRepairStage"
# Pending > 1000: repair backlog, causing latency

# Check write throughput during repair storm:
nodetool tpstats | grep -A3 "MutationStage"
# Suddenly high: repair writes competing with production

# Check disk I/O:
iostat -x 1 | grep "sda"
# %util > 80% during repair: disk saturation

# Identify most diverged replicas:
nodetool netstats
# Shows repair stream activity per node
```
**Fix:** Temporarily reduce `read_repair_chance` on affected tables: `ALTER TABLE products WITH read_repair_chance = 0.0`. Run a targeted `nodetool repair` on stale nodes to rapidly repair all keys (anti-entropy repair is more efficient than per-read repair for large-scale divergences). After repair completes: restore read_repair_chance to 0.1. Long-term: implement repair proactively (cassandra-reaper weekly schedule) so post-partition divergences are repaired before they accumulate.
**Prevention:** After a network partition heals: immediately run targeted Anti-Entropy repair on affected nodes BEFORE re-enabling them for production reads. This prevents the Read Repair storm. Use cassandra-reaper's "adaptive repair" mode — it detects divergences and schedules targeted repair before reads accumulate.

**Failure Mode 2: Sync Read Repair Increases Tail Latency on Critical Path**

**Symptom:** A financial application uses Cassandra for account balance reads. The team sets `read_repair_chance=1.0` on the accounts table (for strong consistency). P50 read latency: 5ms. P99 read latency: 2500ms (500× worse). P99 latency tracks exactly with the slowest replica's write latency. Root cause: `read_repair_chance=1.0` triggers a sync repair on EVERY read — reading all replicas and waiting for repair writes before returning. The P99 is bounded by the slowest repair write.
**Root Cause:** Sync Read Repair adds repair write latency to the read path. The read latency is now: read_latency + repair_write_latency. Repair write latency includes: network round trip to stale replica + disk write on stale replica. If the stale replica is slow (high disk pressure, GC pause): repair write latency is high -> read P99 is high.
**Diagnostic:**
```bash
# Check read repair stage latency:
nodetool proxyhistograms | grep -A5 "ReadRepair"
# High P99: repair writes are slow

# Check which replica is slow for writes:
nodetool proxyhistograms | grep -A5 "Write"
# Identify slow replica

# Check stale replica's disk pressure:
nodetool cfstats keyspace.accounts | grep "Pending"
# High pending compaction: disk pressure causing slow writes
```
**Fix:** Change from sync to async Read Repair: use `read_repair_chance=0.1` (async, probabilistic). The 10% repair check is async — doesn't block read response. For the financial use case where strong consistency is needed: use `CONSISTENCY ALL` for writes (all replicas ack before write success) — this prevents stale replicas at the cost of write availability. Don't use Read Repair as a substitute for write consistency.
**Prevention:** Read Repair is not a substitute for write consistency. For strong consistency: configure at the write level (`CONSISTENCY ALL` or `LOCAL_QUORUM` for writes) — not at the read level via repair. Reserve `read_repair_chance=1.0` only for low-traffic tables where P99 impact is acceptable.

**Failure Mode 3: Security - Read Repair Enables Data Exfiltration via Timing Side Channel**

**Symptom:** An attacker with read access to a multi-tenant Cassandra cluster notices: reads for specific tenant data are consistently 50ms slower than reads for other tenants. Investigation: the slower reads are triggering Read Repair (stale replica). The attacker uses read timing to infer: (1) which keys exist (repair-triggering reads = keys with recent writes), (2) write frequency (high repair frequency = frequently written data), (3) data freshness (repair overhead correlates with how stale the replica is, which indicates time since last write). Even though the attacker cannot see the data values: timing patterns reveal write patterns, key existence, and data staleness.
**Root Cause:** Read Repair is a side channel: its latency overhead is observable by any client that can measure read latency. Multi-tenant clusters that share infrastructure expose this side channel across tenants. Information leak: key existence, write frequency, and data freshness — valuable for competitive intelligence or attack planning.
**Diagnostic:**
```bash
# Check for anomalous read latency patterns by client IP:
# Application-layer: log read latency per tenant per key range
grep "readLatency.*tenant_id" app.log | \
  awk '{print $tenant_id, $latency}' | \
  sort | uniq -c | sort -rn | head -20
# Identify clients systematically probing key ranges

# Check for systematic read patterns (key range scanning):
grep "SELECT.*FROM.*users" cassandra-system.log | \
  grep "client_ip=suspicious_ip" | wc -l
# High count: systematic read scan (possible probing)
```
**Fix:** Add jitter to read responses: introduce random 0-20ms delay on all reads (hides repair latency signal). Move high-security tenants to dedicated clusters (no shared infrastructure). Implement read rate limiting per client to prevent systematic timing attacks. Use consistent-latency reads (pad responses to fixed latency) for security-sensitive tables.
**Prevention:** Multi-tenant clusters with sensitive data should not share Cassandra infrastructure with untrusted clients. If shared: add application-layer latency jitter before returning read responses. Audit read access patterns — systematic reads across all key ranges indicate probing behavior.

---

### 🔗 Related Keywords

**Prerequisites (understand these first):**
- DST-063 - Anti-Entropy (proactive complement to Read Repair; covers what Read Repair misses)

**Builds On This (learn these next):**
- DST-065 - Hinted Handoff (proactive short-term complement for recent missed writes)

**Alternatives / Comparisons:**
- DST-063 - Anti-Entropy (proactive alternative for cold data)
- DST-065 - Hinted Handoff (proactive alternative for recent missed writes)

---

### 📌 Quick Reference Card

```
+------------------+--------------------------------+
| WHAT IT IS       | Inline replica repair during   |
|                  | quorum reads: coordinator      |
|                  | writes correct value to stale  |
|                  | replicas as by-product of read |
+------------------+--------------------------------+
| PROBLEM SOLVED   | Stale replicas serving old     |
|                  | data after missed writes; hot  |
|                  | data consistency without       |
|                  | scheduled repair cycles        |
+------------------+--------------------------------+
| KEY INSIGHT      | Quorum reads already compare   |
|                  | multiple replicas -- repair    |
|                  | is almost free (use the result)|
+------------------+--------------------------------+
| USE WHEN         | Eventually consistent DB;       |
|                  | hot data that needs to stay    |
|                  | consistent; complement to      |
|                  | Anti-Entropy for active keys   |
+------------------+--------------------------------+
| AVOID WHEN       | Very high read rates (repair   |
|                  | write storm risk); strong      |
|                  | consistency required (use      |
|                  | CONSISTENCY ALL on writes)     |
+------------------+--------------------------------+
| TRADE-OFF        | Consistency vs latency:        |
|                  | sync repair = strong but slow; |
|                  | async repair = fast but brief  |
|                  | stale window remains           |
+------------------+--------------------------------+
| ONE-LINER        | Every quorum read is also a    |
|                  | consistency check -- fix stale |
|                  | replicas inline, for free      |
+------------------+--------------------------------+
| NEXT EXPLORE     | DST-063 Anti-Entropy; DST-065  |
|                  | Hinted Handoff; Cassandra docs |
+------------------+--------------------------------+
```

**If you remember only 3 things:**
1. Read Repair is opportunistic and reactive: it only repairs keys that are actively read. Cold data (rarely or never read) relies entirely on Anti-Entropy (DST-063). Read Repair and Anti-Entropy are complementary — together they cover all data. Alone, neither is sufficient.
2. Async Read Repair is the default and preferred mode: client receives response immediately, stale replica is repaired in background. Sync repair adds latency (repair write completes before client response) — only use sync for critical low-latency paths where consistent P99 is more important than speed, and even then prefer strong write consistency instead.
3. Read Repair is not a substitute for strong write consistency: if you need all replicas to be consistent BEFORE the client gets an acknowledgment, use `CONSISTENCY ALL` or `LOCAL_QUORUM` on writes. Read Repair corrects AFTER the fact — there's always a brief window between a write and the next read-triggered repair where stale data exists.

**Interview one-liner:**
"Read Repair is how distributed databases like Cassandra keep hot data consistent without scheduled repair: during a QUORUM read, the coordinator reads from multiple replicas and compares responses. If a replica has a stale value (lower timestamp), the coordinator sends a write with the current value to that stale replica — asynchronously (client gets response immediately) or synchronously (client waits for repair to complete, higher latency). Configured with `read_repair_chance` (probability of triggering cross-replica comparison on each read). Key limitation: only repairs keys that are read — cold data relies on Anti-Entropy (Merkle tree repair). Trade-off: async repair gives low latency but brief stale windows; sync repair ensures all queried replicas are consistent before client gets response."

---

### 💎 Transferable Wisdom

**Reusable Engineering Principle:**
Opportunistic repair: every diagnostic operation is also a repair opportunity — if you've already done the work to detect a problem, repair it immediately rather than logging it for later. This principle minimizes the gap between detection and correction at near-zero incremental cost. Applied broadly: a health check that detects a misconfigured service should fix the misconfiguration, not just alert. A data migration job that validates each row should fix invalid rows inline, not in a separate pass. A cache warming process that finds a cold cache should populate it, not just report it cold.

**Where else this pattern appears:**
- **CPU cache coherence (MESI protocol).** Modern multi-core CPUs have per-core L1/L2 caches. When two cores have different cached values for the same memory address (cache divergence): every read of that address by another core triggers a coherence check. If the cache is stale: the cache controller fetches the current value and updates the stale cache line — inline with the read, before returning the value to the core. This is hardware-level Read Repair: every read is a consistency check, stale cache lines are repaired inline. The mechanism: MESI protocol (Modified, Exclusive, Shared, Invalid) transitions. "Invalid" cache line = stale replica. Read triggers cache coherence protocol = Read Repair. The pattern: read → detect stale → repair → return — at hardware speed (nanoseconds vs milliseconds in Cassandra, but the same logical pattern).
- **DNS recursive resolver caching.** When a DNS resolver has a cached record that's expired (TTL=0 or past expiry): the next DNS lookup for that name triggers a fresh query to the authoritative server — a "repair" of the expired cache entry. The resolver doesn't pro-actively refresh all cached records (that would be anti-entropy). It only refreshes records that are actively queried. Hot domain names (google.com) are continuously refreshed via reads. Cold domain names (obscure internal hosts) may cache-miss more often. This is DNS Read Repair: reactive, proportional to query frequency, complemented by TTL-based proactive refresh (analogous to Anti-Entropy scheduled refresh).
- **Database query cache invalidation and refresh.** Query caches (Redis, Memcached in front of a database) serve stale data when the underlying database is updated. "Read-through cache" pattern: on cache miss, fetch from database AND update cache. This is cache-level Read Repair: the cache miss triggers a repair of the stale (or missing) cache entry. The read path IS the repair path. Cold keys (rarely queried) remain stale in cache until accessed (reactive repair). Hot keys are continuously refreshed by reads. A background "cache warmer" (proactive refresh) is the Anti-Entropy equivalent.

---

### 💡 The Surprising Truth

Cassandra's Read Repair feature, while powerful, has a subtle and often-overlooked failure mode that can cause data to be PERMANENTLY lost even in a correctly configured cluster. If `read_repair_chance=1.0` is set, and a READ occurs against a replica that holds a tombstone (delete marker), and another replica has the original data (tombstone missed due to network partition) — the Read Repair comparison uses LWW (timestamp-based). If the tombstone has a LOWER timestamp than the original data (possible if the delete used `USING TIMESTAMP` with an old timestamp, or due to clock skew): **the Read Repair will propagate the original data BACK to the replica that had the tombstone, resurrecting deleted data**. The surprising truth: **a feature designed to fix data inconsistencies (Read Repair) can itself CAUSE data inconsistencies by applying LWW incorrectly to tombstones and their original values**. This is a known Cassandra "gotcha" called "zombie rows" — data that was intentionally deleted keeps coming back because a replica keeps winning the LWW comparison with the tombstone. Fix: always use `USING TIMESTAMP now()` for application-level deletes (ensures delete timestamp > write timestamp), and never backdate deletes.

---

### 🧠 Think About This Before We Continue

**Q1 (B - Scale):** A Cassandra cluster handles 100,000 reads/second on a `product_catalog` table with `read_repair_chance=0.1`. The cluster has 9 nodes with RF=3. After a routine maintenance window (1 node offline for 30 minutes during which 100,000 writes were missed by that node): how many Read Repair writes will be generated in the first hour after the node returns? How does this compare to a targeted `nodetool repair`? When should you prefer Anti-Entropy vs relying on Read Repair to handle this divergence?
*Hint:* Post-maintenance: 100,000 keys are diverged on the returned node. Read rate: 100,000 reads/sec on product catalog. Fraction of reads that hit the stale node: 1/3 (one of 3 replicas). Reads hitting stale node: ~33,333/sec. Of those, read_repair_chance=0.1 triggers repair check: 3,333 repair checks/sec. But: repair check contacts ALL replicas (not just quorum) — each finds the stale node and repairs it. Effective repair rate: ~3,333 keys/sec repaired via Read Repair. Time to repair all 100,000 diverged keys: 100,000/3,333 = 30 seconds (if read distribution is uniform across all keys). But product catalog reads are NOT uniform (popular products read much more than obscure ones). The 10,000 most popular products: repaired in seconds. The 90,000 less-popular products: may take hours or days. Anti-Entropy repair: targeted `nodetool repair` on the returned node repairs ALL 100,000 keys in ~minutes (Merkle tree identifies all divergences in one pass). Preference: for short outages (30 minutes), Anti-Entropy repair immediately after node returns is more efficient. For long-running divergences (days), Read Repair handles hot keys continuously while Anti-Entropy handles the full cleanup.

**Q2 (D - Root Cause):** A team observes that after every Read Repair, some "repaired" values in Cassandra are actually OLDER than the values already present on the stale replica. The repaired replica ends up with OLDER data than before the repair. What are the possible root causes? How would you diagnose which cause applies?
*Hint:* Root causes for Read Repair applying older values: (1) Clock skew: coordinator reads from Replica A (ts=1000) and Replica B (stale, ts=1200 — actually B has a NEWER value due to clock skew!). LWW picks A (ts=1000) and "repairs" B with A's older value. B actually had newer data than A. Clock skew caused the wrong winner selection. Diagnosis: check NTP sync across nodes. (2) Application using `USING TIMESTAMP` with old timestamps: application wrote a value with `INSERT INTO ... USING TIMESTAMP 500`. Other replica has ts=700 (older wall-clock but later logical time). LWW picks ts=700 as the "correct" value and overwrites ts=500 on the stale replica — but ts=500's write was the INTENDED latest value. Diagnosis: check application code for `USING TIMESTAMP` patterns. (3) Tombstone LWW issue: as described in The Surprising Truth. A tombstone (delete) has timestamp 800, original data has ts=900. LWW: ts=900 > ts=800 -> original data "wins" over tombstone. Repair propagates the original data to the replica that has the tombstone -> data resurrection. Diagnosis: check if affected rows were recently deleted. All three share a root cause: LWW timestamp comparison is only reliable when timestamps are monotonically increasing, causally correct, and without application-level manipulation. Fix: use consistent timestamp generation (HLC or server-side `now()` for all writes).

**Q3 (C - Design Trade-off):** A team is designing a distributed user session store. Sessions expire after 30 minutes (TTL=30 min). Sessions are written on login and read on every API request (high read rate). The team considers three approaches for handling eventual consistency: (1) Read Repair + `read_repair_chance=1.0`, (2) Anti-Entropy only (scheduled weekly), (3) Strong consistency (`CONSISTENCY ALL` reads and writes). For session data: what are the trade-offs of each approach? Which is most appropriate and why?
*Hint:* Session data characteristics: high read rate (every API call), short TTL (30 min expiry), eventual invalidation on logout. Trade-offs: (1) Read Repair + chance=1.0: every read contacts all replicas, waits for repair before response. Latency: highest (repair write added to read path). Consistency: eventual (stale window between write and first repair-triggering read). For sessions: a user who logs out may have their session served from a stale replica for milliseconds until repair propagates. Generally acceptable for session invalidation (30-second stale window is fine). Cost: P99 latency spike due to sync repair. (2) Anti-Entropy only (weekly): sessions expire every 30 minutes. Weekly repair is irrelevant — by the time repair runs, all active sessions have expired and new ones been created. Sessions written to a stale replica will simply not be recognized (user gets 401) until Read Repair fixes it. For high-read data: Read Repair is a much better fit than Anti-Entropy (too infrequent for data that changes every 30 minutes). (3) Strong consistency (CONSISTENCY ALL): every write acknowledged by all replicas; every read from all replicas. Latency: highest for writes (wait for slowest replica). Availability: if one replica is down, writes fail (violates session creation). Not appropriate for session stores where availability is critical. Best approach for sessions: CONSISTENCY LOCAL_QUORUM for writes and reads + low read_repair_chance (0.1). Provides: good availability (quorum not all), low latency (local DC only), and Hot Read Repair for frequently accessed sessions. The 30-minute TTL means even a 5-minute stale window (between missed write and repair) is acceptable for most session use cases.
'@

$f = Join-Path $base "DST-064 - Read Repair.md"
[System.IO.File]::WriteAllText($f, $newContent, [System.Text.UTF8Encoding]::new($false))
Write-Host "DST-064 written: $((Get-Content $f -Encoding UTF8).Count) lines"
