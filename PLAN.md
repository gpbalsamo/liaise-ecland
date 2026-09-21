# PLAN.md

Living state for work in progress. Unlike `CLAUDE.md` (narrative log of what was
tried and found, append-only), this file tracks the *current* plan and its
status, and gets edited/reordered as work completes — so a new session can
pick up mid-task without re-deriving where things stand. When a plan finishes
or is abandoned, fold a one-line summary into `CLAUDE.md` and delete its
section here.

## Active: CaMa-Flood resolution comparison (glb_15min vs glb_06min vs glb_03min, naturalised control)

Started 2026-09-16 evening, superseding the reservoir work below for tonight
(explicit user instruction: "leave aside the investigations of the problem
identified with LDAMYBY-true" — that section is paused, not abandoned, see
below). Goal: run the same 37-year (1988-2024) naturalised (no dams,
`namelist/input_cmf`, `LDAMOUT=.FALSE.`) ecLand-CaMa-Flood coupled control at
three CaMa-Flood resolutions and compare discharge skill against the real
GRDC/CAMELS-Spain gauges, to see whether/how routing resolution changes skill
— and, as a side benefit, whether it changes anything about the dam-module
numerical-stability problem being set aside tonight (raised by the user as a
reason finer resolution might be worth trying regardless).

**Weights**: rederived from scratch (glb_06min: 179x118 grid, 8573 active
cells; glb_03min: 358x234, 34137 cells — both match the counts already
validated and documented earlier in CLAUDE.md exactly). Found and fixed two
real bugs in `derive_cmf_weights.sh`/`build_global_cmf_fixdir.sh` along the
way (`[[ -f pattern* ]]` never glob-expanding, so the cython_ext .so
relocation silently never worked; `FIXDIR` not resolved to absolute before
`cd`-ing into `WORKDIR`) — both committed. Also needed `module load nco`
(missing from the plain `sbatch --wrap` environment) and had to run the two
resolutions' cython builds sequentially, not in parallel, since they share
the same `osm_pyutils/` build directory and race if run concurrently.
**Committed the validated regional weights to Git LFS** — `cama_flood/data_06min/`
and `cama_flood/data_03min/` (same 6-file set as `cama_flood/data/` for
glb_15min: `inpmat.nc`, `rivpar.nc`, `rivclim.nc`, `mpireg.nc`, `bifprm.txt`,
`diminfo.txt`) — per the user's own suggestion, so this doesn't need
re-deriving from scratch again.

**Runs launched** (both naturalised, `LDAMOUT=.FALSE.`, same pinned binary
and `namelist/input_cmf1way` as the validated glb_15min control, 1988 cold
start, 37 years restart-chained — only `CMF_NAMELIST`/`CMF_STATIC_DIR` differ
from the glb_15min run, and both write to their own `RUN_ROOT`, **not**
touching `/perm/pad/liaise_cmf_1988_2024` which stays the glb_15min
reference):
- glb_06min: job `37776649`, `RUN_ROOT=/perm/pad/liaise_cmf_1988_2024_06min`,
  `--time=08:00:00` (budget: ~7min/year x 37 ~= 4.3h, per the single-year
  timing already validated for this resolution).
- glb_03min: job `37776709`, `RUN_ROOT=/perm/pad/liaise_cmf_1988_2024_03min`,
  `--time=20:00:00` (budget: ~25min/year x 37 ~= 15.7h, same basis).

**Status 2026-09-17**: glb_06min **finished** (37/37 years, 4h17m). glb_03min
was found running effectively single-threaded — `--export=ALL` had propagated
an `OMP_NUM_THREADS=1` from the submitting shell, which the run script's own
`${OMP_NUM_THREADS:-4}` default cannot override (that only applies when the
variable is *unset*). Killed and resumed from year 2001 with the new
`START_YEAR`/`INITIAL_RESTART` support and `OMP_NUM_THREADS=4` forced
explicitly (job `37911517`); CPU went from ~95% (1 core) to ~197% (~2 cores of
the 4 allocated — the remainder is the model's own ~50% parallel efficiency,
an Amdahl ceiling, not a job-request problem).

**Measured cost per simulated month** (all single-threaded, so comparable):
15 arcmin 0.24 min/month (1,405 cells, 1h46m for 37 yr) · 6 arcmin 0.58
min/month (8,573 cells, 4h17m) · 3 arcmin 3.00 min/month (34,137 cells,
~22h). Note 15→6 costs only 2.4x for 6.1x more cells (sub-linear — the land
half is fixed cost), but 6→3 costs 5.2x for 4x more cells (super-linear —
finer spacing also shortens the CFL-stable timestep).

**Result, 15 vs 6 arcmin** (`cama_flood/skill_benchmark_resolution.py`, both
scored fresh over 1988–2020, 53 gauges, 1389 station-years each, identical
(station, year) key sets, no row reuse): **6 arcmin is better**. Median over
station-years excluding regulated CASPE — KGE 0.120 vs 0.005, NSE −0.02 vs
−0.19, r 0.545 vs 0.498, PBIAS −39.4% vs −45.0%. 6 arcmin wins 56% of
station-years and 32/52 gauges; by per-gauge median KGE, 31/51 gauges are
positive at 6 arcmin vs 25/51 at 15 arcmin. Largest gains are at small
catchments the 0.25° network over-allocates (SIGÜES +1.06, BINIES +0.75,
JILOCA +0.73). Both still under-predict volume everywhere. Gauge-to-cell
mapping uses the station archive's own per-resolution allocations
(`Cama15/6/3lon/lat`), validated by the 15 arcmin case reproducing the
observation file's stored `cama15_iy/ix` exactly for all 53 stations.

**Two gauges flagged and excluded from headline medians** (still drawn, with a
visible warning): `RIO GUADALOPE, CASPE` (regulated, near-zero baseflow breaks
variance-based scores) and `TUDELA` — a genuine allocation error in the
upstream station archive, which puts a 2,534 km² tributary gauge on a ~25,000
km² Ebro main-stem cell, so the model simulates a different river (obs ~19
vs sim ~141 m³/s, PBIAS ≈ +610% at *both* resolutions).

**Dashboards deployed** with clickable experiment + metric selectors (KGE,
NSE, Correlation, PBIAS, Bias), per-gauge side-by-side comparison, a Δ column
and multi-line sparklines: `sites.ecmwf.int/pad/liaise/gauges/` (15 vs 6
arcmin, 3 arcmin shown as pending) and `…/chains/` (Fortran vs eclandpy→GPU
chain, rebuilt on the same generator). Adding 3 arcmin needs only one more
`--experiment` flag once its run and scoring finish.

**COMPLETE 2026-09-17 — 3 arcmin scored, dashboard rebuilt with all three.**

glb_03min: job `37911517`, `COMPLETED 0:0`, 10h08m, 37/37 years. Scored over the
identical 1389 station-year key set as the other two (1342 after excluding
regulated CASPE and mis-allocated TUDELA):

| metric | 15 arcmin | 6 arcmin | 3 arcmin |
|---|---|---|---|
| median KGE | 0.012 | 0.124 | **0.132** |
| median NSE | -0.183 | -0.007 | -0.004 |
| median r | 0.492 | **0.541** | 0.539 |
| median PBIAS | -46.1% | **-40.2%** | -40.7% |
| gauges with positive median KGE | 25/51 | 31/51 | **33/51** |

Head-to-head on station-years won: 6 beats 15 in **57%**, 3 beats 15 in **57%**,
but 3 beats 6 in only **52%** — a coin flip.

**Conclusion: 6 arcmin is the sweet spot; 3 arcmin is not worth its cost here.**
Nearly all the skill gain is in the 15->6 step (KGE +0.112); 6->3 adds +0.008 and
actually *loses* slightly on r and PBIAS, while costing 5.2x more compute
(3.00 vs 0.58 min per simulated month; 10h08m vs 4h27m wall-clock for 37 years).
Biggest per-gauge gains are at small catchments the 0.25deg network
over-allocates — SIGÜES +1.14 KGE, JILOCA +0.96, BINIES +0.94, SANGÜESA +0.75 —
and these are essentially captured by 6 arcmin already. A few gauges get worse
with refinement (ASPURZ -0.34, VERO -0.20, ESTELLA -0.18).

This matches the Q100 finding above independently: 6 arcmin captures most of the
allocation benefit (41/44 dams sited vs 43/43 at 3 arcmin) and all of the
skill benefit. Dashboard with all three experiments deployed to
`sites.ecmwf.int/pad/liaise/gauges/`.

## Q100 across all three routing resolutions — DONE 2026-09-17

All three 37-year naturalised runs are complete (glb_03min finished 2026-09-17,
job `37911517`, `COMPLETED 0:0`, 10h08m, 37/37 years), so Q100 was computed at
each with the fixed area-aware allocation (`estimate_dam_q100.py`, see
`docs/cama_flood_reservoir_methodology.md`).

**The thing that changes with resolution is dam ALLOCATION, not Q100.**

| resolution | dams | within 20% of `area_alloc` | median alloc error | dams per cell |
|---|---|---|---|---|
| glb_15min | 45 | 19 | 41.5% | 45 dams / 35 cells |
| glb_06min | 44 | 41 | 1.4% | 44 / 44 |
| glb_03min | 43 | 43 | **0.7%** | 43 / 43 |

Restricting to the **19 dams well-allocated (<20% error) at all three
resolutions** — which isolates "routing resolution changed the extremes" from
"allocation finally became possible" — Q100 is **essentially
resolution-invariant**:

```
Q100(3 arcmin) / Q100(15 arcmin):  median 0.99x   mean 1.01x   range 0.32-2.11x
                                   higher at finer resolution: 8/19 dams
```

**15 of the 19 sit within +/-10% of 1.0** (Yesa 1895 -> 1888, Mediano 1065 ->
1041, Rialb 1719 -> 1748, Barasona 690 -> 686, Calanda 1124 -> 1114, Flix
5582 -> 5664). Four move materially:

| dam | uparea | Q100 15min | Q100 3min | ratio |
|---|---|---|---|---|
| Santolea | 1229 km2 | 600 | 194 | **0.32x** |
| LaPena | 1558 km2 | 1451 | 881 | **0.61x** |
| Caspe2 | 3669 km2 | 646 | 1364 | **2.11x** |
| Mequinenza | 57214 km2 | 2530 | 3012 | 1.19x |

Their upstream areas barely change between grids, so this is not a siting
artifact — it is genuinely different routed extremes at those cells. **Tested
and rejected**: the obvious "small catchments are more resolution-sensitive"
explanation does not hold — median |log ratio| is 4% for dams above 2000 km2
and 3% below, Spearman(uparea, |log ratio|) = -0.05, and the four movers span
1229 to 57214 km2. They are idiosyncratic cells, not a size class.

Worth carrying into the dam work: **LaPena's 15 arcmin Q100 is inflated 1.6x**
versus 3 arcmin, and LaPena was one of the four dams the overshoot screen
flagged as Flix-like (that screen used 15 arcmin Qf = 0.3*Q100). Some of that
flagging may itself be a coarse-resolution artifact — another reason to move
the reservoir work to 6 arcmin.

**Interpretation**: at a cell whose catchment the grid already resolves, the
100-year flood is set by the upstream water balance, not by how finely the
channel is routed — consistent with the mass-conservation argument already
established in `CLAUDE.md` for channel width (means are protected; here the
extremes largely are too, once siting is correct). The scientific value of
6/3 arcmin for the reservoir work is therefore that **most of these reservoirs
become siteable at all** (19/45 -> 43/43), not that the flood statistics shift.

Practical consequence: the dam pipeline should move to **glb_06min or finer**,
where every dam also gets its own cell so `build_dam_param_csv.py`'s
co-location dedup stops discarding six reservoirs. Q100 tables:
`/perm/pad/liaise_discharge_compare/ebro_dam_q100_{15min,06min,03min}.csv`.

## Where GloFAS is (2026-09-20) -- so nobody searches $PERM for it again

There is **no GloFAS discharge file under `/perm/pad`**. What exists:
- `/perm/pad/flood_cases/grib_15arcmin/Globe_river_flood_YYYYMM.grb` (1980-01 ..
  2025-12, 64 GB): `class=rd, expver=iyp3, stream=oper, type=fc`, 6-hourly
  `avg_dis` (235270) and `avg_fldffr` (235275) on the global 0.25 deg grid --
  the **IFS-coupled CaMa-Flood** reanalysis-forced experiment, not GloFAS.
  Usable as a third CaMa-Flood chain (IFS forcing, 15 arcmin, 1988-2024).
- `/perm/pad/glofas/`: CaMa-Flood parameter/analysis products for 2016-2022
  (`ana_cmf_*`, `camaflood_dis*.grib`, `CMF_2018*.zarr`), not LISFLOOD output.
- `/perm/pad/GloFAS-bench`, `/perm/pad/benchmark_cmf_gp4hydro_vs_glofas_*`,
  `ifs-riverbench/Workflow/dashboard_data/glofas_v4`: *scored* CaMa-vs-GloFAS
  products for 2018-2022 (KGE maps, station metrics), not discharge.
- **GloFAS v5.0 / LISFLOOD daily discharge itself is in MARS**:
  `class=gf, stream=rfsd, type=sfo, forcing=ecmf-era5, param=235270, step=24`
  (per `ifs-riverbench/Workflow/benchmark_cmf_vs_glofas5.py`). The Ebro box
  1988-2024 at 0.05 deg is ~13.5k daily fields, ~1 GB: retrieve with `mars`,
  not the CDS.

## Three-way on identical days, 2018-2022: GloFAS v4 vs naturalised vs dammed ecLand-CaMa (2026-09-21)

Same 27 Ebro stations, same 1826 days and observation values as the section
below, with the dam run (job 39102478, default parameters) added
(`/perm/pad/liaise_discharge_compare/glofas_v4_vs_nat_vs_dam_2018_2022.json`).
"Regulated" here = station cell downstream of a `data_dam_06min` reservoir on
the 6 arcmin network (21 of 27).

| median KGE | GloFAS v4 | ecLand-CaMa naturalised | ecLand-CaMa + dams (defaults) |
|---|---|---|---|
| all 27 | 0.214 | 0.071 | 0.096 |
| regulated 21 | **0.450** | 0.105 | 0.123 |
| natural 6 | -1.96 | -0.185 | -0.185 (identical, as it must be) |
| median PBIAS, regulated | +12 % | -25 % | -28 % |

Head-to-head at the 21 regulated stations: dams beat naturalised at 11/21,
GloFAS beats the dam run at 14/21. The dam module helps where a reservoir
smooths a flashy tributary -- Segre at Seros -0.50 -> +0.29, Martin at Hijar
-0.79 -> +0.10, Cinca at Fraga 0.11 -> 0.27, Gallego 0.21 -> 0.39 -- and
hurts where the constant-`Qn` rule holds water on the main stem and the
Aragon-Arga axis -- Tortosa 0.64 -> 0.39, Asco 0.57 -> 0.37, Castejon 0.43
-> 0.31, Zaragoza 0.45 -> 0.34, Irati 0.36 -> 0.18. GloFAS v4 (calibrated
LISFLOOD with reservoirs) reaches 0.63-0.76 at Castejon/Mendavia/Zaragoza/
Gallego/Logrono: that is the size of the calibration prize at exactly the
gauges the dam module currently degrades. Where GloFAS is bad it is bad by
volume (Jalon +387 %/+144 %, Arba en Ejea +707 %, Alhama +411 %) and both
ecLand-CaMa runs beat it there.

## GloFAS yardstick, first cut: GloFAS v4 vs ecLand-CaMa naturalised, 2018-2022 (2026-09-20)

`ifs-riverbench/Workflow/dashboard_data/glofas_v4/20180101_20221231_15arcmin/`
holds, per riverbench station, the **daily GloFAS v4 discharge and the
matched observations** for 2018-2022 (station JSONs), so a same-days
comparison needs no retrieval. Extracted the 43 Iberian stations to
`/perm/pad/liaise_discharge_compare/glofas_v4_ebro_stations_2018_2022.json`;
27 of them sit on our 6 arcmin Ebro network with a matching drainage area.
Scored our naturalised 6 arcmin run on exactly the same days and observation
values (`glofas_v4_vs_ecland_cama_nat_2018_2022.json`):

| 27 Ebro stations, 1826 days | GloFAS v4 (LISFLOOD, calibrated, reservoirs) | ecLand-CaMa 6 arcmin, naturalised, uncalibrated |
|---|---|---|
| median KGE | **0.214** | 0.071 |
| better on KGE | 15/27 | 12/27 |
| median PBIAS | +13.0 % | -28.5 % |

The pattern is the interesting part: GloFAS wins the regulated Ebro
main-stem and the big tributaries (Castejon 0.76 vs 0.43, Mendavia 0.74 vs
0.15, Zaragoza 0.63 vs 0.45, Gallego 0.75 vs 0.21, Cinca-Fraga 0.45 vs 0.11),
i.e. where reservoirs and calibration matter; our run wins at Tortosa/Asco
(0.64/0.57 vs 0.50/0.53, PBIAS 0 vs +30 %) and at the semi-arid tributaries
where GloFAS over-predicts grossly (Jalon +387 %/+144 %, Arba en Ejea
+707 %, Alhama +411 %, Jiloca +176 %) while we under-predict moderately.
So the dam module's job is precisely the gap at Castejon/Mendavia/Zaragoza/
Fraga. When job 39102478 reaches 2018-2022, rerun the same script with the
dam run to get the three-way table on identical days.

GloFAS v5 (ERA5-forced) for the full 1988-2024: the riverbench benchmark
script documents it as MARS `class=gf, stream=rfsd, type=sfo, model=lisflood,
configuration=v5.0, forcing=ecmf-era5, timespan=24h, expver=1, step=24`, but
`mars list`/`retrieve` for 1988/2000/2018 under those keys returned nothing
tonight -- confirm the keys (database/expver) with the script's author before
scheduling the ~1 GB Ebro-box retrieval.

## Dam experiments, all resolutions (status 2026-09-21)

Same pipeline at every resolution: corrected 1-based siting, guard binary
`run/bin_damfix`, `namelist/input_cmf_dam`, `dam_param.csv` from the
resolution's own `ebro_dam_q100_<res>.csv` (default parameters), 1988 cold
start, 37 years restart-chained.

| resolution | dams sited | statics | run root | job | status |
|---|---|---|---|---|---|
| 15 arcmin | 35 (dedup drops 10) | `cama_flood/data_dam_15min_fixed` | `/perm/pad/liaise_cmf_1988_2024_dam_15min` | 39210410 | running (~2 h) |
| 6 arcmin | 44 | `cama_flood/data_dam_06min` | `/perm/pad/liaise_cmf_1988_2024_dam_06min` | 39102478 | **done**, scored (sections below) |
| 3 arcmin | 43 | `cama_flood/data_dam_03min` | `/perm/pad/liaise_cmf_1988_2024_dam_03min` | 39210409 | running (~12 h; naturalised took 10 h 08) |

The six one-year 15 arcmin roots `/perm/pad/liaise_cmf_1988_2024_dam{,_livnorm,
_nolapena,_test_noflix_noybY,_test_noybY,_06min_crashed_unpatched}` are the
pre-fix, mis-sited crash diagnostics -- superseded, keep or delete at will.

## Dams vs naturalised over the full gauged record, 1988-2014 at 6 arcmin (2026-09-21)

Definitive version of the interim table below (same code path, dam run job
39102478 through 2014 vs the naturalised 6 arcmin control, identical 1104
(station, year) keys, 53 gauges, 19 with a `data_dam_06min` reservoir
upstream; CASPE and TUDELA excluded as usual).
`/perm/pad/liaise_discharge_compare/skill_06min_{dam,nat}_1988_2014.json`,
summary `dam_vs_nat_06min_1988_2014_summary.json`.

| | n | dam beats natural (KGE) | median KGE nat -> dam | median r | median PBIAS nat -> dam |
|---|---|---|---|---|---|
| all | 1066 | 23 % | 0.120 -> 0.101 | 0.528 -> 0.532 | -40.6 -> -41.4 % |
| regulated | 338 | 25 % | 0.244 -> 0.208 | 0.643 -> 0.639 | -34.1 -> -38.5 % |
| natural | 728 | 22 % | 0.027 -> 0.027 | unchanged | unchanged |

**With default, uncalibrated parameters the reservoir module makes discharge
skill slightly worse, not better**: -0.04 KGE and -4 PBIAS points at the
regulated gauges, zero effect elsewhere (the module is correctly local).
Timing is untouched (r unchanged); the loss is volume and variability -- the
constant-`Qn` rule holds water back at the wrong times. One gauge improves
a lot: **Cinca at Fraga 0.04 -> 0.26** (Mediano/ElGrado/Barasona irrigation
set, 1053 hm3; release smoothing helps there). Everything on the Aragon-Arga
axis loses (Castejon 0.54 -> 0.40, Estella 0.32 -> 0.17, Huarte 0.14 -> -0.14
with PBIAS -51 -> -73 %), as do the Ebro main stem (Gelsa 0.54 -> 0.44) and
the Ega (Arquijas 0.48 -> 0.35). Yesa is the one reservoir whose own gauge
gets better (0.52 -> 0.57, PBIAS 17 -> 13 %).

Reading for the calibration work (feasibility study section 4): the defaults
(`Qn` = naturalised mean, `Qf` = 0.3 Q100, flood volume 37 %, no GRSAD
normal volume) are not a usable prior for Ebro irrigation/hydropower
reservoirs -- a seasonal `Qn` (or the GRSAD-derived normal volume) is the
first thing to fit, and the Aragon-Arga gauges plus Fraga/Castejon/Gelsa are
the objective. The GloFAS v4 comparison (next section) shows what a
calibrated model with reservoirs achieves at exactly these gauges.

## Interim: dams vs naturalised, first 8 years at 6 arcmin (2026-09-20, job 39102478 still running)

Scored with `skill_benchmark_resolution.py --resolution 06min` on the identical
228 (station, year) keys, 1988-1995, 45 gauges, dam run vs the naturalised
6 arcmin control (`/perm/pad/liaise_discharge_compare/skill_06min_{dam,nat}_partial.json`).
Gauges split by whether a GRanD dam of `data_dam_06min` lies upstream on the
6 arcmin network (traced via nextx/nexty): 14 regulated gauges, 31 natural.

| | n | dam beats natural (KGE) | median KGE nat -> dam | median PBIAS nat -> dam |
|---|---|---|---|---|
| all | 228 | 68/228 | 0.060 -> 0.050 | -40.1 -> -41.2 % |
| regulated | 71 | 27/71 | 0.126 -> 0.107 | -31.5 -> -37.7 % |
| natural | 157 | 41/157 | 0.027 -> 0.027 | unchanged (sanity check: the module leaves undammed reaches alone) |

Reading: with **default, uncalibrated** parameters (Qn = naturalised mean, Qf =
0.3*Q100, FldVol = 37 % of capacity, no GRSAD normal volume) the reservoir
module is roughly skill-neutral in aggregate and slightly negative on volume
(it holds water back that the naturalised run passed through, deepening the
under-prediction that both runs already have). Two large effects go opposite
ways: Cinca at Fraga, below the Mediano/ElGrado/Barasona irrigation set,
improves from KGE -1.63 to +0.26 (timing of the regulated releases), whereas
Castejon/Estella/Andosilla/Huarte on the Aragon-Arga system lose 0.1-0.3 KGE
and 4-14 points of PBIAS -- Yesa/Itoiz/Eugui storing too much with the
constant-Qn rule. That is the calibration target the feasibility study set out
(seasonal Qn, GRSAD normal volume); it is now measurable. Caspe (regulated,
near-zero baseflow) remains metric-hostile (-26.9 -> -2.9). Re-score on the
full 1988-2014 record when the job finishes; these 8 wet-decade years are not
the final word.

## Paused tonight, not abandoned: Reservoir operation on the Ebro (CaMa-Flood v4.20 dam module)

Full feasibility writeup: [Ebro Reservoir Operation](https://claude.ai/artifact/V5ZZxE3K4jFS6tsds5JiP3)
(artifact, 2026-09-16) — read it before touching this section, this is just
the status tracker for its 6-step activation pipeline (§3) plus calibration
(§4).

**Reservoirs**: 45 GRanD dams drain to the Ebro inside our 73×49 domain,
7.77 km³ total capacity (confirmed 2026-09-16 by filtering
`/perm/pad/cmf_v420_pkg_20240430/map/data/GRanD_allocated.csv`'s
`lat_alloc`/`lon_alloc` — already snapped to the global glb_15min grid, no
need to recompile/rerun `allocate_dam.F90` — by nearest-cell match against
our own `cama_flood/data/ncdata.nc` `basin` field, basin id 4). Matches the
artifact's figure exactly. Biggest: Mequinenza (1534 MCM, Ebro mainstem,
ix=39/iy=30), Canelles (688 MCM, Noguera Ribagorzana), Itoiz (586 MCM,
Irati). Allocation + Q100 now produced by `cama_flood/estimate_dam_q100.py`
(committed); full per-dam table at
`/perm/pad/liaise_discharge_compare/ebro_dam_q100.csv` (not committed —
regenerate from the script, same convention as the other discharge-compare
outputs).

### Step status (§3 of the artifact)

| # | Step | Status | Note |
|---|---|---|---|
| 1 | Naturalised routing of the control run | **done, full 37 years, AND on a just-fixed restart chain** | Fortran `LECMF1WAY` coupled run (job 37620761) *was* run for all 37 years, but that run — like every multi-year run made with `run/run_liaise_ecland.{sh,slurm}` before 2026-09-16 — turns out to have **silently cold-started the LAND state every 1 January** (soil moisture/snow reset to `soilinit`, not actually carried over; only CaMa-Flood's own river restart was ever chained). Root cause: the driver only reads a restart when `NSTART /= 0`, and this script always sets `NSTART=0`, so the staged `restart_in.nc` was silently ignored. Found and fixed 2026-09-16 (see CLAUDE.md, "The annual restart chain never carried the land state"); the old run is now `/perm/pad/liaise_cmf_1988_2024_NOCHAIN_invalid` and explicitly marked superseded. **The run this Q100 estimate actually used, job `37653123` (submitted 16:15, i.e. after the 16:05 fix), is the corrected, restart-chain-verified rerun** — confirmed by file mtimes before trusting this. Effect size was not small: fixing the chain lowers Jan–Mar discharge by 1.5–4x and annual means by 15–45% versus the old cold-start run, and *raises* peak flows (proper antecedent-moisture memory lets wet spells compound) — so the Q100 numbers below benefit from the fix, not just the full 37-year sample length. `/perm` cleanup separately meant only 22 of these 37 years were on disk mid-session; both a re-run and the restart fix landed the same day, in the right order — worth re-stating since it would have been easy to conflate "more years appeared" with "nothing else changed." The complete 37-year eclandpy→CaMa-Flood-GPU series also exists (`eclandpy_bridge/cmfgpu_out_gpu_repro/`) but carries the documented −21% runoff bias AND predates this land-restart fix (eclandpy has its own separate state handling, not affected by this specific bug, but not re-verified against it either) — kept only as the cross-check series (§1 table), not the final parameter source.|
| 2 | Allocate the dams on the map | **done** | `cama_flood/estimate_dam_q100.py`'s `load_dams()`: 45 dams matched by nearest-cell lookup against `ncdata.nc`'s `basin` field (see above), no Fortran allocator run needed since `GRanD_allocated.csv` ships pre-allocated. 39 unique grid cells (some dams share a 0.25° cell, e.g. Canelles/SantaAna, Talarn/Terradets — expected at this resolution, both get the same naturalised Q100 from their shared cell). |
| 3 | Estimate parameters (p01 mean/max, p02 Gumbel Q100, p03 volume, p04 merge) | **done, first pass (37%-fallback volume)** | `cama_flood/estimate_dam_q100.py` re-run 2026-09-16 once all 37 years landed (superseding the earlier 22-year interim pass — Q100 moved <7% at every dam between the two, e.g. Mequinenza 5713→5703, Itoiz 630→673). Gumbel-via-L-moments checked line-for-line against `p02_get_100yrDischarge.py`. **Key finding stands**: annual-mean discharge agrees closely between the Fortran and GPU/eclandpy naturalised series at every dam despite the documented −21% runoff bias, but Q100 doesn't — Fortran runs ~1.5–1.8× the GPU estimate everywhere (mean flow is protected by mass conservation, extremes aren't). `cama_flood/build_dam_param_csv.py` then reimplements `p04_complete_damcsv.py`'s exact merge rules (Qf=0.3·Q100 with the <Qn bump rule; FldVol=37%·capacity since GRSAD is still blocked; **one dam per grid cell, keep the largest by capacity** — 6 smaller co-located dams dropped: SantaAna, Urrunaga, Terradets, GonzalezLacasa, Laparan, SanLorenzoMongay) into a runtime-ready `dam_param.csv`, 39 dams, exact 13-column `LDAMYBY=.TRUE.` format `cmf_ctrl_damout_mod.F90` reads. Saved at `/perm/pad/liaise_discharge_compare/dam_param.csv` and staged for a run at `cama_flood/data_dam_firstpass/dam_param.csv` (gitignored — first-pass, not GRSAD-calibrated, deliberately kept out of the validated `cama_flood/data/`). |
| 4 | Wire `&NDAMOUT` into the CaMa namelist | **done** | New `namelist/input_cmf_dam` (copy of `input_cmf` with `LDAMOUT=.TRUE.`, `CVARSOUT` +`daminf,damsto`, and the `&NDAMOUT` block from the artifact's §3.4) — kept as a separate file rather than editing `input_cmf` in place, so the naturalised baseline used everywhere else in this project is untouched. `run/run_liaise_ecland.{sh,slurm}`'s `CMF_STATIC_FILES` array gained a `${CMF_STATIC_FILES_EXTRA:-}` extension point (empty by default, zero behaviour change for existing runs) so `dam_param.csv` can be staged without hardcoding it into every run. |
| 5 | First dammed run, 1988–2024 | **unblocked 2026-09-20: guard + corrected 1-based DamIX/DamIY; DONE 2026-09-21: 37-yr 6 arcmin dam run complete (job 39102478); scored vs naturalised and vs GloFAS v4 -- defaults degrade regulated-gauge skill, calibration is next (see CLAUDE.md, "First complete 37-year reservoir run")** | Root cause and fix in CLAUDE.md, "Dam crash fixed"; binary `run/bin_damfix`, source branch `damout-negative-storage-guard` in `ecland-damfix`. | See "Step 5 attempt" below — three submissions, two were this session's own mistakes (wrong `sbatch` invocation, then a missing env var), the third hit a genuine CaMa-Flood dam-module interaction and crashed with SIGFPE ~140 days into 1988. |
| 6 | Score against regulated/natural gauge split | **done 2026-09-21** | Sections above: 1988-2014 dam vs naturalised (19 regulated / 34 natural gauges) and the 2018-2022 three-way with GloFAS v4. |

### Step 5 attempt, 2026-09-16: submission mistakes, then a real crash

**Submission mistakes (own errors, logged so they aren't repeated)**:
1. First attempt used shell-prefixed env vars (`RUN_ROOT=... sbatch run_liaise_ecland.slurm`) — **this cluster's `sbatch` does not propagate ad-hoc shell env vars this way**; the README already documented the right form (`sbatch --export=ALL,VAR=val,... script`) and this should have been checked first. The job silently ran with every default — plain `namelist/input` (no coupling at all), writing into the default `run/output/`/`run/restart/` (not a scratch path) — and "succeeded" in ~1h55m, overwriting all 37 years of the plain CY50R1 control run's restart chain. Not catastrophic (that control run was already invalidated by the land-restart-chain bug above and needed rerunning anyway) but unintentional and unverified — **the control-run diagnostics documented elsewhere in CLAUDE.md are now stale against what's actually on disk in `run/output/`; re-verify before citing them.**
2. Second attempt fixed the `--export=ALL,...` syntax but dropped `CMF_STATIC_FILES_EXTRA=dam_param.csv` from the list — failed in 12 seconds with a clear `forrtl: file not found ... dam_param.csv`, negligible cost.

**The real finding, third attempt**: with both of the above fixed, the run got into 1988 and crashed after ~140 simulated days (2026-09-16, job 37742075) with `forrtl: error (75): floating point exception` inside `cmf_ctrl_damout_mod_mp_cmf_damout_calc_`, specifically `(DamVol/ConVol)**0.5` (line 384) going through a negative base. Diagnosed exactly via `damtxt-1988.txt` (`LDAMTXT=.TRUE.` paid off): 4 grid cells had gone storage-negative by day 141 (19880520) — **all 4 belong to dams with a construction year after 1988** (Itoiz/2003, Rialb/1999, SanSalvador/2013, Pajares/1994, i.e. `DamStat<=0` this year).

Checked the source directly rather than guessing: `CMF_DAMOUT_CALC` does correctly `CYCLE` past `DamStat<=0` dams — the reservoir release rule genuinely never runs for them, so this is **not** a Qf/Qn calibration problem on these 4. But `CMF_DAMOUT_INIT` marks `I1DAM(ISEQ)=1` and `I2MASK(ISEQ,1)=2` (excluded from the adaptive timestep) **unconditionally for every allocated dam cell**, and the `LPTHOUT` bifurcation-stop loop also checks `I1DAM(...)>0` unconditionally — both regardless of `DamStat`/`LDAMYBY`. So a not-yet-built dam cell still loses its adaptive substep and its bifurcation path the moment it's *allocated*, years before its release rule activates. **Correction (2026-09-17)**: the bifurcation half of this IS documented — the v4.20 reservoir manual states `CMF_DAMOUT_INIT` deliberately deactivates bifurcation around reservoir cells "to avoid instability and un-expected water leakage from reservoir" (see `docs/cama_flood_reservoir_methodology.md`); it is intentional, not an oversight. The adaptive-timestep exclusion remains undocumented. The interaction: at these 4 specific cells, removing those stabilising mechanisms was enough to blow up plain river-routing mass balance, independent of any parameter choice in `dam_param.csv`.

**Diagnostic run, `LDAMYBY=.FALSE.` (all 39 dams active from 1988), 2026-09-16, job 37751981**: does **not** cleanly confirm the not-yet-built-cell hypothesis above. It crashed with the identical SIGFPE signature, on the **exact same date, 19880520**, after the identical 564 written `damtxt-1988.txt` records — but this time **no dam ever went storage-negative** (checked every record, not just the last one). Two things follow: (1) the coincidence of both runs dying on the same calendar date points to a specific forcing event around 1988-05-20 as the trigger, not specifically the `LDAMYBY`/inactive-cell mechanism — that mechanism may still be a real, separate issue (the confluence-proximity finding below stands on its own), but this test doesn't isolate it as *the* cause of either crash; (2) a different, more concrete culprit surfaced instead — see below. `namelist/input_cmf_dam_test_ldambyfalse` is a throwaway diagnostic namelist, kept for the record but not part of the real pipeline.

**Root cause, now confirmed and quantified — Flix specifically, uniquely among all 39 dams**:

Checked `CALC_ADPSTP` (`cmf_ctrl_physics_mod.F90`, the exact CFL-based adaptive-timestep calculation, in the same call stack as the crash): it explicitly excludes any cell with `I2MASK>0` — i.e. every allocated dam/dam-upstream cell — from the `DT_MIN` computation that sets the model's global adaptive timestep. So the timestep used everywhere, including at dam cells, is chosen ignoring how fast a dam cell's *own* storage is actually changing.

Computed `AdjVol`/`EmeVol`/`Qa` from `CMF_DAMOUT_INIT`'s own formulas (`EmeVol=ConVol+0.95*FldVol`, `AdjVol=ConVol+0.1*FldVol`, `Qa=(Qn+Qf)/2`) for all 39 dams and compared each one's storage-response band width against how much volume moves through it in a single hourly coupling step (`IFRQ_INP=1h`) at its own flood discharge `Qf`. **Flix is the only dam that fails this check, and by a wide margin**: its case-2 band (`AdjVol-ConVol`) is 0.422 MCM, but one hour at `Qf`=1544.9 m3/s moves 5.56 MCM through it — a **13.2x overshoot in a single non-substepped hour**. The next-highest dam, Irabia, overshoots only 2.7x, and its turnover time at mean flow (121 hours) is nowhere near as fast as Flix's (7.2 hours). Caspe2 and LaLoteta — flagged earlier from the raw inflow-spike magnitude alone — do **not** actually meet this properly-normalized criterion (overshoot 0.2x and 0.9x respectively) once turnover time is accounted for; that was a false lead from not normalizing by capacity. Ribarroja (130 MCM) and Mequinenza (966 MCM), immediately upstream on the same hydropower cascade, are both comfortably fine (0.8x and 0.1x).

**In plain terms**: Flix is a genuine run-of-river afterbay (matches the artifact's own description of the cascade), but the reservoir module's storage-ratio release formulas assume seasonal-scale storage, and the model's adaptive-timestep mechanism structurally cannot see that Flix needs a much finer step than the rest of the domain — so at flood inflow, a single coupling-interval step blows straight through its entire operating range and produces a negative or otherwise invalid ratio argument feeding a fractional power (`**0.5`, `**3.0`, `**0.1`), triggering the SIGFPE. This is a real gap in the upstream CaMa-Flood reservoir module (worth reporting to Yamazaki/the ecland maintainers, independent of this project), not something fixable by better-calibrating `dam_param.csv`.

**Recommendation implemented and tested, 2026-09-16 — result: partial, not a full fix.**
`build_dam_param_csv.py` gained a proper `--exclude` flag; regenerated `dam_param.csv` without Flix (38 dams, `/perm/pad/liaise_discharge_compare/dam_param_no_flix.csv`, staged into `cama_flood/data_dam_firstpass/dam_param.csv`). Resubmitted correctly (job 37756882) — **crashed again**, same SIGFPE, same date (19880520), but this time via the *original* mechanism: Itoiz/Rialb/SanSalvador/Pajares went storage-negative again (Itoiz first, as early as 19880109). Excluding Flix only removed *its* failure mode; the not-yet-built-cell instability was independent all along and had simply been masked by Flix crashing first.

Tested the natural follow-on hypothesis — combine "exclude Flix" with `LDAMYBY=.FALSE.` (job 37757943, `namelist/input_cmf_dam_test_ldambyfalse` + no-Flix `dam_param.csv`), reasoning that active dams get their cold-start storage floored at `ConVol` (verified in `CMF_DAMOUT_INIT`) while not-yet-built dams get unguarded natural-river-storage at a cell that's also lost its adaptive timestep. **Also crashed** — same SIGFPE, same date again, this time with **zero negative-storage dams** (like the first `LDAMYBY=.FALSE.` diagnostic), so the not-yet-built mechanism was avoided as hoped, but *something else* still failed via the Flix-like non-negative-storage pathway.

**Four different configurations now, all failing at the identical calendar date, 19880520, via at least two distinct mechanisms** (negative storage at inactive cells; non-negative-storage instability in the release-rule's case-2/3/4 fractional-power terms). That consistency across configurations is itself the most important new data point: it's hard to explain by one dam's bad parameters alone, and much more consistent with **a genuinely extreme inflow event in the 1988 WFDE5 forcing landing around day ~141** that pushes several dams' inflow past their own `Qf` (itself a Q100-derived design threshold) simultaneously — i.e. the *event*, not any single dam, may be the real trigger, with different dams being the numerically weakest link depending on which are active/excluded.

### 6 arcmin with dams, 2026-09-18: the crash date MOVED for the first time

Job `38445030`, full 44-dam 6 arcmin set (no manual exclusions; Flix and LaPena
both in), parameters rebuilt from `ebro_dam_q100_06min.csv` with the corrected
allocation, `cama_flood/data_dam_06min/` statics. Result: **still crashes
(SIGFPE, status 134), but at 19880724 instead of 19880520** — 65 days further,
and the **first time in seven configurations that the date has moved at all**.

That is real evidence the allocation fix mattered: the reservoirs that were
being over-drained by an inflated `Qn` (Eugui 15 d -> 147 d to empty, Irabia
14 d -> 68 d, Ordunte dropped from the domain entirely) no longer fail early.
It is also the parameter set we want regardless — 44 dams in, 44 out, because
at 6 arcmin every reservoir has its own cell and the co-location dedup never
fires (at 15 arcmin it silently discarded six).

**But the failure mode is unchanged and now broader**: at the crash, **33 of 44
active reservoirs sit at essentially zero storage**, against 7 of 37 at
15 arcmin.

Two explanations tested and **both refuted**:

- *"Mediterranean summer dries the inflow up"* — no. At the 6 arcmin dam cells
  in 1988, Jun-Aug inflow is mostly **above** each dam's own `Qn` (ElGrado1
  1.16x, Oliana 1.28x, Flix 1.63x, SantaAna 1.73x); only **6 of 44** cells have
  summer inflow below their annual mean. Pyrenean snowmelt sustains summer flow,
  and 1988 is the wettest year in the archive.
- *"Storage is tiny relative to throughflow"* — only for a handful. Residence
  time `ConVol/Qn` is under a week for just **3 of 44** dams (Flix 7.2 h,
  SanLorenzoMongay 37.6 h, Ribarroja 5.5 d); the median is **284 days**.

**So it is still unexplained why so many reservoirs sit at zero while receiving
more than their mean flow.** The proximate crash mechanism is not in doubt (see
below), but the reason the reservoirs reach the singular point is.

**Leading remaining candidate, untested**: `Qn*(DamVol/ConVol)**0.5` has an
unbounded derivative as `DamVol -> 0`, so the release rule is infinitely stiff at
the empty end. A reservoir hovering near zero, integrated with a 1 h coupling
step at a cell deliberately excluded from `CALC_ADPSTP`, can overshoot straight
through zero. That would explain why the failure always occurs at the empty end
regardless of resolution, dam set or flow regime. Worth checking how reservoirs
are initialised at a **cold start** (as opposed to `LDAMYBY` activation, which
`LiVnorm` governs and which was already shown inert) — if they all start at or
near zero and fill slowly, they spend a long time in exactly that stiff region.

### ROOT CAUSE (proximate) IDENTIFIED 2026-09-17: unguarded `(DamVol/ConVol)**0.5` on an empty reservoir

After the LaPena test refuted the last dam-specific hypothesis (below), the
traceback plus the source settle it. `ecland`'s
`src/surf/cmflood/cmf_ctrl_damout_mod.F90`, Funato-Yamazaki branch
(`LDAMH22=.FALSE.`, ours), **case 1 "water use"**:

```fortran
IF( DamVol<=ConVol(IDAM) )THEN
  DamOutflw = Qn(IDAM) * (DamVol/ConVol(IDAM))**0.5      ! <-- no non-negativity guard
```

`DamVol` is **not clamped at zero**. For an active reservoir (`ConVol>0`) any
negative storage makes the base negative, and a negative base under `**0.5` is a
floating-point *invalid operation* — which is exactly the crash:
`__libm_pow_e7` called from `cmf_ctrl_damout_mod_mp_cmf_damout_calc_`
(backtrace, job 38017392). `0.0**0.5` is fine, so the storage must genuinely go
negative.

**Why it happens here**: by 1988-05-20 **seven active reservoirs are pinned at
zero storage** — Alloz, ElGrado1, Eugui, Irabia, LaSotonera, Ordunte, Pena, all
printing 0.0000 MCM (damtxt prints 2 d.p., so anything in +/-0.005 is invisible).
They are empty because the domain is in a **spring recession** (domain-mean
discharge falling 75.2 -> 72.3 -> 64.6 -> 59.5 m3/s across the crash window), not
in flood. Dam cells are simultaneously excluded from `CALC_ADPSTP`'s adaptive
timestep (`I2MASK>0`, documented earlier in this file), so the timestep is chosen
without regard to how fast these small reservoirs are draining, and storage
undershoots below zero.

**This explains every observation that defeated the earlier hypotheses:**

| Observation | Explained by |
|---|---|
| Crash date invariant across 6 configurations | It is not one pathological dam; ~7 reservoirs reach empty together on the recession |
| Excluding Flix didn't help; excluding LaPena didn't help | Removing one empty reservoir leaves six others in the same state |
| `LiVnorm`/`LDAMYBY` made no difference (byte-identical output) | Those govern *not-yet-built* dams; this is an *active* dam in water-use mode |
| 1988-05-20 is an ordinary day (rank 94/367) | It is a **drought** failure, not a flood failure — the opposite of what was assumed |
| Invisible in `damtxt` | 4 records/day cannot resolve an intra-timestep undershoot |
| The overshoot-vs-Qf screen failed to predict it | That screen measures *flood* band traversal; this is the empty end of the curve |

**Proposed fix (upstream, one line)**: clamp the base, e.g.
`max(DamVol,0._JPRB)/ConVol(IDAM)`, in case 1 — and check cases 2/3's `**3.0` and
`**0.1` terms for the same exposure. This is a genuine CaMa-Flood v4.20 defect,
worth reporting alongside the `allocate_dam.F90` `dd` bug in
`docs/cama_flood_reservoir_methodology.md`.

**NOT yet done**: patching `/perm/pad/ecland` is a shared-checkout change and a
rebuild there has already once corrupted a running job (see CLAUDE.md, 37-year
control run). Agree the approach before touching it.

---

### `LiVnorm=.TRUE.` tested 2026-09-17 — REFUTED, zero effect, and two other hypotheses fell with it

Job `38013448`, identical to crash #3 (no-Flix 38-dam `dam_param.csv`,
`LDAMYBY=.TRUE.`) with `LiVnorm` flipped and **nothing else** (verified by diff
before submitting). Result: **crashed at 19880520 again**, 1m13s, same SIGFPE,
and its `damtxt-1988.txt` is **byte-identical** to the `LiVnorm=.FALSE.` run's.
Not "similar" — bit for bit. The flag changed nothing.

**Why it could never have worked** (the reasoning error in the hypothesis
below): `LiVnorm` sets initial storage *at the year a reservoir is first
activated*. Every affected dam activates in 1989-2016, so in a crash occurring
in **1988** the flag is inert by construction. "Not yet built" is not the same
state as "just activated", and the hypothesis conflated them.

Two further hypotheses were refuted by the diagnostics this run enabled:

**(a) The "genuinely extreme inflow event around 1988-05-20" reading is wrong.**
Checked the naturalised control's own 1988 discharge directly: 1988-05-20 ranks
**94/367 by domain-mean and 109/367 by peak-cell discharge** — an ordinary day.
Domain mean ~72 m3/s against 136-158 m3/s on the late-January/February peak days,
which the same configuration survives without trouble. The surrounding window is
a flat recession (75.2, 72.3, 64.6, 59.5 m3/s). Whatever selects this date, it is
not flood magnitude.

**(b) The four not-yet-built dams are not the dynamic trigger.** Their storage is
**frozen** for the entire run — ItoizDam -0.26, Rialb -0.07, SanSalvador -0.01,
Pajares -0.02 MCM, constant, zero sign changes across all 564 records. Earlier
notes describing them as having "gone storage-negative by day 141" implied a
progressive drift into failure; they are in fact negative from the start and
never move. Also newly observed: these dams show `TotVol`/`NrmVol` = **-9.00**
(undef) in `damtxt` at runtime even though `dam_param.csv` carries real volumes
for them (ItoizDam: FldVol 216.82, ConVol 369.18, TotVol 586.0) — i.e. the model
deliberately marks not-yet-built reservoirs undef, as designed.

**Where that leaves it**: the failing reservoir is an **active** one, failing on
an unremarkable day, in a fractional-power term. The overshoot screen
(2026-09-17, all 45 dams, volume through in one coupling hour vs the case-2
storage band) flags exactly four dams above 1.0x — Flix, **LaPena**, Terradets,
SanLorenzoMongay — and Flix is excluded from this dam set. **LaPena was the
strongest remaining candidate** — tested as job `38017392` (37 dams, LaPena the
only changed row, verified by diff) and **refuted**: same crash, same
19880520, same 566 damtxt records. That closed the dam-specific line of enquiry
and led to the root cause recorded above.

---

**Superseded hypothesis, kept for the record**: the
v4.20 reservoir manual documents `LiVnorm` as controlling initial storage when a
reservoir first activates under `LDAMYBY=.TRUE.` — `.FALSE.` (our setting, and the
default) activates it with *zero additional storage*, `.TRUE.` activates it at
Normal Volume. Every negative-storage crash above was at a post-1988 dam
(Itoiz 2003, Rialb 1999, SanSalvador 2013, Pajares 1994) going negative on
activation — precisely the path this flag controls. None of the four
configurations tried above varied it. Try this one flag before any further
per-dam parameter surgery. See `docs/cama_flood_reservoir_methodology.md`.

**Not yet done, before trying another configuration blindly**:
- Check the actual WFDE5 1988 forcing / naturalised-run discharge around 1988-05-15 to 05-25 directly for a genuine extreme event (magnitude, how it compares to the Gumbel-fit Q100s already computed) — confirms or refutes the "real record event" reading before chasing more per-dam parameter fixes.
- Get finer-than-daily diagnosis of which dam fails in the *non-negative-storage* crashes specifically — `damtxt-1988.txt`'s once-per-day granularity may be missing the actual failing intra-day state; would need an instrumented build or a coarser question (e.g. does the crash disappear if the single worst day's forcing is clipped/smoothed, as a pure diagnostic, never for a real run).
- Raised independently by the user (2026-09-16): **this whole workaround may not be needed if the domain is rerun at glb_06min or glb_03min** (both already validated for LIAISE, see the "CaMa-Flood coupling" section of CLAUDE.md) — finer resolution changes catchment delineation and channel geometry per cell, which could shift which dams (if any) hit this same scale-mismatch problem, though it isn't guaranteed to eliminate the class of issue entirely, just possibly relocate it. Worth real consideration once glb_15min is either fixed or its limits are fully understood, not as a shortcut to avoid diagnosing the current failure.

No job resubmitted pending one of the above. `namelist/input_cmf_dam_test_ldambyfalse` and the two test `RUN_ROOT`s (`..._dam_test_noybY`, `..._dam_test_noflix_noybY`) are diagnostic scratch, not part of the real pipeline.

The original not-yet-built-cell/confluence finding (3 of 4 flagged cells sit at or within a few steps of a major confluence; none sit directly on a bifurcation path per `bifprm.txt`) remains a real, separate observation, but given the diagnostic run crashed identically without it being the active mechanism, it's likely a second, independent manifestation of the same root cause (small/fast-changing storage at a cell excluded from `CALC_ADPSTP`'s adaptive-timestep consideration) rather than a distinct confluence-specific bug — worth keeping in mind if further dams surface this same failure mode later in the 37-year run, past 1988.

### Step 5 launch command (superseded — do not reuse until the crash above is resolved)
```bash
sbatch --job-name=liaise_cmf_dam --time=08:00:00 \
  --export=ALL,RUN_ROOT=/perm/pad/liaise_cmf_1988_2024_dam,NAMELIST=/etc/ecmwf/nfs/dh2_perm_a/pad/liaise-ecland/namelist/input_cmf1way,CMF_NAMELIST=/etc/ecmwf/nfs/dh2_perm_a/pad/liaise-ecland/namelist/input_cmf_dam,CMF_STATIC_DIR=/etc/ecmwf/nfs/dh2_perm_a/pad/liaise-ecland/cama_flood/data_dam_firstpass,CMF_STATIC_FILES_EXTRA=dam_param.csv,ECLAND_EXE=/etc/ecmwf/nfs/dh2_perm_a/pad/liaise-ecland/run/bin/ecland-master-dp_pinned_20260913 \
  run/run_liaise_ecland.slurm
```
This is the *correct submission form* (note: `--export=ALL,...` as flags, not
shell-prefixed vars) — keep this form for any future submission on this
cluster — but do not re-run until one of the candidate fixes above is chosen,
since it will crash the same way otherwise.

### Open blockers worth flagging early
- **GRSAD download** (surface-area series for normal volume, p03): TDL Dataverse API returns 403 from the HPC; needs a browser/desktop fetch. The 37%-fallback in use now is itself one of the artifact's named calibration targets, so not blocking step 5 — but the first dammed run's `FldVol`/`ConVol` split should be treated as provisional until GRSAD lands.
- **`/perm` cleanup risk, recurring**: the Fortran naturalised `o_totout.nc` has now been cleaned up and re-run once already. The derived Q100 table and `dam_param.csv` are checkpointed at `/perm/pad/liaise_discharge_compare/` precisely so a future cleanup of the raw `o_totout.nc` doesn't erase them — but neither file is in the repo yet (convention: only small *validated* reference data goes in `cama_flood/data/`, and this is the first, fallback-volume pass, not the calibrated version). Reconsider committing once GRSAD-based volumes replace the 37% fallback.

## Completed this session (folded into CLAUDE.md, kept here only as a pointer)
- CAMELS-Spain gauge extraction (46 stations) + non-comparative control skill dashboard, deployed to `sites.ecmwf.int/pad/liaise/gauges/`. See CLAUDE.md and `cama_flood/extract_liaise_grdc_observations.py`/`skill_benchmark_control.py`/`build_control_dashboard.py`.
