# VoxPlan Transformation: Living Project Plan

This document tracks the phased evolution of VoxPlan from a static task tracker with a cold-start supervised model into an independent, AI-powered personal planning system that learns from actual user task-completion patterns.

---

## Phase Overview

| Phase | Title | Status | Scope |
|---|---|---|---|
| **Phase 1** | Foundation, Date Unification & De-mocking | **COMPLETED** | Consistent task schema, arbitrary calendar date handling, removal of demo metric fallbacks, dynamic task-risk visualizations, honest browser Web Speech API, backwards-compatible localStorage migration. |
| **Phase 2** | Local Persistence & Behavioral Telemetry | **COMPLETED** | Local-first IndexedDB event store, versioned behavioral schema (11 event types), explicit stopwatch working duration vs self-reported vs unknown duration, inline reschedule/effort/reorder instrumentation, sparse-data honest behavioral statistics (< 3 completions), Behavioral History & Habit Insights UI panel with JSON export and history deletion, backend batch endpoints, and automated test suite. |
| **Phase 3, Stage 1** | Telemetry Repair & Personal Duration Estimation | **COMPLETED** | Shared task lifecycle engine (`taskLifecycle.js`), active stopwatch finalization, command-bar completion/reopening convergence, idempotent telemetry, local-first Personal Duration Estimator (`personalModel.js`) with weighted median and empirical Bayesian shrinkage ($K = 3.0$), dual duration badges on task cards, cold-start and uncertainty tiers. |
| **Phase 3, Stage 2** | Personal Model Dashboard & Evaluation | **COMPLETED** | Personal Model Dashboard (`PersonalModelDashboard.jsx`), sample weight transparency, Bayesian shrinkage formula explainer, leak-free chronological walk-forward holdout evaluation (`evaluatePersonalDurationModel`), MAE/MdAPE baseline comparison, and honest cold-start states. |
| **Phase 3, Stage 3** | Hybrid Completion-Risk Personalization | **COMPLETED** | Guarded hybrid completion-risk estimator (`personalRiskModel.js`), hardened evaluation guard (min 3 train, min 5 held-out, 8 total tasks), leakage protection, bounded adjustments ($\pm 15\%$), confidence shrinkage ($W / (W+5.0)$), transparent explainability modal, and 53 automated unit tests. |
| **Phase 4, Stage 1** | Adaptive Scheduling Foundations | **COMPLETED** | Standalone deterministic local-first scheduling engine (`src/scheduler/adaptiveScheduler.js`), dependency DAG analysis with cycle detection, personalized duration integration with cold-start fallbacks, daily working-hour capacity bin-packing, weekend rollover, proposal review modal (`AdaptiveScheduleModal.jsx`), safe approval flow, non-destructive diffs, and 19 unit tests (72 tests total). |
| **Phase 4, Stage 3** | Schedule Quality Evaluation & Benchmarking | **COMPLETED** | Documented deterministic schedule quality evaluation module (`src/scheduler/scheduleEvaluator.js`) across 7 dimensions (coverage, deadline feasibility, dependency correctness, capacity compliance, workload balance CV, horizon coverage, stability churn), multi-strategy benchmarking comparing Adaptive against Earliest Deadline First (EDF) and Priority-First under identical hard constraints, 12 reproducible scenario fixtures (`src/scheduler/scheduleBenchmarks.js`), perturbation churn analysis, modal benchmark UI tab, and 93 automated tests across 19 suites. |
| **Phase 4, Stage 4** | Workload Balancing & Sprint Optimization | Next Up | Interactive drag-and-drop slot reallocation, multi-sprint horizon planning, fine-grained calendar capacity overrides, and bottleneck notifications. |
| **Phase 5** | Voice & Conversational Planning Experience | Planned | Rich multi-turn planning dialog, schedule rescheduling commands, review debriefing via natural language. |

---

## Phase 1 Execution Record

### Objective
Establish trustworthy task data, remove misleading demo behavior, eliminate hardcoded date hacks, and ground all frontend visualizations in actual task state.

### Completed Work by Component

#### 1. Backend Date & Feature Engineering
- **File**: `backend/ml/features.py`
  - Replaced hardcoded October 5, 6, 7 date logic with `parse_calendar_date` and `calculate_days_remaining`.
  - Added robust ISO date (`YYYY-MM-DD`, `YYYY-MM-DDTHH:MM:SS`) and natural date parsing with explicit timezone handling.
  - Dynamically computed `task_age` from `createdAt` or creation timestamp instead of fixed static numbers.
  - Handled overdue tasks with progressive deadline pressure, tasks due today, and tasks with no set deadline.
  - Removed silent fallback substitution of arbitrary fixed days.
- **File**: `backend/ml/model.py`
  - Removed hardcoded default `"October 7"` from Pydantic `TaskInput` schema.
  - Added support for `description`, `createdAt`, `created_at`, `due_date`, and `estimated_effort`.
- **File**: `backend/ml/predict.py`
  - Updated `generate_task_explanation` to handle overdue tasks, tasks due today, and flexible timelines without deadlines.
  - Grounded factor explanations in actual task feature thresholds rather than hardcoded sprint assumptions.

#### 2. Backend Automated Test Suite
- **File**: `backend/tests/test_date_handling.py`
  - 18 comprehensive tests covering ISO format, month names, leap years, overdue detection, boundary checks, and timezone safety.
- **File**: `backend/tests/test_ml_backend.py`
  - Updated test payload from `"October 7"` to dynamic ISO dates (`YYYY-MM-DD`).
  - Total test suite: **26 tests passing**.

#### 3. Frontend Core & Task Persistence
- **File**: `src/App.jsx`
  - Implemented `normalizeTask()` ensuring every task has `id`, `title`, `description`, `dueDate` (ISO), `priority`, `estimatedEffort`, `completed`, `dependencies`, and `createdAt`.
  - Replaced hardcoded initial tasks with `getDefaultTasks()` generating valid dynamic ISO dates.
  - Ensured safe migration path for existing `localStorage` data without losing user tasks.
  - Completely removed `INITIAL_PREDICTIONS`, `INITIAL_MODEL_STATUS`, and `INITIAL_FEATURE_IMPORTANCES` fabricated fallbacks.
  - Enhanced deterministic command parser (`executeCommand`) to parse due dates, effort hours, and priority from natural language input.
  - Integrated genuine browser Web Speech API (`webkitSpeechRecognition` / `SpeechRecognition`) with graceful text-input fallback.
  - Passed dynamic user tasks and prediction mapping to `ProjectOverview`.

#### 4. UI De-mocking & Honest State Presentation
- **File**: `src/components/ProjectOverview.jsx`
  - Dynamic user tasks from state, live sprint health calculations.
- **File**: `src/components/MLModelPanel.jsx`
  - Removed hardcoded fallback metrics; displayed honest un-trained / offline states (`—`) when backend is not connected.
- **File**: `src/components/TaskCard.jsx`
  - Removed fallback 50% medium risk for unpredicted tasks; added explicit "Awaiting analysis" badge.
  - Formatted due dates dynamically relative to current calendar date.
- **File**: `src/components/Hero.jsx`
  - Added explicit `✦ ILLUSTRATIVE PREVIEW` badge to hero preview cards.
- **File**: `src/components/CommandBar.jsx`
  - Documented browser Web Speech API honestly.

---

## Phase 2: Personal Behavioural Telemetry & Durable Persistence

### 1. Persistence Architecture Evaluation & Decision

Before writing the database layer, the deployment and persistence constraints were rigorously evaluated:

1. **Hosted Deployment Reality (Render Web Services)**:
   - VoxPlan is deployed on Render (`https://voxplan-u31l.onrender.com/`). Render free-tier instances have an **ephemeral disk**.
   - Ephemeral disks are reset on every instance spin-down (after 15 minutes of inactivity) and during every redeployment. A backend-only SQLite database stored on the hosted filesystem would silently lose user telemetry and task history.
   - Multiple public visitors accessing the same Render backend would collide on a shared SQLite file unless multi-tenant authentication and tenancy isolation were introduced.

2. **Single-User Personal Planning & Privacy Constraint**:
   - VoxPlan is an intimate personal productivity tool. Telemetry captures granular working habits, active hours, pause patterns, and estimation biases.
   - Forcing telemetry into a remote server without explicit authentication introduces privacy leaks and breaks the core offline-first requirement established in Phase 1.
   - Adding cloud-hosted databases (e.g. Supabase, AWS RDS, Neon) or third-party auth (Firebase, Clerk) violates the project constraints (no external paid databases, no unnecessary cloud auth).

3. **Chosen Architecture: Local-First IndexedDB as Source of Truth + Stable Anonymous Profile ID**:
   - **Engine**: Browser **IndexedDB** (`voxplan_db`, version 1) with object stores:
     - `telemetry_events`: Versioned, immutable event records indexed by `event_id`, `task_id`, `event_type`, and `timestamp`.
     - `tasks`: Durable task records and state.
     - `timer_sessions`: Active and completed working session intervals with start/pause/resume timestamps.
   - **Profile Isolation**: A stable anonymous local profile ID (`voxplan_profile_id`, format: `prof_<uuid>`) is generated on the client and stored in `localStorage` and IndexedDB. Every telemetry event is strictly stamped with this `profile_id`.
   - **Durability**: IndexedDB data survives browser tab closes, full application reloads, offline periods, and machine restarts.
   - **Offline Resilience**: The app can create tasks, track timers, log behavioral telemetry, and compute behavioral statistics completely offline without a running backend.
   - **Optional Backend Batch Ingestion**: FastAPI exposes `/api/telemetry/events` for local testing and batch ingestion, validating profile ownership and deduplicating by `event_id`.
   - **User Agency**: Users can inspect all recorded events in full transparency, export their history as JSON, or permanently wipe their behavioral history with a single click without deleting active tasks.

---

### 2. Completed Implementation by Component

#### A. Versioned Behavioral Event Schema & Validation
- **File**: `src/telemetry/eventSchema.js`
  - Defines `SCHEMA_VERSION = 1` and all 11 event types:
    - `task_created`: `{ title, category, priority, due_date, estimated_effort, dependencies }`
    - `task_started`: `{ session_id, started_at }`
    - `task_paused`: `{ session_id, paused_at, elapsed_seconds }`
    - `task_completed`: `{ completed_at, tracked_duration_seconds, self_reported_duration_seconds, duration_source }`
    - `task_reopened`: `{ reopened_at }`
    - `task_rescheduled`: `{ previous_due_date, new_due_date, reason }`
    - `task_priority_changed`: `{ previous_priority, new_priority }`
    - `task_effort_revised`: `{ previous_effort, new_effort }`
    - `task_reordered`: `{ previous_index, new_index, task_ids_order }`
    - `recommendation_accepted`: `{ recommendation_type, recommendation_id, details }`
    - `recommendation_rejected`: `{ recommendation_type, recommendation_id, details }`
  - Robust `validateEvent()` asserting UUID format, ISO-8601 timestamps, schema version match, and payload structure.
  - Frozen `createEvent()` factory ensuring payload immutability.

#### B. Storage Layer & Telemetry Manager
- **File**: `src/telemetry/indexedDbStore.js`
  - Transactional wrapper around `indexedDB` with object stores: `telemetry_events`, `tasks`, `timer_sessions`.
  - In-memory / localStorage fallback for Node.js test runners and non-browser environments.
- **File**: `src/telemetry/telemetryManager.js`
  - Orchestrates profile initialization (`getOrCreateProfileId()`), event creation, and deduplicated storage.
  - Persists active stopwatch timer state in `localStorage` and IndexedDB, ensuring running timers continue tracking accurately across browser reloads.
  - Provides methods for exporting complete telemetry as JSON (`exportTelemetryJson()`) and wiping history (`clearProfileTelemetry()`) safely.

#### C. Behavioral Statistics Layer
- **File**: `src/telemetry/behavioralStats.js`
  - Reconstructs active task state and computes genuine metrics:
    - `completed_count`: Number of completed tasks.
    - `duration_measured_count`: Tasks with stopwatch-measured duration (`tracked`).
    - `self_reported_count`: Tasks with approximate completion time (`self_reported`).
    - `unknown_duration_count`: Tasks completed without duration.
    - `total_tracked_seconds` & `formatted_tracked_time`.
    - `median_observed_duration_hours`: Median duration computed over measured tasks.
    - `median_by_category`: Categorical breakdown of observed duration.
    - `estimation_accuracy_ratio`: Ratio of median observed duration to median estimated effort.
    - `weekday_distribution`: Completion distribution across Monday through Sunday.
    - `postponements_count`: Total deadline changes and postponements.
  - **Sparse-Data Guard**: Enforces `insufficient_data: true` when completed tasks < 3. Never hallucinates productivity trends from 1 or 2 tasks.

#### D. UI Task Instrumentation & Stopwatch Timer
- **File**: `src/components/TaskCard.jsx`
  - Added dedicated stopwatch control: **Start / Pause / Resume** with live seconds ticker (`⏱️ 00:00`).
  - Added inline due-date rescheduling popup and inline effort revision input, firing `task_rescheduled` and `task_effort_revised` events with previous and new values.
  - Added manual reordering triggers (▲ / ▼), firing `task_reordered`.
  - On task completion without an active timer, opens an optional quick self-reported duration prompt (`"Log time: 15m / 30m / 1h / Skip"`), recording duration honestly as `duration_source: 'self_reported'`.
  - On unmeasured completion, records `duration_source: 'unknown'` without fabricating zero minutes.
- **File**: `src/components/TaskList.jsx`
  - Wired reorder, reschedule, effort revision, and timer handler props to each `TaskCard`.

#### E. Behavioral History & Habit Insights UI
- **File**: `src/components/BehavioralHistoryPanel.jsx`
  - Added Section 04: **Behavioral History & Habit Insights**.
  - Features 4 pastel metric cards:
    - **Completed Tasks**: Total completed vs. timer-tracked vs. self-reported counts.
    - **Focused Time**: Accumulated stopwatch duration with median duration per task.
    - **Estimation Accuracy**: Real ratio of actual duration vs. user's estimated effort with honest bias assessment.
    - **Schedule Adjustments**: Count of deadline changes and postponements.
  - Features **Weekday Rhythm** visual bar distribution showing which days the user actually completes work.
  - Features **Local Privacy Promise**: Explicit documentation that data stays 100% in the browser's IndexedDB, never uploaded or sent to third-party AI models.
  - Includes **Export History (JSON)** and **Clear History** with double-confirmation modal that clears telemetry while preserving active tasks.
- **File**: `src/components/CommandBar.jsx`
  - Updated section numbering to Section 05.
- **File**: `src/App.jsx`
  - Initialized telemetry manager on mount.
  - Connected `toggleTaskCompletion`, `cyclePriority`, `handleReschedule`, `handleReviseEffort`, `handleMoveTask`, `handleStartTimer`, and `handlePauseTimer` to telemetry logger.
  - Recorded `recommendation_accepted` when clicking high-risk filter from command bar.
  - Embedded `<BehavioralHistoryPanel />` with live stats subscription.

#### F. Backend Batch Telemetry Endpoints
- **File**: `backend/ml/model.py`
  - Added `TelemetryEventInput`, `TelemetryBatchRequest`, `TelemetryBatchResponse`.
- **File**: `backend/main.py`
  - `POST /api/telemetry/events`: Batch ingestion of validated telemetry events with deduplication.
  - `GET /api/telemetry/events`: Profile-scoped event retrieval.
  - `DELETE /api/telemetry/events`: Profile-scoped history deletion.
- **File**: `backend/tests/test_ml_backend.py`
  - Added test `test_api_telemetry_batch_ingest_and_retrieval` verifying batch storage, deduplication, and profile isolation.

---

### 3. Automated Test Verification & Results

#### A. Node.js Telemetry Test Suite
- **Command**: `npm test` (`node --test tests/**/*.test.js`)
- **Result**: `14 passed, 0 failed, duration: 128ms`.
  - Event schema validation: UUID format, ISO-8601 dates, schema version, required payload fields.
  - Profile isolation: Separate storage and deletion across different profile IDs.
  - Deduplication: Idempotent event writes with duplicate event IDs.
  - Duration distinctions: `tracked` vs. `self_reported` vs. `unknown`.
  - Rescheduling & priority change tracking: Previous and new value preservation.
  - Sparse data handling: `insufficient_data: true` when completed tasks < 3; genuine median and weekday calculations when tasks >= 3.
  - Task reopening: Accurately adjusts completed task statistics.

#### B. Backend Pytest Suite
- **Command**: `python -m pytest backend/tests/ -v`
- **Result**: `27 passed in 5.15s` (18 date handling tests + 9 API & ML tests including telemetry batch ingestion).

#### C. Frontend Code Quality & Bundle Verification
- **Linter**: `npm run lint` (`oxlint`) -> **0 warnings, 0 errors** across 20 files.
- **Build**: `npm run build` (`vite build`) -> **Successfully generated production bundle** (`dist/assets/index-DAlGQmgN.js`, 455 kB gzip: 143 kB).

---

### 4. Known Limitations & Transition to Phase 3

1. **Cold-Start Random Forest Model**: The Random Forest classifier remains trained on the synthetic baseline dataset. Phase 2 collected trustworthy behavioral telemetry; Phase 3 will consume this telemetry to adapt model predictions to the user's actual velocity and estimation bias.
2. **Local-First Single Device**: Telemetry is durably persisted in the client's IndexedDB. Cross-device synchronization is not claimed or implemented. Users can export their telemetry as JSON to migrate data if needed.
3. **Statistical Sample Size**: Behavioral metrics require a minimum of 3 completed tasks to display meaningful patterns. The UI explicitly discloses this requirement to prevent misleading premature conclusions.

---

## Phase 3, Stage 1 Execution Record: Telemetry Repair & Local Personal Duration Estimation

### Objective
Fix command-bar completion and reopening telemetry, ensure active stopwatch timers finalize reliably without duplicate events, and implement a transparent, local-first personal duration estimator that learns user effort estimation bias using genuine historical observations from IndexedDB.

### Completed Work by Component

#### 1. Shared Task Lifecycle & Command-Bar Convergence
- **File**: `src/telemetry/taskLifecycle.js` (NEW)
  - Extracted pure lifecycle state transition logic: `completeTaskLifecycle` and `reopenTaskLifecycle`.
  - **Convergence**: Both TaskCard clicks and CommandBar voice/text actions (`"Complete Prepare Report"`, `"Uncomplete Prepare Report"`) route through identical lifecycle functions.
  - **Timer Finalization**: Automatically finalizes active stopwatch sessions on task completion, calculating non-paused working seconds and recording `duration_source: 'tracked'`.
  - **Idempotency**: Protects against duplicate completion or reopening events on repeated natural language commands by returning `{ success: false, reason: 'already_completed' }` or `{ success: false, reason: 'already_open' }`.
  - **Duration Truth**: Distinguishes `tracked`, `self_reported`, and `unknown` durations. Missing duration is recorded as `null` rather than zero.
- **File**: `src/App.jsx`
  - Integrated `completeTaskLifecycle` and `reopenTaskLifecycle` into `completeTask`, `reopenTask`, and `toggleTaskCompletion`.
  - Rewired natural language commands 8 (uncomplete), 9 (complete), and 10 (delete) to call unified handlers.
  - Memoized `personalDurationModel` from telemetry events and tasks, passing to `<TaskList />`.

#### 2. Local-First Personal Duration Estimator
- **File**: `src/telemetry/personalModel.js` (NEW)
  - Client-side duration estimator extracting genuine observations from IndexedDB telemetry events.
  - **Observation Eligibility**:
    - Groups events by stable `task_id`.
    - Handles reopening: ignores intermediate completion states of reopened tasks, evaluating only final completions.
    - Plausibility boundaries: excludes durations $< 0.01\text{h}$ (36s) or $> 200\text{h}$.
    - Positive initial effort requirement: requires `original_estimated_effort > 0` for ratio calculation.
    - Target leakage safeguard: excludes all post-completion attributes (`completed_at`, `duration_source`, `tracked_duration_seconds`) from prediction inputs. Only pre-completion planning fields are used.
  - **Weighting**: Tracked stopwatch duration $w = 1.0$; self-reported duration $w = 0.5$; unknown duration $w = 0.0$.
  - **Mathematical Formula**:
    $$r_i = \frac{\text{observed\_duration\_hours}_i}{\text{original\_estimated\_effort\_hours}_i}$$
    $$r_{med} = \text{WeightedMedian}\left(\left\{(r_i, w_i)\right\}\right)$$
    $$r_{adjusted} = \frac{W \cdot r_{med} + K \cdot 1.0}{W + K} \quad (K = 3.0)$$
    $$\hat{D} = \text{user\_estimate\_hours} \times r_{adjusted}$$
  - **Uncertainty & Sample Maturity**:
    - `cold_start` ($W = 0$): returns unmodified estimate, explaining no completed tasks exist yet.
    - `sparse` ($0 < W < 3$): returns unmodified estimate, reporting $X$ observations recorded and 3 needed.
    - `developing` ($3 \le W < 8$): applies shrinkage toward 1.0, reporting emerging pattern.
    - `supported` ($W \ge 8$): applies full personal adjustment with empirical spread $[r_{p25} \dots r_{p75}]$.
    - `unavailable`: clearly indicated if user has not provided an effort estimate.
  - **Privacy & History Deletion**: Computed purely on the client. Resetting telemetry via `clearProfileTelemetry()` immediately returns the estimator to cold-start without touching active tasks.

#### 3. Task Card UI Integration
- **File**: `src/components/TaskCard.jsx`
  - Integrated dual duration indicator: when personal observations exist, shows `⏱️ 2h → ~2.6h (4)` with observation count badge.
  - Rich explanatory tooltip disclosing user estimate, adjusted prediction, sample count, effective weight, bias ratio, empirical spread, and plain-language explanation.
  - Distinguishes missing effort estimates with an honest "Duration estimation unavailable (no effort estimate)" message.
  - Preserved pastel aesthetic and layout responsiveness.
- **File**: `src/components/TaskList.jsx`
  - Evaluates `estimateTaskDuration(personalDurationModel, task)` per task and supplies to `TaskCard`.

#### 4. Automated Testing
- **File**: `tests/personal_model.test.js` (NEW)
  - 21 comprehensive unit tests covering:
    - Weighted median calculation with odd/even weights and identical values.
    - Cold-start with no observations.
    - Unavailable state for missing user estimates.
    - 1 tracked observation with shrinkage ($1.0 \times 1.4 \to 1.1$).
    - Multiple consistent observations ($1.5 \to 1.34$).
    - Self-reported lower weighting ($0.5$).
    - Exclusion of unknown durations, negative durations, and implausible values ($> 200$h).
    - Resistance to extreme outliers (100h bug).
    - Shrinkage prevention of overcorrection on sparse data.
    - Deduplication of duplicate completion events.
    - Intermediate completion handling for reopened tasks (no double counting).
    - Absence of fabricated category personalization.
    - History deletion restoring cold-start state.
    - Target leakage verification (post-completion fields do not alter prediction).
    - Lifecycle completion, active timer finalization, idempotency duplicate rejection, and reopen transitions.

---

### Verification Results

1. **Frontend Test Suite**: `npm test`
   - **35 tests passing across 6 suites** (14 duration tests, 5 lifecycle tests, 16 Phase 2 telemetry tests).
2. **Backend Pytest Suite**: `python -m pytest backend/tests/ -v`
   - **27 tests passing** (18 date handling tests, 9 ML & API tests).
3. **Frontend Linter**: `npm run lint` (`oxlint`)
   - **0 errors, 0 warnings** across 23 files.
4. **Production Build**: `npm run build` (`vite build`)
   - Successfully built production bundle in 1.21s.

---

---

## Phase 3, Stage 2 Execution Record: Personal Model Dashboard & Evaluation

### Objective
Build a transparent dashboard for VoxPlan's local personal duration estimator and establish a defensible, leak-free holdout evaluation methodology that honestly measures whether personalized duration predictions improve on the user's original effort estimates.

### Completed Work by Component

#### 1. Chronological Walk-Forward Holdout Evaluation Engine
- **File**: `src/telemetry/personalModel.js`
  - Enhanced `extractEligibleObservations` to track `completedAt` timestamps and sort eligible observations chronologically.
  - Implemented `evaluatePersonalDurationModel(events, currentTasks, options)`:
    - **Walk-Forward Rolling-Origin Design**: Evaluates tasks in strict chronological completion order. For each test step $k \ge 3$, the model is fitted strictly on tasks completed prior to task $k$.
    - **Zero Target Leakage**: The test task's observed duration, completion time, and post-completion metadata are never in the training set.
    - **Observation Isolation**: Groups all events per task; duplicate events or multiple completion cycles for a single task do not inflate evaluation splits.
    - **Minimum Sample Guard**: Requires at least 5 completed tasks with effort estimates and durations (`MIN_EVALUATION_TASKS = 5`). When $< 5$ tasks exist, returns an explicit `insufficient_data` state with progress tracking and an explanation of the walk-forward methodology.
    - **Evaluation Metrics**:
      - Model MAE vs. User Original Effort Baseline MAE: Mean Absolute Error in hours.
      - Error Reduction: Absolute delta in hours and percentage improvement.
      - Model MdAPE vs. Baseline MdAPE: Median Absolute Percentage Error ($\text{Median}(|\hat{D}_i - D_i| / D_i) \times 100\%$).
      - Win / Loss / Tie Counts: Number of test tasks predicted closer to actual duration than the original estimate.
      - Test Details: Audit log of each walk-forward test prediction with training set size, effective weight, applied ratio, and error metrics.

#### 2. Personal Model Dashboard Component
- **File**: `src/components/PersonalModelDashboard.jsx` (NEW)
  - Created Section 05: **PERSONAL ESTIMATION MODEL & EVALUATION** ("HOW VOXPLAN LEARNS YOUR PACE") with editorial typography ribbon `CALIBRATE`.
  - **Core Pastel Metric Cards**:
    - **Maturity Status**: Displays tier (`cold_start`, `sparse`, `developing`, `supported`) with explanatory captions and color-coded status pills.
    - **Effective Sample Weight**: Discloses $W = 1.0 \times N_{tracked} + 0.5 \times N_{reported}$, explicitly distinguishing raw observation counts from effective weighted sample size.
    - **Personal Bias Ratio**: Discloses adjusted multiplier $r_{adjusted}$ alongside raw weighted median $r_{med}$ and shrinkage prior weight ($K=3.0$).
    - **Interactive Simulation**: Live slider/input showing how a user estimate (e.g. 2.0h) transforms into an adjusted duration estimate with empirical spread.
  - **Bayesian Shrinkage Architecture**: Visual equation box explaining the shrinkage math:
    $$\text{Adjusted Ratio} = \frac{W \cdot r_{med} + 3.0 \cdot 1.0}{W + 3.0}$$
    and why neutral prior anchoring protects against wild swings from noisy early tasks.
  - **Walk-Forward Holdout Evaluation Panel**:
    - **Awaiting Data State (< 5 tasks)**: Shows animated progress bar ($X / 5$ tasks), clear explanation of out-of-sample holdout validation, and methodological honesty callout explaining why training-set accuracy is rejected.
    - **Evaluated State ($\ge 5$ tasks)**: Displays Model MAE, Baseline MAE, Error Reduction hours and %, MdAPE comparison, win rate badge, and audit table of test tasks.
  - **Methodological Honesty Disclosures**:
    - Interpretable Bias Correction vs. Black-Box Regressor.
    - Baseline Delay-Risk Distinction (Random Forest in Section 03 remains an empirical synthetic baseline).
    - Durable Local Privacy (100% in-browser IndexedDB, instant reset on history clear).

#### 3. Navigation & App Integration
- **File**: `src/components/Header.jsx`: Added Habits (`behavior`) and Personal Model (`personal-model`) nav links.
- **File**: `src/components/CommandBar.jsx`: Re-indexed section number to 06.
- **File**: `src/App.jsx`: Embedded `<PersonalModelDashboard events={telemetryEvents} tasks={tasks} />` with ribbon `CALIBRATE`.

#### 4. Automated Testing
- **File**: `tests/personal_model.test.js`
  - Added Suite 3: **Personal Model Evaluation & Dashboard Derivations** with 8 tests:
    - Cold-start evaluation returns `insufficient_data` ($N=0$).
    - Sparse data evaluation returns `insufficient_data` with progress count ($N < 5$).
    - Effective weight calculation separates measured ($1.0$) vs. reported ($0.5$) vs. unmeasured ($0.0$).
    - Walk-forward chronological holdout evaluation with 5+ tasks verifies training set sizes ($3 \to 4 \to 5$) and leak-free predictions.
    - Prevention of task-level overlap: duplicate completion events do not inflate evaluation splits.
    - Safe handling of missing or zero estimates during evaluation.
    - History deletion immediately resets model to cold-start and evaluation to `insufficient_data`.
    - Status tier progression (`cold_start` $\to$ `sparse` $\to$ `developing` $\to$ `supported`).

---

### Verification Results

1. **Frontend Test Suite**: `npm test`
   - **43 tests passing across 7 suites** (0 failures, 124ms duration).
2. **Backend Pytest Suite**: `python -m pytest backend/tests/ -v`
   - **27 tests passing** (18 date handling tests, 9 ML & API tests).
3. **Frontend Linter**: `npm run lint` (`oxlint`)
   - **0 errors, 0 warnings** across 24 files.
4. **Production Build**: `npm run build` (`vite build`)
   - Successfully generated production bundle in 266ms (`dist/assets/index-Cjky9M-L.js`, 488 kB / 151 kB gzip).

---

### Limitations & Phase 3, Stage 3 Evolution
1. **Evaluation Sample Size**: Initial Stage 2 protocol began testing at $k=3$. With 5 tasks, this yielded only 2 test predictions, which is insufficient evidence to report aggregate model performance metrics. Corrected in Stage 3 to require at least 5 genuine held-out predictions ($N \ge 8$).
2. **Model Separation**: Synthetic baseline Random Forest retained as a generic reference model, while the client-side personal risk layer is now implemented with conservative shrinkage.

---

## Phase 3, Stage 3 Execution Record: Guarded Completion-Risk Personalization

### Objective
Implement a transparent, local-first hybrid completion-risk estimator that personalizes baseline Random Forest delay-risk estimates using genuine, audited behavioral telemetry from the user's IndexedDB store, while preventing temporal leakage, target leakage, and small-sample overreaction.

### Completed Work by Component

#### 1. Evaluation Guard Hardening
- **File**: `src/telemetry/personalModel.js`
  - Corrected `evaluatePersonalDurationModel`:
    - Requires at least 3 chronologically earlier observations for training before any prediction ($N_{train} \ge 3$).
    - Requires at least 5 genuine held-out test predictions before reporting aggregate performance metrics ($N_{held\_out} \ge 5$).
    - Total observation requirement corrected from 5 to 8 completed tasks ($3 + 5 = 8$).
    - If $N < 8$, returns explicit `insufficient_evaluation_data` state with separate metrics:
      - `eligibleObservationCount`: Total eligible tasks with durations and estimates.
      - `minTotalObservations`: 8.
      - `minTrainObservations`: 3.
      - `heldOutPredictionCount`: $N - 3$ (e.g. 2 predictions at 5 tasks, 4 at 7 tasks).
      - `minHeldOutPredictions`: 5.
      - `trainObservationsPerPrediction`: Minimum 3 prior tasks.
    - Updated `PersonalModelDashboard.jsx` to render progress against both held-out predictions ($X / 5$) and eligible completed tasks ($Y / 8$), with an explicit methodology callout explaining the sample threshold.

#### 2. Audit of Personal Completion-Risk Signals
A comprehensive audit of locally recorded telemetry schemas was performed to identify valid pre-prediction signals and eliminate leakage risks:

| Feature Signal | Telemetry Source & Event | Availability Time | Limitations & Noise | Leakage Safeguard | Decision |
|---|---|---|---|---|---|
| **Postponement Friction** | `task_rescheduled` events for `task_id` | Pre-prediction (when user changes due date) | User may reschedule for external reasons; single reschedule is weak evidence. | Strictly filter `timestamp <= asOfTime`. Exclude duplicate events. | **INCLUDED**: $+5\%$ for 1 reschedule, $+10\%$ for $\ge 2$ reschedules (before shrinkage). |
| **Personal Estimation-Bias Stress** | Pre-prediction duration model ($r_{adjusted}$) vs. calendar gap | Pre-prediction (from prior completed tasks) | Requires $\ge 3.0$ personal history weight; coarse calendar day discretization. | Ratio fitted strictly on prior tasks. Target task actual duration is strictly excluded. | **INCLUDED**: $+6\%$ if $r_{adjusted} \ge 1.25$ and adjusted hours $> 50\%$ remaining work hours; $-4\%$ buffer if $r_{adjusted} \le 0.85$. |
| **Reopening Lifecycle Churn** | `task_reopened` event for `task_id` | Pre-prediction | Rare event; indicates prior incomplete deliverables or changing scope. | Filter `timestamp <= asOfTime`. Only count if task is currently active. | **INCLUDED**: $+5\%$ raw friction delta. |
| **Target Task Incompletion State** | `task.completed === false` | Pre-prediction | A task being incomplete is normal during sprint execution, not evidence of delay. | N/A | **EXCLUDED**: Zero risk delta. |
| **Target Task Actual Duration** | `trackedDurationSeconds` on target | Post-completion only | Completely unavailable at planning time. Using it would be fatal target leakage. | Target task post-completion fields are strictly ignored by estimator. | **EXCLUDED**: Target leakage protection verified by unit test. |
| **Synthetic User Profile Inferences** | Backend training dataset | Offline synthetic | Fabricates non-existent user habits; violates empirical grounding. | Personal risk layer uses IndexedDB events only. | **EXCLUDED**: Synthetic baseline model kept strictly separate. |

#### 3. Conservative Hybrid Risk Estimator Engine
- **File**: `src/telemetry/personalRiskModel.js` (NEW)
  - Implemented `computeGuardedTaskRisk(task, baselinePrediction, events, personalDurationModel, asOfTime)`:
    - **Cold-Start Guard**: If personal history effective weight $W < 3.0$, returns baseline Random Forest risk unmodified with `is_personalized: false` and explanatory fallback reason.
    - **Raw Signal Clamping**: Raw personal signal delta is clamped to $\pm 15\%$ (`MAX_RISK_ADJUSTMENT = 0.15`).
    - **Bayesian Confidence Shrinkage**: Multiplies raw delta by:
      $$\text{Confidence} = \frac{W}{W + 5.0}$$
      (At $W = 3.0$, multiplier is $3.0 / 8.0 = 0.375$, so a raw $+10\%$ postponement signal yields a cautious $+3.8\%$ applied adjustment).
    - **Probability Bounding**: Clamps final adjusted probability to $[0.05, 0.95]$.
    - **Uncalibrated Disclosure**: Explicitly documents that adjustments are heuristic evidence-based shifts, not calibrated probabilities.
  - Implemented `computeBatchGuardedRisk(predictionsMap, tasks, events, personalDurationModel, asOfTime)`:
    - Batch evaluates all tasks, preserving baseline predictions when tasks lack personal signals or when data is sparse.

#### 4. UI Transparency & Model Governance
- **File**: `src/components/TaskCard.jsx`:
  - Updated delay-risk display to use `delay_probability ?? probability`.
  - Added subtle, pastel-styled personal adjustment pill (`+4%`, `-3%`) with hover disclosure:
    `"Personalized: +4% adjustment from observed habits (Baseline: 52%)"`.
- **File**: `src/components/TaskExplanationModal.jsx`:
  - Added dedicated **Personalization Transparency Card**:
    - Discloses synthetic baseline probability vs. personal adjusted probability.
    - Displays effective sample weight and list of applied personal behavioral signals.
    - Displays explicit fallback notice when baseline is preserved due to sparse data.
    - Explains local-first IndexedDB privacy guarantee.
- **File**: `src/components/PersonalModelDashboard.jsx`:
  - Updated walk-forward evaluation progress to reflect hardened guard ($X / 5$ predictions, $Y / 8$ tasks).
  - Added **Guarded Completion-Risk Architecture** panel detailing active personal signals, Bayesian shrinkage formula, and leakage safeguards.
- **File**: `src/App.jsx`:
  - Derived `guardedPredictionsMap` and `effectiveRiskStats` using `useMemo`.
  - Connected guarded predictions to `ProjectOverview`, `TaskList`, and `TaskExplanationModal`.
  - Immediate reset: verified that clearing telemetry via `telemetry.clearHistory()` immediately resets personal risk adjustments back to baseline.

#### 5. Automated Test Suite & Verification
- **File**: `tests/personal_model.test.js`:
  - Expanded test suite to **53 automated tests across 8 suites** (all passing).
  - Hardened evaluation boundary tests:
    - 0 observations: `insufficient_evaluation_data`, 0 held-out predictions.
    - 5 observations: 2 held-out predictions ($< 5$), `insufficient_evaluation_data`.
    - 7 observations: 4 held-out predictions ($< 5$), `insufficient_evaluation_data`.
    - 8 observations: exactly 5 held-out predictions ($= 5$), status `evaluated`.
  - Guarded personal risk tests:
    - Cold-start fallback ($W < 3.0 \to$ baseline unmodified).
    - Postponement friction bounded adjustment.
    - Maximum adjustment bounds ($\le \pm 15\%$).
    - Temporal leakage safety (future events after prediction time ignored).
    - Target leakage safety (target task duration/completion fields ignored).
    - Duplicate event deduplication idempotency.
    - Immediate reset on history deletion.
    - Batch prediction error handling and risk categorization.

---

### Verification Results

1. **Frontend Test Suite**: `npm test`
   - **53 tests passing across 8 suites** (0 failures, 117ms duration).
2. **Frontend Linter**: `npm run lint` (`oxlint`)
   - **0 errors, 0 warnings** across 25 files.
3. **Production Build**: `npm run build` (`vite build`)
   - Successfully generated production bundle in 290ms (`dist/assets/index-CopoHHtt.js`, 427.69 kB / 127.14 kB gzip).
4. **Backend Pytest Suite**: `python -m pytest backend/tests/ -v`
   - **27 tests passing** (18 date handling tests, 9 ML & API tests).

---

### Known Limitations & Prior State
1. **Classification vs. Heuristic Adjustment**: The baseline Random Forest remains a generic supervised model trained on synthetic data. The personal risk layer does not re-train the decision forest on personal tasks; it applies mathematically bounded Bayesian shrinkage to adjust baseline probabilities.

---

## Phase 4, Stage 1 Execution Record: Adaptive Scheduling Foundations

### Objective
Design and implement a deterministic, local-first adaptive scheduling engine for VoxPlan that transforms static task lists into an evidence-based calendar proposal, respecting user-configured working hours, hard deadlines, supported task dependencies, personalized duration estimates, and guarded completion-risk heuristics without ever silently mutating user data or claiming impossible feasibility.

### Architecture & Engine Implementation

#### 1. Input Auditing & Fallback Matrix
Every input parameter to the scheduling engine is rigorously audited:

| Input Parameter | Source | Type / Unit | Limitation / Failure Case | Fallback Strategy |
|---|---|---|---|---|
| `task.dueDate` | User input | ISO `YYYY-MM-DD` | Missing or invalid date string | Allowed: scheduled in current open slot after urgent/due tasks; marked with `placementStatus: 'on_time'` and explanation. |
| `task.estimatedEffort` | User input | Hours (float) | Missing, non-numeric, $\le 0$ | Neutral fallback to `DEFAULT_TASK_FALLBACK_HOURS = 1.0h`; warning flag attached to placement. |
| `personalDurationModel` | `personalModel.js` | Local model object | Untrained ($W < 3.0$), cold start, or missing category | Transparent fallback to user's original `estimatedEffort`; source tagged as `'cold_start_original'`. |
| `task.dependencies` | User input | Array of `taskId` strings | Circular dependencies or missing parent IDs | Completed parents ignored; missing parents logged; circular cycles detected via DFS 3-color coloring and broken safely. |
| `task.priority` | User input | `'high'`, `'medium'`, `'low'` | Unknown/malformed priority string | Defaults to `'medium'` weight ($200$ pts). |
| `guardedPredictionsMap` | `personalRiskModel.js` | Map of probability objects | Untrained backend / no prediction | Secondary heuristic only: neutral $0$ pts adjustment, zero degradation of core constraint solving. |
| `dailyCapacityHours` | User setting | Hours (default $6.0$h) | $\le 0$ or extreme value | Clamped/defaulted to $6.0$h; oversized single tasks allocate full day with capacity-exceeded warning. |
| `workingDays` | User setting | Array of ints ($0-6$) | Weekend or non-working day | Default weekdays $[1, 2, 3, 4, 5]$; weekend slots are skipped and tasks roll over into next working day. |
| `horizonDays` | User setting | Days (default $14$) | Horizon capacity exhausted | Infeasible tasks marked `placementStatus: 'unscheduled'`, `proposedDate: null`, and explicit explanation provided. |

#### 2. Prioritization & Ordering Rules
Tasks are prioritized deterministically using a transparent scoring function (`calculateTaskPriorityScore`):
1. **Topological Dependency Depth**: Tasks at depth 0 (no prerequisites) are prioritized so that downstream dependent tasks can be scheduled without violation.
2. **Overdue Urgency**: Tasks with deadlines already in the past receive maximum urgency boost ($+5000$ pts).
3. **Earliest Deadline First (EDF)**: Shorter calendar windows to deadline receive higher priority ($+1000 \times (1 - \text{daysRemaining}/30)$).
4. **Task Priority**: `high` ($+300$ pts) $>$ `medium` ($+200$ pts) $>$ `low` ($+100$ pts).
5. **Guarded Delay Risk Heuristic**: Tasks with $P_{\text{delay}} \ge 0.65$ receive $+60$ pts boost to pull them forward in the sprint, mitigating late-sprint risk.
6. **Deterministic Tie-Breaker**: Pure string comparison on `taskId` guarantees 100% identical ordering across identical inputs.

#### 3. Capacity Bin-Packing & Calendar Allocation
- Pure function `generateAdaptiveSchedule(tasks, options)`:
  - Zero mutations to input tasks or options.
  - Builds calendar day slots skipping non-working days.
  - Sequential bin-packing fills each day up to `dailyCapacityHours`.
  - When a task exceeds remaining day hours, it rolls over to the next working day.
  - If a task exceeds the entire daily capacity, it takes an entire day slot as dedicated focus and records a `capacity_exceeded` conflict warning.
  - If the planning horizon is exhausted, unscheduled tasks are flagged with `placementStatus: 'unscheduled'` without silently discarding them.
  - Computes global feasibility status: `'feasible'`, `'infeasible_deadlines'`, `'capacity_exceeded'`, or `'dependency_cycle'`.

#### 4. Safe Proposal & User Control Workflow
- **File**: `src/components/AdaptiveScheduleModal.jsx` (NEW)
  - Interactive pastel-themed proposal modal with brut-pastel shadows.
  - Header displays Feasibility Status Badge and Learned Pace active badge.
  - Interactive configuration bar: adjustable daily working hours ($1-16$h), planning horizon ($7, 14, 21, 30$ days), and toggle between Learned Personal Duration vs. Original Cold-Start effort.
  - Metrics overview ribbon: Tasks scheduled ($X/Y$), proposed date shifts ($N$), deadline warnings ($M$), and capacity utilization ($U\%$).
  - Placements table: shows title, priority, category, original due date, proposed due date (highlighted if shifted), effective hours with duration source tag, placement status, and detailed conflict/placement rationale.
  - Dual action controls:
    - **Apply Schedule**: Performs non-destructive batch update of `tasks` state; records individual `task_rescheduled` telemetry events with `reason: 'adaptive_scheduler'`; records `recommendation_accepted` event; displays success feedback.
    - **Discard Proposal**: Leaves current tasks completely untouched; closes modal.
- **File**: `src/components/ProjectOverview.jsx`
  - Added "✦ Adaptive Schedule" button in sprint progression header alongside "Run predictions".
- **File**: `src/App.jsx`
  - Integrated `isScheduleModalOpen` state and `handleApplySchedule`.
  - Added natural language command triggers: `"plan sprint"`, `"adaptive schedule"`, `"schedule sprint"`, `"open scheduler"`.

#### 5. Automated Test Suite
- **File**: `tests/adaptive_scheduler.test.js` (NEW)
  - 19 automated tests across 7 suites:
    1. Deterministic output & immutability guarantee.
    2. Personalized duration model integration vs. cold-start fallback.
    3. Missing / zero effort fallback handling.
    4. Dependency ordering and topological chain constraint respect.
    5. Circular dependency detection and safe cycle breaking without crashing.
    6. Non-working day skipping (weekend rollover) and oversized task focus allocation.
    7. Deadline conflict reporting (days delayed), overdue task recovery, and horizon capacity exhaustion.
    8. ISO date utilities (`formatDateISO`, `parseDateISO`, `addDaysISO`, `isWorkingDay`).
    9. Core engine primitives (`buildCalendarSlots`, `analyzeTaskDependencies`, `calculateTaskPriorityScore`, and default constants).

---

### Verification Results

1. **Frontend Test Suite**: `npm test`
   - **72 tests passing across 15 suites** (0 failures, 116ms duration).
2. **Frontend Linter**: `npm run lint` (`oxlint`)
   - **0 errors, 0 warnings** across 28 files.
3. **Production Build**: `npm run build` (`vite build`)
   - Successfully generated production bundle in 223ms (`dist/assets/index-BGAb9vnp.js`, 450.03 kB / 133.17 kB gzip).
4. **Backend Pytest Suite**: `python -m pytest backend/tests/ -v`
   - **27 tests passing** (18 date handling tests, 9 ML & API tests).

---

## Phase 4, Stage 2 Execution Record: Scheduling Correctness & Reliability Audit

### Objective
Conduct an incremental correctness and reliability audit of the adaptive scheduler, modal proposal workflow, task dependency graph analysis, working capacity constraints, deadline interpretations, prioritization mechanics, and proposal application safety without rewriting the scheduler or discarding existing pastel UI aesthetics.

---

### Audit Findings & Edge-Case Reproductions

Before modifying production code, suspected edge cases were isolated and reproduced via a dedicated verification script (`scratch/reproduce_edge_cases.mjs`):

1. **Topological Order Inversion**: When a dependent child task had a higher urgent score (due date sooner, priority `high`, or $+60$ delay-risk boost) than its prerequisites, sorting candidates globally by score scheduled the child on Day 0 and its prerequisite on Day 1, inverting the dependency order.
2. **Dependent Placement of Unscheduled Prerequisite**: When a prerequisite was unscheduled due to horizon capacity exhaustion or circular dependencies, the dependent task was placed on Day 0 because `effectiveEarliestDay` defaulted to 0.
3. **Silent Cycle Breaking**: Circular dependency cycles (e.g. $A \to B \to A$) were previously broken silently by setting topological depth to 0 and scheduling both tasks as if all dependencies were satisfied.
4. **Oversized Task Daily Cramming**: Tasks with estimated effort greater than `dailyCapacityHours` (e.g. 10.0h with 6.0h daily capacity) were scheduled as a single day's placement, misrepresenting a multi-day effort as completed within a single 6-hour window without multi-day splitting support.
5. **Capacity Utilization Denominator**: Daily utilization metrics averaged individual day percentages rather than calculating the true ratio of scheduled workload to total available horizon capacity.

---

### Architectural & Correctness Hardening

#### 1. Dependency Handling & Kahn's Topological Ready-Queue
- **Topological Ready-Queue**: Replaced static global sorting with Kahn's topological ready-queue scheduling. A task is only placed into the scheduling candidate queue once **all** of its unfinished prerequisites have actually been placed into calendar slots.
- **Strict Earliest Feasible Date**: A dependent task's search for an open capacity slot begins at `max(scheduledPrerequisiteDates)`. A task is guaranteed never to be scheduled before or on an earlier day than its prerequisites.
- **Completed Prerequisite Handling**: Passed full task state (`tasks`) to `analyzeTaskDependencies` so prerequisites marked `completed: true` are recognized as fulfilled and excluded from the blocking dependency graph.
- **Explicit Cycle Detection & Downstream Propagation**: 
  - Uses 3-color DFS traversal (`WHITE`, `GRAY`, `BLACK`) to identify cycles.
  - Cycle paths are explicitly formatted (e.g. `Task A ➔ Task B ➔ Task A`) and exposed in the proposal.
  - Tasks in cycles and **all downstream dependents** of cyclic tasks are marked `status: 'blocked_by_dependency'`, `proposedDate: null`, and assigned explicit conflict reasons explaining which cyclic or missing prerequisite is blocking them. No fake orderings are invented.
- **Self-Dependencies & Missing Parents**: Explicitly detected and isolated; self-dependent tasks and tasks referencing non-existent parent IDs are marked `blocked_by_dependency` with clear error explanations.

#### 2. Working Capacity & Oversized Tasks Feasibility
- **Oversized Tasks Isolation**: Tasks with `effectiveHours > dailyCapacityHours` are flagged as `status: 'oversized_exceeds_capacity'` with `proposedDate: null` and an explicit note: `"Requires manual resolution: task effort (X.Xh) exceeds daily working capacity (Y.Xh) and multi-day splitting is not enabled."`
- **Strict Daily Working Capacity**: Bin-packing requires `slot.remainingHours >= requiredHours`. A day's cumulative scheduled hours never exceeds `dailyCapacityHours`. When a day has insufficient remaining capacity, the task cleanly rolls over to the next working day slot.
- **Accurate Capacity Utilization Metric**: Computes true scheduled workload against total available capacity across working days in the planning horizon:
  $$\text{Capacity Utilization} = \frac{\sum \text{Scheduled Workload Hours}}{\sum \text{Working Slot Capacity Hours}} \times 100\%$$
- **Invalid / Missing Effort**: Handled safely with fallback to `DEFAULT_TASK_FALLBACK_HOURS = 1.0h` without fabricating misleading precision.

#### 3. Deadlines & Horizon Boundary Policies
- **Inclusive Calendar Deadlines**: Due dates are treated as inclusive end-of-day targets. All date parsing operates on ISO calendar components (`YYYY-MM-DD`) without UTC offset shifting to prevent timezone-dependent off-by-one errors.
- **Non-Working-Day Deadlines**: Deadlines falling on non-working days (e.g. Sunday) are considered on-time if the task is scheduled on the preceding working day (e.g. Friday), matching realistic domain expectations.
- **Overdue at Start**: Tasks with deadlines prior to planning start are prioritized for immediate recovery on Day 0 and flagged with `was_overdue` status.
- **No Deadline Tasks**: Placed flexibly into open capacity slots without false deadline warnings (`placementStatus: 'on_time'`).
- **Horizon Exhaustion**: Tasks that cannot fit within the configured planning horizon are flagged with `status: 'unscheduled'`, `proposedDate: null`, and conflict reason `"Planning horizon capacity exhausted"`. Tasks are never silently dropped.

#### 4. Prioritization Scoring & Hard Constraint Guarantee
- **Hard Constraint Primacy**: Kahn's topological ready-queue mathematically guarantees that ordinary priority scores, deadline urgency, and risk heuristics cannot violate hard dependency prerequisites.
- **Audited Scoring Weights**:
  - Overdue Urgency: $+5000$ pts (ensures overdue recovery dominates normal backlog).
  - Earliest Deadline First (EDF): Up to $+1000$ pts ($1000 \times (1 - \text{daysRemaining}/30)$).
  - Explicit Priority: `high` ($+300$ pts), `medium` ($+200$ pts), `low` ($+100$ pts).
  - Guarded Delay-Risk Boost: $+60$ pts for $P_{\text{delay}} \ge 0.65$ (bounded heuristic influence; cannot reorder tasks across different priority tiers or override deadlines).
  - Deterministic Tie-Breaker: Stable alphanumeric comparison on `taskId`.

#### 5. Safe Proposal Application & Stale Proposal Protection
- **Stale Proposal Guard (`AdaptiveScheduleModal.jsx`)**:
  - Captures a deterministic hash of the active task backlog when opened.
  - Detects if tasks were created, updated, or reordered in the background while the proposal was open.
  - Displays a pastel amber warning banner with a `↻ Regenerate Proposal` button and disables `Apply Schedule` until regenerated against current state.
- **Non-Destructive Batch Application (`App.jsx`)**:
  - Filters out any placements with `status: 'unscheduled'`, `status: 'blocked_by_dependency'`, `status: 'oversized_exceeds_capacity'`, or `proposedDate: null`. Only genuine, valid, feasible placements update `dueDate`.
  - Preserves all other task fields (`title`, `priority`, `estimatedEffort`, `completed`, `dependencies`, `createdAt`).
- **Deduplicated Telemetry**:
  - Emits `recordTaskRescheduled` with `reason: 'adaptive_scheduler'` exactly once per shifted task.
  - Emits `recordRecommendationAction` (`recommendation_accepted`) once per batch.
  - If 0 tasks actually changed dates, no spurious rescheduling events are emitted.
- **Proposal Review UI**:
  - Distinct pastel status badges: `On Time` (mint), `Was Overdue` (amber), `Late` (coral), `Blocked` (muted lavender), `Manual Resolution` (soft rose), `Unscheduled` (neutral).
  - Traceable dependency cycle callout rendering exact path loops.
  - Explicit change counters: Planned placements vs. shifts vs. conflicts.

---

### Automated Test Suite Coverage

- **File**: `tests/adaptive_scheduler.test.js`:
  - Expanded from 19 tests across 7 suites to **28 tests across 8 suites** (total repo tests: **81 tests across 16 suites**, all passing):
    1. Deterministic output, immutability, and deterministic tie-breaking.
    2. Personal duration model integration with cold-start fallbacks and missing effort handling.
    3. Dependency DAG handling:
       - Multi-task linear chains.
       - Topological ordering priority-inversion prevention (urgent child scheduled strictly after parent).
       - Direct 2-task cycles and 3-task indirect cycles with downstream dependent propagation.
       - Self-dependencies and missing prerequisite handling.
       - Completed prerequisites passthrough (`t.completed === true`).
    4. Working hours & capacity feasibility:
       - Weekend rollover.
       - Oversized tasks flagged for manual resolution (`oversized_exceeds_capacity`).
       - Cumulative daily working capacity enforcement (zero day-overrun).
    5. Deadlines, conflicts, and capacity exhaustion:
       - Delayed deadline reporting.
       - Overdue task recovery prioritization.
       - Planning horizon capacity exhaustion (`unscheduled`).
       - Accurate capacity utilization denominator calculation.
       - Non-working day deadlines (Sunday satisfied by Friday).
    6. Date utility functions (`formatDateISO`, `parseDateISO`, `addDaysISO`, `isWorkingDay`).
    7. Core engine primitives and constants.
    8. Schedule proposal safety: non-destructive filtering of invalid/blocked/oversized tasks.

---

### Verification Results

1. **Frontend Test Suite**: `npm test`
   - **81 tests passing across 16 suites** (0 failures, 126ms duration).
2. **Frontend Linter**: `npm run lint` (`oxlint`)
   - **0 errors, 0 warnings** across 28 files.
3. **Production Build**: `npm run build` (`vite build`)
   - Successfully generated production bundle in 215ms (`dist/assets/index-qBc7VAb_.js`, 456.68 kB / 134.89 kB gzip).
4. **Backend Pytest Suite**: `python -m pytest backend/tests/ -v`
   - **27 tests passing** (18 date handling tests, 9 ML & API tests).

---

### Known Limitations & Next Stage

1. **Multi-Day Task Splitting**: Tasks exceeding daily working capacity require manual resolution; automated sub-task chunking or multi-day span representation is deferred to Phase 4 Stage 4.
2. **Intraday Timeblocking**: The scheduler places tasks into day-level capacity buckets rather than specific start/end clock times (e.g. 09:00 - 11:30).
3. **Next Stage Completed**: Proceeded to Phase 4, Stage 3: Schedule Quality Evaluation & Benchmarking.

---

## Phase 4, Stage 3 Execution Record: Schedule Quality Evaluation & Benchmarking

### Objective
Establish an independent, deterministic evaluation module and reproducible benchmark suite to measure schedule quality objectively across multiple dimensions without assuming that the adaptive scheduler is superior simply because it uses more inputs or produces a polished proposal.

---

### Schedule Quality Metric Framework

A dedicated, UI-independent evaluation engine was implemented in `src/scheduler/scheduleEvaluator.js`. It evaluates any generated schedule against raw input tasks across 7 core dimensions:

#### 1. Task Coverage (Exhaustive Accounting Invariant)
Every input task $t \in T_{\text{eligible}}$ is partitioned into exactly one mutually exclusive outcome state:
- $N_{\text{scheduled}}$: Assigned to a working calendar slot on or before the horizon.
- $N_{\text{blocked}}$: Blocked due to circular dependencies, self-dependencies, or missing prerequisites.
- $N_{\text{oversized}}$: Requires manual resolution because effort exceeds `dailyCapacityHours`.
- $N_{\text{unscheduled}}$: Unplaced due to planning horizon capacity exhaustion.

$$\text{Coverage Invariant: } N_{\text{scheduled}} + N_{\text{blocked}} + N_{\text{oversized}} + N_{\text{unscheduled}} \equiv N_{\text{total}}$$
$$\text{Scheduled Rate} = \frac{N_{\text{scheduled}}}{N_{\text{total}}}$$

#### 2. Deadline Feasibility
For all tasks with explicit due dates $T_{\text{deadline}} \subseteq T_{\text{eligible}}$:
- **On-Time Rate**: $\frac{N_{\text{on\_time}}}{N_{\text{deadline}}}$, where on-time accounts for non-working days (e.g. completing on Friday satisfies a Sunday deadline).
- **Average Delay Days**: $\frac{\sum_{t \in T_{\text{late}}} (\text{proposedDate}_t - \text{dueDate}_t)}{N_{\text{late}}}$.
- **Pre-Existing Overdue Tasks**: Tasks with $\text{dueDate} < \text{startDate}$ tracked separately ($N_{\text{was\_overdue}}$) so pre-existing overdue status is not counted as scheduler delay.
- **Impossible Deadlines**: Deadlines belonging to blocked, oversized, or horizon-exhausted tasks ($N_{\text{impossible}}$).

#### 3. Dependency Correctness
For all declared dependency edges $(p \to c)$ among eligible tasks:
- **Satisfied Count**: Prerequisites completed or scheduled on/before dependent ($\text{date}_p \le \text{date}_c$).
- **Violated Count**: Dependent scheduled strictly before prerequisite ($\text{date}_c < \text{date}_p$). (Must be 0 under hard constraint).
- **Blocked Count**: Prerequisite is cyclic, missing, or unscheduled, correctly propagating blocked status.
- **Dependency Integrity Rate**: $\frac{N_{\text{satisfied}}}{N_{\text{satisfied}} + N_{\text{violated}}}$ ($100\%$ required).

#### 4. Capacity Compliance & Workload Utilization
- **Total Scheduled Workload**: $H_{\text{scheduled}} = \sum_{d \in D_{\text{working}}} \text{hours}_d$.
- **Total Working Capacity**: $H_{\text{capacity}} = \sum_{d \in D_{\text{working}}} \text{capacityHours}_d$.
- **Capacity Utilization**: $\frac{H_{\text{scheduled}}}{H_{\text{capacity}}} \times 100\%$.
- **Overrun Violations**: Count of calendar days where assigned workload exceeds daily capacity. (Must be 0).

#### 5. Workload Balance (Daily Imbalance Metric)
Evaluates pacing uniformity across active working days ($D_{\text{active}}$ with hours $h_i > 0$, count $K$):
- **Mean Daily Workload**: $\mu = \frac{1}{K} \sum_{i=1}^K h_i$.
- **Workload Standard Deviation**: $\sigma = \sqrt{\frac{1}{K} \sum_{i=1}^K (h_i - \mu)^2}$.
- **Imbalance Coefficient of Variation (CV)**: $\text{CV} = \frac{\sigma}{\mu}$ (Lower is more uniform; 0 indicates perfectly balanced daily workload).
- **Peak-to-Average Ratio**: $\frac{\max(h_i)}{\mu}$.

#### 6. Planning Horizon Compliance
- **Within-Horizon Coverage**: $\frac{N_{\text{within}}}{N_{\text{total}}}$.
- **Beyond-Horizon Overflow**: Tasks requiring a longer horizon window.

#### 7. Schedule Stability & Perturbation Churn
Given base schedule $S_1$ and perturbed schedule $S_2$:
- **Common Tasks**: $T_{\text{common}} = \{t \mid t \in S_1 \text{ and } t \in S_2 \text{ with proposedDate} \ne \text{null}\}$.
- **Shifted Tasks**: $T_{\text{shifted}} = \{t \in T_{\text{common}} \mid S_1(t).\text{proposedDate} \ne S_2(t).\text{proposedDate}\}$.
- **Churn Rate**: $\frac{|T_{\text{shifted}}|}{|T_{\text{common}}|}$ ($0.0 = \text{completely stable}, 1.0 = \text{total date reshuffle}$).

---

### Fair Baseline Comparisons

Three deterministic strategies execute against **identical hard constraints** (Kahn's topological DAG ready-queue, working days, daily capacity bin-packing, oversized task isolation, weekend rollover):

1. **Adaptive Strategy (Recommended)**:
   - Multi-objective score: Topological depth unblocking ($-100 \times \text{depth}$), overdue recovery ($+5000$ to $+6000$), earliest deadline urgency curve ($+0$ to $+1500$), priority tiers (`high` $+300$, `med` $+200$, `low` $+100$), and bounded guarded risk heuristic ($+60$ for high risk).
2. **Earliest Deadline First (EDF) Baseline**:
   - Ranks ready tasks purely by calendar due date urgency. Ignores priority tiers and risk heuristics.
3. **Priority-First Baseline**:
   - Ranks ready tasks purely by priority tier (`high` 3000, `med` 2000, `low` 1000). Ignores deadlines and risk heuristics.

---

### Empirical Benchmark Findings & Strategy Divergence

The 12 curated scenarios in `src/scheduler/scheduleBenchmarks.js` demonstrate key trade-offs:

| Benchmark Scenario | Tasks | Adaptive On-Time | EDF On-Time | Priority-First On-Time | Hard Constraints Violated | Algorithmic Divergence & Rationale |
|---|---|---|---|---|---|---|
| **1. Normal Mixed Backlog** | 6 | 100% (6/6) | 100% (6/6) | 100% (6/6) | 0 (All) | When capacity is ample, all 3 strategies achieve full feasibility. Adaptive demonstrates lowest workload CV (0.178). |
| **2. Shared Deadline Contention** | 4 | 50% (2/4) | 50% (2/4) | 50% (2/4) | 0 (All) | Daily capacity (6.0h) limits Day 1 to 2 tasks. Adaptive & Priority-First prioritize High-priority tasks on time; EDF tie-breaks arbitrarily on task ID. |
| **3. Priority vs. Deadline Tension** | 3 | 67% (2/3) | **100% (3/3)** | 33% (1/3) | 0 (All) | **Key trade-off:** Low-priority task due Day 0 vs High-priority task due Day 5. EDF schedules Low-priority first (100% on-time). Priority-First schedules High-priority first, delaying Low-priority by 2 days. Adaptive balances both. |
| **4. Linear Dependency Chain** | 4 | 100% (3/3) | 100% (3/3) | 100% (3/3) | 0 (All) | Completed prerequisite (`completed: true`) passed through; chain ($A \to B \to C$) preserved identically across all 3. |
| **5. Dependency Cycle Blocked** | 4 | 100% (1/1) | 100% (1/1) | 100% (1/1) | 0 (All) | 2 cyclic tasks + 1 downstream child isolated with `status: 'blocked_by_dependency'`. Independent task scheduled normally. |
| **6. Oversized Task (> Capacity)** | 2 | 100% (1/1) | 100% (1/1) | 100% (1/1) | 0 (All) | 10.0h task flagged `oversized_exceeds_capacity` for manual resolution; regular task scheduled on time. |
| **7. Insufficient Capacity** | 3 | 67% (2/3) | 67% (2/3) | 67% (2/3) | 0 (All) | 15.0h workload competing for 12.0h capacity before deadline. Exactly 1 task delayed; honestly reported with days delayed. |
| **8. Overdue & Undated Recovery** | 3 | 100% (2/2) | 100% (2/2) | 100% (2/2) | 0 (All) | Overdue task prioritized for immediate Day 0 recovery; undated task scheduled in remaining capacity. |
| **9. Non-Working-Day Deadline** | 2 | 100% (2/2) | 100% (2/2) | 100% (2/2) | 0 (All) | Task due Sunday satisfied on Friday. |
| **10. Horizon Exhaustion** | 6 | 80% (4/5) | 80% (4/5) | 80% (4/5) | 0 (All) | 36.0h workload on 30.0h 7-day horizon. 6th task marked `unscheduled` without silent omission. |
| **11. Personal Model Adjustment** | 2 | 100% (2/2) | 100% (2/2) | 100% (2/2) | 0 (All) | 4.0h task adjusted to 5.0h using learned 1.5x bias ratio with Bayesian shrinkage. |
| **12. Heuristic Delay-Risk Signal** | 2 | 100% (2/2) | 100% (2/2) | 100% (2/2) | 0 (All) | High-risk task pulled forward via bounded $+60$ pt urgency boost. |

---

### Schedule Stability & Perturbation Churn

Measured on a representative 5-task backlog (`STABILITY_BENCHMARK`) under 5 atomic perturbations:

| Perturbation | Mutation Applied | Common Tasks | Shifted Tasks | Churn Rate | Feasibility Justification |
|---|---|---|---|---|---|
| **Add Low-Priority Task** | Added 1.0h task due at end of sprint | 5 | 0 | **0.0%** | Appended to open slot; zero churn on existing tasks. |
| **Change Task Priority** | Task 3 promoted Medium $\to$ High | 5 | 0 | **0.0%** | Task 3 already scheduled before its deadline; zero churn. |
| **Move Deadline +1 Day** | Task 2 deadline moved 1 day later | 5 | 0 | **0.0%** | Existing slot remains valid; no unnecessary reshuffle. |
| **Adjust Duration Estimate** | Task 1 effort changed 3.0h $\to$ 3.5h | 5 | 0 | **0.0%** | Day 1 had 3.0h remaining capacity; absorbed without rolling over. |
| **Add Valid Dependency** | Task 3 made dependent on Task 2 | 5 | 1 | **20.0%** | **Feasible shift:** Task 3 pushed from Day 1 to Day 2 to satisfy prerequisite. |
| **Average Churn Rate** | Across all 5 perturbations | — | — | **4.0%** | High stability; shifts occur only when constraint feasibility requires it. |

---

### Hard Constraints vs. Soft Objectives

- **Hard Constraints (Must Never Be Violated)**:
  - Kahn's DAG ready-queue ensures prerequisites are strictly scheduled on or before dependents.
  - Daily working hours cannot be exceeded ($H_{\text{day}} \le \text{dailyCapacityHours}$).
  - Blocked and oversized tasks are isolated with `proposedDate: null` and explicit conflict reasons.
  - Deadlines cannot be claimed feasible if capacity is insufficient.
- **Soft Objectives (Optimization Trade-Offs)**:
  - Minimizing deadline delay days.
  - Pulling urgent and high-priority tasks forward.
  - Smoothing daily workload variance ($\text{CV}$).
  - Minimizing schedule churn across small updates.

---

### UI Implementation: Strategy Benchmark & Quality Tab

- **File**: `src/components/AdaptiveScheduleModal.jsx`
  - Added sub-navigation tab switcher: `✦ Schedule Proposal` and `⚖ Strategy Benchmark & Quality`.
  - Interactive benchmark scenario selector (Current Active Backlog + 12 standard benchmarks).
  - 3-column side-by-side Strategy Cards (Adaptive, EDF, Priority-First) with pastel accents.
  - Comprehensive quality metrics comparison table.
  - Trade-off & algorithmic divergence narrative.
  - Schedule stability & perturbation churn breakdown.
  - Prominent scientific disclosure stating that benchmarks are synthetic constraint fixtures.

---

### Automated Test Suite Coverage

- **File**: `tests/schedule_evaluation.test.js` (NEW)
  - 12 automated unit tests across 3 suites:
    1. Metric calculation invariants: coverage completeness ($N_{\text{sched}} + N_{\text{blocked}} + N_{\text{oversized}} + N_{\text{unscheduled}} \equiv N$), deadline feasibility, non-working-day deadlines, dependency correctness, workload balance CV, empty input handling.
    2. Schedule stability: 0% churn on identical inputs, shift quantification, full perturbation suite.
    3. Multi-strategy comparison: hard constraint satisfaction across all 3 strategies, priority vs deadline trade-off verification, and full 12-benchmark execution.
  - Total repository tests: **93 tests passing across 19 suites**.

---

### Verification Results

1. **Frontend Test Suite**: `npm test`
   - **93 tests passing across 19 suites** (0 failures, 157ms duration).
2. **Frontend Linter**: `npm run lint` (`oxlint`)
   - **0 errors, 0 warnings** across 31 files.
3. **Production Build**: `npm run build` (`vite build`)
   - Successfully generated production bundle in 196ms (`dist/assets/index-DVA9yIeN.js`, 484.99 kB / 142.36 kB gzip).
4. **Backend Pytest Suite**: `python -m pytest backend/tests/ -v`
   - **27 tests passing** (18 date handling tests, 9 ML & API tests).

---

### Known Limitations & Next Stage (Phase 4, Stage 4)

1. **Interactive Slot Reallocation**: Users cannot currently drag-and-drop individual tasks between days within the proposal modal.
2. **Multi-Day Task Splitting**: Oversized tasks require manual breakdown by the user.
3. **Next Stage (Phase 4, Stage 4: Workload Balancing & Sprint Optimization)**:
   - Interactive calendar heatmaps showing daily capacity utilization.
   - User drag-and-drop manual adjustments to proposed schedule slots before applying.
   - Fine-grained working calendar overrides (holidays, personal days off).



