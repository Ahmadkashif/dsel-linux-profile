# Build the datastore decision harness

## Context

`/Users/mac/Desktop/code/mtp/database-benchmarking-suite` contains research only — a
completed five-phase study whose deliverable, `datastore-selection-automation/findings.md`,
specifies a system nobody has built. No `pyproject.toml`, no tests, no harness code.
`phase-3/` holds verification evidence, not an implementation.

Goal: pick a database engine, a server configuration, and a Python workload, and watch
the pair being pushed to its limits live. The driving question is how a **database and
an app server scale together** — connection counts, throughput cliffs, join behaviour
under sustained load — on a single Docker Compose project.

Two things make this more than re-implementing the research:

1. **Live observability is the primary feature, and the research is silent on it.**
   `plan.md` marks the observability survey complete but `discovery.md` has zero content
   on Prometheus, Grafana, OpenTelemetry or cAdvisor. Every phase-3 capture is
   `docker stats --no-stream` — one sample, after the run. No sampling cadence exists
   anywhere. `metrics.ndjson` is named as a bundle artifact and hashed, but **its record
   schema is never defined**. Defining it is a primary deliverable.
2. **There is no app tier anywhere in the research.** The driver talks straight to the
   DB. The app tier, its metrics, its saturation gate and its per-engine data layers are
   new — as is the connection-ramp axis and the connection-scaling instrumentation.

Outcome: mechanisms and scaling curves learned here, transferable to real hardware by
changing a resource envelope rather than rewriting anything.

---

## Locked decisions

| Decision | Choice |
|---|---|
| Scope | Full decision harness, findings.md M0–M7: gate → measure → weigh → audit bundle |
| Live view | Prometheus + Grafana in the same Compose project |
| Latency truth | **HdrHistogram `.hlog` is authoritative.** Prometheus carries derived series for watching only — a scrape bucket must never become a reported percentile |
| Topology | One Compose project, engine + standardised app tier, programmatically selected |
| App tier | Python (gunicorn/uvicorn + real pool; asyncpg for Postgres) |
| Driver paths | Both, switchable. A: driver→DB. B: driver→app→DB. The delta is the tier's cost |
| Ramp axes | Both. Rate ramp (max sustainable, knee, collapse) and **connection ramp** (hold rate, staircase connections, find the cliff) |
| Workload | `@op`-decorated ops as primary path, plus raw-script escape hatch stamped `latency_validity=closed_loop_uncorrected` and refused by the scorer |
| Engines | All five, breadth first: Postgres 18, Valkey 9, ClickHouse 26, OpenSearch 3, MongoDB 8 |
| Build order | Postgres + app tier end to end, then widen, then gate/scoring/bundle |
| Target machine | **This Mac only.** No Linux runner, now or later. *PROPOSED 2026-10-14, pending the user's confirmation:* add a shared Linux host as a second target under the `linux-shared-8c16t` profile, still `reportable=false` (see "2026-10-14 — Linux host profile") |
| Licensing | **No GPL in the toolchain.** Rules out `memtier_benchmark` |

### Hardware slices — locked

```
cpu 0-1   host + docker daemon + app tier + observability stack
cpu 2-5   ENGINE under test              mem 3 GiB
cpu 6-9   load driver                    mem 1 GiB
          app tier                       mem 1 GiB
          prometheus/grafana/exporters   mem 1.5 GiB
                                          = 6.5 of 7.75 GiB
```

**Measured 2026-09-02 — the slices do not isolate.** `--cpuset-cpus` partitions the
Docker VM's ten *guest* vCPUs, and those are not host cores: Virtualization.framework
schedules all ten guest vCPU threads across the host's 4 performance + 6 efficiency
cores, so load on one slice takes host cores from another. Contention swept on one
slice while measuring the other, 6 randomised blocks with a bootstrap CI over blocks
(`dsel env --interference`):

| Load on the neighbouring slice | Engine 2-5 retains | Driver 6-9 retains |
|---|---|---|
| 1 worker  | 0.93 [0.85, 0.97] | 0.95 [0.88, 0.99] |
| 2 workers | 0.79 [0.77, 0.87] | 0.87 [0.81, 0.98] |
| 4 workers | 0.72 [0.67, 0.75] | 0.80 [0.69, 0.86] |

Replicated; the first sweep read 0.69 and 0.75 at four workers, so the honest figure is
a **20–30% loss** under full load on the neighbouring slice. It is symmetric within
error — an interleaved A/B put the two slices at 1.003, so neither is intrinsically
faster. Runs stamp `cpuset_isolation_ineffective`.

The slice table therefore buys *scheduling separation* inside the guest, not performance
isolation. Every engine measurement is depressed by whatever the driver is doing at the
time, and the `driver_cpu_pct` and `app_tier_cpu_pct` denominators are each a function
of the other tier's load. This is the same objection as risk 5, one tier further out,
and it is not fixable by rearranging the slices — only by not running the driver on the
same machine, which this build has ruled out.

**Thermal drift is first-order, measured 2026-09-02.** The first capacity measurement on
a cool machine read 51.1M ops/s and settled to ~41M within seconds: a 20% swing from
temperature alone, larger than several effects the harness is meant to resolve.
findings.md §8.8 lists thermal state among the things that cannot be reproduced; on this
machine it is not a footnote, and any two cells compared across minutes must assume it.

Every run stamps `profile=local`, `envelope_deviation=true`, `reportable=false`. There is
no second profile to build — but the envelope stays a spec value rather than a constant,
so larger hardware would be a YAML change if that ever becomes true.

### What this build will and will not claim

This machine is the only target, which sets the honest scope. **The harness produces
mechanisms, relationships and scaling curves. It will refuse to sign a capacity claim**
("this serves 40,000 orders/sec"), because such a number would not be true anywhere else.
That refusal is enforced by `dsel verify`, not left to discipline, and it goes in the
README at S0 rather than being discovered at G3.

Three consequences to accept up front:

- **MongoDB 8 never runs here** (kernel ≥6.19, SERVER-121912). It stays in the candidate
  set precisely because it exercises the environment gate — "cannot run here" as a
  first-class result is a feature being built, not a gap.
- **Valkey's latency ceiling is permanently unmeasurable.** With GPL ruled out, the
  Python driver saturates first (~80–160k ops/s across four workers, against exp02's
  measured 150–290k). Valkey reports `INCONCLUSIVE_DRIVER_BOUND` with the driver-side
  ceiling recorded. `valkey-benchmark` (BSD-3, already in the image) bounds the ramp and
  proves driver-boundness, but is closed-loop so its latency is never claimed.
- **The A/B delta between driver→DB and driver→app→DB stays `ab_delta_valid=false`**
  locally, because the app tier shares cores 0-1 with the observability stack.

So the ranking machinery will, on this hardware, rank a candidate set of roughly three
engines and decline to emit a signed comparative report. That is the machinery working
correctly. **The machinery is the deliverable.**

---

## Design decisions taken during planning

- **D1 — The driver runs in a container**, never on the macOS host. Host→VM traffic
  crosses VirtioFS-grade overhead and pollutes exactly the latency being measured.
  Container-to-container over a Compose bridge stays inside the VM.
- **D2 — Render `compose.rendered.yaml` from Jinja2**, don't use Compose profiles. The
  envelope, cpusets and digests come from the spec; a rendered file is hashable into the
  bundle and a profile is not.
- **D3 — Prometheus gets data by tailing `metrics.ndjson`** through a custom
  `prometheus_client` Collector. One write path, one source of truth; the exporter is a
  consumer like any other. No pushgateway, no remote-write.
- **D5 — Calibration tools (`pgbench`, `valkey-benchmark`) run inside the engine image**
  on cpuset 6-9, not from the host. They are already in the pinned images.
- **D6 — The driver is multi-process from the start.** A saturated single Python process
  reads ~25% of a 4-core quota, so the 70% gate silently never fires. Per-worker CPU gate
  plus an implementation-independent schedule-lag gate.
- **D7 — No VirtioFS mount inside a measurement window**, ever.
- **D9 — Build the TUI first, Grafana second.** Grafana is AGPL-3.0 and could stall at
  legal review; the live-observability requirement must not depend on it.

### New gate

**App-tier CPU > 70% ⇒ INVALID for database-level claims**, mirroring the driver gate one
tier up. Without it, app-tier limits saturate first and every engine looks identical.

---

## Milestones

**Rule for every phase below: the `Accept:` line is the definition of done.** It must be
decidable by a command — an exit code, a diff, a count, a round-trip comparison, or a
deliberately-tripped failure path. A phase is not finished, and nothing from it is
committed, until its criterion runs and passes. If it fails, that gets reported rather
than worked around.

### Slice 1 — Postgres + app tier, end to end

**S0 Skeleton.** uv project on Python 3.13, `dsel` CLI, run directory layout. README
states plainly what this build can and cannot claim on this hardware.
*Accept:* `uv sync --frozen` succeeds from a clean checkout and `uv run dsel --version`
exits 0; a CI test greps the README for the no-capacity-claims paragraph and fails if it
is absent.

**S1 Environment capture + vCPU speed probe.** *De-risk early.* The M5 is 4 performance +
6 efficiency cores, so `cpuset 2-5` and `6-9` may straddle core classes — findings.md
chose those sets without examining it. Probe: 200 ms of fixed integer work per vCPU,
recorded as `vcpu_relative_speed[0..9]`. If engine-set and driver-set aggregate speed
differ >10%, append `heterogeneous_cores` to `envelope_deviation_reasons`.
*Accept:* the manifest carries a per-vCPU speed vector and the deviation flag is correct.
*Done 2026-09-02.* The premise does not hold, and cannot be tested from inside the VM:
the between-vCPU span was 7.1% against within-vCPU noise of 42.7%, a signal-to-noise of
0.17, because the hypervisor reschedules guest vCPUs across host cores continuously. So
`heterogeneous_cores` cannot fire on merit here; it is implemented and was demonstrated
firing under deliberate contention (12.1% > 10%). A run also stamps
`vcpu_speed_indistinguishable`, so a bare `false` is not misread as a positive finding
of uniformity. The capture also records two facts that bear on cross-bundle comparison:
the VM reports `rotational=1` for `vda`/`vdb` over APFS on NVMe, and THP is `[always]`
and is host-global, so not settable per container.

**S2 Budget assertion.** *De-risk early.* `compose/budget.py` computes cpuset and memory
totals before any container starts and refuses impossible combinations.
*Accept:* `profile=local` + app tier + deep observability is refused with the arithmetic
shown.

**S3–S5 Provisioning.** Digest resolution (index pinned, platform recorded, `unknown/unknown`
attestation entries skipped), resource envelope with `--cpuset-cpus` AND `--cpus` AND
`--memory`/`--memory-swap`, named-volume enforcement via `stat -f -c "%T"`, TCP health
gate, idempotent teardown on SIGINT/SIGTERM/crash.
*Accept:* every knob read back from the running engine matches the envelope; teardown
exits 0 twice.

**S6 `metrics.ndjson` schema.** *De-risk early — every emitter depends on it.* Pydantic
models per record kind → committed `schema/metrics.schema.json`, CI drift-checked.
Sharded writers with `seq`, deterministic merge by `(t_ms, w, seq)`.
Record kinds: `phase`, `latency_window`, `container`, `engine`, `backend`, `pool`, `app`,
`net`, `validity`.
Cadence: containers 1 Hz · engine light 1 Hz / heavy 5 s · per-backend sampling drops to
10 s above 256 connections and stamps `sampler.backpressure=true`.
*Accept:* 100 shuffled shard merges produce a byte-identical file.

**S7 Samplers.** Docker stats stream, cgroup readers (`cpu.stat`, `cpu.max`,
`cpuset.cpus.effective`, `memory.max|current|events`, `pids.current`), `docker events`
for `oom`/`die`/`health_status`.
*Accept:* against a live container, every sampler emits records that validate against
`schema/metrics.schema.json`, and cgroup readings equal the corresponding
`docker inspect .HostConfig` values exactly; killing the container with `--memory` exceeded
produces an `oom` record.

**S8a Live TUI.** `dsel watch` tails the event stream. **This alone satisfies the
live-observability requirement.**
*Accept:* `dsel watch --replay <run-id>` on a finished run reaches the same final screen
state as the live session did, and the warmup→measure boundary is visibly marked in both.
*Done 2026-09-03.* The criterion is an ordering statement, not an arithmetic one, and the
obvious tailer fails it. Screen state is a fold over records, so a live view that applies
whatever is new in each shard lands somewhere the merge never does — a sampler writing
every 300 ms delivers records long after the driver records they should have preceded. So
`live/tail.py` runs the *same* k-way merge over sources that have not ended, holding each
record until no shard can still undercut it (release while `t_ms <` the minimum last-seen
`t_ms` across shards; drain unbounded at close). The screen therefore lags the slowest
sampler's interval by construction — that is the price of live and replay agreeing.
Measured: a 285-record run over three writers, live and replay final state and rendered
screen byte-identical. Two file-level facts had to be handled rather than assumed away — a
trailing line with no newline is not yet a record, and a shard appearing late with records
older than the watermark is refused loudly. One real bug surfaced: `read_shard` enforces
one-writer-per-shard, which a *merged* file legitimately violates, so `read_merged`
enforces the total order instead.

**S8b Prometheus + Grafana.** Tail-and-expose collector, provisioned dashboards
(`now`, `connections`, `joins`, `validity`). Series budget ≤500 active, ≤5000 per run;
`step`/`repeat` join from `dsbench_cell_info` rather than becoming labels.
*Accept:* `count({__name__=~"dsbench_.*"})` stays ≤500 for a full run; every panel in all
four dashboards resolves against a completed run with no "No data"; every latency panel
carries a visible "within-window estimate, not the reported figure" annotation.
*Done 2026-09-03.* Measured against a live stack: **peak 141 active series of the 500 cap,
0 refused, 48 panel targets across the four dashboards, 48 resolved.** Three things had to
change from the obvious build.

*The budget needs admission control, or the acceptance number is meaningless.* A series
count under the cap proves nothing on its own — an exporter that silently dropped families
would also report one. `SeriesBudget` refuses past the cap and publishes
`dsbench_series_refused_total`, and the acceptance asserts the pair: under the cap **and**
zero refused.

*The series that would blow the budget is the per-backend view.* A connection ramp to 500
backends is 500 series per metric, and `step`/`repeat` as labels would multiply the whole
set by the length of a ramp again. So backends are aggregated by state and wait event
before publishing, `step` and `repeat` join from `dsbench_cell_info`, and engine internals
come from an allowlist rather than from whatever keys the engine returned. The exporter
holds 30 individual backends in state and publishes 7 series for them.

*Prometheus `external_labels` do not reach locally stored samples.* `profile=local` and
`reportable=false` were set there first and were absent from every query result. They are
target labels now, so a graph lifted out of Grafana still carries the stamp.

Nothing is bind-mounted: the rendered Prometheus config and the four dashboards are
streamed into a named volume with `docker cp`, because a config bind mount is still a
VirtioFS mount for the life of a run (D7), and Grafana's provisioner polls its directory.

**S10 Open-loop driver.** Poisson arrival, latency from scheduled start, HdrHistogram
per worker, multi-process supervisor, per-worker CPU gate.
*Accept, and verify here not at M7:* a `.hlog` written from Python is read by the Java
`HistogramLogProcessor` in a pinned JDK container with p50/p99/p99.9 matching within one
bucket. The entire "third party recomputes percentiles" claim rests on this.
*Done 2026-09-03.* **Passed — exactly, at p50/p99/p99.9 and at all 57 rows the processor
printed.** But the acceptance as worded compares two things that are not the same
quantity, and this had to be found before the claim could be made honestly.

`HistogramLogProcessor` prints the **percentile iterator**, not `getValueAtPercentile`.
The iterator walks buckets in one direction and each step is forced to a strictly higher
bucket than the last, so where consecutive percentile levels land in the same bucket the
later one is pushed outward; it also prints steps at 0.990234375, never at 0.99.
Comparing its row against a nominal Python `p99` therefore measures the two
implementations' percentile *conventions*. Measured at 2 000, 8 000, 20 000 and 60 000
samples, that comparison disagrees by 1.08%, 1.07%, 1.14% and 0.94% — it does not shrink
with sample size, because it was never sampling noise.

The count column is unambiguous: "the value at which the cumulative count first reaches
k" means one thing in both implementations. Compared on it, **every printed row matches
exactly** — which is the claim that actually matters, since a third party reading our raw
histogram must recover our distribution, not our rounding rule.

Also settled at S10: a worker holds **one request in flight**, so `n` workers cannot
deliver more than `n / service_time` however high the offered rate is set. That ceiling is
not hidden — past it the worker falls behind its schedule, the lateness lands in every
latency it records, and the lag gate fires `INCONCLUSIVE_DRIVER_BOUND`. Demonstrated: 8 ms
of service against a 2.5 ms mean inter-arrival produced a driver-bound verdict and a p50
above 100 ms, rather than a flattering p99. The arrival schedule is index-derived
(`blake2b(seed│worker│index)`), so one arrival can be re-derived from the bundle months
later without replaying the stream. Two logs are written per operation — corrected (from
the scheduled start, reported) and uncorrected (from issue) — so the omission correction
is checkable rather than asserted.

**S11–S12 Rate ramp + pgbench calibration.** If the first-party driver disagrees with
pgbench beyond the noise floor, the driver is wrong.
*Accept:* against identical Postgres and workload, driver and `pgbench -R` agree on
achieved rate within 1% and on mean latency within the measured noise floor; the ramp
recovers a knee and collapse point from a synthetic target whose limits are known by
construction.
*Done 2026-09-03. Ramp: passed. Rate: passed. Mean latency: **not decidable**, and the
reason is recorded rather than tuned away.*

**The ramp.** Against a target whose service time is `median / (1 - offered/C)`, both
limits are arithmetic before the ramp runs: knee `C - (C - baseline)/2` = 350/s, collapse
`W / (median + W/C)` = 566/s. The ramp reported the first step past each — 400/s and
600/s — and its whole achieved-throughput curve tracked the closed form (100 → 107,
200 → 204, 300 → 296, 400 → 398, 500 → 492, then collapse to 380 and 229).

**`time.sleep` is not a way to wait.** The first ramp reported a p50 of 3.7 ms against a
target whose service time was 0.5 ms, and the knee was invisible underneath it. Measured
on this host: `sleep(1 ms)` overshoots by 514 µs, `sleep(5 ms)` by 2 514 µs, `sleep(20 ms)`
by 8 529 µs — roughly *half the requested interval* plus half a millisecond, because the
kernel coalesces timers. There is no fixed margin to subtract. `driver/clock.py` sleeps a
fixed *fraction* of the time remaining, which converges on the deadline geometrically and
cannot overshoot it, then spins the last 1.5 ms. p50 went 3 747 µs → 493 µs against a
closed-form 480 µs. This also added a third driver gate: when median lag exceeds median
service time, the reported latency describes the driver rather than the engine.

**Calibration: what was held equal, and what it cost to find out.** Four confounds, each
found by measurement, each worth more than the comparison itself:

1. *Connection setup was inside the measurement window* — `transport.open()` ran after the
   phase clock started, putting the connect into the denominator of the achieved rate. 1.6%.
2. *Protocol.* pgbench defaults to `-M simple`; asyncpg prepares. 1 837 µs against 585 µs,
   a 3× gap with nothing to do with load generation. `-M prepared` is not tuning, it is
   what makes the two comparable.
3. *Rate definition.* Each tool divides by its own elapsed time, and pgbench's excludes
   connection setup and ends at its last scheduled arrival. Both are recomputed as
   `transactions / duration`.
4. *Latency definition.* pgbench prints `latency average = 1.711 ms` and, separately,
   `rate limit schedule lag: avg 1.500 ms`. **88% of what pgbench reports as latency is
   pgbench waiting for its own scheduler.** Both tools measure from the scheduled start, so
   both carry their own lag; each is subtracted before comparing. Measured, pgbench's own
   lag is 1 137 µs against this driver's 1 µs.

**Rate: passed.** 0.60% between the tools, against the 1% asked. But PLAN.md's flat 1% is
below the sampling noise of any short run: arrival counts are Poisson, so a run's own
relative spread is `1/√N`, and at 300/s for 8 s that is 2%. The comparison had to be
resized to 1 000/s for 12 s — 12 000 arrivals a run, 36 000 pooled — before 1% was a
criterion rather than a coin toss. Repeats now use a different seed each, since replaying
one index-derived schedule three times measures the target's variance, not the tool's.

**Mean latency: not decidable on this host.** `pg_stat_statements` — Postgres measuring
itself, the only arbiter that is not one of the two suspects — reports **22.3 µs of
execution per statement for pgbench against 3.6 µs for this driver**, for an identical
query string. Four explanations were excluded by measurement:

- *cache warmth*: without `pg_prewarm` the first tool to run did the physical reads (1 483
  block reads against 763, and 33 µs against 5 µs of execution as a result). Both sides now
  show **0.000 block reads per call**, and the gap did not move. A rate-limited warmup
  cannot do this job — at 1 000/s for six seconds it makes ~6 000 random accesses across a
  table of 8 000-odd pages.
- *run order*: blocks alternate which tool goes first. The gap followed the tool.
- *protocol mode*: `-M simple` and `-M prepared` differ by ~5%, not 6×.
- *the plan*: plan time is 0 for both, `shared_blks_hit` matches within 1%, rows match.

The untested hypothesis is the parameter and result *format* — libpq text on both against
asyncpg binary on both, with output conversion falling inside the window `mean_exec_time`
covers. **That is a hypothesis, not a finding.** Until it is settled, comparing what two
clients observed says nothing about the clients, because the server is not doing the same
work for them. What the suite asserts instead is the relation that would catch a broken
driver: neither tool may report less client-side service time than the server spent
executing.

**Also built here.** The driver now runs in a container (`images/driver/Dockerfile`,
two-stage because `hdrhistogram` compiles a C extension and the toolchain has no business
in a measurement container). That is not incidental: pgbench runs from the engine image by
D5 and reaches Postgres over a Docker network, so a host-side driver would carry Docker
Desktop's published-port hop that pgbench does not, and the hop would appear in the
comparison dressed as a difference between the tools.

**S13 App tier + its ceiling.** *De-risk early.* FastAPI, per-worker asyncpg pool,
span timing (`t_app_recv`/`t_db_start`/`t_db_end`/`t_app_send`). Measure the `/noop`
ceiling before wiring PATH B, so app-tier saturation is a known number, not a surprise.
*Accept:* `/noop` ceiling is measured and written to the manifest; driving past it makes
the `app_tier_cpu_pct` gate fire and stamp `INVALID(app_tier_saturated)` — the gate is
demonstrated tripping, not merely implemented.
*Done 2026-09-03.* **Passed.** At half a core and one uvicorn worker the tier saturates at
**900/s**, which sets PATH B's rate at 540/s (60%). The gate has a closed side as well as an
open one — 20.4% at 200/s, 50.3% at 500/s, then 73.3% and INVALID(app_tier_saturated) at
900/s — so it is a gate and not a constant. It is stamped into the run's own
`metrics.ndjson`, not derived afterwards: a cell is invalidated by something that happened
during it, and the record has to be in the stream the bundle hashes.

**Reading the CPU after a step is not reading the CPU.** The first version sampled `/cpu`
once when each step finished, which is after the ramp has torn its worker processes down,
so the tier's most recent one-second window was part load and part idle. The curve came out
non-monotonic — 93.7% at 1400/s and 65.1% at 2800/s — and *the gate re-closed above a
ceiling it had already crossed*. A thread now samples throughout each step and the statistic
is the peak, because a tier that spends part of a step above the limit is saturated for
that part. Above the limit the readings plateau near the quota rather than rising, which is
the container being throttled; monotonicity is only required below the gate.

`AppCeilingRecord` distinguishes two numbers that are easy to conflate: the rate where the
gate fires (the planning number) and the highest rate ever served (measured past the gate,
so any result taken there is already invalid).

**S14 PATH B.** Driver→app→DB, scheduled against the measured app ceiling (capped at 60%
of it locally).
*Accept:* for the same workload, PATH B's `t_db_end − t_db_start` distribution overlaps
PATH A's latency distribution; `ab_delta_valid=false` is stamped on every local run.
*Done 2026-09-03.* **Passed, after the comparison found three instrumentation faults —
which is what it is for.**

| | p10 | p50 | p90 | p99 |
|---|---|---|---|---|
| PATH A driver→engine (inner) | 67 | **81** | 100 | 136 |
| PATH B app→engine (`db_us`) | 58 | **67** | 86 | 144 |
| PATH B app total | 205 | 228 | 265 | 364 |

Bulk overlaps; medians 1.21× apart. Getting there took three fixes:

1. **Pool acquisition was inside the engine interval.** `span.db_begin()` fired before
   `pool.acquire()`, so PATH B's "engine interval" read 142 µs against PATH A's *whole*
   latency of 101 µs — the tier appearing slower at the engine than the driver was
   end-to-end. Acquisition is the tier's grip on the engine, not the engine: it queues, it
   is bounded by pool size, and at S16 it is what produces the connection cliff.
2. **The span started after the framework had finished.** A span created inside a handler
   begins after parsing, routing and validation and ends before serialisation, and the
   tier's own cost came out as **1 µs** — the framework had made itself invisible to its own
   instrumentation. ASGI middleware now owns both outer instants; the tier's real cost is
   162 µs at p50.
3. **PATH A's latency is not comparable to PATH B's `db_us`.** The driver pays an entire
   event-loop turn per operation, which the app tier does not pay per request and which
   structurally cannot appear in its `db_us`. Comparing the two end-to-end is the same
   mistake S12 found in pgbench — a client cost read as the engine's. The driver now also
   records an *inner* histogram timed inside the coroutine; **the difference, 21 µs at p50,
   is the driver's own per-operation cost, reported rather than buried.**

The residual after all three is 1.21×, and it has a direction: the driver's own view of
the engine is always the slower one. The interquartile ranges sit *adjacent* rather than
overlapping — 75–93 against 62–74, missing by a microsecond — so the overlap band is stated
as p10–p90 and the residual is asserted by direction and bound instead of being tuned away.
The likely cause is the driver's spin-wait: four workers each spinning the last 1.5 ms of
every inter-arrival is about 0.8 of a core of contention on cpuset 6–9 that the tier on
0–1 does not have. **UNVERIFIED** — the direction and the bound are asserted, the
explanation is not.

`ab_delta_valid=false` is the `Manifest` default and not a placeholder. The tempting number
is `PATH B total − PATH A total = the app tier's cost`; it subtracts two measurements taken
where driver, tier, engine and observability share ten cores that `cpuset` does not isolate
(S1: 20–30% across sets). Each side carries that interference, so the difference is not a
clean measure of anything. The 162 µs is a shape, not a figure to report.

**S15 Phenomena derivation.** `phenomena/*` reads `metrics.ndjson` and never touches
Docker or the engine; `live/sampler/*` writes records and never derives a phenomenon.
*Accept:* an independent script re-derives knee and collapse from `metrics.ndjson` alone.
*Done 2026-09-03.* **Passed.** `scripts/rederive_landmarks.py`, given a file and nothing
else — no run directory, no daemon, no engine — recovers knee 400/s, collapse 600/s and
max sustainable 500/s, identical to the numbers the run reported in memory.

The rules now live in `phenomena/conn_cliff.py` and the driver imports them. It is *one*
definition applied to two data paths; a second copy in the driver would drift, and the
re-derivation would then be two definitions agreeing with themselves. A test asserts the
ramp neither assigns the thresholds nor computes its own landmarks.

Making the file sufficient exposed three bugs in what was being written into it.

**A window claimed a width it did not cover.** `latency_window` carried the *nominal*
width, so the final partial window of every step claimed a full second. Every rate derived
from the file came out low in proportion — 25% on a 4 s step with a 1 s window — and that
includes the `rate_per_s` field itself and therefore the Prometheus series built from it.
Windows now carry the width they actually covered.

**The warmup was inside the first measured window.** The window boundary fires on the
first *completion* past the boundary, so the window that closed at 1.15 s spanned the whole
warmup and held the single operation that had crossed it: `window_ms=1150, count=1`. The
measurement window now opens when the warmup closes.

**Two definitions of "achieved rate".** In memory it was `issued / elapsed` — every
arrival including warmup, over the whole phase. From the file it can only be recorded
arrivals over the measured span. They nearly cancel and did not exactly, so the two paths
disagreed by 1.6% and `max_sustainable` fell on opposite sides of its threshold. The
driver now reports the same quantity the file does.

**And one about the statistic itself.** The file's per-cell p99 was first taken as the
*maximum* of the window estimates. On a busy host that inflated the baseline cell enough to
raise the doubling threshold and move the knee a whole step — 500/s from the file against
400/s in memory, on the same run. It is a count-weighted mean now: a knee that moves with
what the neighbours are doing is not a knee.

Also settled: the closed-form throughput model is held to 20% only *up to* the collapse.
Past it the model's queue term was chosen to be steep and monotonic, not to be an M/M/1,
and it predicted 240/s where the run delivered 185/s. The turn-over point is a prediction;
the depth of the far tail is not one this model is entitled to make, so past collapse only
the shape is asserted.

**S16–S18 Connection ramp + the three phenomena.**
- (a) **Cliff** — hold rate, staircase connections; per-connection rate, aggregate
  turnover, wait-event shift, `pids.current` and `nofile` walls.
- (b) **Backend growth** — per-backend `VmRSS` against connection age, RSS slope with CI.
  Ground truth is `VmRSS`, which works on every version;
  `pg_log_backend_memory_contexts()` (PG14+) is the guaranteed fallback for the cache
  breakdown. Do not depend on `pg_get_process_memory_contexts()` — UNVERIFIED on PG18.
- (c) **Lifecycle** — refusal/reset attribution by mechanism: `max_connections`,
  `idle_in_transaction_session_timeout`, keepalive, pool reaper, TIME_WAIT and ephemeral
  ports from `/proc/net/netstat`+`sockstat`, listen-backlog overflow.
  Note `max_connections=32` provocation needs its own provision cycle — it is not a
  runtime knob.
*Accept:* (a) a ramp past the knee shows aggregate throughput falling while connection
count rises, with knee and collapse re-derivable from `metrics.ndjson` alone; (b) over a
≥1 h soak the per-backend RSS slope has a bootstrap CI excluding zero; (c) a
`max_connections=32` run attributes every refusal to a named mechanism with zero
`unknown` causes.

*(c) Done 2026-09-03. Passed:* 32 opened, 34 failures, **zero unattributed**, three named
mechanisms. `max_connections` is not a runtime knob, so the provocation gets its own
provision cycle — it cannot ride along on a run measuring something else.

Two mechanisms were provoked rather than one, because a table that only ever sees
`max_connections` has been shown to return a constant, not to discriminate. The second one
exposed a real limit of client-side evidence: **when Postgres reaps an idle-in-transaction
session it writes a FATAL and closes the socket, and the client's next statement finds
nothing left to receive an error from.** It arrives as `server_closed`, with no SQLSTATE
and no reason. For anything the server initiates, the client's account is not evidence. The
engine is now provisioned with `%e` in `log_line_prefix` and its log is read as a second
source; without `%e` the attribution would be matching English prose and would break on a
translated server.

Attribution is by SQLSTATE first, errno second, text last, and an unmatched failure is
loudly `unknown` rather than bucketed into the nearest neighbour — a wrong name is worse
than an admitted gap, because a wrong name gets acted on.

*(a) 2026-09-03 — the measured effect was thermal, and finding that out took six runs.*
Run in ascending rung order, five consecutive ramps each reported a clean 10–15% fall in
throughput from 8 connections to 32, then a plateau. Medians from one of them: 3891, 3534,
3321, 3308, 3345, 3333 per second across 8→256 connections. It looked like the result
PLAN.md predicted. **The sixth run, on a machine that had been under continuous Docker load
for forty minutes, came out flat — 3181, 3202, 3149, 3181, 3226, 3125 — at a level 15%
below all five.**

Ascending order makes rung position a proxy for elapsed time, and on this host elapsed time
is a proxy for temperature: the first rung of every ramp ran on a cooler machine than the
last. The rung order is randomised per repeat now, from the seed, the same block design
`audit/interference.py` uses. No directional claim is asserted until the corrected
measurement is in.

Three other things had to be fixed before the question was even askable:

- **`collapse` fired on a single dip.** The rule returned the first point below the running
  peak by 5%, and a 6.7% blip at one rung — contradicted by the next three — was reported
  as a collapse. It requires the fall to be *sustained* now. An error-rate breach still
  fires immediately, because errors are not noise.
- **Repeats were not pooled.** Left as separate points, the running peak becomes the best
  single pass of the best rung and every later drop is measured against that pass's own
  good luck. Repeats are pooled by median now, which is what repeats are for.
- **The engine has to be saturated or the ramp measures nothing.** At 2500/s it delivered
  2484/s at every rung from 8 to 128 — flat, with the extra connections simply idle.
  Contention needs something to contend for; the ramp runs at 8000/s against a one-core
  engine, which serves about 3200/s.

The connection count on the axis is the engine's own `backends` reading, snapped to the
rung, never the number the ramp asked for — the cliff is precisely where those two stop
being the same.

*(b) 2026-09-03 — the first soak produced a degenerate interval, and that is now detected.*
24 connections doing identical work gave 21 *identical* per-backend slopes: every bootstrap
resample had the same median, the interval came out with zero width, and it "excluded zero"
for a reason that had nothing to do with memory. `GrowthResult.degenerate` reports it, and
the acceptance requires `significant` — excludes zero **and** not degenerate. The soak now
gives each connection its own statement (point lookup, range count, sort, join), its own
slice of the key space and its own cadence, because production connections are not clones
either.

**(b) is NOT accepted.** The ≥1 h soak was started on 2026-09-03 and did not survive the
session; its shards are gone and no result was ever recorded. The machinery is built and
unit-tested — the sampler, the per-backend fit, the bootstrap over backends, the degeneracy
check, and `scripts/analyse_backend_growth.py` — but the acceptance criterion has not been
met. To meet it:

```bash
python scripts/soak_backend_growth.py --minutes 65 --connections 24 --out runs
DSEL_SOAK_METRICS=runs/<run-id>/metrics.ndjson uv run pytest \
    tests/integration/test_backend_growth_soak.py -q -s
```

The test skips rather than passes when `DSEL_SOAK_METRICS` is unset, so nothing in the
suite currently claims this phase is done.

### 2026-10-14 — Linux host profile (round 2, registry issue #6)

Run on a shared bare-metal Linux host: Intel i7-10700K (8 cores / 16 threads, a desktop part,
not the laptop the brief expected), MemTotal 31.06 GiB, Ubuntu 24.04.5, kernel 7.0.0-34,
cgroup v2, Docker Engine 29.8.1, ext4 root on NVMe (`rotational=0`), THP `madvise`, governor
`powersave` (intel_pstate), SMT on. Co-tenants at the time: a native ollama service and one
Temporal container; no LLM gateway was listening. Nothing on the host was changed.

**The locked decision.** "This Mac only" is *not* reversed here. The reversal is PROPOSED in
the table above and waits on the user. Everything below is built so that confirming it is a
one-line change to this file.

**Done 2026-10-14.**

- *Toolchain on Linux.* From a fresh clone at 32b167b, `uv sync --frozen`, ruff, ruff format
  and mypy --strict were green unchanged; `pytest tests/unit` failed **1 of 235**:
  `test_the_exception_classifier_keeps_evidence_and_adds_nothing`. Cause: the errno table
  in `phenomena/conn_lifecycle.py` held macOS numbers (ECONNREFUSED is 61 there, 111 on
  Linux, where 61 is ENODATA). It is keyed by symbolic name now, and the name the recording
  host wrote into the record wins over the number. After all changes: 298 unit tests pass.
- *Host profiles* (`src/dsel/hostprofile/`). `local` is the slice table above, verbatim; its
  unit tests pass untouched and its budget arithmetic is asserted byte-identical.
  `linux-shared-8c16t` maps whole physical cores from `lscpu -e` — engine 4-5,12-13, driver
  6,14, app tier + observability 7,15, reserved 0-3,8-11 — and refuses a host below its
  minimum spec, naming the row. The brief's ">= 32 GiB" floor would have refused this 32 GB
  machine (MemTotal 31.06 GiB), so the file says 30 GiB and the user decides.
- *Budget against the allowance.* *Accept:* `dsel budget` on the Linux profile refuses an
  over-allowance plan with the arithmetic shown. **Passed**: deep observability claims
  12.50G against the 12.00G allowance, "over by 0.50G (dsel allowance)", with the host's
  31.06G shown and labelled "is not the budget"; `--engine-memory-gib 10` is refused at
  14.50G.
- *Loopback only.* Engine and app tier `--publish` and the observability compose `ports:`
  bind 127.0.0.1; on Linux the stack uses 19090 / 13000 / 19464 and the exporter binds the
  docker bridge gateway. Asserted by unit tests; the live stack was not started.
- *Every container capped.* Probe, interference, JDK, seed and capture containers get a
  cpuset inside dsel's cores, a memory ceiling with swap equal to it, a pids limit and the
  run label on a shared host. Host-side drivers pin themselves to the driver tier.
- *Found by running on Linux, fixed:* the platform digest was looked up by tag, not by the
  index digest held; the vCPU probe compared set totals, so four engine CPUs against two
  driver CPUs read as 49.6% "heterogeneous"; and the re-derivation divided a multi-op cell's
  rate by its number of ops (see below).
- *Thermal confound, instrumented.* A `host` record (schema v3) carries package temperature
  and the clocks of the CPUs in use, read from /sys at 1 Hz; `phenomena/thermal.py` and
  `rederive_landmarks.py --thermal` report it per rung from the file alone.
- *Verification on something new: `ledger-mix`.* A new read/write workload (60/20/10/10
  balance_read / entry_append / balance_adjust / entries_count) pushed end to end through the
  Linux profile in one low-rate smoke (run `20261014T190715Z-fea3b5`, 72 s): provision,
  envelope and knob readback (cpuset 4-5,12-13, cpu.max `200000 100000`, memory.max
  2147483648, pids.max 512, data on `ext2/ext3`), ramp 50→400/s, 543 records in
  `metrics.ndjson`, TUI replay, re-derivation, write-path check (2251 entries and +1127 on
  balances in the engine, exactly as issued) and label-scoped teardown (0 left). Two things
  it found: (1) the driver's schedule-lag gate fired at 200/s and 400/s — p99 lag 101-106 ms
  at 400/s with worker CPU at 33% and engine-side (inner) p99 under 3 ms — so those rungs are
  `INCONCLUSIVE_DRIVER_BOUND`, and why is UNVERIFIED (candidates: sampler subprocesses on the
  driver's two CPUs, which are one physical core; `powersave` wake-up latency); (2) the file
  re-derived 13/s for a 52/s step, because `summarise_cells` added every op's window width
  to the writer's span. Fixed and re-derived from the same file: 52 / 98 / 201 / 399 per
  second, max sustainable 100/s, knee 400/s, no collapse — identical to the run.

**NOT RUN 2026-10-14** — each waits on a window the user approves on the shared host, and
each is ready to run as written. Before each: record `phase-3/scripts/quiet_check.sh`
output from the registry topic, and stop if a co-tenant shows distress.

```bash
export DSEL_PROFILE=linux-shared-8c16t
# S1 interference sweep inside dsel's cores, 4-5,12-13 against 6-7,14-15, both directions.
# ~8 min (2 x 6 blocks x 4 levels x ~4.5 s). Uses cores 4-7,12-15 only.
uv run dsel env --interference --out runs/env-interference.json
# Integration suite. Several minutes, plus first-time pulls (prom/prometheus, grafana,
# eclipse-temurin) and two `docker build`s, which BuildKit does not confine to a cpuset.
uv run pytest tests/integration -q -rA
# S16(b): the >= 1 h soak (65 min), engine on 4-5,12-13, this process on 6,14.
uv run python scripts/soak_backend_growth.py --minutes 65 --connections 24 --out runs
DSEL_SOAK_METRICS=runs/<run-id>/metrics.ndjson uv run pytest \
    tests/integration/test_backend_growth_soak.py -q -s
python scripts/analyse_backend_growth.py runs/<run-id>/metrics.ndjson --table
# S16(a): connection cliff, rung order randomised per repeat, thermal trace recorded.
# 6 rungs x 3 repeats x 10 s plus provisioning, ~5 min; saturates one engine core by design.
DSEL_RUNS_OUT=runs uv run pytest tests/integration/test_conn_cliff.py -q -s
python scripts/rederive_landmarks.py runs/<run-id>/metrics.ndjson --axis connections --table --thermal
# ledger-mix again, with the samplers pinned off the driver tier, to test the lag hypothesis.
uv run python scripts/ledger_mix_smoke.py --out runs
```

S16(a) and S16(b) therefore remain **not accepted**.

**S19 Joins.** Plausibility pre-flight (`EXPLAIN ANALYZE` assertions, run *before* the
cell starts), plan fingerprinting and flip detection, `work_mem` × nodes × connections
projection asserted against `memory.max`, temp spill from `pg_stat_database`.
`auto_explain` preloaded at provision but held at `log_min_duration=-1` during measure;
plans captured in a separate pass so the instrument does not confound the measurement.
*Accept:* a query that would be optimised away (the ClickHouse `numbers_mt` shape) is
rejected by plausibility pre-flight and the cell never starts; a `work_mem` × nodes ×
connections projection exceeding `memory.max` is refused before provisioning; a plan flip
induced by lowering `work_mem` is detected and recorded with both fingerprints.

### Widening — W1–W4
Valkey, ClickHouse, OpenSearch, MongoDB. Each needs a harness adapter **and** an app-tier
data-access layer. MongoDB 8 exercises `cannot run here` as a first-class outcome.
*Accept, per engine:* the contract test proves the adapter satisfies the Protocol; against
a live container the health gate passes, every knob reads back equal to the envelope, and
the authoritative version field is the correct one (`valkey_version`, not `redis_version`).
*Accept, W4 specifically:* MongoDB 8 returns a `cannot_run_here` **result** carrying the
SERVER-121912 reason — not an exception, not a crash — and the run continues with the
candidate excluded rather than aborting.

### Closing — G1–G3
Gate (capability tables per engine+version, SPDX per digest, environment feasibility),
scoring (reference-anchored, vetoes, sensitivity — `exp09-scoring.py` becomes the
regression fixture), audit bundle + third-party verify.
*Accept G1:* tightening `licence_policy` to `osi_approved_only` excludes MongoDB before
any container starts (assert zero `docker run` calls); ClickHouse fails UC-1's
`multi_document` transaction requirement.
*Accept G2:* the ranking recomputes from `results` + `scoring` with no re-run and matches
`exp09-scoring.py`'s fixture output; perturbing one weight visibly changes the ranking; a
repo-wide grep proves min-max normalisation exists nowhere in `src/`; an
`INCONCLUSIVE_DRIVER_BOUND` candidate is excluded from scoring rather than scored low.
*Accept G3:* `bundle_root` verifies; the dataset regenerates byte-identically from
`seed` + `generator_version`; `dsel verify` refuses to sign a report given
`reportable=false`, and tampering with one metric value changes the root and is detected.

---

## Validity gates after this plan

findings.md §7.5 has six. This adds six and splits one.

| Gate | Limit | Verdict | New |
|---|---|---|---|
| `driver_cpu_pct` | 70, p95 of quota | INVALID | |
| `driver_worker_cpu_pct` | 70, **max over workers** | `INCONCLUSIVE_DRIVER_BOUND` | ★ |
| `schedule_lag_runaway` | lag p99 >20% of mean inter-arrival, or deficit >0 for 10 s | `INCONCLUSIVE_DRIVER_BOUND` | ★ |
| `app_tier_cpu_pct` | 70, p95 of quota | `INVALID(app_tier_saturated)` for DB claims; kept as an app result | ★ |
| `storage_backend` | must be `ext2/ext3` named volume | INVALID | |
| `readback_matches_envelope` | exact | INVALID | |
| `error_rate` | per class, from spec | INVALID | |
| `unknown_error_rate` | 0.1% | INVALID | ★ |
| `steady_state_reached` | within warmup | INVALID | |
| `plausibility` | per `expect` | **cell never starts** | moved to pre-flight |
| `latency_validity` | must be `open_loop_co_corrected` | refused by scorer | ★ |
| `work_mem_projection` | ≤ `memory.max` | **cell never starts** | ★ |
| `cpu_throttling` | `throttled_usec` >5% of window | flag, surface, not INVALID | ★ |

`INCONCLUSIVE_DRIVER_BOUND` is deliberately distinct from `INVALID`. "We could not load
this engine hard enough to find its limit" is a different fact from "this measurement is
broken", and the report must say the first rather than silently penalising the engine.

---

## Files

Maps onto findings.md §10. `=` as specified · `~` extended · `★` new.

```
src/dsel/
├── spec/{models,canonical,loader}.py    =
├── gate/{capabilities,licences,environment}.py   =
├── data/{generator,distributions,hashing}.py     =
├── adapters/base.py        ~ + plausibility_probe, sample_internal(tier),
│                             connection_state, provoke(kind), authoritative_version
├── adapters/postgres.py    ~ reference impl, the slice target
├── adapters/{valkey,mongodb,clickhouse,opensearch}.py   =  (W1–W4)
├── runtime/{docker,envelope,storage,teardown}.py  =
├── runtime/cgroup.py       ★ cpu.stat / cpu.max / memory.* / pids.current readers
├── runtime/events.py       ★ docker events: oom | die | health_status
├── compose/                ★ NEW PACKAGE
│   ├── render.py               Jinja2 → compose.rendered.yaml            (D2)
│   ├── budget.py               cpuset/memory assertion                   (S2)
│   └── templates/, grafana/provisioning/, grafana/dashboards/
├── live/                   ★ NEW PACKAGE
│   ├── schema.py ndjson.py merge.py
│   ├── sampler/{containers,engine_pg,backend_pg,net,pool}.py
│   ├── exporter.py             tail → prometheus_client Collector        (D3)
│   └── tui.py                  dsel watch                                (S8a)
├── driver/{scheduler,histogram,patterns,calibrate}.py  ~
├── driver/worker.py pool.py transport.py ramp.py probe.py workload.py  ★
├── app/                    ★ NEW PACKAGE — the app tier
│   ├── main.py pools.py spans.py metrics.py
│   └── dal/{postgres,valkey,clickhouse,opensearch,mongodb}.py
├── metrics/{container,engine,validity}.py  ~
├── metrics/plausibility.py plans.py       ★
├── phenomena/              ★ NEW PACKAGE — derivation, kept apart from sampling
│   └── {conn_cliff,backend_growth,conn_lifecycle,joins}.py
├── scoring/*.py            =
├── audit/manifest.py       ~ + app_envelope, ab_delta_valid, vcpu_relative_speed,
│                             heterogeneous_cores, obs_component_inventory
└── audit/{environment,bundle,verify}.py   ~
schema/{metrics,environment}.schema.json   ★ committed, CI drift-checked
```

**Two structural rules, enforced in CI:** `live/sampler/*` only writes records and never
derives a phenomenon; `phenomena/*` only reads `metrics.ndjson` and never touches Docker
or the engine. That separation is what makes S15's acceptance criterion achievable.

---

## Risks, in the order they will bite

1. **Cores 0-1 are oversubscribed and the app tier pays.** Mitigation is honesty:
   `ab_delta_valid=false` on `profile=local`, deep observability forbidden in
   `mode=full`, PATH B capped at 60% of the measured app ceiling. Build S2 first so the
   arithmetic is visible on day one instead of discovered at S14.
2. **Heterogeneous cores.** ~~See S1.~~ **Answered 2026-09-02, and the answer was not
   the expected one:** guest vCPUs are indistinguishable from inside the VM, so the
   assumption cannot be examined here at all. What the probe found instead is that the
   slices do not isolate — see *Hardware slices* above, and risk 5.
3. **The GIL silently defeats the driver-CPU gate.** Never ship a single-process driver.
4. **Valkey out-runs the Python driver, permanently.** Settled, not open: GPL is ruled
   out, so there is no admissible open-loop tool that can saturate it here. Report
   `INCONCLUSIVE_DRIVER_BOUND` with the driver-side ceiling recorded — **never as a low
   score.** The scorer must treat this verdict as "not measured", not as a bad result;
   getting that wrong would silently penalise the fastest engine in the set.
5. **Driver and app tier cannot share cores.** Both have a 70%-of-quota gate; sharing
   makes each gate's denominator a function of the other's load and neither means
   anything. The app tier shares 0-1 with observability only because there is nowhere
   else — which is exactly why `ab_delta_valid=false` locally.
   **Measured 2026-09-02 and worse than written:** tiers on *disjoint* cpusets do not
   isolate either, costing 20–30% under full neighbouring load. The gates remain worth
   having as tripwires, but a passing `driver_cpu_pct` no longer means the engine had
   its slice to itself. Treat every local engine number as depressed by the driver.
6. **`.hlog` interop is an unverified single point of failure.** Verify at S10.
7. **Sampling `pg_stat_activity` at 1 Hz becomes the load it measures** at high
   connection counts. Backpressure to 10 s above 256 connections, recorded not silent.
8. **OpenSearch may be a second "cannot run here"** — its `vm.max_map_count` bootstrap
   check is host-global and `vm.*` is not in Docker's `--sysctl` allowlist. Verify the
   linuxkit default at W3. If it also fails, two of five candidates are environmentally
   excluded and the measurable set drops to Postgres, ClickHouse and a driver-bound
   Valkey. Worth knowing before investing in the W3 adapter.
9. **Prometheus series churn**, clock drift across long soaks, and `metrics.ndjson` merge
   determinism — all have specific guards in S6/S8b.
10. **Docker Hub anonymous pull limits**, hit on 2026-09-02 during S1. Digest resolution
   is now local-first, caching the index → platform mapping under the index digest — a
   mapping between two content addresses, so it cannot go stale. S3–S5 still need to pull
   five engine images at least once, so `docker login` before provisioning.

**Build early to de-risk:** S2 budget · S1 vCPU probe · S6 schema · S10 hlog interop ·
S13 app ceiling. Discovered late, these five force rework of everything downstream.

---

## Verification

- **Per-step acceptance criteria** above are mechanically checkable, not prose.
- **Cross-check the driver against `pgbench`** (S12) and `valkey-benchmark` (W1). If the
  first-party driver disagrees beyond the noise floor, the driver is wrong.
- **`.hlog` round-trip** against the Java reference implementation (S10).
- **Merge determinism**: 100 shuffled shard merges, byte-identical output (S6).
- **Independent re-derivation**: a separate script recomputes knee and collapse from
  `metrics.ndjson` alone (S15), and recomputes the ranking from `results` + `scoring`
  without re-running anything (G2, with `exp09-scoring.py` as the fixture).
- **End to end**: `dsel run specs/uc1-orders-inventory.yaml --smoke` provisions a
  digest-pinned Postgres, runs both ramps against both paths, streams live to the TUI and
  Grafana, trips at least one validity gate deliberately, and emits a bundle whose
  `bundle_root` verifies.

- **README honesty check** (S0): the first paragraph states that this harness produces
  mechanisms and scaling curves, not reportable capacity numbers, and that `dsel verify`
  enforces it. If that sentence ever becomes untrue, the build has drifted.
