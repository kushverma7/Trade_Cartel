# RESULTS LEDGER

**Every backtest result on record, in one table.** Built 2026-07-29 by
extracting every result mention from `trader_playbooks/PLAYBOOK.md` and the
recovered session archive.

## Why this file exists

Before it, results lived as prose scattered across 1,097 lines of PLAYBOOK.md
— 19 separate PF mentions, of which only ~12 recorded a trade count and only
5 recorded the date range tested. There was no way to answer "what did engine
X score, on what sample, with what settings" without re-reading the whole
file. That is a large part of why 17 engines got built and none got validated:
the comparison was never actually available.

**Rules for this file**
1. Every row records the sample, not just the headline. A PF with no trade
   count and no date range is not a result.
2. `Unknown` means unknown. Do not infer, do not backfill from memory.
3. Nothing gets a `VALID` status without an out-of-sample test. As of this
   file's creation, **no row qualifies** — that is the finding.
4. New results are appended here in the session they are produced.

---

## The ledger

| # | Date | Engine | Sym / TF | Window | Trades | WR | PF | Net | Max DD | Status |
|---|---|---|---|---|---|---|---|---|---|---|
| 1 | ~07-15 | Reversal Sniper v2 (auto S/D zones) | XAUUSD 5m | Unknown | Unknown | Unknown | **0.731** | Unknown | Unknown | RETIRED — mechanism blamed & banned |
| 2 | 07-20 | Session Trendline Breakout | XAUUSD 5m | ~2 months | 117 | Unknown | **3.656** | Unknown | Unknown | **RETRACTED** — sample too small (free-plan data cap) |
| 3 | 07-20 | Top/Bottom engine, run 1 | XAUUSD 5m | Unknown | Unknown | Unknown | 0.90 (analog) | Unknown | Unknown | superseded |
| 4 | 07-20 | Top/Bottom engine, run 2 | XAUUSD 5m | Unknown | Unknown | Unknown | 0.67 (analog) | Unknown | Unknown | regression, diagnosed |
| 5 | 07-20 | Top/Bottom engine, run 3 | XAUUSD 5m | Unknown | Unknown | Unknown | 0.85 (analog) | Unknown | Unknown | superseded |
| 6 | 07-20 | **Top/Bottom engine, run 4** | XAUUSD 5m | Unknown | **112** | 35.7% | **1.11** (analog) | Unknown | Unknown | first >1; settings recovered 07-29 (see below) |
| 7 | 07-20 | Spaceman + Daye Quarters | XAUUSD 5m | Unknown | 12 | 0% | **0** | Unknown | Unknown | broken — 12/12 losses, root-caused |
| 8 | 07-20 | Spaceman + Daye, re-test | XAUUSD 5m | Unknown | 8 | 12.5% | **0.14** | Unknown | Unknown | abandoned |
| 9 | 07-27 | OMNIBUS four-model | XAUUSD 5m | Jun–Jul | 298 | 40.6% | **0.843** | −13.01% | Unknown | plateau |
| 10 | 07-27 | Key-to-Key | XAUUSD 5m | Jun–Jul | ~245 | 26.1% | **0.886** | −10.87% | 23.15% | plateau |
| 11 | 07-27 | Trendline × Key Levels v1 | XAUUSD 5m | Jun–Jul | 382 | 40.8% | **0.882** | −11.72% | 20.68% | plateau |
| 12 | 07-27 | Trendline × Key Levels v2 (+HTF bias) | XAUUSD 5m | Jun–Jul | ~380 | Unknown | **0.819** | −13.34% | 15.69% | REVERTED — filter made it worse |
| 13 | 07-28 | **Multi-Voice Confluence** | XAUUSD **15m** | Feb 2 – Jul 28 2026 | **521** | 44.15% | **1.093** | +15.25% | 11.90% | best on record; in-sample only, confounded |
| 14 | 07-28 | Multi-Voice + level-to-level exits | XAUUSD 15m | Feb 2 – Jul 28 2026 | 461 | 34.06% | **0.892** | −14.19% | 25.47% | REVERTED — see H74 |
| 15 | 07-29 | Key Levels (Spaceman Edition) v1.0 | XAUUSD 30m | Jan 2025 – Jul 2026 | 22 | 63.64% | **1.783** | +7.70% | 7.01% | **VOID** — order-rejection artifact (BUG-012) |
| 16 | — | Key Levels (Spaceman Edition) v1.1 | XAUUSD 30m | — | — | — | — | — | — | superseded by v1.2, never run |
| 17 | — | Key Levels (Spaceman Edition) v1.2 | XAUUSD 30m | — | — | — | — | — | — | superseded by the offline search |
| 18 | 07-31 | **Key Levels, optimised offline** — PMH/NYH/NYL | XAUUSD 15m | **train** 2019-12→2023-11 | 109 | 49.54% | 1.141 | +8.83% | 11.50% | in-sample, selected |
| 19 | 07-31 | **same config, OUT OF SAMPLE** | XAUUSD 15m | **test** 2023-11→2026-07 | **60** | 45.00% | **1.495** | +16.96% | 6.57% | **REJECTED — failed all 3 gates** |

## What the ledger says when you read it as one table

- **16 runs. Zero out-of-sample tests. Zero valid rows.**
- Two of the three results above PF 1.0 are already dead: #2 retracted for
  sample size, #15 void as an execution artifact. Only #13 survives, and it
  is one in-sample window with a confound (logic and timeframe both changed).
- Rows 9–12 are the plateau: four different architectures, same Jun–Jul 5m
  window, PF 0.819–0.886. Four distinct entry mechanisms converging on the
  same losing number is evidence about the **timeframe**, not the mechanisms.
- Rows 1–8 mostly lack trade counts and date ranges entirely. They cannot be
  compared to anything. Roughly half the project's recorded history is
  unusable as evidence.
- Every window ≤ 07-27 is Jun–Jul only — a ~2-month sample, because of the
  free-plan data cap. Row 13 was the first time a real sample was tested.

## Settings for the results that had them recorded

**#6 Top/Bottom, PF-analog 1.11** (recovered 2026-07-29 from the session
archive — these existed nowhere in the repo before):
```
useTestFail  = false      closePosPct = 0.2       rsiOb = 72
rsiOs        = 31         useTrendVeto = false    cooldown = 20
minReArmAtr  = 1.5
```
User confirmation, verbatim: *"oversold is 31 rest is as told"*.

**#13 Multi-Voice, PF 1.093:** `minScore = 6`, `weightHigh = true`, all 20
voters on, defaults elsewhere. Group ⑤/⑥ did not exist yet.

## Standing conclusions the table supports

1. **Trend / HTF filters have failed three times.** #12 (HTF bias MA, 0.882 →
   0.819), the ADX veto, and `useTrendVeto` on #6. Three strikes.
2. **A suspiciously low trade count is an execution symptom.** #15 looked
   like a 1.783 edge and was rejected orders. #7 looked like a strategy
   failure and was also plumbing.
3. **The plateau is the finding.** Rows 9–12 say XAUUSD 5m does not support
   these mechanisms after costs. Kronos was acquired to test that directly
   and is still blocked on HuggingFace being firewalled.

---

## Overfitting audit — 2026-07-29

Ran the Deflated Sharpe Ratio (Bailey & Lopez de Prado; implementation ported
from stefan-jansen/machine-learning-for-trading) over the ledger itself.
Reproduce with `python3 -m backtest.audit_ledger`.

Per-trade Sharpe reconstructed from (PF, WR, n) for every row that recorded
all three. **The reconstruction assumes uniform win and loss sizes, which
makes it optimistic — these are upper bounds, not measurements.**

| Row | n | PF | SR/trade |
|---|---|---|---|
| #6 Top/Bottom run 4 | 112 | 1.110 | +0.0492 |
| #9 OMNIBUS four-model | 298 | 0.843 | −0.0850 |
| #10 Key-to-Key | 245 | 0.886 | −0.0547 |
| #11 Trendline × Key Levels | 382 | 0.882 | −0.0623 |
| **#13 Multi-Voice** | **521** | **1.093** | **+0.0439** |
| #14 MV + level-to-level | 461 | 0.892 | −0.0551 |
| #15 Key Levels v1.0 (void) | 22 | 1.783 | +0.2932 |

### The result

| trials assumed | E[max SR] from noise | adjusted SR | DSR |
|---|---|---|---|
| 7 (ledger rows only) | 0.0809 | −0.0370 | **0.20** |
| 17 (every engine built) | 0.1066 | −0.0627 | **0.08** |
| 40 (engines × parameter passes) | 0.1277 | −0.0838 | **0.03** |

*(excluding the void 22-trade row, which inflates trial variance; including
it every figure drops below 0.001. The verdict is the same either way.)*

**DSR needs to reach ~0.95 to count as evidence of skill. The best result
this repo has ever produced reaches 0.08 at a realistic trial count.**

The expected maximum Sharpe from running 17 attempts on data with no edge is
**0.107 per trade**. The Multi-Voice engine achieved **0.044**. It did not
merely fail to beat the noise threshold — it came in at less than half of it.

### What this actually settles

PF 1.093 is not a small edge that needs more tuning. Once the number of
attempts is accounted for, it is **below what pure chance would have handed
us anyway**. Every "the plateau is close to 1.0, keep pushing" reading of the
last four months was wrong, and the ledger now says so quantitatively.

**The bar to clear:** at 17 trials and n=521, a result needs SR/trade ≥ 0.179,
which at a 44% win rate is roughly **PF 1.45**. Not 1.10. Anything between
1.0 and ~1.4 on this sample size is indistinguishable from search noise and
should not be built on.

---

## Row 19 — the first out-of-sample positive, and why it was rejected (2026-07-31)

First real dataset: 157,366 bars of XAUUSD 15m, Dec 2019 – Jul 2026, split
60/40 at 2023-11-28. The optimiser selected levels PMH/NYH/NYL on the
training half and the held-out block returned **PF 1.495 on n=60, +16.96%**.

Profit factor went UP out of sample. It looked like the breakthrough.
It is not. `python3 -m backtest.stress_test` failed it on all three gates.

### Gate 1 — random null at the MATCHED sample size: FAIL

Coin-flip entries through identical filters, stops, targets, sizing and
costs, rebuilt at n≈60 (367 trials):

| pct | PF |
|---|---|
| 50th | 0.905 |
| 75th | 1.122 |
| 90th | 1.370 |
| **95th** | **1.544** |
| 99th | 2.039 |

**Our 1.495 sits at the 93.5th percentile — below the 95th.** Random entry
beats it roughly one run in fifteen.

The width is the lesson. At n=60 the noise band runs from 0.905 to 2.039.
An earlier null built from ~810-trade samples gave 0.782–1.052, and using
THAT band here would have declared 1.495 a huge win. Profit-factor error
scales with 1/sqrt(n); a null must be rebuilt at the sample size being
judged. This is now enforced in stress_test.py.

### Gate 2 — deflated Sharpe: FAIL

SR/trade +0.1802 on n=60.

| trials | E[max SR] from noise | DSR |
|---|---|---|
| 1 | 0.0000 | 0.925 |
| 100 | 0.3750 | 0.060 |
| 370 (what the search actually ran) | 0.4387 | **0.019** |

Even granting the impossible fiction that only ONE configuration was ever
tried, DSR is 0.925 — still short of 0.95. At the true trial count it is
0.019.

### Gate 3 — buy and hold: FAIL

**+100.42% versus +16.96%** on the identical window. Gold doubled. The
strategy captured a sixth of that while carrying execution risk, 60 round
trips and a live-money failure mode that buy-and-hold does not have.

### What this actually establishes

**The config is rejected.** But the more useful finding is structural: a
strategy trading 60 times in 2.67 years CANNOT be validated on this data.
The noise band at that sample size is wider than any edge we could
plausibly detect. Selectivity that produces a thin sample is not rigour —
it is untestability.

That reframes the next step. The requirement is not "a better entry
rule", it is **a strategy that trades often enough to be measurable**.
Multi-Voice produced 521 trades in six months, which over this window
would be several thousand — enough that its noise band would be narrow
enough to see through. It is the only engine that ever cleared PF 1.0 and
it has never been tested out of sample.

### Precedent

This is the first time a promising number was killed BEFORE it entered the
ledger as a win. PF 3.656 and PF 1.783 were both celebrated first and
retracted later. The three gates are now mandatory and automated.
