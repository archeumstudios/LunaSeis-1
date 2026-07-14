# Current status

Last updated: 2026-07-14 (Asia/Kolkata)

## State

Phase 0 feasibility and the complete binary-detection experiment cycle are finished. Three prospectively frozen continuous frames are consumed and negative. The final lower-confidence Grade-C challenge contained 63 previously unexposed physical impacts over 1,505.35 station-hours; the frozen 2,761-parameter depthwise CNN recovered 12/63, produced 1,306 false triggers (0.868/hour), and retained 75.38% of the stream. Across all 6,748.22 frozen station-hours, the project does not establish an operational detector. It is packaged as a functioning negative-result research/software prototype authored by Advaith Praveen (APRK), with GitHub documentation, model/data cards, a visually audited preprint PDF, vector/300-DPI figures, tables, citation metadata, notebook, checkpoints, inference CLI, copyright separation, and a literature-backed public-claims boundary. On 2026-07-14, the user reported successful Linux and Google Colab reproduction; exact environment versions and execution transcripts were not supplied or independently archived. Independent scientific review, final account URLs/DOI, and explicit publication remain open.

## Completed

- Inspected the initial workspace: it was empty and was not a Git repository.
- Preserved the complete supplied handoff in `docs/PROJECT_CONTEXT.md`.
- Created the permanent context document set and repository directory skeleton.
- Initialized Git and created commit `2683cd8` (`chore: initialize LunaSeis-1 research repository`).
- Verified waveform bundle `urn:nasa:pds:apollo_pse::1.0`, DOI `10.17189/9ykc-er91`.
- Verified event catalog bundle `urn:nasa:pds:apollo_seismic_event_catalog::1.0`, DOI `10.17189/1520573`.
- Recorded formats, archive layout, timing warning, documented instrument sample rates, and remaining uncertainties in `docs/source_verification.md`.
- Confirmed 47 GiB free before downloading; the catalog required only 2.2 MB.
- Added a manifest-driven catalog downloader and verified all 32 NASA-listed products (2,226,558 bytes) by MD5.
- Audited 11 catalog CSV schemas and generated a machine-readable schema report.
- Inspected the official four-page catalog-description PDF by text extraction and rendered-page review.
- Selected the Apollo 15 S-IVB artificial impact (1971, Julian day 210) as the Phase 0 pilot candidate, with published P arrivals at stations 12 and 14.
- Verified candidate-day availability for S12 and S14 and enumerated all products and official MD5 values.
- Selected MiniSEED plus StationXML/PDS labels: 7,924,909 bytes (about 7.6 MiB), versus over 250 MB for equivalent GeoCSV waveforms.
- Verified product metadata rates: 6.625 Hz mid-period, 53 Hz SHZ, and 1.65625 Hz ATT; corrected the earlier 15 Hz discovery-stage note.
- Documented ATT reception-time semantics, nominal-time drift, uncorrected 1.2-1.4 s Moon-Earth delay, station synchronization risk, and gap sentinels.
- Added and tested a manifest-driven pilot downloader; all 20 products and 7,924,909 planned bytes passed size and NASA MD5 verification.
- Created a Python 3.12 virtual environment with pinned ObsPy/Matplotlib dependencies; pinned setuptools below 81 for ObsPy compatibility.
- Loaded all nine MiniSEED traces and recorded coverage, sample rates, sample counts, full-day sentinels, and event-window sentinels.
- Matched published arrivals through ATT: nominal mapped time is +0.330 s at S12 and +5.233 s at S14 relative to published arrival.
- Generated and visually verified the first unprocessed LunaSeis-1 waveform plot; a strong event signal is visible at both stations.
- Recorded the Phase 0 feasibility result and the scientific limits of this one-event validation.
- Audited NASA science-data, PDS citation, and NASA brand policies; raw PSE observations are operationally treated as CC0, while bulk event-catalog/labeled-derivative republication is deferred pending written PDS clarification.
- Decoded all PDS `T2` event codes, A/B/C grade meanings, quality codes, and station/channel visibility fields from the official XML label.
- Parsed all 13,057 `levent` rows into a local analytical manifest and produced class/year/station/channel counts.
- Found no exact duplicate catalog start-minute keys; identified 319 assigned deep-family IDs and quantified the largest repeating families.
- Defined a conservative A/B pilot pool: 609 deep events, 623 natural impacts, 18 shallow events, and 8 artificial impacts.
- Rejected broad four-class classification for the initial pilot; retained deep-versus-natural-impact only as exploratory secondary work.
- Designed event-disjoint and deep-family-disjoint leave-one-station-out evaluation with chronological validation and no final-station tuning.
- Completed an initial systematic scoping search and extracted ten priority peer-reviewed records plus four screened/background records.
- Established that 2026 FNO work already overlaps lightweight raw-waveform detection/efficiency and that a 2024 short-period catalog expands shallow events from 28 to 74; candidate novelty and labels were revised accordingly.
- Located the authoritative Onodera 2024 article and its 2026 correction; found no separately deposited machine-readable catalog and documented the article tables' CC BY-NC terms.
- Transcribed the corrected tables into a provenance-preserving manifest and reconciled all 28 legacy events exactly to PDS `H` rows; all 46 KO events are absent from the PDS table at the same-minute level.
- Audited 136 event-station pairs: 128 are complete, and every one of the 74 events has at least one complete SHZ+ATT station-day.
- Produced an exact deduplicated plan for 508 PDS products across 127 station-days: 779,909,406 bytes (743.78 MiB / 0.72635 GiB), each with an official expected MD5.
- Kept shallow classification descriptive/exploratory and recorded KO-SMQ-26/KO-SMQ-40 as a repeating pair that must remain split-grouped.
- Downloaded the four KO-SMQ-26 S15 products (7,391,202 bytes) and verified every official MD5 and size.
- Mapped its corrected reference through ATT: nearest ATT is -0.290 s and the associated nominal MiniSEED timestamp is +4.099 s relative to the catalog reference.
- Verified a clear raw emergent SHZ amplitude increase (post/pre RMS 3.56); documented 12.5% isolated one-sample sentinels in the ten-minute SHZ window without interpolating them.
- Downloaded/reused and independently size/MD5-verified all 508 shallow-plan products totaling 779,909,406 bytes.
- Audited all 128 complete event-station windows: 123 usable, one questionable, and four rejected for raw integrity; all 74 events retain at least one usable station.
- Recorded descriptive signal ratios (88 strong, 23 weak, 15 without clear elevation, two unquantifiable) without using them to alter labels or integrity status.
- Combined conservative PDS candidates and corrected shallow events into one 1,314-row physical-event registry without duplicating the 28 overlapping legacy shallow records.
- Preserved source IDs, labels/grades, time precision/semantics, stations/channels, licensing notes, and explicit pending/audited QA status.
- Attached shallow QA, removed four rejected station windows from usable-station fields while retaining all rejected/questionable audit records, and kept all 74 shallow events as candidates with at least one usable station.
- Assigned indivisible physical-event, 115 deep-family, and KO-SMQ-26/KO-SMQ-40 repeating-pair evaluation groups.
- Passed duplicate ID, source ownership, same-minute overlap, cross-class conflict, and legacy PDS-type checks.
- Counted 609 deep, 623 natural-impact, 74 shallow, and eight artificial-impact physical candidates; nonshallow candidates remain pending waveform QA.
- Converted 1,240 nonshallow candidates into 3,071 event-station requests and 2,496 deduplicated/boundary-complete station-days.
- Verified that 1,159 candidates have at least one PDS-backed positive station request; preserved 81 unavailable candidates (57 assigned deep, 24 natural impacts) without relabeling.
- Produced an exact plan for 15,106 MiniSEED/XML products totaling 7,636,136,244 bytes (7.11171 GiB), each with official PDS MD5.
- Partitioned the plan into four deterministic station-day-preserving batches no larger than approximately 2 GiB; no nonshallow waveform data was downloaded.
- Downloaded and exact-size/NASA-MD5 verified all 5,398 Batch 1 products totaling 2,142,346,643 bytes across 845 station-days.
- Hardened the shared downloader to delete and retry completed HTTP responses that fail size/hash checks; no throttled or partial response was accepted.
- Audited 658 events, 842 event-station requests, and 2,234 positive-channel windows with ATT-aware timing and raw gap/extreme-value/RMS metadata.
- Classified 648 Batch 1 events usable, two questionable, and eight rejected on gap/ATT integrity only; visually reviewed the aggregate figure and documented all suspicious cases.
- Updated the unified registry with Batch 1 QA status/stations while preserving every physical label and evaluation group.
- Downloaded and independently re-verified all 3,270 Batch 2 products totaling 2,145,595,149 bytes across 502 station-days.
- Audited 599 Batch 2 events, 599 event-station requests, and 1,337 positive-channel windows using the unchanged ATT/gap procedure.
- Classified 586 Batch 2 events usable, three questionable, and ten rejected within the batch; reviewed every suspicious request and the aggregate QA figure.
- Generalized unified-registry attachment to discover and combine all available audited batches, preserving station-specific rejected evidence.
- Rebuilt the registry with 946 usable, three questionable, nine rejected-only, and 282 pending nonshallow events; every event label and evaluation group remained unchanged.
- Downloaded and independently reverified all 4,014 Batch 3 products (2,145,641,669 bytes) and all 2,424 Batch 4 products (1,202,552,783 bytes).
- Closed the complete nonshallow plan at 15,106 products and 7,636,136,244 verified bytes across 2,496 station-days.
- Audited Batches 3–4 and consolidated 6,236 positive-channel windows, 2,476 event-station requests, and all 1,159 archive-backed events.
- Final nonshallow aggregation is 1,146 usable, three questionable, ten rejected-only, and 81 archive-unavailable candidates.
- Quantified strict/primary/lenient integrity sensitivity and froze the reproducible nearest-valid-ATT-to-nominal mapping while preserving unresolved physical timing semantics.
- Generated 4,747 fold-specific positive assignments with physical-event/deep-family groups indivisible and no group crossing roles within a fold.
- Generated 81,980 deterministic catalog-negative candidates after split assignment with a ±1-hour all-catalog exclusion buffer and explicit positive-day selection-bias warning.
- Froze primary MH preprocessing v0.1 and generated 3,910 primary positive windows.
- Ran energy, STA/LTA, and handcrafted logistic pilot baselines across all four LOSO folds; retained results as diagnostics only.
- Triggered a shortcut/training gate because S12 logistic F1 0.870 and 0.284 FP/hour is anomalously stronger than other folds on a biased background frame.
- Selected 928 official archive station-days across 29 station/year strata with a fixed hash seed before inspecting channel completeness and without reading event catalogs.
- Preserved 201 archive-incomplete selected days without replacement; planned 727 days with ATT plus at least one primary MH channel.
- Downloaded/reused and independently reverified all 5,554 independent-background products totaling 1,585,898,632 bytes.
- Audited full-day gaps, retaining 710 days (S12 210, S14 203, S15 164, S16 133) and rejecting 17 complete days under the frozen gate.
- Constructed 22,444 distinct ten-minute catalog-negative windows after applying ±1-hour buffers around all PDS and corrected shallow catalog times.
- Reran energy, STA/LTA, and handcrafted logistic baselines on independent days; S12 logistic changed from 0.870 F1 / 0.284 FP h⁻¹ to 0.795 / 2.123, confirming material background-frame inflation.
- Opened pilot-only tiny-CNN development while retaining a block on paper-level claims and final evaluation.
- Installed and pinned CPU PyTorch 2.13.0 in the project-local environment.
- Implemented deterministic native-cadence tiny-CNN training with training-fold-only waveform scaling, validation-loss checkpoint selection, validation-only thresholds, sample predictions, state checkpoints, and TorchScript exports.
- Preserved the first 512-bin temporal-averaging run as a failed ablation after its validation loss remained near random guessing and its scores failed to separate classes.
- Trained the corrected 3,057-parameter model across S12/S14/S15/S16 held-out folds. F1 is 0.874/0.714/0.632/0.663 and false positives per hour are 0.462/3.154/5.731/1.553 respectively.
- Determined that the tiny CNN beats the matched logistic baseline only at S12; it is worse at S14/S15 and has lower F1 but fewer false alarms at S16. H1 is not supported by this pilot.
- Ran waveform-zero, all-valid, all-zero, score-gap, and score-RMS shortcut sensitivities. Waveform-zero F1 collapses to 0.008–0.121 and score-gap correlations remain 0.024–0.071.
- Measured 3,057 parameters, approximately 16 KB state checkpoints, approximately 30 KB TorchScript exports, local single-window CPU latency of 0.20–0.25 ms, and post-loading fold training time of 4.5–11.4 seconds.
- Visually reviewed the CNN/logistic comparison figure and froze continuous-scanning v0.1 before any contiguous evaluation.
- Selected two fixed-seed, nonoverlapping 14-day blocks per station from official archive days after excluding 3,146 previously exposed station-days; event catalogs, channel quality, and model scores were not read during selection.
- Corrected a location-code discovery defect (`01` versus `00`) before accepting completeness; the original selected dates remained unchanged and now reproduce exactly.
- Verified zero prior station-day overlap and complete ATT plus primary-MH availability for all 112 selected days, balanced at 28 days per station.
- Produced an exact plan for 448 products and 171,375,344 bytes (163.44 MiB), each with official NASA MD5 and archive-listed size; no waveform was downloaded.
- Audited catalog coverage only after selection: 315 station-specific references to 263 unique catalog events, with seven unified candidates untouched by any prior role in their station fold and pending waveform QA.
- Excluded 16 prior-fold-exposed candidate occurrences from future untouched event-recall claims and retained the other 292 references for catalog-time false-alarm protection only.
- Authorized the bounded download under Decision 0019 while keeping model scoring blocked until checksum and full-day integrity QA pass.
- Downloaded all 448 contiguous-frame products totaling 171,375,344 bytes with exact-size and official NASA-MD5 verification.
- Reran the downloader disk-only; all 448 products were reused and independently reverified with zero network downloads.
- Loaded all 112 ATT/MH day pairs and recorded trace coverage, sample rates, gap fractions, longest gaps, and full-day integrity sensitivities.
- Classified 100 days usable, ten questionable at the 10% sensitivity boundary, and two rejected above the 20% primary full-day gap boundary.
- Audited all 160,272 frozen 600-second/60-second-stride candidate windows locally; 152,986 pass the 20% ATT-and-MH local gap gate.
- Froze 9,329,280 seconds (2,591.4667 hours) of merged underlying scannable time as the false-trigger denominator.
- Audited and visually reviewed all seven untouched candidate windows without loading a model. Six pass integrity; `levent-10063` is rejected for 78.59% waveform gaps and 78.714-second ATT displacement.
- Preserved descriptive signal evidence without relabeling: one weak post/pre RMS ratio, five without a clear increase, and one unquantifiable rejected window.
- Authorized continuous inference under Decision 0020 while retaining the small-event-denominator and paper-claim blocks.
- Reconstructed all CNN, logistic, and STA/LTA thresholds from prior training-station chronological validation data before reading any untouched scan score; the primary rule is the highest threshold retaining at least 90% validation event recall.
- Scored all 152,986 integrity-qualified windows with all three methods and saved every score with station, block, time, and local gap provenance in compressed CSV form.
- Applied frozen +120-second inferred references, 300-second trigger merging, one-to-one catalog matching, and ±60/±180/±300-second tolerances without tuning.
- At the primary ±180-second rule, measured CNN/logistic/STA-LTA eligible recall of 1/6, 1/6, and 0/6 with 2,932, 313, and 732 false triggers.
- Measured false-trigger rates of 1.131, 0.121, and 0.282 per union hour and 27.154, 2.899, and 6.779 per union day.
- Simulated retained-duration fractions of 75.50%, 40.28%, and 97.92%; these are operational failures, not bandwidth-saving evidence.
- Ran frozen matching sensitivities: at ±60 seconds all methods recall 0/6; at ±300 seconds CNN/logistic/STA-LTA recall 1/6, 2/6, and 0/6.
- Determined that the sole CNN/logistic `levent-10093` match is not secure evidence because high false-trigger counts make coincidence plausible.
- Audited false triggers by station and block, positive-window fractions, gap correlations, merged-run sizes, and the top 20 false triggers per method.
- Found severe cross-station threshold shift: CNN and logistic mark essentially 100% of S14 windows positive, while STA/LTA marks 85.8–99.9% positive across stations.
- Visually reviewed the highest-scoring false cases; large steps, ringing, plateau/saturation-like behavior, impulses, and high-frequency texture dominate.
- Accepted continuous scan v0.1 as a preserved negative result, rejected H1 for this pilot, and prohibited all future tuning on this consumed frame.
- Selected and checksum-verified a development-only continuous frame of 56 previously unexposed station-days, 224 products, and 84,837,751 bytes.
- Audited 57,823 catalog-buffered development windows spanning 993.85 physical station-hours and quantified severe station-specific plateau, step, and extreme-value proxy shift.
- Implemented per-window robust-level and robust-difference preprocessing with a validity mask, clipping, deterministic hard-negative selection, and training-station-only continuous validation.
- Trained both candidates across four LOSO folds; both retained 0.9115 mean positive-validation recall, while robust level produced 820 versus 923 merged triggers over 1,998.85 fold-hours and was frozen before test v0.2.
- Selected test v0.2 only after model/threshold freeze: 112 days with zero prior-manifest overlap, 448 products, and 171,072,240 checksum-verified bytes.
- Audited test v0.2 before inference: 157,363 qualified windows, 9,545,040 union seconds, 2,651.4 station-hours, and three integrity-usable prior-unexposed events.
- Ran the frozen v0.2 comparison once. Robust CNN/original CNN/logistic/STA-LTA produced 847/2,448/490/543 false triggers, 0.3195/0.9233/0.1848/0.2048 FP/hour, and retained 45.58%/62.48%/35.22%/96.49% of duration.
- Preserved the 0/3 recall for every method without threshold changes; rejected operational-success and retention claims and consumed test v0.2 permanently.
- Audited every integrity-eligible continuous-test miss over ±2 hours and found no defensible universal timing correction; distant score peaks remain confounded by frequent background activation.
- Trained 2,761-parameter depthwise CNN and 6,109-parameter compact TCN models in all four folds under the existing development-only hard-negative protocol.
- Selected depthwise CNN at equal 0.9115 mean event recall and 0.2106 merged false triggers/hour, versus 0.4102 for robust tiny CNN and 0.4558 for TCN.
- Implemented a public `lunaseis` package, station-held-out checkpoint selection, robust preprocessing, MiniSEED scanner, CLI, and inference tests.
- Ran the CLI on one complete checksum-verified S15 day: 1,418/1,429 windows scored and all 1,418 exceeded threshold, preserving persistent activation as a release limitation.
- Added author/release metadata for Advaith Praveen (APRK), MIT code license, citation metadata, polished README, model card, dataset card, reproducibility guide, release checklist, manuscript draft, paper tables, and Colab-ready tutorial notebook.

## Files changed

- Initial context/skeleton files in commit `2683cd8`.
- `docs/source_verification.md`
- `docs/CURRENT_STATUS.md`
- `scripts/download_catalog.py`
- `scripts/audit_catalog.py`
- `tests/test_download_catalog.py`
- `data/manifests/catalog_schema_audit.json`
- `data/manifests/pilot_event.json`
- `docs/catalog_audit.md`
- `docs/DECISIONS.md`
- `docs/decisions/0004-phase-0-pilot-event.md`
- `data/manifests/pilot_waveform_inventory.json`
- `docs/waveform_inventory_audit.md`
- `docs/source_verification.md`
- `docs/decisions/0005-pilot-waveform-format.md`
- `scripts/download_pilot_waveforms.py`
- `tests/test_download_pilot_waveforms.py`
- `scripts/audit_pilot_waveforms.py`
- `results/predictions/phase0_waveform_audit.json`
- `results/figures/phase0_apollo15_sivb_raw_waveforms.png`
- `pyproject.toml`
- `requirements-lock.txt`
- `docs/phase0_alignment_result.md`
- `docs/decisions/0006-att-aware-window-timing.md`
- `docs/ROADMAP.md`
- `docs/data_publication_policy.md`
- `scripts/audit_event_labels.py`
- `tests/test_audit_event_labels.py`
- `data/manifests/event_label_audit.json`
- `data/manifests/events_audit.csv`
- `docs/event_label_audit.md`
- `docs/data_dictionary.md`
- `configs/data/pilot.yaml`
- `configs/experiment/leave_one_station_out.yaml`
- `docs/decisions/0007-primary-task-and-multiclass-scope.md`
- `docs/decisions/0008-event-and-family-disjoint-loso.md`
- `literature/search_log.md`
- `literature/screening_log.csv`
- `literature/literature_matrix.csv`
- `literature/state_of_the_field.md`
- `scripts/reconcile_shallow_catalog.py`
- `scripts/build_shallow_download_plan.py`
- `tests/test_reconcile_shallow_catalog.py`
- `tests/test_build_shallow_download_plan.py`
- `data/manifests/onodera_2024_shallow_events.csv`
- `data/manifests/onodera_2024_reconciliation.json`
- `data/manifests/onodera_2024_shallow_coverage.csv`
- `data/manifests/shallow_pilot_download_plan.json`
- `docs/onodera_2024_catalog_audit.md`
- `docs/shallow_waveform_coverage.md`
- `docs/decisions/0009-updated-shallow-catalog-scope.md`
- `scripts/download_shallow_sample.py`
- `scripts/audit_shallow_sample.py`
- `tests/test_download_shallow_sample.py`
- `data/manifests/ko_smq_26_sample_download.json`
- `results/predictions/ko_smq_26_waveform_audit.json`
- `results/figures/ko_smq_26_raw_shz.png`
- `docs/ko_smq_26_sample_audit.md`
- `scripts/download_shallow_plan.py`
- `scripts/audit_shallow_windows.py`
- `tests/test_download_shallow_plan.py`
- `tests/test_audit_shallow_windows.py`
- `data/manifests/shallow_plan_download_receipt.json`
- `data/manifests/shallow_window_quality.csv`
- `results/predictions/shallow_window_quality_summary.json`
- `results/figures/shallow_window_quality_overview.png`
- `docs/shallow_window_quality_audit.md`
- `docs/decisions/0010-shallow-window-integrity-gate.md`
- `scripts/build_unified_positive_manifest.py`
- `tests/test_build_unified_positive_manifest.py`
- `data/manifests/unified_positive_events.csv`
- `data/manifests/unified_positive_event_audit.json`
- `docs/unified_positive_manifest_audit.md`
- `docs/decisions/0011-unified-positive-candidate-registry.md`
- `scripts/build_nonshallow_download_plan.py`
- `tests/test_build_nonshallow_download_plan.py`
- `data/manifests/nonshallow_waveform_requests.csv`
- `data/manifests/nonshallow_download_plan.json`
- `docs/nonshallow_storage_availability_audit.md`
- `docs/decisions/0012-batched-nonshallow-waveform-plan.md`
- `scripts/download_nonshallow_batch.py`
- `scripts/audit_nonshallow_batch.py`
- `tests/test_download_nonshallow_batch.py`
- `tests/test_audit_nonshallow_batch.py`
- `data/manifests/nonshallow_batch_1_download_receipt.json`
- `data/manifests/nonshallow_batch_1_window_quality.csv`
- `data/manifests/nonshallow_batch_1_request_quality.csv`
- `results/predictions/nonshallow_batch_1_quality_summary.json`
- `results/figures/nonshallow_batch_1_quality_overview.png`
- `docs/nonshallow_batch_1_audit.md`
- `docs/decisions/0013-nonshallow-batch-1-integrity-result.md`
- `data/manifests/nonshallow_batch_2_download_receipt.json`
- `data/manifests/nonshallow_batch_2_window_quality.csv`
- `data/manifests/nonshallow_batch_2_request_quality.csv`
- `results/predictions/nonshallow_batch_2_quality_summary.json`
- `results/figures/nonshallow_batch_2_quality_overview.png`
- `docs/nonshallow_batch_2_audit.md`
- `docs/decisions/0014-nonshallow-batch-2-integrity-result.md`
- `data/manifests/nonshallow_batch_{3,4}_download_receipt.json`
- `data/manifests/nonshallow_batch_{3,4}_window_quality.csv`
- `data/manifests/nonshallow_batch_{3,4}_request_quality.csv`
- `results/predictions/nonshallow_batch_{3,4}_quality_summary.json`
- `results/figures/nonshallow_batch_{3,4}_quality_overview.png`
- `scripts/audit_all_nonshallow.py`
- `results/predictions/nonshallow_all_batches_audit.json`
- `scripts/build_dataset_splits.py`
- `data/manifests/positive_split_assignments.csv`
- `scripts/build_background_manifest.py`
- `data/manifests/background_window_candidates.csv`
- `scripts/build_preprocessing_manifest.py`
- `data/manifests/preprocessing_positive_windows.csv`
- `configs/data/preprocessing_v0.1.yaml`
- `scripts/run_pilot_baselines.py`
- `results/predictions/pilot_baselines_v0.1.json`
- `results/figures/pilot_baselines_v0.1.png`
- `scripts/audit_pilot_dataset.py`
- `results/predictions/pilot_dataset_audit.json`
- `docs/nonshallow_all_batches_audit.md`
- `docs/pilot_dataset_and_baselines_v0.1.md`
- `docs/research_protocol_v0.2.md`
- `docs/decisions/0015-all-batch-att-integrity-policy.md`
- `docs/decisions/0016-pilot-splits-background-and-training-gate.md`

Exact additional files changed for the all-batch/split/baseline task: `configs/data/pilot.yaml`, `configs/data/preprocessing_v0.1.yaml`, `configs/experiment/leave_one_station_out.yaml`, `data/manifests/background_window_candidates.csv`, `data/manifests/nonshallow_batch_3_download_receipt.json`, `data/manifests/nonshallow_batch_3_request_quality.csv`, `data/manifests/nonshallow_batch_3_window_quality.csv`, `data/manifests/nonshallow_batch_4_download_receipt.json`, `data/manifests/nonshallow_batch_4_request_quality.csv`, `data/manifests/nonshallow_batch_4_window_quality.csv`, `data/manifests/positive_split_assignments.csv`, `data/manifests/preprocessing_positive_windows.csv`, `data/manifests/unified_positive_event_audit.json`, `data/manifests/unified_positive_events.csv`, `docs/CURRENT_STATUS.md`, `docs/DECISIONS.md`, `docs/ROADMAP.md`, `docs/data_dictionary.md`, `docs/unified_positive_manifest_audit.md`, `docs/nonshallow_all_batches_audit.md`, `docs/pilot_dataset_and_baselines_v0.1.md`, `docs/research_protocol_v0.2.md`, `docs/decisions/0015-all-batch-att-integrity-policy.md`, `docs/decisions/0016-pilot-splits-background-and-training-gate.md`, `results/figures/nonshallow_batch_3_quality_overview.png`, `results/figures/nonshallow_batch_4_quality_overview.png`, `results/figures/pilot_baselines_v0.1.png`, `results/predictions/nonshallow_all_batches_audit.json`, `results/predictions/nonshallow_batch_3_quality_summary.json`, `results/predictions/nonshallow_batch_4_quality_summary.json`, `results/predictions/pilot_baselines_v0.1.json`, `results/predictions/pilot_dataset_audit.json`, `scripts/audit_all_nonshallow.py`, `scripts/audit_pilot_dataset.py`, `scripts/build_background_manifest.py`, `scripts/build_dataset_splits.py`, `scripts/build_preprocessing_manifest.py`, `scripts/build_unified_positive_manifest.py`, `scripts/run_pilot_baselines.py`, `tests/test_audit_all_nonshallow.py`, `tests/test_build_background_manifest.py`, `tests/test_build_dataset_splits.py`, `tests/test_build_preprocessing_manifest.py`, and `tests/test_run_pilot_baselines.py`.

Exact files changed for independent-background v0.1: `configs/data/pilot.yaml`, `configs/experiment/leave_one_station_out.yaml`, `data/manifests/independent_background_station_days.csv`, `data/manifests/independent_background_download_plan.json`, `data/manifests/independent_background_batch_1_download_receipt.json`, `data/manifests/independent_background_day_quality.csv`, `data/manifests/independent_background_windows.csv`, `docs/CURRENT_STATUS.md`, `docs/DECISIONS.md`, `docs/ROADMAP.md`, `docs/data_dictionary.md`, `docs/research_protocol_v0.2.md`, `docs/independent_background_v0.1_audit.md`, `docs/decisions/0017-independent-background-and-pilot-training-gate.md`, `results/figures/independent_background_baselines_v0.1.png`, `results/predictions/independent_background_audit.json`, `results/predictions/independent_background_baselines_v0.1.json`, `scripts/audit_independent_background.py`, `scripts/build_independent_background_plan.py`, `scripts/download_nonshallow_batch.py`, `scripts/run_pilot_baselines.py`, `tests/test_audit_independent_background.py`, and `tests/test_build_independent_background_plan.py`.

Exact files changed for tiny-CNN pilot v0.1: `.gitignore`, `configs/model/tiny_cnn_v0.1.yaml`, `configs/evaluation/continuous_scanning_v0.1.yaml`, `docs/CURRENT_STATUS.md`, `docs/DECISIONS.md`, `docs/ROADMAP.md`, `docs/data_dictionary.md`, `docs/tiny_cnn_pilot_v0.1.md`, `docs/decisions/0018-tiny-cnn-pilot-and-scanning-freeze.md`, `models/checkpoints/tiny_cnn_pilot_v0.1/*`, `requirements-lock.txt`, `results/figures/tiny_cnn_512bin_failed_ablation.png`, `results/figures/tiny_cnn_pilot_v0.1.png`, `results/predictions/tiny_cnn_512bin_failed_ablation.json`, `results/predictions/tiny_cnn_512bin_failed_ablation/*`, `results/predictions/tiny_cnn_pilot_v0.1.json`, `results/predictions/tiny_cnn_pilot_v0.1/*`, `results/predictions/tiny_cnn_shortcut_audit_v0.1.json`, `scripts/audit_tiny_cnn_shortcuts.py`, `scripts/run_tiny_cnn_pilot.py`, `tests/test_audit_tiny_cnn_shortcuts.py`, and `tests/test_run_tiny_cnn_pilot.py`.

Exact files changed for untouched contiguous evaluation planning: `configs/evaluation/continuous_scanning_v0.1.yaml`, `data/manifests/contiguous_evaluation_station_days.csv`, `data/manifests/contiguous_evaluation_download_plan.json`, `data/manifests/contiguous_evaluation_catalog_audit.csv`, `docs/CURRENT_STATUS.md`, `docs/DECISIONS.md`, `docs/ROADMAP.md`, `docs/data_dictionary.md`, `docs/contiguous_evaluation_plan_v0.1.md`, `docs/decisions/0019-untouched-contiguous-frame-plan.md`, `results/predictions/contiguous_evaluation_plan_audit.json`, `scripts/audit_contiguous_evaluation_plan.py`, `scripts/build_contiguous_evaluation_plan.py`, `tests/test_audit_contiguous_evaluation_plan.py`, and `tests/test_build_contiguous_evaluation_plan.py`.

Exact files changed for contiguous-frame download and integrity QA: `configs/evaluation/continuous_scanning_v0.1.yaml`, `data/manifests/contiguous_evaluation_download_receipt.json`, `data/manifests/contiguous_evaluation_day_quality.csv`, `data/manifests/contiguous_evaluation_eligible_event_quality.csv`, `docs/CURRENT_STATUS.md`, `docs/DECISIONS.md`, `docs/ROADMAP.md`, `docs/data_dictionary.md`, `docs/contiguous_evaluation_integrity_v0.1.md`, `docs/decisions/0020-contiguous-integrity-and-scan-frame.md`, `results/figures/contiguous_evaluation_eligible_events.png`, `results/predictions/contiguous_evaluation_integrity_summary.json`, `scripts/audit_contiguous_evaluation_data.py`, `scripts/download_contiguous_evaluation.py`, `tests/test_audit_contiguous_evaluation_data.py`, and `tests/test_download_contiguous_evaluation.py`. Raw products remain ignored.

Exact files changed for continuous scanning v0.1: `configs/evaluation/continuous_scanning_v0.1.yaml`, `docs/CURRENT_STATUS.md`, `docs/DECISIONS.md`, `docs/ROADMAP.md`, `docs/data_dictionary.md`, `docs/continuous_scanning_result_v0.1.md`, `docs/decisions/0021-continuous-scan-negative-result.md`, `results/figures/continuous_scanning_results_v0.1.png`, `results/figures/continuous_scanning_top_false_triggers_v0.1.png`, `results/predictions/continuous_scanning_thresholds_v0.1.json`, `results/predictions/continuous_scanning_window_scores_v0.1.csv.gz`, `results/predictions/continuous_scanning_triggers_v0.1.csv`, `results/predictions/continuous_scanning_results_v0.1.json`, `results/predictions/continuous_scanning_error_audit_v0.1.json`, `scripts/run_contiguous_scanning_v0_1.py`, `scripts/audit_continuous_scanning_errors.py`, `tests/test_run_contiguous_scanning_v0_1.py`, and `tests/test_audit_continuous_scanning_errors.py`.

Exact files changed for artifact-robust development and test v0.2: `configs/model/artifact_robust_cnn_v0.1.yaml`, `configs/evaluation/continuous_scanning_v0.2.yaml`, `data/manifests/continuous_validation_*_v0.1.*`, `data/manifests/contiguous_evaluation_*_v0.2.*`, `models/checkpoints/artifact_robust_v0.1/*.pt`, `results/predictions/continuous_validation_audit_v0.1.json`, `results/predictions/artifact_robust_model_selection_v0.1.json`, `results/predictions/contiguous_evaluation_*_v0.2.json`, `results/predictions/continuous_scanning_*_v0.2.*`, `results/figures/continuous_validation_shift_v0.1.png`, `results/figures/contiguous_evaluation_eligible_events_v0.2.png`, `results/figures/continuous_scanning_results_v0.2.png`, `scripts/build_contiguous_evaluation_plan.py`, `scripts/audit_contiguous_evaluation_plan.py`, `scripts/audit_contiguous_evaluation_data.py`, `scripts/audit_continuous_validation.py`, `scripts/train_artifact_robust_models.py`, `scripts/run_contiguous_scanning_v0_2.py`, `docs/artifact_robust_continuous_validation_and_v0.2.md`, `docs/decisions/0022-artifact-robust-development-selection.md`, `docs/decisions/0023-continuous-scan-v0.2-negative-result.md`, and permanent context documents. Raw NASA products remain ignored.

Exact files changed for the release-prototype cycle: `.github/workflows/tests.yml`, `.gitignore`, `AUTHORS.md`, `CONTRIBUTING.md`, `README.md`, `LICENSE`, `CITATION.cff`, `pyproject.toml`, `configs/model/depthwise_cnn_v0.1.yaml`, `lunaseis/__init__.py`, `lunaseis/model.py`, `lunaseis/inference.py`, `lunaseis/cli.py`, `scripts/audit_missed_continuous_events.py`, `scripts/train_compact_model_suite.py`, `scripts/predict_lunaseis.py`, `models/checkpoints/compact_model_suite_v0.1/*`, `results/predictions/missed_continuous_event_audit.json`, `results/predictions/compact_model_suite_v0.1.json`, `docs/MODEL_CARD.md`, `docs/DATASET_CARD.md`, `docs/REPRODUCIBILITY.md`, `docs/RELEASE_CHECKLIST.md`, `docs/decisions/0024-release-prototype-not-operational-claim.md`, `docs/decisions/0025-depthwise-release-prototype.md`, `paper/manuscript.md`, `paper/tables/continuous_tests.csv`, `paper/tables/development_models.csv`, `paper/tables/event_inventory.csv`, `output/jupyter-notebook/lunaseis_inference_colab.ipynb`, `tests/test_lunaseis_inference.py`, and permanent context documents.

Exact files changed for the release-claims freeze: `README.md`, `paper/manuscript.md`, `literature/state_of_the_field.md`, `docs/RELEASE_CLAIMS.md`, `docs/RELEASE_CHECKLIST.md`, `docs/data_dictionary.md`, `docs/DECISIONS.md`, `docs/decisions/0026-release-claims-boundary.md`, and `docs/CURRENT_STATUS.md`.

Exact files changed for the user-reported portability checkpoint: `docs/RELEASE_CHECKLIST.md` and `docs/CURRENT_STATUS.md`.

Exact files changed for public authorship normalization: `AGENTS.md`, `AUTHORS.md`, `docs/PROJECT_CONTEXT.md`, `docs/RELEASE_CHECKLIST.md`, and `docs/CURRENT_STATUS.md`.

Exact files changed for the Grade-C challenge freeze: `scripts/build_grade_c_challenge_plan.py`, `tests/test_build_grade_c_challenge_plan.py`, `data/manifests/grade_c_challenge_station_days.csv`, `data/manifests/grade_c_challenge_catalog.csv`, `data/manifests/grade_c_challenge_download_plan.json`, `configs/evaluation/grade_c_challenge_v0.3.yaml`, `docs/DECISIONS.md`, `docs/decisions/0027-grade-c-confirmatory-challenge-freeze.md`, and `docs/CURRENT_STATUS.md`.

Exact files changed for pre-inference Grade-C integrity and context QA: `scripts/build_grade_c_catalog_context.py`, `scripts/run_grade_c_challenge.py`, `data/manifests/grade_c_challenge_1_download_receipt.json`, `data/manifests/grade_c_challenge_day_quality.csv`, `data/manifests/grade_c_challenge_event_quality.csv`, `data/manifests/grade_c_challenge_catalog_context.csv`, `results/predictions/grade_c_challenge_integrity_summary.json`, `results/predictions/grade_c_challenge_catalog_context.json`, `results/figures/grade_c_challenge_event_windows.png`, `configs/evaluation/grade_c_challenge_v0.3.yaml`, `docs/decisions/0027-grade-c-confirmatory-challenge-freeze.md`, and `docs/CURRENT_STATUS.md`. Raw products remain ignored.

Exact files changed for the consumed Grade-C result and publication package: `results/predictions/grade_c_challenge_window_scores.csv.gz`, `results/predictions/grade_c_challenge_triggers.csv`, `results/predictions/grade_c_challenge_results.json`, `configs/evaluation/grade_c_challenge_v0.3.yaml`, `docs/DECISIONS.md`, `docs/decisions/0028-grade-c-challenge-negative-result.md`, `docs/RELEASE_CLAIMS.md`, `docs/DATASET_CARD.md`, `docs/MODEL_CARD.md`, `docs/COPYRIGHT_AND_RELEASE_GUIDE.md`, `docs/RELEASE_CHECKLIST.md`, `docs/ROADMAP.md`, `docs/data_dictionary.md`, `COPYRIGHT.md`, `README.md`, `paper/manuscript.md`, `paper/tables/continuous_tests.csv`, `paper/figures/*`, `scripts/build_paper_figures.py`, `scripts/build_manuscript_pdf.py`, `output/pdf/lunaseis_1_manuscript_preprint.pdf`, `release/SHA256SUMS`, and `docs/CURRENT_STATUS.md`.

## Commands and verification

- Ran the committed depthwise model and frozen station thresholds exactly once over all 89,159 integrity-qualified Grade-C windows. At ±180 seconds it recovered 12/63 physical events, produced 1,306 false triggers over 1,505.35 hours, and retained 75.38% of duration; the frame is consumed and prohibited from retuning.
- Generated four consistent paper figures in vector PDF and 300-DPI PNG, visually reviewed all four, corrected label collisions, and regenerated them from committed result evidence.
- Rendered the manuscript as an A4 preprint PDF with author metadata, page numbers, figures, captions, references, and copyright notice; rendered every page to PNG and visually checked the complete document for clipping, overlap, and legibility.
- Reviewed official Copyright Office of India, GitHub licensing, and WIPO guidance; separated code, paper/figure, checkpoint, NASA-data, and third-party rights and recorded the DOI/tag/registration provenance strategy without promising that copyright can prevent all plagiarism.
- Ran all 57 unit tests, compiled public package/scripts/tests, parsed all YAML plus `CITATION.cff`, verified Grade-C plan/result/table/checkpoint hashes and headline invariants, checked the PDF metadata, and ran `git diff --check`; all passed.

- Downloaded and exact-size/NASA-MD5 verified all 256 Grade-C challenge products (97,596,992 bytes). Audited 64 event-station observations representing 63 physical impacts without loading the model; all event windows passed integrity, providing 1,505.35 scannable station-hours. Froze 102 additional catalog references as protected context before inference.

- Built the Grade-C challenge plan from the decoded PDS catalog and official PDS day listings without loading waveforms or model scores. Fixed 64 unique, previously unexposed station-days (16 per station), confirmed zero overlap with 3,426 prior station-days, and attached official MD5 values to all 256 planned products totaling 97,596,992 bytes.

- Audited tracked text for tool-brand, automated-assistance, and shared-authorship wording; normalized repository context headings/instructions, changed the review checklist to independent scientific review, and confirmed public metadata consistently names Advaith Praveen (APRK) as the sole project author. Scientific source citations remain intact.

- Recorded the user's 2026-07-14 report that Linux reproduction and the Google Colab notebook succeeded. No distribution, package-version transcript, Colab output artifact, or independent rerun was provided, so the permanent record preserves that evidence boundary.

- Rechecked the direct Apollo ML predecessors from their publisher/DOI records: Knapmeyer-Endrun and Hammer (2015), Civilini et al. (2021), Onodera (2024), and Al-Qadasi and Bin Waheed (2026). Froze supported/prohibited public wording in `docs/RELEASE_CLAIMS.md` and added manuscript references without making an absolute novelty claim.
- Reran all 56 unit tests, compiled `lunaseis`, scripts, and tests, parsed every YAML config plus `CITATION.cff` with the system Ruby YAML parser, and ran `git diff --check`; all passed. The project virtual environment does not include the optional PyYAML module, so the equivalent Python YAML check was not used.

- Generalized contiguous selection/audit scripts to named frames, then asserted that validation and test v0.2 have zero overlap with every earlier manifest.
- Ran checksum-gated downloads for all 224 validation and 448 test-v0.2 products; exact byte totals reconciled to 84,837,751 and 171,072,240.
- Ran continuous validation QA, both four-fold robust candidate training/selection passes, test-v0.2 day/event QA, and the frozen four-method operational comparison.
- Visually inspected the station-shift, eligible-event, and final v0.2 comparison figures; verified primary trigger accounting, duration denominators, retention bounds, file hashes, and the three-event numerator.
- Re-ran both checksum downloaders in disk-only mode (224/224 and 448/448 reused and reverified), ran all 53 tests, script compilation, YAML parsing, exact dependency-lock set comparison, cross-frame disjointness, result/hash invariants, and `git diff --check`; all passed.
- Ran post-test missed-event timing diagnostics, eight depthwise/TCN development trainings, candidate selection invariants, public API/CLI full-day inference, and executed every notebook code cell top-to-bottom locally.
- Installed the project editable, validated the `lunaseis-predict` console entry point, parsed citation/configuration metadata, verified selected checkpoint hashes/table counts, and ran the full 56-test suite successfully.
- Reconstructed validation-only thresholds, ran all three methods over 152,986 untouched windows, generated compressed per-window predictions, merged triggers, matched catalogs at three frozen tolerances, computed retention, and ran post-result error analysis without retuning.
- Repeated the complete scanner after deterministic-gzip hardening and confirmed byte-identical prediction, trigger, and threshold hashes; ran the full 50-test regression suite, compilation, YAML parsing, dependency-lock set comparison, artifact/count/rate/hash invariants, and `git diff --check` successfully.
- Visually inspected the continuous-result figure and nine highest-scoring false-trigger waveforms; independently verified score/trigger counts, hashes, false-rate denominators, eligible-event numerators, station totals, sensitivity monotonicity, and retention bounds.
- Ran the checksum-gated contiguous downloader twice, with the second run reusing and revalidating all 448 files; loaded/audited all 112 ATT/MH pairs; enumerated 160,272 frozen scan windows; computed local gap gates and merged union duration; audited and plotted seven eligible event windows without model inference.
- Visually inspected the full-resolution seven-event raw-MH figure, reviewed the rejected candidate metrics, and independently asserted receipt, day, window, duration, event, and hash totals.
- Ran the fixed-seed archive-block selector, inspected 112 official PDS day listings, resolved actual MiniSEED location codes from listings, attached official MD5s, reran selection for reproducibility, and ran the post-selection catalog/exposure audit without model scores.
- Verified exact product/byte/day/station/block totals, zero prior overlap, 112/112 channel completeness, manifest hashes, seven strict untouched candidate IDs, 52 GiB free storage, YAML parsing, script compilation, full regression tests, and `git diff --check`.
- Installed PyTorch into `.venv`, regenerated the exact dependency lock, ran the 512-bin failed ablation and native-cadence pilot twice deterministically, ran shortcut counterfactual inference, inspected score distributions and learning curves, measured efficiency, and visually inspected the final comparison figure.
- Ran model-specific unit tests, script compilation, full regression tests, YAML parsing, artifact/hash/count/metric invariants, deterministic rerun comparison, and `git diff --check`.
- Ran script compilation, the full 33-test regression suite, independent selection/receipt/day-gap/event-buffer/baseline invariants, YAML parsing, and `git diff --check`; all passed.
- Built the independent plan from official archive directory discovery, ran the resumable downloader and disk-only reconciliation, audited 928 selected days, constructed event-buffered windows, reran all three baselines, and visually inspected the independent comparison figure.
- Ran script compilation, the full 31-test regression suite, dataset-manifest hash/leakage audit, registry/receipt/label invariants, YAML parsing, and `git diff --check`; all passed.
- Ran script compilation, the full 26-test regression suite, Ruby YAML parsing, `git diff --check`, and explicit Batch 2 receipt/QA/registry invariants; all passed. An initial optional Python `yaml` import was unavailable, so YAML validation was rerun successfully with the system Ruby parser.
- Ran script compilation, YAML parsing, the full 25-test suite, `git diff --check`, and explicit Batch 1 receipt/QA/registry invariants, including checks that every physical label and evaluation group remained unchanged; all passed.

- Inspected with `ls -la`, `find`, `rg --files`, and `git status`.
- Compared the permanent context against the supplied handoff byte-for-byte before commit.
- Reviewed repository status and required files before commit.
- Queried official NASA PDS pages and inspected both official PDS4 bundle XML labels and READMEs.
- Inspected the official catalog and waveform collection directory listings without downloading the archive.
- Ran `python3 scripts/download_catalog.py`; all 32 product checksums passed.
- Ran `python3 -m unittest discover -s tests -p 'test_download_catalog.py' -v`; 2 tests passed.
- Ran `python3 scripts/audit_catalog.py`; audited 11 CSV files and wrote the schema manifest.
- Converted Julian day 210 of 1971 independently to 1971-07-29 for the candidate record.
- Inspected official S12/S14 day directories, StationXML, PDS MD5 manifest, and the 41-page 2022 Software Interface Specification.
- Checksum-verified the locally cached StationXML, its PDS label, and the specification PDF.
- Recomputed the planned product total from every listed file size: 7,924,909 bytes.
- Ran five downloader/parser unit tests successfully.
- Reran the pilot downloader after download to verify idempotent integrity checks.
- Ran `scripts/audit_pilot_waveforms.py` with pinned Python dependencies and inspected its JSON output.
- Visually inspected the full-resolution plot for signal visibility, correct channel labeling, markers, gaps, and disclosure of absent preprocessing.
- Queried official NASA Science Data License, PDS citation, NASA science-information, and NASA media/brand guidance.
- Parsed field descriptions directly from the PDS4 `levent.1008weber.xml` label.
- Ran `scripts/audit_event_labels.py` across all 13,057 rows and independently checked headline counts/family sizes.
- Searched NASA/PDS/NTRS, publisher, DOI, and institutional sources with documented queries; extracted the initial literature matrix.
- Added and ran catalog-time conversion tests, including invalid-HHMM rejection.
- Ran `.venv/bin/python scripts/reconcile_shallow_catalog.py`; verified 74 rows, 28 exact PDS shallow matches, 46 new same-minute absences, and the generated CSV SHA-256.
- Ran `.venv/bin/python scripts/build_shallow_download_plan.py`; queried official PDS day listings and MD5 manifest and generated the 508-product plan.
- Independently asserted event coverage, product/path uniqueness, exact byte sum, MD5 shape, and event-manifest SHA-256.
- Ran `.venv/bin/python -m unittest discover -s tests -p 'test_*.py' -v`; all 10 tests passed.
- Ran `git diff --check`; passed. Removed temporary PDF/download directories after source inspection.
- Ran `.venv/bin/python scripts/download_shallow_sample.py`; four products and 7,391,202 bytes passed exact size and official MD5 checks.
- Ran `.venv/bin/python scripts/audit_shallow_sample.py`; generated the timing/gap audit and raw plot, then visually inspected the full-resolution figure.
- Independently measured gap-run structure: 3,975 isolated one-sample sentinels in an exact ten-minute slice; no continuous outage.
- Reran `.venv/bin/python -m unittest discover -s tests -p 'test_*.py' -v`; all 11 tests passed, and the sample downloader was idempotently re-verified.
- Ran `.venv/bin/python scripts/download_shallow_plan.py --workers 4`; verified 508/508 products and exact total bytes, reusing four prior KO-SMQ-26 products.
- Ran `.venv/bin/python scripts/audit_shallow_windows.py`; generated 128 row-level QA records, aggregate JSON, and a visually reviewed overview figure.
- Corrected an over-strict initial ATT-gap rule before freezing results: timing quality now uses nearest valid ATT displacement while retaining ATT gap counts as metadata.
- Ran `.venv/bin/python -m compileall -q scripts` and the complete unit-test suite; all 14 tests passed. Independently asserted download totals, row counts, status counts, and one usable station for every event.
- Ran `.venv/bin/python scripts/build_unified_positive_manifest.py`; generated 1,314 candidate rows and the machine-readable source/QA/leakage/conflict audit.
- Verified 1,240 PDS nonshallow plus 74 corrected shallow candidates, 28 exact source merges, 46 KO additions, 824 evaluation groups, and a clean overlap/conflict result.
- Ran the full regression suite (17 tests), script compilation, YAML parsing, `git diff --check`, manifest SHA-256 verification, and explicit invariants for all eight requested gates; all passed.
- Ran `.venv/bin/python scripts/build_nonshallow_download_plan.py --workers 8`; inspected and cached 2,496 official PDS station-day listings, fetched the official MD5 manifest, and generated request/product plans.
- Corrected and retested MiniSEED location-code handling (`00` for MH, blank for ATT/SHZ) and channel-summary parsing before accepting results.
- Verified exact product/byte/channel/batch totals, 81 missing events, boundary-day coverage, and request CSV SHA-256; no bulk download occurred.
- Ran script compilation, YAML parsing, the full 20-test regression suite, `git diff --check`, and independent product/path/MD5/byte/batch/station-day invariants; all passed.
- Ran `scripts/download_nonshallow_batch.py --batch-id 1` resumably; the final reconciliation verified 5,398/5,398 products and exact total bytes.
- Ran `scripts/audit_nonshallow_batch.py --batch-id 1`; generated channel/request CSVs, aggregate JSON, and a visually inspected overview figure.
- Reviewed the two questionable and eight rejected events individually from row-level metrics; rejection evidence is severe waveform loss and/or ATT displacement, not amplitude.
- Rebuilt `unified_positive_events.csv` and its SHA-256 audit with Batch 1 outcomes attached.
- Ran `scripts/download_nonshallow_batch.py --batch-id 2 --workers 4`; verified 3,270/3,270 products and the exact planned total, then reran it with all products reused and re-verified from disk.
- Ran `scripts/audit_nonshallow_batch.py --batch-id 2`; generated 1,337 channel rows, 599 request rows, aggregate JSON, and an overview figure.
- Reviewed all three questionable and ten rejected Batch 2 requests from row-level gap and ATT evidence and visually inspected the full-resolution aggregate figure.
- Rebuilt the unified registry from all existing batch QA files; explicitly compared it with the committed registry and confirmed identical event IDs, physical labels, and evaluation groups.
- Ran and idempotently reran `download_nonshallow_batch.py` for Batches 3 and 4; every planned byte and NASA MD5 passed.
- Ran `audit_nonshallow_batch.py` for Batches 3 and 4 and visually inspected both full-resolution QA figures.
- Reviewed all non-usable Batch 3/4 request/channel records from their raw gap and ATT measurements.
- Ran `audit_all_nonshallow.py`, `build_dataset_splits.py`, `build_background_manifest.py`, and `build_preprocessing_manifest.py`; checked aggregate counts and group-role isolation.
- Ran `run_pilot_baselines.py` across all four folds and visually inspected the baseline comparison figure.

## Decisions

- The supplied handoff is the canonical stable project context.
- Work begins at Phase 0; modelling remains prohibited until event-to-waveform alignment is verified.
- Treat the PDS event catalog as multiple source tables requiring semantic reconciliation, not an immediately usable flat label file.
- Product metadata, not only instrument-level documentation, will determine actual processing sample rates.
- Use a known artificial impact with two published station arrivals for the first alignment test; this is a feasibility choice, not a final taxonomy choice.
- Use MiniSEED with StationXML and PDS labels for the pilot; include ATT and preserve explicit gaps.
- Treat nominal and ATT-derived timestamps as separate provenance fields; no silent global timing shift.
- Publish code, manifests, aggregate analyses, and models with PDS citations; do not mirror raw archives or catalog-derived labeled datasets before release review/PDS clarification.
- Keep binary detection primary; broad multiclass is unsupported by the initial conservative PDS-only counts.
- Treat physical event and deep-family ID as indivisible split groups, including across stations in LOSO evaluation.
- Use only the 2026-corrected Onodera tables for the 74-event shallow audit; preserve attribution and CC BY-NC constraints.
- Do not promote shallow classification to a headline task; require window QA and group KO-SMQ-26/KO-SMQ-40 together.
- Represent each physical candidate once; merge corrected legacy shallow identities with PDS and never conflate positive visibility with audited waveform integrity.
- Use only positive channels plus ATT for first-pass nonshallow QA, include required midnight boundary days, and download in four bounded station-day batches if authorized.
- Accept the 648 Batch 1 events passing gap/ATT integrity, preserve two as questionable, exclude eight from usable windows, and keep RMS/extreme-value metrics descriptive.
- Attach Batch 2 station-level outcomes using the same integrity rules; aggregate physical-event usability across audited stations while preserving rejected requests and keeping amplitude metrics descriptive.
- Freeze nearest-valid ATT mapping plus primary and sensitivity integrity thresholds without claiming catalog phase-pick semantics are resolved.
- Freeze group-disjoint LOSO pilot splits and primary MH preprocessing; block neural training on the coverage-selected background frame.
- Adopt independent-background v0.1, retire positive-conditioned metrics from decisions, and permit only pilot neural training while final claims remain blocked.
- Retain the tiny-CNN pilot as mixed/negative evidence, preserve the failed averaging ablation, and freeze continuous-scanning v0.1 before selecting the untouched contiguous evaluation frame.
- Accept the fixed 112-day frame without replacement, authorize only its checksum-gated 163.4 MiB download, and keep model scoring blocked until full-day integrity QA.
- Freeze 152,986 local-gap-qualified windows and 2,591.47 union hours; exclude one severe-gap event and authorize continuous inference for six integrity-eligible events.
- Accept continuous scan v0.1 as a negative result, reject H1 for this pilot, and prohibit tuning thresholds/models against the consumed untouched frame.
- Select robust-level preprocessing on unconsumed training-station continuous validation and freeze it before test v0.2.
- Preserve test v0.2 as a second negative result; consume it permanently and treat H1/H6 as unsupported under the tested protocol.
- Continue as a transparent research-prototype release authored by Advaith Praveen (APRK), not an operational/flight-ready detector claim.
- Select the 2,761-parameter depthwise CNN for the public interface while preserving its persistent-activation limitation.

## Unresolved uncertainties

- Exact scalable ATT correction/interpolation policy and catalog-pick time-basis reconciliation remain unresolved.
- The corrected Onodera catalog has integrity-audited windows, but independent confidence in the 46 KO detections remains unresolved.
- Written PDS clarification is still required before publishing catalog CSVs or catalog-derived labeled windows.
- The candidate event's time standard and precise relationship to waveform/timing-trace time remain unresolved.
- Waveform reuse has an operational CC0 basis; catalog and catalog-derived dataset licensing still requires written PDS clarification before republication.
- Full environment portability beyond the tested Apple Silicon Python 3.12 setup remains to be verified later in Colab/Linux.
- No standalone author-deposited Onodera catalog file/checksum was found; the local manifest is a transparent transcription of corrected article tables, not an official machine-readable release.
- Automated integrity QA now covers all 74 events, but morphology/artifact review beyond aggregate metrics remains incomplete.
- The 20%/50% SHZ-gap and 1 s/10 s ATT thresholds are provisional engineering gates requiring sensitivity analysis before protocol freeze.
- Fifteen intact windows lack a clear raw RMS increase and two are unquantifiable; they require review without label demotion or cherry-picking.
- Seven corrected legacy shallow events retain PDS grade C and three are ungraded; their inclusion comes from Onodera provenance and must be handled explicitly in sensitivity analyses.
- The 81 nonshallow candidates without an archive-backed positive request may reflect deployment/archive/visibility inconsistencies and require source-specific review before any permanent exclusion claim.
- Batch 1 extreme-value occupancy flags possible constant/saturated/quantized windows but lacks a frozen physical clipping rule; it cannot yet drive exclusion.
- The 81 nonshallow candidates without complete archive-backed requests remain unavailable and require source-specific review.
- The catalog start-time physical meaning and absolute time standard remain unresolved even though computational ATT mapping is frozen.
- Independent windows are sampled ten-minute segments rather than fully contiguous trigger evaluation; FP h⁻¹ remains diagnostic.
- The background-frame sensitivity across S12/S15/S16 requires station-specific error and acquisition-artifact analysis during neural development.
- Tiny-CNN cross-station behavior is unstable; S12 improvement does not generalize to S14–S16.
- S14 CNN score has a 0.500 correlation with waveform RMS in the pilot test subset and needs amplitude/acquisition sensitivity analysis.
- Local CPU latency and memory measurements are Apple-Silicon microbenchmarks, not portable deployment measurements.
- The consumed continuous frame had only seven prospectively eligible candidates before waveform QA and six afterward, so its event recall is high-uncertainty and cannot be a stable headline estimate.
- Only six untouched catalog events pass integrity, and five lack a clear raw RMS increase; event recall will be high-uncertainty and descriptive.
- Full-day status uses a 10% sensitivity boundary while the primary per-window exclusion remains the established 20% gap gate.
- Validation-derived thresholds show severe station/date distribution shift; persistent positive runs make trigger rate alone misleading.
- The single CNN/logistic matched event may be coincidental given the false-trigger burden.
- Top false triggers contain strong acquisition/instrument artifacts, but their physical causes have not been authoritatively classified.
- Continuous frame v0.1 is consumed and cannot serve as an untouched test after model changes.
- Artifact proxies expose severe station differences but do not establish the physical cause of plateaus, steps, or extreme values.
- Test v0.2 contains only three eligible events, so 0/3 recall is highly uncertain even though the false-trigger exposure is long.
- Robust preprocessing improves the CNN relative to its original version but still fails to beat logistic regression operationally.
- All three continuous frames are consumed; additional detector optimization would require a new preregistered design and new untouched data.
- The depthwise model improves development trigger rate but failed to transfer to the prospectively frozen Grade-C challenge and persistently activates on the documented S15 smoke day.
- GitHub account/repository URL, Hugging Face location, and Zenodo DOI are intentionally unset until the user explicitly authorizes publication.

## Exact next task

Obtain independent scientific review of the manuscript and repository, then resolve the author's GitHub/Hugging Face account URLs and publication authorization for the final tagged/DOI release.
