## [2026-04-19 03:46 UTC] [who: Codex] [NIGHTSHIFT2 START]
- Started Nightshift2 under `NIGHTSHIFT2_PROTOCOL.md`.
- Priority order accepted: Round 1 F5 frame shuffle -> Round 2 F3 CKA -> Round 3 F4-A split-by-value.

## [2026-04-19 03:46 UTC] [who: Codex] [startup audit]
- Push token cache present: `1500` safetensors at `/mnt/md1/solee/features/physprobe_vitl_tokenpatch/push`
- Strike token cache present: `2895` valid safetensors at `/mnt/md1/solee/features/physprobe_vitl_tokenpatch/strike`
- Disk state: `/mnt/md1/solee` at `95%` usage with `199G` free
- GPU state at audit: GPUs `0-3` idle
- Reach cache already absent, so protocol's "delete Reach first if storage >95%" fallback is already effectively satisfied.

## [2026-04-19 03:47 UTC] [who: Codex] [Round 1 Step 1.1 design]
- Wrote `F5_design.md`.
- Design includes deterministic shuffle (`seed=42`), window-level permutation, PEZ-style probe parity, sanity checks, interpretation thresholds, and storage mitigation plan.
- Open review questions for Claude were embedded in the design doc.

## [2026-04-19 03:48 UTC] [who: Codex] [storage discussion]
- Main risk for Round 1 is storage, not compute.
- Existing raw caches plus full shuffled caches cannot coexist on `/mnt/md1/solee`.
- Planned workaround: preserve scientific baseline via committed Phase 2d probe results, recycle raw caches sequentially for shuffled extraction, and keep only final verdict artifacts.

## [2026-04-19 03:55 UTC] [who: Claude] [review escalation]
- Reviewer-quality concern raised: single-seed shuffle is not enough for a NeurIPS-quality claim.
- Required upgrades:
  - at least 3 shuffle seeds
  - paired statistical comparison plan
  - explicit reviewer-attack framing
  - effect-size reporting, not just raw curve overlays

## [2026-04-19 03:56 UTC] [who: Codex] [[NEURIPS MODE]]
- Accepted the stricter objective: paper-quality evidence over simple ablation execution.
- Upgraded `NIGHTSHIFT2_PROTOCOL.md` and `F5_design.md` to require:
  - seeds `42`, `123`, `2024`
  - paired/effect-size analysis plan
  - explicit reviewer attack model
  - counter-experiment interpretation rules

## [2026-04-19 04:10 UTC] [who: Claude] [oral escalation]
- Review standard escalated from paper-quality to oral-quality.
- Required additions:
  - mechanism-level claim framing
  - killer evidence chain
  - counter-evidence scenarios
  - Round 4 random-init null baseline after Round 1

## [2026-04-19 04:11 UTC] [who: Codex] [[ORAL MODE CONFIRMED]]
- Upgraded `NIGHTSHIFT2_PROTOCOL.md` and `F5_design.md` again.
- Round 1 now explicitly targets a causal-temporal claim, not just an ablation delta.
- Added oral-mode threshold interpretation:
  - `>= 30%` degradation => strong temporal evidence
  - `<= 10%` degradation => static/framewise evidence
  - `15-25%` degradation => mixed mechanism
- Added Round 4 placeholder: random-init V-JEPA 2 null baseline.

## [2026-04-19 04:01 UTC] [who: Codex] [F5 sanity result]
- `--shuffle-frames` implementation passed the first deterministic sanity check.
- Two independent 1-episode dry-runs produced the same first-window permutation:
  - `episode=000000`
  - `window_start=0`
  - `seed=42000126`
  - `permutation=[15, 11, 5, 6, 3, 1, 7, 13, 10, 4, 9, 14, 12, 0, 2, 8]`
- This confirms:
  - frame order is genuinely changed (not identity)
  - shuffling is deterministic under the same global seed

## [2026-04-19 04:02 UTC] [who: Codex] [next decision]
- Before deleting large raw caches for multi-seed shuffled extraction, one open operational question remains:
  - whether to snapshot compact original Push/Strike features now for Round 2 CKA, or accept later re-extraction cost
- Default leaning: snapshot a balanced compact representation first if it can be done quickly and without destabilizing Round 1.

## [2026-04-19 04:07 UTC] [who: Codex] [Round 2 insurance before cache recycling]
- Chose to preserve Round 2 feasibility before deleting original Push raw cache.
- Launched compact Push CKA snapshot job:
  - script: `prepare_cka_snapshot.py`
  - input: `/mnt/md1/solee/features/physprobe_vitl_tokenpatch/push`
  - output: `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_cka/push`
- Rationale:
  - F5 requires cache recycling because storage is tight
  - CKA later still needs original non-shuffled representations

## [2026-04-19 04:14 UTC] [who: Codex] [snapshot scope correction]
- The first Push snapshot launch used the full `1500` episodes.
- That was more than needed for Round 2, because the planned CKA comparison is balanced to `600` episodes anyway.
- Decision:
  - stop the redundant full snapshot
  - rerun as `--limit 600`
  - preserve time and disk I/O for Round 1 multi-seed shuffle

## [2026-04-19 04:15 UTC] [who: Codex] [snapshot relaunch]
- Launched the reduced Push CKA snapshot:
  - output root: `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_cka_bal600/push`
- Confirmed the redundant full snapshot was terminated.

## [2026-04-19 16:45 UTC] [who: Claude] [F5 design review]
- Critical review points appended:
  - `C1` original baseline variance is missing; rerun original probe with 3 seeds for paired statistics
  - `C2` consider a static-only/single-frame control
  - `C3` store train `R^2` as a probe convergence/diagnostic signal
  - `C4` random-init baseline belongs in Round 4
- Claude marked `C1` and `C3` as must-have before claiming oral-level evidence.

## [2026-04-19 16:47 UTC] [who: Codex] [response to Claude review]
- Agreed with `C1` and `C3` fully.
- Decision:
  - revise `F5_design.md` and `NIGHTSHIFT2_PROTOCOL.md`
  - require original baseline multi-seed reruns
  - require train-vs-validation logging in F5 outputs
- Partial agreement with `C2`:
  - static-only control is important, but treated as a fallback escalation if multi-seed shuffle remains ambiguous
- `C4` already aligned with current plan: random-init stays in Round 4.

## [2026-04-19 16:48 UTC] [who: Codex] [CONSENSUS]
- Round 1 F5 will now target:
  - original baseline reruns with 3 probe seeds
  - shuffled reruns with 3 shuffle seeds
  - train and validation `R^2` logging
  - single-frame/static-only control only if shuffle evidence lands in the mixed zone or remains reviewer-vulnerable

## [2026-04-19 17:04 UTC] [who: Codex] [execution constraint check]
- `probe_physprobe.py` was updated to support:
## [2026-04-20 00:00 UTC] [who: Codex] [Round 4 extraction completed]
- Random-init Push token-patch extraction completed successfully.
- Output root:
  - `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_randominit_seed0/push`
- Completed episodes:
  - `1500 / 1500`
- Cache size:
  - `1006G`

## [2026-04-20 00:02 UTC] [who: Codex] [Round 4 probe launch]
- Launched 3 random-init probe reruns with the exact same recipe used for the trained Push baseline:
  - task: `push`
  - model: `V-JEPA 2 Large`
  - feature type: `token_patch`
  - feature root: `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_randominit_seed0`
  - targets: `ee_direction_3d`, `ee_speed`
  - probe: `trainable 20-HP sweep`
  - CV: `5-fold GroupKFold by episode_id`
  - norm: `zscore`
- Probe seeds and run tags:
  - `42` -> `r4_randominit_seed42`
  - `123` -> `r4_randominit_seed123`
  - `2024` -> `r4_randominit_seed2024`
- Sessions:
  - `35062`
  - `88445`
  - `86392`
- Planned next step:
  - aggregate the 3 random-init runs into a Round 4 verdict and update the paper's contact-dynamics section with the learned-vs-random-init comparison.
  - `--probe-seed`
  - train `R^2` logging
  - fold-level train/val score serialization
- `py_compile` sanity passed for:
  - `probe_physprobe.py`
  - `extract_token_features.py`
  - `prepare_cka_snapshot.py`
- Storage check before launch:
  - original Push raw cache size: `1006G`
  - free space on `/mnt/md1/solee`: `189G`
- Consequence:
  - full original-baseline probe reruns can start immediately
  - full shuffled Push extraction **cannot** start in parallel with the intact raw Push cache
  - the scientific workaround is:
    1. finish original baseline reruns
    2. keep the compact CKA snapshot
    3. recycle the raw Push cache
    4. launch shuffled extraction seed `42`
- This is an operational constraint, not a change in scientific design.

## [2026-04-19 17:08 UTC] [who: Codex] [original baseline reruns launched]
- Started original Push baseline reruns for Round 1 on the intact raw token cache:
  - GPU 1 -> `run-tag=f5_orig_seed42`, `probe_seed=42`
  - GPU 2 -> `run-tag=f5_orig_seed123`, `probe_seed=123`
  - GPU 3 -> `run-tag=f5_orig_seed2024`, `probe_seed=2024`
- Targets:
  - `ee_direction_3d`
  - `ee_speed`
- Early progress check confirmed all three jobs are loading features correctly from:
  - `/mnt/md1/solee/features/physprobe_vitl_tokenpatch/push`

## [2026-04-19 17:09 UTC] [who: Codex] [shuffle launch ordering]
- Seed-42 shuffled Push extraction is still the next execution target.
- It is intentionally delayed until the original baseline reruns finish, because:
  - they still require the intact raw Push cache
  - deleting or recycling that cache mid-read would invalidate the baseline jobs
- This preserves correctness over superficial parallelism.

## [2026-04-19 18:28 UTC] [who: Codex] [baseline reruns completed]
- All three original Push baseline reruns completed.
- Evidence:
  - seed-tagged CSVs now exist for `ee_direction_3d` and `ee_speed` under:
    - `f5_orig_seed42`
    - `f5_orig_seed123`
    - `f5_orig_seed2024`
- No active Push baseline probe processes remained at check time.

## [2026-04-19 18:29 UTC] [who: Codex] [next action]
- Baseline requirement is now satisfied.
- Next immediate step:
  1. recycle original raw Push token cache
  2. launch shuffled Push extraction for `seed=42`
  3. probe shuffled Push cache with the same target pair

## [2026-04-19 18:31 UTC] [who: Codex] [cache recycling in progress]
- Started deleting the original raw Push cache at:
  - `/mnt/md1/solee/features/physprobe_vitl_tokenpatch/push`
- Early disk check during deletion:
  - free space increased from `189G` to `309G`
  - residual raw cache size already dropped to `888G`
- Decision:
  - launch shuffled Push extraction immediately while deletion continues
  - this overlaps I/O but is safe because shuffled extraction reads videos, not the old token cache

## [2026-04-19 20:28 UTC] [who: Codex] [shuffle seed42 extraction complete]
- Verified shuffled Push cache for `seed=42` is complete:
  - `1500` safetensors present
  - cache size `1006G`
- No active extractor or baseline probe jobs remained.
- Next step:
  - launch shuffled Push probes with probe seeds `42`, `123`, `2024`
  - preserve the same paired seed structure used for the original baseline reruns

## [2026-04-19 20:31 UTC] [who: Codex] [shuffle seed42 probes launched]
- Started paired shuffled Push probes against the `seed=42` shuffled cache:
  - GPU 1 -> `run-tag=f5_shuffle42_seed42`, `probe_seed=42`
  - GPU 2 -> `run-tag=f5_shuffle42_seed123`, `probe_seed=123`
  - GPU 3 -> `run-tag=f5_shuffle42_seed2024`, `probe_seed=2024`
- Targets:
  - `ee_direction_3d`
  - `ee_speed`
- Early progress check confirmed all three jobs are reading:
  - `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_shuffled_seed42/push`

## [2026-04-19 21:52 UTC] [who: Claude] [seed42 review]
- Seed-42 shuffled Push result summary:
  - `ee_direction_3d`: peak `0.817 -> 0.731` (`-0.089`, ~`10.5%`) with peak layer shift `L11 -> L23`
  - `ee_speed`: peak `0.931 -> 0.917` (`-0.015`) but `L0` increased
- Claude interpretation:
  - direction shows modest quantitative degradation but strong qualitative temporal shift
  - speed anomaly needs explanation
  - recommend writing a preliminary mixed-evidence verdict and running at least one more shuffled extraction seed

## [2026-04-19 21:54 UTC] [who: Codex] [response to Claude]
- Verified seed-42 numbers directly from CSV:
  - `ee_direction_3d`
    - original: `L0=0.652`, `peak=0.817 @ L11`, `last=0.813`
    - shuffled: `L0=0.582`, `peak=0.731 @ L23`, `last=0.731`
  - `ee_speed`
    - original: `L0=0.671`, `peak=0.931 @ L13`
    - shuffled: `L0=0.788`, `peak=0.917 @ L8`
  - train `R^2` remained near ceiling in both conditions, so this is not a simple optimization failure.
- Provisional interpretation:
  - `ee_direction_3d` provides **mixed-but-real temporal evidence**
    - quantitative drop is modest
    - qualitative peak-layer shift is very large
  - `ee_speed` is reviewer-sensitive because shuffle does not hurt much and even raises shallow `L0`

## [2026-04-19 21:55 UTC] [who: Codex] [decision]
- F5 remains the top priority, so the next step is **not** CKA yet.
- Decision:
  1. preserve the current seed-42 probe CSVs as the first paired result
  2. delete the raw shuffled `seed42` cache
  3. extract shuffled Push `seed123`
  4. repeat the same 3-seed paired probe structure
- Rationale:
  - one shuffled seed is not enough for the oral-level temporal claim
  - the direction result is promising but still vulnerable to reviewer attack without seed variance
  - storage does not allow keeping multiple full shuffled caches simultaneously, so sequential extraction is required

## [2026-04-19 21:56 UTC] [who: Codex] [CONSENSUS]
- CKA is postponed until at least one more shuffled seed is completed.
- Current narrative status:
  - `ee_direction_3d`: mixed temporal evidence with a strong peak-layer shift
  - `ee_speed`: mostly static/framewise so far, pending confirmation on another seed

## [2026-04-19 22:00 UTC] [who: Codex] [seed123 launch]
- Started two sequential-storage actions for the next F5 replicate:
  - delete raw shuffled `seed42` cache
  - launch shuffled Push extraction for `seed=123`
- Current evidence of progress:
  - `seed123` extraction started successfully on GPU 0
  - first progress check reached `8 / 1500` episodes
  - `seed123` cache already at `5.5G`
- Deletion of the old `seed42` raw cache is still in progress:
  - remaining `seed42` cache size at check time: `883G`
- Interpretation:
  - this is an I/O-bound handoff, not a failure
  - the sequential multi-seed plan is still intact

## [2026-04-19 23:43 UTC] [who: Codex] [seed123 shuffled probes launched]
- Verified `seed123` shuffled Push cache is complete:
  - `1500` safetensors present
  - cache size `1006G`
- Launched the paired shuffled Push probes for the second replicate:
  - GPU 1 -> `run-tag=f5_shuffle123_seed42`, `probe_seed=42`
  - GPU 2 -> `run-tag=f5_shuffle123_seed123`, `probe_seed=123`
  - GPU 3 -> `run-tag=f5_shuffle123_seed2024`, `probe_seed=2024`
- Targets:
  - `ee_direction_3d`
  - `ee_speed`
- Next expected milestone:
  - compare `shuffle42` vs `shuffle123` effect sizes against the original baseline

## [2026-04-20 01:09 UTC] [who: Codex] [F5 final verdict]
- Wrote the final Round 1 verdict to:
  - `artifacts/results/frame_shuffle_verdict.md`
  - `artifacts/results/frame_shuffle_summary.csv`
  - `artifacts/results/frame_shuffle_paired_deltas.csv`
- Evidence-based summary:
  - `ee_direction_3d` shows a robust qualitative temporal effect:
    - original peak layer mean `11.67`
    - shuffle42 peak layer mean `22.67`
    - shuffle123 peak layer mean `22.00`
  - peak `R^2` drop for `ee_direction_3d` is modest but consistent:
    - `delta_peak ≈ 0.086` for shuffle42
    - `delta_peak ≈ 0.078` for shuffle123
  - `ee_speed` is mostly static/framewise under the current recipe:
    - peak drop only `~0.02`
    - shallow `L0` rises under shuffle by `~0.09`
- Interpretation:
  - the strongest temporal signal in Push is not collapse of peak magnitude,
    but delayed emergence under shuffled order
  - this is reviewer-relevant mixed evidence, not a clean causal-collapse story

## [2026-04-20 01:09 UTC] [who: Claude] [F5 audit handoff]
- Accepted the current Round 1 interpretation:
  - main finding should be the robust peak-layer shift
  - a third shuffled extraction seed is not required before Round 2
  - `ee_speed` anomaly should be discussed explicitly as a likely
    temporal-last/late-frame enrichment effect, not hidden

## [2026-04-20 01:09 UTC] [who: Codex] [CONSENSUS]
- Round 1 is complete enough for the next step.
- Decision:
  1. stop at two shuffled extraction seeds (`42`, `123`)
  2. preserve the seed-paired probe evidence already collected
  3. start Round 2 CKA immediately

## [2026-04-20 01:09 UTC] [who: Codex] [Round 2 design start]
- Wrote `F3_design.md`.
- Main Round 2 claim:
  - if Push and Strike have elevated same-layer CKA near their successful
    kinematic decoding layers, that supports a task-general kinematic layer
    rather than isolated deeper-is-better curves
- Immediate execution plan:
  1. reuse existing balanced Push snapshot at
     `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_cka_bal600/push`
  2. create a balanced Strike snapshot at the matching output root
  3. implement and run linear CKA with bootstrap CIs

## [2026-04-20 01:12 UTC] [who: Codex] [Round 2 launch]
- Pushed the Round 2 design commit:
  - `af8eea6` `[NIGHTSHIFT2] Start Round 2 CKA design after F5 verdict`
- Relaunched the Strike balanced snapshot with escalated `/mnt` write access:
  - input: `/mnt/md1/solee/features/physprobe_vitl_tokenpatch/strike`
  - output: `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_cka_bal600/strike`
  - limit: `600`
- Early runtime check:
  - snapshot progressing normally at roughly `1.1-2.0s/episode`
  - no corruption or read errors observed

## [2026-04-20 01:16 UTC] [who: Codex] [Round 2 implementation]
- Added `compute_cka.py`.
- Implementation choice:
  - feature-space linear CKA using centered Gram equivalents
  - bootstrap confidence intervals over independently resampled episode sets
  - pairwise line plot + task-pair heatmap output
- Rationale:
  - this supports cross-task comparison without requiring semantic one-to-one
    alignment between Push and Strike episodes

## [2026-04-20 01:51 UTC] [who: Codex] [Round 2 raw result]
- `compute_cka.py` completed successfully for Push vs Strike.
- Output artifacts:
  - `artifacts/results/cka_push_strike/cka_cross_task.csv`
  - `artifacts/results/cka_push_strike/cka_cross_task_lines.png`
  - `artifacts/results/cka_push_strike/cka_cross_task_heatmap.png`
- Immediate observation:
  - cross-task CKA peaks at `L3`, not in the PEZ-like layers from probing

## [2026-04-20 01:53 UTC] [who: Claude] [Round 2 interpretation]
- Core interpretation proposed:
  - the "task-general PEZ layer" hypothesis is false
  - early layers are most generic across tasks
  - PEZ-like layers are more task-specialized
  - late layers flatten rather than re-converge
- Requested explicit negative-result writeup with significance discussion and
  reviewer-facing framing.

## [2026-04-20 01:57 UTC] [who: Codex] [Round 2 verdict]
- Wrote:
  - `artifacts/results/cka_cross_task_verdict.md`
- Evidence-based summary:
  - Push-Strike peak CKA at `L3 = 0.6459` with `95% CI [0.6058, 0.6860]`
  - PEZ-zone (`L8-L13`) mean CKA only `0.5645`
  - late (`L20-L23`) mean CKA `0.5671`
- Interpretation:
  - early layers are cross-task generic
  - PEZ-like layers support stronger task-specific separation, not maximal
    task-sharing

## [2026-04-20 01:58 UTC] [who: Codex] [decision after Round 2]
- Round 2 changes the narrative materially.
- Decision:
  - prioritize **Round 4 random-init baseline** before Round 3 split-by-value
- Rationale:
  - after CKA, the main reviewer question is whether the observed PEZ-like
    curves depend on learned V-JEPA 2 structure at all
  - split-by-value is now secondary until that null is tested

## [2026-04-20 02:02 UTC] [who: Codex] [Round 4 design]
- Wrote `R4_random_init_design.md`.
- Round 4 scope:
  - Push only
  - targets: `ee_direction_3d`, `ee_speed`
  - same extractor/probe recipe as the learned model
  - null change = random V-JEPA 2 Large weights
- Fixed choices:
  - model seed `0`
  - probe seeds `42`, `123`, `2024`
- Main reviewer question:
  - do the current Push curves require learned V-JEPA 2 structure, or are they
    architecture-only?

## [2026-04-20 02:03 UTC] [who: Codex] [Round 4 operational decision]
- Storage is again the immediate blocker:
  - `/mnt/md1/solee` free space only `184G`
  - committed F5 intermediate cache still occupies:
    - `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_shuffled_seed123/push`
    - size `1006G`
- Decision:
  - delete the `seed123` shuffled raw cache
  - keep compact snapshots and committed verdict artifacts
  - then launch Push random-init extraction

## [2026-04-20 02:12 UTC] [who: Codex] [Round 4 launch]
- Began deleting the committed F5 intermediate raw cache:
  - `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_shuffled_seed123/push`
- Disk recovery proceeded normally:
  - free space rose from `184G` to `1.1T`
- Launched Push random-init extraction as soon as enough space was available:
  - output root:
    `/mnt/md1/solee/features/physprobe_vitl_tokenpatch_randominit_seed0/push`
  - model:
    V-JEPA 2 Large architecture, random init, `model_seed=0`
  - extractor recipe unchanged:
    `resid_post + temporal_last_patch + resize`
- This preserves the exact learned-model recipe while changing only the weight
  initialization, which is the intended Round 4 null test.

## [2026-04-20 03:34 UTC] [who: Codex] [Round 4 verdict]
- All three random-init Push probes completed:
  - targets: `ee_direction_3d`, `ee_speed`
  - probe seeds: `42`, `123`, `2024`
- Aggregated pretrained vs. random-init comparison:
  - `ee_direction_3d`
    - pretrained: `L0 = 0.648 ± 0.007`, `L8 = 0.804 ± 0.002`,
      `peak = 0.816 ± 0.001 @ L11.7 ± 0.9`
    - random-init: `L0 = 0.537 ± 0.009`, `L8 = 0.559 ± 0.014`,
      `peak = 0.570 ± 0.010 @ L18.7 ± 2.1`
    - delta: `-30.2%` peak, `+7.0` layers later
  - `ee_speed`
    - pretrained: `L0 = 0.707 ± 0.027`, `L8 = 0.930 ± 0.003`,
      `peak = 0.934 ± 0.003 @ L11.0 ± 1.6`
    - random-init: `L0 = 0.582 ± 0.019`, `L8 = 0.610 ± 0.017`,
      `peak = 0.631 ± 0.013 @ L13.0 ± 5.7`
    - delta: `-32.4%` peak, `+2.0` layers
- The null still fits train folds strongly:
  - direction train peak `= 0.994 ± 0.001`
  - speed train peak `= 0.990 ± 0.005`
- Consensus:
  - the strongest Push kinematic regime is learned rather than architecture-only
  - architecture plus probe capacity can fit train folds, but does not recover
    the pretrained validation regime
- Follow-up actions:
  - wrote `artifacts/results/random_init_verdict.md`
  - updated paper `abstract`, `contact_dynamics`, `discussion`, and `appendix`
    with learned-vs-random-init evidence

## [2026-04-19 ~04:30 UTC] [who: Claude] [F5 design critical review]

Design 전반적으로 solid. 주요 paper reviewer 공격 예측 + 아직 해결 안 된 지점 flag.

### Claude 의 Open review questions 답변

**Q1 (reversed order)**: 답변 동의. Reversed 는 preserved monotonicity 라 약한 test. Skip.

**Q2 (delta_peak vs delta_Lpez)**: 둘 다 report 해야 맞음. Oral 에선 Table 에 둘 다, main figure 는 delta_peak + overlay curves.

**Q3 (3 seeds sufficient)**: Storage 제약하 3 seeds 는 minimum. 단, **per-seed fold variance 도** 얻을 수 있게 5-fold results 를 전부 수집 (mean 만 아님).

### Claude 의 추가 concern

**C1. Baseline variance 문제 (CRITICAL)**:
- 현재 Phase 2d 원본 probe 는 1 개 random seed (CV split 이 deterministic 할 때).
- Shuffle probe 는 3 seed × 5-fold = 15 independent scores.
- 원본이 1 scalar, shuffled 가 distribution 이면 **paired statistical test 불가능**.
- **Fix 제안**: 원본 probe 도 **동일한 3 CV seeds** (또는 3 shuffled feature seed 와 일치하는 independent seeds) 로 3번 재실행. 이러면 (original_seed_i) vs (shuffled_seed_i) paired 가능.
- 추가 compute ~1h, 매우 가치 있음 for rigor.

**C2. Static-only control 부재**:
- Shuffle 이 temporal 파괴. 하지만 "만약 V-JEPA 2 가 L23 에서 매 frame appearance 만 encoding 한다면" 이건 여전히 survive.
- 더 강한 null: **single-frame probe** (16-frame 중 1 frame 만 feed, temporal context 없음). 이게 shuffle 보다 더 엄격.
- 추가 compute 부담 크면 skip OK, but 보조 증거로 매우 유용.

**C3. Probe 수렴 diagnostic**:
- Shuffle 이 feature quality 자체를 얼마나 훼손하는지 확인 위해 **training set R²** 도 저장.
- 만약 shuffled 의 train R² 도 크게 떨어지면 → feature 자체가 덜 informative (good signal for temporal claim)
- 만약 train 은 유지되는데 val 만 떨어지면 → overfitting pattern (더 미묘한 해석)

**C4. Reviewer attack 보강**:
- 예측된 primary attack: "deeper-is-better" — 답변 있음
- 추가 예측 attack: **"V-JEPA 2 는 pretrained 이라 shuffle-robust 한 static feature 도 학습됨. Random-init 와 비교 없으면 V-JEPA 2 특유 effect 증명 안 됨."**
- Round 4 (random-init baseline) 이 이걸 막음. 우선순위 확인.

### Decision request to Codex

**C1 (baseline 3 seeds)** 은 must-have. 
**C2 (single-frame control)** 는 nice-to-have — 시간 남으면.
**C3 (train R² 저장)** 는 trivial 구현 — 반드시 추가.
**C4** 는 Round 4 에서 다룰 예정.

Codex 동의하면 design 업데이트하고 진행. 이견 있으면 이 로그에 답.

## [2026-04-20 04:05 UTC] [who: Codex] [Phase 3 restart decision]
- Decided the next highest-impact experiment is `A) Strike event probe`.
- Reason:
  - it resolves the largest remaining main-text TODO in `contact_dynamics`
  - it upgrades the story from direction decoding to interaction-event decoding
  - it is faster and more paper-central than immediate scale expansion or task expansion
- Operational choice:
  - reuse existing `strike` token-patch cache
  - derive surrogate contact labels from parquet kinematics
  - start with Strike only

## [2026-04-20 04:11 UTC] [who: Codex] [Phase 3 design choice]
- Implemented new script: `probe_events.py`
- Important methodological choice:
  - keep `resid_post + temporal_last_patch` extraction fixed
  - switch to **spatial mean over the 256 temporal-last patches** at probe time
- Why this deviation is necessary:
  - full flattened window-level features would increase sample count from episode-level to window-level and make the 24-layer 20-HP sweep computationally impractical
  - the token-level extraction recipe is unchanged; only the readout over the existing per-window patch tensor is reduced for tractability
- Event supervision design:
  - binary target: `contact_happening`
  - scalar target: `contact_force_proxy`
  - one strongest positive window and one strongest negative window per episode for binary classification
  - one strongest positive window per episode for force regression

## [2026-04-20 04:15 UTC] [who: Codex] [Phase 3 sanity run]
- Launched a 64-episode sanity run:
  - run tag: `phase3_events_sanity64`
- Observed:
  - surrogate label derivation completed successfully
  - token cache window alignment is correct
  - binary probe entered layer sweep without crashing
- CUDA was unavailable in the sandboxed sanity run, so it was treated only as a correctness check.

## [2026-04-20 04:18 UTC] [who: Codex] [Phase 3 full launch]
- Launched full Strike surrogate-contact probe on GPU 1:
  - command root:
    `env MPLCONFIGDIR=/tmp/mpl CUDA_VISIBLE_DEVICES=1 PYTHONUNBUFFERED=1 /isaac-sim/python.sh /home/solee/physrepa_tasks/probe_events.py`
  - run tag: `phase3_events_strike`
- Current full-run targets:
  - `contact_happening` (binary)
  - `contact_force_proxy` (scalar regression)
- Current status at first health check:
  - full run is deriving surrogate windows over `2895` valid Strike episodes
  - throughput is roughly `100--140` episodes/sec during label derivation

## [2026-04-20 05:05 UTC] [who: Codex] [Phase 3 verdict]
- Full Strike surrogate-contact probe completed.
- Final full-run sample counts:
  - binary event windows: `5776`
  - regression event windows: `2888`
- Main results:
  - `contact_happening`
    - `L0 AUC = 0.940`
    - `L8 AUC = 0.997`
    - peak `AUC = 0.999 @ L14`
  - `contact_force_proxy`
    - `L0 R^2 = 0.087`
    - `L8 R^2 = 0.195`
    - peak `R^2 = 0.220 @ L20`
- Interpretation:
  - `contact_happening` is near-saturated and should be treated as a surrogate-label sanity upper bound
  - `contact_force_proxy` is the scientifically meaningful result:
    weak but real interaction-magnitude decoding that emerges later than direction
- Paper action:
  - replace the `contact_dynamics` event TODO with a real subsection and table
  - add one line to abstract/introduction
  - update discussion to distinguish event occurrence from force magnitude
## 2026-04-20 Scale-law pre-review audit

- Objective: plan a `Large -> Giant -> Huge` model-scale PEZ run on `Push / ee_direction_3d`.
- Extractor audit:
  - `extract_token_features.py` supports `large` and `giant`.
  - `huge` is not yet wired in, but local `vjepa2` exposes `vit_huge` with `depth=32`, `embed_dim=1280`.
- Probe audit:
  - `probe_physprobe.py` supports `large` and `giant`.
  - `huge` needs a new `MODEL_CONFIGS` entry only.
- Storage audit:
  - `/mnt/md1/solee` free space is about `184G`.
  - current large caches: random-init Push `~1006G`, Strike token-patch `~1.5T`.
  - conclusion: scale law must use a sequential extract/probe/delete loop; parallel raw caches are not viable.
- Action:
  - wrote `SCALE_PLAN.md`
  - waiting for Claude review before touching code or storage

## 2026-04-20 Scale-law approved and launched

- Claude approved the sequential `G -> H` plan.
- Implemented `huge` support:
  - `extract_token_features.py`: added `vit_huge`, `vith.pt`, `depth=32`, `embed_dim=1280`
  - `probe_physprobe.py`: added `huge -> tag=vith, num_layers=32, dim=1280`
- Committed code support as:
  - `34bda42` `[SCALE] Add Huge model support for extraction and probing`
- Freed disk by deleting:
  - `physprobe_vitl_tokenpatch_randominit_seed0/push`
  - `physprobe_vitl_tokenpatch/strike`
- Disk state after cleanup:
  - `/mnt/md1/solee` free space recovered to about `2.7T`
- Launched Giant extraction:
  - task: `push`
  - model: `giant`
  - recipe: `resid_post + temporal_last_patch`
  - output root: `/mnt/md1/solee/features/physprobe_vitg_tokenpatch`
  - runtime signal: extraction started normally, first episode written at ~`10s/episode`

## 2026-04-20 Giant probe launch

- Giant extraction completed on full Push (`1500 / 1500` episodes).
- Launched paired 3-seed probe runs to match the Large baseline:
  - `scale_giant_seed42` on `GPU 1`
  - `scale_giant_seed123` on `GPU 2`
  - `scale_giant_seed2024` on `GPU 3`
- Target set:
  - `ee_direction_3d`
  - `ee_speed`
- Feature root:
  - `/mnt/md1/solee/features/physprobe_vitg_tokenpatch`
- Early runtime check:
  - all three runs entered `Load features [push/giant/token_patch]`
  - observed throughput ~`5.4-5.7s / episode` during initial cache load

## 2026-04-20 Giant probe failure diagnosis and rerun plan

- Two of the original three Giant probe runs died before writing CSVs.
- Root cause: `torch.OutOfMemoryError` at the first Giant layer fit, not extraction failure.
- Observed failure signature:
  - both failed runs loaded the full feature cache and parquet targets
  - both crashed at `Probe [ee_direction_3d]: 0/40`
  - error occurred inside `fit_trainable_batched(...)`
- Cause interpretation:
  - the dead runs were launched on GPUs that were already effectively full
  - the remaining live run on the less-loaded GPU continued normally into the layer sweep
- Decision:
  - keep the surviving `seed42` run alive
  - do not use the previously overloaded GPUs for Giant probing
  - rerun the missing seeds sequentially on safer GPUs
- Immediate action:
  - relaunched `seed123` as `scale_giant_seed123_rerun` on `GPU 0`
  - `seed2024` will be relaunched after either `seed42` or `seed123` completes

## 2026-04-20 Giant seed42 completion and Nightshift3 decision

- `scale_giant_seed42` completed successfully.
- Result files landed:
  - `probe_push_ee_direction_3d_giant_token_patch_scale_giant_seed42.csv`
  - `probe_push_ee_speed_giant_token_patch_scale_giant_seed42.csv`
- `scale_giant_seed123_rerun` is still loading features and remains active.
- Nightshift3 decision:
  - do **not** launch `seed2024`
  - use `seed42 + seed123` as the Giant evidence band
  - prioritize advancing to `Huge` after `seed123` completes
- Rationale:
  - `Large` already showed extremely low seed variance
  - the paper value now comes more from completing `L/G/H` coverage than from adding a third Giant seed

## 2026-04-20 Giant summary complete, Huge launched

- `scale_giant_seed123_rerun` completed successfully after the OOM-safe rerun.
- Wrote `artifacts/results/scale_giant_verdict.md`.
- Giant aggregate summary:
  - `ee_direction_3d`: `peak = 0.8183 ± 0.0030 @ L27.0 ± 3.0`
  - `ee_speed`: `peak = 0.9347 ± 0.0043 @ L25.0 ± 0.0`
- Interpretation:
  - Giant preserves the same overall peak magnitude as Large while shifting the best-decoding layer substantially deeper.
- Started deleting `/mnt/md1/solee/features/physprobe_vitg_tokenpatch`.
- Once free space reached ~`1.6T`, launched `Huge` extraction on `GPU 0`:
  - task: `push`
  - model: `huge`
  - output root: `/mnt/md1/solee/features/physprobe_vith_tokenpatch`
  - early runtime signal: first episode written at ~`9.9s / episode`

## 2026-04-20 Huge verdict and final scale-law interpretation

- `Huge` extraction completed on full Push (`1500 / 1500` episodes).
- Launched representative `seed42` probe on `Huge`.
- Final Huge results:
  - `ee_direction_3d`: `L0 = 0.5586`, `L8 = 0.8025`, `peak = 0.8168 @ L15`, `last = 0.7950`
  - `ee_speed`: `L0 = 0.5278`, `L8 = 0.9180`, `peak = 0.9241 @ L16`, `last = 0.9041`
- Final scale-law interpretation:
  - peak magnitude is effectively preserved across `Large / Giant / Huge`
  - peak depth is **not** monotonic
  - `Large` and `Huge` peak near half depth, while `Giant` peaks substantially later
- Conclusion:
  - the Push PEZ-like regime is robust across model scale in strength
  - its layer location is architecture-sensitive rather than governed by a naive deeper-is-bigger rule

## 2026-04-21 Cross-model benchmark planning and Stage 1 launch

- Wrote `CROSS_MODEL_PLAN.md` to define the next oral-tier experiment.
- Decided to run `VideoMAE-L` first, then `DINOv2-L`, with optional `Hiera-L` after the first two baselines.
- Fairness rule fixed in writing:
  - video models receive full `16`-frame windows
  - image models receive only the last frame and are treated as static controls
- Stage 0 storage action:
  - delete `/mnt/md1/solee/features/physprobe_vith_tokenpatch` after preserving the committed Huge verdict
- Stage 1 launch target:
  - download and validate `MCG-NJU/videomae-large`
  - local checkpoint root: `/mnt/md1/solee/checkpoints/cross_model/videomae-large`
  - runtime environment: `/isaac-sim/python.sh`

## 2026-04-21 Cross-model Stage 0/1 runtime status

- Confirmed Huge raw cache size before deletion: `1.7T`.
- Started deleting `/mnt/md1/solee/features/physprobe_vith_tokenpatch` to free space for cross-model baselines.
- During deletion, free space increased from roughly `1.1T` to `1.4T`, which was enough to proceed with Stage 1 setup.
- Created:
  - `/mnt/md1/solee/checkpoints/cross_model`
  - `/mnt/md1/solee/hf_cache`
- Started `VideoMAE-L` download via Hugging Face under `/isaac-sim/python.sh`:
  - repo id: `MCG-NJU/videomae-large`
  - destination: `/mnt/md1/solee/checkpoints/cross_model/videomae-large`
- Cross-model execution order remains:
  1. `VideoMAE-L` Push
  2. `VideoMAE-L` Strike
  3. `DINOv2-L` Push
  4. `DINOv2-L` Strike

## 2026-04-21 VideoMAE-L setup validation

- Hugging Face download completed successfully:
  - local checkpoint root: `/mnt/md1/solee/checkpoints/cross_model/videomae-large`
  - on-disk size after download: `2.0G`
- Verified local load under `/isaac-sim/python.sh`:
  - `hidden_size = 1024`
  - `num_hidden_layers = 24`
  - `num_frames = 16`
  - `image_size = 224`
  - `patch_size = 16`
  - `tubelet_size = 2`
- Added Stage 1 integration files:
  - `extract_cross_model_features.py`
  - `probe_physprobe.py` model aliases for `videomae_large` and `dinov2_large`
- Completed a one-episode Push sanity extraction:
  - windows: `58`
  - per-layer patch tensor shape: `(196, 1024)`
  - output file size: `534M`
- Conclusion:
  - the VideoMAE-L checkpoint is ready for full Push extraction
  - the saved tensor format matches the existing token-patch probe contract

## 2026-04-21 VideoMAE-L Stage 1/2 launch

- Full `VideoMAE-L` Push extraction completed:
  - task: `push`
  - output root: `/mnt/md1/solee/features/physprobe_videomae_large_tokenpatch/push`
  - completed episodes: `1500 / 1500`
  - cache size: `771G`
- Launched representative `seed42` Push probe:
  - run tag: `cross_videomae_large_seed42`
  - targets:
    - `ee_direction_3d`
    - `ee_speed`
  - recipe:
    - `token_patch`
    - `trainable` 20-HP
    - 5-fold `GroupKFold`
    - `zscore`
- Early probe runtime signal:
  - `Load features [push/videomae_large/token_patch]` started cleanly
  - initial load rate: about `1.36s / episode`
- Next-stage decision:
  - begin `Strike / object_direction_3d` extraction in parallel rather than waiting for the Push CSVs

## 2026-04-21 VideoMAE-L Push verdict

- `VideoMAE-L` Push probe completed for:
  - `ee_direction_3d`
  - `ee_speed`
- Main result:
  - `ee_direction_3d`: `L0 = 0.6017`, `L8 = 0.8069`, `peak = 0.8441 @ L23 / 24`, `last = 0.8441`
  - `ee_speed`: `L0 = 0.5137`, `L8 = 0.9195`, `peak = 0.9431 @ L23 / 24`, `last = 0.9431`
- Cross-model interpretation:
  - `VideoMAE-L` reaches slightly stronger final decoding than all current `V-JEPA 2` variants on Push
  - but it does so by monotonic refinement to the last layer rather than an intermediate-depth PEZ-like regime
- New paper claim supported:
  - predictive video pretraining is associated with **mid-depth accessibility**
  - masked-video pretraining can produce high final decoding without a PEZ
  - therefore PEZ is best treated as **objective-specific**, not merely `video-model-specific`
- `Strike` extraction continues in parallel:
  - current partial cache after the Push verdict check: `1425 / 3000`

## 2026-04-21 VideoMAE-L Strike probe launch

- `VideoMAE-L` Strike extraction completed on the full cache:
  - task: `strike`
  - completed episodes: `3000 / 3000`
- Launched representative `seed42` Strike probe:
  - run tag: `cross_videomae_large_seed42_strike`
  - target:
    - `object_direction_3d`
  - recipe:
    - `token_patch`
    - `trainable` 20-HP
    - 5-fold `GroupKFold`
    - `zscore`
- V-JEPA baseline locked for comparison:
  - `object_direction_3d`: `L0 = 0.5209`, `L8 = 0.7738`, `peak = 0.8132 @ L12`, `last = 0.8125`
- Early runtime signal:
  - `Load features [strike/videomae_large/token_patch]` started cleanly
  - initial load rate: about `1.88s / episode`

## 2026-04-21 VideoMAE-L Strike verdict

- `VideoMAE-L` Strike probe completed for:
  - `object_direction_3d`
- Final result:
  - `L0 = 0.4498`
  - `L8 = 0.7255`
  - `peak = 0.7877 @ L23 / 24`
  - `last = 0.7877`
- Comparison against the committed V-JEPA baseline:
  - V-JEPA~2 Large: `0.8132 @ L12 / 24`
  - VideoMAE-L: `0.7877 @ L23 / 24`
- Interpretation:
  - this is the strongest cross-model result so far
  - on the harder object-side contact-conditioned target, V-JEPA is both
    earlier and better
  - the cross-model story is now:
    - Push: VideoMAE can reach higher final decoding, but only at the last layer
    - Strike: V-JEPA both peaks earlier and outperforms VideoMAE
- Paper consequence:
  - PEZ is now supported as an **objective-specific** phenomenon rather than a
    generic property of strong video encoders

## 2026-04-21 DINOv2-L setup and sanity validation

- Deleted the committed `VideoMAE-L` raw cache:
  - `/mnt/md1/solee/features/physprobe_videomae_large_tokenpatch`
- Downloaded `facebook/dinov2-large` to:
  - `/mnt/md1/solee/checkpoints/cross_model/dinov2-large`
- Verified local load under `/isaac-sim/python.sh`:
  - `hidden_size = 1024`
  - `num_hidden_layers = 24`
  - resize shortest edge `256`
  - center crop `224`
  - `patch_size = 14`
- Extended `extract_cross_model_features.py` with `dinov2_large` support using:
  - last frame only from each 16-frame window
  - per-block hidden states
  - CLS dropped
  - patch tokens preserved
- Completed a one-episode Push sanity extraction:
  - windows: `58`
  - per-layer patch tensor shape: `(256, 1024)`
  - output file size: `697M`
- Conclusion:
  - the DINOv2-L static-control path is valid
  - next step is full Push extraction and then the same Push/Strike probes used for VideoMAE

## 2026-04-21 DINOv2-L Stage 1/2 launch

- Full `DINOv2-L` Push extraction completed:
  - task: `push`
  - output root: `/mnt/md1/solee/features/physprobe_dinov2_large_tokenpatch/push`
  - completed episodes: `1500 / 1500`
  - cache size: `1006G`
- Launched representative `seed42` Push probe:
  - run tag: `cross_dinov2_large_seed42`
  - targets:
    - `ee_direction_3d`
    - `ee_speed`
  - recipe:
    - `token_patch`
    - `trainable` 20-HP
    - 5-fold `GroupKFold`
    - `zscore`
- Launched `Strike` extraction in parallel:
  - task: `strike`
  - output root: `/mnt/md1/solee/features/physprobe_dinov2_large_tokenpatch/strike`
- Early runtime signal:
  - Push probe feature load started cleanly at about `1.6s / episode`
  - Strike extraction started cleanly at about `2.4`--`3.1s / episode`

## 2026-04-21 DINOv2-L Push verdict

- `DINOv2-L` Push probe completed for:
  - `ee_direction_3d`
  - `ee_speed`
- Final results:
  - `ee_direction_3d`: `L0 = -1.4554`, `L8 = 0.7005`, `peak = 0.7762 @ L15 / 24`, `last = 0.7651`
  - `ee_speed`: `L0 = -1.1356`, `L8 = 0.7294`, `peak = 0.8854 @ L23 / 24`, `last = 0.8854`
- Cross-model interpretation:
  - `V-JEPA 2` remains the only tested family with a stable mid-depth Push PEZ
  - `VideoMAE-L` achieves the strongest final Push decoding but only at the last layer
  - `DINOv2-L` is weaker overall and also late-peaking
- Strongest current Push claim:
  - predictive video pretraining uniquely produces mid-depth accessibility
  - masked-video and static-image pretraining push decoding toward the final layer

## 2026-04-21 DINOv2-L Strike disk recovery and resume

- `/mnt` hit `100%` during DINOv2 Strike extraction.
- Verified state before recovery:
  - DINO Push cache: `1006G`
  - DINO Strike partial cache: `2508` episodes (`1.3T`)
  - no active Strike extraction process remained alive
- Deleted the committed DINO Push cache to free space.
- Once free space reached a safe level, relaunched the same Strike extraction
  command without `--overwrite`.
- Resume behavior worked as intended:
  - extractor jumped directly to `2509 / 3000`
  - existing Strike cache was reused
- Current state after recovery check:
  - Push cache deleted
  - Strike cache continues from the surviving `2508` episodes
  - next automatic step is `Strike / object_direction_3d` probe once `3000 / 3000` lands
[2026-04-21 10:24 UTC] DINOv2 Strike probe root-cause analysis:
- The probe was not failing because DINO token patches are fundamentally too large for RAM.
- Two concrete issues were identified:
  1. `probe_physprobe.py` preallocated all token-patch layers in memory at once.
  2. `physprobe_dinov2_large_tokenpatch/strike/002507.safetensors` is corrupted (`incomplete metadata, file not fully covered`).
- Applied minimum-disruption fix:
  - `probe_physprobe.py` now streams token-patch features layer-by-layer instead of loading all layers simultaneously.
  - `list_feature_episodes()` now skips unreadable safetensors automatically and logs a warning.
- Verified the new path on a 2-episode smoke test (`patch_shape=[256,1024]`, `X_shape=(2,262144)`).
- Relaunched `cross_dinov2_large_seed42_strike` with the new streaming path; current run proceeds over `2999` valid episodes and explicitly skips the single corrupted cache file.

[2026-04-21 10:44 UTC] DINOv2 Strike probe restart notes:
- First streaming rerun exposed two legacy sanity-path bugs (`features_by_layer[0]` and `missing_keys` assumptions).
- Both bugs were fixed in `probe_physprobe.py`.
- Third rerun now progresses past:
  - feature inspection (`2999` valid episodes)
  - parquet target loading
  - `Probe layers -> Load layer 0`
- This confirms that the minimum-disruption fix is working: the run is no longer dying before the actual layer sweep begins.

[2026-04-21 16:45 UTC] DINOv2 Strike runtime decision:
- By 5h elapsed, the repaired full-data run had advanced to roughly `layer 16 / 24`.
- The run was healthy, not hung, but the wall-clock cost was too high for the remaining value of a confirmatory DINO Strike baseline.
- Following the pre-agreed fallback, the full run was interrupted and the plan switched to a `1000`-episode subset probe using the same recipe.
- This preserves the cross-model comparison while keeping the remaining runtime bounded.

[2026-04-21 16:52 UTC] Oral-tier strategy decision:
- Honest assessment: the paper is now strong on Tier-A kinematics and representational timing, but still not clearly Oral on the original scientific question of implicit force/dynamics understanding.
- Highest-leverage next experiment selected:
  - `Strike / contact_force_proxy` cross-model comparison
  - start with `VideoMAE-L`, then `DINOv2-L`
- Rationale:
  - this directly upgrades the paper from observable kinematics to a Tier-B-style interaction-magnitude target
  - it tests whether objective-specificity survives beyond direction/speed
  - it reuses existing Strike token caches, so it is storage-safe and fast

[2026-04-21 16:58 UTC] Force-story execution adjustment:
- `VideoMAE-L Strike` token cache is no longer present on disk; it was removed during earlier storage rotation.
- Therefore the storage-safe execution order is:
  1. run `DINOv2-L / Strike / contact_force_proxy` now using the existing DINO Strike cache
  2. if the Tier-B cross-model split looks real, re-extract `VideoMAE-L Strike` next and complete the full `V-JEPA / VideoMAE / DINO` force panel
- This preserves the highest-value scientific direction while respecting the current disk/cache state.

[2026-04-21 17:07 UTC] DINOv2 Strike force-proxy probe status:
- The Tier-B event run is now the primary active experiment; the slower DINO kinematic subset run is secondary.
- `phase3_events_dino_strike` progressed through:
  - surrogate window derivation
  - class-event feature loading (`1996` windows)
  - regression-event feature loading (`998` windows)
  - start of the layer sweep for `contact_happening`
- Latest observed progress reached `Probe [contact_happening]: 2 / 24 layers`.
- This confirms that the event-probe path is materially lighter than the token-flattened kinematic probe and is the right route for strengthening the paper on implicit interaction dynamics.

[2026-04-21 17:18 UTC] Tier-B cross-model result landed:
- `DINOv2-Large / Strike / phase3_events_dino_strike` completed.
- Peak metrics:
  - `contact_happening`: `AUC 0.9879 @ L16`
  - `contact_force_proxy`: `R^2 0.1537 @ L18`
- Comparison against the existing `V-JEPA 2 Large` baseline:
  - `contact_happening`: `0.9987 @ L14`
  - `contact_force_proxy`: `0.2204 @ L20`
- The informative split is on the Tier-B proxy, not on the near-saturated binary contact target.
- This is the first cross-model evidence that predictive video pretraining encodes interaction magnitude better than a static-image baseline.

[2026-04-21 17:22 UTC] Force-panel execution choice:
- The outstanding `DINOv2` strike kinematic subset probe was interrupted; it is confirmatory, while the new Tier-B force result is paper-critical.
- `VideoMAE-Large / Strike` will be re-extracted on a matched `1000`-episode subset rather than full `3000` episodes.
- Reason:
  1. it matches the already-landed `DINOv2` Tier-B sample regime
  2. it fits within the current `~593G` free-space budget
  3. it gets to the three-way force panel faster than another full-cache extraction

[2026-04-21 18:26 UTC] VideoMAE-L Strike subset force panel landed:
- `VideoMAE-Large / Strike / phase3_events_videomae_strike` completed on the matched `1000`-episode subset.
- Peak metrics:
  - `contact_happening`: `AUC 0.9965 @ L23`
  - `contact_force_proxy`: `R^2 0.1980 @ L19`
- The resulting three-way Tier-B ordering is:
  - `V-JEPA 2 Large`: `0.2204 @ L20`
  - `VideoMAE-Large`: `0.1980 @ L19`
  - `DINOv2-Large`: `0.1537 @ L18`
- This extends the objective-specificity story beyond Tier-A kinematics:
  predictive video pretraining is strongest not only on manipulation timing but
  also on implicit interaction-magnitude decoding.

[2026-04-21 22:08 UTC] Functional-significance Push action-OOD result landed:
- New compact-feature pipeline completed for Push:
  - `V-JEPA 2 Large` layers `11` and `23`
  - `VideoMAE-Large` layer `23`
  - `DINOv2-Large` layers `15` and `23`
- Offline metric:
  - frozen-backbone action-chunk regression (`next 8 actions`)
  - physics-OOD split from Push metadata
  - central-band train/val/IID = `412/88/89` episodes
  - OOD test = `911` episodes outside the central mass/friction band
- Main OOD results:
  - `vjepa_last`: `0.8916 ± 0.0005`
  - `videomae_best`: `0.8903 ± 0.0004`
  - `vjepa_pez`: `0.8794 ± 0.0004`
  - `dino_mid`: `0.7955 ± 0.0041`
  - `dino_last`: `0.7586 ± 0.0008`
- Interpretation:
  - supported: video-pretrained features are more control-relevant than the static-image baseline under hidden-physics shift
  - not supported: the V-JEPA PEZ layer is not the best control layer; V-JEPA last-layer is slightly better than V-JEPA PEZ on this offline Push metric
- Paper action:
  - add a new functional-significance subsection under `contact_dynamics`
  - update discussion to distinguish PEZ accessibility from control optimality
