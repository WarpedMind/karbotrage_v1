# Karbot Rage! Session Summary
# Entries are ordered newest-to-oldest. Most recent session is at the top.

## 2026-08-29 (Session 33 — housekeeping: VPS spot-check, closed the paper-trade fee-variance and P&L-inflation KNOWN DEBT items with a direct compliance.db query, shipped Telegram /mute /unmute)

### Mandate
Prompted by the operator wanting legitimate Oracle Cloud VPS traffic (so the
account doesn't look inactive) rather than a thin ping script — combined with
picking real, already-flagged items off the standing "Next up" list instead of
inventing busywork. No strategy code touched.

### What was done
1. **VPS spot-check (read-only, over SSH)** — `git log -1` on the box matches
   local `main` (`7ec5b3d`) exactly; `karbot` and `karbot-canary` both
   `active`/`enabled`; disk 17% of 49G; the canary's 18:13 UTC sweep evaluated
   3,049 events with zero candidates and zero errors, consistent with every
   sweep since deployment; `telegram.enabled: true` confirmed by reading
   `config.yaml` directly rather than inferring it from a log line (the
   `config_resolved` startup log itself has since scrolled out of `journalctl`
   retention, which only goes back to 2026-08-21 despite `uptime` reporting 27
   days — journal retention, not a reboot; not investigated further).
2. **Paper-trade fee variance and P&L inflation — both closed.** Pulled all
   757 rows from `logs/compliance.db`'s `trades` table directly. Finding: the
   fee split is real but isn't "old formula vs. new formula" as the original
   Session 25/28 hypothesis had it — 312 rows at exactly `fee_paid=70.0` plus
   a long tail of other large values ($15–$330) are **all** the
   pre-Session-26 flat-14% formula at different Kelly-derived position sizes
   (0.14 × size; $500 was just the most common size, landing on a round $70).
   The last such row is 2026-07-13T19:09:14 UTC; every row after that has
   `fee_paid` under $2.30 — exactly Session 27's 5 known post-fix trades
   ("$0.05–$81.36" positions). So there was never a live bug in the corrected
   fee formula. This also independently corroborates Session 29's separate
   finding (via sequence-gap correlation, a completely different method) that
   every one of these 757 rows is a book-reconstruction artifact, not a real
   edge — two methods landing on the same population is real confirmation,
   not a restatement. Full numbers in CLAUDE.md's KNOWN DEBT section.
3. **New debt found in the process, not fixed**: `compliance.db`'s
   `filled_price`, `quantity`, and `ordered_price` columns are `NULL` on all
   757 rows. The Session 16 fix documented in CLAUDE.md only touched the
   CSV-writing path (`kalshi_trades.csv`) — the `compliance.db` INSERT path
   never got the equivalent fix. Flagged, not built.
4. **Shipped Telegram `/mute` `/unmute`** (standing item 17) —
   `agents/notifications/telegram_agent.py`: in-memory `_muted` flag toggled
   in `_handle_operator_reply`, checked before the kill-switch/yes-no paths
   (same pattern the kill switch already used). Suppresses Tier 2 only
   (trade opened/resolved, rejected opportunity, generic tier-2
   notifications); Tier 1 (leg failure, feed health) and pending permission
   requests are untouched by design — the Session 20 feed-down alert must
   keep bypassing mute, and it does. Resets to unmuted on every restart
   (no persistence file), so a forgotten mute can't outlive a deploy.
   16 new tests (`tests/test_telegram_mute.py`); full suite 321/321 passing
   (305 pre-existing — 4 more than CLAUDE.md's previously documented 301, an
   unexplained small pre-existing discrepancy, not chased down — plus the 16
   new ones). Deployed to the VPS via `git pull` + `systemctl restart karbot`;
   service confirmed to restart cleanly with no errors in the log. **Live
   round-trip confirmed same session** — the operator sent `/mute` and
   `/unmute` from their phone and confirmed it working.

### What was decided
- Mute state is in-memory and per-process, not persisted — deliberate: the
  alternative (a state file) risks a forgotten mute silently surviving a
  restart indefinitely, which is worse than occasionally having to
  re-mute after a deploy.
- The fee-variance and P&L-inflation KNOWN DEBT items are closed together,
  since the direct data query answered both from the same table in one pass
  — recorded as two separate closures in CLAUDE.md rather than merged, so
  the historical record of what each session originally flagged stays intact.

### What to do first next session
- Standing items unaffected by this session: the stuck order-book reset loop,
  the `_request_snapshot` concurrency limiter, the Health Monitor agent, and
  the full line-by-line CONFIRMED-LIVE re-audit (today's was a spot-check,
  not the full pass). See README.md "Next up" / CLAUDE.md "Next session
  priorities" for the complete current list.

---

## 2026-08-02 (Session 32 — built the S5a/S5b passive arbitrage canary as a standalone detect-and-log process. Live-verified end to end. Zero candidates in the first sweeps, with every near miss exactly one spread wide.)

### Mandate
Build the S5a/S5b canary the operator chose at the end of Session 31: a REST
poller plus arithmetic, no LLM, no orders, no hot path, logging candidates so
that "one snapshot found nothing" becomes real frequency data over weeks.
Full reasoning and every measured number: **DECISIONS.md Session 32**.

### What shipped
`canary/` — a new top-level package, run as its own process, never imported by
the trading path (`tests/test_canary_isolation.py` enforces it):

| module | job |
|---|---|
| `kalshi_rest.py` | one paginated sweep primitive + authoritative order-book top |
| `strikes.py` | Kalshi strike conventions as intervals; implication and disjointness |
| `qualify.py` | what a series' **settled history** proves; `confirmed`/`refuted`/`insufficient_evidence` |
| `economics.py` | one basket evaluator: ask prices, ceil'd per-order fees × N legs, depth-capped size |
| `scan.py` | two-stage sweep — bulk snapshot, then per-leg order-book re-confirmation |
| `run_canary.py` | loop, JSONL output, per-sweep heartbeat |

Plus `scripts/karbot-canary.service` (systemd, **written but not deployed**),
`canary/README.md`, and 75 new tests. **301/301 passing** (226 through Session 31).

### The design decision worth knowing
**Structure proposes, history disposes.** Strike arithmetic only *generates*
candidate relations; a relation is usable only if the series' real settled record
has never violated it. The reason is a live counterexample:
`KXMLBSPREAD-26AUG021340CWSTB` puts eight `greater` markets in one event covering
**two different metrics** (each team's winning margin) at overlapping strikes, so
interval logic "proves" that Tampa Bay winning by 4+ implies Chicago winning by
3+. Measured on the settled record: **2,267 violations**, series disqualified.

Two text-based tests for metric identity were tried and rejected on evidence.
An `expiration_value` identity test is outright **wrong** — across 123 settled
KXMLBSPREAD events all markets share one `expiration_value` despite being on
different metrics.

### Three things nearly missed, all caught by counting rather than by tests
1. **The first live sweep evaluated zero events** and errored on nothing. The
   60-series profile budget went entirely to the series the events endpoint
   returns first — `KXNEXTNATOSECGEN`, `KXNEWPOPE`, `KXXISUCCESSOR` — all
   long-horizon "who will be next" markets with **zero settled events**. Fixed by
   ranking unqualified series by their open markets' 24h volume.
2. **The reconciliation check caught a real bug on its first live run**: 8,608
   events accounted for as 8,631, because per-event evaluation *notes* were being
   counted alongside event *dispositions*. Split into `event_skips` (must
   reconcile) and `evaluation_notes`. Session 31's lesson paying for itself
   within an hour.
3. **A settlement outcome that is neither YES nor NO.** Kalshi finalizes a
   postponed game or unplayed match as `result: "scalar"`, `status: "finalized"`
   on every leg — **0.7% of KXMLBGAME events and 4.1% of KXATPMATCH events**. The
   first implementation filed these under "unsettled" and dropped them, so the
   profile reported `exhaustive: confirmed` while nothing had checked whether
   the basket's guaranteed dollar survived. That is Session 31's failure mode
   reproduced in brand-new code. Now split, measured — **and then resolved**.

### The void question was framed wrong, and the framing is the lesson
It was escalated as a binary: does Kalshi refund a voided position **at cost**
or **not**? Both wrong. Kalshi's own `rules_secondary` — which ships on every
market, so it is the cheapest primary source available — says a cancelled match
*"will resolve to a **fair price** in accordance with the rules"*. Neither a
refund nor a zero. So the question that actually decides the basket is a third
one: **do a cancelled event's fair prices sum to $1?**

They do. Every leg carries `settlement_value_dollars`, a field nobody had
noticed. **243 of 243 scalar-settled events across 8 series (236 two-leg, 7
three-leg) sum to exactly $1.00** — zero violations, zero unverifiable,
reconciled. A YES-basket still pays `Σ settlement = $1`; a NO-basket still pays
`Σ(1 − settlement) = $(N−1)`. Now checked per series in
`qualify.scalar_sum_to_one`, with an unverifiable cancellation counting
**against**, never for.

Then confirmed on the deployed VPS across all 60 live profiles, which is
stronger evidence than the hand-picked sample: the **19 partition series** show
**361 cancellations and 0 violations**; the **6 non-partition series**
(KXMLBHIT, KXMLBHR, KXMLBKS, KXMLBSPREAD, KXPGATOP5/10/20) show **96 violations
and 0 clean**. The invariant holds exactly where it structurally must and is
correctly absent where it needn't — independent player props on one event have
no reason to sum to $1. Zero exceptions in either direction. And the gate
currently blocks **0** qualifying series, so it costs no coverage.

The transferable part: *before escalating a question as "open and decisive",
check whether the data already in hand answers it.* This one had been sitting in
`rules_secondary` and `settlement_value_dollars` the whole time.

### Deployed — and deploying found two things nothing else would have
Installed as `karbot-canary.service` (enabled, active, `Restart=always`,
`Nice=10`) after confirming the VPS was 10 commits behind and that **none of
those commits touched the live path** (`git diff --name-only` over the agent
dirs returned nothing — checked, not assumed).

1. **`requests` was an undeclared dependency** — documented by `backtest/` since
   Session 31, present locally by coincidence, `ModuleNotFoundError` on the VPS.
2. **The dev machine and production disagree on floating-point arithmetic.** A
   test asserting `basket_fee(...) == 0.10` passed locally and failed on the
   VPS: local Python is 3.14, the VPS is 3.10, and CPython 3.12 gave `sum()`
   compensated summation for floats. **"301/301 passing locally" was never
   evidence about production.** Fixed with `approx` in the test and an `EPSILON`
   in `is_candidate`, so a break-even basket can't be logged because a float
   landed 1e-16 above zero.

### The rate-limit coupling: predicted, then measured, after one false alarm
`canary` and `karbot.service` share one IP and therefore Kalshi's rate limit —
raised and documented *before* deploying. A first measurement said the canary
made no difference; that was wrong, because it counted `grep 429`, which matches
sequence numbers containing those digits (`expected=27854299`). The real counter
is `book_reset_rest_failed`: **0 failures across 38,752 REST snapshots in the 84
minutes before, 4 across 2,390 in the 13 minutes after (~0.17%)**. Real, an
order of magnitude below Session 23's 5.5%, and absorbed by the existing retry
path. The zero-failure pre-canary baseline is itself new information about the
REST snapshot path's health.

### Confirmed live
- **NO-leg depth is `yes_bid_size_fp`** — the field with the opposite name; there
  is no `no_ask_size_fp`. Verified both directions against `/orderbook`.
- **The bulk snapshot is stale within seconds** (16/16 agreement back-to-back; a
  traded market moved yes_bid 0.10 → 0.14, size 3 → 2071 over ~10s). Hence
  mandatory per-leg re-confirmation before anything is logged.
- **`strike_type` census over 12,000 open markets**; `less`/`cap_strike`
  reconfirmed 105/105; `structured` found to be two different things.

### Result: zero candidates
**12 consecutive sweeps, 13,094 event-evaluations, zero candidates, zero errors,
every sweep reconciling.** Coverage climbed 725 → 1,284 evaluated events per
sweep as the profile cache filled (720 series qualified), so the run also
demonstrates the deferred-qualification design converging rather than stalling.

8,598 open events, 76,483 markets, 3,086 series. Of the first 60 qualified, 26
qualified for something — including the **genuine winner-take-all events Session
29 noted were missing from its sample** (MLB, ATP/WTA/ITF, CS2, LoL, Dota,
soccer). Near misses:

| event | legs | basket cost | guaranteed payout |
|---|---|---|---|
| KXATPMATCH | 2 | $1.01 | $1.00 |
| KXCS2GAME | 2 | $1.02 | $1.00 |
| KXMLBGAME | 2 | $1.07 | $1.00 |
| KXHIGHLAX | 6 | $1.09 | $1.00 |

ATP is one cent away, but two near-the-money legs pay ~3.5¢ in taker fees, so it
needs $0.965 to be real. **This does not show S5a/S5b arbitrage exists** —
twenty-five minutes on a Sunday afternoon is not weeks, and real arbitrage is
sporadic by nature. What exists now is the instrument, verified against real
books rather than fixtures.

### Watchdog: the "dies quietly" gap closed the same session
A separate systemd unit inherits none of `karbot_runner.py`'s supervision or
Telegram alerting, and `Restart=always` covers a crash but not a hang. So
`scripts/karbot-canary-alert.sh` now runs from cron every 15 minutes, mirroring
`karbot-disk-alert.sh`'s conventions (secrets from `/etc/karbot/secrets/`,
edge-triggered state, nothing echoing the token). It alerts on **CANARY
STALLED** (no sweep for 20 minutes, with a recovery message) and on **CANARY
FOUND N CANDIDATE(S)** with the candidate's economics and its
`confirmed`/`vanished_on_recheck` status.

**Both alert paths plus the silent no-op were exercised with real Telegram sends
before being trusted**, against a scratch file via `CANARY_LOG`/
`CANARY_STATE_DIR` overrides. Deliberate: an untested watchdog is worse than
none, and the precedent is `karbot-disk-alert.sh` — the watchdog built to
prevent a silent outage — being itself silently non-functional from Session 26
to Session 29.

### Asked and answered: should the project pay for data?
Operator asked directly. **Recommendation: not yet**, for a structural reason
rather than a budgetary one — full entry in DECISIONS.md. The short form: the
binding question is not "is it paid?" but "do the participants setting the price
already have it?", and on Kalshi 75.4% of volume is sports, where the sharpest
public forecast is nearly free and the counterparties already buy better feeds
than any subscription would provide. Neither remaining strategy is
data-constrained anyway — S5a/S5b is arithmetic on Kalshi's own books, and
market-making needs an order layer, which is engineering. Three specific,
testable conditions that would change the answer are recorded in DECISIONS.md.

### Test suite green on the VPS for the first time — two portability bugs
Running the suite on the box (never done before) found two failures, both the
same root cause as the float-summation find: **dev machine Python 3.14, VPS
3.10**.
- **`asyncio.timeout` landed in 3.11**, so ten regulatory-intelligence tests
  errored with `AttributeError`. Added a fallback that **really enforces** the
  deadline rather than yielding unguarded — a timeout guard that silently stops
  guarding on the platform you deploy to is worse than the error it replaces.
  Confirmed the live path never uses it, so this was only ever a test bug.
- **`test_config_resolved_log` asserted `telegram_enabled=False`** on the
  grounds that no `config.yaml` exists in the test environment. The VPS has a
  real one with Telegram enabled — created in Session 24 precisely so alerting
  would stop being a silent no-op. The test was asserting the *absence of a
  production config file*: it could never catch a real regression on the box it
  was meant to protect, and went red for correct behaviour. Now derives expected
  values from a freshly loaded `KarbotConfig`.

**305/305 on the VPS.** A red suite on production hides the next failure.

### Direction analysed; Kalshi enquiry drafted
`documentation/kalshi-mm-enquiry-draft.md` — four questions to the exchange
before any order-layer build, because market-making **cannot be falsified
offline at all** and asking costs minutes while building costs sessions. Full
direction reasoning in DECISIONS.md's Session 32 addendum. Conclusion: the
**Health Monitor** and the **stuck order-book reset loop** are *prerequisites*
for market-making rather than alternatives to it, so working on them is phase
one of that build and retains value regardless. Recorded with its honest
counter-argument — this is the shape of a project that builds forever and ships
nothing — plus two guards: a bounded list, and an information trigger rather
than a date.

### Not done
Phase 0 item 4 (paper resolution against real outcomes) and `--mode` remain
open. The Kalshi enquiry is drafted but **not sent** — operator action. 11 pre-existing test failures on the VPS (10 in
`test_regulatory_intelligence.py`, 1 in `test_config_resolved_log.py`) are
environment differences unrelated to this work and were not investigated — all
76 canary tests pass there.

---

## 2026-08-02 (Session 31 — Phase 1 executed: the S6 weather calibration backtest was built and run. RESULT: NOAA/NBM is measurably WORSE calibrated than the Kalshi price at every lead. Gate G2 FAILS; S6-weather stops here.)

### Mandate
Build `backtest/` and produce the calibration report Session 30 specced —
"a report, not a trading agent" — and stop if the model does not beat the
market price. It did not. Stopping.

### The answer, up front
| contested markets, test split | 12h | 24h | 30h |
|---|---|---|---|
| Brier — NBM model | 0.2013 | 0.1795 | 0.1713 |
| Brier — **market (baseline)** | **0.1757** | **0.1612** | **0.1567** |
| Brier — climatology | 0.2104 | 0.1896 | 0.1812 |
| skill vs market | −0.146 | −0.114 | −0.093 |
| P(model no better) | 1.000 | 1.000 | 1.000 |

36 independent dates; 95% CIs from a bootstrap over whole **dates**, all
entirely negative. 17 of 18 cities lose. The model barely beats climatology
while the market beats it comfortably.

Trading it makes the point plainly: the model claims **+$0.11 to +$0.17** net EV
per contract and **realises −$0.01 to −$0.04**. Tightening the divergence filter
makes it *worse*, which is what a divergence signal looks like when the model is
the less-informed party.

### Why — measured, not guessed
Recovered the market's implied expected temperature from each city-day ladder
(an exhaustive partition, so its normalised YES prices are a real distribution)
and scored both against the settled high:

| | NBM | market-implied |
|---|---|---|
| point MAE @12h | 1.59 °F | **1.27 °F** |
| point MAE @24h | 1.77 °F | **1.47 °F** |

NBM's published spread meanwhile is close to right (published SD 2.32 vs
realised RMSE 2.16, ratio 0.93). **So the deficit is the forecast, not the
probability conversion** — a better error model cannot recover it. The Kalshi
weather market already prices a better temperature forecast than a raw NBM run.

Session 30's own honest counter said this would be the risk ("Kalshi weather
markets are known to attract participants already using NOAA"). It was the
decisive consideration, not a footnote.

### The objection that would have killed the result — tested and closed
*"The model was handed stale data."* **NBM does not publish a daytime-max
forecast at less than 12 hours' lead** — the 18Z cycle's 00Z-valid `TXN` column
is null. Twelve hours is NOAA's freshest. The model loses at NOAA's own best.

Separately: these markets only trade for **~42 hours**, so there is no market
price beyond ~36h of lead — a strategy premised on "NOAA sees further ahead"
has no venue here.

### Proved before any modelling ran (each treated as a gate)
- **Settlement rule replayed against reality: 7,565/7,565 exact**, all three
  strike types, using each market's real `expiration_value` and `result`.
- **Ladders are exhaustive partitions: 1,261/1,261 city-days have exactly one
  YES.**
- **Station identity resolved empirically: 18/18 at 100% exact match** against
  NWS CLI highs. **Houston is KHOU (Hobby), not KIAH.** Also KMDW not KORD,
  KNYC not KLGA/KJFK, KDCA not KIAD, KDFW not KDAL. Guessing would have been
  wrong on at least one and unfalsifiably so.
- **NBM valid-time → local-day mapping** scored both ways: correct reading MAE
  1.85 °F, naive same-date reading 3.46 °F.
- **Fee model cross-checks against the live `KalshiFeeModel`** at every probe.

### A bug found by counting, not by testing
Gate 1 first reported "7,565/7,565 matched" on **6,305 checked out of 7,566
seen**. The totals do not reconcile, and the missing 1,255 were almost exactly
one per city-day.

Cause: **Kalshi's `less` markets carry the threshold in `cap_strike` and leave
`floor_strike` null** — the opposite convention from `greater`. Reading
`floor_strike` returned `None`, and the `None` was skipped silently, deleting
the entire low tail of every ladder while the printed rate still read 100%.

Nothing failed; no test caught it; a total did not add up. `verify_strike_logic`
now counts every skip by reason and refuses to pass with any unhandled case.
**Standing lesson: a validation reporting a rate rather than a reconciliation
can hide an arbitrarily large omission behind a perfect-looking number.**

### An architectural finding that outlives the negative result
Session 30 specced the forecast leg as GRIB2 byte-range fetches needing an
eccodes/cfgrib binary dependency plus grid interpolation. **Unnecessary.** The
same S3 bucket's `text/` suite publishes plain-ASCII **station** bulletins, and
the NBP product carries per station and valid time: `TXNMN` (mean), `TXNSD`
(spread) **and** `TXNP1/2/5/7/9` (quantiles). No decoder, no interpolation,
exactly the airport stations Kalshi settles on. `backtest/` ships with **zero
new dependencies** — stdlib plus `requests`.

Cost of the text route: values are integer degrees, including the spread. That
was the reason to suspect overconfidence; measured, it does not bind.

### A trap for whoever builds a live weather provider
IEM has two daily-temperature feeds and they disagree. `cgi-bin/request/daily.py`
(ASOS) reads KLAX 2026-08-01 as **79 °F**; `json/cli.py` (parsed NWS CLI) reads
**80 °F**. Kalshi's `expiration_value` is 80.00. Kalshi settles on CLI. The more
obvious endpoint is the wrong one.

### Retraction, recorded rather than dropped
Mid-session I called a 12h RMSE of 2.27 °F next to KLAX's `TXNSD` of 1 "a first
sign the model will be overconfident" from integer truncation. **Wrong** — that
generalised one station to the population; the population mean published SD is
2.32 °F and the ratio to realised error is 0.93 (slightly *wide*). Same shape as
Session 30's fee error: a confident conclusion from an incomplete look. Caught
by measuring it.

### Also fixed this session
- **Parser sign flip.** NBS rows that pack 3-digit values with no separator
  (VIS, SLV, CIG, LCB) bleed one character left of the FHR-derived column grid,
  so `-88` parsed as `88` and `100` as `00`. Repaired, bounded by the label
  length — NBP labels like `TXNP1` end in a digit and an unbounded repair
  destroys the row. Both directions have regression tests.
- `.gitignore` gained `backtest/cache/`; an initial append merged into the
  previous line (no trailing newline) and briefly produced the nonsense pattern
  `karbotrage_env/backtest/cache/`, verified fixed with `git check-ignore -v`.

### Tests
**226/226 passing** (157 baseline + 69 new across three files:
`test_backtest_nbm_parser.py`, `test_backtest_probability.py`,
`test_backtest_scoring_costs.py`). Two of the new tests caught real defects
while being written — the parser sign flip, and a bin-index error that was mine,
not the code's. Runner smoke test unaffected; no live-path code was touched.

### What was NOT done
- Phase 0's last item (PaperExecutor resolving against real outcomes) — it was
  a prerequisite for S6 *paper trading*, which no longer has a strategy behind
  it. Left open and re-scoped in CLAUDE.md rather than built speculatively.
- `--mode` is still parsed and never applied.
- No VPS work; no live-path code changed.

### Cost of learning this
One session. No order layer, no capital, no paper trades. That was the whole
argument for sequencing divergence ahead of market-making, and it held.

---

## 2026-08-01 (Session 30 — SPEC ONLY, no strategy code: pivot direction chosen and specced — external-model divergence (S6) first, market-making deferred, arb continues as a passive canary; Session 28's maker-fee premise found wrong)

### Mandate
Turn the already-made decision ("shift from pure structural arbitrage
toward statistical/correlated trading") into a concrete, phased,
implementable plan. Explicitly not an implementation session — the
deliverable is documentation the next session can build from without
re-deriving anything. Same pattern as the Session 28 review, which worked.

### Measured live before deciding anything (2026-08-02 ~03:00 UTC)
Kept the project's own discipline — pulled real data rather than reasoning
from the vision docs. Public Kalshi REST, no auth, 40,000 open markets
(`mve_filter=exclude`), 74,654,881 contracts of 24h volume:

| What | Number |
|---|---|
| Sports share of volume | **75.4%** (KXPGATOUR 31.3%, MLB series ~36%) |
| Weather share of volume | **3.2%** — 2,404,232 contracts, 672 markets |
| Fed/CPI/econ share of volume | **0.1%** — 46,953 contracts across 453 markets |
| Markets with vol≥100 and a two-sided book | 3,918–3,938 |
| Spread p25 / median / p75 / p90 | 1¢ / **2¢** / 4¢ / 8¢ |
| Top-of-book min(bid,ask) p25/med/p75/p90 | 5 / **42** / 395 / 1,395 contracts |
| Spread ≥2¢ AND ≥100 contracts both sides | **486 markets** |

Three consequences, all of which changed the plan from what was expected
going in:
1. **Fed/econ markets on Kalshi are effectively dead** (0.1% of volume).
   The clean-sounding "Kalshi vs CME FedWatch" idea has almost no volume
   behind it. Ruled out as a starting point on measured grounds.
2. **Sports is 75% of volume** but the external benchmark is a sharp
   sportsbook's closing line — the hardest benchmark in the space, and not
   free. Right target eventually, wrong first target.
3. **Weather is small but uniquely tractable.** Confirmed live from
   `rules_primary`: Kalshi weather markets settle on *"the National Weather
   Service's Climatological Report (Daily)"* for a named station (e.g. Los
   Angeles Airport). The forecast source and the settlement source are the
   same agency's number for the same station — a property nothing else in
   the scanned universe has. Structure is 12-market city-day temperature
   ladders with machine-parseable `strike_type`/`floor_strike` (no LLM
   needed); `KXHIGHLAX` alone did 616,690 contracts/24h.

### A mistake made and corrected inside the same session: the maker-fee "correction" that was itself wrong
Worth recording in full, because the failure mode is one this project
keeps meeting in new costumes.

Session 28 recommended market-making partly on "maker fee = $0 on most
Kalshi markets." Three independent third-party fee references say the maker
fee is "25% of the taker fee," and this repo's own `KalshiFeeModel`
docstring says the same. On that basis this session declared Session 28
wrong, wrote it into four docs, and committed it.

Then the operator supplied Kalshi's actual published fee schedule
(effective 2026-07-07), which shows the two formulas have **different
default multipliers**:
```
taker:  round up(M × 0.07   × C × P × (1−P))    M defaults to 1
maker:  round up(M × 0.0175 × C × P × (1−P))    M defaults to 0
```
Maker fees are therefore **$0 by default**, charged only on the ~76 series
explicitly enumerated in the schedule's Non-Standard Fees table.
**Session 28 was right; the correction was wrong and has been retracted**
across DECISIONS.md, CLAUDE.md and README.md.

The instructive part: three independent sources agreed with each other
*and* with an internal docstring, and all four were still insufficient —
because every one of them described the coefficient (0.0175 = 25% of 0.07)
and none described the multiplier it multiplies. This is the same shape as
Session 26's "tests internally consistent with a wrong formula" and Session
28's "0 candidates is a wiring fact, not a market fact," and it happened in
a session whose stated premise was verified-beats-argued. **Standing
lesson: agreement among secondary sources is not confirmation.**

Measured consequence, live (~04:15 UTC; note total volume read 69.4M on
this pass vs 74.7M an hour earlier — intraday snapshots, not constants):

| | share of 24h volume | tradeable two-sided markets | median spread | spread ≥2¢ AND ≥100 both sides |
|---|---|---|---|---|
| Maker fee **$0** | **42.5%** (29.5M) | **3,651** | **2¢** | **489** |
| Maker fee charged | 57.5% (39.9M) | 207 | 1¢ | 27 |

The split matters more than the headline: the fee-charging series are both
the highest-volume (KXPGATOUR, KXMLBGAME) **and** the tightest at 1¢ —
already professionally market-made. The wide spreads sit in mid-volume
zero-fee series: KXMLBTOTAL (2.45M), KXBOXING (2.28M), KXLIGAMXGAME
(2.17M), KXMLBSPREAD (1.64M). So market-making is a **stronger** candidate
than this session first concluded, concentrated somewhere other than the
obvious markets.

**Does it flip the direction?** No — but it does retire one of the four
arguments. Reasons 1, 2 and 4 (offline falsifiability; the order layer
must be built entirely up front; the fair-value abstraction transfers to
other venues) are untouched by the fee. Reason 3 was the fee argument and
is withdrawn. The sequencing now rests on the remaining three.

Two other details from the primary source: the rounding prose says
"centicent" ($0.0001) while the schedule's own table shows ceil-to-cent on
small orders (implement against the table, verify against a real fill);
and Kalshi now lists **perpetual futures** on a tiered bps schedule (taker
12.0 / maker 5.0 bps at tier 0) — a new instrument class on a
CFTC-regulated venue, noted for multi-asset scoping, not acted on.

### The decision
**S6 — External Model Divergence, NOAA/weather first, detect-and-log,
gated behind an offline backtest.** Market-making (S8) deferred behind a
live order-management layer that does not exist. S5a/S5b arb detection
continues **in parallel as a cheap passive canary** — a REST poller plus
arithmetic, no LLM, no orders, no hot path — so "one snapshot found
nothing" becomes real frequency data over weeks.

Operator asked directly why divergence before market-making, and whether
arb was still feasible at all. Answered plainly rather than with a
recommendation alone; the four reasons and the three-different-answers
breakdown of "is arb dead" are both recorded in full in DECISIONS.md.
Short version: **divergence can be falsified offline and market-making
cannot** — NWS publishes forecasts and Kalshi publishes settlements, so
"when the model said 70% and the market said 55%, what happened?" is
answerable from history with no capital; whereas whether resting quotes get
filled, and whether those fills are the ones you didn't want, is only
observable by placing real orders. A direction that can be killed cheaply
beats one that can only be evaluated expensively — the exact discipline
that killed S1 for $0.

And on arb specifically: S1 is dead by construction and not revisitable;
S5a/S5b were never disproven — Session 29 found no candidates in one
snapshot, but unlike S1 there is no structural reason they can't exist,
since Kalshi doesn't atomically match across an event's separate markets.

### What was specced (full detail in DECISIONS.md — not repeated here)
- **`FairValueEngineAgent`** (Research Floor) with a pluggable
  `FairValueProvider` registry; first provider `NoaaTemperatureProvider`.
  api.weather.gov confirmed free, no API key, `User-Agent` with contact
  info required.
- **`DivergenceScannerAgent`** (Trading Floor) — deliberately a separate
  module from `ArbScannerAgent`, to keep riskless and statistical
  strategies from blurring the way Session 28 found they had everywhere
  else.
- **New `FairValueEstimateEvent`**, additive, with a load-bearing
  `valid_until` so RiskGate can reject stale models.
- **RiskGate**: this is finally where Kelly is correct — but fed the
  model's probability, not a hardcoded per-strategy constant. Closed form
  derived for a binary contract bought at price `c` with model probability
  `p`: **`f* = (p − c)/(1 − c)`**. Plus: per-strategy staleness horizons
  (S6 lives for hours, current code hardcodes 30s for non-S1), a
  correlated-exposure cap (five strikes on one city's ladder are one bet),
  and a per-provider capital cap (a biased provider makes every position
  wrong at once).
- **Hard requirement flagged**: `PaperExecutor` currently resolves every
  trade at its own `expected_pnl`, which is tautological for a directional
  strategy. S6 paper resolution must settle against the market's real
  outcome or its paper results are meaningless.
- **Backtest harness** (`backtest/`, offline) with the scoring bar stated
  precisely: not "is NOAA accurate" but "**is NOAA better calibrated than
  the Kalshi price**" — the baseline is the market, and Brier score is
  measured against it.
- **G1–G5 gates** before S6 sees paper money, each a stop.

### Phase 0 begun: the "biggest open unknown" was raised and then answered, same session
Flagged the forecast-archive question as the thing that decides the S6
timeline, then went and answered it rather than leaving it for later.
**Result: the backtest is buildable now, over real history — no weeks of
forward data collection.** Three legs, all verified live and all
unauthenticated:
1. **NOAA NBM archive on AWS Open Data** — bucket `noaa-nbm-grib2-pds`,
   anonymous S3, **2020-05-18 → current**. The `core` GRIB2 index carries
   `TMAX:2 m above ground:12-24 hour max fcst` (exactly what Kalshi
   settles on) **and `:ens std dev`** — so a first-cut `P(high > strike)`
   comes straight from the published mean and spread, with a `qmd/`
   quantile suite available as the better-calibrated upgrade. This
   substantially retires the "must build a bespoke forecast-error model"
   concern raised earlier in the session. `.idx` sidecars allow
   byte-range fetching a single TMAX record instead of multi-GB files.
2. **Kalshi settled outcomes** — `status=settled` gives clean
   `result` ∈ {yes,no} with `floor_strike`/`strike_type`; 414 settled
   markets for KXHIGHLAX alone.
3. **Kalshi historical prices** — the `candlesticks` endpoint returns
   hourly bars with `yes_bid`, `yes_ask`, OHLC price, volume and open
   interest. This is the market baseline the model has to beat, and it
   carries **bid and ask**, so the backtest can be scored on the
   executable side of the book from day one — structurally avoiding the
   bug class that invalidated S1.

**Binding constraint is Kalshi's history, not NOAA's**: KXHIGHLAX settled
markets start 2026-05-25 (~69 days), ~12 markets per city-day across ~12
cities. Usable, but **summer-only** — any calibration result must state its
season, and cross-season generalization stays unproven until winter data
exists.

### The open unknown as originally flagged (now resolved above — kept for the record)
`api.weather.gov` serves the *current* forecast, not an archive of past
forecasts. Historical NWS/NBM forecast archives are understood to exist
(NOAA NOMADS, Iowa State IEM) but **this session did not verify any is
reachable, complete, or matched to the stations Kalshi settles on.** That
question decides the timeline: with a usable archive, a real backtest is a
single session over months of history; without one, the fallback is forward
collection of (forecast, price, outcome) triples and the answer takes
weeks. **Resolving this is the first task of the next session — before any
model code is written.** Also flagged: NWS gridpoint forecasts are
deterministic values, not probabilities, so converting "predicted high 78°"
into "P(high > 75°)" requires a per-station, per-lead-time forecast-error
distribution. That error model *is* the strategy; NBM probabilistic
guidance may supply it directly and should be checked first.

### Phase 0 implementation — the two live bugs fixed (157/157 tests passing)
Operator pushed back on the proposed sequencing ("if we'll eventually need
all the code anyway, continue with that... I don't want zombie code — but
sounds like what we build is needed still right?"). Correct, and it
reframed the plan usefully: **these were never S6 prerequisites, they are
outstanding bug fixes to live code that had been mislabeled as S6
scaffolding.** Neither becomes unnecessary if S6 dies. Done on that basis.

**1. The dollars-vs-contracts unit bug (Session 28 entry 3) — FIXED.**
`RiskGateAgent._calculate_position_size` returned Kelly **dollars**;
`PaperExecutor` wrote that number straight into each leg's `"quantity"`
and `PositionTracker` booked `price × quantity`. It only ever balanced
because an S1 YES+NO pair costs ≈$1. Now:
- Returns an **integer contract count** — a dollar budget divided by
  `_basket_cost_per_contract()` (sum of leg ask prices), floored, with
  anything under 1 contract returning 0. Session 27's 0.05-contract paper
  trade could not have existed on Kalshi.
- **Riskless vs statistical sizing split.** `RISKLESS_STRATEGIES`
  (S1/S2/S5a/S5b) size against the caps, which removes the hidden
  ~5.26% minimum-edge floor that Kelly at a hardcoded `p=0.95` was
  silently imposing and that made `s1_min_net_profit_pct=0.5` a dead
  letter. A test now pins this directly: a 0.6% riskless edge must size
  positively.
- **Kelly, correctly, for statistical strategies**: `f* = (p − c)/(1 − c)`,
  fed by a new additive `OpportunityEvent.model_probability`. If that field
  is absent, the trade sizes to **0** rather than falling back to a
  hardcoded pseudo-probability — the exact bug being fixed.
- Check 2 (`POSITION_TOO_LARGE`) now falls back to the derived basket cost
  when `capital_required_usd` is unset, so a check that had **never once
  run** finally binds.
- The approval log emits `size_contracts` and `cost_usd` instead of
  `size_usd`, so historical log lines can't be misread the same way again.
- `KalshiFeeModel.taker_fee_dollars()` added, implementing Kalshi's real
  per-order round-up — validated against the published fee table
  (1 contract @ $0.10 → $0.01; 100 @ $0.50 → $1.75; 100 @ $0.30 → $1.47).
  The old continuous `taker_fee_fraction()` is kept but now documented as
  systematically optimistic, worst on the tiny orders this system places.

**2. `from_yaml()` silently ignoring four config sections — FIXED.**
`data_feeds:`, `capital:`, `risk:`, `strategies:` and `intelligence:` are
now parsed through a generic `_section()` helper that additionally
**warns on unknown keys** (`config_unknown_keys`). That warning is the
point: Session 24 lost three live deploys to a flag that looked configured
and did nothing. RiskConfig's `ABSOLUTE_*` ceilings and the Phase 1
invariants still bind against YAML — both explicitly tested, so making
these sections configurable did not become a way to configure past the
hard limits.

**Test note worth recording**: three existing liquidity-cap tests failed
against the new sizing, and the reason was diagnostic rather than
incidental — they constructed `OpportunityEvent`s with **no legs at all**,
which passed under the old code because sizing never looked at what it was
buying. That is the unit bug in miniature. Updated to carry real ask-priced
legs, with each test's original intent preserved.

157/157 passing; runner smoke test exits cleanly with S1 canary firing as
designed.

### Deployed to the VPS and verified live — which surfaced a real regression
Deployed (`git pull` + `systemctl restart`), VPS now at `f88584e` = `main`.
Checked the config first rather than pulling blind: the box's `config.yaml`
contains only `system:`, `trading:`, `telegram:` and
`regulatory_intelligence:` — all sections that were *already* parsed — so
the config-parsing change is a **no-op** there and could not silently alter
live behaviour. Post-restart: service active, `config_resolved` shows
`telegram_enabled=True kalshi_ws_enabled=True polymarket_ws_enabled=False
regulatory_intelligence_enabled=True paper_mode=True phase=1`, **no
`config_unknown_keys` warnings** (so no typos in the live config), zero
tracebacks, no restarts.

**Then a check that produced a false alarm — the session's fourth wrong
conclusion, and the most instructive.** Measured the event mix over 10
minutes:
```
book_snapshot_requested   2174
book_reset_rest_failed      16     (all HTTP 429)
book_snapshot_applied        0
```
Reported this as a regression to ~0% book-reset completion, matching the
pre-fix Session 22 signature. **Wrong.** Reading the code instead of the log
names showed both halves were naming artifacts:
- `book_snapshot_requested` was logged **after** a successful
  `apply_snapshot()`, so despite its name it counted *completed recoveries*.
- `book_snapshot_applied` exists only inside `OrderBook.apply_snapshot` at
  **DEBUG**, filtered out of production since Session 26 — it could never
  have appeared at any health level.

**Correct reading: 2,174 successful REST recoveries in 10 minutes against 16
failures — 0.7%, better than Session 23's confirmed 5.5%.** The mechanism is
healthy.

Fixed rather than just retracted: the INFO log is renamed
`book_snapshot_applied_rest` and now carries `bid_levels`/`ask_levels`, with
a comment recording why the name matters. **Consequence for historical
analysis: any prior session's numbers that grep `book_snapshot_requested`
were counting successes, not attempts** — including Session 22's own
regression evidence, which should be re-read with that in mind. There is
currently no attempt counter at all; add one deliberately if the
attempt-vs-success ratio is ever wanted.

Also noticed and newly documented: `RSS parse error: mismatched tag: line
26, column 4` fires twice at every startup in `RegulatoryIntelligenceAgent`
— one configured feed serves malformed XML and is silently contributing
nothing. The cycle survives it. Low severity, previously unrecorded.

**Process note — four wrong conclusions in one session, same root cause.**
Maker fees (three agreeing secondary sources, none mentioning the default
multiplier), VPS access (one directory listing treated as a search), the
book-reset "regression" (two log names taken at face value without reading
the code that emits them), and the build-order sequencing. Every one was a
confident negative or positive conclusion drawn from an *incomplete search*,
and every one was caught by going one step further — reading the primary
source, asking the operator, grepping the emitting code. The instinct to
verify was right every time; the stopping point was too early. That is the
specific discipline to carry forward, and it is worth more than any
individual finding here: **"deployed" is not "confirmed live," "the service
is active" is not "the service is working," and a log line's name is not
evidence of what it measures.**

### Alternative / unconventional data — SIGNAL_REGISTER.md created
Operator raised a broad set of candidate data sources (weather-modification
and cloud-seeding trackers, ADS-B, satellite loops, solar/lunar/tidal and
geophysical events, launch schedules, Farmer's Almanac) and asked that it
be documented and treated as an open question rather than pre-judged —
*"data is data... awareness and an open mind keeps one able to make
connections not anticipated."*

Created `SIGNAL_REGISTER.md`: a standing, tiered register with a hard
methodology gate. Two things worth surfacing from it here:
- **The strongest item on the list is an official government registry.**
  Weather modification is real, legal and funded; NOAA maintains a
  legally-required public repository of project reports, and filers must
  report **≥10 days before activity commences**. Advance public notice of
  planned cloud seeding has a direct physical path to precipitation
  markets. (Caveat flagged in the register: the repository publishes
  *quarterly*, so whether filings are visible at submission time or only at
  publication is **unverified and decisive** for tradability.)
- **The real risk is multiple comparisons, not the subject matter.**
  ~800–5,000 settled outcomes against hundreds of candidate signals will
  manufacture "significant" findings by construction. The register makes
  the vision doc's own guardrails mandatory (Bonferroni/FDR, n≥20,
  replication across 3 periods, ≥2h lead, out-of-sample, and always the
  market price as baseline). Also documented: contrail-report data has a
  textbook common-cause confound — persistent contrails form because of
  upper-atmosphere humidity and temperature, so they will correlate with
  weather without predicting it, and must be tested against an
  NBM-conditioned baseline.

### Also decided: the 30-day paper clock is reset, not paused
It started 2026-06-29 targeting 2026-07-29 — a date that has now passed.
That window is not usable evidence: 9 of its first 14 days had a dead
persistence layer (Session 26) and every S1 trade in it is a confirmed
book-reconstruction artifact (Session 29). Clock restarts when a strategy
that passes its gates actually begins paper trading. CLAUDE.md updated so
the stale dates stop reading as live.

### A second self-inflicted error the same session: "VPS access lost"
This session checked `~/.ssh/`, found only `id_rsa`, saw it rejected by
the VPS, and concluded **"VPS access lost — state unknown"** — writing
that into CLAUDE.md, SESSIONS.md and README.md and committing it. The
operator then simply logged in: the key lives at
**`~/kalshi-keys/oracle-vps.key`**, outside `~/.ssh/` entirely.

`ssh -i ~/kalshi-keys/oracle-vps.key ubuntu@147.224.209.18` — recorded in
CLAUDE.md so no future session repeats this. Same root cause as the
maker-fee error an hour earlier: a confident negative conclusion drawn
from an incomplete search, when asking would have cost one question.

**VPS state, now actually CONFIRMED LIVE (2026-08-02 ~04:00 UTC)**:
service `karbot` **active**, uptime 35 days, disk **17% of 49G** (healthy
— the Session 26 outage was 100%), repo at `d1ac08c` = one commit behind
`main` after this session's docs-only push, which is expected since no
code changed. Pending: a `*** System restart required ***` notice and 12
updates including 3 security updates — worth scheduling.

### Still unverified — reported, not assumed
1. **A local `logs/audit_trail.jsonl` write at 2026-08-02T03:11 UTC** (a
   `DailySummary` compliance checkpoint) with **no** `karbot_runner`
   process currently running locally (`ps` count 0). Something started and
   exited, or the file is being synced from elsewhere. Not investigated,
   not load-bearing for this session's work, but flagged rather than
   ignored — an unexplained write to a compliance log is exactly the sort
   of thing this project has learned not to wave off.

### Vision-doc re-read (all four April 2026 .docx)
Kept: Options Signal Agent (becomes the second `FairValueProvider`, not a
separate agent), Health Monitor (still missing, more important once
positions carry variance), and the *problem* the Portfolio Manager exists
to solve (correlated exposure) — though solved with a RiskGate correlation
cap, not the specced Bull/Bear LLM debate. Set aside with reasons: News
Analyst / Sentiment / Geopolitical (diffuse signals into directional bets
with no calibration infrastructure), Whale Tracker / Resolution Verifier
(Phase 2 only), and the Correlation Engine / 12-persona panel — whose
premise ("test thousands of speculative correlations") is in direct tension
with the one discipline that has actually produced results here. Its first
legitimate instance already exists inside this plan: measuring whether the
fair-value model beats the market price, per category, over time. That is
the correlation engine in miniature, and the version worth building first.
One more find from the re-read: the vision's own S1 trigger
("YES_price + NO_price < 1.00") never said *which side of the book* — the
ambiguity that became the Session 26 sign bug and the Session 28 structural
finding was in the spec from day one. The S6 spec names the executable
price side and the settlement source explicitly for exactly that reason.

### Not done, deliberately
No strategy code, no new agents, no config changes, no tests — spec-only
mandate. Nothing was deleted or gutted: S1 canary, S2/S3/S4 groundwork, the
event bus, order-book reconstruction, RiskGate, PaperExecutor,
ComplianceOfficer and the Telegram agent all stay exactly as they are, as
reusable substrate. Test suite untouched at 133/133 from Session 29 (not
re-run this session — no code changed).

---

## 2026-07-16 (Session 29 — independently verified Session 28's S1 finding live; implemented S1 canary mode, Telegram sender-auth fix, disk-alert.sh secrets-path fix)

### Independent verification of Session 28's core claim
Before acting on Fable's review, ran its own specified verification plan
rather than trusting the analysis on its word:

1. **Rest-state scan**: pulled 778 real, currently-quoted Kalshi markets
   directly via the public REST markets endpoint. **0/778** show a
   crossed book (`yes_bid + no_bid >= 1.00`). Exact match to the
   structural prediction ("zero").
2. **Trade/gap correlation**: checked all 5 of Session 27's real trades
   against `sequence_gap_detected` activity on their exact market at
   their exact timestamp (pulled market_id per trade from
   `audit_trail.jsonl`, since `opportunity_approved` logs don't include
   it). **5/5 fired in the same second** as a sequence-gap event on that
   specific market — not "nearby," concurrent. Confirms Session 28's
   prediction ("most or all correlate") at 100%, not partial.

Verification plan item 3 (persistence test — do candidates survive to
the next delta) not run this session; items 1-2 were already
sufficiently conclusive to act on.

**Conclusion: Session 28's finding is confirmed, not just argued.**
Every S1 signal observed to date, including all 5 "hand-verified" paper
trades, correlates with a known book-reconstruction failure mode. S1
must stop trading (even in paper mode) until the underlying
reconstruction bug is fixed and independently re-verified.

### Fixed this session
1. **S1 canary mode** (`karbot/core/config.py`:
   `StrategiesConfig.s1_canary_mode`, default `True`) — `arb_scanner.py`
   `_check_s1_rebalancing` still detects and logs every candidate
   (`s1_opportunity_found_canary_only`, useful as a data-quality
   signal — a hit means the local book disagrees with a state the
   exchange permits) but never returns a real `OpportunityEvent`, so
   nothing downstream (`RiskGate`/`PaperExecutor`) can act on it. No
   more S1 trades, paper or otherwise, until this is deliberately turned
   off after the reconstruction bug is actually fixed. 3 new tests;
   existing S1 pipeline tests updated to explicitly set
   `s1_canary_mode = False` where they test the underlying mechanics
   (pricing, ceiling, liquidity cap) rather than canary behavior itself.
2. **Telegram sender-auth (SECURITY, HIGH)**: `_poll_updates` previously
   processed a message from **any** Telegram user as an authoritative
   operator command — confirmed by reading the code, exactly as Session
   28 found. Also confirmed live: the VPS's `config.yaml` still uses the
   default, publicly-committed `regulatory_clear_phrase` ("CLEAR
   REGULATORY HOLD"), meaning anyone who found the bot could have sent
   that phrase and had it processed as if from the operator. Fixed:
   `_is_authorized_sender()` checks `msg.chat.id` against the configured
   `TELEGRAM_CHAT_ID` before dispatching to `_handle_operator_reply`;
   unauthorized messages are dropped and logged. 4 new tests. **Not yet
   done**: rotating the VPS's regulatory clear phrase to a non-default
   value — flagged for next session, low-risk to do but touches live
   VPS config outside tonight's scope.
3. **`karbot-disk-alert.sh` reading the wrong (deleted) secrets path**
   — Session 28 flagged this as worth verifying; checked and confirmed
   true: the script still hardcoded
   `ENV_FILE="/home/ubuntu/karbotrage_v1/.env"`, the exact path Session
   26 deleted after moving secrets to `/etc/karbot/secrets/karbot.env`.
   Because the script's `grep ... || true` swallows a missing-file error
   silently, this had been failing silently since Session 26 — the
   disk-space watchdog built specifically to prevent a repeat of the
   9-day silent outage was itself silently broken. Fixed the path on the
   VPS directly, verified live with a real test message send.

### What to do next
See CLAUDE.md's rewritten priorities (Session 28/29 combined) — the
remaining Session 28 items (kill switch has no trigger path, RiskGate
unit mismatch, S2/S3/S4 all need fixing or disabling, S5a/S5b build-out)
are substantial and not yet started. Prioritized in CLAUDE.md.

### Addendum, same session — Phase 1 safety cleanup completed, Phase 2 empirical check on S5a/S5b run BEFORE writing any strategy code
Operator asked directly whether continuing was worth the effort, or
whether this project was "trying to make a square peg fit into a round
hole." Answered honestly rather than defaulting to optimism: proceed to
a cheap empirical check first, gate any real building on what it shows.

**Phase 1 (done)**: wired `KillSwitchEvent` to a real trigger for the
first time — the Telegram operator channel, gated behind the Session
28/29 sender-auth fix, listening for `TelegramConfig.kill_switch_phrase`
(default `"EMERGENCY KILL SWITCH"` — a predictable default is fine here,
unlike the regulatory phrase, since an unauthorized trigger only *halts*
trading, a safe failure). 6 new tests. Also disabled S3/S4 by default
(both confirmed broken/unreachable per the Session 28 audit) and rotated
the VPS's `regulatory_clear_phrase` off the public default — confirmed
`from_yaml()` actually parses the `regulatory_intelligence` section
(unlike the known `strategies:` gap) before trusting the change took
effect, verified live via clean restart. All deployed, 133/133 tests
passing.

**Phase 2 (done) — the actual answer to "is this worth it," checked
empirically rather than argued**:
- **S5a (event sum-to-one basket)**: pulled 1,600 real open markets,
  grouped into 313 multi-market events, found 78 that looked like naive
  sum-to-one candidates (`Σyes_ask < 1` or `Σno_ask < N-1`). Checked
  every single one's actual `mutually_exclusive` flag via the events
  endpoint (the exact check Fable's own spec called for and that a
  first-pass naive scan skips) — **0 of 78 are real basket candidates**.
  Every one turned out to be a threshold/spread/total ladder (team
  totals, player props, temperature ranges) misidentified as a
  mutually-exclusive outcome set by summing markets that share an
  `event_ticker` without checking the flag — the same class of
  "too-good-to-be-true, verify before trusting" trap S1 fell into,
  just caught before any code was written this time. Does not rule out
  S5a existing on genuine winner-take-all events (elections, award
  winners) not well-represented in this particular sample — not yet
  checked.
- **S5b (threshold/date-ladder arb)**: took the real ladder families
  the S5a scan surfaced (which are exactly S5b's intended target) and
  computed the actual arbitrage condition properly — `yes_ask(low
  strike) + no_ask(high strike) < 1` — across every strike pair, not
  just adjacent ones, on 8 diverse real live ladders (temperature ×5,
  gold, silver, oil). **Closest any of them got to a real arbitrage was
  1.01; none crossed below 1.00.** Same efficient-market signature as
  S1's real (non-fake) order books.

**Honest read given this**: neither S5a nor S5b shows a *currently
sitting, obviously exploitable* opportunity in this real, live sample.
This doesn't prove they never will — real arb (if it exists) is
inherently sporadic, and a single point-in-time snapshot can't rule out
rare windows during volatility or thin off-hours trading — but it does
mean there's no free lunch quietly waiting to be scooped up right now
either. This matches the third-party-corroborated expectation from
Session 28 ("thin... not a gold mine") almost exactly, just confirmed
with real numbers instead of taken on faith.

### Revised recommendation
Given this, building full S5a/S5b scanners immediately is a judgment
call, not an obvious next step — detect-and-log mode over 1-2 weeks
(Fable's original sequencing) would still be needed to catch the rare
real windows this snapshot can't see, but that's a real time investment
for something not yet confirmed to pay off, versus the cheap, decisive
checks that killed S1 and (so far) haven't found anything to build on
for S5a/S5b either. Operator should decide whether to invest that time
or reconsider direction (e.g. market-making, per Session 28's "S8" note,
or a broader S5a search across genuine winner-take-all events) before
committing more building effort.

---

## 2026-07-16 (Session 28 — strategy/architecture review, ANALYSIS ONLY, no code changed: S1 found structurally impossible on Kalshi; S2/S3/S4 audited and all defective; Telegram security hole; new strategy roadmap)

### Context and mandate
Operator used temporary access to a more capable model (planned in
Session 27) for a full fresh-eyes strategy/architecture review:
independently re-derive the S1 math, audit S2/S3/S4 for the Session 26
bug class, assess the RiskGate dollar/quantity mismatch, do a security
pass, read the four original April-2026 planning docs
(`~/Projects/karbotrage/Karbot_Rage_*.docx`), and propose new
strategies. Explicitly review-only: all output is documentation
(DECISIONS.md — five new entries, CLAUDE.md — KNOWN DEBT + priorities,
this entry). Nothing committed or pushed; no VPS access used.

### Headline finding: S1 cannot exist on Kalshi — the strategy was chasing a state the exchange's matching engine deletes on contact
Re-deriving the Session 26 math from scratch confirmed the sign fix was
correct — and surfaced what it implies one step further on. The
corrected condition `yes_ask + no_ask < 1` is algebraically identical
to `yes_bid + no_bid > 1` (because `yes_ask = 1 − no_bid` and
`no_ask = 1 − yes_bid` on Kalshi's bid-only unified book). That is a
**crossed book**: in Kalshi's own representation, a bid resting above
an ask in the same order book. A price-time-priority matching engine
matches crossed orders immediately — two bids summing over $1 are
minted into a contract pair the moment the second arrives (Kalshi's
help center describes the automatic pairing directly). So a correct,
current view of any Kalshi book can NEVER satisfy S1's trigger. Every
S1 signal in this system's history — before and after the sign fix —
was a view of the book the exchange itself never had. Third-party
corroboration: botforkalshi.com's arbitrage guide calls single-market
YES+NO arb a myth in exactly these terms ("never a harvestable gap...
the 'gap' you see is the bid-ask spread itself"). Every live book this
project has ever documented (0.23/0.30, 0.42/0.40, 0.47/0.51) sums its
bids below $1, as the argument requires.

Two known-live mechanisms explain the residual ~2 signals/day that
survived Session 26's fixes: (1) **mid-match multi-delta transitions** —
one atomic server-side match arrives as multiple WS deltas, and
`ArbScanner` evaluates on every delta, reading half-applied crossed
states at full confidence (Session 15's confirmed +523/−523 paired
deltas are this exact shape); (2) **stale phantom bids** from the
still-unfixed stuck book-reset loops. Session 27's dollar-exact hand
verification checked arithmetic from recorded prices; PaperExecutor
fills unconditionally at recorded prices, so that check cannot detect
unfillable prices — same trap as Session 26's "tests internally
consistent with a wrong formula."

**Not yet live-verified.** Three cheap tests are specced in DECISIONS.md
(REST rest-state scan across ~200 books, gap-log correlation for the 5
Session 27 trades, candidate persistence-to-next-delta). Until they
run: treat all S1 paper P&L, including Session 27's $11.79, as artifact
measurement, not edge evidence. If confirmed, S1's honest role is a
data-quality canary — an S1 signal means our book disagrees with a
state the exchange permits, i.e. a reconstruction bug detector.

### S2/S3/S4 audit (Step 2 of the mandate) — all three share the bid-side bug; each is also dead upstream
Full detail in DECISIONS.md ("strategy audit" entry). Compressed:
- **S2**: sums BID prices for a two-platform BUY (same sign bug class
  S1 had); exact-`market_id` cross-platform matching can never hit
  (Kalshi tickers vs Polymarket condition ids); Polymarket fee model
  outdated; no depth cap. Latent, not live (phase gate + RiskGate
  check 6 auto-rejects unverified cross-platform trades).
- **S3**: the "live with zero candidates" framing was wrong —
  `MarketAnalyst.update_markets()` has **zero callers**, so
  `_active_markets` is always empty and the LLM analysis loop has
  skipped every cycle since it was written. S3 has never analyzed one
  market or spent one API cent in production. Additionally: prices off
  `yes_bid` (wrong side), an EMPTY book reads as `yes_bid=0.0` and
  inflates `edge_pct` to `market_a_price × 100` (the thinner the book,
  the bigger the phantom edge), and single-leg S3 is a statistical
  convergence bet, not arb — the riskless form is paired
  (buy YES(B) + NO(A), payout ≥ $1 whenever A⇒B holds).
- **S4**: unreachable (no `NewsSignalEvent` publisher exists — News
  Analyst was never built) behind an enabled-by-default flag; prices
  off `yes_bid`; hardcoded 0.95 target/1.0% fee/0.5% slippage; and it
  is directional speculation, not arbitrage — should be specced as such
  when it's real.
- Bonus: `ReflectionAgent`'s `StrategyWeightUpdateEvent` output is
  stored by ArbScanner and never read by any decision — the learning
  loop's actuator is a dead knob.

### RiskGate unit mismatch (Step 2) — confirmed, traced, and worse than flagged
`_calculate_position_size` outputs Kelly **dollars**; `PaperExecutor`
consumes `approved_size` as per-leg **contract quantity**;
`PositionTracker` books `price × quantity`. It balanced for 63 hours
because an S1 YES+NO pair costs ≈ $1, making dollars ≈ contracts by
coincidence of the strategy's shape; any single-leg strategy breaks it
by a factor of 1/price. The deeper find: Kelly at p=0.95 sizes to zero
below `q/p ≈ 5.26%` net — so `s1_min_net_profit_pct=0.5` never
mattered, the system structurally rejected all small (i.e. all
plausible) edges and traded only implausible ones. Accidentally
protective given the artifact finding; wrong by design. Also:
`capital_required_usd` is never populated so RiskGate check 2 has never
run; Kalshi requires integer contracts ≥ 1 (the 0.05-contract Session
27 trade cannot exist live); Kalshi fees round UP to the next cent,
which the continuous `KalshiFeeModel` underestimates precisely on the
tiny liquidity-capped orders this system actually does. Maker orders
pay no fee on most markets — relevant to the market-making proposal
below. Fix direction specced in DECISIONS.md (integer-contract unit
system; cap-based sizing for riskless strategies; Kelly only for
statistical ones).

### Security pass (Step 2) — one HIGH finding, several secondary
- **HIGH: Telegram trusts any sender.** `_poll_updates` never checks
  `message.chat.id` against `TELEGRAM_CHAT_ID`. Anyone who finds the
  bot's username can approve pending permission requests ("yes"), clear
  an urgency-5 regulatory halt (the default clear phrase "CLEAR
  REGULATORY HOLD" is committed in the public repo), and will own any
  future operator commands (/mute, kill switch). ~5-line fix; top of
  the priority list; must land before any operator-command expansion.
- Secondary: bot token can leak into logs via raw aiohttp exception
  interpolation (URLs embed the token); kill switch has **no trigger
  path at all** (no `KillSwitchEvent` publisher, no
  `activate_kill_switch` caller — vision doc required CLI + dashboard +
  Telegram paths); `AnnouncementWarningEvent`/`GeopoliticalRiskEvent`
  have no publishers either (risk-gate checks 4/5 can never fire from
  real data); VPS runs as sudo-capable `ubuntu`, not the dedicated
  service user CLAUDE.md's own rules require; and
  `/usr/local/bin/karbot-disk-alert.sh` was written to read the repo
  `.env` that Session 26 itself deleted hours later — **verify on the
  VPS**, the disk watchdog may have been silently dead since
  2026-07-13. Positive: secrets handling is genuinely clean (env-only,
  gitignore confirmed for `.env`/`config.yaml`, no secret values in any
  log call found, no secrets in the local config.yaml).

### Vision-vs-implementation gaps (from the four planning docs)
The April 2026 docs spec 16 agents; 10 exist. Not built: Execution
Agent (live), News Analyst (→ S4 dead), Sentiment, Geopolitical (→ geo
risk input dead), Options Signal (S6 — the docs' self-described "secret
weapon"), Whale Tracker, Resolution Verifier (→ S2 hard-blocked),
Portfolio Manager (Bull/Bear debate, the $200+ trade gate), Health
Monitor (→ the dead-lettered heartbeats). Strategies S5 (combinatorial
— includes what this review proposes as S5a), S6, S7 unbuilt. Economic
calendar, dashboard, monthly IRS exports, backtesting framework,
Manifold-as-sandbox: all unbuilt. Two vision details worth flagging:
the docs' own S1 trigger ("YES_price + NO_price < 1.00") never said
which side of the book — the bid/ask ambiguity that became the Session
26 bug (and this session's structural finding) was present in the spec
from day one; and the architecture doc's "everything configurable"
principle is violated by `from_yaml()` silently ignoring `capital:`,
`risk:`, `strategies:`, and `data_feeds:` sections (capital is
permanently the $10k paper default on the VPS). Also `--mode` on
karbot_runner.py is parsed and never applied.

### New strategy analysis (Step 3) — categorized by risk type
**TRUE RISKLESS ARB (S1's intended guarantee class, all Kalshi-only):**
1. **S5a — event sum-to-one baskets** (top recommendation): Kalshi does
   NOT atomically match across the N separate markets of a
   multi-outcome event, so basket mispricings can genuinely rest.
   YES-basket (`Σ yes_ask < 1 − fees`, requires the event be exhaustive)
   and NO-basket (`Σ no_ask < (N−1) − fees`, requires only mutual
   exclusivity — robust to none-of-the-above). Kalshi's API exposes
   `event_ticker` and `mutually_exclusive`. Residual real risks: N legs
   fill independently (no atomic basket order — partial-fill exposure
   for seconds), ceil'd per-order fees × N legs kill thin/longshot
   baskets, capital locked to resolution. Third-party experience says
   candidates are real but thin — measure before believing.
2. **S5b — threshold/date-ladder arb**: deterministic S3 with no LLM.
   A = "metric > x_hi" implies B = "metric > x_lo" by arithmetic alone
   (strike parsed from ticker/`floor_strike`); when priced backwards,
   buy YES(B)+NO(A) at ask → payout ≥ $1 always ($2 between strikes);
   arb iff cost < 1 − fees. Zero semantic risk, same machinery as S5a.
**CORRELATED/STATISTICAL EDGE (real but with variance — build only
after the riskless layer is measured):**
3. **S8 — market making**: maker fee = $0 on most Kalshi markets and
   every live book observed sits just outside taker break-even — i.e.
   just inside MAKER break-even. Quote both sides where spread >
   fees+buffer; inventory/adverse-selection risk until offset; needs a
   live order-management layer (place/cancel/track) that doesn't exist.
   The most promising non-arb idea, and Kalshi-sanctioned (they run MM
   programs).
4. **Paired S3 via LLM** (riskless-if-relation-holds): the tail risk
   lives in the LLM's judgment that A⇒B, not in prices. High
   confidence + human review of each new relation could make this
   near-arb; classify honestly as statistical until a relation
   whitelist exists.
5. **Public-model divergence trades**: Kalshi weather markets vs NOAA
   model output; Fed/CPI markets vs CME FedWatch and options-implied
   probabilities (the vision's S6); sports markets vs devigged sharp
   sportsbook closing lines. All are calibrated-source vs market-price
   divergence bets — directional variance, statistical edge, no
   guarantee.
**SPECULATIVE/DIRECTIONAL (deliberate departure from "safest first" —
flagged, not endorsed):** S4 news-speed settlement trading, S7
longshot-bias fade, whale following. Each needs calibration
infrastructure this project doesn't have yet; none belong in Phase 1.

### Cross-platform S2 assessment (Step 3, explicit per mandate)
S2's risk category is fundamentally different from S1/S5: the two legs
execute on different venues with no atomicity — a fill on one and a
miss/move on the other leaves an open, unhedged directional position,
converting "riskless" into "long one side of a news event at size."
Historical Kalshi/Polymarket gaps (1-5% on 2024 politics) have
compressed under competition; the remaining edge concentrates in exactly
the moments (breaking news) when leg risk is worst. Preconditions
before S2 is worth building: (1) Resolution Verifier agent (the 2024
government-shutdown divergence is the canonical warning — currently no
publisher exists for `ResolutionVerificationResult`, so RiskGate
correctly auto-rejects); (2) a real market-matching layer (semantic,
human-confirmed — exact-id matching never hits); (3) verified Polymarket
US legal-access status and current fee schedule (their US re-entry via a
CFTC-licensed entity was in progress as of mid-2026 — verify before any
integration; the vision docs' "never use a VPN" rule exists precisely
because of this); (4) pre-positioned capital on both venues (USDC rails
vs Kalshi ACH settle on different clocks — an unwind can't wait for a
transfer); (5) simultaneous IOC-limit submission sized ≤ min top-of-book
depth of both legs, plus an unwind protocol that accepts small realized
losses. Alternative second venues considered: **ForecastEx (IBKR)** — a
real CFTC DCM with overlapping econ/climate markets and a mature API,
institutionally cleaner than Polymarket but thin liquidity;
**PredictIt** — poor (fee structure + position caps); **Betfair/
Smarkets** — unavailable to US persons; **Manifold** — play money,
useful only as a free sandbox for testing S3/S5 detection logic (the
architecture doc already suggested this; still a good idea). Verdict:
S2 stays deferred behind S5a/S5b and market-making; if/when pursued,
tiny size, human approval per trade, Phase 2 gate intact.

### What was deliberately NOT done
No code changes, no commits, no pushes, no VPS access (the disk-alert
and trade/gap-correlation checks are specced for the implementation
session). README.md not updated — per the standing rule it gets
refreshed on the next push, alongside these doc changes. The 30-day
paper clock (target 2026-07-29) should be considered restarted-in-
spirit for whatever strategy replaces S1 — its S1 data measures
artifact frequency, not edge.

## 2026-07-16 (Session 27 — first real trades under the Session 26 fixes observed and hand-verified; scheduled viability-check task found broken; a Telegram display bug found and fixed)

*(Header restored 2026-07-16, Session 29 addendum — this entry existed in
full below but was missing its own `## ` heading, making it read as if
it were part of Session 28's "review-only, no code changed" entry
immediately above, which directly contradicts what it describes. No
content changed, only this heading added, once diagnosed as a real doc
bug rather than assumed away.)*

### Context
Operator scheduled a one-time task (`karbot-s1-viability-check`, fireAt
2026-07-15T09:00 EDT) at the end of Session 26 to check S1 viability data
after ~2 days of real operation. Operator returned unable to find the
report.

### The scheduled task fired but never completed — found and diagnosed
`list_scheduled_tasks` confirmed it fired on time (`lastRunAt:
2026-07-15T13:00:03Z`) and auto-disabled correctly. But its transcript
(found by tracing `scheduledTaskId` → session file → `cliSessionId` →
the actual `.jsonl` transcript under `~/.claude/projects/`) showed it
only got through 2 tool calls (an SSH status check, a local git log
comparison) before the session simply stopped — no final report was ever
written. Root cause not investigated further (infrastructure/harness
issue, not a Karbot Rage bug) — noted for awareness that scheduled tasks
in this environment aren't guaranteed to complete, not relied upon as a
sole reporting mechanism going forward.

### Real viability data pulled live instead (2026-07-13 20:04 UTC → 2026-07-16 11:17 UTC, ~63 hours)
- `s1_candidate_seen`: 244 (positive gross spread candidates)
- Cleared the trading threshold: 61
- `opportunity_approved` (real trades): **5**
- `ZERO_APPROVED_SIZE` rejections: 0 (the 2026-07-13 fix never needed to fire — good sign, not evidence it's broken)
- Sanity-ceiling rejections (implausible spreads still caught): 3
- Feed health transitions (down/recovered): 3

All 5 real trades, with dollar-exact hand-verified math on two of them (by the operator, independently, on paper):

| Time (UTC) | Size | Net % | Realized PnL |
|---|---|---|---|
| 7/13 23:54 | $10.00 | 5.99% | $0.60 |
| 7/15 18:04 | $1.00 | 8.95% | $0.09 |
| 7/15 19:33 | $81.36 | 12.91% | $10.50 |
| 7/16 09:00 | $5.00 | 11.89% | $0.59 |
| 7/16 11:12 | $0.05 | 8.30% | $0.00 (real, see below) |

Total: **$11.79 realized paper profit, 5 trades in ~2.6 days (~2/day)**.
Checked the Kelly math on the two biggest trades: both were liquidity-
capped, not capital-capped — e.g. the $81.36 trade's real edge would
have sized to ~$844 under pure Kelly on a $10k account, but only ~$81
of real order-book depth existed at the quoted price. Consistent
pattern across every trade so far: real depth, not capital, is the
binding constraint. This is real, positive, if modest, evidence that
the corrected S1 strategy works — genuine small edges are showing up at
roughly 2/day, not zero and not constant, exactly the "thin, rare,
liquidity-limited" shape predicted.

### A live "regression" that wasn't — Telegram display bug found and fixed
The 2026-07-16 11:12 trade showed in Telegram as "YES @0.17 x0 / NO
@0.72 x0", "Expected PnL: $0.00", "Fees: $0.00" — looked exactly like
the `size_usd=0.0` bug fixed in Session 26 had regressed. Investigated
via VPS logs before assuming either way: `ZERO_APPROVED_SIZE` count was
0 for the whole window, and the actual log line showed
`size_usd=0.05` — a real, legitimate, liquidity-capped 5-cent trade,
correctly *not* rejected (0.05 > 0). The zero-size fix worked exactly as
intended; the confusion was purely `telegram_agent.py` formatting
(`:.0f` for quantity, `:.2f` for dollars) rounding small-but-real values
down to what looked like zero.

Fixed: `TelegramNotificationAgent._fmt_qty()` (uses `.4g` — "10" stays
"10", "0.05" stays "0.05") and `_fmt_usd()` (extra precision under 1
cent, e.g. "0.0042" instead of "0.00") wired into both the trade-opened
and trade-resolved messages. 8 new tests, 120/120 total passing.

### Also confirmed live for the first time: Telegram feed-health alerting
The 3 feed-health transitions in the operator's Telegram (`FEED DOWN` /
`FEED RECOVERED` / `FEED DOWN`) are the first real disconnect/reconnect
pair ever observed firing correctly in production — this was flagged as
unconfirmed since Session 19 across multiple sessions. Closing that out.

### What to do next
1. Operator has limited access to a more capable model (Fable) for "a
   couple more days" — plan is to use it for: independently re-verifying
   the S1 bid/ask and fee math from Session 26, auditing S2/S3/S4 for
   the same class of bugs, the RiskGate dollar/quantity unit mismatch
   (flagged Session 26, not fixed), a security-focused pass, and
   brainstorming strategies not yet in the codebase (e.g. multi-way
   "sum-to-one" arbitrage generalizing S1 beyond 2-outcome markets;
   market-making instead of only taking liquidity, given real spreads
   observed sitting just slightly in the market's favor).
2. Continue letting real S1 (and S3, already running, 0 candidates
   observed so far) trades accumulate — 5 trades is still a small
   sample.
3. Everything else from Session 26's next-priorities list is still open
   (stuck order-book reset loop, re-audit "CONFIRMED LIVE" claims, paper
   fee variance, S1 multi-level depth walk).

---

## 2026-07-13 (Session 26 — VPS silently dead for 9 days: disk-full outage found and fixed; VPS discovered 4 commits behind main; P&L inflation reproduced live with a concrete root-cause candidate)

### Context
No session or commit had touched this project since Session 25 (2026-07-01). Operator asked to review status and get moving again toward live trading. Live investigation (VPS SSH access recovered — credentials were `ubuntu@147.224.209.18` with `~/kalshi-keys/oracle-vps.key`, not any of the previously-guessed usernames) immediately surfaced a serious, previously-undetected production outage.

### What was found
- **VPS disk was 100% full since 2026-07-04 03:23 UTC** (9 days). `compliance.db`, `kalshi_trades.csv`, and `audit_trail.jsonl` all stopped receiving writes at that point — last real trade write was `2026-07-04T00:05:19`. `systemctl status karbot` showed "active (running)" the entire time — **this failure was completely silent**, no alert, no crash, nothing in the existing Telegram alerting caught it (that alerting only covers feed disconnects and restart-budget exhaustion, not disk space).
- **Root cause of the full disk**: `/var/log/syslog` had grown to 47.5GB of the 49GB disk. `structlog.get_logger()` is used throughout every agent, but `structlog.configure()` was **never called anywhere in the codebase** — `logging.basicConfig(level=logging.INFO)` in `karbot_runner.py` only filters the stdlib root logger, not structlog's own rendering pipeline. Every `log.debug()` call has rendered unconditionally since this was written. This was invisible at normal volume but catastrophic combined with the next finding.
- **A specific order-book market gets stuck in a permanent reset loop**: live journalctl showed `book_needs_reset` → `book_reset_throttled` firing for the same market dozens of times within the same second, repeating indefinitely. The 10s per-market throttle (Session 22/23) only blocks the actual REST re-fetch — it does not suppress the debug logging that fires on every single delta received while the book is in a needs-reset state. Live count: **169 million `book_needs_reset` lines** in the syslog. This is the mechanism that filled the disk in under two weeks. The underlying "why does this book never actually resync" question is NOT fixed this session — only the log-volume symptom is.
- **The VPS was 4 git commits behind `main`** (`origin/main` was at `7057d8d`, missing `8a7e6ce`, `185dc6c`, and `7d022b9` — i.e. the Session 23 docs finalize, the Session 24 `config_resolved` fix, and the Session 25 duplicate-Telegram-alert removal). CLAUDE.md and README documented all three as "CONFIRMED LIVE" — **that was true of the commits, not of the deployed VPS code.** No prior session verified `git log` on the VPS itself before declaring something live. This is a process gap: "confirmed live" must mean confirmed against the actual running VPS HEAD, not just a local commit + a plausible-looking log line.
- **P&L inflation (KNOWN DEBT, flagged since Session 25) is confirmed real and actively reproducing**, observed live immediately after this session's clean restart (fresh code, fresh disk, no historical confound): `opportunity_approved` events showing `net_pct` values of 20.7%, 31.7%, 54.7%, 61.7%, 47.7% — against a realistic S1 benchmark of 1–5%. These fired in the same few seconds as multiple `sequence_gap_detected` warnings for different markets, directly supporting the existing hypothesis (corrupt/stale order books → bad spreads → phantom arb opportunities). **New concrete finding**: `agents/floor/arb_scanner.py` has a lower-bound rejection (`net_pct < s1_min_net_profit_pct`) but **no upper-bound sanity check at all** — nothing rejects a spread that's implausibly large, which is exactly what a stale/corrupt book would produce. Also observed: some `opportunity_approved` events have `size_usd=0.0` — zero-size trades being approved and executed, a separate minor bug.

### What was fixed
- `karbot_runner.py` — `setup_logging()` now calls `structlog.configure(wrapper_class=structlog.make_filtering_bound_logger(logging.INFO))`, so DEBUG-level structlog output is actually suppressed in production. Verified locally: `--mock-prices --exit-after-test` run is clean (no DEBUG lines), full test suite still 83/83 passing. Committed (`9b210fe`) and pushed to `origin/main`.
- VPS: `/var/log/syslog` truncated to free 45GB immediately; stale `kalshi_trades.csv.tmp` (0 bytes, orphaned from a torn write during the outage) removed; `karbot.service` restarted (paper mode, no real money — 19 in-flight `FILLED`-but-unresolved trades from before the outage were accepted as an acceptable loss rather than trying to recover their resolution timers).
- VPS: `git pull` to bring the deployed code up to `main` HEAD (`9b210fe`), which included the Session 23/24/25 fixes that had never actually been deployed, plus today's structlog fix. Restarted again after pull; confirmed live that the new process emits no DEBUG output and disk growth is back to a normal handful of MB over 15 minutes (was 45GB/9 days).
- VPS: `/etc/logrotate.d/rsyslog` — added `maxsize 300M` so oversized logs get rotated even between the existing weekly schedule, rather than waiting for a fixed calendar day. Added `/etc/cron.hourly/logrotate-size-check` (runs `logrotate /etc/logrotate.conf`) since the size check only fires when logrotate actually runs, and the default cadence (daily via anacron) was too slow to catch a fast-growing file in time.
- VPS: new independent disk-space watchdog, `/usr/local/bin/karbot-disk-alert.sh`, run every 15 minutes via `/etc/cron.d/karbot-disk-alert`. Deliberately outside the karbot app process (reads Telegram credentials directly from the `.env` file and calls the Telegram API via `curl`) so it keeps working even if `karbot.service` itself is wedged, crash-looping, or the disk issue is caused by the app itself. Alerts on crossing 80% usage, alerts again on recovery below 80%, debounced via a state file so it doesn't spam on every 15-minute check. Verified working live — a real test message was sent and confirmed received in Telegram.

### What was decided
- Freeing disk space and restarting the paper-trading service immediately was judged safe without a separate confirmation step, since it's paper mode (no real capital at risk) and the alternative (leaving the disk full) guarantees continued data loss — operator had already given a blanket "proceed however you see fit" for this category of fix.
- Pushed the structlog fix directly to `main` and deployed it rather than leaving it as an uncommitted local change, given the operator explicitly asked to "take charge" and get the system back to a trustworthy state; this is a config-only, test-covered, low-risk change.
- Did NOT attempt to fix the underlying stuck order-book loop or the arb-scanner sanity-check gap in this session — both are real code changes to core trading logic that deserve their own focused session with the operator, not a rushed fix bundled into an infra-outage response.

### Known debt this session did NOT resolve (carried forward, now with sharper root-cause evidence)
- **P&L inflation — still not fixed, now understood**: add an upper-bound sanity ceiling to `ArbScanner`'s S1 detection (e.g., reject/flag `net_pct` above some threshold like 10-15%, since real liquid-market S1 arb should be single-digit), and/or gate arb detection on order-book freshness (don't trust a book for pricing while it has an unresolved sequence gap or is < N seconds since last successful snapshot/delta). This is now the top blocker before live trading — the system has been generating phantom profitable opportunities, not real ones, for an unknown portion of the 30-day paper run.
- **Stuck order-book reset loop** — why does the specific book (e.g. `KXWORLDNEWSMENTION-26JUL10-WILD`) never actually complete recovery via the Session 22/23 REST-fetch mechanism? Needs its own investigation; the log-level fix only stops it from filling the disk, it doesn't stop the loop itself.
- **"CONFIRMED LIVE" claims in CLAUDE.md/README must be re-audited** — given three previously-documented "live" fixes were not actually deployed, treat every existing "CONFIRMED LIVE" claim in this doc as unverified until re-checked directly against VPS `git log -1` and live log output, not just trusted from prior session notes.
- **Secrets policy deviation found, not yet fixed**: `karbot.service`'s `EnvironmentFile=/home/ubuntu/karbotrage_v1/.env` — CLAUDE.md's VPS security rules explicitly say secrets should be injected via systemd `EnvironmentFile` **outside** the repo directory (e.g. `/etc/karbot/secrets/`), not from a `.env` inside the repo. The live VPS violates this. Not fixed this session (didn't want to touch the running secrets path during an active outage response) — flag for a dedicated session.
- Fee variance (Session 25 KNOWN DEBT) — not investigated this session; still open.
- 30-day paper trading clock (`started 2026-06-29, target 2026-07-29`) has a confirmed dead zone from 2026-07-04 to 2026-07-13 (9 of the 14 elapsed days had broken persistence) — any "30 days of clean paper data" claim needs to account for this gap.

### Addendum — same session, P&L root cause fixed and deployed
Operator asked a sharp clarifying question before letting this proceed:
could the 20-62% net_pct figures be genuine (if unusual) opportunities
rather than a bug? Investigated properly rather than asserting: (1)
mathematically, 60% net implies buying YES+NO for ~$0.40 total against a
guaranteed $1 payout — a mispricing that large would be arbed away by
Kalshi's own market makers in seconds, not persist; (2) it was happening
simultaneously across many unrelated markets (MLB, weather, geopolitics)
in the same few seconds, which rules out an isolated real dislocation;
(3) most conclusively, found the exact code defect: `_handle_kalshi_delta`
in `agents/floor/price_watcher.py` called `book.apply_delta(...)` and
**discarded its return value**. `apply_delta` returns `False` and sets
`_gap_detected = True` the instant a sequence gap is detected, but the
function fell straight through to `await self.bus.publish(book.to_price_event(...))`
regardless — publishing a `PriceUpdateEvent` built from the book's stale,
pre-gap prices on the exact delta that first revealed the book was
corrupt. Only the *next* delta for that market was blocked by the
existing `needs_reset` early-return; the triggering delta always leaked
through. `ArbScanner` then priced an "opportunity" off that stale data
with total confidence.

**Fixed**: check `apply_delta`'s return value; skip the publish (request a
fresh snapshot instead) when it reports a gap. Added
`s1_max_net_profit_pct` (default 15%, `karbot/core/config.py`) to
`ArbScanner` as defense-in-depth — logs loudly and rejects rather than
silently discarding, so any future data-quality issue is auditable instead
of invisible. 9 new tests (`test_price_watcher_gap_publish.py`,
`test_arb_scanner_s1_sanity_ceiling.py`), all passing alongside the
existing suite (92/92 total).

**Also fixed while in there**: operator noted the Telegram trade messages
were hard to interpret (bare trade_id + one dollar figure) and, worse,
`TelegramNotificationAgent` never subscribed to `TradeResolvedEvent` at
all — every message the operator ever saw was the pre-resolution
*estimate* (`expected_pnl_usd`, the same number driven by the bug above),
never the actual realized outcome. Added `_handle_trade_resolved`;
expanded both messages to include market_id, strategy, and per-leg
side/price/quantity, and labeled the entry message's PnL as "(estimate,
not final)" so it can't be mistaken for a settled result again. 3 new
tests (`test_telegram_trade_resolved.py`).

**Deployed and confirmed live**: pushed (`eb230ca`), pulled and restarted
on the VPS. Watched `opportunity_approved` events immediately after
restart: every approved trade now shows net_pct in the 0.7%-10.7% range
(vs. 20.7%-61.7% before the fix), while implausible spreads (27.7%,
38.7%-42.7% observed) are now correctly caught and rejected with a loud
`s1_opportunity_exceeds_sanity_ceiling` warning naming the market and
prices — auditable, not silent.

**New minor bug noticed while watching, not fixed**: several
`opportunity_approved` events show `size_usd=0.0` — zero-size trades
being approved and executed pointlessly. Separate from tonight's work;
flagged for a future session.

### Second addendum — same session: operator pushed back on "why are we still seeing implausible numbers," which led to the actual root cause

Operator asked directly why blocked events (27-42% net_pct) were still
appearing after the sanity-ceiling fix, and whether that was evidence the
"passing" 0.7-10.7% trades couldn't be trusted either. Right question —
investigated rather than reassured:

1. Pulled the real, live Kalshi order book for one flagged market
   directly from the REST API (ground truth, no app code involved). Found
   the quote was genuinely real, not stale — but backed by as little as 1
   contract. Traced the fill pipeline (`RiskGate._calculate_position_size`
   → `PaperExecutor`) and confirmed **no order-book depth was ever
   considered anywhere** — positions were sized purely off Kelly
   criterion and capital, then paper-filled in full at the top-of-book
   quote regardless of actual available size. This meant even
   "plausible"-looking trades could be simulating fills that never had
   real liquidity behind them.
2. Investigating how to size against real depth required understanding
   which side of the book a BUY order actually executes against — bids
   are prices *other participants* will pay, not prices this system can
   buy at. That question exposed something much larger: **`agents/floor/
   arb_scanner.py::_check_s1_rebalancing` computed profitability from
   `yes_bid + no_bid`, not `yes_ask + no_ask`** — the wrong side of the
   book for a BUY trade entirely. Verified against real numbers (not just
   algebra): a live Kalshi market with `yes_bid=0.23`/`no_bid=0.30` was
   reported as +47% profit by the old formula; the real executable cost
   via asks is $1.47 for a guaranteed $1 payout — a 47% **loss**. A
   second, unremarkable-looking example (`yes_bid=0.42`/`no_bid=0.40`,
   reported as a clean +3.7% edge) comes out to an 18% loss under the
   correct formula. Cross-checked against this project's own history:
   `SESSIONS.md` Session 2 (2026-05-25) recorded that the strategy's
   *original* spec prices (0.47/0.51) were rejected as unprofitable by
   whatever formula existed then, requiring invented 0.40/0.40 fixture
   prices instead — under the corrected ask-based formula, 0.47/0.51
   comes out to a small ~2% loss, exactly what a healthy, efficient
   market should look like. This is strong independent evidence the sign
   has been backwards since the very first working version of this
   strategy.
3. **This means every S1 "opportunity" this system has ever flagged as
   profitable was very likely a computed loss with the sign flipped** —
   not a data-quality issue on top of a sound strategy, but the strategy
   itself scoring the wrong side of the market since inception.

Full mathematical writeup, live verification, and historical
cross-check: **DECISIONS.md, "S1 arb formula uses BID prices for both
legs of a BUY trade."** Fixed with operator approval after a pause to
present the finding and confirm scope (`_check_s1_rebalancing` now reads
`event.yes_ask`/`event.no_ask`), alongside the liquidity-depth fix
designed together with it: `OrderBook.depth()` +
`PriceUpdateEvent.yes_ask_depth`/`no_ask_depth` expose real book depth at
the ask; `OpportunityEvent.max_fillable_qty` caps S1 size to what's
actually resting at the quoted price (top-of-book only, not a multi-level
walk — deliberately conservative scope); `RiskGate._calculate_position_size`
clips Kelly-derived size to that cap. Test fixtures updated to use
realistic ask-side prices large enough to clear both Kalshi's fee model
and the Kelly formula's own ~5.26% breakeven threshold at p=0.95 (the old
fixture's more modest ask prices were realistic but legitimately
Kelly-negative — correct behavior, not a bug to route around). 17
new/updated tests, 99/99 total passing.

**Deployed and confirmed live**: after restart, zero `opportunity_approved`
or ceiling-rejected events fired over ~4 minutes and 1,331 lines of book
activity — a dramatic, clean contrast with the pre-fix behavior where
nearly every price tick produced a "profitable" signal. This is the
expected, healthy result: real markets rarely offer a genuine executable
edge after fees, and the system was previously treating a near-universal
bid-side coincidence as if it were one.

**Revert point if this needs to be backed out**: commit `5348533`
(depth plumbing only, predates the formula fix, fully unaffected by it).

### What to do first next session
1. **Let real post-fix data accumulate and watch for the first genuine S1
   trade** — with the corrected formula, expect trades to be rare (real
   arbable edges after fees + Kelly's ~5.26% threshold don't come along
   often). Zero trades over the first several minutes is expected, not a
   bug; confirm the pipeline still fires when a real edge does appear.
2. Investigate the `size_usd=0.0` approved-trade bug noticed earlier this session.
3. Investigate the stuck order-book reset loop (why some books never complete recovery) — still open, only its disk-filling symptom was fixed.
4. Re-audit every "CONFIRMED LIVE" claim in CLAUDE.md against actual VPS state.
5. Move `.env` secrets off the repo path to `/etc/karbot/secrets/` per the documented (but currently violated) security policy.
6. Investigate the paper-trade fee variance (Session 25 KNOWN DEBT, still open).
7. Consider extending the S1 liquidity cap from top-of-book-only to a real multi-level depth walk (deliberately deferred tonight, not because it's unsafe post-fix, but to keep tonight's change reviewable) — would let the strategy price in reasonable size against a moderately deep book instead of capping hard at the first level.
8. Consider whether S2/S3/S4 (not touched tonight) have similar bid/ask or depth-blindness issues — this session only audited S1.

### Third addendum — same session: operator asked whether S1 is even a viable strategy, which surfaced a fourth bug (the fee model)

Operator's question wasn't "did you make a mistake" this time — it was
"even if the fix is correct, is single-market S1 arbitrage actually
capable of making money." Investigating that honestly required checking
one more input to the profitability calculation: `KalshiFeeModel`,
flagged in its own docstring as "approximate"/"simplified."

Fetched Kalshi's real, published fee schedule via web search + fetch:
taker fee = `0.07 * price * (1 - price)` per contract (peaks at 1.75% on
a 50c contract, falls toward zero at the extremes). `KalshiFeeModel` was
using a **flat 14% of trade value regardless of price** — roughly 4-8x
too high for a typical near-the-money contract. This directly gates
`s1_min_net_profit_pct`, meaning the system was very likely rejecting
real, small, genuinely profitable edges as "not enough to cover fees,"
compounding on top of the pricing and liquidity bugs found earlier
tonight.

Fixed: `KalshiFeeModel.taker_fee_fraction(price)` implements the real
formula; `estimate_fee_pct` sums real per-leg fees instead of a flat
constant; each `OpportunityEvent` leg now carries its own real fee
instead of an even split of a flat total. Test fixtures retuned — the
existing 0.40/0.40 fixture, calibrated against the old wrong 14%
assumption, scored 16.34% net under the corrected (much lower) fee and
would have been rejected by the sanity ceiling; retuned to 0.45/0.45
(net ~6.2%) to clear both the real fee total and the Kelly formula's
~5.26% breakeven threshold while staying under the ceiling. 8 new tests,
107/107 total passing.

**Deployed and confirmed live**: even with the much more accurate (and
substantially lower) fee estimate, zero opportunities fired over the
following observation window. This is a meaningful, honest data point
for the viability question — it means the earlier "zero opportunities"
result wasn't an artifact of an overly conservative fee assumption
suppressing real edges; real Kalshi markets during this sample window
genuinely aren't offering a crossable S1 edge after correcting for both
pricing direction and real fees.

### Honest viability assessment (not yet a verdict — needs real observation time)
Pure single-market S1 arbitrage on an actively market-made exchange is
a well-known, thin-margin, well-competed strategy — the two live order
books checked tonight both sat just slightly on the unprofitable side of
break-even ($1.01, $1.02 combined ask cost), which is the normal
signature of a functioning, roughly efficient market, not a broken one.
This means S1 alone should be expected to fire rarely — genuine
risk-free gains show up during brief real mispricings (thin/niche
markets, news-driven volatility), not constantly. Whether that's
"viable" as a standalone strategy depends on real trade frequency and
average edge size over a meaningful observation period, which requires
letting the corrected code run for real, not further code review. S1 was
always intended as Phase 1's "safest starter" strategy in this project's
roadmap, with S3 (logical/semantic arb) and S4 (settlement arb) expected
to carry more real edge — that framing was already baked into the
project's design before tonight, and tonight's findings are consistent
with it rather than contradicting it.

---

## 2026-07-01 (Session 25 — removed duplicate/broken regulatory Telegram alert; first live Telegram verification since Session 24's config fix)

### Context: tonight was the first time Telegram alerting has actually been enabled and exercised
- Following Session 24's `config.yaml`/`config_resolved` fix, the operator
  enabled `telegram.enabled: true` on the VPS tonight and observed live
  Telegram output for the first time since the notification layer was
  built (Sessions 19-20). This immediately surfaced a real bug that unit
  tests never would have caught, because no test exercised both
  `RegulatoryIntelligenceAgent` and `TelegramNotificationAgent` together
  against the same live event stream.

### Bug found: every regulatory item produced two Telegram messages, one broken
- `RegulatoryIntelligenceAgent._route_by_urgency` already correctly
  publishes a well-formatted, urgency-branched `TelegramNotificationEvent`
  (3=ℹ️ info, 4=⚠️ acknowledgment-required, 5=🚨 trading-paused) using real,
  populated data (`summary`, `affected`, `source_url`, `recommended_action`).
  It also **always** publishes `RegulatoryAlertEvent` for every item
  regardless of urgency (per its own existing comment: "Always publish
  RegulatoryAlertEvent so ComplianceOfficer logs it") — that event is
  needed for `ComplianceOfficer.handle_regulatory_alert`'s audit logging.
- `TelegramNotificationAgent` also subscribed to `RegulatoryAlertEvent`
  directly (`_handle_regulatory_alert`), producing a **second**, separate
  Telegram message for the same item. This second message was broken in
  two ways: (1) it read `event.source_name` and `event.matched_keywords`,
  fields `RegulatoryAlertEvent`'s publisher never populates (both default
  empty and are never set in `_route_by_urgency`) — so every message
  showed a blank source and "see logs"; (2) it instructed the operator to
  "Review logs/regulatory_alerts.txt immediately" — a file that was
  intentionally deleted in an earlier session (see DECISIONS.md,
  "ComplianceOfficer polling loop removed" / "regulatory_alerts.txt
  removed"), so the instruction was actively wrong, not just stale.
- **This was actively harmful, not just noisy**: the broken message was
  hardcoded to `"🚨 KARBOT RAGE! CRITICAL"` regardless of the actual
  urgency level. A routine urgency-3 FYI item produced a message labeled
  CRITICAL right alongside (or instead of) the correctly-tiered real
  message — training the operator to associate "CRITICAL" with noise,
  which directly undermines trust in the one alert that matters most
  (urgency 5, trading-halt). Confirmed live tonight: every regulatory item
  produced exactly this pattern (one useless, one genuinely useful message).

### What was built
- **`agents/notifications/telegram_agent.py`** — removed
  `_handle_regulatory_alert` entirely, its subscription to
  `RegulatoryAlertEvent` in `register_subscriptions()`, and the now-unused
  `RegulatoryAlertEvent` import. Nothing else in the file changed —
  `_handle_leg_failure`, `_handle_trade_executed`,
  `_handle_rejected_opportunity`, `_handle_feed_health`, and all other
  handlers/subscriptions are untouched.
- **Did NOT touch** `RegulatoryAlertEvent` itself, its publication in
  `regulatory_intelligence.py`, or the urgency-branching
  `TelegramNotificationEvent` logic in `_route_by_urgency` — all confirmed
  correct and left exactly as-is. `ComplianceOfficer.handle_regulatory_alert`'s
  subscription to `RegulatoryAlertEvent` (for `compliance_actions.jsonl`
  logging) is also untouched — confirmed via `git diff --stat` showing zero
  changes to `agents/management/compliance.py` and
  `agents/research/regulatory_intelligence.py`.
- **`tests/test_telegram_no_duplicate_regulatory_alert.py`** (new, 3 tests):
  - `test_telegram_agent_has_no_regulatory_alert_handler` — confirms the
    method no longer exists on the class at all.
  - `test_telegram_agent_does_not_subscribe_to_regulatory_alert_event` —
    confirms `EventBus._handlers[RegulatoryAlertEvent]` is empty after
    `register_subscriptions()`.
  - `test_publishing_regulatory_alert_event_does_not_queue_telegram_message`
    — publishes a `RegulatoryAlertEvent(urgency=5)` directly and confirms
    `TelegramNotificationAgent._outbound_queue` stays empty.

### What was decided
- The now-sole source of regulatory Telegram messages is
  `RegulatoryIntelligenceAgent._route_by_urgency`'s existing, already-correct
  urgency-branched path — no new code was written for this, only dead/wrong
  code was removed. `RegulatoryAlertEvent` remains a pure logging signal for
  `ComplianceOfficer`, decoupled from Telegram entirely now, which is
  arguably the correct event-bus design this should have had from the
  start: one event, one well-defined consumer per concern, rather than two
  consumers independently reinterpreting the same event for overlapping
  purposes.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **83/83 passed** ✓
  (80 baseline + 3 new)
- `grep -n "regulatory_alerts.txt\|_handle_regulatory_alert\|RegulatoryAlertEvent" agents/notifications/telegram_agent.py`:
  zero matches ✓
- `git diff --stat agents/management/compliance.py
  agents/research/regulatory_intelligence.py`: empty — both files
  confirmed untouched; `ComplianceOfficer`'s `RegulatoryAlertEvent`
  subscription (line 242, `handle_regulatory_alert`) still present and
  unmodified ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓
- `execution/engine.py` and `main.py` untouched ✓
- No Session 19-24 code touched — confirmed via diff scope: only
  `agents/notifications/telegram_agent.py` modified plus one new test file ✓

### NEW KNOWN DEBT / OPEN QUESTION — paper trade fee variance (not investigated this session)
Operator observed live tonight via Telegram trade-executed messages that
fee amounts show unexplained variance across trades: some show a flat
$70.00 fee regardless of PnL size, others show $0.00, $42.78, $113.27,
$56.64. Not investigated this session — flagged for next session to pull
the fee calculation logic (`PaperExecutor` or wherever fees are computed)
and cross-reference against `compliance.db` to determine whether this is
expected (fee scaling with position size or trade type in a way simply not
obvious from the Telegram summary text) or a real bug. Do not assume either
way without checking the actual numbers.

### NEW KNOWN DEBT / OPEN QUESTION — HIGH PRIORITY NEXT SESSION: P&L magnitude not yet re-verified post book-reset-recovery fix
The original P&L inflation concern (see DECISIONS.md: $58-$288 realized PnL
per trade at ~$500 position size, 11-57% net margins, vs. a realistic 1-5%
benchmark for S1 arb) was hypothesized to be caused by corrupt order books
from unresolved sequence gaps feeding stale spreads to ArbScanner. That
mechanism was fixed and confirmed live in Session 23 (REST-based book-reset
recovery, live-confirmed working from ~16:31 UTC 2026-07-01 onward) — but
the actual resulting P&L distribution has NOT been checked against the
1-5% benchmark since. Operator observed via live Telegram messages tonight
that PnL figures ($338.50, $343.50, $383.50, $323.50, etc.) appear
comparable to or larger than the originally-flagged inflated range — **NOT
yet confirmed improved**, and by eyeball may not have improved at all.
**This must be the first priority next session**: pull a clean sample of
RESOLVED trades from `compliance.db` with timestamps AFTER 2026-07-01
16:31 UTC, compute PnL as a percentage of position size for each, and
determine whether the distribution is now realistic (1-5%) or still
inflated. Do not continue treating paper trading data as validated until
this is checked — the 30-day clock continues to run, but confidence in
what it's measuring is not yet restored. If P&L is still inflated after
the book-reset fix, the original hypothesis (corrupt books → bad spreads →
spurious S1 opportunities) was incomplete or wrong, and a fresh
investigation is needed rather than assuming the Session 23 fix also fixed
this.

### What to do first next session
1. **HIGH PRIORITY**: verify P&L magnitude against the 1-5% benchmark using
   RESOLVED trades from `compliance.db` timestamped after 2026-07-01 16:31
   UTC (see KNOWN DEBT above). Do not skip this or assume the book-reset
   fix also fixed P&L realism.
2. Investigate the paper-trade fee variance (KNOWN DEBT above) if time
   permits after priority 1.
3. Continue the Session 24 Telegram-alerting live-verification checklist
   now that the duplicate/broken regulatory message is removed — with that
   noise gone, confirm the feed-down/recovered and restart-exhaustion
   alerts (Session 19/20) are visible and correctly tiered in the live
   Telegram stream.
4. Continue monitoring 30-day paper trading clock (started 2026-06-29,
   target live date 2026-07-29) — with the caveat above about P&L
   confidence not yet restored.

---

## 2026-07-01 (Session 24 — Telegram alerting has NEVER fired live: telegram.enabled=False, no config.yaml on VPS)

### Root cause: Telegram alerting was never actually running in production, across three live deploys
- `TelegramConfig.enabled` defaults to `False`, and `KarbotConfig.from_yaml()`
  falls back to that default whenever `config.yaml` doesn't exist. Confirmed
  via `ls ~/karbotrage_v1/config.yaml` on the VPS: **the file does not
  exist** — only the committed `config.yaml.example` template is present.
- This means every Telegram-dependent feature shipped since Session 19 has
  been running with `telegram.enabled=False` in production the entire
  time: the feed-down/feed-recovered Tier 1 alert (Session 20), the capped
  auto-restart's CRITICAL "AUTO-RECOVERY EXHAUSTED" alert (Session 20), and
  the RegulatoryIntelligence/LegFailure Tier 1 alerts from earlier
  sessions. `TelegramNotificationAgent.run()` no-ops entirely when
  disabled — no HTTP calls, no polling, and critically, **no error or
  warning of any kind**. This is a silent no-op by design (correct
  behavior when genuinely disabled), but with no config.yaml driving it
  intentionally, it meant three separate live deploys — including today's
  (2026-07-01, ~16:00-16:05 UTC) real PriceWatcher
  crash/restart/restart-budget-exhaustion cycle from Session 23's work —
  produced zero Telegram messages, and nothing in the logs made that
  obvious without already knowing to check `config.yaml`'s existence.
- **All "DEPLOYED BUT NOT YET CONFIRMED LIVE" notes for Telegram features
  in SESSIONS.md/CLAUDE.md from Session 19 onward should be read as
  "never actually exercised in production," not "pending verification."**
  The code itself may well be correct — the entire notification layer
  simply never ran with `enabled=True` to find out.

### What was built
- **`config.yaml.example`** — added a comment block above `telegram:`
  making explicit that `enabled` must be `true` for *any* Telegram
  notification to send (including Tier 1 "always send" alerts), that the
  disabled state is a total, silent no-op (no HTTP calls, no polling, no
  error), and pointing at the new `config_resolved` startup log line as the
  way to confirm the actual resolved value in production. Also added a
  comment above the `api:` section noting that `KarbotConfig.from_yaml()`
  does not currently parse it at all — confirmed by reading the source,
  `kalshi_ws_enabled`/`polymarket_ws_enabled` come from `DataFeedsConfig`'s
  dataclass defaults regardless of what's written under `api:` — so a
  future operator editing those `enabled:` keys wouldn't silently assume
  they do something they don't. (Discovered as a byproduct of writing the
  `config_resolved` log line and tracing exactly which fields `from_yaml`
  actually populates; not fixed this session, since the task scope was
  config + one log line, not a `from_yaml` rewrite — flagged in KNOWN DEBT.)
- **`karbot_runner.py`** — added a `config_resolved` INFO log line
  immediately after config load, before any agent is instantiated, logging
  the actual resolved value of every subsystem enable/disable flag:
  `telegram_enabled`, `kalshi_ws_enabled`, `polymarket_ws_enabled`,
  `regulatory_intelligence_enabled`, `paper_mode`, `phase`. Uses
  `config.regulatory_intelligence.enabled` (not `config.intelligence.enabled`
  as loosely suggested in the task brief) — verified by reading
  `karbot/core/config.py` that `IntelligenceConfig` (MarketAnalyst's LLM
  settings) has no `enabled` field at all; the actual Regulatory
  Intelligence on/off flag lives on `RegulatoryIntelligenceConfig`. Using
  the brief's literal suggestion would have raised `AttributeError` at
  every startup. This closes the "silent no-op with no error" gap this
  session's root cause depends on — any operator reading VPS logs after a
  restart can now see immediately which subsystems are actually active,
  rather than needing to already suspect a config problem and go check
  `config.yaml`'s existence and contents by hand.
- **`tests/test_config_resolved_log.py`** (new, 1 test) —
  `test_config_resolved_log_fires_once_with_accurate_values` runs the
  existing `--mock-prices --exit-after-test` path (no live network calls,
  matches the project's established smoke-test pattern) and asserts
  exactly one `config_resolved` log line fires, with values matching the
  resolved `KarbotConfig` defaults (no `config.yaml` present in the test
  environment): `telegram_enabled=False`, `kalshi_ws_enabled=True`,
  `polymarket_ws_enabled=False`, `regulatory_intelligence_enabled=True`,
  `paper_mode=True`, `phase=1`.

### What was decided
- Did not fix `KarbotConfig.from_yaml()`'s gap in parsing a `data_feeds:`
  YAML section (or the dead `api:` section in `config.yaml.example`) this
  session — out of scope per explicit instruction ("config + one log line
  change — do not modify any agent logic"). Documented the gap in a code
  comment and here so it isn't silently rediscovered again later.
- The actual `config.yaml` with `telegram.enabled: true` is being created
  directly on the VPS by the operator — not committed, per
  `.gitignore`/CLAUDE.md security rules (`config*.yaml*` pattern already
  covers it). This session's commit contains only `config.yaml.example`
  (template/documentation) and the `karbot_runner.py`/test changes.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **80/80 passed** ✓
  (79 baseline + 1 new)
- Manually confirmed the log line's values match `KarbotConfig.from_yaml()`'s
  actual resolution by running it directly against `config.yaml.example`
  in a Python shell — output matched the log line format exactly ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files — confirmed via
  `git status --short`; a local, gitignored, untracked `config.yaml` exists
  in this dev environment (pre-existing test artifact) but was never staged
  and does not appear in the diff ✓
- `execution/engine.py` and `main.py` untouched ✓
- No agent logic, Telegram handler code, or event bus behavior modified —
  confirmed via diff review: only `config.yaml.example` (comments only) and
  one new log-line block in `karbot_runner.py`'s `run()` changed ✓

### KNOWN DEBT (new, discovered as a byproduct of this session)
- `KarbotConfig.from_yaml()` does not parse a `data_feeds:` section from
  YAML at all — `kalshi_ws_enabled`/`polymarket_ws_enabled` always come
  from `DataFeedsConfig()` dataclass defaults, never from `config.yaml`.
  `config.yaml.example`'s `api.kalshi.enabled`/`api.polymarket.enabled`
  keys are consequently dead — editing them has no runtime effect. Not
  fixed this session (out of scope); flagged with a comment in
  `config.yaml.example` and here. A future session should either wire
  `data_feeds:` parsing into `from_yaml()` or remove the misleading `api:`
  section from the example file if Phase 1 will never need it configurable.

### What to do first next session
1. **Operator creates `config.yaml` on the VPS** with `telegram.enabled: true`
   (not committed — gitignored, environment-specific) and deploys/restarts.
2. After restart, confirm the `config_resolved` log line appears with
   `telegram_enabled=True`, and that a real Telegram message actually
   arrives on the next feed-down/feed-recovered transition or restart-cap
   event — this is the FIRST live confirmation of the entire Telegram
   notification layer since it was built.
3. Once Telegram is confirmed live, re-open the Session 19/20 verification
   items (before_sleep_log fix, feed-down alert, restart-cap CRITICAL
   alert) — these can now actually be checked against real Telegram
   messages instead of just log lines.
4. Consider the `data_feeds:` YAML-parsing gap (KNOWN DEBT above) if it
   becomes relevant to a near-term task (e.g. before Phase 2 Polymarket
   work, or before live executor work needs to toggle `kalshi_ws_enabled`
   from config rather than code).
5. Continue monitoring 30-day paper trading clock (started 2026-06-29,
   target live date 2026-07-29).

---

## 2026-07-01 (Session 23 — REST snapshot auth removed after live crash; CONFIRMED LIVE)

### Live outage: Session 22's REST snapshot fetch crashed PriceWatcher 3x in ~8 minutes
- Deploying Session 22's REST-based book-reset recovery caused
  `PriceWatcher` to crash three times in roughly 8 minutes with
  `AttributeError: 'NoneType' object has no attribute 'resume_reading'`
  inside `websockets`' internal `recv()` flow-control path, exhausting the
  Session 20 restart budget (3 restarts/60min) and leaving the agent
  permanently stopped.
- **Root cause**: `_request_snapshot()` called `_load_kalshi_private_key()`
  (blocking disk read) and `_build_kalshi_auth_headers()` (blocking
  RSA-PSS signing) synchronously, inside an `async def`, on every single
  REST snapshot fetch. Under the observed load (~13,761
  `book_needs_reset`/15min, ~1,073 throttled-through REST calls), that
  blocking work stacked up on the event loop long enough that the WS
  listen loop couldn't respond to Kalshi's ping frames within
  `ping_timeout=10s`. Kalshi tore down the WS transport mid-flight; the
  next `recv()` call then hit a `None` transport, producing the crash.
  Additionally, Kalshi's own docs confirm
  `GET /trade-api/v2/markets/{ticker}/orderbook` requires **no
  authentication** — the auth headers added in Session 22 were purely
  defensive, added without empirical verification (explicitly flagged as
  an open question in that session's own SESSIONS.md entry), and turned
  out to be the direct cause of a real outage rather than a safety margin.

### What was built
- **`agents/floor/price_watcher.py` — `_request_snapshot` no longer
  authenticates.** Removed the `_load_kalshi_private_key()` and
  `_build_kalshi_auth_headers()` calls entirely; the REST `GET` now sends
  no `headers` kwarg at all.
- **Shared `aiohttp.ClientSession`** — added `PriceWatcherAgent._rest_session`
  (initialized to `None`) and a new `_get_rest_session()` helper that lazily
  creates one `aiohttp.ClientSession` and reuses it across every
  `_request_snapshot` call, instead of the prior `async with
  aiohttp.ClientSession() as session:` pattern that constructed a brand new
  session per call. Gap events fire across many markets within the same
  second under real load, so unbounded per-call session creation was
  wasteful even independent of the blocking-auth bug. Closed in
  `PriceWatcherAgent.stop()` (`if self._rest_session is not None and not
  self._rest_session.closed: await self._rest_session.close()`) so nothing
  leaks across restarts.
- **Fix 2 investigated, no change needed**: confirmed
  `KalshiWebSocketClient.__init__` already loads the private key exactly
  once at construction (`self._private_key = _load_kalshi_private_key(...)`)
  and reuses it for the WS connect handshake — this is a one-time cost per
  WS connection, not a recurring per-message/per-call blocking pattern like
  the bug in `_request_snapshot`. No fix needed here; noted in this
  session's summary as investigated and ruled out, per instruction not to
  touch it unless trivially safe.
- **`tests/test_kalshi_orderbook.py`** — 4 new tests (79 total):
  - `test_request_snapshot_does_not_call_auth_helpers` — confirms neither
    auth helper is called and the GET carries no `headers` kwarg.
  - `test_request_snapshot_reuses_shared_session_across_calls` — three
    calls across different (non-throttled) markets construct
    `aiohttp.ClientSession()` at most once.
  - `test_get_rest_session_returns_same_instance` — repeated
    `_get_rest_session()` calls return the identical object while open.
  - `test_stop_closes_rest_session` — `PriceWatcherAgent.stop()` awaits
    `close()` on the shared session and clears the reference.
  - Existing throttle/success/failure tests for `_request_snapshot`
    rewritten to mock the new shared-session shape
    (`agent._get_rest_session()` patched directly) instead of patching
    `aiohttp.ClientSession` as a fresh per-call context manager.

### LIVE VERIFICATION — CONFIRMED
Operator deployed to the VPS and reported back:
- **HTTP status for the unauthenticated `GET
  /trade-api/v2/markets/{ticker}/orderbook`: 200.** 1,764
  `book_snapshot_applied` events fired in a ~2.5 minute window with valid
  order book data — the REST-based recovery mechanism (Session 22's design,
  Session 23's no-auth fix) works end-to-end for the first time.
- **Zero crashes** (`TypeError`/`resume_reading` or otherwise) observed
  over sustained load after the fix deployed.
- **Minor known issue, not urgent**: 56 of 1,016 REST requests (~5.5%) hit
  HTTP 429 (`too_many_requests`) during the initial post-restart surge, when
  many markets simultaneously had stale books needing recovery at once.
  Already handled gracefully by the existing failure path —
  `book_reset_rest_failed` logs the 429, `_gap_detected` stays `True`, and
  the next throttled window (10s later) retries. Not a crash risk, just an
  efficiency gap under restart-time bursts.

### What was decided
- Root cause (per-call blocking crypto/file I/O on the event loop) was
  confirmed via direct code inspection of the old `_request_snapshot`
  implementation and cross-referenced against `websockets`' documented
  `ping_timeout` behavior, then confirmed as the fix via live deploy — not
  just inferred from the crash traceback alone.
- Did not implement a concurrency limiter (`asyncio.Semaphore`) on
  in-flight REST snapshot calls this session, despite the 429 finding —
  explicitly flagged as a non-urgent follow-up per instruction. See KNOWN
  DEBT below.

### KNOWN DEBT — follow-up, not urgent
- **REST snapshot fetch has no concurrency limit.** Right after a restart
  (or any event that leaves many markets simultaneously with stale books),
  `_request_snapshot` can fire many concurrent REST calls in a short
  window — observed 56/1,016 (~5.5%) hitting Kalshi's rate limit (HTTP
  429) in the post-restart surge during this session's live verification.
  Currently handled safely (429 logged, gap stays detected, retried on the
  next 10s throttle window) but wastes calls and delays recovery for the
  affected markets. A future session should add an `asyncio.Semaphore` (or
  similar) bounding in-flight `_request_snapshot` REST calls to smooth
  bursts, especially right after a restart. Not implemented this session —
  not a crash risk, purely an efficiency improvement.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **79/79 passed** ✓
  (75 baseline + 4 new)
- Diff review (`git diff agents/floor/price_watcher.py`): confirms the
  throttle logic, the "client connected" guard, and the failure-handling
  path are unchanged in substance — only the transport (removed
  authentication, added a shared session) changed ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓
- `execution/engine.py` and `main.py` untouched ✓
- Session 19 (`before_sleep_log`/structlog fix) and Session 20 (Telegram
  feed-down alert, capped auto-restart) code confirmed untouched —
  `agents/notifications/telegram_agent.py`, `core/events.py`,
  `karbot/core/config.py`, and `karbot_runner.py` are not in this session's
  diff at all ✓
- **Live deploy on the VPS**: 200 HTTP status confirmed, 1,764
  `book_snapshot_applied` in ~2.5 min, zero crashes over sustained load ✓

### What to do first next session
1. Continue monitoring the book-reset recovery path on the VPS — confirm
   the 429 rate stays low/stable and doesn't grow, and that
   `book_needs_reset` rate trends down as recovery keeps working.
2. Consider the concurrency-limiter follow-up (KNOWN DEBT above) if 429s
   become a recurring pattern rather than a one-time post-restart surge.
3. Continue verifying the Session 19 before_sleep_log fix and the Session 20
   Telegram/restart features per their own outstanding verification plans.
4. Continue monitoring 30-day paper trading clock (started 2026-06-29,
   target live date 2026-07-29).

---

## 2026-07-01 (Session 22 — book-reset recovery replaced with REST fetch; Session 21 diagnostics reverted — DEPLOYED, NOT YET CONFIRMED LIVE)

### Root cause of the book_snapshot_applied=0 regression (from Session 21's live capture)
- Session 21's temporary diagnostic instrumentation (unconditional per-message
  `kalshi_raw_msg_diag` logging of every WS message's `type`/`id`) captured
  real traffic and confirmed: Kalshi responds to a duplicate WS subscribe
  message with `{"type": "ok", "id": N}` — a plain acknowledgment — **not**
  a fresh `orderbook_snapshot`. Cross-checked against Kalshi's own WS docs,
  which state snapshot delivery only happens on the *initial* subscribe to
  a channel, never on re-subscribing to an already-subscribed market.
- This means the Session 18 `_request_snapshot` WS re-subscribe recovery
  mechanism could never have worked as designed, from the moment it was
  written (Session 17 follow-up 3). The Session 18 id-collision fix
  improved request/response *correlation*, but correlating cleanly with an
  ack message that never carries book data doesn't recover a corrupted
  book. The regression that triggered this session (`book_snapshot_requested`
  climbing to 3,365 in 18 minutes while `book_snapshot_applied` fell to
  zero, down from 37% before the last restart) is explained: whatever
  changed between measurements, the underlying recovery path was already
  fundamentally broken.

### What was built
- **`agents/floor/price_watcher.py` — `_request_snapshot` rewritten to use
  a REST fetch instead of a WS re-subscribe.**
  Makes an `aiohttp` GET to
  `https://api.elections.kalshi.com/trade-api/v2/markets/{ticker}/orderbook`,
  reusing `_build_kalshi_auth_headers` (matching the existing pattern in
  `_fetch_active_kalshi_markets` — simpler than adding an unauthenticated
  code path for one endpoint, and Kalshi accepts the auth headers even
  though the endpoint itself doesn't strictly require them).
  Parses `orderbook_fp.yes_dollars`/`no_dollars` (string `[price, count]`
  pairs — cast to float; NO bids still derive YES asks at `1-p`, same
  convention as the WS snapshot schema) and calls
  `book.apply_snapshot(bids, asks, seq=0)` directly.
  **Sequence handling**: the REST response carries no sequence number.
  Verified against the actual gap-check code
  (`OrderBook.apply_delta`: `if seq != self.sequence + 1 and self.sequence
  != 0`) that a `seq=0` sentinel is safe — `self.sequence == 0`
  short-circuits the gap check, so the next delta is accepted regardless of
  its own seq value and `self.sequence` naturally realigns. No special
  handling needed downstream.
  The existing 10s per-market throttle (`_reset_requested`) and the
  "client must exist and be connected" guard are unchanged — both still
  apply to a REST-based recovery path.
  On any failure (non-200, network error, timeout — one `try/except
  Exception` wraps the whole call, 5s `aiohttp.ClientTimeout`), logs
  `book_reset_rest_failed` at warning and returns without calling
  `apply_snapshot` — `_gap_detected` stays `True`, so the next delta on
  that market retriggers a throttled retry rather than crashing
  `_kalshi_connection_loop`.
  The Session 18 `_snapshot_request_id_counter` is kept (per explicit
  instruction) but is no longer load-bearing for this path — a comment
  explains why, since no WS message is sent from `_request_snapshot` anymore.
- **Session 21 diagnostic instrumentation fully reverted.** All four
  `TEMPORARY DIAGNOSTIC` blocks removed: `kalshi_raw_msg_diag` in
  `_route_message`, `_diag_msg_type_counts`, `_diag_summary_loop`, and
  `kalshi_raw_msg_diag_sent` in the old `_request_snapshot`. Confirmed via
  `grep -in "diagnostic\|diag" agents/floor/price_watcher.py` → zero matches.
- **`tests/test_kalshi_orderbook.py` — rewritten `_request_snapshot` test
  coverage (21 tests total in this file, was 17):**
  - Rewrote the throttle tests (`test_request_snapshot_throttled_second_call_suppressed`,
    `test_request_snapshot_throttle_resets_after_window`) to mock the REST
    call (`aiohttp.ClientSession`, `_load_kalshi_private_key`,
    `_build_kalshi_auth_headers`) instead of asserting on WS `send` calls,
    following the exact mocking pattern already established in
    `tests/test_price_watcher.py` for `_fetch_active_kalshi_markets`.
  - Replaced the two "distinct id sent over WS" tests (no longer meaningful
    — nothing is sent over WS anymore) with
    `test_request_snapshot_id_counter_still_increments`, confirming the
    counter still increments even though it's not transmitted anywhere.
  - **New**: `test_request_snapshot_rest_success_applies_snapshot_and_clears_gap`
    — a pre-seeded gapped book gets float bids/asks applied and
    `needs_reset` clears to `False`; also confirms `sequence == 0` (sentinel).
  - **New**: `test_request_snapshot_rest_creates_book_if_missing` — no
    `OrderBook` exists yet for the market; one is created before
    `apply_snapshot` is called.
  - **New**: `test_request_snapshot_rest_non_200_leaves_gap_detected` — a
    500 response logs a warning, leaves `needs_reset` `True`, does not raise.
  - **New**: `test_request_snapshot_rest_network_error_leaves_gap_detected`
    — a raised `TimeoutError` during the REST call logs a warning, leaves
    `needs_reset` `True`, does not raise.

### What was decided
- Reused `_build_kalshi_auth_headers` for the REST call even though Kalshi's
  docs say this endpoint doesn't require authentication — matches the
  existing REST-call pattern in this file (`_fetch_active_kalshi_markets`),
  avoids a second, differently-authenticated code path for a single
  endpoint, and costs nothing extra since the headers are cheap to compute.
  Not empirically verified against the live unauthenticated case this
  session (no live Kalshi access from this environment) — if the
  authenticated call fails in an unexpected way once deployed, try the
  request without auth headers as a fallback and note which actually works,
  per the same "verify empirically, don't assume" discipline as prior
  sessions' Kalshi API work.
- `seq=0` sentinel chosen after reading `OrderBook.apply_delta`'s actual gap
  -check condition, not assumed — the reasoning is documented in a comment
  on `_request_snapshot` and in DECISIONS.md so a future session doesn't
  have to re-derive it.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **75/75 passed** ✓
  (72 baseline − 2 removed WS-id tests + 1 counter test + 4 new REST tests)
- `grep -in "diagnostic\|diag" agents/floor/price_watcher.py`: zero matches ✓
- Diff review (`git diff agents/floor/price_watcher.py`): confirms the
  throttle logic, the "client connected" guard, and the id counter are
  unchanged in substance — only the transport (WS send → REST GET) and
  response-handling changed ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓
- `execution/engine.py` and `main.py` untouched ✓
- Session 19 (`before_sleep_log`/structlog fix) and Session 20 (Telegram
  feed-down alert, capped auto-restart) code confirmed untouched — `grep`
  confirms `_log_before_sleep`, `before_sleep=_log_before_sleep`, and the
  `error=str(e)` param on `_handle_health_change` are all still present;
  `agents/notifications/telegram_agent.py`, `core/events.py`,
  `karbot/core/config.py`, and `karbot_runner.py` are not in this session's
  diff at all ✓

### STATUS: DEPLOYED BUT NOT YET CONFIRMED LIVE
The REST-based recovery has NOT been exercised against the real Kalshi
REST endpoint on the VPS as of this entry. Next session must:
1. Deploy (`git pull origin main`, restart `karbot`).
2. Confirm `book_snapshot_requested` → (REST fetch, no longer a WS log
   line) → `book_snapshot_applied` actually completes again — compare the
   apply rate against both the Session 18 baseline (10.2%) and the
   pre-this-session regression (0%). A healthy apply rate (ideally close to
   100%, since REST GET either succeeds or fails per-call, with no
   response-correlation ambiguity) confirms the fix.
3. Watch for `book_reset_rest_failed` — if it fires frequently, investigate
   whether the auth-headers-on-an-unauthenticated-endpoint assumption needs
   revisiting (try without auth headers) or whether it's a genuine rate
   limit / network issue.
4. Re-check whether the P&L inflation KNOWN DEBT item (corrupt books
   feeding stale spreads to ArbScanner) resolves now that books can
   actually recover from sequence gaps.

### What to do first next session
1. Deploy this fix to the VPS and verify per the STATUS section above.
2. Continue verifying the Session 19 before_sleep_log fix and the Session 20
   Telegram/restart features per their own outstanding verification plans.
3. Continue monitoring 30-day paper trading clock (started 2026-06-29,
   target live date 2026-07-29).

---

## 2026-07-01 (Session 21 — TEMPORARY diagnostic instrumentation for book_snapshot_applied=0 regression — REVERT NEXT SESSION AFTER CAPTURE)

### Context: new regression, not the Session 18 hypothesis
- `book_snapshot_requested` climbed from 23,412/day (Session 18 baseline) to
  3,365 in an 18-minute window right after the latest restart, while
  `book_snapshot_applied` dropped to **zero** in that same window — down
  from a 37% apply rate measured just before the restart. This is worse
  than the original Session 18 problem (10.2% completion), not an
  improvement, and the drop to exactly zero suggests something structural
  changed, not a continuation of the id-collision issue.
- Two hypotheses were checked and ruled out by code/diff review before
  reaching for instrumentation: (1) a WS "id" collision between
  `_request_snapshot`'s counter and `subscribe_markets`'s per-batch ids —
  reviewed both call sites, ids are independent counters with no shared
  state or expected collision; (2) a regression introduced by the Session
  20 Telegram/restart-cap deploy — reviewed that diff, it touches
  `FeedHealthEvent`, `TelegramNotificationAgent`, and `karbot_runner.py`
  only; nothing in the snapshot-response code path changed. Both ruled out;
  root cause is unknown without seeing the actual wire traffic.

### What was built (TEMPORARY — must be reverted next session after capture)
Following the same temporary-diagnostic-then-revert pattern used in
Session 15 to resolve the WS schema ambiguity (raw-message logging, capture
real traffic, resolve, revert):
- **`agents/floor/price_watcher.py` — `KalshiWebSocketClient._route_message`**:
  now logs `kalshi_raw_msg_diag` at INFO for **every** incoming message
  (`msg_type`, `msg_id`), unconditionally — not just `orderbook_snapshot` —
  so we can see if snapshot responses are arriving under an unexpected
  `type`, with unexpected `id`s, or not arriving on the wire at all.
- **`_diag_msg_type_counts: Dict[str, int]`** (new field on
  `KalshiWebSocketClient.__init__`) — incremented per message in
  `_route_message` for every `msg_type` seen (empty type bucketed as
  `"<empty>"`).
- **`_diag_summary_loop()`** (new method on `KalshiWebSocketClient`) — logs
  `kalshi_raw_msg_diag_summary` with the running tally once every 60s, so
  the per-message lines don't have to be grepped by hand to see traffic
  composition. Started as a sibling task in `listen()`, cancelled in a
  `finally` block when `listen()` exits (WS disconnect or cancellation) —
  no dangling task.
- **`_request_snapshot()`** — added `kalshi_raw_msg_diag_sent` INFO log
  immediately after a successful send, with the `msg_id` and `market_id`
  just sent, so sent-ids can be cross-referenced against received-ids in
  the `kalshi_raw_msg_diag` stream.
- All four additions are marked with `# TEMPORARY DIAGNOSTIC — Session 21,
  revert after capture` comments, placed immediately around each change so
  they are unmistakable and trivial to find/remove (`grep -n "TEMPORARY
  DIAGNOSTIC" agents/floor/price_watcher.py`).

### What was explicitly NOT changed
- `_handle_kalshi_snapshot`'s matching/routing logic — untouched.
- The 10s throttle in `_request_snapshot` — untouched.
- The `_snapshot_request_id_counter` monotonic id fix (Session 18) —
  untouched, confirmed present via `grep`.
- The `before_sleep_log`/structlog fix (Session 19) — untouched, confirmed
  present via `grep`.
- The Telegram feed-down alert and capped auto-restart (Session 20) —
  untouched; only `agents/floor/price_watcher.py` was modified this
  session, none of `core/events.py`, `agents/notifications/telegram_agent.py`,
  `karbot/core/config.py`, or `karbot_runner.py`.
- No event-bus publish/subscribe pattern changes — this is logging only.
- `execution/engine.py` and `main.py` — untouched.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **72/72 passed**,
  unchanged from baseline — confirms no test asserts on log volume/content
  in a way this instrumentation breaks ✓
- Diff review (`git diff agents/floor/price_watcher.py`): confirms every
  change is additive (new log lines, a new counter dict, a new
  cancel-on-exit summary task) — no existing conditional, return value, or
  control-flow branch was altered ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓

### STATUS: TEMPORARY — MUST BE REVERTED NEXT SESSION AFTER CAPTURE
This instrumentation is not a fix and not a feature. It exists solely to
capture real wire traffic during the next live window so the actual root
cause of the `book_snapshot_applied=0` regression can be diagnosed from
data instead of a third guess. Next session must:
1. Deploy (`git pull origin main`, restart `karbot`).
2. Let it run through at least one `book_snapshot_requested` burst, then
   pull VPS logs and inspect: does `kalshi_raw_msg_diag` show any message
   type at all correlating with sent `msg_id`s from
   `kalshi_raw_msg_diag_sent`? Is Kalshi responding with `orderbook_snapshot`
   under an unexpected id, a different type entirely, an `error` message, or
   not responding at all? Check `kalshi_raw_msg_diag_summary` for the
   overall type-count breakdown across the capture window.
3. Diagnose and fix the actual root cause based on that data.
4. **Revert all Session 21 diagnostic code** (`grep -n "TEMPORARY
   DIAGNOSTIC" agents/floor/price_watcher.py` to find every change) once
   root cause is captured and understood — this must not stay in the
   codebase permanently, same as the Session 15 precedent.

### What to do first next session
1. Deploy this instrumentation to the VPS and capture live traffic per the
   STATUS section above.
2. Diagnose the `book_snapshot_applied=0` regression from captured data,
   fix it, then revert all Session 21 diagnostic logging.
3. Continue verifying the Session 19 before_sleep_log fix, the Session 18
   book-reset id-collision fix, and the Session 20 Telegram/restart
   features per their own outstanding verification plans.
4. Continue monitoring 30-day paper trading clock (started 2026-06-29,
   target live date 2026-07-29).

---

## 2026-07-01 (Session 20 — Telegram feed-down alert + capped runner-level auto-restart — DEPLOYED, NOT YET CONFIRMED LIVE)

### What was built
- **`core/events.py` — `FeedHealthEvent.error` field added.** Additive
  optional `str = ""` field so a disconnect caused by an exception can carry
  the underlying error message through the event bus to any subscriber,
  without a new event type or a direct call out of price_watcher.py.
- **`agents/floor/price_watcher.py` — `_handle_health_change` gained an
  optional `error: str = ""` parameter**, passed through to the new
  `FeedHealthEvent.error` field. Only the `_kalshi_connection_loop` exception
  handler passes a real value (`str(e)`); the other two call sites
  (successful connect, silence-timeout in `_health_monitor`) are unchanged
  and still omit it (default `""`).
- **`agents/notifications/telegram_agent.py` — Tier 1 feed-health alert.**
  `TelegramNotificationAgent` now subscribes to `FeedHealthEvent` and tracks
  `_feed_connected: Dict[str, bool]` (last known connected state per
  platform). `_handle_feed_health`:
  - Ignores any platform other than `"kalshi"`.
  - Fires an alert only on a connected→disconnected or disconnected→connected
    **transition** — not on every `FeedHealthEvent`, so repeated
    `connected=False` events during one continuous outage (e.g. from the
    agent's own `_health_monitor` silence check) do not spam the operator.
  - Down alert: "FEED DOWN", platform, error message (if present), timestamp.
  - Recovery alert: distinct "FEED RECOVERED" text, platform, timestamp.
  - Both bypass `config.telegram.enabled`-gated Tier 2/3 message routing the
    same way the existing `_handle_leg_failure`/`_handle_regulatory_alert`
    Tier 1 handlers do — pushed directly to `_outbound_queue`, ignoring any
    future mute state (mute is not yet built, but this alert path is
    explicitly designed to bypass it once it exists, per instruction).
- **`karbot/core/config.py` — `SystemConfig` gained three new fields**:
  `agent_restart_delay_seconds` (default 30), `agent_restart_max_count`
  (default 3), `agent_restart_window_minutes` (default 60). Wired into
  `KarbotConfig.from_yaml()`'s `system:` section parsing with the same
  default-fallback pattern as the existing `paper_resolution_delay_seconds`.
- **`karbot_runner.py` — `_run_supervised_with_restart()`, new general-purpose
  supervision function.** Takes `agent_name`, a `coro_factory` (a zero-arg
  callable returning a fresh awaitable — `agent.run`, not `agent.run()`,
  since a coroutine object can only be awaited once), the event bus, and the
  three restart parameters. On crash (any non-`CancelledError` exception):
  records a `time.monotonic()` timestamp, prunes timestamps outside the
  rolling window, and either sleeps `restart_delay_seconds` and relaunches,
  or — if the budget is exhausted — logs an error, publishes a
  `TelegramNotificationEvent(tier=1, ...)` with distinct "AUTO-RECOVERY
  EXHAUSTED for {agent_name}" wording (different from the Tier 1 feed-down
  alert above), and returns permanently (agent stays stopped). The existing
  `_run_supervised()` (fire-once, log-and-continue, no restart) is
  **unchanged** and still used for every other agent.
  Wired only to `PriceWatcher` in the agent task-creation loop via
  `isinstance(agent, PriceWatcher)` — `MockPriceWatcher` (used in
  `--mock-prices` test mode) is a separate class, not a `PriceWatcher`
  subclass, so mock/paper-mode-under-test behavior is unaffected; confirmed
  via a full `--mock-prices ... --exit-after-test` run (unchanged output,
  clean exit, all agents including `MockPriceWatcher` used the old
  `_run_supervised` path as before).
- **`tests/test_telegram_feed_health.py`** (new, 4 tests):
  - `test_feed_down_triggers_exactly_one_alert_per_outage` — 3 consecutive
    `connected=False` events for one outage → exactly 1 alert, containing
    platform + error text.
  - `test_feed_recovery_triggers_distinct_alert` — down alert, then
    `connected=True` → a second, textually distinct "FEED RECOVERED" alert;
    a further `connected=True` repeat does not re-alert.
  - `test_non_kalshi_platform_ignored` — `platform="polymarket"` never alerts.
  - `test_disabled_telegram_does_not_queue_message` — `telegram.enabled=False`
    → no message queued regardless of transitions.
- **`tests/test_runner_restart.py`** (new, 3 tests):
  - `test_four_crashes_in_window_suppresses_fourth_restart_and_alerts` — a
    test double crashing 4 times within the rolling window: exactly 3
    restarts occur, the 4th crash trips the budget, exactly one
    `TelegramNotificationEvent(tier=1)` publishes with "AUTO-RECOVERY
    EXHAUSTED" text, and the function returns (agent stays stopped —
    `call_count == 4`, no 5th launch attempt).
  - `test_two_crashes_in_window_restart_normally_no_critical_alert` — 2
    crashes within the window restart normally (3rd `run()` call reaches the
    simulated long-running/healthy state), zero CRITICAL alerts published.
  - `test_restart_uses_configured_delay` — confirms `asyncio.sleep` is
    actually awaited with the configured `restart_delay_seconds` value
    (30 in the test) between a crash and the next restart attempt.

### What was decided
- **Operator decision implemented**: task-level auto-restart with a capped
  budget (30s delay, 3 restarts/60min, then CRITICAL alert + stop) — this
  resolves the "failure-recovery philosophy" question flagged as open in
  Session 19 (see DECISIONS.md, marked resolved this session).
- The restart alert (event bus `TelegramNotificationEvent`) and the
  feed-down alert (dedicated `FeedHealthEvent` subscription) are
  intentionally two separate mechanisms with distinct wording: a feed-down
  alert can fire and self-resolve many times while `PriceWatcher`'s own
  internal tenacity retry succeeds — that's normal operation, not something
  requiring a restart. The restart-exhaustion alert only fires when the
  *runner* gives up relaunching the agent task entirely — a categorically
  more serious event.
- Restart logic built as a general `_run_supervised_with_restart()` function
  (agent-agnostic: `agent_name` + `coro_factory` + bus + three params) but
  wired only to `PriceWatcher` this session, per explicit instruction — no
  other agent's supervision behavior changed.
- Added `FeedHealthEvent.error` as a plain additive optional field rather
  than a new event type — keeps the existing event-bus subscription pattern
  intact and avoids a second code path for "feed health, but with an error".

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **72/72 passed** ✓
  (65 baseline + 4 new in test_telegram_feed_health.py + 3 new in
  test_runner_restart.py)
- Full `karbot_runner.py --mode paper --mock-prices
  tests/fixtures/paper_test_prices.json --exit-after-test` run: unchanged
  behavior, clean exit, `MockPriceWatcher` confirmed to still use the
  unmodified `_run_supervised` path (not the new restart wrapper) ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓
- `execution/engine.py` and `main.py` untouched ✓
- Event-bus publish/subscribe pattern preserved — the feed-down alert flows
  through `FeedHealthEvent` (existing subscription pattern) and the
  restart-exhaustion alert flows through `TelegramNotificationEvent`
  published via `bus.publish()` (no direct call into `TelegramNotificationAgent`) ✓
- Did NOT modify the Session 19 `before_sleep_log`/structlog fix or the
  Session 18 snapshot `id` fix — confirmed via diff review, both are present
  and unmodified (`_log_before_sleep`, `_snapshot_request_id_counter` grep
  confirmed intact) ✓

### STATUS: DEPLOYED BUT NOT YET CONFIRMED LIVE
Neither the Telegram feed-down alert nor the capped auto-restart has been
exercised against a real Kalshi WS outage or a real crash on the VPS as of
this entry. Next session must:
1. Deploy (`git pull origin main`, restart `karbot`).
2. Trigger (or wait for) a real Kalshi WS disconnect and confirm: a "FEED
   DOWN" Telegram message arrives promptly, a "FEED RECOVERED" message
   arrives on reconnect, and no duplicate alerts fire during the outage.
3. If the disconnect is severe enough to exhaust `PriceWatcher`'s internal
   `stop_after_attempt(10)` retry (Session 19), confirm the runner actually
   restarts the agent after ~30s rather than leaving it dead, and that
   restart succeeds (feed comes back without a manual `systemctl restart`).
4. Manually verify the restart-budget CRITICAL alert path only if 4+ crashes
   occur within an hour in practice — otherwise this stays unverified against
   real conditions (the unit tests confirm the logic; only a live VPS
   observation confirms the operational behavior end-to-end).

### What to do first next session
1. Deploy this fix to the VPS and verify per the STATUS section above.
2. Continue verifying the Session 19 before_sleep_log fix and the Session 18
   book-reset id-collision fix per their own outstanding verification plans
   — those remain open independently of this session's work.
3. Continue monitoring 30-day paper trading clock (started 2026-06-29,
   target live date 2026-07-29).

---

## 2026-07-01 (Session 19 — before_sleep_log/structlog TypeError killed WS reconnect retry — DEPLOYED, NOT YET CONFIRMED LIVE)

### What was built
- **`agents/floor/price_watcher.py` — `@retry`'s `before_sleep` argument fixed.**
  Root cause: the `@retry` decorator on `_kalshi_connection_loop` used
  tenacity's `before_sleep_log(log, "WARNING")`, which is written for stdlib
  `logging.Logger` and calls `logger.log("WARNING", ...)` — passing the level
  as a string. `log` here is a `structlog.get_logger(__name__)` instance;
  structlog's `BoundLogger.log()` expects an int level and does
  `if level < min_level`, raising
  `TypeError: '<' not supported between instances of 'str' and 'int'`. That
  TypeError occurred inside tenacity's own retry machinery, on the very first
  retry attempt after any connection failure — meaning `@retry` had never
  actually retried successfully since this decorator was written. It crashed
  through to `_run_supervised` in `karbot_runner.py`, which logs the crash and
  lets the agent die permanently.
  **Confirmed live impact**: a Kalshi WS disconnect at 07:42:02 UTC on
  2026-06-30 killed the price feed. It stayed dead for ~6 hours (until
  ~13:3x UTC) with zero retry attempts logged, requiring a manual
  `systemctl restart karbot`.
  Fix: replaced `before_sleep_log(log, "WARNING")` with a custom
  `_log_before_sleep(retry_state)` module-level function that calls
  `log.warning("kalshi_reconnect_retry", attempt=..., wait_seconds=...)`
  directly — compatible with structlog's keyword-based API. `before_sleep_log`
  removed from the tenacity import. `stop_after_attempt(10)`,
  `wait_exponential(...)`, and `retry_if_exception_type(...)` unchanged.
- **Documented, not changed: behavior after `stop_after_attempt(10)` is
  exhausted.** Added a `NOTE` comment directly above `_kalshi_connection_loop`
  stating that once 10 real failed reconnect attempts occur, the failure
  (wrapped as `tenacity.RetryError`) propagates out of the coroutine,
  `_run_supervised` logs the crash, and `PriceWatcher` is dead until an
  operator runs `systemctl restart karbot` — there is no agent-level
  auto-restart after a cooldown. **This is flagged as an open architectural
  question for operator decision, not resolved this session** (see below).
- **`tests/test_kalshi_reconnect.py`** (new file, 2 tests):
  - `test_kalshi_connection_loop_retries_and_succeeds_after_failure` — mocks
    `KalshiWebSocketClient.connect()` to raise
    `websockets.exceptions.ConnectionClosedError` on the first call and
    succeed on the second; confirms the before_sleep callback does NOT raise
    and the retry actually proceeds to a successful second attempt (this is
    the test that would have caught the original bug — it fails immediately
    with the old `before_sleep_log` because the TypeError inside tenacity's
    machinery pre-empts any retry).
  - `test_kalshi_connection_loop_gives_up_after_max_attempts` — confirms
    `stop_after_attempt(10)` still terminates after exactly 10 failed
    attempts and the failure propagates as `tenacity.RetryError` (documents
    current, unchanged behavior).
  - Both tests patch `asyncio.sleep` to a no-op so tenacity's real
    exponential backoff (which would otherwise sum to 151s across 9 waits
    before the 10th attempt) doesn't slow down the test run; the real
    stop/wait/retry logic still executes unmodified.

### What was decided
- Root cause is confirmed via direct code inspection of both tenacity's
  `before_sleep_log` implementation and structlog's `BoundLogger.log()` — not
  just inferred from the live symptom. This is a different verification
  posture than the Session 18 id-collision fix (which is still an unconfirmed
  hypothesis); this one is a mechanically demonstrable bug, and the new test
  reproduces it directly (it fails against the pre-fix code).
- Did NOT implement agent-level restart of a dead `PriceWatcher` in
  `_run_supervised` — this is a real architectural question (see below),
  not something to decide unilaterally in this session.

### OPEN ARCHITECTURAL QUESTION — needs operator decision
Once `stop_after_attempt(10)` is genuinely exhausted, `PriceWatcher` dies
permanently and requires a manual `systemctl restart karbot`. Two paths:
1. **Accept as designed**: operator gets paged/alerted via Telegram
   (`FeedHealthEvent`/existing alerting) and manually restarts. Simple, but
   means any Kalshi-side outage longer than ~10 exponential-backoff attempts
   (up to ~4.5 minutes worst case: 1+2+4+8+16+30+30+30+30 = 151s, this
   session's test confirmed 151s slept across 9 waits) requires human
   intervention even if Kalshi recovers on its own shortly after.
2. **`_run_supervised` restarts a dead `PriceWatcher` after a cooldown** —
   would require `_run_supervised` to distinguish "this specific agent
   crashed and should be relaunched" from other failure modes, and decide on
   a cooldown/backoff strategy at the runner level (on top of the agent's own
   internal retry). Not implemented this session per explicit instruction —
   flagged for operator decision.
**This is a real question about acceptable downtime and failure-recovery
philosophy, not a code-correctness bug — do not decide unilaterally.**

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **65/65 passed** ✓
  (63 baseline + 2 new in test_kalshi_reconnect.py)
- `grep -rn "before_sleep_log\|before_log" --include="*.py" .`: only match is
  the explanatory docstring comment in the new `_log_before_sleep` function
  itself — no other tenacity `before_sleep_log`/`before_log` usage with a
  structlog logger exists elsewhere in the codebase ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓
- `execution/engine.py` and `main.py` untouched ✓
- Event-bus publish/subscribe pattern untouched — only the retry decorator's
  `before_sleep` argument and a doc comment changed ✓
- Did NOT touch the Session 18 snapshot `id` fix or `book_needs_reset` log
  level — confirmed via diff review, those lines are unmodified ✓

### STATUS: DEPLOYED BUT NOT YET CONFIRMED LIVE
This fix has NOT been deployed to the VPS as of this entry. Next session must:
1. Deploy (`git pull origin main`, restart `karbot`).
2. Confirm no further `TypeError` appears in logs if/when a real Kalshi WS
   disconnect occurs.
3. Confirm `kalshi_reconnect_retry` (new log key) appears with increasing
   `attempt` numbers on any real disconnect, and that the feed actually
   recovers (reconnects) instead of dying — this is the live confirmation
   that was impossible before this fix (every real disconnect previously
   crashed on attempt 1).
4. Bring the open architectural question above to the operator for a
   decision before implementing either path.

### Interaction with Session 18 (book-reset id collision fix)
This bug is a precondition-breaking issue for the entire Session 18
investigation: if `PriceWatcher` dies permanently on the first WS disconnect
and never reconnects, `book_snapshot_requested`/`book_snapshot_applied`
completion-rate data from the VPS may be confounded by an agent that was
dead for stretches of the observation window, not actively processing gap
events. Re-verify the Session 18 completion-rate comparison only after this
fix is confirmed live and the feed is confirmed to survive disconnects.

### What to do first next session
1. Deploy this fix to the VPS and verify per the STATUS section above.
2. Bring the open architectural question (agent-level restart after
   `stop_after_attempt` exhaustion) to the operator.
3. Once confirmed stable, proceed with the Session 18 verification (compare
   `book_snapshot_requested`/`book_snapshot_applied` completion rate) — note
   the Session 18 baseline data may be unreliable if the feed was dead for
   part of that window.
4. Continue monitoring 30-day paper trading clock (started 2026-06-29,
   target live date 2026-07-29).

---

## 2026-06-30 (Session 18 — book_snapshot_requested id collision fix — DEPLOYED, NOT YET CONFIRMED LIVE)

### What was built
- **`agents/floor/price_watcher.py` — `_request_snapshot` correlation id fixed.**
  VPS logs from 2026-06-30 showed 23,412 `book_snapshot_requested` events but
  only 2,380 `book_snapshot_applied` events (10.2% completion rate) — the
  Session 17 follow-up 3 re-subscribe recovery was firing but mostly not
  completing. Root-cause hypothesis: `_request_snapshot` sent a hardcoded
  `"id": 99` on every WS re-subscribe message regardless of market. Gap
  events routinely fire across dozens of markets within the same second;
  if Kalshi's WS server correlates responses to requests via `id`, concurrent
  reset requests sharing id=99 would cause most responses to be dropped or
  misattributed to the wrong market's book.
  Fix: added `self._snapshot_request_id_counter: int = 0` in `__init__`,
  incremented and used as the `id` value on every `_request_snapshot` call.
  Single asyncio event loop, single call site (inside `_handle_kalshi_delta`,
  invoked serially per incoming WS message) — confirmed no concurrent-call
  hazard, plain int increment is safe without a lock.
- **`agents/floor/price_watcher.py` — `book_needs_reset` log demoted to debug
  (noise reduction, secondary fix).** This log fired at warning level on
  every delta received while a market awaited snapshot recovery (not once
  per gap episode) — 2.17M warning-level lines in a single day on the VPS,
  burying real signal. Changed the call site in `_handle_kalshi_delta`
  (previously line 537) from `log.warning` to `log.debug`. Left
  `sequence_gap_detected` in `OrderBook.apply_delta()` untouched at warning
  — that one already fires only once per gap (False→True transition).
- **`tests/test_kalshi_orderbook.py` — 4 new tests (63 total):**
  - `test_request_snapshot_uses_distinct_id_per_market` — two calls across
    different markets produce two distinct, non-99 `id` values
  - `test_request_snapshot_id_increments_monotonically` — successive
    non-throttled calls produce strictly increasing ids
  - `test_book_needs_reset_logs_at_debug_not_warning` — confirms the
    `_handle_kalshi_delta` call site uses `log.debug`, not `log.warning`
  - `test_sequence_gap_detected_still_logs_at_warning` — confirms
    `apply_delta()`'s existing warning log is untouched

### What was decided
- Root cause was reasoned from the observed 10.2% completion rate plus the
  known gap-event pattern (dozens of markets per second) rather than
  confirmed by capturing live Kalshi WS traffic this session — same category
  of risk flagged in prior sessions' decisions (Session 15: "verify each
  layer against the live API/wire before declaring it fixed"). This fix is
  the leading hypothesis, not a confirmed root cause.
- Did not add a lock around the counter — single event loop, single call
  site, calls are inherently serialized by the WS message-receive loop.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **63/63 passed** ✓
  (59 baseline + 4 new)
- `grep -n '"id": 99' agents/floor/price_watcher.py`: zero matches ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓
- `execution/engine.py` and `main.py` untouched ✓
- Event-bus publish/subscribe pattern untouched — only the WS message body
  and one log level changed ✓

### STATUS: DEPLOYED BUT NOT YET CONFIRMED LIVE
This fix has NOT been deployed to the VPS or verified against live Kalshi
traffic as of this entry. Before marking resolved in DECISIONS.md, next
session must:
1. Deploy (`git pull origin main`, restart `karbot`).
2. Tail VPS logs and compare `book_snapshot_requested` vs
   `book_snapshot_applied` counts over a comparable window to the 2026-06-30
   baseline (23,412 requested / 2,380 applied, 10.2%). A meaningfully higher
   completion rate confirms the id-collision hypothesis; if the rate does not
   improve, the id fix was not the (or not the only) cause and the REST
   snapshot / forced reconnect fallback from the original KNOWN DEBT note
   must be designed instead.
3. Confirm `book_needs_reset` no longer dominates VPS log volume (was 2.17M
   lines/day) — should now appear only at debug level.
4. Re-check whether paper P&L figures ($58–$288/trade, 11–57% net margins)
   normalize toward the expected 1–5% net range once books recover
   reliably — do not treat paper P&L as realistic until this is confirmed.

### What to do first next session
1. Deploy this fix to the VPS and verify per the STATUS section above.
2. If completion rate improves: update DECISIONS.md to mark the book-reset
   recovery caveat resolved, and re-evaluate whether P&L figures are now
   trustworthy.
3. If completion rate does NOT improve: design REST snapshot or forced
   reconnect fallback (see KNOWN DEBT in CLAUDE.md).
4. Continue monitoring 30-day paper trading clock (started 2026-06-29,
   target live date 2026-07-29).

---

## 2026-06-30 (Session 17 close-out — documentation only)

### What was done
- **CLAUDE.md** — three updates:
  1. Added two KNOWN DEBT entries:
     - `book_needs_reset` recovery deployed but `book_snapshot_applied` not yet
       observed in VPS logs — books may still stay corrupt until full reconnect.
     - Paper trading P&L figures ($58–$288/trade at ~$500 position, 11–57%
       net margins) are likely inflated due to corrupt order books feeding
       stale spreads to ArbScanner. Do not treat paper figures as live forecast.
  2. Updated Next session priorities — snapshot recovery verification is now
     #1 (gate on P&L validity), Telegram mute/unmute is #2, paper monitoring
     moved to #3, live executor spec to #4.
  3. Fixed stale Current status: compliance.py was still listed as "v2 UPDATED";
     corrected to "v4 UPDATED" with pointer to Architecture section.
- **DECISIONS.md** — new entry at top covering four Session 17 decisions:
  S1 deterministic P&L (no polling), CSV atomic read-modify-write, real-time
  DB INSERT, and book reset re-subscribe (deployed but unconfirmed).
- **SESSIONS.md** — this entry.
- No `.py` files touched this close-out.

### Session 17 full summary (all four code tasks)
Test count progression: 49 → 53 (S17 main) → 53 (S17-fu1, no change) → 55 (S17-fu2) → 59 (S17-fu3)

| Task | What shipped | Key decision |
|------|-------------|--------------|
| S17 main | `handle_trade_resolved` in compliance.py — CSV atomic RMW, DB UPDATE, audit trail | S1 P&L deterministic; no Kalshi API call |
| S17-fu1 | Import path check — `TradeResolvedEvent` already on `core.events`; no change | — |
| S17-fu2 | `_insert_db_trade_executed` + `_ensure_log_files` DB bootstrap | Real-time INSERT over nightly batch |
| S17-fu3 | `_request_snapshot` in price_watcher.py — WS re-subscribe on gap, 10s throttle | Re-subscribe > REST or forced reconnect |

### Open questions going into next session
1. Does Kalshi actually respond to a duplicate subscribe with an `orderbook_snapshot`?
   Watch for `book_snapshot_requested` → `book_snapshot_applied` in VPS logs.
2. If yes: does `book_needs_reset` rate drop and P&L figures normalize to <5% net?
3. If no: design fallback (REST `/markets/{ticker}/orderbook` or forced reconnect).

### Verification (close-out session)
- No `.py` files modified (documentation only) ✓
- All prior test passes (59/59) still stand — no new code to break them ✓

---

## 2026-06-30 (Session 17 follow-up 3 — WS snapshot re-request on sequence gap)

### What was built
- **`agents/floor/price_watcher.py` — `_request_snapshot` added; `_handle_kalshi_delta`
  reset block wired to call it.**
  Root cause: `book.needs_reset` (set on sequence gap) caused the affected market's
  order book to stay corrupt indefinitely — the `book_needs_reset` guard dropped every
  subsequent delta, and the comment said "In production: request snapshot from REST API"
  but nothing was ever sent. Live VPS logs showed this firing continuously on dozens of
  markets, meaning ArbScanner ran S1 detection against stale books with no path to
  recovery short of a full WS reconnect.
  Fix: `_request_snapshot(market_id)` sends a `subscribe` message over the existing WS
  (`cmd: "subscribe", channels: ["orderbook_delta"], market_tickers: [market_id]`) —
  no REST API call needed. Kalshi responds with an `orderbook_snapshot` message which
  routes through `_handle_kalshi_snapshot` → `book.apply_snapshot()` → clears
  `_gap_detected = False`. Normal delta flow resumes.
  Rate-limited: at most one re-subscribe per market per 10 seconds (checked via
  `_reset_requested: Dict[str, float]`, market_id → `time.monotonic()` of last send).
  Repeated gap events on the same market log `book_reset_throttled` at DEBUG instead
  of spamming the WS.
  Guards: no-ops if `_kalshi_client is None` or `_kalshi_client._connected is False`
  (`book_reset_skipped_no_connection`); send errors are caught and logged as
  `book_reset_send_failed`, never raised. Full WS reconnect via tenacity handles
  catastrophic failure.

- **`tests/test_kalshi_orderbook.py` — 4 new tests (59 total):**
  - `test_sequence_gap_sets_needs_reset_and_snapshot_clears_it` — gap → needs_reset=True,
    apply_snapshot → needs_reset=False. (Confirms existing `OrderBook` contract holds.)
  - `test_request_snapshot_throttled_second_call_suppressed` — two calls within 10s → one WS send.
  - `test_request_snapshot_throttle_resets_after_window` — call after >10s IS sent.
  - `test_request_snapshot_noop_when_client_none` — returns silently, no entry written to
    `_reset_requested`.

### What was decided
- WS re-subscribe is the correct recovery mechanism (not REST API snapshot): Kalshi
  sends a fresh `orderbook_snapshot` in response to a duplicate subscribe message on an
  already-subscribed market. `_handle_kalshi_snapshot` already handles these correctly.
  No new code path needed beyond the send.
- 10-second throttle per market chosen based on VPS log observation of gap events firing
  dozens of times per second on the same market during a gap event window. One re-subscribe
  is sufficient to trigger recovery; subsequent events before the snapshot arrives should
  be dropped (the `book.needs_reset` guard already does this) rather than flood the WS.
- `_subscribed_markets` tracking deliberately NOT modified on re-subscribe: we don't want
  to remove+re-add the market ID since the market is still considered subscribed. The WS
  send is a recovery signal, not a subscription state change.
- `id: 99` used as the message correlation ID (arbitrary fixed value; Kalshi doesn't
  enforce uniqueness, and this makes re-subscribe messages distinguishable in debug logs).

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **59/59 passed** ✓
  (55 baseline + 4 new in test_kalshi_orderbook.py)
- All four log points confirmed in source:
  `book_needs_reset` (line 537), `_request_snapshot` (line 561),
  `book_snapshot_requested` (line 594), `book_reset_throttled` (line 575) ✓
- `_reset_requested` initialized in `__init__` (line 342) ✓
- No new `aiohttp` usage in `_request_snapshot` ✓
- `execution/engine.py` and `main.py` untouched ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓

### After deploy to VPS, expect to see:
- `book_needs_reset` warnings still appear (gap detected)
- `book_snapshot_requested` INFO appears shortly after (new — recovery send)
- `book_snapshot_applied` DEBUG appears (existing — snapshot received)
- `book_needs_reset` rate drops significantly; markets recover instead of staying
  corrupt indefinitely
- `book_reset_throttled` DEBUG if gap events cluster (expected, not an error)

---

## 2026-06-30 (Session 17 follow-up 2 — real-time DB INSERT in handle_trade_executed)

### What was built
- **`agents/management/compliance.py` — `_insert_db_trade_executed` added;
  `handle_trade_executed` now calls it after the CSV write.**
  Root cause: compliance.db `trades` table was always empty — the INSERT path
  never existed, so ReflectionAgent's nightly cycle had nothing to read.
  Fix: `_insert_db_trade_executed` does `INSERT OR IGNORE INTO trades` with
  all available fields from `TradeExecutedEvent` (trade_id, opportunity_id,
  strategy, platform, market_id from first leg, fee_paid, expected_pnl_usd,
  paper_mode, status='FILLED', timestamp/opened_at=now, realized_pnl=0.0,
  resolved_at=None, holding_period_hours=0.0). `INSERT OR IGNORE` is idempotent
  against duplicate events. Logs `trade_inserted_db` at INFO.
  DB schema confirmed live via `PRAGMA table_info(trades)` before writing —
  all target columns present; no migration needed.
- **`_ensure_log_files` — compliance.db schema bootstrapped at agent startup.**
  Previously the DB was created by a separate Session 14 script; if the file
  was absent (e.g. fresh test environments), INSERT/UPDATE would silently skip.
  Now `_ensure_log_files` runs `CREATE TABLE IF NOT EXISTS` for `trades`,
  `rejections`, `audit_trail` synchronously via `sqlite3` (safe in `__init__`,
  no event loop yet). Existing DBs are unaffected (`IF NOT EXISTS`). This also
  means the DB is always available from the first trade onward without a
  separate bootstrap step.
- **`tests/test_compliance_resolution.py` — 2 new tests (55 total):**
  5. `test_trade_executed_inserts_db_row` — full pipeline trade → DB row with
     status='FILLED', realized_pnl=0.0 at fill time.
  6. `test_trade_executed_then_resolved_db_lifecycle` — same row transitions
     to status='RESOLVED', realized_pnl>0 after 1s paper resolution delay.

### What was decided
- DB schema bootstrap belongs in `_ensure_log_files` (always-on agent, startup
  is the right time) rather than a separate script or lazy-create on first INSERT.
  This removes the silent skip-on-missing-DB guard from the hot path and makes
  the DB always-ready for real-time writes from the first trade.
- `trade_id TEXT UNIQUE` constraint added in the bootstrapped schema — enforces
  the one-row-per-trade invariant at the DB level and makes `INSERT OR IGNORE`
  work correctly. The live DB (created Session 14) lacks this UNIQUE constraint;
  it will be added via migration before live trading. Not a blocker for paper.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **55/55 passed** ✓
  (53 baseline + 2 new in test_compliance_resolution.py)
- `INSERT OR IGNORE` confirmed in source (line 326 of compliance.py) ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓
- `execution/engine.py` and `main.py` untouched ✓

### DB schema note (live VPS)
The live `compliance.db` was created in Session 14 without the `UNIQUE`
constraint on `trade_id`. `CREATE TABLE IF NOT EXISTS` will not modify it.
The INSERT OR IGNORE will still work (no error; if a duplicate arrives,
the row is silently skipped). Add the UNIQUE constraint before live trading
via: `CREATE UNIQUE INDEX IF NOT EXISTS idx_trades_trade_id ON trades(trade_id)`.

### What to do first next session
1. Deploy to VPS (`git pull origin main`, restart `karbot`).
2. After first trades execute, confirm:
   `sqlite3 logs/compliance.db "SELECT trade_id, status, realized_pnl FROM trades LIMIT 5;"`
   returns FILLED rows immediately (not waiting for nightly cycle).
3. After `paper_resolution_delay_seconds`, confirm same rows show RESOLVED.

---

## 2026-06-30 (Session 17 follow-up — import path check)
Import path already consistent: `TradeResolvedEvent` was correctly placed in the
existing `from core.events import (...)` block by Session 17; no `karbot.core.events`
import present. No file changes needed. 53/53 tests confirmed.

---

## 2026-06-30 (Session 17 — TradeResolvedEvent wired into compliance.py)

### What was built
- **`agents/management/compliance.py` — `handle_trade_resolved` added.**
  Root cause: nothing subscribed to `TradeResolvedEvent` in compliance.py,
  so CSV rows written at fill time (with `gain_loss=0`, `status="FILLED"`)
  were never updated when a trade resolved. The P&L calculation in
  `PaperExecutor` was already correct — this was purely an event-wiring gap.
  Fix: added `TradeResolvedEvent` import, wired subscription in
  `register_subscriptions()`, implemented `handle_trade_resolved()` which:
  1. **CSV atomic read-modify-write** — reads all rows from
     `logs/kalshi_trades.csv`, updates every row matching the `trade_id`
     (sets `gain_loss = realized_pnl / num_matched_legs`,
     `hold_duration_seconds = holding_period_hours * 3600`,
     `status = "RESOLVED"`), writes to a `.csv.tmp` in the same directory,
     then `os.replace()` so a crash mid-write cannot corrupt the file.
  2. **DB update** — `UPDATE trades SET status='RESOLVED', resolved_at=?,
     realized_pnl=?, holding_period_hours=? WHERE trade_id=?` via
     `aiosqlite` against `logs/compliance.db`.
  3. **Audit trail** — appends `TradeResolvedEvent` entry to
     `logs/audit_trail.jsonl` via the existing `_append_audit` path.
  4. **Warning on unmatched** — if zero rows match `trade_id` (e.g. mock
     data, or resolution arriving before fill row was written), logs
     `trade_resolved_no_matching_rows` and does not raise.
  P&L split: `realized_pnl / len(matched_rows)` — evenly across however
  many leg rows exist for the trade (no hardcoded "2").
  No Kalshi API calls added. `execution/engine.py` and `main.py` untouched.

- **`tests/test_compliance_resolution.py`** — 4 new tests:
  1. `test_trade_resolved_updates_csv_gain_loss` — full pipeline (arb →
     gate → paper executor → compliance), 1s resolution delay, confirms
     both leg rows get `gain_loss = realized_pnl/2` and `status=RESOLVED`
  2. `test_trade_resolved_unmatched_trade_id` — unmatched trade_id logs
     warning, does not raise, existing CSV rows untouched
  3. `test_trade_resolved_updates_db` — pre-seeded DB row updated correctly
     (status, realized_pnl, holding_period_hours, resolved_at)
  4. `test_trade_resolved_written_to_audit_trail` — TradeResolvedEvent
     appears in audit_trail.jsonl

- **`CLAUDE.md`** — updated:
  - compliance.py status → v3, TradeResolvedEvent subscription noted
  - Test count → 53/53
  - Next session priority 1 updated to mention resolved-row verification
  - KNOWN DEBT: added Reconciliation subsection (future audit job against
    Kalshi's resolution API for S1 edge cases — NOT built this session)
  - FUTURE ROADMAP: added CSV→DB migration item (kalshi_trades.csv is
    currently the live write target; compliance.db should become source of
    truth in a future session); added clarifying note on S3/S4 settlement
    arb vs. S1 deterministic-P&L distinction

### What was decided
- S1 P&L is fully deterministic at fill time — no Kalshi resolution polling
  needed. `realized_pnl` on `TradeResolvedEvent` is computed by
  `PaperExecutor` as `(opp.net_profit_pct / 100) * approved_size`, same
  formula as `expected_pnl_usd`. Any future strategy that genuinely depends
  on real Kalshi settlement should design its resolution-polling path from
  scratch when that strategy is actually specced, not preemptively.
- DB schema confirmed live: `trades` table has `realized_pnl`,
  `holding_period_hours`, `status`, `resolved_at` columns — all present
  from Session 14; no schema migration needed.
- CSV schema confirmed: `gain_loss`, `hold_duration_seconds`, `status`
  all present in `KALSHI_CSV_HEADERS` — no column addition needed.
- Atomic write (`.csv.tmp` + `os.replace()`) used over direct in-place
  overwrite to prevent a crash mid-write from corrupting the IRS tax record.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: **53/53 passed** ✓
  (49 baseline + 4 new in test_compliance_resolution.py)
- No regressions in existing 49 tests ✓
- `ComplianceOfficer.handle_trade_resolved` registered as handler for
  `TradeResolvedEvent` confirmed in smoke test logs ✓
- compliance.db schema verified live via `PRAGMA table_info(trades)` —
  all target columns present ✓
- No `.env`, `config.yaml`, or `*.pem` in staged files ✓
- No credential values in any new log line ✓
- `execution/engine.py` and `main.py` untouched ✓
- Atomic temp-file + `os.replace()` confirmed in implementation ✓

### DB query confirming resolution update path (test_trade_resolved_updates_db):
```
SELECT status, realized_pnl, holding_period_hours, resolved_at
FROM trades WHERE trade_id = 'test-trade-db-001';
-- Returns: ('RESOLVED', 42.75, 2.5, '<iso-timestamp>')
```

### What to do first next session
1. Monitor `logs/kalshi_trades.csv` on VPS — deploy this fix (`git pull
   origin main`, restart `karbot`), then after `paper_resolution_delay_seconds`
   (default 300s) confirm rows show `gain_loss > 0` and `status=RESOLVED`.
2. Query `logs/compliance.db` via sqlite3 to confirm DB rows are also
   updating: `SELECT trade_id, status, realized_pnl FROM trades WHERE
   status='RESOLVED';`
3. Continue monitoring 30-day paper trading clock (started 2026-06-29,
   target live date 2026-07-29).

---

## 2026-06-29 (Session 16 — compliance CSV schema fix + Foundry hooks)

### What was built
- **`agents/management/compliance.py` — `_build_trade_row` / `handle_trade_executed`
  rewritten.** Root cause identified: `TradeExecutedEvent` stores all trade
  data inside `platform_legs` (a list of dicts), but `_build_trade_row` was
  reading nonexistent flat fields (`market_id`, `side`, `contracts`,
  `price_paid`, `fees_paid`, etc.) via `getattr(event, field, default)` —
  every field silently fell through to its default (empty string or 0), and
  `status` hardcoded to `"FILLED"` via the getattr default literal. This
  has been silently dropping all real trade data since Session 8 (when
  PaperExecutor was first wired). `_build_failure_row` had the same bug
  against `LegFailureEvent.failed_leg`.
  Fix: `handle_trade_executed` now iterates `event.platform_legs` and calls
  `_build_trade_row(event, leg)` once per leg (one CSV row per position —
  YES and NO legs each get their own IRS record). `_build_trade_row` reads
  real leg fields: `quantity`, `filled_price`, `fee_paid`, `market_id`,
  `side`, `platform`. `_build_failure_row` reads from `event.failed_leg`
  dict using the same field names. `gain_loss` and `hold_duration_seconds`
  remain 0 at fill time — correct, they update on `TradeResolvedEvent`.
  Confirmed live: VPS audit_trail.jsonl shows real Kalshi market trades
  (PGA, World Cup, tennis, MLB) with full `platform_legs` data already
  flowing correctly — this fix ensures that data now lands in the CSV.
- **`tests/test_paper_trading.py`** — `test_scenario1_happy_path` assertion
  updated from `rows == 1` to `rows == 2` (S1 arb produces 2 legs, 2 rows
  is correct). 49/49 passing.
- **`.gitignore`** — added 17 broader secret/credential filename patterns
  (`*.pem*`, `*.key*`, `config*.yaml*`, `secret*.yaml`, `*credential*.json`,
  `*.credentials*`, etc.) that catch suffixed variants the prior bare
  `*.pem` / `*.key` / `config.yaml` patterns missed. Validated with a 21-
  file adversarial fixture (9 dangerous caught, 9 legitimate not flagged).
- **`.claude/settings.json`** — Foundry hooks wired:
  - Hook 1 (SessionStart doc-loader): upgraded to bash-array form, safe
    for filenames with spaces
  - Hook 3 (Foundry status): shows "Active (scaffolded 2026-06-29)" at
    session start
  - Hook 2 (PreToolUse secrets-guard): blocks `git commit` when a
    credential-like file is staged; validated against 21-file fixture
- **`logs/kalshi_trades.csv`** — truncated to header-only locally (all prior
  rows were test-fixture artifacts from `--mock-prices` dev runs, not real
  paper trades). VPS truncation to be done as part of deploy sequence.

### What was decided
- Identified two separate bugs: (1) `_build_trade_row` schema mismatch
  with `TradeExecutedEvent` (every field empty — the high-priority fix);
  (2) the 50 "phantom" rows on the VPS are accumulated `--mock-prices`
  test-run artifacts from multiple prior sessions, not a startup code path
  firing unconditionally. No code path writes `TradeExecutedEvent`s at
  startup — `PaperExecutor._on_approved` is the only constructor and it
  only fires on `ApprovedOpportunityEvent`.
- One row per leg is the correct IRS record structure (each YES/NO position
  is a discrete $1-contract purchase at a specific price). A single
  summary row per trade hid the leg-level detail a CPA needs.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: 49/49 passed ✓
- End-to-end smoke test: CSV rows now show `market=KALSHI-TEST-001
  side=YES contracts=109.21 price_paid=0.4 fees=7.6447 status=FILLED` ✓
- No `.env`, `config.yaml`, or `*.pem` in staged changes ✓

### VPS confirmation + clock start (same session, later)
- VPS deployed: `git pull origin main`, CSV truncated, `karbot` restarted.
- **Confirmed live**: `kalshi_trades.csv` now contains real trades with
  real market IDs, sides, prices, and quantities (PGA, World Cup, tennis,
  MLB markets). `[COMPLIANCE] Trade logged | legs=2 | market=<real-id>`
  appearing in VPS logs. Fix fully verified end-to-end.
- **30-day paper trading clock started: 2026-06-29.**
  **Target live trading date: 2026-07-29.**

### What to do first next session
1. Monitor `logs/kalshi_trades.csv` and `logs/compliance_actions.jsonl` —
   paper trading clock is running, review periodically for any new bugs.
2. Begin live executor spec on 2026-07-29 when 30-day run completes.
3. Investigate dead_letter `AgentHeartbeat` events in VPS logs.

---

## 2026-06-28 (Session 15 continued — Kalshi WS message schema rewrite)

### What was built
- **`agents/floor/price_watcher.py` — `_handle_kalshi_snapshot()`,
  `_handle_kalshi_delta()`, `OrderBook.apply_delta()` rewritten.** After
  the mve_filter fix got real markets subscribing (785/4000), live VPS
  logs showed zero order book activity for 15+ minutes despite a healthy
  TCP socket (`ss -tnp` confirmed `ESTAB`, 0 queued bytes) and a
  successful `kalshi_subscribed` ack. Root cause: the WS message handlers
  assumed a schema that doesn't exist — `msg.get("market_ticker")` at the
  top level and `msg.get("yes", {}).get("bids"/"asks", [])` — so every
  snapshot and delta hit an early `return` on the empty `market_id` check
  before any log line fired, explaining the total silence.
  Confirmed the real schema two ways: (1) Kalshi's official WS docs
  (docs.kalshi.com/websockets/orderbook-updates), which clarified the
  payload is nested under `msg["msg"]` and named the real fields
  (`yes_dollars_fp`, `no_dollars_fp`, `price_dollars`, `delta_fp`, `side`)
  but left two correctness-critical questions unanswered: whether
  yes/no_dollars_fp are both bid-only books, and whether `delta_fp` is
  absolute or relative; (2) added temporary raw-message logging
  (`kalshi_raw_msg_diag`, committed and reverted within this session),
  redeployed, and inspected real captured Kalshi traffic directly. That
  resolved both open questions empirically: `yes_dollars_fp`/
  `no_dollars_fp` are both resting-bid-only books (standard Kalshi binary
  convention — YES ask = 1 − best NO bid, already implicit in
  `to_price_event()`'s existing math), and `delta_fp` is a RELATIVE
  change to the existing size (confirmed via a live matched +523.00/
  -523.00 pair on `KXCS2GAME-...-AIM` when a resting order moved from
  price 0.02 to 0.08 — only explicable as incremental deltas, not
  absolute replacements).
  `OrderBook.apply_delta()` signature changed from "set absolute size"
  to "add relative delta, clamp at 0, remove level at/below 0." Both
  handlers now read the nested `msg["msg"]` payload and route `side:
  "no"` deltas to the derived YES-ask book at `1 - price_dollars`.
- **tests/test_kalshi_orderbook.py** (new, 10 tests): `OrderBook.apply_delta`
  relative-size semantics (add, remove-at-zero, clamp-negative, the
  matched move-between-price-levels case mirroring the live KXCS2GAME
  example), snapshot parsing with real nested payload shape + NO→ask
  derivation, missing-ticker no-ops, and an unknown-`side` value handled
  without raising.

### What was decided
- Did not trust Kalshi's WS docs alone for the two correctness-critical
  questions (bid-only book structure, relative vs. absolute delta) —
  the docs themselves were explicitly ambiguous on both. Added
  temporary, clearly-marked diagnostic logging (`kalshi_raw_msg_diag`)
  to capture and reason from real live traffic instead of guessing,
  then removed it once both questions were resolved. This is the same
  empirical-verification discipline that caught the volume field name,
  pagination, and mve_filter bugs earlier in this session — applied here
  to a deeper, higher-blast-radius piece of logic (CLAUDE.md flags
  `OrderBook`/order book reconstruction as the most correctness-critical
  code in the system: "A bug here silently corrupts ALL downstream
  pricing").
- This was the third independent, compounding bug found in the Kalshi
  price-flow path this session (after the field-name/pagination bug and
  the mve_filter catalog-composition bug) — each was invisible until the
  prior layer was fixed and re-verified live. Reinforces: do not declare
  a fix complete on "tests pass" or even "the immediately-visible log
  line looks right" — verify the actual downstream effect (here, real
  order book data arriving) before updating CLAUDE.md status.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: 49/49 passed (39 prior
  + 10 new in test_kalshi_orderbook.py) ✓
- No `.env`, `config.yaml`, or `*.pem` in staged changes ✓
- Added a permanent one-shot `kalshi_first_price_update` INFO log (fires
  once per platform on the first successfully-applied delta) so this and
  future sessions have a real live confirmation signal instead of
  needing ad-hoc diagnostic logging again.
- **Deployed and confirmed live on the VPS**: `kalshi_ws_connected` ✓,
  `kalshi_markets_fetched count=1217 total=4000` ✓, `kalshi_markets_subscribed
  total=1217` ✓, `kalshi_first_price_update market=KXITFWMATCH-26JUN28MAQVAN-MAQ
  side=no` fired ~2 seconds after subscribing ✓. The full Kalshi
  price-flow chain (auth → fetch → subscribe → real order book deltas)
  works end-to-end for the first time this session.

### What to do first next session
- Confirm S1 arb opportunities appear in logs and paper trades land in
  `kalshi_trades.csv` now that PriceUpdateEvents are genuinely flowing
- Once paper trades are confirmed executing, start the 30-day paper
  trading clock — record the exact start date in CLAUDE.md and
  SESSIONS.md
- Update git remote URL on local + VPS from `WarpedMind/karbotrage_v1` to
  `WarpedMind/karbotrage`
- Begin live executor spec after the 30-day paper run completes
- Investigate `dead_letter` events for `AgentHeartbeat` firing every
  ~30s in VPS logs (noticed incidentally during this session's
  investigation) — likely a pre-existing gap (no Health Monitor agent
  subscribed to heartbeats yet) rather than a regression, but worth
  confirming it isn't masking a real event-bus wiring issue

---

## 2026-06-28 (Session 15 — Kalshi volume filter fix: field name + pagination + mve_filter)

### What was built
- **`_fetch_active_kalshi_markets()` fix** (agents/floor/price_watcher.py):
  diagnosed entirely via live API investigation from the VPS (real
  credentials, RSA-PSS auth against `api.elections.kalshi.com`) — three
  independent, compounding bugs were found, not one. The first two were
  caught and fixed before deploying; the third was only caught because
  the fix was verified live on the VPS after deploy rather than assumed
  fixed once tests passed locally.
  1. **Field name was wrong.** The code checked
     `m.get("volume_24h", m.get("volume", 0))`. Neither field exists on
     real Kalshi market objects. The actual field is `volume_24h_fp`,
     returned as a **string** (e.g. `"1837.10"`). The fallback to `0`
     meant the filter always evaluated against the default, excluding
     every market regardless of true volume.
  2. **Pagination was silently truncated to one page.** The function
     fetched exactly one page (`limit=200`, no cursor follow-up) and
     ignored the `cursor` field present in every response.
  3. **Caught only after deploying fixes 1+2 to the VPS**: a live check
     still showed `kalshi_markets_fetched count=0 total=4000` — the
     20-page cursor cap was being fully consumed by zero-volume markets.
     A deeper live probe (60 pages / 12,000 markets) found **every
     single one** was `KXMVESPORTSMULTIGAMEEXTENDED` or
     `KXMVECROSSCATEGORY` — multi-variable event (combo) markets. Pulled
     Kalshi's official API docs (docs.kalshi.com/api-reference/market/
     get-markets) for `GET /markets` and found a documented
     `mve_filter` parameter (`exclude`/`only`) made exactly for this.
     Verified live with `mve_filter=exclude`: page 1 alone returned real
     sports markets (MLB, KBO, NPB, tennis, World Cup) with genuine
     volume, 15/200 already nonzero, several clearing the >100 threshold
     (e.g. `KXWCMENTION-26JUN30MEXECU-NQE` at `489.0`).
  Fix: `mve_filter=exclude` added to every page's request params (primary
  fix — without it, pagination alone would need to climb past 12,000+
  dead markets with no guaranteed end); `cursor` pagination retained as a
  secondary safeguard (20-page cap, `KALSHI_MARKETS_PAGE_CAP`); read
  `volume_24h_fp`, cast to `float()`, missing/malformed values excluded
  rather than raising; `kalshi_markets_fetched` log reports total across
  all pages. Signing, padding, and the WS URL/path were not touched —
  confirmed working as of Session 13/14 and out of scope for this fix.
- **tests/test_price_watcher.py** (new): 4 tests — multi-page cursor
  following + volume_24h_fp filtering, exclusion of markets with
  missing/malformed volume fields, confirmation that `mve_filter=exclude`
  is sent on every page request, and early stop on non-200 response.

### What was decided
- Diagnosed via multiple rounds of live API investigation (small sample,
  full single-page pull, deep 12,000-market scan, official docs lookup,
  then a targeted `mve_filter` live verification) before each round of
  fixes — consistent with the Session 13/14 precedent of verifying
  claims against ground truth. Critically, also re-verified *after*
  deploying the first fix instead of trusting "tests pass locally" as
  sufficient — the test suite mocks the API shape we believe is correct,
  so it cannot catch a wrong assumption about the live catalog's actual
  composition. The mve_filter bug would have been invisible to any
  unit test written from the first round's (incomplete) understanding.
- Used the documented `mve_filter=exclude` param instead of a deeper
  page cap or a `series_ticker` allowlist — confirmed via Kalshi's own
  docs rather than guessing a workaround, and avoids hardcoding specific
  tickers.

### Verification
- `karbotrage_env/bin/python -m pytest tests/ -v`: 39/39 passed (35
  baseline + 4 in test_price_watcher.py) ✓
- No `.env`, `config.yaml`, or `*.pem` in staged changes ✓
- Live VPS deploy of fixes 1+2 confirmed the bug was deeper than
  expected (`count=0 total=4000`) — this entry's fix (mve_filter) has
  not yet been redeployed/reverified live; that is the first item for
  next session.

### What to do first next session
- Deploy this updated fix to the VPS (`git pull origin main`, restart
  `karbot` service) and confirm `kalshi_markets_fetched` reports a
  nonzero `count` in live logs — do not assume success without checking,
  per this session's own lesson
- Confirm S1 arb opportunities appear in logs and paper trades land in
  `kalshi_trades.csv` now that PriceUpdateEvents should be flowing
- Once paper trades are confirmed executing, start the 30-day paper
  trading clock — record the exact start date in CLAUDE.md and
  SESSIONS.md
- Update git remote URL on local + VPS from `WarpedMind/karbotrage_v1` to
  `WarpedMind/karbotrage`
- Begin live executor spec after the 30-day paper run completes

---

## 2026-06-27 (Session 14 — VPS deployment verification, compliance.db, AsyncAnthropic migration)

### What was built
- **VPS deployment**: SSH access to the Oracle VPS (`karbot-rage-prod`,
  147.224.209.18) was confirmed working (the Session 13 lockout was
  resolved before this session started). `git pull origin main` deployed
  the Session 13 Kalshi fix (`a7dc0ae`); `sudo systemctl restart karbot`
  restarted cleanly. Live logs confirmed `kalshi_ws_connected` and
  `kalshi_markets_fetched` (HTTP 200) — the domain + RSA-PSS fix works
  against the real production API, not just the local verification script.
- **logs/compliance.db** (local + VPS): created with `trades`, `rejections`,
  and `audit_trail` tables. The handoff brief proposed `data/compliance.db`
  with `created_at`/`opened_at` columns and no `audit_trail` table — neither
  matched what `ReflectionAgentImpl` actually reads. `ReflectionAgent.__init__`
  hardcodes `data_dir = Path("logs")`, and the nightly cycle queries a
  `status` column (filtered to `'RESOLVED'`), a generic `timestamp` column,
  and a SQLite `audit_trail` table (`event_type`, `entry_json`, `timestamp`)
  that nothing previously created. Built the schema to match the actual
  queries in agents/management/reflection.py, keeping the handoff's useful
  additive columns (trade_id, fee_paid, opportunity_id, etc.).
- **AsyncAnthropic migration**: the task as briefed named
  agents/research/regulatory_intelligence.py, but that file already used
  `AsyncAnthropic` correctly. The actual synchronous `anthropic.Anthropic`
  clients (matching CLAUDE.md's KNOWN DEBT wording) were in
  agents/research/market_analyst.py and agents/management/reflection.py.
  Both migrated to `AsyncAnthropic`; all four `.messages.create()` call
  sites (`market_analyst.py` ×2, `reflection.py` ×2) now use `await`, all
  within existing `async def` functions. Removed the now-stale KNOWN DEBT
  docstring note from `ReflectionAgent`.

### What was decided
- Verified the handoff brief's claims against the actual code before acting
  on them, twice: the compliance.db path/schema and the AsyncAnthropic
  target file were both incorrect in the brief. Built to match what the
  code actually does, not what the brief assumed — consistent with the
  Session 13 precedent of verifying external claims against ground truth
  before applying them.
- Did not touch the Kalshi market volume filter (`volume_24h > 100` in
  `_fetch_active_kalshi_markets()`) even though it currently returns 0
  active markets out of 200 fetched — out of scope for this session, no
  strategy/filter changes without explicit instruction. Logged as KNOWN
  DEBT instead.

### Verification
- VPS: `kalshi_ws_connected` ✓, `kalshi_markets_fetched` (200, count=0) ✓,
  zero 401/auth errors in logs ✓
- VPS: `logs/kalshi_trades.csv` has header only, no trade rows yet —
  expected, since 0 markets currently pass the volume filter so no
  PriceUpdateEvents flow and ArbScanner has nothing to evaluate
- `logs/compliance.db` created locally and on VPS; `trades`, `rejections`,
  `audit_trail` tables confirmed present in both via `sqlite_master` query
- `karbotrage_env/bin/python -m pytest tests/ -v`: 35/35 passed ✓
- `karbot_runner.py --mock-prices ... --exit-after-test`: 10 agents start,
  2 paper trades execute, exits cleanly — confirms AsyncAnthropic migration
  did not break the runtime path ✓

### What to do first next session
- Investigate the Kalshi market volume filter — 0/200 markets currently
  pass `volume_24h > 100` in `_fetch_active_kalshi_markets()`, so no
  PriceUpdateEvents flow and no paper trades can execute despite working
  auth and WS connection
- Update git remote URL on local + VPS from `WarpedMind/karbotrage_v1` to
  `WarpedMind/karbotrage` (old name still works via GitHub redirect, but
  should be cleaned up)
- Begin live executor spec (30-day paper run completed 2026-06-25)

---

## 2026-06-27 (Session 13 — Kalshi API migration: domain + RSA-PSS signing)

### What was built
- **agents/floor/price_watcher.py**: Kalshi migrated their API to a new domain
  (`api.elections.kalshi.com`, replacing `trading-api.kalshi.com`) and now
  requires RSA-PSS signing instead of RSA-PKCS1v15. Both changes applied:
  - `KalshiWebSocketClient.WS_URL` / `WS_PATH`, the REST base URL in
    `_fetch_active_kalshi_markets()`, and docstring references all updated
    to `api.elections.kalshi.com`.
  - `_build_kalshi_auth_headers()` now signs with
    `PSS(mgf=MGF1(hashes.SHA256()), salt_length=PSS.MAX_LENGTH)` instead of
    `crypto_padding.PKCS1v15()`.

### What was decided
- Changed one variable at a time rather than applying both fixes blind:
  first verified the domain-move claim against a live 401 error from
  Kalshi's own server ("API has been moved to
  https://api.elections.kalshi.com/"), applied the URL fix alone, then
  live-tested PKCS1v15 against the new domain — got
  `401 INCORRECT_API_KEY_SIGNATURE`, a signature-format rejection, not a
  routing error. Only then tried RSA-PSS, confirmed `200 SUCCESS` against
  `/trade-api/v2/portfolio/balance` using the real Kalshi credentials in
  `.env` / `/Users/tom/kalshi-keys/kalshi_private.pem`, and applied the PSS
  change to the actual source function (not just a throwaway test script).
- The RSA-PSS requirement was initially surfaced via a third-party web
  search with no independent confirmation — it was NOT applied until a live
  401 from Kalshi's real API confirmed the PKCS1v15 signature was actually
  being rejected post-migration.

### Verification
- Live auth test against `_build_kalshi_auth_headers()` in the actual
  source file: `200 SUCCESS` against `api.elections.kalshi.com` ✓
- `python -m pytest tests/ -v`: 35/35 passed ✓
- VPS-side verification (real WS connection, `kalshi_ws_connected`,
  `kalshi_markets_fetched`, live S1 opportunities) still blocked — SSH
  access to the Oracle VPS (`karbot-rage-prod`, 147.224.209.18) is currently
  lost; the authorized key's comment is `ssh-key-2026-05-27` and no local
  file matches it. Serial console recovery was in progress as of this
  session but not completed.

### What to do first next session
- Restore SSH access to the VPS (serial console recovery, or locate the
  missing `ssh-key-2026-05-27` private key)
- `git pull` on the VPS to get this fix, then confirm `kalshi_ws_connected`
  and `kalshi_markets_fetched` in the logs with the new domain + RSA-PSS
- Once data flows: confirm S1 opportunities and paper trades land in
  logs/kalshi_trades.csv
- Build compliance.db schema so ReflectionAgent's nightly cycle can run
- Begin live executor spec (30-day paper run completed 2026-06-25)

---

## 2026-06-14 (Session 12 — Security fix: PriceWatcher startup log + repo rename)

### What was built
- **Fixed CLAUDE.md security violation introduced in Session 11**:
  `PriceWatcher.run()` (agents/floor/price_watcher.py) logged
  `key_id=key_id, key_path=key_path` at INFO level when starting the Kalshi
  WS connection — both are `SecretsConfig` field values, and `key_path` is a
  private key filesystem path. Removed both fields from the log call; the
  message now just reads `"PriceWatcher: starting Kalshi WS connection"`
  with no arguments.
- Updated README.md to reflect the current 10-agent architecture (was stale
  at "six agents"), correct run commands (`--mode paper`, `--mock-prices`,
  `--exit-after-test`), updated project layout, and current "Next up" list.
- Updated CLAUDE.md GitHub repo URL to the renamed repo (see below).

### What was decided
- GitHub repo renamed from `WarpedMind/karbotrage_v1` to
  `WarpedMind/karbotrage` (the `_v1` suffix was unnecessary — GitHub handles
  versioning via branches/tags/releases, not repo names). GitHub
  automatically redirects the old URL, and the local `origin` remote was
  updated to point at the new URL.

### Verification
- python -m pytest tests/ -v: 35/35 passed ✓
- karbot_runner.py --exit-after-test: 10 agents start, 2 paper trades execute,
  zero "Task was destroyed" warnings, exits cleanly ✓
- Confirmed no other code/docs referenced the old `kalshi_api_key_id`/
  `kalshi_private_key_path` values in log calls ✓

### What to do first next session
- SSH to VPS, `git remote set-url origin https://github.com/WarpedMind/karbotrage.git`
  (or rely on GitHub's redirect), then `git pull` to get this fix
- Continue with Session 11's "what to do first next session" items (Kalshi WS
  connection verification, S1 opportunities, compliance.db schema)

## 2026-05-30 (Session 11 — Real paper trading: stub wiring + Kalshi auth)

### What was built
- **Kalshi RSA auth (price_watcher.py)**: replaced the incorrect HMAC-SHA256 implementation
  with RSA-PKCS1v15/SHA-256.  New module-level `_load_kalshi_private_key()` and
  `_build_kalshi_auth_headers()` helpers use `cryptography` to sign the request.
  `KalshiWebSocketClient` now takes `key_id` + `private_key_path` (matching
  `SecretsConfig.kalshi_api_key_id` / `kalshi_private_key_path`); private key is
  loaded once at construction.  `additional_headers=` used for websockets 12+.
  `subscribe_markets()` now sends all tickers in a single batched message
  (chunked at 50) rather than one message per market.
  `_fetch_active_kalshi_markets()` now uses RSA-signed headers and accepts both
  `volume_24h` and `volume` field names from the Kalshi REST response.
- **PriceWatcher** now inherits from `PriceWatcherAgent`.  `run()` checks for
  credentials; if present, calls `self.start()` to open the real Kalshi WS
  connection; if absent, idles with an informative log and zero network calls.
- **ArbScanner.run()**: starts `_heartbeat_loop` + `_cache_cleanup_loop` tasks,
  then idles.  Subscription handling (PriceUpdateEvent → S1 check → OpportunityEvent)
  was already wired through the inherited `ArbScannerAgent` implementation.
- **RiskGate.run()**: starts `_heartbeat_loop` task, then idles.  All eight
  pre-trade checks were already in the inherited `RiskGateAgent` implementation.
- **MarketAnalyst** now inherits from `MarketAnalystAgent`.  `run()` starts the
  5-minute LLM analysis loop, heartbeat, and cache-cleanup tasks.  Analysis is
  a no-op when `ANTHROPIC_API_KEY` is not set (no API calls made).
- **ReflectionAgent** now inherits from `ReflectionAgentImpl`.  `run()` starts the
  nightly scheduler (02:00 ET / 07:00 UTC) and heartbeat.  Nightly cycle will
  fail gracefully (logged, not raised) until `compliance.db` exists with the
  required schema — deferred to a future session.
- **PaperExecutor** added to the continuous paper mode agent list in
  `karbot_runner.py`.  Previously only present in the `--mock-prices` branch,
  so approved opportunities in continuous mode had nowhere to go.
  `PaperExecutor.register_subscriptions()` self-guards on `paper_mode`; safe
  to include in live mode when that path is eventually enabled.
- **`--exit-after-test` cleanup**: added a second cancellation pass over
  `asyncio.all_tasks()` after the main tasks are cancelled, eliminating
  "Task was destroyed but it is pending!" warnings from background sub-tasks.
- **`cryptography>=41.0.0`** added to `requirements.txt`.

### What was decided
- All five stub agents now use inheritance over delegation — consistent with the
  existing `ArbScanner`/`RiskGate` pattern.
- Synchronous `anthropic.Anthropic` client in `MarketAnalystAgent` and
  `ReflectionAgentImpl` blocks the event loop for ~1-2 s per LLM call.
  Acceptable for paper trading; must be replaced with `AsyncAnthropic` before
  live trading.  Added to KNOWN DEBT.
- `ReflectionAgent` nightly DB dependency deferred: `compliance.db` schema
  creation is a separate session item.

### Verification
- python -m pytest tests/ -v: 35/35 passed ✓
- karbot_runner.py --exit-after-test: 10 agents start, 2 paper trades execute,
  zero "Task was destroyed" warnings, exits cleanly ✓
- Mock-prices path unaffected ✓

### What to do first next session
- SSH to VPS and tail the runner logs to confirm Kalshi WS connects with RSA
  auth and PriceUpdateEvents start flowing
- Watch for `kalshi_ws_connected` and `kalshi_markets_fetched` in the logs
- If auth fails: check KALSHI_API_KEY_ID format and private key path in .env;
  verify RSA key is registered at kalshi.com → Account → API Keys
- Once data flows: observe S1 opportunities being found (or not) and confirm
  PaperExecutor is logging paper trades to logs/kalshi_trades.csv

---

## 2026-05-26 (Session 10 — Continuous paper mode fix)

### What was built
- karbot_runner.py — added `_run_supervised()` helper; wraps each agent's `run()` so
  any non-CancelledError exception is logged and swallowed, letting all other agents
  continue running; agent task creation now passes through the supervisor wrapper;
  main `asyncio.gather()` updated to `return_exceptions=True`
- agents/floor/price_watcher.py — `PriceWatcher.run()` (the BaseAgent stub ONLY;
  `PriceWatcherAgent` full impl was not touched) now checks `config.paper_mode`:
  - If True: logs INFO "PriceWatcher: paper mode active, no mock feed configured —
    idling. No PriceUpdateEvents will be emitted." then enters 60s sleep loop with
    DEBUG heartbeat; zero network calls
  - If False (future live path): falls through to existing "stub running" loop

### What was verified (9/9 smoke test checks green)
- Runner starts without errors in continuous paper mode ✓
- All agents log startup messages ✓
- PriceWatcher paper idle message logged exactly once ✓
- No WebSocket connection attempts in logs ✓
- No credential-related errors ✓
- No exceptions or tracebacks ✓
- python -m pytest tests/ -v: 35/35 passed ✓
- karbot_runner.py --exit-after-test still works (mock path unaffected) ✓
- Ctrl+C (SIGINT) exits cleanly (exit_code=0) ✓

### What was decided
- PriceWatcher paper idle path lives only in the stub (PriceWatcher.run()), never in
  PriceWatcherAgent — confirmed explicitly
- Supervisor wrapper swallows non-fatal agent exceptions so one crash cannot kill others
- 30-day paper trading clock is confirmed running — continuous mode is stable

### What to do first next session
- Review paper trading daily summary logs (logs/compliance_actions.jsonl)
- When 30-day clock completes (2026-06-25): provision Kalshi RSA credentials per
  .env.example, then open spec session for live_executor.py

---

## 2026-05-26 (Session 9 — Security + TradeResolvedEvent)

### What was built
- SecretsConfig dataclass in karbot/core/config.py — all credentials load from
  environment variables only; warns on missing secrets at startup
- config.yaml moved to .gitignore; config.yaml.example and .env.example created
- python-dotenv added to requirements.txt; load_dotenv() at top of karbot_runner.py
- telegram_agent.py updated to read credentials from config.secrets.*
- regulatory_intelligence.py updated to pass API key explicitly to AsyncAnthropic()
- SystemConfig.paper_resolution_delay_seconds added (default 300s)
- PaperExecutor now schedules TradeResolvedEvent via asyncio.create_task() after
  paper_resolution_delay_seconds; realized_pnl computed from net_profit_pct * capital
- PositionTracker._on_trade_resolved() confirmed correct — no changes needed
- tests/test_paper_trading.py — 2 new tests: test_paper_trade_resolves_after_delay
  (1s delay, confirms capital returns to 0, total_capital grows) and
  test_full_paper_pnl_cycle (two trades resolve, cumulative P&L verified)
- Full paper P&L cycle confirmed end-to-end

### What was decided
- SecretsConfig is the project-wide permanent pattern for credential loading
- config.yaml is never committed — config.yaml.example is the committed reference
- 30-day paper trading clock starts this session (target complete 2026-06-25)
- Next milestone: Kalshi credential provisioning + live executor spec

### Verification
- python -m pytest tests/ -v: 35/35 passed ✓
- karbot_runner.py --exit-after-test: starts and exits cleanly ✓
- config.yaml confirmed gitignored ✓
- No credential values in runner output ✓

### What to do first next session
- Review paper trading daily summary logs (logs/compliance_actions.jsonl)
- When 30-day clock completes: provision Kalshi RSA credentials per .env.example
  instructions, then open a spec session for live_executor.py

---

## 2026-05-26 (Session 8 — PositionTracker Phase 2)

### What was built
- agents/floor/position_tracker.py — **Phase 2 COMPLETE** — register_subscriptions() now wires TradeExecutedEvent, TradeResolvedEvent, LegFailureEvent; _on_trade_executed computes capital from filled_price×quantity across all legs, appends to _open_positions, increments _daily_trades, publishes snapshot; _on_trade_resolved frees capital (floored at 0), adds realized_pnl to _daily_pnl and _total_capital, removes position, publishes snapshot; _on_leg_failure unwinds position (floored at 0), logs WARNING, publishes snapshot; _maybe_daily_reset() helper resets _daily_pnl/_daily_trades at UTC midnight, called from 30s loop; _publish_snapshot() now computes unrealized_pnl_usd as sum of expected_pnl_usd across open positions
- tests/test_position_tracker.py — **NEW** — 9 tests all passing; covers startup snapshot, executed/resolved/failed trade state transitions, double-trade stacking, capital floor, daily reset, graceful empty-legs handling; integration test (test_risk_gate_sees_accurate_capital) confirms Risk Gate enforces 40% capital limit against real deployed capital

### What was verified
- python -m pytest tests/ -v: 33/33 passed ✓
- python -m pytest tests/test_position_tracker.py::test_risk_gate_sees_accurate_capital -v: PASSED ✓
- karbot_runner.py --exit-after-test: starts cleanly, deployed capital updates live (87→174 USD after two paper trades), exits cleanly ✓
- logs/kalshi_trades.csv: prior rows intact + 2 new rows written this session ✓

### What was decided
- _maybe_daily_reset() extracted as a separate (sync) method so tests can call it directly without running the 30s loop — cleaner than mocking datetime
- capital_used computed as sum(filled_price × quantity) across all legs — matches paper executor's fill model
- TradeResolvedEvent handler adds realized_pnl to both _daily_pnl and _total_capital — correct: total capital grows/shrinks as trades resolve

### What to do first next session
1. Wire execution layer to emit TradeExecutedEvent and LegFailureEvent on real fills so the live path mirrors the paper path
2. Wire TradeResolvedEvent on market resolution so positions close and total_capital updates correctly (required before live trading)

---

## 2026-05-26 (Session 7 — Regulatory Intelligence Agent)

### What was built
- agents/research/regulatory_intelligence.py — **COMPLETE** — RegulatoryIntelligenceAgentImpl (full impl) + RegulatoryIntelligenceAgent (BaseAgent stub); polls CFTC RSS + Federal Register every 6h; keyword pre-filter controls Claude API costs; Claude Sonnet (claude-sonnet-4-6) assesses urgency 1-5; urgency 3→Telegram FYI, 4→Telegram alert, 5→Telegram+trading pause; weekly sweep (Sunday 06:00 UTC) skips keyword filter; per-cycle cap, daily hard cap, circuit breaker, overflow queue, monthly spend estimator; operator clears urgency-5 pause by sending regulatory_clear_phrase via Telegram
- core/events.py — RegulatoryAlertEvent extended with AI-assessment fields (urgency, summary, affected, recommended_action, raw_title, cycle_type); TelegramPermissionResponseEvent extended with response_text; EventBus priority queue fixed with 3-tuple (priority, seq, event) tiebreaker
- karbot/core/config.py — RegulatoryIntelligenceConfig sub-dataclass added; wired into KarbotConfig + from_yaml()
- config.yaml — regulatory_intelligence: block added with all 11 configurable parameters
- agents/management/compliance.py — polling loop removed; subscribes to RegulatoryAlertEvent and logs to compliance_actions.jsonl; aiohttp import removed
- agents/floor/risk_gate.py — subscribes to RegulatoryAlertEvent; _regulatory_pause state; urgency=5 blocks trade approvals with REGULATORY_PAUSE; urgency=0 clears pause
- agents/notifications/telegram_agent.py — _handle_operator_reply publishes TelegramPermissionResponseEvent with response_text on every operator message (not just when pending request exists)
- karbot_runner.py — RegulatoryIntelligenceAgent added to both agent lists (now 10 agents)
- tests/test_regulatory_intelligence.py — 11 tests all passing; mocked Claude API; covers keyword filter, overflow queue, urgency 1-2/3/5, Risk Gate pause/resume, operator clear, deduplication, daily cap, circuit breaker, compliance logging, bad API response

### What was decided
- Claude Sonnet over Haiku for regulatory assessment — quality matters for compliance decisions
- Circuit breaker requires runner restart — not clearable via Telegram by design
- EventBus tiebreaker: (priority, seq, event) 3-tuple — pre-existing bug exposed by heavy same-priority event publishing; fixed globally

### Verification
- python -m pytest tests/ -v: 24/24 passed ✓
- karbot_runner.py --exit-after-test: 10 agents start and exit cleanly ✓
- ComplianceOfficer polling loop gone (confirmed via grep) ✓
- test_urgency_5_pauses_risk_gate: PASSED ✓
- test_operator_clear_resumes_risk_gate: PASSED ✓

### What to do first next session
1. Wire PositionTracker to subscribe to TradeExecutedEvent so deployed capital is tracked accurately across runs (Phase 2 of PositionTracker)
2. Wire execution layer to emit LegFailureEvent on partial fill / API error so compliance audit trail captures failures

---

## 2026-05-26 (Session 6 — Telegram notification agent)

### What was built
- agents/notifications/__init__.py — new package
- agents/notifications/telegram_agent.py — TelegramNotificationAgent (full impl) +
  TelegramAgent (BaseAgent stub); subscribes to TelegramNotificationEvent,
  TelegramPermissionRequestEvent, RegulatoryAlertEvent (Tier 1), LegFailureEvent
  (Tier 1), TradeExecutedEvent (Tier 2), RejectedOpportunityEvent (Tier 2);
  getUpdates polling every 3s; 1 msg/sec rate limit; single-operator FIFO permission
  resolution; always publishes TelegramPermissionResponseEvent with response_text;
  enabled=False → complete no-op (no HTTP calls, no polling)
- core/events.py — 4 new event types added: RegulatoryAlertEvent,
  TelegramNotificationEvent, TelegramPermissionRequestEvent,
  TelegramPermissionResponseEvent
- karbot/core/config.py — TelegramConfig sub-dataclass added; wired into KarbotConfig
  and from_yaml(); credentials load from environment only (TELEGRAM_BOT_TOKEN,
  TELEGRAM_CHAT_ID)
- karbot_runner.py — TelegramAgent added last in both agent lists (now 9 agents at
  end of this session)

### What was decided
- Polling over webhook: VPS does not expose public inbound ports; polling at 3s
  intervals is sufficient for human response times; zero additional infrastructure
- Single-operator FIFO permission resolution: any yes/no reply resolves oldest
  pending request; revisit if concurrent permission requests become a real scenario
- TelegramConfig credentials from environment only — never config.yaml
- enabled=False is the default — must be explicitly opted in

### Verification
- python -m pytest tests/ -v: 13/13 passed (at time of this session) ✓
- karbot_runner.py --exit-after-test: 9 agents start and exit cleanly ✓
- TelegramAgent confirmed no-op when enabled=False ✓

### What to do first next session
- Spec and build Regulatory Intelligence Agent (uses Telegram layer)
- Replace ComplianceOfficer keyword polling with Claude API interpretation

---

## 2026-05-26 (Session 5 — Paper trading verification, debt cleanup, sequencing)

### What was done
- Fixed pre-existing Secrets import collection errors in test_config.py and test_core_config.py
- Root cause: Secrets dataclass and compliance/alerts sub-configs were removed in a prior session; test files not updated
- Deleted test_secrets_creation() with explanatory comment; updated remaining tests to match current KarbotConfig structure
- Full test suite now 13/13 green, zero collection errors, zero new failures
- Cleared KNOWN DEBT section in CLAUDE.md
- Decided next two roadmap items: Telegram standalone layer → Regulatory Intelligence Agent
- Decided Telegram architecture: Option A (standalone agent, not inline)

### What was decided
- Telegram built as standalone BaseAgent before Regulatory Intelligence Agent
- Project principle locked in: quality and best practice over speed, always
- Spec in Claude.ai before every Claude Code session, no exceptions

### What to do first next session
- Spec the standalone Telegram notification layer in Claude.ai
- Key design questions to resolve in spec: which event types trigger Telegram alerts, how operator permission requests work over Telegram, whether the agent subscribes to a dedicated TelegramNotificationEvent or handles multiple event types directly

---

## 2026-05-26 (Session 4 — Secrets import fix / test cleanup)

### What was fixed
- tests/test_config.py — removed stale `Secrets` import; removed `assert Secrets is not None` from test_config_loading(); added comment explaining the removal
- tests/test_core_config.py — removed stale `Secrets` import; removed assertions for `config.compliance` and `config.alerts` (these sub-configs do not exist in the current KarbotConfig dataclass); deleted `test_secrets_creation()` with an explanatory comment; added comment explaining the import removal
- CLAUDE.md — removed KNOWN DEBT section (resolved) and removed item 3 from Next session priorities

### What was decided
- `Secrets` was deliberately removed from `karbot/core/config.py` in a prior session; no replacement exists; API credentials are not managed as a config dataclass in the current architecture
- `config.compliance` and `config.alerts` were removed along with `Secrets`; current KarbotConfig has: system, data_feeds, capital, risk, strategies, intelligence
- Both tests were preserved where the functionality they tested still exists; only the stale `Secrets`-dependent assertions and the `test_secrets_creation` test were removed

### Verification
- `python -m pytest tests/ -v`: 13/13 passed, 0 collection errors, 0 new failures ✓
- Paper trading tests still pass (3/3) ✓

### What to do first next session
- Wire PositionTracker to subscribe to TradeExecutedEvent so deployed capital is tracked accurately across runs (Phase 2 of PositionTracker)
- Wire execution layer to emit LegFailureEvent on partial fill / API error so compliance audit trail captures failures

---

## 2026-05-25 (Session 3 — PositionTracker startup snapshot)

### What was built
- agents/floor/position_tracker.py — new BaseAgent that publishes a PositionSnapshot at the very top of run() before entering its periodic loop; PAPER_DEFAULT_CAPITAL=10_000 used when config.capital.total_deployed_usd is 0 and paper_mode=True; 30s periodic re-publish to keep snapshot fresh
- agents/floor/mock_price_watcher.py — added 0.1s initial delay before first price emit; this gives PositionTracker's startup snapshot one event-loop iteration to be dispatched to RiskGate before the first OpportunityEvent can arrive
- karbot_runner.py — PositionTracker imported and placed first in both agent lists (mock and normal branches); ordering comment explains why it must be first

### What was decided
- Startup sequencing is the fix, not a ready-gate in RiskGate: PositionTracker publishes synchronously at the start of run(), bus.run() dispatches it before MockPriceWatcher's 0.1s sleep expires, so RiskGate always has a snapshot before the first OpportunityEvent
- PAPER_DEFAULT_CAPITAL=10_000 avoids ZERO_CAPITAL rejection in dev/test runs where operator has not set total_deployed_usd in config.yaml
- PositionTracker.run() never calls agent.run() in tests — tests continue to inject PositionSnapshot manually via bus.publish() for full control over capital state

### Verification
- Runner --exit-after-test: trades approved and logged (KALSHI-TEST-001 and KALSHI-TEST-002 both executed) ✓
- logs/kalshi_trades.csv: header + 2 data rows ✓
- logs/audit_trail.jsonl: 2 × TradeExecutedEvent entries present ✓
- tests/test_paper_trading.py: 3/3 pass ✓
- tests/ full suite: 10 collected, 2 pre-existing Secrets import errors (not introduced here), 0 new failures ✓

### What to do first next session
- Wire PositionTracker to subscribe to TradeExecutedEvent and update deployed capital across runs (Phase 2)
- Wire execution layer to emit TradeExecutedEvent / LegFailureEvent from real trade attempts
- Address pre-existing Secrets import collection errors in test_config.py and test_core_config.py

---

## 2026-05-25 (Session 2 — Paper trading pipeline / PaperExecutor)

### What was built
- agents/floor/paper_executor.py — thin BaseAgent that closes the paper trading loop; subscribes to ApprovedOpportunityEvent, simulates full fill at opportunity leg prices, emits TradeExecutedEvent(paper_mode=True)
- agents/floor/mock_price_watcher.py — fixture-driven price replay agent; reads a JSON file, emits PriceUpdateEvents, signals completion via asyncio.Event so --exit-after-test can wait on it
- tests/fixtures/paper_test_prices.json — 3 price snapshots (happy path / rejection / no-opportunity); prices use YES=0.40, NO=0.40 (sum=0.80) to clear Kalshi's ~14% round-trip fee model; spec's 0.47/0.51 was noted as unprofitable after fees
- tests/test_paper_trading.py — 3 pytest scenarios, all passing; each uses a fresh EventBus + agents in-process (no subprocess); monkeypatches LOGS_DIR for isolation
- karbot_runner.py — added argparse with --mock-prices <path> and --exit-after-test flags; --mock-prices swaps in MockPriceWatcher + PaperExecutor; --exit-after-test waits on done_event, settles 2s, cancels cleanly
- agents/management/compliance.py — fixed _append_audit datetime/Enum JSON serialization bug (added _audit_json_default encoder); this was a pre-existing bug triggered by the new TradeExecutedEvent and RejectedOpportunityEvent payloads

### What was decided
- Fixture prices deviate from spec's 0.47/0.51: Kalshi fee model (~14% round-trip) makes those prices unprofitable; 0.40/0.40 (sum=0.80, gross=20%, net≈5.7%) is used instead to make the pipeline fire correctly
- Tests do NOT run agent.run() loops — only register_subscriptions() + bus.run(); this avoids the regulatory check making live HTTP calls during tests
- Scenario 2 rejection is triggered by injecting a saturated PositionSnapshot (90% deployed > 40% limit) before the price event; this is more deterministic than relying on capital_required_usd

### What to do first next session
- Implement PositionTracker agent so runner mode can emit PositionSnapshot events (currently Risk Gate always rejects with NO_POSITION_DATA in runner mode)
- Wire execution layer to emit TradeExecutedEvent / LegFailureEvent from real trade attempts

---

## 2026-05-25 (Session 1 — ComplianceOfficer v2)

### What was built
- ComplianceOfficer v2 — full implementation replacing stub; all 7 verification steps passed
- IRS dual-track trade logging: Kalshi trades logged as ordinary income, Polymarket as capital gains (Section 1256)
- Append-only audit trail (logs/audit_trail.jsonl) — every trade, rejection, and leg failure recorded
- Regulatory monitor — polls CFTC RSS feeds and Federal Register every 6h; keyword matching triggers REGULATORY_ALERT warning banner
- compliance_actions.jsonl — operator-facing action log, serves as CFTC Letter 26-15 cooperation evidence
- REGULATORY_HALT enforcement — if config.yaml sets regulatory_halt: true, bot refuses to start until operator clears and documents it
- ComplianceOfficer subscriptions wired to TradeExecutedEvent, LegFailureEvent, RejectedOpportunityEvent
- CLAUDE.md updated with full CFTC regulatory context (Letter 26-15, Van Dyke prosecution, DEATH BETS Act)

### What was decided
- ComplianceOfficer is the compliance-first layer; it runs live and verified at each startup
- regulatory_halt is an operator-set gate — not automated — requiring documented human sign-off
- CFTC Letter 26-15 (effective May 19 2026): compliance_actions.jsonl IS the cooperation evidence; treat it as a legal record
- Karbot Rage! is clean: public data only, arbitrage only, no MNPI, Kalshi-only Phase 1, full audit trail from day one

### What to do first next session
- Paper trading end-to-end test via agent layer
- Wire execution layer to emit TradeExecutedEvent / LegFailureEvent so ComplianceOfficer logs real trades

---

## 2026-05-25 (Session 0 — Requirements, Config, Market Data, Agent Wiring)

### What was built
- karbot_runner.py — new event-bus-driven entry point; all 6 Phase 1 agents start, run, and shut down cleanly (verified)
- agents/management/compliance.py — ComplianceOfficer stub; always-on, cannot be disabled
- All 6 runner-facing agent stubs given conforming run() and register_subscriptions() methods
- KarbotConfig extended: from_yaml() classmethod, .phase property, .paper_mode property
- karbot/core/ package created; Phase 1 invariants enforced structurally at __init__ (polymarket_ws_enabled + phase=1 raises ValueError; s2_cross_platform_enabled + phase=1 raises ValueError; RiskConfig hard limits enforced at instantiation)
- requirements.txt restored (aiohttp, pydantic, websockets, pyyaml, python-json-logger, structlog, tenacity, aiosqlite, anthropic, pytest, pytest-asyncio, black, flake8)
- core/config.py defaults fixed: Kalshi enabled, Polymarket disabled
- data/market_data.py fixed: Kalshi-first, Polymarket gated behind polymarket_ws_enabled flag
- CLAUDE.md and DECISIONS.md fully updated and accurate

### What was decided
- Event-bus architecture is the canonical path; legacy execution/engine.py intentionally deferred until paper tested end-to-end
- BaseAgent interface (bus, config, register_subscriptions, run) is the standard for all runner-facing classes
- ComplianceOfficer is always-on — cannot be disabled by config

### What to do first next session
- Wire ComplianceOfficer subscriptions to TradeExecutedEvent
- IRS dual-track logging (Kalshi = ordinary income, Polymarket = capital gains)
- Paper trading end-to-end test via agent layer

---

## 2026-05-22 (Initial session)

### What was built
- Complete multi-agent trading system framework for prediction markets
- Modular architecture with core, execution, data, intelligence, strategies, trading, and monitoring components
- Configuration system with defaults
- Documentation files (README, DOCUMENTATION, ARCHITECTURE)
- Example usage script
- Testing framework
- Git repository setup with proper remote

### What was decided
- Multi-agent architecture with specialized agents for different functions (monitoring, analysis, strategy, trading, compliance)
- Modular design following clean architecture principles
- Configuration-driven system with defaults
- Separation of concerns between data handling, intelligence, strategy execution, and trading
- Logging and monitoring built-in from the start

### What to do first next session
- Implement actual market data API integrations for Polymarket and Kalshi
- Add real trade execution capabilities
- Implement more sophisticated trading strategies
- Add advanced risk management features
- Complete the testing framework with actual tests
