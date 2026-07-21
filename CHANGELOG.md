# Changelog

All notable changes to the Monash Myeloma Model project will be documented in this file.

The format is based on [Keep a Changelog](https://keepachangelog.com/en/1.0.0/), and this project adheres to [Semantic Versioning](https://semver.org/spec/v2.0.0.html).

## [Unreleased]

### Added
- **Refractory-status capture in the extraction** (`prep/data_extraction.do` + new `prep/sub/MRDR/build_refractory.do`). `MRDR Long` now carries, per chemotherapy line, an IMWG `Refractory` flag (non-response on the line, or a progression event within 60 days of it) and `LineProg` / `LineProgDate`; per patient, the maintenance drug, `MNT_Len`, `MNT_Refr`, `MNT_LenRefr`, `MntLenRefrStart`; and two carried-forward **lenalidomide-refractory** flags evaluated *as at entry to each line* (strictly prior lines only) — `LenRefr_Tx` (treatment-dose) and `LenRefr_Mnt` (maintenance-dose, line-resolved by date), kept separate because the form the drug sits in is the dose proxy. Progression uses a hybrid definition (Review structured ∪ treatment-record; the treatment record is essential — ~390 patients progress with no Review progression filed). Additive only: `MNT` and the event skeleton are unchanged, so `risk_equations.do` runs identically. The treatment-dose flag is now consumed by the engine (see below); the maintenance-dose flag is not. Definitions, evidence and design decisions: `docs/refractory.md`.
- **`docs/refractory.md`** — the specification of record for the refractory subsystem. It also carries the specification for `prep/data_extraction.do` and `prep/sub/`, which are git-ignored under the data-governance rule and therefore have no other home in the repo.
- **Maintenance duration: capture and equations** (`prep/data_extraction.do`, `prep/risk_equations.do`, `analyses/default/outcomes/mnr_{full,train}.do`), addressing the maintenance over-costing under Known issues below. `MRDR Long` now carries, per patient, `MND_L1` (maintenance duration delivered in the billed L1 gap, days - the benchmark target) and `MNR_L1` (maintenance regimen), and the extraction now KEEPS the L1 maintenance start/end events (110/111) in the event skeleton instead of dropping them. `risk_equations.do` gains **`gen_mnr`**, mirroring `gen_txr`, and two equations beside the `MNT` logit complete whether / which / how long: **`L1_MNR`** (mlogit, lenalidomide vs thalidomide) and **`L1_MND`** (parametric survival on the duration, split by transplant like `L1_TFI`: `i.MNR_L1`, Age, `i.ECOGcc`, `i.RISS`, and `i.BCR_SCT` for the ASCT arm / `i.BCR_L1` for the no-ASCT arm). SIMPLE-FIRST scope: lenalidomide and thalidomide only, no 'other' regimen. `L1_MND` carries `ln(TFI_L1)` with a regimen interaction so lenalidomide duration scales with the gap (runs to progression) and thalidomide stays fixed; the engine caps the drawn duration at the realised TFI_L1. The restored maintenance events subdivide the L1-to-L2 span but do not move any other equation's origin/failure (which resolve by date), so OS/TFI/TXD are untouched. Consumed by the engine: see Fixed below. Design and evidence: `docs/refractory.md` sections 4.4 and 7.

- **Lenalidomide-refractory status (treatment lines) generated and consumed by the engine.** `LenRefr_Tx` now affects model behaviour. Generation is `core/outcomes/sim_lenrefr.do`: a latched 0-to-1 state (`vLenRefr_in`) fired at each line's END, after that line's OS, so the covariate every equation reads is refractoriness from strictly prior lines. It flips definitionally when best response is SD/PD, else by a Bernoulli draw from a residual-arm logit (`LENREFR_TX` in `risk_equations.do`, pooled across lines with the line collapsed to L1/L2/L3+, fitted on not-yet-refractory rows so it carries no prior-state covariate). The lenalidomide gate is by drawn regimen (`global LENREFR_regimens`, declared per analysis in `outcomes/txr_<coeffs>.do`, "7 31" in the default), the engine analogue of the fit's `Lenalidomide == 1`. Consumed as `LenRefr_Tx_in` in the L2-L4 regimen mlogits (`sim_txr.do`) and the L2-L4 OS survival models (`sim_os.do`); nothing in TXD, TFI or response (no independent signal once BCR and regimen are present). New `rn_lenrefr()` CRN slot re-lays-out `mRN` (`rn_K()` 76 -> 85). Only the treatment arm is wired; maintenance refractoriness stays out (no generation model, see Known issues). **In-sample the L3 regimen/duration overshoot the change targeted collapsed (6 benchmark FAILs to 0); out-of-sample whole-population OS validates within ~1.5% at 3/5/10 years and by comorbidity.** Adding a worse-prognosis covariate to OS is mean-preserving redistribution: refractory patients get worse survival and non-refractory correspondingly better, sharpening subgroup discrimination without moving the calibrated aggregate. Design, engine map and the subgroup-magnitude caveat: `docs/refractory.md` sections 3.5, 4.7, 5.6.

### Known issues
- **No generation model for maintenance refractoriness.** `docs/refractory.md` 4.4 specified a definitional tail rule (`tail = TFI_L1 - TTM - MND_L1 <= 60 days`) at AUC 0.905 against a logit's 0.69. **That validation was contaminated and the rule is withdrawn.** The score also contained the registry's cessation-reason column (`rcess == 5`), IMWG 1.5's *first* limb, which is close to a restatement of the outcome, which the compared logit never saw, and which **the engine cannot compute at all** since reason-for-cessation is not modelled. Re-measured like-for-like on the same 230 patients the tail alone is **0.637**, the logit **0.586**, and `rcess` alone **0.880**; the engine reported **33.7%** flagged against a registry 70.4%, which is the rule working correctly at gap lengths it was never calibrated for. The binding constraint was **selection, not functional form**: a *share* needs an observed gap *end*, so it was fitted on complete gaps only (median **23.9 months**) against a true median of **73.5 months** for ASCT/CR patients - which is why the duration was rebuilt as a survival model on the maintenance events, made gap-dependent by ln(gap) on complete gaps (see Fixed). `MNT_LenRefr_L1` is derivable from that capped duration but is not yet emitted by the engine. Three paths forward, and the evidence for each: `docs/refractory.md` 4.4.
- **Reproducible treatment-cost engine** (`prep/`): treatment costs rebuilt from first principles as the PBS **Dispensed Price for Maximum Quantity**, derived from a dated PBS Schedule extract rather than a manual spreadsheet — `build_cost_index.do` (ABS CPI deflator), `extract_pbs_costs.do` (Schedule → drug prices), `extract_pbs_restrictions.do` (eligibility reference) and `treatment_costs.do [year] [wholepack|prorata]` → `prep/inputs/treatment_costs_<year>.csv`. Non-treatment costs are phase-of-care (Yap 2025), with the initial phase netted of the transplant admission to avoid double-counting. Perspective is the Australian health system, so the full DPMQ is used with the co-payment **not** netted off; oral packs default to whole packs (dispensing wastage costed, per PBAC convention), with pro-rata as a sensitivity. Derivations in `docs/economic_inputs.md`.
  - **`$cost_year` falls back to the latest available file** when the requested year has no cost CSV. Check the cost year before re-running any near-submission analysis: 2026 generic price disclosure moved drug costs materially, so a re-run can silently reprice an older analysis.

### Changed
- **Simulation cohorts migrated from `population_*` to `synthetic_*`.** The `population` cohort token is retired: `core/load_patients.do` now resolves `$data` to `synthetic` / `synthetic_<n>` (the incidence cohorts), `$cohort_file` (an explicit override) or a predicted patient file. `patients/population_1995_2040_*.dta` are superseded and deleted — they carried the retired ordinal comorbidity score (`CMc`) and the unused `CM_LVR` / `CM_PNR` / `CM_MLG` flags, and their covariates came from an imputation model that still included them. `patients/synthetic_1995_2040_1..10.dta` (from `prep/synthetic_1995_2040.do`) replace them.
  - The `patients/population_historical.csv` and `population_forecast.csv` **incidence inputs** (AIHW and Daffodil Centre) keep their names: they are inputs *to* the cohort build, not cohorts.
  - Line-entry cohort pools (`analyses/*/patients/cohort_pool.do`) now loop the synthetic cohorts. A pool built from the old `population_*` files is not reproducible against the current inputs and must be rebuilt.
- **Removed the dead `$data == "population"` early-exits** from `core/simulation_engine.do` (four line-truncation branches belonging to the archived `base_model` analysis; they never fired for the `population_<n>` / `synthetic_<n>` cohort-pool tokens).
- **Two-arm report shows patient counts in the treatment-pathways table.** The number receiving each line (n) now sits directly below the Reached % in each arm's column (`core/generate_report.do`), so the proportion and the absolute count are read together.
- **Two-arm report: cost-over-time figure.** New page showing mean undiscounted cost per patient by year since the decision line, split treatment vs non-treatment for each arm (`core/generate_report.do`). Treatment cost is allocated across each line's relative-time window; non-treatment across the survival window at the phase rate. A per-patient trajectory (no uptake) intended as the building block for a calendar-year budget-impact analysis.

### Fixed
- **Maintenance cost was overstated by 69%** (`core/process_data.do`). `cost_tx_mnt` billed the blended `cMNT` across the entire `TFI_L1`, i.e. it assumed the patient was on maintenance for the whole L1-to-L2 gap. It now bills a modelled episode: `sim_mnr.do` draws the regimen (lenalidomide or thalidomide), `sim_mnd.do` draws the **duration** from a parametric survival model (`streg`, log-normal, split by transplant like `L1_TFI` with `i.MNR_L1`, response, `i.ECOGcc` and `i.RISS`), and `process_data.do` **caps** it at the realised `TFI_L1` before billing. The `L1_MND` fit is a normal `stset` on the maintenance start/end events (110/111) restored to the skeleton - `origin(Event1==110) failure(Event1==20 111)` - so `stset` derives the survival time and failure cleanly with no separate censoring variable. The fit adds `ln(TFI_L1)` (complete gaps) with a regimen interaction so lenalidomide duration scales with the gap and thalidomide stays fixed; the no-ASCT arm is restricted to responders (BCR CR/VGPR/PR/MR), since SD/PD do not receive maintenance and would otherwise empty a factor cell on the small sample - `sim_mnd.do` drops the same patients. The cap turns a draw that overshoots the gap into continuous-to-progression maintenance and inherits `sim_mort`'s death curtailment. **Known shortcoming**: the share validates only directionally. Fitted on complete gaps (median ~24 months) but simulated out to ~98-month gaps, the drawn duration undershoots at long gaps - the simulated lenalidomide share rises with the gap (right direction, OOS mid-bands within ~6-8pp of the registry) but too shallowly, so band 4 (42mo+, about half the maintenance cohort) under-shares (in-sample 0.44 against a registry 0.83) while very short gaps over-share via the cap. This under-bills long-gap maintenance and is accepted as the gap-extrapolation limitation (5(5)), not a bug. The whole model still validates out-of-sample at **83.9% (146/174)**, unchanged by the maintenance and refractory work. SIMPLE-FIRST: lenalidomide and thalidomide only, no window and no TTM start offset (an earlier share-of-the-window `betareg` design was withdrawn before release). Affects the **`default`** full-pathway analysis and budget-impact work; `transport_dvd` and `car_t` are `$line 2` and never costed maintenance. Two limitations remain, both pre-existing: pricing is still the blended `cMNT` (only lenalidomide has a PBS maintenance listing), and **later-line maintenance is costed nowhere**. The `rn_mnr()` / `rn_mnd()` slots re-lay-out `mRN` (`rn_K()` 74 -> 76), so patient-level results are not comparable with runs before this change. Evidence and the rejected full decomposition: `docs/refractory.md` section 7.
- **Best clinical response (BCR) was collapsing to a single imputation.** In `prep/multiple_imputation.do` the direct-column LOCF carry-forward filled BCR's m=0 master, so the subsequent `mi update` reset the per-imputation values to that single master value — only ~24 of ~5,000 imputed response rows varied across the 10 imputations (every covariate imputed correctly). Fixed by carrying forward only the imputation columns for BCR (`_cf … nomaster`), leaving the master missing as a registered imputed variable requires; the response now varies correctly (FMI ≈ 0.1–0.45). The two ASCT equations whose estimation sample conditions on imputed BCR (`if BCR != 6` at L1 end, `if BCR_L1 != 6` at ASCT; `prep/risk_equations.do`) now use `esampvaryok`, since the eligible sample legitimately varies across imputations. Out-of-sample validation is unchanged at **139/172 (80.8%)** — the pooled point estimates are stable, so the correction acts on the between-imputation variance (standard errors / prediction intervals), not the point predictions. Coefficients regenerated.

### Planned
- Integration with R for post-processing analysis
- Extended documentation for health economic applications
- Daratumumab **SC** regimen option (a regimen-file switch; cheaper at this body weight and closer to current practice)

## [3.0] - 2026-07-07

### Added
- **Calibrated Transport methods** (`analyses/transport_dvd/`): out-of-trial outcome prediction (e.g. DVd at L2) with a common-random-number engine, sample-size workflow, and cohort pipeline.
- **Common Random Numbers (CRN)**: aligned RNG across treatment arms via an `mRN` slot registry (`core/rng_slots.do`) and `rnDraw` migration, for variance-reduced cost-effectiveness comparisons.
- **Per-line overall survival**: OS re-specified as a separate parametric model per line/stage of therapy, each clocked from that line's own start (`OS_DN`, `OS_L1`/`_NoASCT`/`_ASCT`, `OS_L2..L5` (+`_End`), `OS_L6plus`), replacing the single from-diagnosis survival curve — removes an accumulated-time bias that inflated survival for poor responders at later lines. Engine: `core/outcomes/sim_os.do` (per-stage firing map, diagnosis-clock storage).
- **Individual comorbidity covariates**: the OS and both ASCT-eligibility equations now carry four individual comorbidity flags — renal impairment (`CM_CKD`, derived from imputed eGFR), cardiac (`CM_CRD`), pulmonary (`CM_PLM`) and diabetes (`CM_DBT`) — replacing the earlier single ordinal comorbidity score (`CMc`). Engine plumbing in `core/mata_setup.do`, `sim_os.do`, `sim_asct_*.do`, `process_data.do`.
- **Consolidated pipeline**: dispatchers unified onto `core/run_pipeline.do`; added `analyses/transport_dvd/ce_sample_size.do`.
- **Standardised CSV result exports**: machine-readable results for downstream/programmatic access (R/Python post-processing, dashboards, assistant-driven manuscript drafting) instead of manual copy-to-Excel.
  - **`core/export_results.do`**: engine-level export of CSVs common to every analysis (per-patient summary, BCR distribution, mean cost/QALY/LY). Runs by default as part of the simulation pipeline (immediately after `process_data`, once per arm; skipped during bootstrap), reading `core/process_data.do` outputs into `simulated/<scenario>/`. First adopted by the `dvd_method` dispatcher.
  - **`analyses/<name>/results/` contract**: each analysis exposes a single `results/` folder of final (cross-scenario) CSVs plus a `results.md` narrating the key figures — the canonical downstream read surface. Analysis-specific and cross-scenario aggregation live under `analyses/<name>/`, not `core/`.

### Changed
- **Rebranded** from *EpiMAP Myeloma* to **Monash Myeloma Model**; GitHub repository renamed `CHE-Monash/EpiMAP-Myeloma` → `CHE-Monash/Myeloma-Model` (old URLs auto-redirect). Published papers and DOIs retain the EpiMAP Myeloma name.
- **Version bump to 3.0**: consolidates the v2.1 vectorised engine with the Calibrated Transport/CRN methods and the July 2026 calibration work (per-line OS + individual comorbidities) into a single major release. From v3.0 onward, major versions increment with each published paper (see Version Naming Convention).

### Licensing
- **Relicensed to a dual, source-available model from v3.0**: the software is now offered under the **PolyForm Noncommercial License 1.0.0** (free for academic/noncommercial use), with **commercial use — including industry-sponsored regulatory/reimbursement (e.g. PBAC) submissions — by separate licence from Monash University**. Registry-derived data and fitted parameters are additionally governed by the MRDR data agreement. See `LICENSING.md`.

### Incorporated from v2.1
- Vectorised Mata engine, modular `mata_setup.do`, and the comprehensive validation suite — see the [2.1] entry below for detail.

## [2.1] - 2025-10-27

### Added
- **Vectorised Implementation**: Complete rewrite of core simulation engine using Mata vector and matrix operations
- **`core/vector_setup.do`**: New modular vector setup module for efficient data preparation
- **Comprehensive Test Suite**: New validation framework in `tests/` directory
  - `validate_vectors.do`: Validates vectorised implementation against original
  - Additional outcome-specific validation tests
- **Improved Error Handling**: Enhanced validation of vector dimensions and data consistency
- **Performance Metrics**: Built-in validation summaries with detailed reporting

### Changed
- **Core Engine**: Replaced patient-level loops with vectorised Mata operations throughout
- **Data Processing**: All patient characteristics now processed as vectors for simultaneous operations
- **Matrix Operations**: Optimised matrix algebra for risk equation calculations
- **Code Structure**: Modular architecture with clear separation between setup, computation, and validation
- **Repository Organisation**: Modernised Git-based versioning (removed version folders)
- **File Naming**: 
  - `EpiMAP_Start.do` → `run.do` (clearer purpose)
  - Simplified main dispatcher naming
- **Documentation**: Updated README with vectorisation details and performance notes

### Performance
- **Execution Speed**: Significantly faster for large cohorts (10,000+ patients)
- **Memory Efficiency**: Reduced memory overhead through bulk operations
- **Scalability**: Better handling of bootstrap iterations and large-scale simulations

### Fixed
- Memory allocation issues in large simulation runs (now handled via vectorisation)
- Numerical precision edge cases through consistent vector operations
- Random number generation consistency across parallel operations

### Validation
- All vectorised outcomes validated to produce identical results to v2.0
- Comprehensive testing confirms bit-for-bit equivalence with loop-based implementation
- Extended validation suite for ongoing quality assurance

### Technical Details
- Implementation uses Mata's native vector and matrix operations
- Pre-allocated vectors for all patient characteristics (age, sex, ECOG, R-ISS, comorbidities)
- Matrix-based risk equation calculations with element-wise operations
- Consistent random number seeding for reproducibility

## [2.0] - 2025-01

### Added
- Reorganised repository structure with clear version folders (v1.0/, v2.0/)
- Enhanced documentation with detailed user guide
- Improved parameter validation and error checking
- New treatment pathway options for later lines of therapy
- Comprehensive testing framework for model validation
- Better handling of edge cases in survival calculations

### Changed
- **BREAKING**: Repository structure reorganised - models now in version-specific folders
- **BREAKING**: Updated file naming conventions for better clarity
- Improved simulation performance through code optimisation
- Enhanced random number generation for better reproducibility
- Updated coefficient matrix structure for additional parameters
- Refined treatment-free interval calculations

### Fixed
- Corrected edge case in ASCT eligibility determination
- Fixed rare numerical precision issues in survival probability calculations
- Resolved memory allocation issues in large simulation runs
- Improved handling of missing data in patient characteristics

### Model Updates
- Updated risk equations based on latest MRDR data analysis
- Refined treatment regimen proportions to reflect current clinical practice
- Enhanced Best Clinical Response prediction accuracy
- Improved Overall Survival curve fitting

### Documentation
- Complete rewrite of user documentation
- Added model specification document with technical details
- Created parameter reference guide
- Added validation report with benchmark results

## [1.0] - 2024-08

### Added
- Initial public release of EpiMAP Myeloma simulation model
- Discrete-event simulation framework for multiple myeloma outcomes
- 30 risk equations based on MRDR patient-level data
- Support for up to 9 Lines of Therapy (LoTs)
- Hypothetical patient dataset with 1,000 patients for testing
- Complete documentation and usage instructions

### Model Features
- **Patient Characteristics**: Age, sex, ECOG performance score, ISS stage
- **Treatment Pathways**: Comprehensive modelling of treatment sequences
- **Survival Analysis**: Parametric survival models for overall survival
- **Clinical Response**: Ordered logit models for Best Clinical Response
- **ASCT Support**: Separate analysis paths for transplant-eligible patients
- **Maintenance Therapy**: Modelling of post-induction maintenance treatment

### Risk Equations
1. Overall Survival
2. Planned ASCT eligibility
3. Diagnosis to treatment interval
4. LoT 1 chemotherapy regimen selection
5-7. LoT 1 chemotherapy duration (with manual splines for ASCT patients)
8. LoT 1 chemotherapy duration (non-ASCT patients)
9. LoT 1 Best Clinical Response
10. Receipt of ASCT
11. ASCT Best Clinical Response
12. Receipt of maintenance therapy
13-14. LoT 1 to LoT 2 treatment-free intervals (ASCT vs non-ASCT)
15-17. LoT 2 treatment pathways and outcomes
18-30. LoTs 3-6+ treatment pathways and outcomes

### Chemotherapy Regimens
- **LoT 1**: VCd (58%), VRd (15%), Other (26%)
- **LoT 2**: Rd (16%), DVd (11%), Other (73%)
- **LoT 3+**: Averaged survival benefit approach

### Technical Specifications
- **Platform**: Stata 15.0 or higher required
- **Programming**: Stata with Mata matrix operations
- **Data Format**: Stata .dta files for patient data
- **Coefficients**: Mata .mmat matrix files for risk equations
- **Output**: Comprehensive simulated patient outcomes dataset

### Validation
- Model calibrated against MRDR registry data (2009-2023)
- Survival curves validated against observed patient outcomes
- Treatment pathway distributions match registry patterns
- Out-of-sample validation with 70/30 split (2,884/1,237 patients)
- 100 bootstrap iterations for robustness testing
- No significant difference in 90% of 120 months post-diagnosis

---

## Migration Guides

### Upgrading from v2.0 to v2.1

**Good News**: v2.1 is fully backward compatible with v2.0 inputs!

**What's Different**:
- Internal implementation is vectorised, but all inputs/outputs remain the same
- No changes to data formats, coefficient files, or simulation parameters
- Results are identical (validated bit-for-bit equivalence)
- Significantly faster performance, especially for large cohorts

**Action Required**:
- None for basic usage - existing scripts will work unchanged
- Optional: Review new test suite in `tests/` for validation examples
- Optional: Update file references if using old naming (`EpiMAP_Start.do` → `run.do`)

**Performance Benefits**:
- ~2-5x faster for typical simulations (depends on cohort size)
- Better scaling for bootstrap analyses
- More efficient memory usage

### Upgrading from v1.0 to v2.1

**Breaking Changes**:
- Repository structure has changed (no more version folders)
- File paths for analyses updated
- Coefficient file organisation modified

**Action Required**:
1. Review new repository structure
2. Update file paths in custom scripts
3. Verify coefficient file locations in `analyses/*/data/coefficients/`
4. Test simulations with small cohort first

**New Features Available**:
- Extended treatment regimens
- Vectorised performance
- Comprehensive validation tools

## Release Notes

Each release includes:
- **Complete Model**: All necessary files to run simulations
- **Documentation**: User guides, technical specifications, and examples
- **Validation Results**: Benchmark tests and model performance metrics
- **Test Data**: Example datasets for testing and validation

## Contact

- **Model Questions**: adam.irving@monash.edu
- **Technical Issues**: Create an issue on GitHub
- **MRDR Data Access**: Visit mrdr.net.au
- **Collaboration**: Contact the research team via email

## Version Naming Convention

From v3.0 onward, **major versions increment with each published paper** (the model state used for that paper) or a significant methodological upgrade; minor versions cover interim features and fixes between papers:
- **Major version** (e.g. 2.0 → 3.0): the model as used for a new published paper, or a significant methodological/architectural upgrade.
- **Minor version** (e.g. 3.0 → 3.1): new features, improvements, or fixes between papers; backward compatible where possible.

Examples:
- v1.0: Initial release
- v2.0: Reorganised structure (breaking changes)
- v2.1: Vectorised implementation (backward compatible)
- v3.0: Calibrated Transport & CRN methods; rebrand to Monash Myeloma Model
