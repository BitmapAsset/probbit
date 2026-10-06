# probbit benchmarks

Every section names the command that produced it (a `bench/` script or `cargo run --example`, from the repo root; `PROBBIT=path/to/probbit` overrides the binary);
numbers carried over from an earlier build are marked as such and were not re-run.
Machine unless stated: Apple M4 (4 performance + 6 efficiency cores), 16 GB, macOS, rustc 1.98.1, `cargo build --release`
(fat LTO, **portable**: no `target-cpu` pin). Timing runs were made with no other benchmark running (except §5.4, contention on
purpose), but not always on an idle machine: during some runs fseventsd used ~190% CPU, and other runs logged load averages of 3-17 from other
processes; sections give the load where it was recorded.
Format: median [interquartile range] over N runs, unless a cell says p50/p95 or min-max. Each table ends with what it lets us claim
and what it does not.
Rows and sentences tagged R19.n were measured in 0.2.0 development round n (2026-09-30 to 2026-10-01); `P1.x`-style ids
name items of that round's work plan; short hex ids name development builds. R19.10 is the final 0.2.0 build.

**Vocabulary (0.2.0).** The 0.1.0 verdict `certified` is retired; it is now `diagnostics_passed` (same test). Where a section
below says "certified", "certificate" or "false certificate", read: the whole answer passed the gate's diagnostics, and a false
one is a whole answer that passed with a released item outside tolerance. Those measurements were taken under the old name and
were not re-run for the rename. **Released** (every section): an item's odds passed the gate, i.e. a 3σ Monte-Carlo error bound
of at most 0.05 total variation from multi-chain batch means, plus split R-hat, batch-size stability and frozen-resource checks,
tuned against exact oracles. It is a diagnostic, not a proof, and it has counterexamples: see [Known failure modes](#known-failure-modes). **Oracles**: router family A (§2.1) is checked against a transfer-matrix DP
(`probbit-decide/src/oracle.rs`), separate code from the sampler and the exact tiers. Every other oracle is probbit's own exact tier
(`probbit_ir::exact` enumeration for max-cut, colouring and scheduling; the frontier DP for router family B), not an independent
solver. Cross-checks: that enumeration equals an independent bitmask DFS on 20 sudokus (counts and per-cell odds, §4) and the
frontier DP equals enumeration to 1e-9 (earlier build); a truncation bug found in `exact()` was fixed, and every oracle total re-ran
unchanged afterwards.

## §1 Kernel and sampler updates/s (portable build, `bench/portable_vs_native.py`, N = 5)
The p-bit literature counts "flips/s" (p-bit updates per second). Ours, from the fastest structured kernel down to general programs:

| what runs | threads | site updates/s |
|---|---|---|
| `probbit-core` multispin, 2D ±J lattice L = 512, 64 replicas bit-sliced per word (fast path) | 4 | 1.48e11 [1.43e11-1.48e11] |
| same | 10 | 1.47e11 [1.44e11-1.48e11] |
| same, one thread | 1 | 3.71e10 [3.67e10-3.72e10] |
| `probbit-core` heat-bath, f32 lookup table, one lattice (fast path) | 1 | 9.13e8 [9.01e8-9.15e8] |
| `probbit-ir` general sampler, 400-spin ring program (`probbit stats`) | 1 | 2.28e7 [2.23e7-2.31e7] |
| same | 4 | 7.68e7 [7.63e7-7.74e7] |
| router sampler, 300-task demo (`probbit decide`, 2,000 sweeps) | 4 | 5.31e7 [5.18e7-5.40e7] (0.1.x moves; R19.2 same session, N = 5, load ~8: `--collective off` 5.36e7 [5.22e7-5.74e7], `on` (the 0.2.0 default) 5.11e7 [5.00e7-5.40e7], -4.7%) |

Claim: the substrate's structured kernels reach ~1.5e11 replica-site updates/s on a Mac mini; a sparse general program (the
400-spin ring) runs at ~2.3e7 updates/s per thread, denser ones slower (router ~1.3e7 per thread, the G1-like max-cut ~3e6, §3).
The first four rows are standalone kernels (`probbit-core/examples/kernels`); `probbit decide` / `probbit run` use only probbit-core's RNG. Not claimed: that a general program gets kernel speed (the general sampler is ~40x slower per
thread than the one-lattice heat-bath kernel and ~1,600x slower than the multispin figure); the multispin rate counts 64
packed replicas per word that share one random draw per site (so they are not independent samples), and one problem does not get 64x faster; FPGA/ASIC p-bit numbers *(lit.)*, not quoted here, are not
comparable to these without the same problem and metric. The fast multispin path stops scaling past 4 threads on the M4
(1.48e11 at 4 and 10 threads; the older multispin path goes 9.37e10 -> 1.27e11), likely memory-bound (inferred).

## §2 Router: probbit vs greedy+repair vs exact vs ILP (`router_bench.rs`, `bench/router_ilp.py`, `bench/router_latency.py`)
The router assigns tasks to workers under hard rules (allowed workers, quotas) with soft scores and a same-workflow affinity.
Methods: **exact** = the frontier tier `probbit decide` runs first; **greedy** = best-score-first matching with augmenting-path repair
(`feasible_init`); **greedy+polish** = greedy, then the same anneal probbit uses, for the same wall time probbit spends; **probbit** = what
`probbit decide --mode sample` runs (4 chains for 200 ms, the certification gate, 50 ms polish of the best plan). A task is
*released* when the gate certifies its odds; it is *wrong* if its odds are more than 0.05 TV from the exact odds.

### 2.1 Against exact odds and the exact optimum (`cargo run --release -p probbit-decide --example router_bench`, 36 s)
A: 16 exact-oracle queues (chains of blocks, 8 settings incl. saturated and strong affinity, T = 200 x 12 and T = 80 x 4, 2,720
tasks; exact odds and optimum by transfer-matrix DP).

| method | ms p50 / p95 | plan gap to the optimum, nats p50 (max) | tasks whose most likely worker matches the exact odds | tasks released (wrong) |
|---|---|---|---|---|
| exact frontier tier | 3.17 / 5.65 | 0 (0) | 100% (odds error 3.7e-15) | all, exact |
| greedy | 0.025 / 0.042 | 176.5 (1,060) | 51.9% (a plan, no odds) | none |
| greedy+polish, equal time | 259.0 / 267.4 | 0.151 (26.3) | 79.2% (a plan, no odds) | none |
| probbit (0.1.0 gate) | 258.9 / 267.3 | 0.011 (3.93) | 96.6% | 1,580 of 2,720 (0 wrong); 7/16 queues certified whole |
| probbit (current gate/3; re-run R19.10, HEAD 3312bda, load ~3.5) | 262.9 / 281.0 | 0.000 (4.03) | 96.6% | 1,395 of 2,720 (0 wrong); 6/16 queues passed whole |

A replication on a later build gave the same exact, greedy and probbit rows (probbit released 1,590, 0 wrong);
greedy+polish, being wall-clock bound, came out at 0.081 nats median instead of 0.151 (0.117 in the R19.10 re-run). The ms
columns are p50 / p95 over the 16 queues (one run each), not repeats. The current-gate row is lower in coverage, not in
correctness: gate/3's never-moved and indicator rules (R19.3) refuse more (Known failure modes), and 0 released task was wrong.

B: `probbit demo --tasks N` queues, N = 12 / 18 / 24 / 30, 4 seeds each (336 tasks; exact odds from the frontier tier with a raised cap).
The exact tier answers in 0.17 / 1.47 / 5.83 ms at N = 12 / 18 / 24 and declines N = 30 at its default 4,096-state cap. Greedy is
2.95 / 6.68 / 8.14 / 9.14 nats (median) below the optimum. Greedy+polish and probbit both reach the optimum on 16/16 queues. probbit
certified 16/16 and released 336/336 tasks, 0 wrong; its odds name the exact most likely worker for 98.6-100% of tasks, while a
single optimal plan agrees on 71-78%. Claim: on these queues with an oracle, probbit's released odds were not once wrong (1,916 released
tasks on the 0.1.0 gate; 1,731 = 1,395 A + 336 B on the current gate, R19.10 re-run, B unchanged at 16/16 and 336/336; 0 wrong both) and its plan was at least as close to the optimum as greedy+polish at equal time (0.011 vs 0.151 nats median on A).
Not claimed: coverage everywhere (A: 58% of tasks released on the 0.1.0 gate, 51% on gate/3; on gate/3, 9 queues released
nothing, 4 of them inside tolerance (max TV 0.012-0.042: the two A1 saturated queues, A4 seed 7012 and A6 seed 7006). On 0.1.0: nothing was released on the 4 saturated queues, whose odds were within
0.011-0.087 TV, i.e. two of them were refused needlessly, nor on the 4 strong-affinity T = 80 queues, off by 0.04-0.44, one of them
(0.041; 0.042 in a later re-run) also needlessly: 3 of the 8 zero-release queues were inside tolerance) or that the
plan is optimal (up to 3.93 nats short on A).

### 2.2 The single best plan vs an ILP solver (`python3 bench/router_ilp.py`, needs numpy + scipy >= 1.9, N = 5)
Exact MAP as an integer program (HiGHS through scipy 1.17.1 `milp`; a benchmark dependency, not a probbit one), same queues as
`probbit demo` (generator signatures checked identical). HiGHS proves optimality (status 0) on every queue.

| queue | ILP: optimum, ms median [min-max] | `probbit decide` defaults: plan log w, gap | probbit ms | greedy / greedy+polish gap (2.1 harness) |
|---|---|---|---|---|
| 30 tasks | 69.88, 7.5 [7.0-11.9] | 69.88 certified, 0 | 287.0 | - |
| 300, seed 7 | 708.31, 52.9 [52.6-54.7] | 707.30 certified, 1.01 | 299.6 | 109.79 / 0.98 |
| 300, seed 8 | 690.09, 347.6 [345.4-350.1] | 689.20 certified, 0.89 | 298.6 | 99.87 / 0.37 |
| 300, seed 9 | 677.31, 111.7 [111.2-114.3] | 675.59 certified, 1.72 | 298.6 | 104.84 / 2.10 |
| 300, seed 10 | 694.59, 52.4 [52.4-53.7] | 692.71 certified, 1.88 | 299.2 | 107.58 / 1.48 |
| 300 `--hard` | 1012.21, 212.3 [211.6-214.4] | 1002.50 partial, 9.71 | 344.8 | - |

Claim: none for probbit here: for ONE best plan an off-the-shelf ILP solver is optimal, proves it, and was faster than probbit's
default path on 5 of 6 queues. probbit's plan is 0.9-1.9 nats short at 300 tasks (9.7 on `--hard`; a replication on a later
build gave 0.8-2.0 and 9.3 with ILP times within 4%; a third run on a still later build gave 0.45-1.91
and 9.71 with ILP times within 3%: the gap moves run to run with the wall-clock polish, 0.45-2.0 nats over three runs), and greedy+polish at equal time
was closer to the optimum than probbit's sampler+polish on all 8 seed-runs at 300 tasks (0.37-2.10 vs 0.42-2.75 nats; the `router_bench` run and its
replication). What the ILP does not return: per-task odds, a certificate that those odds are right, a refusal when they
are not, or what-if odds under clamps; that is what the probbit column is for. Not measured: whether those odds are worth more to a
user than LP relaxation values or a plain MCMC run would be.

### 2.3 End-to-end latency at defaults (`bench/router_latency.py`, N = 20; re-run)
Wall = the whole subprocess (start, parse, decide, print); probbit ms = the time probbit reports.

| queue | verdicts | probbit ms p50 / p95 | wall ms p50 / p95 |
|---|---|---|---|
| 12 tasks | exact (enumeration) x20 | 7.1 / 7.5 | 9.0 / 9.6 |
| 24 tasks | exact (frontier) x20 | 25.1 / 25.5 | 27.2 / 27.9 |
| 30 tasks | certified x20 | 287.1 / 288.6 | 290.6 / 291.9 |
| 300 tasks | certified x20 | 299.0 / 301.1 | 303.1 / 305.5 |
| 300 tasks `--hard` | partial x20 | 344.2 / 345.9 | 348.1 / 350.2 |

The frontier cap is a knob (`--frontier-states`; `bench/frontier_cap.py`, N = 5, normal and `--hard` queues): at 16,384 states
instead of the default 4,096, the 30- and 36-task queues are answered exactly in 40.8-104.0 ms instead of 277.8-304.0 ms sampled;
queues it still declines pay +22.5 to +33.2 ms at 42-60 tasks and +3.6 to +5.9 ms at 90-300 tasks. At 65,536 (N = 5 probe) the
48-task queue is exact in 416 ms, slower than sampling it, and 300 tasks pay +114 ms. The default stays 4,096: which cap is better
depends on your queue sizes (unmeasured on real traffic). Load average was ~9.7 during the cap run (another process was busy). Claim: small queues get exact answers in milliseconds, and the sampled path is budget-bound at ~0.3 s with a tight p95.
Not claimed: that the sampled path is fast; it spends its whole budget by design.

Re-run on the final 0.2.0 build (R19.10, HEAD 4a97099, same script, N = 20, load 3.6-4.3):
probbit ms p50 / p95 8.0 / 8.4 (12 tasks, exact x20), 27.3 / 28.1 (24, exact x20), 294.1 / 295.1 (30, `diagnostics_passed` x20),
309.4 / 310.7 (300, `diagnostics_passed` x20), 354.0 / 354.6 (300 `--hard`: partial x19, refused x1); wall 10.1 / 29.6 / 298.0 /
314.3 / 358.7 ms p50. Same verdicts except one `--hard` refusal (wall-clock budget at the release threshold), and 2-12% slower than
the table, which was measured on an earlier build with no load recorded. An old-vs-new A/B (§6, "Tiny exact inputs since R19.9")
attributes the 12- and 24-task exact rows to R19.9's enumeration change (+5-12%); the sampled rows are the same in the binaries
before and after R19.9 (N = 7), so their +2-3.5% against the table is an earlier build or load, not separated.
## §3 Max-cut: odds vs brute force, and cut value vs simulated annealing (re-runs of `maxcut_oracle.rs` and `maxcut_gset.rs`)
Odds vs brute force (`cargo run --release -p probbit-ir --example maxcut_oracle`, 2.3 s): random 3-regular graphs n = 12 / 16,
coupling 0.3 / 0.7 / 1.5 per cut edge, fields 0 or uniform ±0.2, 4 chains x 500 or 5,000 sweeps, 6 instances per setting =
144 runs, each checked against the exact marginals from enumerating all 2^n states.

| sweeps per chain | runs | passed (`diagnostics_passed`) | false passes | released spins | wrong released spins | 0.1.0 gate: passed / released / wrong |
|---|---|---|---|---|---|---|
| 500 | 72 | 0 | 0 | 0 | 0 | 11 / 417 / 0 |
| 5,000 | 72 | 61 | 0 | 929 | 0 | 61 / 929 / 0 |

Counts, not timings: N = 72 runs per row (12 settings x 6 instances), one run each. The current-gate columns were re-run in R19.10
(HEAD 2d386d2, Apple M4, load ~2-3); the last column is the 0.1.0 record, whose 500-sweep row
this table showed until R19.10 without saying so (0.2.0's dual-pass batch rule refuses every 500-sweep run: 7 long batches).
Claim: on these frustrated Ising programs no passed whole answer and no released spin was wrong (tolerance 0.05 TV) under either
gate, and more work buys coverage (500 sweeps release nothing at all now; 0.1.0 released nothing there only at coupling 1.5). Not claimed: correctness beyond n = 16 (brute force stops there).

`cargo run --release -p probbit-ir --example maxcut_gset`. The graphs are generated with the shapes of the Gset recipes, NOT the
Gset files, so literature best cuts do not apply. Equal wall time (200 ms), 4 threads per method, 5 seeds (N = 5 runs per method, one per seed), best cut median [IQR].

| graph | probbit sample (beta 2) | probbit sample 100 ms + anneal 100 ms | probbit anneal only | simulated annealing (geometric beta 0.2 -> 5, untuned), 4 restarts |
|---|---|---|---|---|
| G1-like: Erdos-Renyi n = 800, p = 0.06, 18,918 unit edges | 11450 [11437-11454] | 11453 [11447-11460] | 11463 [11463-11469] | **11470** [11465-11470] |
| G11-like: torus 20 x 40, weights ±1 | 562 [558-562] | 568 [564-568] | 568 [566-568] | **572** [570-572] |

Throughput: probbit 11.4-12.2 M site updates/s (G1-like, 4 chains) and 58-62 M (G11-like); SA 76.3 M and 308 M Metropolis
flip attempts/s (a cheaper operation than a heat-bath update). Claim: probbit's anneal-only mode gets within 0.06% (G1-like) and
0.7% (G11-like) of an untuned SA (fixed geometric schedule) at equal time, and its sampler, the mode that gives odds, is 0.17% and
1.75% behind; and its exact tiers (not this table; earlier builds) give exact odds and log Z on small instances. Not claimed:
that probbit finds better cuts. SA wins both, and a dedicated max-cut heuristic would likely win by more (unmeasured).
## §4 Sudoku vs backtracking, and graph colouring vs exact odds (re-runs of `sudoku_bench.rs` and `colouring_oracle.rs`)
`cargo run --release -p probbit-ir --example sudoku_bench`. "Unique" puzzles have one solution; "open" puzzles have extra givens
removed (4,849 to 305,753 solutions). DFS = bitmask backtracking with minimum-remaining-values. N = the puzzles in the row
(20 / 10 / 10), one timed run per puzzle and method: a cell is the median [IQR] (or the median) ACROSS puzzles, not repeats of
one puzzle, and the last column is the per-puzzle ratio, median (range).

| task | bitmask DFS (MRV) | probbit | probbit / DFS |
|---|---|---|---|
| solve + prove unique, all 20 puzzles | 0.011 [0.008-0.018] ms | sampler + gate 114.7 [114.3-115.1] ms: refused 20/20 (0 released, 0 false) | — |
| count all solutions + exact per-cell odds, unique (10) | 0.0185 ms median | exact tier (MRV enumeration) 0.787 ms | 44x (32.5-74) |
| same, open (10) | 35.7 ms median | 567.6 ms | 16.7x (14.6-18.0) |

A later re-run on the engine with the exact-tier gap budget (N = 5 runs, alternating with the engine before it, `MS=5`, median [IQR] of per-run medians): exact tier
0.818 [0.815-0.819] ms unique / 606.3 [605.7-607.7] ms open vs DFS 0.017 / 35.5 ms, i.e. 48-53x / 17-18x (per puzzle 36-102x / 15-20x;
the largest ratios are on puzzles the DFS finishes in ~4 µs). That gap budget (§6) costs 1.4% (unique, engine before it 0.807
[0.803-0.814] ms) and 4.2% (open, 582.1 [581.1-587.5] ms) here: IQRs disjoint, answers and odds identical (error 0 on all runs).
A later change then moved that count out of the inner loop (same count, same answers); one run afterwards: 0.956 ms unique / 567.0 ms open.
An A/B comparison (script not included in this repository; 12 generated puzzles (`N=6`), 3 runs alternating with the previous engine): after a later change
moved the exact search's stop checks out of its hot path, the IR exact tier is **17% faster** (per-puzzle median new / old 0.827, range
0.811-0.850; e.g. 380 vs 465 ms, 2,644 vs 3,121 ms on open puzzles), solution counts identical; the same change measured 0.832-0.942 on
4 colouring programs. The cause is inferred (code layout from the `#[cold]` split), not proven. The table above is not re-run:
the DFS still wins by more than an order of magnitude *(inferred from the ratios: ~14x / ~37x)*. Measured later (`N=3`: 6 puzzles,
1 run, final binary): 13.3-15.6x on open puzzles, ~37x on unique ones; counts identical, odds error 0, sampler refused 6/6.
Re-run of the full bench on the final 0.2.0 build (R19.10, HEAD 70db37b, load 3.0-4.5): 20/20 refused,
0 released, 0 false; exact odds error 0 and counts equal to the DFS on all 20; DFS solve + prove 0.011 [0.008-0.022] ms; sampler + gate
127.8 [127.0-128.2] ms across puzzles (the table's 114.7 ms is from an earlier build; gate/3 runs more checks; not separated from load).

probbit's exact odds equal the DFS odds on all 20 puzzles (error 0). Claim: probbit expresses sudoku as a program, gives exact
per-cell odds on puzzles with many solutions, and its sampler refuses these programs (20/20) instead of releasing odds. Not claimed: speed. A dedicated
backtracker is 15-102x faster at the same exact job (per puzzle, re-runs above), and the sampler cannot certify these frozen, one-hot-constrained
programs at all (later re-run: 20/20 refused, 0 released). A puzzle that unit propagation (naked singles) solves is the exception in
the current build: every cell is then a proven constant and `--op sample` certifies it (the CLI test's puzzle); none of these 20 is one.

Graph colouring (`cargo run --release -p probbit-ir --example colouring_oracle`): random G(n, p) with mean degree 3, two vertices
pre-coloured by clamps, soft colour preferences. The IR's exact tier (probbit's own enumeration, see Oracles above) gives the
reference odds; the sampler (4 chains, 100 ms) is
scored on every vertex it releases. N = the graphs column (one exact run and one sampler run per graph): the time is the median
[IQR] across those graphs; the verdict and vertex columns are totals over them.

| setting | graphs | colourings (median, range) | exact tier ms, median [IQR] | sampler verdicts | released vertices | outside ±0.05 TV |
|---|---|---|---|---|---|---|
| n = 12, k = 4 | 20 | 4,320 (198-22,356) | 0.30 [0.20-0.80] | 19 certified, 1 refused | 228 | 0 |
| n = 12, k = 5 | 20 | 93,321 (28,440-2,048,000) | 5.70 [4.00-8.62] | 20 certified | 240 | 0 |
| n = 14, k = 3 | 14 colourable | 97.5 (4-864) | 0.00 [0.00-0.03] | 4 certified, 1 partial, 9 refused (later re-run; earlier builds: 14 refused) | 57 (earlier builds: 0) | 0 |

Claim: on these colouring programs the gate released 525 vertices and none was outside tolerance (later re-run; earlier builds released
468, all 3-colourings refused). A later build changed the stuck-chain rule for programs that are not partitions: a vertex its clamped
neighbours force (unit propagation: a cap forced vertices fill removes that colour from the others, to a fixpoint) is a constant,
not a stuck chain; and a stuck vertex now escalates only its connected component instead of the whole answer. Over 6 sets
(h scale 1 and 6 x 3 seed bases, this one included; M4, 4 chains, 100 ms): 82 colourable 3-colourings -> 14 certified, 9 partial,
59 refused (all 82 refused before), 219 released vertices, 0 outside tolerance (max 0.016); k = 4 / 5 unchanged on every set.
Not claimed: that the sampler is needed at this size (the exact tier is faster than the 100 ms sampler on every instance), or
coverage on few-solution graphs (k = 3: still 59 of 82 refused). With 10x the sampler time (1 s, default set) the k = 3 verdicts
are identical (4 / 1 / 9): the refusals are structural. Of those 9, 6 had a vertex off by 0.11-0.46 (the stuck rule is right to refuse)
and 3 were within 0.048 (over-refusals). Kill test for the component rule (`--example stuck_twins`):
a rigid 3-coloured part next to a 4-coloured part that mixes, joined by one edge in half the programs; 4 seeds, 120 programs (85 with
a frozen variable): 938 released vertices (430 + 508 from the raw CSVs of two runs, not included here; first reported as 859, a mis-sum found in
a later audit), 0 outside tolerance. A deliberately broken rule whose caps do not link components
released 21 vertices outside tolerance on the first 62 of them, so the test can fail.

### 4.3 Scheduling vs exact odds, and vs greedy + repair (`cargo run --release -p probbit-ir --example schedule_oracle`, ~25 s)
Unit-time jobs are variables, time slots are values. Hard rules: a release/deadline window per job, at most `cap` jobs per slot,
precedence i -> j as pair caps (at most one of (i, a), (j, b) for every a >= b; O(T^2) caps per edge). Soft: weighted completion
time plus noise. Baseline: greedy list scheduling (topological, heaviest ready job first, best slot not later than its latest
start) + repair (move / swap hill climbing); "restarts" repeats it with random ready-job orders for the same wall time.
M4, load average 5-7 from another process; sampler 4 chains / 4 threads, 100 ms per method. N = the instances column (one run
per instance and method): the exact-tier time is the median [IQR] across instances; the other columns are totals or counts. The
second table lists every seed (N = 5 per setting) instead of a median.

| setting | instances | schedules (median, range) | exact tier ms, median [IQR] | sampler verdicts | released jobs | outside ±0.05 TV | MAP found: greedy+repair / restarts / probbit |
|---|---|---|---|---|---|---|---|
| 10 jobs, 6 slots, cap 2 | 20 | 15,559 (861-100,120) | 1.9 [1.1-3.8] | 20 certified | 200 | 0 (max 0.0058) | 9/14 (6 greedy dead ends) / 20/20 / 20/20 |
| 12 jobs, 6 slots, cap 3 | 19 feasible | 634,026 (48,186-6,148,512) | 30.1 [13.6-79.9] | 19 certified | 228 | 0 (max 0.0050) | 8/19 / 19/19 / 19/19 |

Larger, no oracle (plan log w at equal 100 ms; probbit = anneal from the plain greedy plan; 5 seeds):

| setting | precedence edges (median) | probbit minus restarts, per seed | probbit better | single greedy+repair |
|---|---|---|---|---|
| 200 jobs, 40 slots, cap 10 | 181 | -0.18, +4.63, +2.92, +2.05, +4.06 | 4/5 | 0.36 ms, 8.2 log w below probbit (median) |
| 500 jobs, 50 slots, cap 20 | 469 | +4.02, +17.41, +3.27, +3.18, -7.34 | 4/5 | 2.5 ms, 15.7 below probbit (median) |

Claim: scheduling is expressed in the existing IR (no new constraint types; at 100-200 jobs it needed engine fixes: the anneal
warm start and the feasible-start retry; the exact tier's gap budget, the start retries and the start inside the
budget); on 39 oracle instances the gate released 428 jobs and none was
outside tolerance; at 200-500 jobs the anneal from a greedy start beat a restarted greedy + repair at equal time on 4 of 5 seeds.
Not claimed: optimality at scale, or that restarts are the strongest heuristic. A later run added the ILP baseline
(`/opt/homebrew/bin/python3 bench/schedule_ilp.py`, scipy HiGHS; three 200-job x 40-slot programs, cap 10, 77-90 K precedence
pair caps = schedule_oracle `PROBE_START=200 PSEED=0/1/2`, N = 3 probbit runs each, Apple M4): HiGHS PROVES the optimum in
0.68-0.95 s (about 6,000 binaries x 78-90 K rows); `probbit run --op decide` is 3.27-4.26 nats short of it at `--budget-ms 2000`
(refused, 0 released) and 3.27-3.95 short at 5000 (partial 156-173 released on 2 programs, refused on the third; wall 6.2 s;
0 violations in all 18 runs). For the best schedule, use a MIP solver: probbit adds the per-job odds and the refusal, not the plan. Part B anneals from the greedy plan because, when it ran, the sampler could not start: its random
feasible start (a 2M-node MRV search at O(n k caps) per node) gave up after 105.3 s on the feasible 200-job program
(`PROBE_START=200`). Since then that search has a work budget and retries in ascending value order (MRV, then input order): start
found in 0.68-0.73 s (5 runs, 3 instances); sampler at a 1 s budget: refused (R-hat 1.0043), at 5 s: partial on all 3
instances, 186 / 186 / 181 of 200 jobs released (R-hat 1.0006 / 1.0003 / 1.0007), 0 violations. With the start inside the budget
(one run each, load 10-17 from other processes): 1 s refused on all 3 (1.06-1.19 s total incl. gate, was ~1.97 s); 5 s
partial 170 / 170 / 153 of 200 (R-hat 1.0005 / 1.0006 / 1.0016), 0 violations; re-run at load 6.5-7: 171 / 170 / 154, so the
drop from 186 / 186 / 181 follows the ~0.7 s of start now inside the budget, not the load (inferred). No oracle exists at 200 jobs, so
those odds are unchecked. The retry never fired on the sudoku
(§4) or colouring runs (0 of all their starts), so their starts are unchanged.
At 100 jobs (`PROBE_START=100`, 3 instances) one instance could not start 4 chains: 3 of 8 chain streams gave up
without retrying (their random attempt ran out of nodes, not work, and only the work budget triggered the retry) and 2 still
failed both retries. Now any budget exit retries, then up to 4 more MRV attempts with fresh random tie-breaks (only after every
earlier attempt failed, so earlier starts are unchanged): 8 of 8 streams start (slowest 1.36 s). Sampler, 4 chains: at 1 s
refused / partial 76 / refused (R-hat 1.0024 / 1.0010 / 1.0004); at 5 s certified 100 / certified 100 / refused (the third has 6
frozen capacities; later re-run at 5 s with per-component escalation: certified / certified / refused, 0 of 100 released, frozen 6). The 1 s verdicts were measured with the start
outside the budget (earlier build) and were not re-run; the 5 s verdicts were re-run on a later build (start inside the budget) with the same outcome. Unchecked: no oracle at 100 jobs either.
Cost of the extra attempts on a program that cannot start (`PCAP=4 PROBE_START=200 PROBE_STREAMS=2`: 200 jobs, 160
slot places): a chain reports no start after 2.09-2.12 s, vs 0.69-0.75 s with the reranks off (the start search did not
watch the budget then, so a `--budget-ms` shorter than that was overrun). It now stops at the budget's deadline: `probbit run
--budget-ms 500` on that program answers `refused` ("no feasible start found within the search budget") in 0.666 s (measured before the exact-search fallback was added, not re-measured; median of 5;
was 2.42 s, median of 3; 0.845 s with the clock read every 4,096 nodes, ~170 ms apart here, now every 64). `--op sample`
(no exact tiers): 504 ms inside the run, 0.575 s wall.

**How to read the times in §4.4-4.10 (program families, R19.7).** Each `bench/*.py` family script times ONE subprocess run per
call (`time.time()` around `probbit run`): a default-run time is N = 1 per instance and a range spans the instances, not repeats;
a "median ms" column is the median over the sampler seeds (1..4, one run each) of one instance. None of these is a median [IQR]
of repeated runs of one configuration, so read them as orders of magnitude, not as A/B timings (checked in R19.9 from the scripts).

### 4.4 Knapsack and bin packing through IR `linear` rules (R19.7, weighted caps)

`linear: [{"terms": [[var, value, weight], ...], "limit": L}]` lowers to one weighted cap. Two generated programs, exact
enumeration vs the sampler at defaults (`probbit run --op sample --seed S`, S = 1..5; Apple M4, load 8.5-9.1, single runs):

| program | exact (`--op exact`) | default `probbit run` | sampler verdicts | released | max \|odds - exact\| released | tv_bound | wall |
|---|---|---|---|---|---|---|---|
| knapsack20 (weights 1..9, limit 40% of total) | 242,272 plans, 27.8 ms | exact (enumerate) 27.4 ms | 5/5 diagnostics_passed | 20/20 | 0.0015-0.0018 | 0.0025-0.0028 | ~330 ms |
| bins10x3 (sizes 1..5, cap ceil(total/3)+1, 5 Potts pairs) | 6,672 plans, 3.1 ms | exact (enumerate) 2.8 ms | 5/5 diagnostics_passed | 10/10 | 0.0011-0.0016 | 0.0031-0.0034 | ~284 ms |

Beyond enumeration, against an independent DP (`python3 bench/knapsack.py`, stdlib; weights 1..20, h_in ~ U(0, 1.5), budget
40% of the total weight; oracle = log-space forward/backward DP over the used capacity + max-product for the optimum; baseline =
greedy by h_in / weight; 3 instances per size, sampler seeds 1..4; Apple M4, load 10-14):

| n | default `probbit run` | default plan vs DP optimum | greedy vs optimum | sampler (`--op sample`, 4 seeds x 3 instances) | released | max \|odds - DP\| | median wall |
|---|---|---|---|---|---|---|---|
| 20 | exact (enumerate), 25.8-27.6 ms | equal (3/3) | 0 to -0.24 nats | 12/12 diagnostics_passed | 240/240 | 0.0027 | ~335 ms |
| 40 | sampled, 416-425 ms | equal (3/3) | 0 to -0.29 nats | 12/12 diagnostics_passed | 480/480 | 0.0033 | ~340 ms |
| 80 | sampled, 453-463 ms | equal (3/3) | 0 to -0.07 nats | 12/12 diagnostics_passed | 960/960 | 0.0060 | ~342 ms |

Totals: 36 sampled answers, 1,680 released items, 0 outside 0.05 of the DP, 0 false `diagnostics_passed`. Test
`run_knapsack_example_matches_dp` pins `examples/knapsack-20.json` (exact tier = an in-test Rust DP: odds 5.1e-7, log Z, plan).
What it allows: knapsack / bin-packing rules run on every tier unchanged, and the sampler's odds on these programs match
enumeration or the DP well inside the 0.05 tolerance. What it forbids: claims beyond n = 80 single-budget knapsacks
(multi-budget and bin packing beyond 10 x 3 have no independent oracle run yet), and any speed claim against a DP. Where it
loses: a pure knapsack is solved exactly by the O(n x budget) DP (its wall time was not measured here; the table has 80 x 640
cells); probbit samples it in ~0.45 s. Enumeration answers n = 20 and the 10 x 3 bins in 3-28 ms; the sampler is the fallback.

Bin packing (`python3 bench/binpacking.py`, stdlib): n items of size 1..6 into 3 bins of capacity ceil(total / 3) + 2, one
`linear` rule per bin, preferences h(item, bin) ~ U(-0.5, 0.5); oracle = exact forward/backward DP over the vector of bin
loads (log Z, P(item in bin), optimum); baseline = largest-first greedy (each item, largest first, onto its preferred bin that still fits). 2 instances per size,
sampler seeds 1..4 (Apple M4, load ~6):

| n (raw space) | default `probbit run` | plan vs DP optimum | greedy vs optimum | sampler | released | max \|odds - DP\| |
|---|---|---|---|---|---|---|
| 12 (531,441) | exact (enumerate), 10.0-12.6 ms | equal (2/2) | 0 to -0.39 nats | 8/8 diagnostics_passed | 96/96 | 0.0016 |
| 24 (2.8e11) | sampled, 357-387 ms | equal (2/2) | -0.34 to -0.80 nats | 8/8 diagnostics_passed | 192/192 | 0.0030 |
| 36 (1.5e17) | sampled, 370-371 ms | equal (2/2) | -1.48 to -2.45 nats | 8/8 diagnostics_passed | 288/288 | 0.0051 |

24 sampled answers, 576 released, 0 outside 0.05, 0 false (n = 36: same machine and load). What it
allows: bin capacities written as `linear` rules, with sampled odds within 0.0051 of an exact load-vector DP on 3 bins up to 36
items, and the default plan equal to the DP optimum on all 6 instances. What it forbids: claims past 3 bins x 36 items (no
oracle run there) and any speed claim against the DP (its wall time was not compared). Where it loses: this DP is exact for preference-only bin packing
(no pair terms) with a few bins; probbit's case is the same rule next to pairs / quotas / precedences the DP does not model.

### 4.5 Ising-MRF image denoising (R19.7, P2.2; `python3 bench/denoise.py`, stdlib)

The classic p-bit demo. 8 x 12 binary image (a filled ellipse), each pixel flipped with probability 0.1; program = one {0, 1}
variable per pixel, unary +-1.1 toward the observed pixel, Potts +0.7 between 4-neighbours (`examples/denoise-8x12.json` =
image 1). Oracle: row transfer matrix (256 states per row): exact log Z, per-pixel odds, exact MAP (Viterbi). Baseline: ICM
(iterated conditional modes from the noisy image). probbit: `probbit run` at defaults; `probbit run --op sample --seed 1..4`. Pixel
errors are against the CLEAN image (Apple M4, load ~6):

| image | noisy | ICM | exact MAP | exact MPM | default `probbit run` (sampled, ~285 ms): plan errors, plan = exact MAP? | sampler: verdicts | released | max \|odds - exact\| | sampler MPM errors |
|---|---|---|---|---|---|---|---|---|---|
| 1 | 11 | 4 | 8 | 10 | 8, yes | 4/4 diagnostics_passed | 384/384 | 0.0048 | 10 |
| 2 | 7 | 9 | 7 | 7 | 7, yes | 4/4 diagnostics_passed | 384/384 | 0.0042 | 7 |
| 3 | 12 | 7 | 5 | 4 | 5, yes | 4/4 diagnostics_passed | 384/384 | 0.0035 | 4 |

Totals: 12 sampled answers, 1,152 pixels released, 0 outside 0.05 of the transfer matrix, 0 false. What it allows: probbit
reproduces this model's exact posterior odds and its exact MAP image. What it forbids: "probbit denoises better than ICM": pixel
error measures the model (eta, J), not the solver; on image 1 ICM's local optimum is closer to the clean image (4 vs 8 errors)
than the model's own exact MAP. Where it loses: a transfer matrix answers an 8-wide grid exactly (and faster, in a compiled
language); probbit samples it (~265-285 ms). Test `run_ising_denoise_matches_brute_force` (4 x 4, exact vs 2^16 brute force +
sampler at fixed work).

### 4.6 Tree-structured probabilistic inference (R19.7, P2.2; `python3 bench/tree_infer.py`, stdlib)

Random trees (parent of node i uniform in 0..i-1), 3 values, unaries and per-edge 3 x 3 tables ~ U(-1, 1). Independent oracle:
log-space two-pass sum-product in Python. probbit: `probbit run` at defaults (the inference compiler's forest tier) and
`probbit run --op sample --seed 1..4` (2 instances per size; Apple M4, load ~4):

| n | default `probbit run` | \|log Z - oracle\| | max \|odds - oracle\| | default wall | sampler | released | max \|odds - oracle\| released | sampler wall |
|---|---|---|---|---|---|---|---|---|
| 200 | exact (forest) | <= 4.2e-7 | 5.0e-7 (the CLI prints 6 decimals) | 4.0-4.5 ms | 8/8 diagnostics_passed | 1,600/1,600 | 0.0094 | ~260 ms |
| 1,000 | exact (forest) | <= 4.6e-7 | 5.0e-7 | 11.2-11.5 ms | 8/8 diagnostics_passed | 8,000/8,000 | 0.0249 | ~267 ms |

What it allows: tree-shaped programs are answered exactly at defaults, matching an independent sum-product to print
precision, ~23-65x faster than sampling them. What it forbids: reading the sampler's 0.0249 worst item at n = 1,000 as typical
precision (within the 0.05 tolerance, but 5x the n = 20 knapsack's); loopy graphs get no exact tier unless enumeration,
components, the frontier or the count DP apply.

### 4.7 Budgeted selection with pair correlations (portfolio shape; R19.7, P2.2; `python3 bench/portfolio.py`, stdlib)

n assets in a sector chain: in / out, h_in ~ U(-0.2, 1.0), cost 1..10, one `linear` budget (35% of the total cost), Potts
J_i ~ U(-0.6, 0.6) between neighbours. No exact tier of probbit applies (a weighted rule plus pairs), so defaults sample.
Independent oracle: exact DP over (position, choice, used budget) for log Z, P(in) and the optimum. Baseline: greedy by
h_in / cost, ignoring the pairs (scored with them). 2 instances per size, sampler seeds 1..4 (Apple M4, load ~4):

| n | default `probbit run` (sampled) | plan vs DP optimum | greedy vs optimum | sampler | released | max \|odds - DP\| |
|---|---|---|---|---|---|---|
| 30 | 406-427 ms | equal (2/2) | -1.69 to -1.92 nats | 8/8 diagnostics_passed | 240/240 | 0.0032 |
| 60 | 412-413 ms | equal (2/2) | -2.05 to -4.78 nats | 8/8 diagnostics_passed | 480/480 | 0.0036 |

16 answers, 720 released, 0 outside 0.05, 0 false. What it allows: a budget and correlations in one program, with checked odds
and the optimum on these instances. What it forbids: general portfolio claims (real covariance is dense, not a chain; dense
pair graphs have no independent oracle here). Where it loses: this chain-plus-budget shape has an exact O(n x budget) DP, which
probbit does not detect (a mixed weighted-cap + forest tier would; not built).

### 4.8 3-SAT solution counting and sampling (R19.7, P2.2; `python3 bench/sat.py`, stdlib)

Planted random 3-SAT at clause ratio 4.0 (satisfiable by construction), uniform over the solutions; one IR `tables` forbid per
clause (its falsifying tuple). Oracle: brute force over 2^n. Baseline: WalkSAT (p = 0.5), which finds ONE solution. 2 instances
per size, sampler seeds 1..4 (Apple M4, load ~4):

| n | m | solutions | WalkSAT flips to a solution | default `probbit run` | sampler (`--op sample`) |
|---|---|---|---|---|---|
| 14 | 56 | 10 / 18 | 10 / 10 | exact (enumerate): the count and every odd = brute force (print precision), 2.6-3.5 ms | 8/8 **refused**, 0 released |
| 18 | 72 | 22 / 5 | 27 / 161 | exact (enumerate), 2.8-3.0 ms | 8/8 **refused**, 0 released |

What it allows: exact solution counts and per-variable odds over the solutions for small formulas, in milliseconds. What it
forbids: "probbit samples SAT solutions": near the threshold the solutions are few and isolated (no single-variable or swap move
connects them), and the gate refuses every sampled answer (16/16; 0 wrong, 0 false) instead of reporting one cluster as the
answer. Where it loses: finding one solution is WalkSAT's job (10-161 flips here); formulas past `--exact-limit` get a refusal.
MaxSAT (soft clauses) is not expressible in v1 (no soft ternary terms; an auxiliary-variable encoding was not built).

### 4.9 Agentic tool-call planner (R19.7, P2.2; the AI demo; `python3 bench/agent_planner.py`, stdlib)

One variable per step over {search, read, code, test, ask, stop}; unaries = a policy's per-step scores (search/read favoured
early, code/test later); a `table` pair between consecutive steps = transition preferences (search->read, read->code,
code->test, test->stop, repeats penalised); rules: at most 2 search and 1 ask (value caps), stop is absorbing and test needs
code or test just before it (`implies`), no test first (`forbid`), and a token budget (`linear`: search 3, read 2, code 5,
test 4, ask 1, stop 0 <= 3 x steps). Oracle: brute force over 6^T by the rules' direct meaning; baseline: greedy step by step.
2 instances per size, sampler seeds 1..4 (Apple M4, load ~3; `examples/agent-plan-6.json`):

| steps | feasible plans | default `probbit run` | plan = optimum | greedy vs optimum | sampler | released | max \|odds - brute\| |
|---|---|---|---|---|---|---|---|
| 6 | 1,921 | exact (enumerate), odds <= 4.9e-7, 3.0-5.4 ms | 2/2 | -1.53 to -1.89 nats | 8/8 diagnostics_passed | 48/48 | 0.0019 |
| 7 | 6,001 | exact (enumerate), odds <= 4.9e-7, 3.6-3.8 ms | 2/2 | -1.64 to -2.15 nats | 8/8 diagnostics_passed | 56/56 | 0.0029 |

What it allows: a planner's soft policy and hard rules (quotas, ordering, absorbing stop, a token budget) in one program, with
the exact best plan and per-step odds of each action in milliseconds at this size. What it forbids: claims about long
horizons (no oracle past 7 steps here) or about a real agent's policy (the scores are synthetic). Where it loses: a
step-indexed DP over (step, last action, budget, counts) solves this exact shape too; probbit's case is that the rules are data,
not code.

### 4.10 Assignment with side constraints (R19.7, P2.2; `python3 bench/assign_side.py`, stdlib)

n tasks onto 3 workers: scores ~ U(-1, 1); a per-worker effort budget (`linear`, efforts 1..4); n/3 conflict pairs that may not
share a worker (`all_different`); one implication; a value cap on worker C. Oracle: brute force over 3^n by the rules' direct
meaning (no ILP baseline: scipy / HiGHS are not installed on this machine); baseline: greedy by best score. 2 instances per
size, sampler seeds 1..4 (Apple M4, load ~6):

| n | feasible plans | default `probbit run` | plan = optimum | greedy vs optimum | sampler | released | max \|odds - brute\| |
|---|---|---|---|---|---|---|---|
| 8 | 378 / 608 | exact (enumerate), odds <= 4.8e-7, 2.8-4.7 ms | 2/2 | 0 to -0.46 nats | 8/8 diagnostics_passed | 64/64 | 0.0024 |
| 12 | 15,637 / 27,682 | exact (enumerate), odds <= 4.9e-7, 5.0-6.1 ms | 2/2 | -0.07 to -1.71 nats | 8/8 diagnostics_passed | 96/96 | 0.0029 |

What it allows: assignment with budgets, conflicts, implications and quotas in one program, exact at this size. What it
forbids: any comparison with an ILP solver (not run here; §2.2 has the router-vs-ILP comparison on a machine with scipy).

## §5 Processor controls

### 5.1 `--threads` on the router (`bench/decide_threads.py`, N = 5)
300-task demo, `probbit decide --sweeps 400 --chains 4 --polish-ms 0` (fixed work):

| `--threads` | wall ms | process CPU ms | sampler site updates/s | answer |
|---|---|---|---|---|
| 1 | 74.1 [72.7-74.3] | 78.3 | 14.62 M | reference |
| 2 | 58.5 [57.8-59.1] | 79.9 | 27.08 M | identical |
| 4 | 50.9 [50.1-51.7] | 83.6 | 47.40 M | identical |

Wall ms is the median [IQR] of N = 5; the CPU and rate columns are medians of the same 5 runs (the script prints no IQR for them).
Claim: at fixed work (fixed `--sweeps`, and `--polish-ms 0` or the newer `--polish-sweeps`) the answer is bit-identical at 1, 2 and
4 threads (tested; chains are seeded per chain, not per thread), and the sampler scales 3.2x on 4 threads. With the default wall-clock polish only the polished plan can vary (in the current build). Not
claimed: wall time scales the same way; the serial part (exact tiers' decline, parse, gate: ~40 ms here, inferred as wall
minus sampler time) dominates at this size.

### 5.2 `--progress` cost (`bench/progress_overhead.py`, N = 7 alternating)

| program (fixed work, 4 chains / 4 threads) | off, M updates/s | on, M updates/s | change |
|---|---|---|---|
| router, 300-task demo, 2,000 sweeps | 54.00 [52.68-54.32] | 52.39 [51.89-53.34] | -3.0% |
| IR, 400-spin ring, 4,000 sweeps | 78.16 [77.08-78.96] | 79.21 [78.83-79.51] | +1.3% |
| IR, 3-variable toy, 400,000 sweeps | 82.57 [72.44-85.93] | 80.03 [75.31-83.13] | -3.1% |

A second full run (verification) gave -0.6% / +4.6% / -8.3% (toy IQRs 72.28-86.91 off vs 68.94-75.36 on, still overlapping).
Claim: on the two realistic programs the monitor costs within about ±5% and did not change the answer in these runs. Not claimed: zero cost.
On tiny programs it plausibly costs up to ~8% (inferred cause: 4 threads adding to one shared counter every 64 very short sweeps).
The off-path cost against a build without the counter was not A/B measured.

### 5.3 `--mem-limit-mb` (`bench/mem_limit.py`, `bench/mem_limit_hard.py`)

| case | unbounded | capped |
|---|---|---|
| 300 tasks, `--budget-ms 3000`, peak RSS (N = 3, median, min-max) | 579.9 MB (460-622) | 40.6 MB (40.6-41.8) at 16 MB |
| 18/24-task demos vs exact odds, forced sampler, 24 runs per column | 528 released, 0 outside ±0.05 TV | 528 released, 0 outside, at 1 MB (~31x thinning) |
| 300-task `--hard`, 1 s, released tasks (N = 5 seeds) | 300 (5/5 certified) | 300/300/300/299/300 at 8 MB; 239 median at 2 MB (5/5 partial) |

A later measurement (one run each, 300 tasks): unbounded peak RSS grows ~170-195 MB per second of budget (190.5 / 585.6 / 1,666.9 MB at 1 / 3 /
10 s). The 299 at 8 MB in the table is within run-to-run noise (an unbounded replicate also gave 299). At 10 s, `--mem-limit-mb 1024` peaked at 1,632 MB in an earlier build, because the capped buffer grew by doubling. Now it is reserved
once and peaks at 1,042 MB (3 s at 256 MB: 275.6 MB; 3 s at 16 MB: 33.5 MB; all certified).

Claim: the cap bounds the buffers that grow with the budget (peak RSS = cap + ~20 MB base in the current build), and in these runs it never
produced an answer outside tolerance. Not claimed: the cap is free. Thinning a slowly mixing chain costs releases (third row).

**Default in the current build: 1024 MB** (`--mem-limit-mb 0` = unbounded, the old default). Measured (M4, 300 tasks, load average 3.9-6.9 from
another process): at the default 200 ms budget peak RSS 41.7 MB (41.5-41.9, N = 5) vs 52.5 MB (45.9-52.6) unbounded, 300/300 certified
each (no thinning: ~34.5k rows vs a cap of 1.77M); at `--budget-ms 10000` 1,024.2 MB (1,013.9-1,031.5, N = 3) vs 1,625.0 MB
(1,606.8-1,627.6), 300/300 certified each (one capped run thinned: 1.31M rows kept vs 1.71-1.75M). Claim: a default run can no longer
grow its sample memory past ~1 GB + base. Not claimed: 1 GB suits every machine (it is not derived from installed RAM), or the
Windows cost: the capped buffer is reserved once, which Windows commits up front (unmeasured; a smaller cap or 0 avoids it).

### 5.4 `--priority low` under contention (`bench/priority_contention.py`, `bench/priority_low_alone.py`, N = 5)
Foreground: 400-spin ring, 10 chains x 20,000 sweeps on 10 threads. Background: the same program with a 4 s budget on 10 threads.

| background priority | foreground wall ms | slowdown vs alone |
|---|---|---|
| none (alone) | 702.7 [678.2-715.9] | 1.00 |
| normal | 1251.9 [1242.2-1307.6] | 1.78 |
| low = nice 10 only (earlier-build behaviour) | 1275.0 [1227.7-1289.8] | 1.73 (separate run; alone 737.4) |
| low = nice 10 + macOS background band (current build) | 716.9 [687.3-735.0] | 1.02 |

The cost: a `low` run on an idle M4 takes 481.5 [453.4-489.8] ms vs 114.6 [99.3-116.1] ms at normal priority (x4.2 wall,
x3.9 CPU; same answer). Claim: on macOS, `--priority low` kept probbit out of the way of the other job tested (a probbit foreground run). Not claimed: anything
about Linux or Windows (Linux unmeasured; Windows exits 2).

### 5.5 Portable vs `-C target-cpu=native` (`bench/portable_vs_native.py`, N = 5 alternating)
Native / portable ratio on 16 metrics (probbit-core kernels, `probbit stats`, router sampler): 0.975 to 1.012. For example the
older (not the §1 fast-path) heat-bath f32 LUT kernel ran at 5.36e8 updates/s/thread in both builds, and the older
64-lane multispin kernel at 2.41e10/thread
(64 packed replicas per word sharing one random draw per site, not independent and not one problem 64x faster). Kernel checksums and the router's answer are identical
across the two builds. Claim: on Apple silicon the portable default loses nothing measurable. Not claimed: anything about
x86-64, where `native` can enable AVX2/AVX-512 (unmeasured).

### 5.6 `probbit stats` self-test (N = 7)
400-spin ring, 4 chains x 2,000 sweeps: 23.05 [22.70-23.07] M site updates/s on 1 thread, 77.65 [76.11-79.37] M on 4
(x3.37 [3.30-3.54]). This is the number `probbit stats` prints on your machine: it is a self-test, not a comparison.

### 5.7 `--cpu-limit` on the router (`bench/decide_cpu_limit.py`, N = 3)
300-task demo, `probbit decide --sweeps 1000 --polish-ms 0`, 4 threads: sampler phase 23.9 / 57.0 / 132.0 ms and process CPU
137.2 / 139.8 / 152.1 ms at `--cpu-limit` 100 / 50 / 25; same answer. Subtracting the ~40 ms serial part
(inferred in 5.1 as wall minus sampler time), the sampler used ~44% and ~21% of 4 cores at 50 and 25. Claim: it stays under the cap
here, for +11% CPU per unit of work at 25. Not claimed: that this holds generally. On `probbit run` with a 2,000-spin ring, 25% cost 4.1x
the CPU (earlier build).

### 5.8 The plan polish honours `--threads` (`bench/polish_threads.py`, N = 5 alternating, old vs new binary)
300-task demo, `probbit decide --sweeps 400 --polish-ms 50`. In an earlier build the polish ran 4 threads whatever `--threads` said.

| `--threads` | binary | wall ms | process CPU ms | CPU / wall | plan log w, median (min-max) |
|---|---|---|---|---|---|
| 1 | before | 122.8 | 277.7 | 2.26 | 707.77 (707.32-708.01) |
| 1 | after | 122.4 | 126.9 | 1.04 | 705.12 (704.63-706.83) |
| 4 | before | 100.1 | 282.9 | 2.83 | 707.32 (707.27-707.86) |
| 4 | after | 99.5 | 282.4 | 2.84 | 707.27 (706.96-707.93) |

Wall and CPU are medians of N = 5 per row (the script prints no IQR for them); plan log w is the median (min-max) of the same runs.
Claim: `--threads 1` now means one thread through the whole answer, and 4 threads are unchanged. Not claimed: that it is free:
at the same wall time one thread polishes a quarter as long per chain, so the plan was 2.65 log w lower (the ILP optimum of
this queue is 708.31, §2.2). The load average was ~4.5 during this run (another process was busy; alternating runs).

## §5b Inference compiler tiers (R19.3-R19.4): exact answers where structure allows

Before = the R19.3 binary (copied before the change), after = R19.4, same machine (Apple M4, 16 GB, macOS), `probbit run` /
`probbit decide` at defaults, `ms` field of the answer, medians of N = 5 (one binary at a time, alternated per input), load 3.6-18
(the machine is shared). No IQR was kept for this table: the before / after medians differ by 3-4 orders of magnitude, far
outside any run-to-run spread measured elsewhere in this file, so the medians alone carry the comparison. Inputs: `probbit-cli/tests/stress/` and two generated programs not in the repo (blocks4, const_tables32).

| Input | Structure | Before: verdict, tier, median ms | After: verdict, tier, median ms | Exactness check |
|---|---|---|---|---|
| chain100 (`probbit run`) | path, 100 two-value vars | `diagnostics_passed`, sample, 281.9 | `exact`, forest, 0.055 | odds vs transfer matrix <= 5.1e-7 (print rounding) |
| chain1000 (`probbit run`) | path, 1,000 vars | `diagnostics_passed`, sample, 281.3 | `exact`, forest, 0.390 | IR test on a random 1,000-var table chain: log Z vs transfer matrix, 4e-13 absolute |
| blocks4 (`probbit run`) | 4 independent 8-var rings, overlapping caps (non-partition, 2^32 raw space) | `diagnostics_passed`, sample, 385.5 | `exact`, components (4 enumerated), 0.057 | per-block Python brute force, max diff 4.6e-7 |
| asymmetric-router32 h0.03 (`probbit decide`) | one 32-task group, 2 workers, uniform affinity | `diagnostics_passed`, sample, 428.8 | `exact`, occupancy, 0.092 | P(B) vs ESP oracle <= 5.1e-7, 20/20 seeds |
| asymmetric-router32 h0.06 | same | `diagnostics_passed`, sample, 426.4 | `exact`, occupancy, 0.087 | same |
| heterogeneous-router32 | same, per-task scores | `diagnostics_passed`, sample, 423.4 | `exact`, occupancy, 0.086 | same |
| const_tables32 (`probbit run`) | 32 independent vars + 496 constant tables (0.5) | `diagnostics_passed`, sample, 385.7 | `exact`, frontier (496 tables folded), 0.045 | log Z = table-free log Z + 248 |
| review case E17 (R19.3) | 32 vars + 496 `potts: 0` pairs | sample, 115.7 (single run) | `exact`, frontier, 0.051 (N = 7) | identical to the pair-free program |

What this allows: on decomposable programs (independent parts, trees, two-value groups with one uniform coupling, factors
that change no odds) probbit answers exactly, with log Z and an exact MAP plan, in well under a millisecond, where it used to
spend its 200 ms sampling budget and could be wrong when the chains shared a wrong mode (the router rows are the external review's
counterexamples). What it forbids: reading these as sampler speedups — the sampler is unchanged; `--op sample` /
`--mode sample` still sample these inputs (and the stress tests run both paths). Where it loses: the tiers decline in
microseconds-to-milliseconds on programs with no such structure (one component with cycles and caps, mixed couplings,
> 2048 counted members, forest work > 5e7), and a program that is mostly decomposable with one hard part is still sampled
WHOLE (the residual part is not yet sampled alone: R19.5+); components enumeration shares one `--exact-limit` budget.
Bounded-width variable elimination (P1.3(e)) is not built.

## Known failure modes

The gate's statistics measure Monte-Carlo error AROUND the modes the chains visit. When every chain stays in the same wrong
macroscopic mode, R-hat is ~1, batch means agree, and the bound shrinks with more sampling while the error stays ~0.5-0.87.
These inputs are frozen in `probbit-cli/tests/stress/` (provenance: the 2026-09-30 external review) with oracles that do not use
probbit's inference (`probbit-cli/tests/stress.rs`: occupancy count DP, brute force, transfer matrix; `stress_oracles_agree` passes).
Measured on the R19.1 build (Apple M4, load 7-9), seeds 1..20, at defaults and at fixed work (`--sweeps 4000 --polish-ms 0`):

| Input (command) | Truth | Defaults: whole answers passed / false / released items wrong | Fixed work |
|---|---|---|---|
| `asymmetric-router32-w0.2-h0.03.json` (`probbit decide --seed S`) | P(B) per task from the count DP | 2 / 2 / 64 of 64 (18 refused) | 2 / 2 / 64 of 64 |
| `asymmetric-router32-w0.2-h0.06.json` (`probbit decide --seed S`) | P(B) = 0.8698133938587349 every task | 3 / 3 / 96 of 96 (17 refused) | 3 / 3 / 96 of 96 |
| `heterogeneous-router32.json` (`probbit decide --seed S`) | count DP | 2 / 2 / 64 of 64 (18 refused) | 2 / 2 / 64 of 64 |
| `ferro12.json` (`probbit run --op sample --seed S`) | 1/2 every spin (symmetry; brute force) | 3 / 3 / 36 of 36 (17 refused) | 3 / 3 / 36 of 36 |
| `ferro12-w0.5-redundantcaps.json` (`probbit run --op sample --seed S`) | 1/2 every spin | 0 / 0 / 0 (20 refused) | 3 / 3 / 36 of 36 |
| `ferro12-w1.0-redundantcaps.json` (`probbit run --op sample --seed S`) | 1/2 every spin | 2 / 2 / 24 of 24 (18 refused) | 0 / 0 / 0 (20 refused) |
| `chain100.json` (`probbit run --op sample --seed S`): control | transfer matrix | 20 / 0 / 0 of 2,000 | 20 / 0 / 0 of 2,000 |

Since R19.4 `probbit decide` answers the three router inputs EXACTLY at defaults (inference compiler, tier `occupancy`: a count
DP over the number of tasks on B; 20/20 seeds, every P(B) within print rounding of the oracle; 426-429 ms sampled -> 0.086-0.092
ms, medians N = 5, load 8-18), and `probbit run` answers chain100 exactly (tier `forest`, 281.9 ms -> 0.055 ms). The sampled rows
above therefore reproduce only with `--mode sample` (router; with `--collective off --cluster off --cycles off` for the red counts, which the ignored measurement test
`stress_gate_alone_moves_off` prints: R19.9 re-run 2 / 3 / 2 / 0 / 3 / 0 false of 20, as R19.3) or `--op sample`
(IR), which the stress tests now run explicitly next to the defaults.
What this table allows: a frozen, reproducible set of inputs on which the R19.1 gate passed false whole answers (counts over
seeds 1..20, not timings). What it forbids: reading `diagnostics_passed` as a guarantee when every chain may sit in one wrong
mode. With the current defaults these families answer exactly, and their sampled runs with the moves on give 0 false whole
answers and 0 wrong released items (frozen corpus re-run on R19.9 HEAD 2513937: 280 runs, 9,280 released).

Example (one false whole answer, deterministic; every collective move off — since R19.4 the default `--cluster on` answers this
seed correctly, max true error 0.0021 with `--collective off` alone, checked R19.9): `target/release/probbit decide --mode sample
--collective off --cluster off --cycles off --sweeps 4000 --seed 5 --polish-ms 0 <
probbit-cli/tests/stress/asymmetric-router32-w0.2-h0.06.json` -> `diagnostics_passed`, 32/32 released, `tv_bound` 0.001542,
`gate.worst.chain_means` 0.9972 / 0.9969 / 0.9969 / 0.9978 for worker A on every chain while the truth is P(A) = 0.1302. No
partial answers occurred on these inputs: every answer the gate let through was wrong. The external review's seeds 1..100 at defaults gave
12/100 (h = 0.03) and 14/100 (h = 0.06) whole answers, all false. R19.1 `#[ignore]`d the red tests; R19.2 un-ignored them (below).

**The external review's reproduction cases on the final build (R19.10, HEAD 8e6d15a, outcomes recorded, not asserted).** The review's three launch findings, same inputs and commands:
the wrong whole answer above is `exact` at defaults (tier occupancy, error 0.0), `diagnostics_passed` with error 0.0009
under `--mode sample`, and STILL a false `diagnostics_passed` (error 0.8686, `tv_bound` 0.001542) when every collective move
is turned off: the gate alone does not see it, the moves and the exact tier do. The silently ignored rule (`"allowed": "A"`)
and the invalid output JSON (a 1e303 weight) now exit 2 with one structured error (`schema` at `tasks[0].allowed`; `limit` at
`vars[0].h.1`). The review's 12 saved contract inputs: the 10 malformed ones exit 2 with an error object (1e309 at parse time
gives path `""` and the byte offset in the message), the 2 valid ones give the same plan as before.

**After the collective moves (R19.2, `--collective on`, the default from 0.2.0).** A global flip of every free two-value
variable and a swap of two value labels everywhere, each a symmetric involution with a Metropolis accept and every cap checked
(tests: incremental log-weight change = full recomputation on 4,356 random states; sampled marginals = enumeration on random
capped programs, worst max TV 0.0065). Same inputs, same commands, seeds 1..20, defaults and fixed work: **every family 20/20
`diagnostics_passed`, 0 false whole answers, 0 wrong released items** (640 released on each router input, 240 on ferro12 and on
each redundant-caps input, 2,000 on chain100). The external review's scale, seeds 1..100: h = 0.03 12/100 false (384 wrong) -> 0/100 false
(100 passed, 3,200 released, 0 wrong); h = 0.06 14/100 false (448 wrong) -> 0/100 false (3,200 released, 0 wrong), at defaults
and at fixed work (Apple M4, load ~11). `--collective off` reproduces the table above exactly. Cost: +0.3-1.2% per sweep on a
400-spin ring, +12.8-19.5% on ferro12 (12 variables: the flip is a large share of a tiny sweep), +14.9% on a 400-variable
3-colouring ring (label swap), fixed work, medians of 7-9 at load 5-8; at defaults (200 ms) the sweep counts of the 300-task demo,
asymmetric router and chain100 did not drop measurably (noise ±16% at load ~7).

**Holdout calibration (R19.4, P1.4; `bench/calibrate.py`, gate/3 thresholds frozen at commit 54c9a16 before the run).**
`python3 bench/calibrate.py --holdout --holdout-seed 20261001 --seeds 4 --per-family 5` (5 seeded programs per family,
brute-force oracle, `probbit run --op sample`, Apple M4, load 4-11): rare modes in two weakly bridged 6-spin ferro clusters:
**8 whole answers passed the gate, all 8 false (96 wrong released items)**, 12 refused; varying group sizes under a global
cap: 12/20 refused, 0 false; heterogeneous groups, 3-value constrained cycles, a 7-value alphabet: 20/20, 0 false. The
global flip maps the two clusters' (A,A) to (B,B) but never to (A,B), every chain stays in its pair of modes, and the gate's
statistics cannot see a mode no chain visits (assumption 1). With the Wolff cluster move (`--cluster on`, a diagnostic on the
same seed) rare-modes gave 20/20, 0 false. `--cluster on` became the default and was validated on the untouched seed
20261002: every family 20/20 whole answers, 0 false, 0 wrong, 0 refused; control, the same seed with `--cluster off`:
rare-modes 9/9 whole answers false (108 wrong), group-sizes 8/20 refused. No threshold was changed. The frozen corpus at the
new defaults (seeds 1..20, defaults and sampler-forced): 0 false, 0 wrong, 0 refused. Cost at defaults (median sweeps in the
200 ms budget, sampler forced, N = 5 alternating, load ~3): asymmetric router -20.4%, ferro12 -2.4%, 300-task demo -2.1%,
chain100 within noise.

**Harder holdout families + per-family table (R19.5, gate/3 unchanged, commit df33424).** Five new seeded families from their
own random stream (the R19.4 five reproduce their programs byte for byte): three 4-spin ferro clusters with one positive and one
negative bridge per cluster pair (`three-clusters-mixed`, 2 values); two 5-variable 3-value ferro clusters that both lean to
value c under a cap that lets only one be c (`rare-behind-cap`); 3-value ferro clusters of 3 / 3 / 4 with weak mixed-sign
bridges (`k3-clusters`); a 150-variable 4-value path with random tables, oracle = a log-space transfer matrix (`chain150-k4`);
an 8-value alphabet with two values capped at 1 (`alphabet-8-caps`). Untouched seed 20261004 (all 10 families x 5 programs x
seeds 1..4) + the frozen corpus (seeds 1..20); Apple M4, macOS, load 2.9-5.4, `--jobs 2`; `ms` = the answer's own `ms` (median over the row's
`runs`, one run each, no IQR; excludes process spawn); "sampler" = `--op sample` / `--mode sample` (the gate decides); a run counts as FALSE when an answer
called whole (`exact` / `diagnostics_passed`) has any variable more than 0.05 TV from the oracle.

| family (source) | runs | defaults: whole / FALSE / tier / median ms | sampler: whole / FALSE / released / WRONG / partial / refused / median ms |
|---|---|---|---|
| asym-h0.03 (corpus) | 20 | 20 / 0 / occupancy / 0.105 | 20 / 0 / 640 / 0 / 0 / 0 / 259.5 |
| asym-h0.06 (corpus) | 20 | 20 / 0 / occupancy / 0.105 | 20 / 0 / 640 / 0 / 0 / 0 / 259.3 |
| heterogeneous (corpus) | 20 | 20 / 0 / occupancy / 0.104 | 20 / 0 / 640 / 0 / 0 / 0 / 259.4 |
| ferro12 (corpus) | 20 | 20 / 0 / enumerate / 0.180 | 20 / 0 / 240 / 0 / 0 / 0 / 256.1 |
| ferro12-rc-w0.5 (corpus) | 20 | 20 / 0 / enumerate / 0.179 | 20 / 0 / 240 / 0 / 0 / 0 / 255.3 |
| ferro12-rc-w1.0 (corpus) | 20 | 20 / 0 / enumerate / 0.180 | 20 / 0 / 240 / 0 / 0 / 0 / 255.8 |
| chain100 (corpus) | 20 | 20 / 0 / forest / 0.052 | 20 / 0 / 2,000 / 0 / 0 / 0 / 259.6 |
| rare-modes (holdout) | 20 | 20 / 0 / enumerate / 0.138 | 20 / 0 / 240 / 0 / 0 / 0 / 258.6 |
| hetero-groups (holdout) | 20 | 20 / 0 / enumerate / 0.031 | 20 / 0 / 240 / 0 / 0 / 0 / 280.7 |
| constrained-cycle (holdout) | 20 | 20 / 0 / enumerate / 2.339 | 20 / 0 / 220 / 0 / 0 / 0 / 272.2 |
| alphabet-7 (holdout) | 20 | 20 / 0 / enumerate / 14.557 | 20 / 0 / 140 / 0 / 0 / 0 / 255.4 |
| group-sizes (holdout) | 20 | 20 / 0 / enumerate / 11.772 | 20 / 0 / 400 / 0 / 0 / 0 / 272.4 |
| three-clusters-mixed (new) | 20 | 20 / 0 / enumerate / 0.127 | 20 / 0 / 240 / 0 / 0 / 0 / 259.0 |
| rare-behind-cap (new) | 20 | 20 / 0 / enumerate / 1.365 | 20 / 0 / 200 / 0 / 0 / 0 / 267.8 |
| k3-clusters (new) | 20 | 20 / 0 / enumerate / 1.289 | 20 / 0 / 200 / 0 / 0 / 0 / 257.4 |
| chain150-k4 (new) | 20 | 20 / 0 / forest / 0.119 | 20 / 0 / 3,000 / 0 / 0 / 0 / 255.9 |
| alphabet-8-caps (new) | 20 | 20 / 0 / enumerate / 2.977 | 20 / 0 / 120 / 0 / 0 / 0 / 270.7 |

Control on the same seed with the moves off (`--extra "--collective off --cluster off"`, a diagnostic, not a tuning run):
three-clusters-mixed 20/20 refused, rare-behind-cap 20/20 refused, k3-clusters 13 whole / 6 partial / 1 refused (166 released),
0 false and 0 wrong in all three; chain150-k4 and alphabet-8-caps 20/20 whole as with the moves. So the three cluster families
are hard for single-site Gibbs, the gate refused instead of guessing, and the collective moves (global flip, label swap, Wolff
cluster) are what turns those refusals into correct whole answers. Commands, per-run records and the generated programs:
`python3 bench/calibrate.py --holdout --holdout-seed 20261004 --seeds 4 --per-family 5 [--families ...] --out FILE` (the
programs are written into the `--out` file). Seed 20261004 is now USED. What this allows: on these 17 families, at defaults
and with the sampler forced, no whole answer and no released item was outside 0.05 TV. What it forbids: reading it as
coverage of every multi-modal program; every family here is small enough for an exact oracle (k^n <= 2^20, or a chain), and
the three families that are hard for plain Gibbs here are (inferred, not measured move by move) hard in a way whole-cluster
flips or relabels undo. Modes that differ on part of a cluster, or that need several coordinated moves, are not represented.

**Final R19.5 holdout (commit 4970ebd, untouched seed 20261008, all 12 families x 5 programs x seeds 1..4, defaults and
sampler forced, Apple M4, load 6-9):** every family and mode 20/20 whole answers, 0 false, 0 wrong, 0 partial, 0 refused. Seeds 20261001..20261008 are USED.

**IR v2 constructs through the runner (R19.5, P2.1).** Family `v2-constructs` (7 variables x 4 values; an at-least cap, an
all_different, an implication, a forbid table, a precedence; oracle = brute force that checks each construct by its direct
meaning, not by probbit's cap lowering), untouched seed 20261007, 5 programs x seeds 1..4, Apple M4, load ~5: defaults 20/20
`exact` (enumerate, median 0.110 ms), sampler forced 20/20 `diagnostics_passed`, 140 released, 0 false, 0 wrong, 0 refused
(median 295.3 ms). What it forbids: reading it as coverage of large constructed programs; these are 4^7-state programs.

**FINDING (R19.5): precedence chains defeat the feasible-start search.** 20 jobs x 30 ordered slots, `all_different` +
19 chained `precedes` (j0 < j1 < ... < j19, gap 1; random unaries; lowered to 8,865 caps). The program is feasible (j_i = s_i),
but `probbit run` at defaults is `refused` after 15.2 s (15,178.9 / 15,178.6 / 15,245.4 ms, seeds 1..3, exit 3; the 200 ms
budget does not bound the bounded exact search's fallback) and `--op sample` is `refused` in 200.5 ms ("no feasible start found
within the search budget"). Never a wrong answer, but no answer either: pairwise forbid caps give the randomised depth-first
start search no forward checking along a chain, so an early job placed late leaves later jobs no slot. On the small
precedence test (4 jobs x 5 slots) the sampler is fine (5/5 `diagnostics_passed`, max TV <= 0.0015 vs brute force). Input: a generated
20-job x 30-slot chain (not in the repo). Fix direction (P2.1/P2.3): bound-propagating start search (or a precedence-aware start)
and a hard cap on the exact tiers' wall clock: the same input refuses in 7,739 ms with `--exact-ms 100` and in 200.5 ms with
`--exact-limit 1` (seed 1, N = 1); with `--sweeps 1000` (no decide fallback) 8,034.6 ms, and 759.3 ms with `--exact-ms 100`
added. So about 8 s is the exact tiers before the sampler (the enumeration's node budget, which `--exact-ms` bounds and
`--budget-ms` does not), and about 7 s is the decide fallback's exact search after no chain started, which neither flag
bounds.

**FIXED (R19.6)** by three mechanisms (Apple M4 16 GB, 1-min load ~6, seeds 1..3, N = 1 each): (1) an arc-consistent (MAC) start
search for programs whose two-variable forbid caps prune under root arc consistency; (2) under `--op decide` with a wall-clock
budget, the exact tiers before the sampler stop at `--budget-ms` when the raw space exceeds `--exact-limit`; (3) the no-start
fallback stops hard at the end of the sampling budget. Same input, defaults: 0.80 / 0.54 / 0.54 s wall (was 15.2 s), the
chains start (12,416-12,536 sweeps), verdict `refused` by the gate (tv_bound 0.168 > 0.05), and that refusal is honest: an
independent forward/backward chain DP over slots (log Z 16.892008) puts the worst item at
TV 0.0537 from the 200 ms sample. `--op sample`: `refused` by the gate in 341 ms (was `refused`, no start). More budget buys
the answer: `--budget-ms 1000` `partial`, 4 released, max TV 0.0073 vs the DP (2.49 s wall); `--budget-ms 3000`
`diagnostics_passed`, 20 released, max TV 0.0112 (7.39 s wall). What it forbids: reading this as fast mixing on long chains;
single-site moves cross a 20-job chain slowly and the gate says so.

**`--cycles on` default (R19.5, P1.4; gate unchanged).** An 11th family, saturated quotas (`saturated-k3`: 12 variables, 3
values, each variable allows 2, every value capped at 4 = n/3, so every feasible plan uses each value exactly 4 times and no
single-variable change is feasible; random unaries and weak tables). Seed 20261005, sampler forced: `--cycles off` (the R19.4
default) 20/20 **refused** (program 0, seed 1: `gate.frozen_saturated_caps` 3, all 12 variables escalated with `release_reason` frozen,
although 148,134 label swaps were accepted), 0 false; the
diagnostic `--cycles on` 16/20 whole, 0 false, 0 wrong, 4 refused (one program, every seed). `--cycles on` became the CLI
default, attempted only with k > 2 values and at least one cap (else byte-identical to off at fixed work). Validation on the
untouched seed 20261006 (11 families x 5 programs x seeds 1..4, Apple M4, load 6.9-14): every family 20/20 whole, 0 false, 0
wrong, 0 refused in both modes; control, same seed, `--cycles off`: saturated-k3 20/20 refused, the other ten unchanged
(20/20). Frozen corpus at the new defaults: 0 false / 0 wrong / 0 refused. Cost at defaults (median `gate.sweeps` in 200 ms,
N = 5 alternating, load ~6.5): 300-task demo -13.7% sweeps (the only one of the four inputs where the move runs). Seeds
20261005 and 20261006 are now USED. What this forbids: reading "0 refused" as "quota programs always mix": the rotation
connects states that differ by a 3-cycle of values; quota-saturated programs whose states differ only by longer cycles of
values within allowed sets are not represented here.

**Members forced by counting read as frozen (found R19.6, fixed R19.7; a false refusal, never a wrong answer).** Holdout seed
20261009, saturated-k3 program 3: four variables allow {a, c}, eight allow {b, c}, every value capped at 4 with n = 12, so the
four {a, c} variables are forced to a by counting (70 plans). The chains mixed (rhat 1.000005, tv_bound 0.0024) but every item
was refused with `release_reason` frozen: the rule read the cap on c (always 4 {b, c} occupants) as a saturated cap that never
changes hands and the four constant variables as stuck. Over the used seeds 20261005..20261010 (saturated-k3 only, 5 programs x
seeds 1..4 each): 8/120 sampler answers refused (2 programs x 4/4 seeds), 0 false. Fix (`probbit_ir::forced_values`, partition
programs, at most 64 tests per gate call): a variable that every chain held at one value a is tested with a forbidden; if the
capacitated matching (complete on partition programs: a proof) finds no plan, it is a constant like a clamp: not stuck, left out
of the class counts, a forced member of its caps. After (same seeds and programs, Apple M4, load 6.7-8.7): **0/120 refused**,
0 false, 0 wrong, 1,440 released. Controls: `--cycles off` on seed 20261006 still 20/20 refused, 0 false (a stuck variable that
is not forced still counts); untouched holdout 20261011 (12 families x 5 programs x seeds 1..4, load 8.4-14.8): 0 false, 0
wrong, 0 refused in both modes (5,380 released each); frozen corpus 0 / 0 / 0 (9,280 released, load 16-17). (That run's record
names commit bda5f4c: the change was not yet committed, the binary had it. An independent re-run on the committed R19.7 binary b962602
at the script's default seeds 1..20: 2,400 whole answers, 53,800 released, 0 false / 0 wrong / 0 refused; not re-run in R19.8.) Seed 20261011 is now USED. Tests: `stress_saturated_forced_by_counting_is_not_frozen` (un-ignored), `forced_by_counting_is_not_frozen`. What it
forbids: the same claim on non-partition programs (their budgeted start search proves nothing; they are not tested).

**Composition hazard (found R19.2, fixed).** Two moves that are each correct can cancel. With the opt-in Wolff cluster move
(`--cluster on`) attempted every sweep next to the global flip, both flipped ferro12 whole every sweep, so each chain's recorded
state stayed in one mode: `probbit run --op sample --sweeps 4000 --polish-ms 0 --cluster on --cycles on --seed S < ferro12.json`,
seeds 1..10: 8 refused and **2 false whole answers** (seeds 8 and 9, error 0.5). The cluster move is now attempted with
probability 1/2 per sweep (a random mixture of pi-invariant moves is pi-invariant): seeds 1..20, 20/20 `diagnostics_passed`,
0 false, on ferro12 and on the w1.0 redundant-caps input (`stress_ferro12_all_moves`). The default path (`--cluster off`) was
never affected.

What it lets us claim: the gate is a set of diagnostics with published counterexamples; `exact` and `infeasible` remain
proof-grade under the score model; these seven inputs are answered correctly at defaults. What it forbids: reading
`diagnostics_passed` as "within ±0.05" on any program with well-separated modes that the moves do not connect. The gate is
unchanged (it still measures error around the modes the chains visit); the collective moves remove these barriers (mirror
modes of two-value variables, label-permuted modes), not every barrier: modes that differ on a subset of the variables, or by
anything other than a global two-value flip or a label swap, can still be missed (R19 P1.2: mode-aware diagnostics).

**Mode-aware gate (R19.3, gate/3): what it adds and what it does not.** Every release now also needs the variable's own
indicator split-R-hat (half-chains, Bernoulli within-variance, values with pooled P > 0.02) below 1.05, and a whole answer needs
every variable's (`release_reason` `item_rhat`; `gate.item_rhat_max` / `gate.item_rhat_infinite`). It sees chains that hold
different values of a variable when their log-weight traces agree (symmetric modes), which the log-weight R-hat cannot: 8-spin
complete ferromagnet, +2.5 nats, moves off, 4 chains, seeds 1..8: every seed whose chains split has R-hat > 10.5 on every spin
and releases nothing (`item_rhat_sees_chains_split_between_symmetric_modes`). The indicator R-hat alone does NOT fix the table
above: with the moves off (`--collective off --sweeps 4000 --polish-ms 0`, seeds 1..20, `stress_gate_alone_moves_off`, load
~5) it gave the gate/2 counts, 2 / 3 / 2 / 3 / 3 false whole answers (h0.03 / h0.06 / heterogeneous / ferro12 / w0.5 redundant
caps; w1.0: 20 refused), every released item wrong: in those runs every chain sits in the same wrong mode (assumption 1). The
final gate/3 (with the never-moved rule below) changes one row: ferro12 0 false, 20 refused (its frozen chains never move a
spin; the rule now reaches programs without capacity constraints, which the code classifies as partition programs). The three
router inputs and the w0.5 input keep 2 / 3 / 2 / 3 false.
Cost on the night's oracle suites (same binaries before/after, Apple M4, load 4-8): `maxcut_oracle` (fixed sweeps,
deterministic) 144 runs, 61 passed, 929 released, 0 false, identical with the moves off and on (72 / 1,008 / 0); 1,000 iid fair
bits, 4 chains, seeds 1..50: 280 and 400 sweeps refuse (fewer than 8 long batches; the external reviewer's run on the 0.1.0 gate released
14,983 / 45,653 with 20 / 14 misses), 800 sweeps 50/50 whole, 50,000 released, 0 misses, identical. Wall-clock suites (run-to-run
noise), released before -> after, 0 false in every run: colouring 525 -> 525 (moves on 554 -> 554), scheduling 428 -> 428,
stuck_twins 188 -> 189 (moves on 262 -> 263), router_bench 3,111 -> 3,101 (one family-A4 run 375 -> 365).
(R19.5: the never-moved rule now escalates per connected component on partition programs too, not every variable; on
`router_bench` it changes nothing, family A 6/16 passed and 1,390 -> 1,380 released at wall clock, 0 wrong, because a router
program is one component through its caps; it only frees the moving parts of decomposable programs.)
The second gate/3 change, the never-moved test on partition programs (the router, and every program without capacity
constraints, e.g. max-cut and ferro12), costs one run: `router_bench` family A 7 -> 6
of 16 whole answers, 1,565 -> 1,370 released, 0 wrong before and after (the refused 200-task run was right: maxTV 0.0178). That
is the price of not being able to tell "certain" from "stuck" from inside a run. The third, the per-constraint occupancy-count
R-hat (members of a capacity whose load trace disagrees across chains are escalated), changed nothing further on these suites
(scheduling 428 -> 428; stuck_twins 188 -> 188; router_bench family A 1,375 released, 0 wrong); it exists for count modes that
per-variable indicators cannot see (a synthetic 7-vs-9-ones split: indicator R-hat < 1, occupancy R-hat infinite). None of the
three can see a mode no chain visits: `gate.mode_transitions` reports the accepted collective moves per run (the moves-off false
answer above reads 0 transitions on 4 chains).

**Gate cost at many chains (R19.7, P2.3 started).** The chain-disagreement check compared every pair of chains (O(chains^2)).
It now uses sign projections from 128 chains on (k <= 12; L1 diameter = max over 2^(k-1) sign vectors; equal to the pairwise
scan up to rounding, test `chain_disagreement_projection_matches_pairs`; default 4-chain runs keep the pairwise scan and their
bytes). Same binary, projection disabled vs enabled, `probbit demo --tasks 24 --seed 1 | probbit decide --mode sample --chains N
--seed 1` (Apple M4, load 8.6-10.6; N = 3 pairwise, 3-5 projection): 1,000 chains gate 93.2-94.4 ->
51.7-53.0 ms; 10,000 chains 6,463-6,495 -> 2,159-2,257 ms (one 4,321 ms outlier right after a rebuild). The rest of the
10,000-chain gate (~2.2 s) is other per-chain work (not profiled yet: e.g. one thread per chain in the frozen check); all runs
`refused` (the demo at 10,000 x a 200 ms budget is not mixed). Two-binary record (R19.6 b97a931 vs R19.7 b962602, same command,
interleaved, load 2.9-5.4; the maintainer's independent re-run, not re-run in R19.8): 1,000 chains gate 90.9-95.3 vs
46.8-55.1 ms (N = 5 each, medians 94.6 -> 54.0); 10,000 chains 6,508-6,553 vs 2,284-4,945 ms (N = 3: the gain was load-sensitive
while one thread per chain remained; fixed by the pool below).

**Gate cost at many chains (R19.8, P2.3 item 1 done).** Profiled (macOS `sample`, 10,000 chains): nearly all of the remaining gate
was thread create / map / unmap / teardown: the two batch-means passes and the frozen check each spawned ONE THREAD PER CHAIN.
They now run on a bounded pool (`probbit_ir::pool_map`, `--threads` workers; results combined in chain order, so every statistic is
bit-identical: test `gate_pool_is_bit_identical`, and old vs new binary give the same bytes at fixed `--sweeps` on 4 / 37 / 1,000 /
3,000 chains); the sign projections visit each chain once per variable (all signs) on the same pool, and the long-batch pass no
longer recomputes the disagreement it discarded. Two binaries (R19.7 b962602 vs R19.8 c1), same command as above, interleaved
OLD/NEW, Apple M4, load 6.2-7.2 (shared machine):

| chains | gate ms OLD (median, N) | gate ms NEW (median, N) | whole call ms OLD -> NEW | peak RSS MB OLD -> NEW |
|---:|---:|---:|---:|---:|
| 1,000 | 54.0 (51.4-56.1, 5) | 15.9 (12.2-28.5, 5) | 307.1 -> 269.9 | 101.6 -> 50.6 |
| 10,000 | 2,255.7 (2,224.1-4,814.1, 5) | 15.8 (15.4-16.2, 5) | 2,537.3 -> 300.7 | 840.4 -> 368.2 |
| 100,000 | no answer in 90 s (1) | 88.5 (83.7-89.3, 5) | > 90,000 -> 583.0 | n/a -> 356.3 |

What this allows: thousands of chains no longer pay seconds of gate. What it forbids: reading `--budget-ms` as a deadline at
100,000 chains: the SAMPLING phase dominates there (R19.8: 448 ms median for a 200 ms budget). Profiled in R19.9 (macOS `sample`, 1 s at
1 ms): chain builds and starts (`Chain::new` + the feasible start) ~29% of the sampling samples, sweeps the rest: each chain timed its own
budget / 25,000 = 8 us slice and read the clock every 8 sweeps, so overruns were never charged to the next chains. Router `sample_on` now
gives the r-th chain of a worker the deadline call start + (r + 1) slices (same chains, same output shape): sampling 431.5 [353.4-453.1]
-> 269.4 [255.3-282.6] ms, whole call 571.9 -> 405.2 ms (two binaries interleaved, N = 5 medians, load 3.5-3.6;
both `refused`; 4 chains unchanged: 200.1 ms both). These numbers move with the machine's load: the orchestrator's interleaved
re-check (N = 5, load 4.2) read sampling 353.6 -> 318.4 ms and call 497.8 -> 459.9 ms, so the honest statement is a range: sampling
old 354-432 ms -> new 269-318 ms, call 498-572 -> 405-460 ms (medians of N = 5, loads 3.5-4.2). At 100,000 chains on 200 ms NO chain
sweeps in the new build: `telemetry.sweeps` is 0 (all 5 R19.9 runs and 2 R19.10 checks at load 4.1): the answer is the 100,000
feasible starts, which the gate refuses (the old build's overrunning slices did sweep: 60,000-306,896 sweeps in total). The ~70-120 ms
over the budget are the 100,000 builds themselves: not removable without fewer chains. Gate at 100,000 chains across runs: 84.5-100.1 ms (R19.8 / the maintainer's
re-run, loads 3.0-10.0; 89.3 ms in the R19.9 profile run). Every run in the table is `refused` (this demo at a 200 ms budget is not mixed at any of these
chain counts); the default 4-chain runs are byte-identical. The pool's width barely matters: at 10,000 chains `--threads`
1 / 4 / 8 give gate 18.2 / 14.5 / 15.0 ms (N = 5 medians, load 3.0-3.2, final R19.8 binary),
so the gate's statistics are cheap even on one thread and the old seconds were the thread churn. The IR front-end shares the
gate: `probbit run --op sample --chains 10000 --seed 1` on the stress program ferro12, old vs new binary interleaved, N = 3, load
7.7-8.2: gate 2,138.2 -> 4.6 ms, whole call 2,405.0 -> 281.4 ms (medians; `refused` both).

## §6 Where it loses
- CPU cap: `--cpu-limit 25` kept the CPU share under the cap but spent 4.1x the CPU for the same work on a 2,000-spin ring
  (earlier build); on the router it cost +11% (5.7), so the price depends on the program. To share the machine cheaply, lower `--threads` first.
- Priority: `--priority low` costs 4.2x wall on an idle Mac (5.4).
- One thread: `--threads 1` gives a 2.65 log w worse plan at the same wall time on the 300-task demo, since the polish now obeys it (5.8).
- Memory cap: at 2 MB on the hard 300-task demo, 61 fewer tasks were released (5.3).
- Tiny inputs (`bench/tiny_exact.py`, N = 7): on the 12-task demo, exact enumeration of all 180,540 feasible plans takes
  7.30 [7.29-7.32] ms. The forced sampler takes 273.6 [271.2-276.8] ms (x37) and is only approximately right (certified 7/7,
  max TV 0.0019 vs exact). This is why `probbit decide` runs the exact tiers first. Re-run on the final build (R19.10, N = 7, load
  5.9): 8.16 [8.08-8.20] ms exact vs 278.2 [277.9-279.2] ms sampled (x34), 7/7 `diagnostics_passed`,
  max TV 0.0019.
- Small-group exact inputs since R19.9 (R19.10 FINDING): the enumeration's per-(group, worker) mate counts and affinity memo,
  which took the near-saturated 3,000-task group from 199.9 s to 2.7 s, cost 5-22% on programs with small groups, where the old
  per-node loop touched at most a couple of group mates. Old binary (e97c9b4, before R19.9) vs new, `probbit decide` at defaults, interleaved, N = 9 medians
  [IQR], load 4.8, same answers: 12-task demo 7.167 [7.122-7.301] -> 8.009 [7.983-8.056] ms (+11.7%);
  12 `--hard` 7.229 -> 7.987 ms (+10.5%); 24-task (answered by the frontier tier; the enumeration runs and declines first *(inferred)*) 26.54 -> 27.97 ms (+5.4%). Under `--mode exact`
  (full enumeration, where the per-node cost dominates) the gap is larger: 14-task demo 1,455.1 [1,453.4-1,456.5] -> 1,773.3
  [1,769.3-1,784.2] ms (+21.9%, N = 5 interleaved, load 3.5-3.6, same answer). A macOS `sample`
  profile puts all of both binaries' time in the inlined `Ex::dfs`; hypothesis *(inferred)*: per candidate the new code reads
  `cnt`, `mlen`, `moff` and `memo` where the old one scanned at most two mates. The
  sampled path is unchanged (30 / 300 tasks: 293.8 / 306.4 -> 293.7 / 309.5 ms, N = 7, load 3.3-3.7). Not fixed: a size switch
  (the direct fold for small groups computes the same sequential sum, so it should stay bit-identical *(inferred)*) is next-wave work.
- Sudoku (§4): DFS backtracking does the same exact job 15-102x faster per puzzle (medians 17x open, ~50x unique), and the sampler refused all 20 generated puzzles (in the current build a puzzle that naked singles solve is certified: every cell is forced).
- Max-cut (§3): simulated annealing finds better cuts at equal time on both Gset-like shapes (by 7 and 4 cut edges against probbit's
  anneal-only mode, by 20 and 10 against its sampler).
- Router, single best plan (§2.2): an ILP solver (HiGHS) proves the optimum on 300 tasks in 52-352 ms (three runs) and was faster than
  probbit's default path on 5 of the 6 queues tested; probbit's plan is 0.45-2.0 nats short over three runs (9.3-9.7 on `--hard`). If you only need one plan, use an ILP/CP-SAT solver
  (or greedy+polish, which beat probbit's plan at equal time on all 8 runs at 300 tasks, §2.2).
- Scheduling, single best plan (§4.3): HiGHS proves the optimum of three 200-job programs in 0.68-0.95 s; probbit's plan is
  3.3-4.3 nats short at 2 s and 5 s budgets, and at 5 s it releases 156-173 of 200 jobs on two programs and none on the third.
- Router, coverage (§2.1): over 16 oracle queues 51% of tasks were released on the current gate (58% on 0.1.0; re-run R19.10,
  where one more queue, A4 seed 7012, released nothing although its odds were within 0.018). Nothing was released on saturated queues (every
  worker full; 2 of 4 refused although their odds were within 0.018) or on strong-affinity ones (3 of 4 rightly, odds off by 0.16-0.44;
  one needlessly, 0.041). Mid-size thin queues (30-36 tasks) are sampled at ~0.3 s although a larger
  frontier cap answers them exactly in 41-104 ms (§2.3).
- Scheduling (4.3): on a 200-job precedence schedule the sampler's start takes 0.7 s (it gave up after 105 s in an earlier build) and
  at 1 s of budget the gate refuses; 5 s gives 153-171/200 released on 3 instances since the ~0.7 s start was moved inside the
  budget (181-186 before; unchecked, no oracle). The gate runs after the budget: a 5 s budget returned after 5.91-6.01 s and a
  1 s budget after 1.06-1.19 s on this program (one run per instance). Through the CLI
  (`probbit run --op decide --budget-ms 1000`, the same program as a 5.3 MB probbit-ir JSON; one run each): the binary from
  before the start search got its work budget and retries gave no output within a 45 s alarm; after that change 3.39 s wall, `partial`, 2 of 200 released, 0 violations,
  R-hat 1.00187 (sample ~1.75 s including the starts, gate 210 ms). The other ~1.2 s was the exact tier declining: `--op sample` (no exact tiers)
  took 2.13 s vs 3.33 s for `--op decide`; parse + build is ~0.09 s (`--op sample --sweeps 1`: 0.85 s wall, 0.76 s of it the
  start); `exact()` declined after 1,154 ms at limit 1 and 1,155 ms at limit 2M. A profile showed that the MRV
  enumeration spent 1.66 G capacity checks (19,564 dead ends) finding its FIRST plan, then produced 2M plans in 32 ms. It now
  declines after max(64 x limit, 1e8) checks without a new plan (every answering sudoku / colouring / scheduling oracle run needs
  <= 5.1 M between plans; their exact answers are unchanged): `exact()` declines in 75 / 96 ms at limit 1 / 2M (medians, N = 5),
  and `probbit run --op decide` takes 2.21 s vs 2.12 s for `--op sample` (N = 5 each). Then a later change put the chains' start search
  inside the budget (the docs already promised a deadline for the sampling phase): 1.29 s wall (median of 5, load ~10 from other
  processes; sampling 1,004 ms, gate 38-45 ms), but at this budget the verdict is now `refused` (it was `partial`, ~2 of 200
  released): less sweeping. Precedence costs O(T^2) pair caps per edge (82,678 caps at 200 jobs).
  A single greedy + repair is 0.4-2.5 ms; and it hit dead ends on 6 of 20 tight small instances.
- Also lost or refused (measured, collected in a review pass): colouring: the exact tier is faster than the sampler on every
  instance and 3-colourings (k = 3, n = 14) are mostly refused (59 of 82 over 6 sets after the stuck-chain rule change, all before; §4); max-cut at coupling 1.5 with 500 sweeps released nothing (§3);
  one 100-job schedule with 6 frozen capacities is refused even at 5 s (4.3); an unstartable 200-job program took 0.666 s (measured before the exact-search fallback was added) to
  answer `refused` at a 500 ms budget (4.3); `--progress` costs up to ~8% on tiny programs (5.2); the exact-tier gap budget
  cost 1-4% on sudoku counting (§4) and 18-21% on 3-colouring infeasibility proofs (5 instances, median of 3
  alternating runs); a later change precomputes the per-variable count (same count, same answers): now 2-5% slower than the engine before the gap budget on those proofs
  and 12-16% faster than the first gap-budget engine.
- Proofs of infeasibility (`bench/csp_gap_probe.py`, 3 runs per binary): the exact-tier gap budget made `probbit run
  --op decide` answer `refused` (exit 3) in 0.33-0.35 s on 5 of 5 infeasible random 3-colourings (150-200 vertices, mean degree
  4.6, one edge clamped) that the binary from before the gap budget proved `infeasible` (exit 1) in 0.13-4.3 s (medians 0.126 / 0.190 / 0.247 / 1.835 /
  4.277 s). `--op exact` still proves them (0.15-5.1 s). Safe (no false answer) but a lost proof; the refusal reason now says so.
  Partly fixed in the current build: under `decide` with a wall-clock budget each chain's start search stops at half of its slice of the budget
  (`--budget-ms` / ceil(chains / threads)) and, when any chain finds no start, the samples are dropped and the exact search runs
  again to the budget's end. Same probe (NS=150,200, one run each): 1 of the 3 proofs that take
  0.13-0.27 s comes back `infeasible` at `--budget-ms 500` (0.485 s), 3 of 3 at 1000 (0.73-0.88 s); the 1.9 / 4.4 s proofs are
  refused on budget (1.007 s; in an earlier build a refusal overran the budget by ~110 ms: 612-618 ms at 500, 6 runs each). A first version
  that gave the exact search the FIRST half of the budget recovered more proofs (2 of 3 at 500) but cost feasible programs
  sampler time (200-job schedules at 5 s: 174 -> 97 released, and 157 -> refused); the fallback costs them nothing (173 / 157 vs
  170 / 157, N = 1 each). `--op sample` and `--sweeps N` keep the work-only bound (refused).
- The exact tier is outside `--budget-ms` (`probbit run --budget-ms 200`, loose random 3-colourings from
  `bench/csp_gap_probe.py`'s generator at mean degree 2, seed 7, 1-2 runs each): on a program with more plans than `--exact-limit`
  (2M) the tier enumerates until it has counted `--exact-limit` + 1 plans, then declines, and every plan resets its gap budget. `--op decide` took
  0.44 / 0.71-0.75 / 1.62-1.70 s at 300 / 1,000 / 3,000 variables vs 0.29-0.35 s for `--op sample` on the same programs (all
  `refused`): up to 8x the budget, growing with the size. Bounding it by the clock would also turn exact sudoku answers (0.11-8.1 s
  at the default budget, §4) into sampler refusals; the default is not changed (decision for the maintainer). Opt-in in the current build:
  `--exact-ms N` stops the exact tiers that run before the sampler N ms into the call (re-run after a parsing fix, same programs, 5 runs each,
  interleaved, CLI wall, medians [IQR]): `--op decide` 430 [430-430] / 699 [699-699] / 1,480 [1480-1480] ms -> 341 /
  347 / 346 ms at `--exact-ms 50` and 291 / 295 / 296 ms at `--exact-ms 0`, vs 292 / 296 / 296 ms for `--op sample` (verdicts unchanged:
  refused; in a first run, before the parsing fix: 438 / 711 / 1,530 -> 342 / 352 / 384, sample 292 / 302 / 334).
  On the 300-task router demo (`probbit decide`: 305 ms vs 264 ms with `--mode sample`) the exact tiers add ~41 ms *(inferred from
  the difference)*, so `--exact-ms 50` changes nothing there. One router group of 3,000 tasks
  (`probbit decide` at the default 200 ms budget, 1 run each, machine load 5-8) took 7.55 s wall at 1,159 MB peak RSS (5,000 tasks: 12.77 s,
  1,895 MB; both `refused`), ~37x the budget: ~7 s is the enumeration counting toward `--exact-limit` (`--exact-limit 0` 0.59 s,
  `--exact-ms 0` 0.44 s, `--mode sample` 0.46 s). R19.8 FINDING (worse shape, N = 1, load 3.7-5.9): one NEAR-SATURATED group of
  3,000 tasks (6 workers, caps 550 = 3,300 slots, affinity 0.01, random scores in [-1, 1]; generator in lab cycles/R19.8-c02)
  took 199.9 s by default before `refused` (macOS `sample`: all of it in the router enumeration `Ex::dfs`). Cause (read from the
  code): the node budget is 64 x `--exact-limit` = 128M nodes, but each node sums the affinity over every group mate (O(group
  size)), and near saturation the bottom of the tree has one open worker, so each new plan re-descends hundreds of levels.
  `--exact-ms 50` answers in 0.74 s. Same generator, default decide, N = 1, load ~3: 500 tasks
  at 63% fill 1.26 s; 1,000 at 77% fill 2.83 s; 1,000 at 91% fill (cap 184) 19.76 s; 2,000 at 91% (cap 367, load 4.8) 93.98 s: near-saturation drives
  it, and at ~91% fill the time grows faster than linearly with group size (19.8 / 94.0 / 199.9 s at 1,000 / 2,000 / 3,000). FIXED in R19.9, bit-identical: the enumeration keeps per-(group, worker) counts of
  assigned mates (push / pop with the search) and a per-(task, worker) memo of the SAME sequential affinity fold, so every node costs
  O(workers) instead of O(group size); every addend is the same affinity, so the sum depends only on the count, never on the mates'
  order. `GOLDEN_EXACT` / `GOLDEN_GATE` unchanged (no re-pin); test `enumeration_affinity_memo_is_bit_identical` (240 random programs vs
  the old enumeration, every bit, also with the memo capped); old vs new binary, timing fields removed, same answer at `--sweeps 50
  --polish-ms 0` on 6 inputs (demo 12 / 24 `--hard`, demo 24, demo 300, the 500- and 1,000-task groups) and on the 3,000-task group (default `--exact-limit`: old 205.4 s, new 5.2 s, final binary;
  and at `--exact-limit 1`). Default `probbit decide`, Apple M4 16 GB, wall s, N = 5 medians [IQR] (old and new
  interleaved, the final binary re-timed alone right after):

  | one group, 6 workers, affinity 0.01 | fill | old (e97c9b4) | new (R19.9 c1) | load |
  |---|---|---|---|---|
  | 500 tasks, caps 133 | 63% | 1.141 [1.139-1.147] | 0.294 [0.293-0.296]; final 0.295 | 6.4-6.8; 2.4 |
  | 1,000 tasks, caps 216 | 77% | 2.557 [2.548-2.576] | 0.379 [0.368-0.379]; final 0.386 | 5.8-6.4; 2.4 |
  | 1,000 tasks, caps 184 | 91% | 19.630 [19.581-20.243] | 0.706 [0.695-0.720]; final 0.731 | 3.9-5.9; 2.4-2.6 |
  | 3,000 tasks, caps 550 | 91% | 199.9 (N = 1, R19.8); 205.4 at `--sweeps 50` (N = 1, R19.9) | 2.693 [2.681-2.703]; final 2.702 | 3.7-3.9; 2.5-2.6 |

  Every run is `refused`, before and after (the sampler does not mix these groups in 200 ms). Peak RSS is within run-to-run noise, not a regression:
  1.65-1.96 GB on the 3,000-task group for BOTH binaries (R19.9 read old and new 1,953-1,957 MB at `--exact-limit 1 --sweeps 50`; the
  orchestrator's re-check read new 1,721 vs old 1,957 MB there and new 1,646-1,709 MB at default `decide`: about ±250 MB run to run on
  either binary). The memo arena is <= 128 MB by construction (one flat arena of at most 2^24 f64 entries, past which the fold
  continues unstored). What this allows: default `decide` on big near-saturated groups in seconds without `--exact-ms`. What it forbids: reading
  2.7 s as the budget: the enumeration still walks its whole node budget (64 x `--exact-limit` nodes) before declining; macOS `sample` of the
  final binary on the 3,000-task group (2 s at 1 ms): `Ex::dfs` 1,244 samples, then the sampler's per-site loops over every group mate
  (`Chain::site` 323, `Chain::pair_e` 167, `Chain::cycle3` 148: O(group size) per site update, the second O(G) loop, NOT fixed: they cost
  sweeps within the budget, not wall time). (An apparent run-to-run difference of that answer was the
  `telemetry.nice` echo: zsh ran a background job at nice 5; at equal niceness the answers match bit for bit.) `--mode exact` on that group has no plan cap (u64::MAX / 128) and ran > 3 min in
  `Ex::dfs` before it was stopped: `--exact-ms` is the control there. R19.8 also stopped the router lowering from running outside its use: `--mode sample` on that
  group 884.6 -> 618.3 ms, `--exact-ms 0` 885.6 -> 614.9 ms, `--exact-ms 50` 898.1 -> 741.0 ms (two binaries interleaved, N = 5
  medians, load 7.4-8.1; outputs byte-identical at fixed `--sweeps` on 5 configurations). Without the
  flag the output is unchanged (A/B vs the binary from before the flag, timing fields removed: 13 of 14 cases identical; the 14th, a wall-clock
  sampler run, differs by timing only and is identical at fixed `--sweeps`). What this allows: bounding the
  exact tiers' extra wall time on large loose programs. What it forbids: expecting exact answers from a cap shorter than the
  program's exact time (a capped exact tier declines; `decide` then samples). Kill test: the cap swept
  across the exact time of 5 programs (two 3-colouring infeasibility proofs of 186 / 238 ms, a 7,159,296-plan colouring answered
  in 2.19 s, the router demo at 13 / 11 tasks under `--mode exact`) and the 11-task demo under `--mode auto`: 165 capped runs, 0 wrong. Every exact-mode run
  (155) gave the uncapped answer (identical, timing removed) or declined; no partial sum and no unfinished proof came out labelled exact
  or infeasible, including caps that stop the second enumeration pass (1.1-2.2 s on the 7.16M-plan colouring). Under `--mode auto`,
  the 10 capped runs answered from the sampler with `exact_ms_reached: true` (later check: 10 such runs, seeds 1-10, against the
  exact odds: 110 released tasks, max TV 0.0023, same most likely worker for every task).
  The tradeoff in one program (1 run each, `probbit run` default op): the Wikipedia sudoku as an IR program is `exact` in
  18-38 ms with or without `--exact-ms 100`; with rows 7-9 cleared (502,260 solutions) the default answers `exact` (full count +
  per-cell odds) in 4.53 s, and `--exact-ms 100` answers `refused` (sampler, 0 released) in 0.41 s.
- The plan polish overran `--polish-ms` on huge grouped router inputs (found and measured in an earlier build, `--budget-ms 500`, 100,000 tasks in
  groups of 4: 2.71 s wall at the default `--polish-ms 50` vs 0.68 s at `--polish-ms 0`; 8.38 s at `--threads 1`; `--polish-sweeps 1`
  4.66 s). FIXED in the current build. The cause was not the per-temperature chain builds (an earlier reading of the code; profiled: ~20 ms
  each) but the plan score `Problem::logw`, which tested every pair of tasks for a shared group (O(t^2), ~2 s per call at 100,000
  tasks), run once per polish chain before its clock and once per sweep. It is now linear above 96 tasks (the pairwise loop stays up to 96, where it is faster; it is still 2-4% faster per polish sweep at
  100-110 tasks; R19.8 timed the two paths per call, `examples/logw_threshold.rs`, 6 workers, groups of 4 / 8, median of 7
  alternating rounds, load ~8.6: linear / pairwise = 1.52 / 1.25 at 96 tasks, 0.96 / 0.92 at 128, 0.97 / 0.68 at 160, 0.78 / 0.63
  at 192, 0.53 / 0.51 at 256: the crossover is between 96 and 128, so the threshold stays at 96 and raising it to 150-200 would cost) and bit-identical (test), and the polish
  stops building chains once its time share has passed. Old vs fixed binary, same input shape, `probbit decide --mode sample`, default `--budget-ms 200`,
  3 runs each (machine load 5-8): time after sampling 2,039-2,041 -> 82-86 ms (4 threads), 7,868-7,871 -> 102-109 ms (`--threads 1`)
  (re-run on the final binary, 5 interleaved runs, load ~3, median [IQR]: 2,038 [2,037-2,038] -> 86 [85-86] ms; 7,745 [7,736-7,777] ->
  105 [103-105] ms);
  `--polish-sweeps 1` 4.19 -> 0.34 s; fixed-work outputs identical on 6 inputs; on the 300-task demo the polish does 1.5-1.6x more
  sweeps per second, so at equal wall time its plan is better on 5 of 8 seeds (`--hard`: 7 of 8). What this allows: `--polish-ms`
  as a near-deadline on this shape (32-59 ms over at 50). What it forbids: calling it a hard deadline (each polish chain builds at
  least one chain before its first clock read).
- Very many chains (R18 record, before R19.7-R19.8): the gate grew about quadratically with `--chains` (pairwise chain
  disagreement + one thread per chain) (30-task demo, `--mode sample`, 1 run each): 64 / 1,000 / 10,000 chains took gate
  10 / 103 / 7,488 ms; 100,000 chains gave no answer within 20 s. FIXED for the gate ("Known failure modes", "Gate cost at many chains (R19.8)":
  24-task demo, 10,000 chains 2,255.7 -> 15.8 ms, 100,000 chains answer in 583 ms, N = 5). Still losing: at 100,000 chains the
  sampling phase overruns a 200 ms `--budget-ms` (R19.8 448 ms median; R19.9 per-worker deadlines: old 354-432 -> new 269-318 ms,
  medians of N = 5 in two interleaved runs at loads 3.5-4.2, see "Gate cost at many chains"; the rest is the per-chain build every
  chain needs, ~11 us each on 4 workers). At 100,000 chains on 200 ms no chain sweeps at all (`sweeps` is 0 in the output): the
  answer is the starts, which the gate refuses. The IR sampler
  still gives each chain its own slice: `probbit run --op sample --chains 100000 --seed 1` on the stress program
  ferro12-w0.5-redundantcaps samples 284-345 ms on the default 200 ms (R19.9: 284.0-309.9 ms, N = 3, load 4.7-5.0; orchestrator
  re-check: 334.8-344.6 ms, N = 3, load ~4; not profiled). So
  `--budget-ms` is not a deadline there; `--deadline-ms` (`probbit run`) is the whole-call control. The Windows many-chain overrun
  is unmeasured here. The defaults (4 chains) are not affected.
- Not measured: CP-SAT (OR-Tools is not installed here), ILP with per-task odds (it has none), Linux/x86-64 numbers for any table,
  an ILP baseline for scheduling above 200 jobs (4.3 has 200-job programs only).

## §7 The QUBO hand-off vs the native sampler (re-run of `cargo run --release -p probbit-decide --example hardware_lowering`, N = 1)
One run on 3 router instances (seeds 7 / 11 / 13), each lowered to a 34-bit one-hot QUBO with slack bits (165 couplings; the
energy of every feasible plan equals -log w exactly, acceptance test `ir_round_trip_and_lowering_exact`). Every sampler gets 20 ms
of wall clock on this CPU; TV is against the exact odds, over the feasible samples only. Single run per sampler and seed
(N = 1): every cell is that run's value, with no median or IQR (no repeat was run), so small differences between
neighbouring cells are not separated from run-to-run noise.

| sampler | infeasible samples (seeds 7 / 11 / 13) | TV on feasible samples (7 / 11 / 13) |
|---|---|---|
| native constraint-preserving Gibbs | 0 by construction (36,800 / 98,240 / 100,352 samples) | 0.0049 / 0.0018 / 0.0019 |
| p-bit Gibbs on the QUBO, penalty 0.5 | 100.0% / 100.0% / 100.0% | 0.2249 / 0.1094 / 0.0452 (1-10 feasible samples) |
| penalty 1 | 99.5% / 99.4% / 98.9% | 0.0166 / 0.0160 / 0.0121 |
| penalty 2 | 87.8% / 90.3% / 82.4% | 0.0076 / 0.0036 / 0.0019 |
| penalty 4 | 24.5% / 37.0% / 19.9% | 0.0111 / 0.0128 / 0.0072 |
| penalty 8 | 0.7% / 0.8% / 0.4% | 0.0698 / 0.1664 / 0.0457 |
| penalty 16 | 0.0% / 0.0% / 0.0% | 0.1612 / 0.2325 / 0.0912 |

Claim: on these instances the native sampler keeps every rule by construction at TV 0.002-0.005. The QUBO form matches that
accuracy on its feasible samples only at penalty 2-4 (seed 13 at penalty 2: 0.0019, equal), where 20-90% of its samples break a
rule and must be thrown away; at the penalties that keep over 99% of samples feasible (8-16) its TV is 0.05-0.23. Not claimed: anything about
p-bit, FPGA or annealing hardware (none was run; their penalty tuning and embedding are unmeasured), or instances beyond 34 bits.

## §8 Live and bounded learning (`python3 bench/live_learning.py`, stdlib, 2 min 50 s; probbit 0.7.0)
The shipped tutor (`examples/persona/tutor.yaml`: 9 traits, 7 habits) plus the learning block that `--demo week` adds (praise and
criticism move the learned deltas of verbosity and humour; rate 0.5, step_cap 0.2, total_cap 1), driven through
`probbit live --clock fixed` one event at a time, events 1 h apart. Deterministic: two runs on a development build and one on
0.7.0 gave the same counts, odds and distances; the times moved a little (live 4.49-4.57 s, verify 3.26-3.29 s). Load average
about 2 during the runs.

**8.1 An adversary that wants jokes on failures** (10,000 turns per seed, seeds 0-9: 100,000 turns). Every third turn reports a
failure (`loss`; the habit `no_jokes_on_loss` holds humour at none and emoji at most sparse); every turn judges the stance before
it: praise for a joke (humour light or playful), criticism for none, the none a failure forces included. "No learning" is the same
individual (same seed, same genes) of the shipped tutor on the identical events.

| measure | seeds 0-9 |
|---|---|
| rule breaks (habit violations the stance reports) | 0 in 100,000 turns |
| failure turns; humour above none on them; emoji above sparse on them | 33,330; 0; 0 |
| learned humour deltas at the cap (±1) | from turn 8-26, through turn 10,000 |
| P(joke) off failure turns, turns 9,001-10,000: learner vs no learning | 0.835-0.994 vs 0.457-0.970 (gain 0.02-0.38) |

Seed 2 over time, P(joke) off failure turns (no learning in brackets): turns 1-10 0.670 (0.460); 11-30 0.842 (0.468); 31-100 0.834
(0.454); 101-10,000 0.835-0.836 (0.456-0.458). Its humour deltas: [-0.87, +0.97, -0.09] at turn 10, [-1, +1, -0.24] at turn 30,
[-1, +1, -1] from turn 300 on. The level that gains is the one the individual took: light for seed 2, playful for the other nine
(the update credits the stance's level, docs/persona.md §2.8). The gain is small where the individual already joked 95% of the time.

**8.2 Strand and verify** (seed 2's 10,000 events from a file, N = 3): a 3,055,367-byte strand; `probbit live` 3.46 s with `--seed`
(2,890 events/s), 4.49 s with `--state` (the state file rewritten after every event); `probbit live verify` 3.26 s (3,067 events/s),
ok. The strand written from the events file equals the one written while the adversary drove the run, byte for byte.

**8.3 Identity: how far learning moves an individual.** Learners of seeds 0-19 after 200 and 2,000 adversarial turns, then a quiet
1,000 h and a feedback-free probe script of 27 events (a quiet turn and each input alone, three times); distance = mean
total-variation distance of the stance odds over turns and traits (as `persona diff`), to the learner's own initial individual and
to the other 99 initial individuals of seeds 0-99.

| total_cap | turns | distance to its own initial self, mean (max) | its own initial self is the nearest of the 100 | siblings as near or nearer, worst learner |
|---|---|---|---|---|
| 1 (the demo's) | 200 | 0.0793 (0.0935) | 11 of 20 learners | 4 of 99 |
| 1 | 2,000 | 0.0793 (0.0936) | 11 of 20 learners | 4 of 99 |
| 0.25 | 2,000 | 0.0230 (0.0263) | 20 of 20 learners | 0 of 99 |

For the seed-2 learner at total_cap 1 the nearest sibling is at 0.0769 and the median one at 0.1658 (the test
`learning_moves_an_individual_as_far_as_its_cap` in `probbit-cli/src/live.rs` prints both).

**8.4 `--demo week`** (`probbit live examples/persona/tutor.yaml --seed 2 --demo week --plain`, N = 5): 0.023 s [0.022-0.024], 50
events, a 21,361-byte strand that verifies; its last line's sha256 is f713b1a7…4dbe4ba on 0.7.0 (the header names the engine
version, so each version writes its own). The paced version at a terminal (bars on stderr, 1 s per hour, each night in 2 s): 56.1 s
of wall clock end to end under a pseudo-terminal (`script`, 150 x 40, N = 1, development build), 98 redraws, the same strand.

Claim: on the tutor with this block, 100,000 adversarial turns broke no rule and put no joke on any of the 33,330 failure turns,
while the learned humour deltas reached their cap within 8-26 turns and raised the odds of a joke on the other turns above the same
individual's without learning; how far learning moves an individual is set by its cap, not by how long it is taught (200 and 2,000
turns: the same distance); a 10,000-event life replays and verifies in about 3.3 s. Not claimed: anything about personas, habits or
learning blocks not run here (the rules hold because a habit is a rule of the program and the learned deltas are unaries, §2.8;
these runs measure that design on one persona, they do not prove it beyond what `prove` proves); that an individual stays nearest
its own initial self at any cap (at the demo's cap, 9 of 20 learners have a sibling as near or nearer); other machines.
