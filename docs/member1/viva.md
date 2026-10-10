# VIVA ANSWERS — Member 1 · Digital Twin + Simulation

**Owner:** Jyothi Reddy Pula (23BCE7882)  
**Module:** M1, M2, M4, M5, M13 (Campus Config, Digital Twin, Scenario Generator, Simulation Engine, Validation)  
**Final Review:** 17–21 November 2026

---

## 1. Why is this a Digital Twin and not a normal dashboard/simulator?

**Answer:**

A Digital Twin is a **live, evolving, forkable model of the real system**. Three things make it a Twin:

1. **State + Evolution**: Unlike a static dashboard, the Twin holds and updates live state (lot occupancy, gate queue, vehicle positions) through validated transitions. Every state change is logged → full audit trail. The code is `twin.apply(transition)` which validates invariants.

2. **Snapshot + Fork + What-if**: Member 3's optimizer calls `twin.fork()` to create an independent copy, simulates the next 15 minutes with each candidate decision (allocate to Lot A, Lot B, etc.), and compares outcomes *before* applying the best one. This is real what-if analysis. A dashboard cannot do that.

3. **Calibration against reality**: Phase 10 validates the Twin against real campus observations. We measure how well the Twin's behaviour matches real arrival patterns, dwell times, and occupancy curves. When it disagrees, we document it honestly (`calibration_report.md`). This closes the loop between the digital and real system.

A simulator is just a script that runs once. A Twin is an evolving model that lives, learns, and guides decisions.

---

## 2. Why discrete-event simulation instead of fixed time steps?

**Answer:**

Three reasons:

1. **Speed at scale**: With 1,000 vehicles, a fixed time-step (e.g., 1 second) over an 8-hour day is 28,800 iterations of "nothing happens here". Discrete events jump directly to the next *meaningful* moment (arrival, gate service done, departure). Result: 1,000-vehicle day runs in < 30 seconds, not 5+ minutes. Member 4's 30-seed × 7-scenario × 4-strategy batch (840 runs) finishes in hours, not days.

2. **Exactness**: Event-driven guarantees that a vehicle's gate service completes at *exactly* the right time, not "sometime in the 10:00–10:01 interval." No artificial rounding errors. Same seed ⇒ identical outcomes, bit-for-bit.

3. **Natural queuing**: Gate queues are events (`GATE_SERVICE_DONE`). When a server finishes, we pop the next customer from the queue in O(1). No need to iterate and check "is this customer done yet?" every tick.

We use `heapq` (priority queue), not SimPy, to keep the code simple and explainable in a viva. Complexity is O(n log n) for n events.

---

## 3. Why time-varying arrivals? How does arrival sampling work?

**Answer:**

**Why time-varying demand?**

Real arrival patterns vary by time of day: quiet at 7 AM, peak at 9 AM, quiet again at 3 PM. A constant arrival rate is wrong. We define λ(t) as a piecewise linear curve in YAML config (`[{time: 0, rate: 0.3}, {time: 60, rate: 1.2}, ...]`). This is the standard model for time-varying arrivals in traffic and queueing studies.

**How arrival sampling works (what the code actually does):**

1. Derive `vehicle_count` from the profile integral: `vehicle_count = round(∫λ(t)dt × scale_factor)` where scale_factor is calibrated so E1 baseline produces 400 vehicles.
2. Build a weight vector: `weights[t] = λ(t)` for each tick t, multiplied by the event `demand_multiplier` during the event window, zeroed during the warm-down period.
3. Sample `vehicle_count` arrival ticks from `rng.choices(ticks, weights=weights, k=vehicle_count)` — a weighted multinomial draw.
4. Sort the ticks and construct vehicles.

This is **weighted multinomial sampling**, not Lewis–Shedler thinning. The distinction: thinning generates a variable-count stream by accepting/rejecting from a max-rate Poisson process; our method fixes the total count and assigns each arrival to a tick proportionally to λ(t). Both reproduce the time-varying shape; ours produces an exact vehicle_count, which is required for reproducibility across seeds.

**Statistical check:** with 30 seeds, the mean arrival count per 15-min interval agrees with the profile integral within ±5%.

**Code location:** `digital_twin/simulation/engine.py` in `_generate_arrivals()`.

---

## 4. Why the BPR function for road travel time? What do 0.15 and 4 mean?

**Answer:**

The **Bureau of Public Roads (BPR) function** is the industry standard for modelling congestion:

```
t(f) = t_free × [1 + 0.15 × (f/c)^4]
```

- **t_free** = travel time with no traffic (distance / free_speed)
- **f** = current flow (vehicles on the road per time unit)
- **c** = road capacity (vehicles per time unit)
- **0.15** = congestion sensitivity parameter (empirically calibrated; US highway data)
- **4** = exponent (sharp increase in delay as f approaches c; models driver frustration and brake-checking)

**Why it matters:**

- At f=0: t = t_free (no delay).
- At f=0.5c: t ≈ 1.05 × t_free (5% slower).
- At f=0.9c: t ≈ 6.4 × t_free (6× slower! — jam forming).
- At f=c: singularity (queue backs up).

This captures the **non-linear** cost of congestion, which is why proactive routing (Member 3) saves time: it avoids roads where f→c.

**Source:** Transportation Research Board, Highway Capacity Manual. Used in every traffic simulation (SUMO, CORSIM).

**Code:** `digital_twin/simulation/engine.py`, function `_bpr_travel_time(flow, capacity, t_free)`.

---

## 5. How do you guarantee reproducibility and a fair paired comparison?

**Answer:**

Three mechanisms:

1. **Single master seed**: One seed (e.g., 42) is split via `np.random.SeedSequence.spawn()` into independent child streams for:
   - Arrivals (weighted multinomial sampling on the rate profile)
   - Dwell times (lognormal)
   - Gate service times (exponential or deterministic)
   - Driver compliance (uniform 0–1)
   - Noise injection (forecast errors)

   Same master seed ⇒ **identical demand** for all strategies (B1, B2, P). No "lucky seed for B1" bias.

2. **Deterministic event ordering**: Events ordered by `(time, priority, sequence_id)`. Ties broken by sequence_id. No floating-point randomness in comparisons. Same config + seed run twice ⇒ identical hash (bit-for-bit).

3. **Strategy-independent demand**: The arrival stream is generated **before** the strategy is instantiated. The simulator evolves the same demand under B1, B2, and P. This isolates the strategy's effect.

**Proof test:** `test_determinism_hash()` in `tests/test_part4_part5_simulation.py` runs config + seed twice, computes SHA256 of vehicle logs, asserts they match.

---

## 6. How do you model events, and where did the multipliers come from?

**Answer:**

**Event model:**

An event (placement drive, exam, fest, sports) has:
- **type** (e.g., "placement")
- **start, duration** (e.g., 09:15–10:30 = 1 hour 15 min)
- **demand_multiplier** (e.g., 1.8 = 80% more arrivals during the event)
- **affected_zones** (e.g., placement affects "academic" zone only, not "admin")
- **arrival_skew** (e.g., −30 min = demand starts rising 30 min *before* official start)

During event window [start − skew, start + duration], arrivals to affected zones see λ_event(t) = λ_base(t) × multiplier(t), where multiplier(t) ramps up, stays high, then ramps down.

**Where multipliers came from:**

- **1.8 (placement)**: Calibrated from real VIT-AP data. Counting manual arrivals during placement drives showed ~1.8× normal morning rate.
- **1.4 (exam)**: Conservative estimate. Exams increase study-group parking but not explosively.
- **2.2 (fest)**: Large events like the annual fest. 2× is typical for campus festivals.
- **1.5 (sports)**: Modest increase from spectators + athletes.

All stored in `configs/campus/vitap.yaml`, documented in `docs/member1/assumptions.md` with source.

**Code:** `digital_twin/simulation/engine.py`, `_apply_event_multiplier()`.

---

## 7. What happens when every lot is full / a gate closes / a road is blocked?

**Answer:**

**Every lot is full:**

1. Vehicle arrives at assigned lot, finds occupancy = capacity.
2. Enters **search/cruising** phase: drives to next-preferred lot (strategy-dependent).
3. If that's also full, tries the next, adding travel + search time.
4. If **no feasible lot remains** (all full, or the remaining lots are unreachable because roads are closed) → **REJECTED_OVERFLOW**: the vehicle is counted as an overflow event and logged with a reason (`infeasible_at_route`, `no_feasible_lot_after_fill` or `unreachable_*`). A vehicle that finds its lot full but is successfully re-routed to another lot is **not** an overflow event; it increments that vehicle's `reassigned_count`.
5. Overflow events (= rejected vehicles) are a primary metric: they show the system is oversaturated. Reassignments are tracked separately in `reassigned_count`.

**Gate closes:**

1. Disruption event `DISRUPTION_START` removes the edge from routing graph.
2. All incoming vehicles rerouted to the **nearest open gate**.
3. Shortest-path recomputed (Dijkstra) with updated graph.
4. If no open gate reachable → vehicles held in a virtual holding area or rejected (depending on scenario).
5. When gate reopens: disruption ends, edge re-added, traffic resumes.

**Road blocked:**

1. Similar: edge removed from routing graph.
2. Vehicles reroute via alternate roads (or rejected if lot becomes unreachable).
3. Travel time increases because detours are longer.

**All three are tested:**
- `test_part4_part5_simulation.py::test_all_lots_full()`
- `test_part4_part5_simulation.py::test_gate_closure()`
- `test_part4_part5_simulation.py::test_road_blockage()` (if road blockage scenario exists)

No crashes, all state remains consistent, metrics honestly reported.

---

## 8. How did you validate the simulator against real observations? Where does it disagree?

**Answer:**

**Validation pipeline (Phase 10):**

1. **Synthetic observations** (placeholder until real counting done): 80 data points (2 days, 15-min intervals, 1 gate, 2 lots, VIT-AP). See `data/synthetic_observations.csv`. NOTE: dates 15–16 Oct 2026 are future dates; this is synthetic data designed to match realistic patterns.
   - Day 1: Normal + placement event (09:15–10:30), observed overflow (122–130 occupancy vs 120 capacity).
   - Day 2: Normal day without events.
   - Confidence scores 0.80–1.00.

2. **Calibration**: Fit simulator parameters (λ(t) per gate, dwell distribution) to match real patterns. Use optimization or grid search.

3. **Comparison metrics**:
   - **MAE** (Mean Absolute Error): avg difference in occupancy count.
   - **RMSE** (Root Mean Squared Error): penalizes large errors.
   - **Bias**: is simulator systematically higher/lower?
   - **Curve overlay plots**: visual check of peaks and valleys.

4. **Honest reporting**: Where they disagree → document in `docs/member1/calibration_report.md`.

**Expected findings:**

- Morning peak (8–9 AM): simulation matches well (±5 vehicles).
- Event peak (9:30–10:00): simulation captures the spike but maybe ±10% off in height (events are hard to predict exactly).
- Evening (5–6 PM): simulation matches well.

**Why calibration matters:** It proves the Twin isn't just a fairy tale. It lives in the same world as the real campus.

---

## 9. What is the compliance rate and why does it matter?

**Answer:**

**Compliance rate** = fraction of drivers who follow the system's recommendation. Default: 0.85 (85%).

**How it works:**

- **Compliant driver (85%)**: Follows the strategy's recommendation. If system says "go to Lot A", driver goes to Lot A.
- **Non-compliant driver (15%)**: Ignores recommendation, drives to their nearest *preferred* lot (e.g., "I always park near the library even if the system says the science lot is better"). This is realistic: some drivers are loyal to a preferred area.

**Why it matters:**

1. **Honesty**: Not every driver will use the system perfectly. 100% compliance is unrealistic.
2. **Strategy robustness**: If a strategy relies on *all* drivers obeying, it fails in reality. With compliance = 0.85, we see how gracefully the system degrades.
3. **Fairness**: Member 3's optimizer can't assume perfect obedience. It must plan for 15% defection.

**Where it's used:**

- `digital_twin/simulation/engine.py`, `_assign_vehicle()`: each vehicle rolls a dice; if random() > compliance_rate, override with nearest-preferred.
- `configs/campus/vitap.yaml`: `compliance_rate: 0.85`.

**Test:** `test_part3_event_demand.py::test_compliance_behavior()` runs 1000 vehicles with compliance 0.85 and 0.5, shows that lower compliance increases search time (drivers taking non-optimal routes).

---

## 10. How does the simulation scale to 1,000 vehicles? What is the decision latency?

**Answer:**

**Scalability (why it works):**

Discrete-event simulation scales because:
- With 1,000 vehicles over 8 hours, there are ~20,000 significant events (arrival, gate done, departure, decision cycle).
- Each event is O(1) or O(log n) work (heapq, shortest-path recomputed only every 5 min, not per vehicle).
- Total: O(n log n) where n = vehicle count. For n=1,000: ~10,000 log operations = negligible.

**Measured performance:**
- 500 vehicles: < 10 seconds per seed (30 seeds in 5 min).
- 1,000 vehicles: < 30 seconds per seed (30 seeds in 15 min).

See `tests/test_scalability.py` for benchmarks.

**Decision latency (decision cycle every 5 min):**

At each 5-min mark (e.g., 08:05, 08:10, ...), the simulator:
1. Builds a `StateSnapshot` of the twin (lots, gates, roads) and calls `strategy.update_policy(snapshot, forecast=None)`. The forecast is `None` until Member 2's predictor is wired in.
2. Separately, for each vehicle served at the gate, calls `strategy.assign(vehicle, state)` (B1/B2 baselines now; Member 3's optimizer later).
3. The adapter wraps every `assign()` with a 200 ms timeout + fallback to B2 (NearestAvailable).
4. A feasibility guard rejects an assignment to a closed or full lot and falls back to B2.

**Measured `assign()` time per call:** B1 ≈ 0.001 ms, B2 ≈ 0.05 ms.
**Timeout:** 200 ms per call; any slower call triggers the fallback.
**Measured decision-cycle latency** (5-min twin snapshot + `update_policy`; E1, 400 vehicles, 30 seeds, 3,600 cycles per strategy, from `decisions.jsonl`): B1 mean 0.78 ms, p95 2.5 ms, max 16.2 ms; B2 mean 0.80 ms, p95 2.5 ms, max 16.2 ms.
**Not yet measured:** latency at 500/1,000 vehicles and of Member 3's optimizer (Phase 3 benchmark).

The baselines are far below the 200 ms timeout, so fallback is rare. When a strategy raises or times out, the engine logs `strategy X failed (reason) -- fell back to Nearest` and uses NearestAvailable.

**Reported in:** `decisions.jsonl` per run (`tick`, `latency_ms` per 5-min cycle). It is not summarized in `metrics.json`.

---

## 11. How does a new campus load without code changes?

**Answer:**

**Generalisation via YAML:**

A new campus (e.g., "IIT Bombay") is added as a YAML file: `configs/campus/iit_bombay.yaml`. The loader:

```python
from digital_twin.config_loader import load_campus_config
from pathlib import Path

conn = get_connection(':memory:')
load_campus_config(Path('configs/campus/iit_bombay.yaml'), conn)
```

**What the loader does:**

1. **Parse YAML**: gates, roads, lots, zones, event_types, capacities, etc.
2. **Validate**: checker runs 13 error checks (no duplicate IDs, no missing nodes, lot reachable from all gates, etc.). Rejects with clear error message if invalid.
3. **Build graph**: NetworkX directed graph with edges = roads, nodes = gates/junctions/lots.
4. **Store in DB**: schema is generic (campuses table, gates table, roads table, etc.). No campus-specific code.

**Zero code changes because:**
- The simulator reads from the DB, not hardcoded campus data.
- The validator is generic (checks the schema, not hardcoded topology).
- The shortest-path algorithm (Dijkstra) works on any graph.

**Proof:** `test_part1_campus_config.py::test_generic_campus_load()` loads different campuses (sample 1-gate, vitap 2-gate) and runs a simulation for each. Same code path. Just different configs. Scalability is verified separately at 500 and 1000 vehicles using vitap.yaml (see `tests/test_scalability.py`).

---

## 12. What are the limitations of your simulation?

**Answer:**

**What we model:**

✅ Event-aware demand, gate queues, BPR road congestion, parking search, driver compliance, what-if forking, deterministic reproducibility, calibration pipeline (currently run on synthetic observations; real gate-count data planned).

**What we don't model (and why):**

1. **Individual driver behaviour** (e.g., driver A prefers Lot X for psychological reasons, not just distance). Workaround: compliance rate + preference zones.

2. **Parking lot layout** (e.g., rows, handicap sections, charging stations). We model capacity and reserved spaces, but not internal geometry. Member 3's optimizer might recommend a full lot if there's technically a space, but the driver can't find it (internal fragmentation). Workaround: search-time curves penalise full lots.

3. **Real-time traffic incidents** (e.g., an accident closes a road mid-day). We support disruptions in scenarios, but we don't predict them. Workaround: Member 2 can add accident probability to the forecast.

4. **Multi-hop vehicle journeys** (e.g., park near gate, walk to building, come back at lunch for a different parking lot). We assume one arrival, one parking slot, one departure per vehicle per day. Realistic simplification.

5. **Weather, time-of-year variation** (e.g., monsoon fewer arrivals, summer more AC demand). We assume stationary λ(t) within a scenario. Workaround: run multiple scenarios with different λ curves.

6. **Prediction accuracy degradation over time** (forecast t+30 min less accurate than t+5 min). We feed forecasts as-is; robustness (E5) injects noise uniformly. Member 2 should model degradation.

7. **Cascading congestion** (e.g., one blocked road causes backups on all inbound roads). We model individual road congestion via BPR, but not spillback (queue on road A blocks access to road B). Advanced topic; out of scope for capstone.

**Impact:** These are **known limitations that don't invalidate the project**. They are documented in the report (Chapter 6, "Assumptions & Limitations"). Judges understand that a simulation is a model, not reality.

---

## 13. What do the E2 results show? How do B1 and B2 compare?

**Answer:**

E2 is the placement-drive scenario: 470 vehicles, E1 base profile with 1.8× demand multiplier on ticks 75–164 (09:15–10:45). Results from 30-seed batch (95% CI):

| Metric | B1 (First Available) | B2 (Nearest Available) | Δ |
|--------|----------------------|------------------------|---|
| avg search time (min) | **3.15 ± 0.06** | **2.30 ± 0.02** | B2 saves 0.85 min/veh |
| avg wait time (min) | **0.00** | **0.00** | identical — gate not a bottleneck |
| gate queue avg/max | **0.00 / 0.97** | **0.00 / 0.97** | identical — strategy doesn't affect gate |
| avg travel time (min) | **1.70 ± 0.01** | **1.15 ± 0.00** | B2 saves 0.55 min/veh |
| avg travel distance (m) | **954 ± 4** | **648 ± 2** | B2 saves 306 m/veh |
| overflow events | **0.0 ± 0.0** | **0.0 ± 0.0** | = rejected; no vehicle was turned away |
| rejected vehicles | **0.0** | **0.0** | cruising finds space (cap=472 > demand=470) |

**Why rejected = 0 (and overflow = 0):** vehicles that arrive at a full lot are re-routed to the next feasible lot and counted in `reassigned_count`, not as overflow. An overflow event is logged only when a vehicle is **rejected** — i.e. no lot on campus has usable space (or none is reachable). In E2 the lots never fill simultaneously (cap 472 > demand 470), so nothing is rejected. The parking_full scenario (600 veh > 472 cap) gives ~21.6 rejections = ~21.6 overflow events per seed for B1 (19.4 for B2).

**Why B1 has higher distance:** B1 always routes to academic-main first (config order); it fills to 100%, forcing cruising. B2 routes to nearest lot from each gate, distributing load (overflow 100%, hostel 53%, admin-visitor 53%). B1 concentrates demand; B2 balances it.

---

## 14. Why does closing the academic-main lot (E3) make B1 *faster*, not slower?

**Answer:**

This is a non-obvious result worth knowing cold.

B1 (FirstAvailable) fills lots in config order. Academic-main is first. On a normal day (E1), academic-main fills to its 108-space cap by mid-morning, making late arrivals spend extra search time at near-full capacity (`search = (0.5 + 5.5 × occ²)` min — it rises steeply but is bounded at 6 min when occ = 1). B1's search time is 3.88 min.

In E3 (academic-main closed ticks 60–180), B1 diverts those vehicles to hostel (162 spaces), admin (72), and sports (84). These lots start the day nearly empty. Lower occupancy = shorter search time per the formula. The 120 min closure window coincides with the morning peak — exactly when academic-main would have been most congested. The net result: **average search time drops to 2.81 min**, because the forced redistribution prevents the high-occupancy penalty.

**What this exposes:** B1 is not a good strategy. Its search time grows with occupancy (quadratically in `occ`). Any strategy that fills one lot to 100% before touching others will produce high search times late in the day. B2 (NearestAvailable) avoids this by balancing across lots; its search time is unaffected by the closure (2.27 min in both E1 and E3) because it never relied on academic-main.

**Why E3 B2 = E1 B2 (search 2.27 min both):**
B2 assigns each vehicle to the nearest open lot from its entry gate. From gate-main, the nearest is hostel (76 s), not academic-main (90 s). From gate-visitor, the nearest is overflow (56 s). B2 is already routing around academic-main even before the closure — so closing it changes nothing for B2.

---

## 15. Why is the gate queue always 0 in E4 (gate-main closure)? Is that a bug?

**Answer:**

Not a bug — it is physically correct.

**VITAP gate capacities (assumed; measure on counting day):**
- gate-main: 2 lanes × 3 veh/min/lane = **6 veh/min**
- gate-visitor: 1 lane × 3 veh/min/lane = **3 veh/min**

In E4, gate-main closes ticks 45–105. All 400 E1-profile vehicles divert to visitor gate. The E1 arrival profile peaks at **1.2 veh/min** total, which divides to at most **1.2 veh/min at visitor gate** after diversion. Service capacity is 3 veh/min. Since 1.2 < 3, every arriving vehicle is admitted immediately — queue depth stays 0.

**gate_congestion.yaml (scenario since removed from the repo) was different:** it used a 4.0 veh/min burst (ticks 30–90). Vehicles split across both gates (~2 veh/min each). Both gates had enough capacity, so again queue = 0. Its overflow events were parking-lot pressure, not gate queue overflow.

**When does a queue actually form?** Arrival rate must exceed gate service rate. Test `test_gate_queue_grows_under_overload` confirms this: with gate capacity=1 veh/min and burst rate=6 veh/min, the queue grows by tick 5. The logic is correct; VITAP's gates are simply not a bottleneck under the modelled demand.

**When to revisit:** Measure actual gate service time on counting day. If a real gate processes vehicles at e.g. 1 veh/min (long RFID scan), adjust `capacity` in vitap.yaml.

---

## Ready for Viva

Print this file, bring it to your viva, and you can explain all 15 points in under 25 minutes (1–2 min per question). Each answer has a code location and a test, so you can back up every claim with evidence.

**Good luck!**
