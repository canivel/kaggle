# Stuck Review v2 — 2026-07-23 (revision for R18; R17 objections addressed)

Parent: `stuck_review_2026-07-21.md` (R17: 5× MAJOR-REVISION, 3 FATAL).
Independent verification since: `runs/verify_2026-07-21/report.md` — all gate
arithmetic reproduces exactly; 4 discrepancies found and adopted below.

## 0. Verified state update (post-verification corrections)

- Fork band corrected: **0.82–1.33** (n=12 now; new draws 1.14 and 0.82).
- Pricing re-based on the 15-draw pooled ledger (mean 0.962, σ̂ 0.144):
  **E[max@~102 remaining] ≈ 1.35, P(touch 1.44) ≈ 0.18** — down 40% from the
  stale 0.29. Filler-only is a losing policy with rising confidence.
- EWM clean carrier set shrinks to **{tn36, tu93, ls20, ft09-L1}** (tr87
  ALIASED-UNRESOLVED on binding holdout — R16 objection confirmed).
- Throughput (verified): 9 consecutive scored windows with zero new
  mechanism live; panels R10–R17 = 0/34 ACCEPTs, 169 majors; ≥7 mechanisms
  built-and-validated, 2 ever live (both killed); infra incidents 8/11 days.

## 1. Resolution of R17 FATAL 1 (R5-contradicts-RC4; pricing currency)

The methodology panel's max-currency insight is **adopted in full and
computed**. The LB keeps the max draw; the opportunity cost of giving one
window to an experiment is P(displaced filler draw > current best 1.33) ×
E[exceedance], not a mean-lift deficit. From the verified posterior
(mean 0.962, σ̂ 0.144): P(draw > 1.33) ≈ 0.5–1.5% per window (1.33 is
+2.6σ), E[exceedance | exceed] ≈ 0.05–0.08 → **opportunity cost ≈ 0.001–0.002
E[max]-equivalent per window** — two orders below the old +0.06–0.12 rule.

**A21 (new): Exploration window budget.** 12 scored windows (of ~102
remaining) are pre-registered as EXPLORATION draws for mechanism arms that
have passed their build-rail canary + screen (not full gate). Cost of the
full budget at the verified posterior: ΔE[max] ≈ −0.01 to −0.02 —
purchased against scored-regime evidence no rail can produce (R16's own
regime objections). Sequencing: no arm gets a 2nd exploration window before
its 1st is analyzed; a harm signal (arm draw < 0.80) pauses that arm.
The +0.06–0.12 mean-lift rule is retired for exploration draws; it remains
for PROMOTION (making an arm the default nightly draw).

## 2. Resolution of R17 FATAL 2 (quota is not free) — GPU-hour budget table

Weekly Kaggle GPU quota: 30 h. Rail SKU (verified from kernel logs, both
rails): RTX PRO 6000 Blackwell 96GB — NOT T4/P100/L4 (R17-systems' hardware
premise was wrong, but the finiteness point stands and is adopted).

| deliverable (by Aug 4) | runs × h/run | GPU-h |
|---|---|---|
| sentinel eval seeds 1–2 | 2 × 2.5 | 5.0 |
| A17 72B-VL capability+parity screen | 1 × 7.5 | 7.5 |
| (f)-default regression ride-along | 0 (shares above) | 0 |
| EWM Stage-1 measurement | CPU-only | 0 |
| contingency/re-run | — | 5.0 |
| **total (2 weeks available: 60 h)** | | **17.5** |

Fits with 3.4× headroom. A21 exploration draws use the daily submission
window, not GPU quota.

## 3. Resolution of R17 FATAL 3 (A17 envelope check) — one-pager

From `a17_72b_screen_scope.md` + kernel logs: Qwen2.5-VL-72B-Instruct-AWQ =
**43 GB weights on a 96 GB card** (53 GB headroom for KV at 32k ctx —
fits). Scored-rail SKU is IDENTICAL to bench SKU (verified: sm_120 both).
Throughput: 27B-FP8 baseline serves the full 8h window today; 72B-AWQ at
the scoped 2.5–3× decode penalty ⇒ ~⅓ the turns/window. The screen's
CAPABILITY prong measures exactly whether fewer-but-smarter turns net
positive levels; the ACTION-PARITY prong bounds the throughput loss. If
measured penalty exceeds 3.5× the screen self-reports envelope-infeasible —
that IS a valid NO-GO datum (distinct from capability NO-GO, no panel
ratification needed for physics). Serve-config risk (hermes parser, no
qwen3 thinking flags) is runtime-tested pre-push per scope doc.

## 4. Resolution of R17 MAJOR (watchdog kills the bench)

**A24 revised:** wedge signal = missing HEARTBEAT, not file-write silence.
Every registered long-run (bench pushes, panel rounds) must emit a
heartbeat line/file ≥ every 20 min (the harness already streams logs; the
loop's watchdog greps recency). Registered benches are exempt from the 6h
session cap; unregistered sessions are not. Kill only fires on 60 min of
missing heartbeat.

## 5. The reset, restated (A21–A25)

- **A21** exploration budget (§1) — 12 windows, canary+screen entry bar,
  harm-pause, promotion still gate-sealed.
- **A22** two-track governance — build-rail pushes need pre-registered
  one-page intent only (metric, canary, kill rule); full-panel seals only
  for scored-window PROMOTION, wall-closer kills, sealed-statistic edits.
  Quota governance per §2 table, republished weekly.
- **A23** A17 starts under §3 envelope; capability NO-GO requires panel
  ratification with false-NO-GO probability quantified; envelope NO-GO is
  self-certifying.
- **A24** loop hardening per §4 (heartbeat watchdog, bench exemptions,
  audit stub stays, panel recovery map stays).
- **A25** seal termination — two consecutive full-panel rounds, 0 fatals,
  median ≥6 → seal WITH NAMED CONDITIONS (tracked, owned, dated).

## 6. 14-day falsification (unchanged in spirit, dated from Jul 23)

By **Aug 6**: sentinel screen verdict; A17 capability/parity/envelope
numbers; EWM Stage-1 measurement on the clean 4-carrier set; (f) defaulted;
first exploration draw fired. If none lands, the reset is refuted and the
panel reconvenes on pod-spend vs accept-the-band.

## 7. Question to reviewers

Same as v1 §5, now with the R17 fatals resolved above: approve A21–A25, or
name the harm scenario the current process prevents that this reset does
not — weighed against the verified §0 throughput numbers.
