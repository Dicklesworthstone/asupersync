# ATP-rq "beat rsync" — negative-evidence ledger + experiment designs

> Discipline from `/running-the-gauntlet-on-your-rust-port`: every perf hypothesis gets an
> experiment-design entry (hypothesis / minimal-repro / expected-signal / falsifiability /
> one-line-invocation / result-inline). Every REFUTED candidate gets a negative-ledger entry with
> a **retry-condition predicate** (never "later", never "if it seems important"). Grep this file
> BEFORE re-chasing a lever. Keep-gate: profile-first, both gates same run window, report cv_pct,
> attribute to a frame ≥0.1% self-time, isomorphism proof per change.

Reference benchmark (cross-machine OVH 16c → Contabo 10c, 100M, sha-verified):
rsync(tuned)=8.44s · baseline atp-rq(scalar,serial)=164.75s · F3(parallel encode)=113.85s.
Target: ≤ rsync on clean; FASTER under loss/high-BDP.

---

## CONFIRMED FACTS (positive evidence)

- **F-POS-1 · Systematic fast path EXISTS and is correct.** `DecodingPipeline::try_decode_block`
  (src/decoding.rs:664) calls `try_complete_from_source_symbols` first; if all K source symbols of
  a block are present it reassembles by **memcpy** (decoding.rs:736-754) and never runs the O(K²)
  `decode_block` inactivation solve. The solve runs ONLY for blocks missing source symbols.
  ⇒ Implication: clean, loss-free delivery of source symbols = near-memcpy receive. The slow path
  is entered only when symbols are DROPPED.
- **F-POS-2 · F3 parallel per-block encode landed** (commit 4c665fe6a) — 164.75→113.85s (1.45×),
  byte-identical. Removes the *sender* single-core encode wall (CPU 99%→125%).

## REFUTED / NEGATIVE (do NOT re-chase unless retry-condition fires)

- **N-1 · SIMD AVX2 GF(256) (`simd-intrinsics`) gives no net throughput win for atp-rq.**
  Evidence: 100M xmachine F3+simd 133.57s vs F3-scalar 113.85s (slower, within variance);
  loopback 170 vs 162. The receive bottleneck is feedback-rounds + solve-on-incomplete-blocks +
  per-symbol bookkeeping, NOT GF(256) vector throughput.
  **Retry-condition:** re-test SIMD ONLY if a profile shows `gf256_{mul,addmul}_slice` frames
  ≥5% self-time in a steady-state run (i.e. after pacing makes the solve the dominant cost again).
- **N-2 · Parallel encode ALONE does not approach rsync on a fast/loopback path.**
  Evidence: loopback 100M 204→160s (1.27×) — shifts wall to receiver; the parallel burst (~10MB/s)
  outruns the receiver drain → recv-buffer overflow → 5-6 feedback rounds, 2.25× symbol inflation
  (230600 sent / 102565 needed for 100M).
  **Retry-condition:** N/A — F3 is kept (helps the WAN encode-bound case); this entry records that
  encode-parallelism is NOT sufficient on its own. Must be paired with pacing (E-1).

## OPEN HYPOTHESES (experiment queue — profile-first)

### E-0 · PROFILE: where does the 113.85s actually go? (BLOCKS all others)
- **Hypothesis:** the F3 100M wall is dominated by feedback-round latency + solve-on-incomplete
  blocks (caused by burst-induced drops), NOT by sender encode (already parallel) nor raw GF256.
- **Minimal repro:** cross-machine 100M with F3 binary; capture sender CPU%, receiver CPU%,
  feedback_rounds, symbols_sent/accepted, and a per-phase timeline (round0-spray / drain / solve /
  needmore-RTT). `/usr/bin/time -v` both ends + the JSON `feedback_rounds`.
- **Expected signal (if true):** sender CPU << 100% (not encode-bound anymore); receiver shows
  bursty solve activity; wall ≈ Σ(feedback round RTTs + per-round drain). symbols_sent ≫ source.
- **Falsifiability:** if sender stays ~99% CPU → still encode-bound (E-0 false, revisit encode).
  If receiver pegs one core for ~all of wall with feedback_rounds≤1 → solve-bound (→ N-1 retry).
- **One-line:** `bash /tmp/xm_profile.sh`.
- **Result (2026-06-17, SapphireHill):** ★ **FEEDBACK-ROUND-BOUND, not CPU-bound.** 100M xmachine
  wall 116s: **sender 124% CPU** (NOT pegged — F3 fixed encode), **receiver 16% CPU** (NOT
  decode-bound — mostly idle/waiting!), **feedback_rounds=6**, symbols_sent 256200 vs accepted
  102600 (2.5× inflation). ⇒ The wall is the burst→kernel-recv-overflow→drop→NeedMore-RTT cycle,
  NOT encode CPU and NOT decode CPU. **E-1 (pacing) is THE primary lever.** E-5 (parallel decode)
  is DECONFIRMED. N-1 (SIMD) re-confirmed irrelevant (receiver isn't GF256-bound).

### E-1 · Rate-paced spray (F2 / 317hxr.3.x): eliminate self-inflicted drops
- **Hypothesis:** pacing the spray to ≈ receiver drain rate (or link rate) keeps blocks
  source-complete → systematic memcpy fast path (F-POS-1) → 0-1 feedback rounds → big win.
- **Expected signal:** feedback_rounds → 0-1; symbols_sent ≈ source count (overhead → ~1.0x);
  100M wall drops toward network-bound (~rsync).
- **Falsifiability:** if paced run still has many feedback rounds → drops are network-loss not
  burst (→ FEC is genuinely needed, tune E-2 instead).
- **One-line:** prototype a token-bucket / sleep-paced `send_symbol_datagram`; A/B vs F3.
- **Result:** _pending_

### E-2 · repair_overhead + source-retransmit tuning (lazy vs eager FEC)
- **Hypothesis:** on a low-loss link, `repair_overhead=1.0` (source-only round 0) + cheap
  missing-source retransmit (the `missing_source_symbols` path already exists, decoding.rs:778)
  beats sending speculative repair. Under real loss, a small overhead amortizes an RTT.
- **Expected signal:** clean-link: less encode + fewer bytes → faster. lossy-link: find the
  overhead that minimizes wall (convergence in ≤2 rounds).
- **Falsifiability:** if source-retransmit costs more RTTs than speculative repair saves → eager
  wins; record crossover loss rate.
- **One-line:** sweep `--repair-overhead {1.0,1.03,1.1}` × loss {0,1%,5%} cross-machine + netem.
- **Result:** _pending_

### E-3 · Multi-stream UDP saturation vs single-TCP rsync on high-BDP
- **Hypothesis:** ATP's N-way UDP spray fills a high-bandwidth×delay pipe that rsync's single TCP
  stream (cwnd/RTT-limited) cannot — IF ATP is not CPU-bound (requires E-1).
- **Expected signal:** at high RTT (e.g. 100ms) + moderate bandwidth, atp-rq (paced) throughput
  > rsync; widen the `--streams` count until the NIC/loss saturates.
- **Falsifiability:** if a single paced UDP stream already saturates → multi-stream adds nothing.
- **One-line:** netem delay 50-100ms; atp `--streams {1,4,8,16}` vs rsync; same link.
- **Result:** _pending_

### E-4 · max_block_size sweep (is decode superlinear in K?)
- **Hypothesis:** default 8MiB ⇒ K=8192; if `decode_block` is superlinear in K, smaller blocks
  cut solve cost AND widen encode/decode parallelism (more independent blocks). If decode is
  ~linear, smaller blocks only help parallelism width.
- **Expected signal:** microbench `decode_block` wall vs K for fixed total bytes; superlinear ⇒
  smaller K wins. (CLI does not expose max_block_size yet → would add `--max-block-size`.)
- **Falsifiability:** if decode wall ∝ total bytes regardless of K → block size irrelevant to
  solve cost (only parallelism). 
- **One-line:** criterion bench `decode_block` at K ∈ {256,1024,4096,8192} same total bytes.
- **Result:** _pending_

### E-5 · Parallel decode (F6.3 / 317hxr.7.3) — DECONFIRMED by E-0
- **Hypothesis:** decode independent blocks concurrently. **Status: NOT the lever.** E-0 measured
  the receiver at **16% CPU** during a 100M transfer — it is NOT decode-bound, it is idle waiting
  on feedback-round RTTs. Parallelizing an idle decoder yields nothing.
- **Retry-condition:** revisit ONLY if, AFTER pacing (E-1) eliminates feedback rounds, a profile
  then shows the receiver decode pegged ≥80% CPU on a single core. Until then, do not pursue.

---

## ASUPERSYNC LEVERAGE AUDIT (are we fully using the runtime?)

Per `/asupersync-mega-skill`. Findings on whether atp-rq exploits asupersync's machinery:

- **L-FINDING-1 · Sender does ONE syscall per symbol.** `send_symbol_datagram`
  (transport_rq/mod.rs:1907) → `sock.send(&dgram)` (one `send_to` per symbol; ~100k for 100M).
- **L-FINDING-2 · Receiver does ONE `poll_recv` per symbol.** `pump_until_control`
  (transport_rq/mod.rs:2955) polls `udp.poll_recv` for a single datagram per loop iter (biased
  select with the control stream). It does NOT use `recv_batch_from` (udp.rs:1226), which drains
  ALL immediately-ready packets after a single reactor-readiness wait.
- **L-FINDING-3 · asupersync has NO true batched-syscall UDP path.** `send_batch_to` (udp.rs:1190)
  is a portable no-op loop (`fallback_used:true`, one `send_to` each — no `sendmmsg`).
  `grep sendmmsg|recvmmsg|UDP_SEGMENT src/net/` ⇒ none. So GSO/GRO/sendmmsg/recvmmsg are
  UNIMPLEMENTED in the runtime. This is both a missed-leverage finding AND a runtime-enhancement
  opportunity that would also benefit transport_quic + quic_native.
- **L-FINDING-4 · CLI blocking pool IS used** (599356511) and F3 dispatches encode to it. Good.
  spawn_blocking is region-owned + cancel-correct. The receiver decode does NOT use it (E-5).
- **L-FINDING-5 ★ THE BIG ONE · A complete adaptive controller EXISTS but is UNWIRED.**
  `src/net/atp/transport_rq/adaptive.rs` (1105 lines, `br-asupersync-mixdaw`, design doc
  `docs/atp_rq_adaptive_design.md` 443 lines) implements `AdaptiveController` +
  `update_estimate`/`update_path_signals`/`next_block_plan` + `AdaptivePolicy` + `PathEstimate`
  (online RTT/loss/bandwidth/**CVaR trough goodput**/coding-throughput) and DERIVES the calibrated
  repair overhead ε*(K, p̄, α) for a target decode-failure prob AND rate-matches λ/(1+ε) to coding
  throughput. `grep adaptive::|AdaptiveController|PathEstimate src/net/atp/transport_rq/mod.rs
  src/bin/atp.rs` ⇒ **ZERO callers**. It is opt-in/dead. Wiring it is the master lever (E-7):
  it directly produces the pacing rate (E-1) + repair overhead (E-2) + fan-out (E-3) the campaign
  needs, adaptively per link. Violates the "all optimizations default-on" mandate.

### E-7 ★ MASTER LEVER · Wire the AdaptiveController (adaptive over ANY link, default-on)
- **Goal (user):** atp-rq faster than tuned rsync over ANY connection (good/bad/spotty), adaptive,
  lower memory. The controller already computes the knobs; wire it into the live send/feedback loop.
- **Hypothesis:** drive `AdaptiveController` from online feedback (receiver reports loss/RTT/pending
  → `PathEstimate`); apply its outputs each round: (1) **rate-matched pacing** (λ/(1+ε)) so the
  spray never overruns the receiver (kills the feedback-round explosion E-0 found) → clean link
  hits the systematic memcpy fast path → MATCH rsync; (2) **calibrated overhead ε*(p̄)** so a lossy
  link decodes in ~1 round instead of 6 → BEAT rsync (whose single TCP collapses under loss);
  (3) **CVaR-trough conservative fallback** under high loss-variance → "acceptable robustness".
- **Expected signal:** clean: feedback_rounds→0-1, overhead→~1.0, wall→network-bound (~rsync).
  lossy (1-10%): feedback_rounds≤2, wall ≪ rsync (no TCP collapse). spotty: regime shift detected,
  overhead/rate adapt within ~1-2 RTT, no divergence.
- **Falsifiability:** if the wired controller still oscillates / overshoots on a regime shift, the
  estimator/control law needs the changepoint reset (project has `changepoint_exp3_reset`); record.
- **Plan:** pane-2 reads adaptive.rs + the design doc, assesses why it's unwired, wires it with a
  deterministic conservative fallback (per alien-artifact: never ship adaptive without a safe mode),
  A/B vs F3 on clean + netem-lossy + netem-spotty. Reserve adaptive.rs + send_path.
- **Result:** _in progress — wiring plan below (E-7.1 done by SapphireHill, read-only)_

#### E-7.1 controller assessment + wiring plan (for pane-2 / MaroonIvy)
adaptive.rs IS complete + sophisticated; it was just never threaded into send_path. Design:
- `AdaptiveController` = **EXP3 adversarial bandit** (no-regret) over arms `(k ∈ {256,512,1024,2048,
  4096,8192}) × (fanout ∈ {1,2,4,8})`; reward = wall-seconds / useful-byte (lower=better).
- `overhead_for_target(k, p̄, α)` = inverse-normal-tail analytic seed + bisection on
  `decode_fail_probability` → calibrated repair overhead hitting decode-failure α (default 1e-3),
  capped `max_overhead=0.5`. THIS is adaptive FEC.
- `PathEstimate{rtt_s, loss_p_hat, loss_p_bar, bw_median_bps, trough(CVaR), samples}` +
  `decode_symbols_per_s_at(k)`; `PathSignalSample{smoothed_rtt, cwnd, loss_rate}` (EMA-smoothed).
- **Built-in safe fallback:** `next_block_plan` returns `None` until `samples ≥ min_samples (3)` →
  caller uses fixed config. Deterministic via `DetRng(seed)` → lab-replayable.
**WIRING STEPS:**
1. In `send_path`: `let mut ctl = AdaptiveController::new(AdaptivePolicy{cores: available_parallelism
   as f64, ..default()}, seed_from_transfer_id)`. Pick initial k/fanout ONCE at start (block
   boundaries + sockets are fixed at round 0 — do NOT churn k/fanout mid-transfer; only overhead +
   pace adapt per-round).
2. **Round 0 conservative start (fixes the burst E-0 found):** do NOT full-burst. Start paced
   (slow-start-like) at a conservative rate; this alone should cut the 6 feedback rounds.
3. Each feedback round, build `PathEstimate` from the NeedMore WITHOUT a wire change: infer
   `loss_p_hat ≈ pending_or_missing / sent_this_round`; `rtt_s` from control send→NeedMore timing;
   `bw_median_bps` from delivered_bytes/round_wall; `samples += 1`. `ctl.update_estimate(est)`.
4. `ctl.next_block_plan(symbol_size)` → `BlockPlan{k, overhead, fanout}` (or None→fixed). Apply
   `overhead` to this round's repair (replaces static `repair_overhead`).
5. **PACING (the core anti-burst lever — NOT returned directly):** compute
   `rate = min(est.bw_median_bps, decode_symbols_per_s_at(k)*symbol_size)` and pace the spray
   (token bucket / inter-packet sleep in send_symbol_datagram). This is the λ/(1+ε) rate-match.
   Add a `ctl.pacing_bytes_per_s()` helper if cleaner.
6. After the round: `ctl.observe(sent, received, wall_s, useful_bytes)` to update the bandit.
7. **Conservative fallback (E-7.5):** None / high loss-variance / regime-shift → conservative pace +
   modest overhead. Round-0 conservative start covers warmup.
**CAVEATS for pane-2:** (a) k/fanout adapt only at transfer start, overhead+pace adapt per-round;
(b) prefer inferring loss from `pending` (no wire change) over adding a NeedMore loss field;
(c) keep byte-identical wire + sha; (d) reserve adaptive.rs (may be peer-dirty) + send_path.

### E-8 · Memory: paced delivery + bounded retention (less RSS than rsync, ideally O(1) in file size)
- **Hypothesis:** E-0 receiver RSS was **1.7 GB** (vs rsync ~13 MB) — driven by the 120 MiB recv
  buffer + symbols retained across 6 feedback rounds + per-K=8192 decoder state. With pacing (E-7)
  there are ~0 feedback rounds and blocks complete on arrival → recv buffer can be SMALL and symbol
  retention bounded to a few in-flight blocks → RSS becomes O(in-flight) not O(file). Smaller
  max_block_size (E-4) further cuts per-block decoder memory.
- **Expected signal:** receiver RSS bounded (flat vs file size), target < 100 MB for 1G.
- **Cross-cutting:** every experiment reports peak RSS (both ends); a "faster" change that blows
  memory is not a keep.
- **Result:** _pending_

### E-6 · Batched UDP syscalls + GSO (deepest runtime-leverage lever)
- **Hypothesis (two tiers):**
  (a) cheap: switch the rq receiver pump to `recv_batch_from` (amortize the reactor-readiness wait
      per burst). Possibly a small win.
  (b) high-ceiling: add a real `sendmmsg`/`recvmmsg` + **GSO (`UDP_SEGMENT`)** fast path to
      `UdpSocket` (one `sendmsg` pushes up to 64 segments; kernel/NIC segments). This is how
      WireGuard/quinn hit line rate. Collapses ~100k syscalls → ~1.5k and offloads segmentation.
- **Expected signal:** (a) modest drain-time reduction at high packet rate; (b) sender packet rate
  rises from ~per-syscall-bound to GSO-bound (≫12 MB/s ceiling) → lets ATP EXCEED rsync on fat
  pipes, not just match it.
- **Falsifiability:** if E-0 shows the wall is feedback-rounds (not syscall/packet-rate), E-6 is a
  ceiling-raiser not a near-term win — defer behind E-1. Only matters once paced + clean.
- **Scope/risk:** (b) needs `#[allow(unsafe_code)]` libc in udp.rs + reactor integration + the
  unsafe ledger (artifacts/unsafe_boundary_ledger_v1.json). Benefits QUIC too.
- **One-line:** (a) prototype recv_batch_from in pump_until_control; (b) microbench sendmmsg+GSO
  packet rate vs send_to loop on loopback.
- **Result:** _pending_

### Synthesis — why ATP can beat rsync (the actual thesis)
On a CLEAN link, the win path is: **lazy/paced source-symbol streaming (E-1,E-2) → systematic
memcpy receive (F-POS-1, already built) → 0 feedback rounds → match rsync**; then **GSO + N-stream
UDP (E-6,E-3) → EXCEED rsync** by saturating a fat/long pipe a single TCP stream can't fill. On a
LOSSY link, the *same* fountain machinery repairs loss without TCP's retransmit/HoL collapse — but
ONLY once ATP is not self-bottlenecked on CPU/feedback.

**Revised priority after E-0 + L-FINDING-5:** E-0 (done: feedback-round-bound, recv 16% CPU) →
**E-7 (wire AdaptiveController = E-1 pacing + E-2 calibrated overhead, adaptive per link)** →
E-8 (memory falls out of pacing) → E-3 multi-stream + E-6 GSO (ceiling-raisers to EXCEED rsync on
fat pipes) → E-4 block-size. E-5 (parallel decode) DECONFIRMED. N-1 (SIMD) refuted.
The user's goal "beat tuned rsync over ANY connection, less memory" = E-7 + E-8 as the spine,
E-3/E-6 to win on high-BDP, fountain-FEC to win under loss. The adaptive math already exists
(adaptive.rs); the work is wiring + a conservative fallback + honest A/B across link regimes.
