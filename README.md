# DiGi.GIS.YOLO.UI

DiGi.GIS.YOLO.UI provides the headless prediction runner and WebAPI-backed pipeline orchestrator for Year Built prediction using YOLO and ML.NET.

## The Year Built prediction pipeline

Part of the master plan in [DiGi.YOLO#1](https://github.com/DiGi-Organization/DiGi.YOLO/issues/1). One unattended run, sourced entirely from `api.digiproject.uk`:

```
building_2d + orto_datas -> YOLO detections -> building_data
                         -> ML feature table -> predicted year
                         -> year_built_data + building_data."Predicted year built"
```

`Modify.RunYearBuiltPredictionsAsync` is the orchestrator; `DiGi.GIS.YOLO.UI.ConsoleApp` is the headless run surface. `DiGi.GIS.PostgreSQL.UI` will host the same orchestrator as a tray task.

### Why the pipeline lives here

The orchestrator was first built in `DiGi.GIS.PostgreSQL.UI` and moved here on 2026-09-02.

- **Not in `DiGi.GIS.PostgreSQL.UI`**, because a console runner referencing it inherits `UseWPF`, `UseWindowsForms` and the ASP.NET shared framework for a process that draws nothing.
- **Not in `DiGi.GIS.YOLO`**, which is kept dependency-light for callers that only want the detection translation; the orchestrator needs `DiGi.GIS.WebAPI`, `DiGi.GIS.PostgreSQL` and `System.Drawing`.
- **`.UI` here means "run surface", not WPF.** Everywhere else in the workspace the suffix means a desktop application; this repository holds a library and a console executable, and no window.

### Why `net10.0-windows7.0`

`Modify.SavePredictionImage` - the one encoder the inference export and the training dataset builder share - decodes and re-encodes the stored orthophoto bytes through `System.Drawing.Image`, which is Windows-only from .NET 7 onward. That fixes the target framework, and `NoWarn;CA1416` plus `[SupportedOSPlatform("windows")]` follow from it. The runner cannot be hosted on Linux until that re-encode moves off `System.Drawing` — and it cannot simply be replaced, because the detector's weights are frozen and the export has to stay byte-identical to the one they were trained against.

### Configuration

Three files, all resolved by `Query.ConfigurationFilePath` against the application output. `CopyUserFiles` runs after `CopyFiles`, so anything in the git-ignored `user files` folder overwrites the committed default of the same name.

| File | Committed | Purpose |
|---|---|---|
| `files/GIS_WebAPI_Client.conf` | yes, with `Key=""` | The deny-by-default placeholder. The real key goes in `user files/GIS_WebAPI_Client.conf` and is never committed. |
| `files/YearBuiltPredictionPipelineOptions.json` | yes | The option set, with every write step off and no county named. Copy it to `user files/YearBuiltPredictionPipelineOptions.json` and edit that. |
| `files/YOLOTrainingDatasetOptions.json` | yes | The training dataset option set (`--dataset`, `--check-labels`, `--evaluate-detector`), with no county, no output directory and `CountOnly` on. Copy it to `user files/YOLOTrainingDatasetOptions.json` and edit that. |

**`CountyIds` are county row identifiers, never county codes.** A code is the four character territorial value (`"2212"`); an identifier is a database row running into six figures, and a county whose territory is in several pieces has **one identifier per piece** — name every one of them, so each written row is filed under the part its reference belongs to. Code `2212` (słupski) is identifiers `73482` and `73485`. Getting this wrong used to produce a green run that exported nothing, detected nothing and scored nothing; `Query.UnknownCountyIds` now stops the run and says which identifiers were meant.

Every write step is off in the template on purpose: the pipeline writes deployed data, so a first pass over a county is a read-only one.

### Exit codes

| Code | Meaning |
|---|---|
| 0 | The run completed and no step reported a failure. |
| 1 | The options file could not be read, names no county or no scratch directory, narrows the model's feature contract, names a `ReferencesFilePath` that does not read as a manifest, or sets `ChunkSize` below 1. |
| 2 | The environment preflight failed — this machine cannot run the detector, or the year built model is missing. |
| 3 | No Web API authorization key was found. |
| 4 | A step failed while running. |
| 5 | The run was cancelled. |

Each run logs the **SHA-256 of the detector weights** with its start line and adds it to `YearBuiltPredictionResult.Messages` (`Model SHA-256: …`). Stored detections carry only the run stamp, so this line is what ties a run to the detector that wrote it once `model.pt` has been replaced in place. Weights that exist but cannot be read to hash them are refused (exit code 2).

### Bounded image folders — `ChunkSize`

A county is never exported into one folder. Its buildings are sorted ordinally and split into chunks of at most `ChunkSize` buildings (default 5000, about 55 000 images). Each chunk is exported, detected and recorded on its own ([#30](https://github.com/DiGi-Organization/DiGi.GIS.YOLO.UI/issues/30)):

```
<ScratchDirectory>/<countyId>/
├── chunks/000000/       the chunk's {reference}_{year}.jpeg, removed once its marker is written
├── chunks/000000.json   marker: the chunk's buildings, the ones it had imagery for, the weights' SHA-256, Confidence
├── chunks/000000.bbrf   the detector's results for the chunk
└── results.bbrf         the chunk results joined in order, written once every chunk is scored
```

- **Why.** One flat folder of 1.4 M files collapsed the export of m. st. Warszawa (55417) from about 200 to 6.5–8 images/s, on a machine generating NTFS 8.3 short names. Turning that off (`fsutil 8dot3name set C: 1`) restored 204 images/s, but it is an administrator setting kept per machine, and it was back on a few days later. A bounded folder does not depend on it. It also bounds the disk: at most one chunk of imagery exists at a time when `CleanScratchDirectory` is on.
- **Resume.** With `Resume` on, a chunk whose marker names the same buildings, the same weights (SHA-256) and the same `Confidence` is neither exported nor detected again. A chunk without a matching marker keeps the imagery of its own buildings, so an interrupted export continues, and drops imagery of buildings that moved to another chunk. That happens when `ChunkSize` or the manifest changed. The weights are part of the match because `model.pt` is replaced in place.
- **Score-only runs are unchanged.** They read `results.bbrf` and take the buildings the detector was handed from the markers, since the chunk folders are gone by then. A detection run deletes `results.bbrf` before its first chunk and joins it only after the last, so a run that stopped part way leaves no results to score.
- **A county folder from before #30** (a flat `images/` folder and no `chunks/`) is still read as written when `ExportImages` is off.
- The detector starts once per chunk: about 31 starts for Warszawa at the default.

### Writing detections with new weights

The detection write (`UpdateDetections`) **replaces** each scored building's detection columns across `Years` (default 2008..2025). Every building whose imagery the detector was handed is written. A building it did not fire on is written with those columns set to NULL. Without this, a building the new weights never fire on would keep the previous detector's values, false positives included, beside the new detector's values for its neighbours ([#21](https://github.com/DiGi-Organization/DiGi.GIS.YOLO.UI/issues/21)). Scoring still covers only the buildings the detector fired on.

### Narrowing a run to a dataset's buildings — `ReferencesFilePath`

`ReferencesFilePath` names a `dataset_references.tsv` manifest written by `--dataset`. Every step of the run is then restricted to the manifest's buildings within the named `CountyIds`. This is the detection rewrite a regressor retrain needs ([#22](https://github.com/DiGi-Organization/DiGi.GIS.YOLO.UI/issues/22)): 25 008 labelled buildings take about an hour, where their 217 counties would take weeks.

A manifest that is missing, has no header or names no building refuses the run before any request is sent (exit code 1, step `ReferencesFilePath`). The tray application never sets this option.

Detection-only rewrite of the labelled buildings with candidate weights. `Score` and the two year-built writes are off, so no prediction is stored while the regressor still expects the old detector:

```json
{
  "CountyIds": [ "...the 217 county identifiers of the dataset..." ],
  "ScratchDirectory": "scratch",
  "ModelPath": "user files/YOLO/models/model_train9_fresh.pt",
  "ReferencesFilePath": "D:/YOLO/train9_dataset/dataset_references.tsv",
  "ExportImages": true,
  "RunPrediction": true,
  "Score": false,
  "UpdateDetections": true,
  "UpdateYearBuiltData": false,
  "UpdatePredictedYearBuilt": false
}
```

## The YOLO training dataset

Part of [#12](https://github.com/DiGi-Organization/DiGi.GIS.YOLO.UI/issues/12), built in [#13](https://github.com/DiGi-Organization/DiGi.GIS.YOLO.UI/issues/13). The `train8` dataset is lost, so the detector's training set is **rebuilt from the deployed database** through `api.digiproject.uk`. Three console modes share one options file, `YOLOTrainingDatasetOptions.json`:

| Mode | Entry point | What it does |
|---|---|---|
| `--dataset [options.json]` | `Modify.AppendYOLOTrainingDatasetAsync` | With `CountOnly` it counts: labelled buildings, the split, the Legacy agreement table, bounded entries, cross-part duplicates and a size estimate. It requests no orthophoto and writes nothing. Without `CountOnly` it builds a fresh dataset into `OutputDirectory`, and the build can be resumed. |
| `--check-labels [options.json]` | `Modify.CheckYOLOTrainingDatasetLabels` | Runs `ModelPath` (the current detector) over a seeded sample of positive Train/Validate images. Reports the IoU of each label box with the best detection (mean, median, share ≥ 0.5, per county) and writes overlays to `ReportsDirectory/label_check`. |
| `--evaluate-detector [options.json]` | `Modify.EvaluateYOLODetectors` | Runs every file in `WeightsPaths` over the same Test images. Scores each first detection year against its label (MAE, RMSE, exact share) for all Test buildings and for the **clean** subset (Test ∧ ¬Legacy). Prints one row per weights file per subset. Nothing is written to the API. |

Run them in this order: `--dataset` with `CountOnly` (post the output on #12), then `--dataset`, then `--check-labels` (stop on a low IoU), then train, then `--evaluate-detector`.

**Precondition:** the Year Built building-data update has run since the last user edits. The labels are read from the `User year built` column that update writes.

### Data sources

| Data | Table | Read with |
|---|---|---|
| Label | `building_data` column `User year built` | `Query.UserYearBuiltsAsync`: paged by reference, then `DiGi.GIS.IO.Query.YearBuiltLabels` (most frequent exact user year, the regressor's rule). A page that fails fails the whole county part. |
| History, Test buildings only | `year_built_data` | `Query.StoredYearBuiltDatasAsync` with `fallbackbyreference=true`. It returns every row per reference and the references of pages that failed. |
| Footprint | `building_2d` | `Query.Building2DsAsync`: sent with the county first, then misses are retried without it (server fallback by reference). |
| Orthophotos | `orto_datas` | `Query.OrtoDatasAsync`: same fallback as the footprints. |
| Cross-part duplicates | `building_2d` | `Query.ReferenceDuplicatesAsync`. The endpoint is global, so `CountOnly` filters the rows to the named parts. |

### Labelling rule

- **Eligible:** only references with a label. A reference found under several named county parts is built once, under the lowest identifier. Conflicting labels are counted.
- **Split:**
  - A reference that `DiGi.GIS.IO.Query.Holdout(reference, HoldoutDenominator)` holds out goes to **Test only**. These are the same buildings the regressor holds out.
  - The remaining references are sorted ordinally. A seeded `Random(Seed)` then puts a `ValidateWeight` share of them in Validate and the rest in Train.
- **Images:** one per orthophoto year, the first of each year in date order. Each is saved by `Modify.SavePredictionImage`, the encoder the inference export uses, as `{reference}_{year}.jpeg` with an invariant-culture year.
- **Positive** (`year >= label`): one box of class `Building` (index 0). The box is the footprint's bounding box (a clone) grown by `Offset` metres, projected with `OrtoData.ToOrto`, and **clamped to the image** (`Query.PixelBoundingBox`). It is normalised by the saved image's **pixel** size. If the box has no area inside the image, the image is not written.
- **Negative** (`year < label`): the image is registered with an empty label file.
- **Duplicates:**
  - Identical photo bytes under two years with **conflicting** labels are both dropped.
  - Identical bytes with **agreeing** labels are kept once, at the earliest year.
  - Everything dropped or merged is counted.

### The `Legacy` rule

`train8` saw an unknown set of buildings. A Test building is **Legacy** when either of two records places it there (`Query.LegacySource`):

- the list in `LegacyReferencesFilePath` names it. This is `DiGi.GIS.ML/Data/Data_2025.05.27.tsv`; copy it into `user files/`.
- any user entry of any stored row is undated, or dated before `LegacyCutoff` (`2025-05-23T00:00:00Z`, `train8`'s save date).

The two are combined as a union, so doubt removes a building from the clean subset rather than adding one.

The manifest records the result in `LegacySource`: `tsv`, `timestamp`, `both`, empty (clean), or `unknown`. `unknown` means the county part's history could not be read in full; those buildings count as Legacy, never clean, and the step is reported as failed. Train and Validate buildings carry only the list part, because their Legacy flag feeds no metric.

### Output and resume

The dataset's layout:

- `conf.yaml`: an absolute `path:` and `names: 0: Building`.
- `images/{train,val,test}` and `labels/{train,val,test}`.
- `dataset_references.tsv`, the **manifest**, with columns `Reference, CountyId, Category, Label, Legacy, LegacySource`.

The manifest is also the resume journal:

- A building's images and label files are written first, and its row is appended after them.
- A building the manifest names is complete, and a resumed run skips it.
- The files of a building it does not name (left half-written by a stopped run, matched by the reference before the last `_`) are removed and rebuilt.
- A building with no footprint or no imagery is not journaled, so a later run looks for it again.

The build refuses:

- a non-empty `OutputDirectory` that is not a dataset it started;
- an existing dataset when `Resume` is off.

### Options — `YOLOTrainingDatasetOptions`

| Member | Default | Used by |
|---|---|---|
| `CountyIds` | none — required | `--dataset` |
| `OutputDirectory` | none — required, absolute | all |
| `CountOnly` | `false` (the committed template: `true`) | `--dataset` |
| `Resume` | `true` | `--dataset` |
| `LegacyReferencesFilePath` | `user files/Data_2025.05.27.tsv` | `--dataset` |
| `LegacyCutoff` | `2025-05-23T00:00:00Z` | `--dataset` |
| `Offset` | `1` (metres) | `--dataset` |
| `ValidateWeight` | `0.1` | `--dataset` |
| `HoldoutDenominator` | `5` (the regressor's) | `--dataset` |
| `Seed` | `0` | `--dataset`, `--check-labels` |
| `MaxConcurrentRequests` | `8` | `--dataset` |
| `ReferenceBatchSize` | `10000` (clamped to the endpoint cap) | `--dataset` |
| `ReferenceDuplicateLimit` | `100000` | `--dataset` with `CountOnly` |
| `PythonPath`, `WorkingDirectory` | `null` | `--check-labels`, `--evaluate-detector` |
| `ModelPath` | `user files/YOLO/models/model.pt` | `--check-labels` |
| `Confidence` | `0.1` (production) | `--check-labels`, `--evaluate-detector` |
| `LabelCheckSampleSize` / `LabelCheckOverlayCount` | `500` / `20` | `--check-labels` |
| `ReportsDirectory` | `user files/reports` | `--check-labels` |
| `WeightsPaths` | `null` | `--evaluate-detector` |
| `Years` | `null` (2008–2025) | `--evaluate-detector` |

### Exit codes of the dataset modes

The prediction run's codes, with these meanings:

| Code | `--dataset` | `--check-labels`, `--evaluate-detector` |
|---|---|---|
| 0 | completed, no failed step | completed, no failed step |
| 1 | the options cannot be read, have no absolute `OutputDirectory` or no county, the scope is unknown, the legacy list cannot be read, or the output folder is refused | the options or the dataset (manifest, `conf.yaml`, images) cannot be read, or no weights are named |
| 2 | — | the weights or the interpreter are missing |
| 3 | no Web API key | — (these modes read nothing from the API) |
| 4 | a step failed while running (a county's labels or history, footprints, the final write) | the detector failed |
| 5 | cancelled; the manifest lets a re-run continue | cancelled |

### Disk and time

`CountOnly` estimates:

- **Requests:** one orthophoto read per building, plus the paged footprint reads.
- **Images:** 8 per building.
- **Disk:** about 16 kB per image.

These are rough figures from one sample building, meant to give the order of magnitude. A county of 30 000 labelled buildings is therefore about 30 000 orthophoto requests, 240 000 images and 4 GB. At `MaxConcurrentRequests = 8`, requests are the bottleneck, so measure the first county before scheduling the rest.

## Retraining the detector — `--train`

`--train [path-to-YOLOTrainingRunOptions.json]` runs the retraining as one run, stopping at the first failed step. The steps always run in this order, and `Steps` narrows them (null runs all):

1. `Dataset` — `--dataset`: builds the training dataset, or appends to the folder that already exists (resumable).
2. `LabelCheck` — `--check-labels`.
3. `Train` — `DiGi.YOLO` `Modify.Train` from `StartWeightsPath`, a `.pt` checkpoint (an earlier detector) or the base `yolo26x.pt`. With `ResumeTraining` it continues the run's own `weights\last.pt` instead.
4. `Validate` — `Modify.Validate` on the Test split. Without `Train` it measures the start weights, the baseline a candidate is compared with.
5. `Evaluate` — `--evaluate-detector` over `DatasetOptions.WeightsPaths` plus the trained weights.

The trained weights are copied to `<ProjectDirectory>\<RunName>\<RunName>.pt`, a new file that is never overwritten and never named `model`. The start weights and the copy are printed and logged with their **SHA-256**, and the copy is re-hashed and compared with the digest the training reported, so every row of the comparison table names exactly which file it measures. Every path is made absolute, and everything that can be known without starting a process — a missing start file, an unusable interpreter, a run name that is taken, a `ProjectDirectory` inside a `YOLO\models` folder, an empty Validate split — is refused before the first step, with the option it concerns as the step name.

The `Train` step needs a non-empty Validate split, because ultralytics trains against it: a small dataset has none, since the non-Test buildings are drawn one by one against `ValidateWeight`, and with the defaults (`Seed 0`, `ValidateWeight 0.1`) the first Validate building is the 16th non-Test one. A run that trains on the dataset as it stands is checked in the preflight (before the interpreter is probed); a run that still builds the dataset is checked once it is final, after the `Dataset` step. A `ResumeTraining` run is never checked — its checkpoint was trained on a dataset that already held a Validate split. The refusal names the split and the remedy, and the `Dataset` step reports its Train / Validate / Test building counts, warning when Validate is 0.

With no working directory named, the interpreter preflight runs in its own scratch folder (`%TEMP%\DiGi_YOLO_Preflight`) and never writes into the dataset directory, so a new dataset directory stays empty for the `Dataset` step to build. The training itself still uses the dataset directory — the folder holding `conf.yaml` — once the dataset exists.

Progress lines are the same `[PROGRESS]` / `[INFO]` lines as the other modes. The nested `DatasetOptions` is a plain object, exactly as in a `YOLOTrainingDatasetOptions` file.

### Options — `YOLOTrainingRunOptions`

| Member | Default |
|---|---|
| `DatasetOptions` | none — required, with an absolute `OutputDirectory`; `PythonPath` and `WorkingDirectory` of the run take precedence over its own |
| `StartWeightsPath` | none — required for `Train` and `Validate`; ignored when `ResumeTraining` is set |
| `ResumeTraining` | `false` — continue the interrupted run named by `ProjectDirectory` + `RunName` instead of starting a new one (see below) |
| `RunName`, `ProjectDirectory` | none — required for `Train` (the folder is absolute) |
| `Epochs` / `Patience` / `ImageSize` / `Batch` / `Seed` | `150` / `50` / `640` / `16` / `0` (the `DiGi.YOLO` README); ignored when `ResumeTraining` is set |
| `AutoResumeCount` | `0` — the runner's own retries after a stall or a crash; the tray sets `3` (see below) |
| `InactivityTimeout` | `null` — the `DiGi.YOLO` default, 15 minutes; a `TimeSpan` such as `00:15:00` overrides it, and `0` disables the limit |
| `Device`, `PythonPath`, `WorkingDirectory` | `null` |
| `Steps` | `null` — all; the committed template lists only `Dataset`, and counts |

### Recovering an interrupted run — `ResumeTraining`

Set `ResumeTraining` to `true` to continue a run whose training was stopped instead of starting a new one. The run keeps its name: it is identified by `ProjectDirectory` + `RunName` and continues `<ProjectDirectory>\<RunName>\weights\last.pt` at the next epoch, in the same folder. Nothing is copied or renamed by hand, and after the training the runner copies, re-checks, validates and evaluates exactly as a fresh run does.

- `StartWeightsPath`, `Epochs`, `Patience`, `ImageSize`, `Batch` and `Seed` are **ignored** and logged as ignored — the checkpoint restores them, and the epoch ceiling is fixed by the checkpoint. A different ceiling is a new run, not a resume. `Device`, `PythonPath`, `WorkingDirectory`, `DatasetOptions` and `Steps` still apply.
- `Steps` must name `Train` and must **not** name `Dataset`: a resume never rebuilds the dataset the checkpoint was trained on. `null` (all steps) includes `Dataset`, so list the steps explicitly, for example `["Train", "Validate", "Evaluate"]`.
- A resumed run is **not bit-identical** to an uninterrupted one (the dataloader RNG restarts). The log and the result say `Resuming … from epoch N of M`, and the final table's `Start` row reads `Start (resume of epoch N)`.

The run is refused before the training starts, with the reason named by its option (exit code `1`), when:

| Check | Refusal |
|---|---|
| `Train` step not selected | `ResumeTraining` without training |
| `Dataset` step selected | a resume never rebuilds the dataset it was trained on |
| `<ProjectDirectory>\<RunName>` missing, or no `weights\last.pt` | nothing to resume |
| `<ProjectDirectory>\<RunName>\<RunName>.pt` exists | the run completed; choose a new run name |
| the checkpoint cannot be read, is finished, or records a dataset that is gone | the checkpoint is not resumable |
| the checkpoint records a different project or name | the folder was moved or renamed; ultralytics would write elsewhere |

### Stalls and automatic resume — `AutoResumeCount`

A training can stop producing output while staying alive — a data-loader deadlock holds the GPU with every process at 0 % CPU — or its process can die with a driver fault. `DiGi.YOLO` ends a run whose output stays silent for `InactivityTimeout` (15 minutes by default) and reports it as stalled rather than cancelled. `AutoResumeCount` makes the runner continue such a run by itself, up to that many times, without an operator.

- Only a **stall** or a **crash** (a non-zero exit code from a process that started) is resumed. A refusal raised before a process started, a finished checkpoint and a stop requested with Ctrl+C are never resumed.
- Each resume first copies `weights\last.pt` to `weights\last_autoresume<N>_<yyyyMMdd_HHmmss>.pt`, then continues from `last.pt` with the epoch ceiling the checkpoint holds. The copy keeps the previous checkpoint recoverable if the process is killed while saving.
- The log says `Training stalled at epoch E (last output hh:mm:ss) - automatic resume N of M`, or `Training exited with code X at epoch E - automatic resume N of M`, preceded by the last 30 lines of the crashed attempt's error output (`  | …`, its traceback), or by `The attempt that exited with code X wrote no error output - …` when a process ended from outside wrote none. The attempt that ends the run is logged the same way, ending `- no automatic resume left (M of M used)` (or `- automatic resume is off (AutoResumeCount 0)`), and the closing `Resumed automatically N time(s): Stalled at epoch E (hh:mm:ss), …` names the same interrupted epochs; the final table names each resume, and the result records them in `AutoResumes`. The tray reads those lines for its live status.
- The default is `0` — no retries — because a library must not retry unasked; the tray offers `3` for an unattended run. `InactivityTimeout` is a `TimeSpan` such as `00:15:00`; leave it unset for the `DiGi.YOLO` default, and note that `0` disables the limit rather than meaning "immediately".
- A run still dies with the tray or a power cut: automatic resume shortens a stall or a crash, it does not make a run survive. That recovery is `ResumeTraining` above.

### Exit codes of `--train`

The prediction run's codes, plus two:

| Code | Meaning |
|---|---|
| 0 | every step that was asked for completed |
| 1 | an option cannot be used (options, dataset, start weights, run name, project folder, resume) or the dataset step refused its scope |
| 2 | the interpreter or weights are missing, or the interpreter cannot run the training |
| 3 | no Web API key (only when `Dataset` runs) |
| 4 | the dataset build, the label check or the evaluation failed while running |
| 5 | cancelled; earlier outputs are left as they are and the dataset manifest lets a re-run continue |
| 6 | the training did not produce weights |
| 7 | the trained weights could not be validated on the Test split |

`Query.YOLOTrainingRunExitCode` maps a `YOLOTrainingRunResult` to these codes; failed steps are listed as `YOLOTrainingStep.<Step>` so a dataset split named `Train` is never read as a failed training.

## 💻 Coding Guidelines for Developers & AI Agents

To maintain codebase health, performance, and compatibility within Visual Studio 2026 / C# 10+ environments, all developers and AI agents must strictly comply with these guidelines.

### 1. General Coding Standards
1. **English only** — identifiers and comments.
2. **Explicit typing — no `var`** (unless the compiler forces it, e.g. anonymous types). Use target-typed `new(...)` when the type is declared (avoids IDE0090): `PointNode pointNode = new();`. Use collection expressions `[]` for collections (avoids IDE0028): `List<int> numbers = [];`, `int[] array = [1, 2, 3];`.
3. **Variable naming:** start with the type name in camelCase, adding a `_`-suffixed qualifier when needed (`PointNode pointNode_Base`, `pointNode_Temp`).
   - **Collections:** don't prefix with the collection type — use the element type pluralized (`FilterConditions`, not `Conditions`/`listConditions`; `FilterGroups`, not `Groups`/`listGroups`).
   - **Property matching its value type:** if a value type is fully descriptive and unique in the class, name the property after the type (`public AggregateFunction AggregateFunction { get; set; }`).
   - **Primitives** may use plain camelCase (`double tolerance`, `string name`, `int count`).
4. **Zero warnings/analyzer messages** — nullability, parameter validation, clean code.
5. **C# 10+ / C# 13/14** (`LangVersion` ≥ 10) — modern features (enhanced pattern matching, target-typed `new`, collection expressions, `System.Threading.Lock`, etc.) are fine within these architectural constraints. **Namespaces must be block-scoped** (as in every example below); file-scoped namespaces are disallowed and enforced via `.editorconfig` (`csharp_style_namespace_declarations = block_scoped`). See `Coding - Editor Config.md` for the unified baseline rules.
6. **Parameter Line Breaks (`<= 7` Rule):** If a method, constructor, or delegate declaration has 7 or fewer parameters, keep them on a single line however long the line becomes. Multi-line parameter lists are reserved for 8 or more parameters (strictly one parameter per line, enforced via `DIGI0001`). Call sites prefer single-line but allow multi-line formatting when arguments are complex expressions, lambdas, or object initializers.
   - **Correct (<= 7 parameters):**
     ```csharp
     public void Calculate(double centerX, double centerY, double radius, double? storeyHeight = null)
     {
     }
     ```
   - **Incorrect (<= 7 parameters):**
     ```csharp
     public void Calculate(
         double centerX,
         double centerY,
         double radius,
         double? storeyHeight = null)
     {
     }
     ```
   - **Correct (>= 8 parameters, one per line):**
     ```csharp
     public void Calculate(
         double centerX,
         double centerY,
         double radius,
         double? storeyHeight,
         double wallThickness,
         double slabThickness,
         string materialName,
         CancellationToken cancellationToken = default)
     {
     }
     ```
7. **Async method naming:** All asynchronous method names must end with `Async`.
   - **Example:**
     ```csharp
     public async Task<IActionResult> GetDetailsByReferenceAsync([FromQuery(Name = "reference")] string? reference)
     ```
8. **`CancellationToken` is always the LAST parameter (CA1068).** This holds for every method — public, private, static, extension, local — and for every overload. When adding a new optional parameter to an existing signature, insert it *before* the token; never append after it.
   - **Correct:**
     ```csharp
     public static async Task<bool> ClearAsync(NpgsqlConnection? npgsqlConnection, string tableName, int commandTimeout = 30, CancellationToken cancellationToken = default)
     ```
   - **Incorrect** — appending after the token is the usual way this rule gets broken:
     ```csharp
     public static async Task<bool> ClearAsync(NpgsqlConnection? npgsqlConnection, string tableName, CancellationToken cancellationToken = default, int commandTimeout = 30)
     ```
   - The `<param>` tags in the XML doc block must be reordered to match, so the docs still mirror the signature exactly.
   - **Pass the token by name at call sites** — `cancellationToken: cancellationToken` — whenever intervening parameters are left at their defaults. Positional calls silently rebind if the signature is ever reordered again; named arguments turn a reordering into a compile error rather than a wrong-argument bug.
   - **Detection:** `grep -rnE "CancellationToken [a-zA-Z_]+( = default)?, " --include=*.cs .` — every hit that is not the final parameter is a violation.
9. **Simplify member access (IDE0002/IDE0001) — but verify the binding first.** Inside the `DiGi` root, drop any namespace qualifier the compiler does not need; a `DiGi.` prefix on a type that already resolves is redundant noise.
   - **Correct** — in `namespace DiGi.GIS.PostgreSQL.UI.Classes`, `Serilog` resolves up the enclosing chain to `DiGi.Serilog`:
     ```csharp
     Serilog.Modify.Log(Serilog.Enums.LogEventLevel.Error, "Import failed");
     ```
   - **The exception — innermost-namespace shadowing.** C# resolves the FIRST segment against each enclosing namespace from innermost outwards, and once it binds there is **no fallback**. From `DiGi.GIS.PostgreSQL.UI.Classes`, `WebAPI` binds to `DiGi.GIS.WebAPI` (not `DiGi.WebAPI`), so the qualifier must stay:
     ```csharp
     postResponse = await DiGi.WebAPI.Query.GetAsync<Building>(httpClient, requestUri, postOptions);
     ```
     The same trap applies to `Core`, `Geometry`, `Analytical` and any other segment that repeats at several depths.
   - **Method:** remove the qualifier, then **rebuild**. A shadowed name usually fails with CS0234/CS0246 — restore the prefix and leave a short comment saying why. Never shorten a qualifier you have not compiled. If BOTH namespaces expose a matching member, the shortened form compiles and silently calls the wrong one — keep the qualifier regardless of the analyzer suggestion.
10. **Project Structure:** Assume the C# codebase consists of multiple SEPARATE projects, not a single monolithic solution. Handle namespaces and references accordingly.
11. **Output Optimization:** Prioritize highest code quality and output token minimization. Skip conversational filler, polite introductions, and conclusions. Output only the necessary code, logic, or requested explanations.
12. **Temporary code markers:** code that exists only until a migration completes is tagged `TODO [MarkerName]:` at every site, where `MarkerName` is PascalCase and names the migration rather than the issue (`[ReferenceFormat]`, `[ReferencedObjectIndexes]`) — one tag reused everywhere, so `grep -rn "MarkerName"` returns the whole deletion checklist.
   - Every marker states its **removal condition**: the observable fact that makes deletion safe ("once every deployed database has run this DDL at least once"), not just that the code is temporary. Name the tracking issue when there is one.
   - Inline comment at the site; file header above the `using` block when the whole file is temporary (`DiGi.Core/Query/TryParseLegacy.cs`); `[TEMPORARY]` as the first token of the XML `<summary>` when removing a whole public member would be a public-API change (`DiGi.GIS.WebAPI.UI/Controllers/SolarController.cs`).
   - Mark only what is actually temporary — permanent code shipped alongside it must not carry the tag.
13. **`ToString()` is not a key.** `Range<T>.ToString()` and `$"[{min}, {max}]"` follow `CurrentCulture`, so a dictionary keyed on them files `[0,5, 12,25]` under pl-PL and nothing throws. Anything used as an identity - a dictionary key, a stored reference, a hash input - renders through `CultureInfo.InvariantCulture` (`"R"` for floating point with `-0.0` folded, `G29` for decimal, ticks for `DateTime`); `DiGi.Typology.Visual.Query.Key` is the reference renderer and its fact re-runs the assertions under `pl-PL`. An `object`-typed value comes back from a JSON reload as `double`, so such a key must also be width-agnostic.
14. **A member resolved by name through reflection is a contract on the whole hierarchy.** `Typology.Query.RuleData` calls `GetMethod(nameof(RuleData))`, which silently forbids any derived rule from hiding `RuleData` with `new`. Document such a lookup at the reflection site and on the base type, prefer a non-generic interface member while the design is open, and probe `GetMethod` behaviour with a scratch app rather than reasoning about it.
15. **No caching in an optimization unless the request explicitly allows it.** No static `Dictionary`/`ConcurrentDictionary`, memoized reflection or cached `MethodInfo`/`Type` lookups: a cache adds static mutable state, thread-safety obligations and unbounded memory to a library every host loads (the `DiGi.Core` caches in `Description`, `Serialize`, `Value` and `Clone` were all rolled back). Remove allocations, avoid repeated enumeration, build a one-pass `HashSet`/`Dictionary`; if a cache really is the fix, propose it with the measurement and ask first.

---

### 2. Architecture & Project Structure (DiGi.Core Pattern)
Data models are strictly separated from business logic (anemic models + static extension methods). Follow this structure for all new features.

**Data models:**
- **Classes** → `/Classes`, ns `[Project].Classes` — lightweight (properties + basic constructors only), **no** complex logic.
- **Interfaces** → `/Interfaces`, ns `[Project].Interfaces`.
- **Enums** → `/Enums`, ns `[Project].Enums`.

**Business logic** — all complex behavior is an extension method in one of static partial classes; never create a manager/service class:
- **`Query`** (`/Query`) — returns a result from a query; does NOT modify the source (e.g. translating dynamic filter groups into SQL/parameterized commands).
- **`Modify`** (`/Modify`) — modifies the state/properties of the existing object.
- **`Create`** (`/Create`) — creates and returns a completely new object from input data.
- **`Convert`** (`/Convert`, subdirs `/Convert/To[TargetArea]` e.g. `/Convert/ToSystem`, `/Convert/ToEPW`, `/Convert/ToDiGi`) — converts/formats/transforms an object or raw components into another representation; method names follow `To[TargetArea]_[TargetType]` (`ToSystem_String`, `ToSystem_DateTime`, `ToEPW_DateTime`).

### Exception — interface-contract members are implemented ON the class
The anemic-model + static-extension rule governs behavior that is **not** part of an interface the `/Classes` type implements. When a method is declared on an interface the class implements, it MUST be a normal **instance method on that class** — C# offers no other way to satisfy the contract, and moving it to a `Query`/`Modify` extension leaves the interface unimplemented (CS0535).

This is the deliberate design for **behavior-rich geometry primitives**. `DiGi.Geometry`'s `Ellipse2D`, `Circle2D`, `Segment2D`, `Polygon2D`, `Rectangle2D`, their spatial counterparts, etc. implement rich behavioral interfaces and therefore carry their behavior as instance methods — for example `IBoundable2D.GetBoundingBox()`, `ITransformable2D.Transform(...)`, `IMovable2D.Move(...)`, and `IClosedCurve2D.{GetInternalPoint, InRange, Inside, GetArea}`. These types are **not** anemic, and that is correct.

- **Do not "migrate" a geometry primitive's instance methods to `Query`/`Modify` extensions, and do not flag them as anemic-model violations.** Deleting a contract implementation breaks the interface and diverges from the entire library.
- **Before proposing to move or remove such a method, check the interface chain first** (the `I*2D` hierarchy under `Planar/Interfaces` / `Spatial/Interfaces`). Only behavior that is genuinely not a contract member — and that belongs to a data model rather than a geometry primitive — goes into the static partial classes.
- **Private helpers are allowed on such a class.** The "strictly avoid private methods" rule below is scoped to the static partial utility classes (`Query`/`Modify`/`Create`/`Convert`), not to `/Classes` types that implement behavioral interfaces.

### Constructors stay cheap — the work belongs in a `Create` factory
**A constructor on a `/Classes` type assigns and clones. Nothing else.** No validation sweep, no normalisation, no cleanup pass, no geometric or numeric computation — not even an `O(n)` scan over a collection the caller just handed over. A constructor sits on the hot path of every clone, every copy constructor and every deserialization, and a caller who already holds clean data must not pay for a check it does not need.

- **Any such work goes into a `Create` factory** named after the type it returns, at `/Create/[TypeName].cs`. The factory does the work, then calls the plain constructor. It returns the type as **nullable** and returns `null` when the input cannot make a valid object — the guard is a return value, not an exception.
- **Order inside the factory:** materialise and filter the input → run the cleanup → *then* check the result is still valid. Validating before the cleanup measures the wrong thing: a ring of three positions that repeats a corner passes a "three or more" check and then becomes a two-corner polygon.
- **Document the split on both sides.** The constructor's `<summary>` points at the factory for callers whose data is not already clean; the factory's `<summary>` says what it removes and why the constructor does not.

Reference: `DiGi.Geometry.Planar.Create.Polygon2D(IEnumerable<Point2D?>?, double)` and `DiGi.Geometry.Spatial.Create.Polygon3D(IEnumerable<Point3D?>?, double)` both drop points repeating their predecessor via `Modify.RemoveDuplicates(..., closed, tolerance)` *before* checking the corner count, while `Polygon2D`'s constructors store whatever they are given.

```csharp
// /Classes — plain assignment, no work
public Polygon2D(IEnumerable<Point2D>? point2Ds)
    : base(point2Ds)
{
}

// /Create — the work lives here, and the guard runs after it
public static Polygon2D? Polygon2D(this IEnumerable<Point2D?>? point2Ds, double tolerance = DiGi.Core.Constants.Tolerance.Distance)
{
    if (point2Ds == null)
    {
        return null;
    }

    List<Point2D> point2Ds_Temp = [];
    foreach (Point2D? point2D in point2Ds)
    {
        if (point2D != null)
        {
            point2Ds_Temp.Add(point2D);
        }
    }

    point2Ds_Temp.RemoveDuplicates(true, tolerance);

    if (point2Ds_Temp.Count < 3)
    {
        return null;
    }

    return new Polygon2D(point2Ds_Temp);
}
```

### File organisation — one member per file
- **`Query`/`Modify`/`Create` hold exactly one public method per file, and the file is named after that method** (`/Spatial/Query/NearestIndexes.cs` holds `NearestIndexes`). Do **not** group related methods into one file — `TryGetNearestIndexes`, `NearestIndexes` and `NearestNeighbors` are three files, not one.
  - **Overloads are the same method and stay together.** Every `Triangle3D(...)` overload lives in `Triangle3D.cs`; the plural `Triangle3Ds(...)` is a different method name and gets `Triangle3Ds.cs`.
  - A helper promoted to `public static` under the encapsulation rule below gets its own file too, named after the helper.
  - **`Convert` is the exception** and keeps its file-per-TARGET-type layout, `/Convert/To[TargetArea]/[TargetType].cs`.
- **Nested types get their own file, `[Outer].[Inner].cs`**, beside the outer type's file, carrying only the nested type and declaring the outer type `partial` — `/Spatial/Classes/PointCloud3D.Point.cs` and `/Spatial/Classes/PointCloud3D.Enumerator.cs` sit next to `/Spatial/Classes/PointCloud3D.cs`. Keep the type nested; promoting it to top level changes the public API and the bare name rarely stands alone (`Point`, `Enumerator`). The repeated outer `partial` declaration carries no XML `<summary>`, per the "do not document `partial` class declarations" rule.

### Method Encapsulation and Reusability in Utility Classes
- **Strictly avoid creating private methods** within `Query`, `Convert`, `Modify`, and similar partial utility classes.
- If a helper method has well-defined inputs, no side effects, and high reusability, implement it as a **public static method** within the appropriate partial class (e.g., `Query`, `Convert`, `Modify`).
- If a helper method is strictly single-use or specific to a narrow scope, implement it as a **local function (inline method)** directly inside the method you are currently implementing.

### Convert Class Pattern (conversion methods)
`public static partial class Convert` is the **first choice** for any method that transforms an object into another representation — including performance-oriented variants that avoid defensive cloning. Never implement a conversion as an instance method on a `/Classes` model; model classes stay anemic.

The pattern, as established across the `Convert` folders (reference: `DiGi.Geometry/Planar/Convert`):

- **Folder/file layout:** `/Convert/To[TargetArea]/[TargetType].cs` — one file per TARGET type, named after the target type; all source-type overloads converting to that target live in that file (e.g. `ToNTS/LinearRing.cs`, `ToDiGi/Polygon2D.cs`, `ToNTS/Coordinates.cs`).
- **Method shape:** `public static` **extension method on the SOURCE type**; reference-type parameters are nullable; return `null` for null/invalid input instead of throwing.
- **Naming:** plain `To[TargetArea](...)` when the source type has a single natural target in that area — the target is then distinguished by the source overload (`ToNTS(this Point2D?)` → `Coordinate`, `ToNTS(this Segment2D?)` → `LineSegment`, `ToNTS(this IPolygonal2D?)` → `LinearRing`). Use the suffixed form `To[TargetArea]_[TargetType](...)` when the same source converts to several targets in one area (`ToNTS_LineString(this Segment2D?)` and `ToNTS_Polygon(this IPolygonal2D?)` beside the plain overloads above; `ToDiGi_Polygon2Ds(this Polygon?)` beside `ToDiGi(this Polygon?)` → `PolygonalFace2D`).
- **Non-cloning access for a conversion:** add a **public** opt-out overload of the model's existing getter — `Segmentable2D.GetPoints(bool clone)`, whose `<summary>` says the caller must not mutate the list it returns for `clone: false` — and consume that from `Convert`. Never an `internal` accessor.

### Naming Conventions for Query Partial Class
- Enforce a property-like naming convention for methods inside the `Query` class.
- **Do not use verbs as prefixes** (e.g., avoid `Get`, `Find`, `Calculate`).
  - *Example:* `GetBoundingBox()` must be named `BoundingBox()`.
- **Exceptions:** Verbs indicating boolean checks or safe-retrieval patterns are required. Allowed prefixes are `Is`, `Has`, and `Try`.
  - *Examples:* `IsPlanar()`, `HasMaterial()`, `TryConvert()`.

## Project assets — `files/` vs `user files/` (NEVER commit secrets)
Runtime assets a project copies to its output belong in one of two solution-root folders, chosen by
sensitivity. **Secrets, credentials and machine-specific configuration MUST go in `user files/`,
never in `files/`.** Both are copied to the build output by a `.csproj` target; the difference is git.

- **`files/`** — committed to source control. Non-sensitive, environment-agnostic deployment assets
  shared by everyone (e.g. `web.config`, `app_offline.htm.bak`). Copied by a `CopyFiles` target:
  ```xml
  <Target Name="CopyFiles" AfterTargets="Build">
    <ItemGroup>
      <_Files Include="$(ProjectDir)..\files\**\*.*" />
    </ItemGroup>
    <Copy SourceFiles="@(_Files)" DestinationFiles="@(_Files->'$(OutputPath)%(RecursiveDir)%(Filename)%(Extension)')" SkipUnchangedFiles="true" />
  </Target>
  ```
- **`user files/`** — git-**ignored**. Fragile / user-specific / secret data: database connection
  configs (`*.conf` with host/user/password), API keys, local paths, per-machine settings. Copied by
  a `CopyUserFiles` target specifying `AfterTargets="CopyFiles"` so user files overwrite any duplicates
  copied by `CopyFiles`:
  ```xml
  <Target Name="CopyUserFiles" AfterTargets="CopyFiles">
    <ItemGroup>
      <_UserFiles Include="$(ProjectDir)..\user files\**\*.*" />
    </ItemGroup>
    <Copy SourceFiles="@(_UserFiles)" DestinationFiles="@(_UserFiles->'$(OutputPath)%(RecursiveDir)%(Filename)%(Extension)')" SkipUnchangedFiles="true" />
  </Target>
  ```
  - **Generated output also belongs here.** Test reports, diagnostic dumps, benchmark logs and text
    logs written during a run go to `user files/reports/` — never to `files/`. In tests, resolve the
    folder with `assembly.ReportsDirectory()` rather than a hardcoded path (see §7).
  - **`user files/` ships with the build.** `CopyUserFiles` flattens it into `bin` and `Deploy.ps1`
    carries `bin` to the hosts, so it holds only what the deployed tool reads at runtime. Training inputs
    (alternative weights, base weights, reference tables, training options and reports) live in a training
    directory outside the workspace; the Year Built runner extension deploys from an allowlist, of `YOLO`
    only `model.pt` (`Coding - YOLO.md` §3, §5).

**Overriding Rule:** In case of duplicate relative file paths between `files/` and `user files/`, assets from `user files/` MUST ALWAYS take precedence and override assets from `files/`. Specifying `AfterTargets="CopyFiles"` ensures `CopyUserFiles` runs strictly after `CopyFiles` to overwrite any duplicates.

**Enforcement:** the solution-root `.gitignore` must contain the case-insensitive rule
`[Uu]ser [Ff]iles/`. Verify with `git check-ignore -v "user files/<file>"` — git must report the rule
as the reason the file is ignored. If a new solution needs runtime secrets and lacks this rule, add
it before dropping any secret in. Reference implementations: `DiGi.GIS.PostgreSQL.UI`,
`DiGi.GIS.PostgreSQL.WebAPI` (both hold `GIS_PostgreSQL_Main.conf` in an ignored `user files/`).

**Decision rule when placing a runtime asset:** would committing it leak a secret, or break another
developer's / the server's machine-specific setup? If yes → `user files/`; otherwise → `files/`.

- **Script configurations (PowerShell)**: PowerShell scripts requiring machine-specific, secret, or environment-specific paths (e.g., local backup paths or cloud storage directories) must load these settings from a `.conf` file inside the `user files/` directory, rather than hardcoding them in the scripts or introducing custom `.gitignore` records.

## Host dependencies — `HintPath` drops a library's NuGet packages

DiGi projects reference each other with `<Reference><HintPath>..\..\X\bin\X.dll</HintPath>`, never
`<ProjectReference>`. A raw assembly reference is **opaque to NuGet**, and the DiGi class libraries do
not copy their own NuGet dependencies into their `bin` — so a library's third-party dependencies never
reach a host that consumes it by `HintPath`.

> **When a `HintPath`-referenced library needs a NuGet package, re-declare that `PackageReference` on
> the deployed host (the `Exe` / `WinExe` / `Microsoft.NET.Sdk.Web` project) at the identical version.**

- The chain runs deeper than the direct reference: `DiGi.Geometry` → `DiGi.Math` → `MathNet.Numerics`.
  Audit the whole closure, not just the assemblies listed in the `.csproj`.
- Do **NOT** use `CopyLocalLockFileAssemblies=true` on the netstandard2.0 library — it bloats its `bin`
  with `System.*` 4.3.0 shims.
- `<ProjectReference>` consumers (siblings, `.xUnit`, `.Rhino`) are unaffected; NuGet flows normally.

**The failure signature is a partial result, not an error.** `FileNotFoundException` is thrown per item
deep inside a loop, so a batch run completes and reports success while silently delivering less than it
should — one county produced models for 65 % of 33 687 buildings and reported success. A green build and
a green test suite prove nothing, because the `.xUnit` projects re-declare these packages themselves.
**When a run completes but delivers less than it should, check the host's output directory for missing
assemblies before investigating the data.**

**Extension hosts are one probing set.** `DiGi.GIS.WebAPI`, `DiGi.GLTF.WebAPI`, `DiGi.Communication.WebAPI`
and `DiGi.User.WebAPI` deploy into `DiGi.WebAPI.WindowsService\bin\extensions\<name>` and are loaded into
`AssemblyLoadContext.Default` with cross-directory `AssemblyDependencyResolver`s. Audit the host output
**together with** its `extensions\*` folders, and declare a shared dependency once on
`DiGi.WebAPI.WindowsService` — that is already how `Microsoft.OpenApi` and `Serilog` reach the extensions.

Verify after building — both read compiled output, not project files:
```powershell
PowerShell -ExecutionPolicy Bypass -File ".\CheckHostDependencies.ps1"
```
```powershell
PowerShell -NoProfile -ExecutionPolicy Bypass -File ".\BuildAll.ps1" -Configuration Release -CheckDependencies
```
Each deployment unit declares its reviewed exceptions inside `CheckHostDependencies.ps1`, every one with a
stated reason — an unexplained entry there re-hides the exact class of bug the script exists to find.

---

### 3. Reference Comparison (`IReference` / `IUniqueReference`)

> **Never compare two interface-typed references with `==` or `!=`. Use `Core.Query.Equals(reference_1, reference_2)`.**

This is not a style preference. `==` between two interface-typed operands compiles to **reference equality**, silently returns `false` for two equal references, and the compiler emits no warning. It has already produced an infinite loop in `BuildingModelShellUpdater` and mis-attributed geometry in `ShellByPlaneSplitSolver`.

**Why the operators do not apply.** For `a == b`, C# gathers user-defined operator candidates from the **static types of the operands and their base classes** — an interface contributes none. The `==`/`!=` operators live on `SerializableReference`, so the comparison is correct as soon as **one** side is a concrete `SerializableReference`-derived type (or the `null` literal).

| Static type of the operands | What `==` compiles to | Verdict |
|---|---|---|
| both interfaces (`IReference`, `IUniqueReference`, `ISerializableReference`, …) | predefined reference equality | **silent bug** |
| at least one `SerializableReference`-derived (`GuidReference`, `TypeReference`, …) | `SerializableReference.operator ==` → `Equals` | correct |
| one side is the `null` literal | null check | correct |
| `.ToString()` on both sides | string comparison | correct, but allocates |

This cannot be fixed by adding operators: interfaces contribute no operator candidates, a `operator ==(IReference, IReference)` declared in a helper class is **CS0563**, and C# 11 static abstract interface operators dispatch only through a constrained generic type parameter (and require net7.0+, while `DiGi.Core` targets `netstandard2.0`).

**The compounding trap — clone-per-call accessors.** Many model properties return `Core.Query.Clone(field)` and therefore hand back a **new instance on every read**, so `face.UniqueReference == face.UniqueReference` is `false` — the same face compared with itself. Read the property into a local before using it; never call it inside a predicate that runs per element (it is also an allocation per iteration).

| Intent | Use |
|---|---|
| Are these two references the same reference? | `Core.Query.Equals(reference_1, reference_2)` (null-safe, two nulls are equal) |
| Look up / group / de-duplicate | `Dictionary`, `HashSet`, `List.Find`/`FindAll`/`FindIndex`/`Contains` — already correct, they route through `Equals`/`GetHashCode` |
| I need the concrete API | pattern-match: `if (uniqueReference is GuidReference guidReference)` |
| Is this the same *instance* of a model object? | compare its `Guid` — a reference identifies the referenced object, not the object holding it |

```csharp
// WRONG - both operands are IUniqueReference, this is reference equality and never matches
int index = faces.FindIndex(x => x.UniqueReference == face.UniqueReference);
```

```csharp
// CORRECT - hoist the clone-returning accessor into a local, then compare by value
IUniqueReference? uniqueReference = face.UniqueReference;

int index = faces.FindIndex(x => Core.Query.Equals(x?.UniqueReference, uniqueReference));
```

**Do not assume an `IReference` is a `SerializableReference` — never cast to it.** `ListClusterReference<TKey_1, TKey_2>` implements `IReference` directly, and `IUniqueReference` has two class branches (`UniqueReference` and `UniqueExternalReference<T>`) with no common base below `SerializableReference`.

---

### 4. XML Documentation Standards
All public constructors, properties, methods, and enum values must be fully documented using XML comments:
* **Code preservation & sync:** Edit only `///` comments — never change C# logic. Add missing tags, and rewrite any existing comment that is outdated, inaccurate, or describes logic/parameters that no longer exist.
* **Explicit typing:** No `var` in any code snippet you touch.
* **Partial classes:** Don't document the class declaration itself when marked `partial`; document only its members.
* **Exhaustive coverage:** Every public member must have an accurate, up-to-date description.
* **Quality over speed** — prioritize accuracy and alignment with the code's actual behavior.
* **Reference context:** For each referenced library, ingest its sibling XML doc file (`LibraryName.dll` → `LibraryName.xml`, same directory) for accurate cross-referencing, terminology, and external type/parameter descriptions.
* **Signature matching:** Docs must match signatures exactly — remove `<param>` tags for parameters that no longer exist, add tags for new ones. Document all `<param>`, `<returns>`, and `<typeparam>` to avoid CS1591/CS1573.
* **Single summary:** Exactly one `<summary>` per element. When updating, overwrite the old one — never append. Do a final pass to strip any redundant tags.
* **No empty lines** inside doc blocks (no blank line or bare `///`) — they break Visual Studio IntelliSense tooltip rendering. Use `<para>` for paragraph breaks:

   ```csharp
   // INCORRECT — a blank line splits the block
   /// <summary>
   /// Calculates the total volume of the selected Revit elements.

   /// This operation might take a while on large BIM models.
   /// </summary>

   // CORRECT — use <para>
   /// <summary>
   /// Calculates the total volume of the selected Revit elements.
   /// <para>This operation might take a while on large BIM models.</para>
   /// </summary>
   ```

---

### 5. API Reference Documentation Locating
To minimize token consumption and avoid parsing full implementation files, you MUST consult the generated Markdown documentation first when exploring type schemas, namespaces, and public API interfaces:
To save tokens, consult the generated Markdown API docs before parsing `.cs` source when exploring type schemas, namespaces, or public API.

- **Path:** `documentation/API/[AssemblyName]/` in each active workspace — one directory per assembly, split by **namespace** (e.g. `DiGi.Core.Classes.md`). These files hold exact signatures and `<summary>` descriptions for all public classes, constructors, methods, properties, and enums.
- **Fallback:** if `documentation/API/` is absent, scan the C# source and `/bin/*.xml` files.

---

### 6. Serialization Pattern (SerializableObject / ISerializableObject)
Classes under `/Classes` needing JSON persistence, cloning, or polymorphic deserialization MUST inherit `DiGi.Core.Classes.SerializableObject` in this exact shape (reflection-driven — no manual JSON parsing).

1. **Marker interfaces** per project under `/Interfaces` (mirroring `DiGi.GIS.Interfaces.IGISObject`/`IGISSerializableObject`):
   ```csharp
   // /Interfaces/I<Project>Object.cs
   public interface I<Project>Object : DiGi.Core.Interfaces.IObject
   {
   }

   // /Interfaces/I<Project>SerializableObject.cs
   public interface I<Project>SerializableObject : I<Project>Object, DiGi.Core.Interfaces.ISerializableObject
   {
   }
   ```
   Every serializable class implements `I<Project>SerializableObject` (e.g. `public class Holiday : SerializableObject, IEPWSerializableObject`).
2. **Fields:** `private readonly`, each `[JsonInclude, JsonPropertyName(nameof(PublicPropertyName))]` — always `nameof(...)`, never a hardcoded string literal.
3. **Three constructors, always in this order:**
   - **Primary** (plain params, assigns fields) — no `base(...)` call needed.
   - **Copy** `ClassName(ClassName? classNameInstance) : base(classNameInstance)`, copying every field:
     - Primitive/value-type fields and strings: copy by value.
     - `List<T>`/`IList<T>` of **primitives**: `new List<T>(source)` (or `null` if source is `null`).
     - `IList<T>` of **nested `SerializableObject`-derived items**: clone element-by-element filtering nulls (see the excerpt below). Do NOT pipe the `IEnumerable<T>.Clone<T>()` extension into an `IList<T>` field — it returns `List<T?>?`, a nullable-element mismatch against a non-nullable `IList<T>` field.
     - A single nested `SerializableObject` reference: `field = Core.Query.Clone(source.field);`.
   - **JSON** `ClassName(JsonObject? jsonObject) : base(jsonObject)` — pure delegation, empty body.
4. **Properties:** `[JsonIgnore]` get-only, returning the backing field (the field attribute handles serialization — do not also serialize through the property).
5. **Project file:** `.csproj` needs a `<Reference Include="DiGi.Core"><HintPath>..\..\DiGi.Core\bin\DiGi.Core.dll</HintPath></Reference>` and a `<PackageReference Include="System.Text.Json" .../>` matching the version used elsewhere (check `DiGi.Core.csproj`).

### Example — simple class with primitive fields (`/Classes/Holiday.cs`)
```csharp
using DiGi.Core.Classes;
using DiGi.EPW.Interfaces;
using System.Text.Json.Nodes;
using System.Text.Json.Serialization;

namespace DiGi.EPW.Classes
{
    public class Holiday : SerializableObject, IEPWSerializableObject
    {
        [JsonInclude, JsonPropertyName(nameof(Name))]
        private readonly string? name;

        [JsonInclude, JsonPropertyName(nameof(Date))]
        private readonly string? date;

        public Holiday(string? name, string? date)
        {
            this.name = name;
            this.date = date;
        }

        public Holiday(Holiday? holiday)
            : base(holiday)
        {
            if (holiday != null)
            {
                name = holiday.name;
                date = holiday.date;
            }
        }

        public Holiday(JsonObject? jsonObject)
            : base(jsonObject)
        {
        }

        [JsonIgnore]
        public string? Name
        {
            get
            {
                return name;
            }
        }

        [JsonIgnore]
        public string? Date
        {
            get
            {
                return date;
            }
        }
    }
}
```

### Example — nested list of `SerializableObject` items (copy-constructor excerpt)
```csharp
public HolidaysDaylightSaving(HolidaysDaylightSaving? holidaysDaylightSaving)
    : base(holidaysDaylightSaving)
{
    if (holidaysDaylightSaving != null)
    {
        leapYearObserved = holidaysDaylightSaving.leapYearObserved;

        if (holidaysDaylightSaving.holidays != null)
        {
            holidays = [];
            foreach (Holiday holiday in holidaysDaylightSaving.holidays)
            {
                if (Core.Query.Clone(holiday) is Holiday holiday_Temp)
                {
                    holidays.Add(holiday_Temp);
                }
            }
        }
    }
}
```

### Example — `List<double>` of primitives (copy-constructor excerpt)
```csharp
public GroundTemperature(GroundTemperature? groundTemperature)
    : base(groundTemperature)
{
    if (groundTemperature != null)
    {
        depth = groundTemperature.depth;
        monthlyValues = groundTemperature.monthlyValues == null ? null : new List<double>(groundTemperature.monthlyValues);
    }
}
```

---

### 7. Automatic Tests (xUnit)
1. **One test project per project:** `[ProjectName].xUnit` (e.g. `DiGi.Core.xUnit`, `DiGi.Geometry.xUnit`).
2. **`public partial class Facts`** holds all test methods (one shared class per namespace).
3. **Files under `/Facts`.**
4. **Namespace matches the test project** (e.g. `namespace DiGi.Core.xUnit`).
5. **`Xunit` is global-usinged** by project config — do NOT add `using Xunit;`.
6. **`[Fact]`** marks test methods.
7. **Name the method** after the class/property/method under test (`Color()`, `PlanarIntersectionResult_Performance()`).
8. **XML `<summary>` on every test** describing what is tested — no empty lines inside the block (they break VS tooltips); use `<para>` for paragraph breaks.

#### 📂 Shared Test Data Files (Fixtures)
When a test needs an on-disk input file (`.gmf`, `.json`, `.epw`, …), use the **one shared `files` directory** — do NOT add a per-project data folder.

1. **Location:** `DiGi.Test/files/` (the `DiGi.Test` repo sits beside the other `DiGi.*` repos under the `DiGi` workspace root; from a `DiGi.Test/<ProjectName>.xUnit/` dir it is `../files/`). The path is given relative to the workspace root because this guideline lives in the separate `DiGi.Maintenance` repo.
2. **Add a fixture:** drop the file into `DiGi.Test/files/` and reference it by file name only. Files are read **in place** (not copied to build output) — no `<None CopyToOutputDirectory>` entry needed.
3. **Resolve the path:** `Core.xUnit.Query.FilePath(System.Reflection.Assembly.GetExecutingAssembly(), "<fileName>")` returns the absolute path to `DiGi.Test/files/<fileName>`; for the directory itself use `assembly.FilesDirectory()`. Both live in `DiGi.Core.xUnit/Query/` (`FilePath.cs`, `FilesDirectory.cs`) and resolve by walking up from the test assembly's `bin/<ProjectName>.xUnit/` output. `FilePath` `Assert`s the directory resolves, so a `null`/missing result fails the test cleanly.
4. **No `using` needed** — call it fully qualified as `Core.xUnit.Query.FilePath(...)`; it resolves via the same innermost-enclosing-namespace lookup as `Core.xUnit.Query.SerializationCheck(...)`, as long as the test namespace nests under `DiGi`. Add `using System.Reflection;` (or fully qualify `Assembly`).
5. **Example:**
   ```csharp
   using System.Reflection;
   // ...
   string? path = Core.xUnit.Query.FilePath(Assembly.GetExecutingAssembly(), "0207_GML.gmf");
   Assert.False(string.IsNullOrWhiteSpace(path));
   Assert.True(System.IO.File.Exists(path));
   ```
   References: `DiGi.GIS.xUnit/Facts/OrtoDatas.cs`, `DiGi.EPW.xUnit/Facts/EPWFile.cs`, `DiGi.Geometry.xUnit/Facts/InRange.cs`.
6. **Large binaries** (multi-MB `.gmf`, etc.) are git-tracked (not ignored) — prefer a representative-but-minimal sample, and consider Git LFS if size becomes a concern.

#### 📄 Test Reports & Diagnostic Outputs
Input fixtures are read from `files/`; everything a test **writes** goes to `DiGi.Test/user files/reports/`.

1. **Rule:** ALL reports, text dumps, benchmark logs and diagnostic output produced during test execution must be written to `user files/reports/` — never to `files/`, and never to a hardcoded machine path. `user files/` is git-ignored, so test output never lands in a commit.
2. **Resolve the folder:** `Core.xUnit.Query.ReportsDirectory(Assembly.GetExecutingAssembly())` or `assembly.ReportsDirectory()` (both resolve **and create** `DiGi.Test/user files/reports/`). For the parent folder use `assembly.UserFilesDirectory()`. Helpers live in `DiGi.Core.xUnit/Query/` beside `FilePath.cs` / `FilesDirectory.cs`.
3. **Example:**
   ```csharp
   using System.Reflection;
   // ...
   string? pathReportsDirectory = Core.xUnit.Query.ReportsDirectory(Assembly.GetExecutingAssembly());
   Assert.False(string.IsNullOrWhiteSpace(pathReportsDirectory));

   string pathReport = System.IO.Path.Combine(pathReportsDirectory!, "Diagnostic_Report.txt");
   System.IO.File.WriteAllLines(pathReport, reportLines);
   ```
   References: `DiGi.CityGML.xUnit/Facts/InspectDuplicates.cs`, `DiGi.GIS.Analytical.xUnit/Facts/BuildingModel_Enclosed.cs`.

#### Browser Testing (Interactive DoD)
Verify *interactive* front-end behaviour (panel toggles, drag-resize with clamps, keyboard operability, `localStorage` persistence, responsive stacking, shared header/footer collapse) in a **real browser** instead of only reading the code. Full recipe in `Coding - Browser Testing.md`.

1. **Confirm the toolchain on THIS machine first — availability is per-machine.** Probe Python + pip, Playwright (`pip show playwright`), and an installed Chromium-based browser (Microsoft Edge, Chrome, or Playwright's own Chromium); install whatever is missing. Do not treat any observed versions as a fixed requirement.
2. **Run with the host shell, not the isolated sandbox** — the sandbox has no host filesystem, no network, and cannot reach `localhost`. Keep test scripts and screenshots in the scratchpad so the repo stays clean.
3. **Recipe:** start the app from the build output with a fixed `ASPNETCORE_URLS`, poll a cheap endpoint until it returns 200, then drive it with `page.click` / `keyboard.press` / a `page.mouse` step-drag; assert computed styles, `aria-expanded`, `localStorage`, and no horizontal overflow; `set_viewport_size` for responsive breakpoints; **terminate the server in a `finally`**.
4. **Gotchas:** a collapsed panel measures 0 — open it before measuring (the `localStorage` value is the source of truth); drag with `page.mouse` steps, not a one-shot `.drag_to()`; settle before asserting; **rebuild before re-verifying a `.cshtml` change** (Razor views compile at build time, while CSS/JS serve live from source).
5. **Verify rendered output, not state:** a toggle whose flags flip is not a toggle whose effect is visible — assert a screenshot-region luminance that moves with the toggle and restores after toggling back; a pixel-minimum across several parameter values isolates parameter-independent artefacts; GPU cost comes from `EXT_disjoint_timer_query_webgl2` in a headed browser with vsync off (rAF cadence is CPU submit time; headless SwiftShader numbers are unusable).
6. **Not for:** pure server-side/C# logic (use xUnit, see §7) or a one-off "does it render" check (a `curl` of the endpoint is enough).

---

### 8. Branch Synchronization & Versioning Protocol
1. **Version branch only:** run only when the active branch is a bare SemVer `*.*.*` (e.g. `0.8.2`, `1.12.0`). Skip anything with text, prefix, or suffix (`feature/login`, `v0.8.2`, `0.8.2-beta`, `main`).
2. **Differs from main:** run only for repos where the active branch differs from `main`; skip repos where they are identical.

#### 🔄 Synchronization Workflow (Execution Steps)
1. **Sync with main:** merge the version branch into `main` so both hold the exact same codebase, with no pending diffs.
2. **Bump patch:** increment the third version digit by 1 (`0.8.2` → `0.8.3`).
3. **Branch off main** using that new version name.
4. **Update `Directory.Build.props`** (if present): set `<Major>`/`<Minor>`/`<Build>` to the new version's components and commit on the new branch before pushing.
5. **Push & track:** push both `main` and the new version branch to `origin`, using `-u` on the new branch so it tracks properly (`git push -u origin <version_branch>`).

---

### 9. Full Guideline Set
This block is the condensed, always-applicable subset. The canonical, task-specific guidelines live in
`DiGi.Maintenance/documentation/AI Guidelines/` (path relative to the workspace root, since they sit in
the separate `DiGi.Maintenance` repo). Read the one matching the task rather than all of them; each is
also mirrored per repository as a skill under `.agents/skills/<skill-name>/SKILL.md`.

| Guideline | Read it when |
|---|---|
| `Coding - General.md` | Writing or editing any C# production code; adding a NuGet package to a `HintPath`-referenced library. |
| `Coding - Editor Config.md` | Configuring or auditing `.editorconfig` code style and diagnostic severities. |
| `Coding - API Documentation.md` | Looking up a public signature — read `documentation/API/` before `.cs` source. |
| `Coding - References.md` | Comparing, keying or de-duplicating an `IReference` / `IUniqueReference`. |
| `Coding - Automatic Tests.md` | Writing xUnit tests, shared fixtures, or test report output. |
| `Coding - Geometry.md` | Orienting, closing, triangulating, hashing or sweeping geometry — `SunDirection` points away from the sun, `Vector3D.Unit` is never null, `IsClosed` is not monotonic in tolerance, sub-tolerance corners hang `Triangulate`, symmetric fixtures cannot catch a mirror. |
| `Coding - ComputeSharp.md` | Writing or changing a ComputeSharp `IComputeShader` — never combine an odd root constant count (`ConstantBufferSize / 4`) with an odd resource count (silently wrong results on NVIDIA RTX 5090); reorder or pad fields, then update the layout guard fact. |
| `Coding - YOLO.md` | YOLO Year Built detector — runner modes, `model.pt` resolution, the first-detection year built predictor, training data and training scratch outside the workspace (never in `user files/`), deploying the runner extension from an allowlist (only `model.pt`). |
| `Coding - Templates.md` | Scaffolding a solution/project from `templates/`. |
| `Coding - WebAPI GLTF.md` | Building or extending a Web API on the `DiGi.GLTF` 3D framework. |
| `Coding - WebAPI Contracts.md` | Changing a WebAPI route/parameter, or writing an HTTP client of one; adding a controller constructor (exactly one public) or returning a DiGi object (`Content(Core.Convert.ToSystem_String(x), "application/json")`, never `Ok(x)`); client timeouts. |
| `Coding - WebAPI Simple Authorization.md` | Simple API-key-based tiered authorization for WebAPI controllers (deny-by-default, `key` request header, `.conf` assets, `Deploy.ps1` alignment). |
| `Coding - Deployed WebAPI.md` | Verifying a change against the live API at `api.digiproject.uk` (read-only GET; never in `DiGi.Test`); which per-prefix Swagger document to fetch (`/swagger/<prefix>/swagger.json`) to keep context small. |
| `Coding - Browser Testing.md` | Verifying interactive front-end behaviour in a real browser (Playwright driving an installed Chromium-based browser) — panel toggles, drag-resize with clamps, keyboard operability, `localStorage` persistence, responsive stacking, shared header/footer collapse; confirm the toolchain on THIS machine first. |
| `Coding - GIS Administrative Data.md` | Touching `administrative_areal_2d`, `building_2d`, or anything keyed by a county code or id. |
| `Coding - PostgreSQL.md` | Designing schemas, composite unique constraints, batching, timeouts, or converters in PostgreSQL/Npgsql. |
| `Coding - PostgreSQL Distributed Queue Processing.md` | Distributed bulk update queues — table schema (`claimed_at`, `created_at`, natural uniqueness), atomic lease claims (`FOR UPDATE SKIP LOCKED`), native interval arithmetic, explicit batch acknowledgment, and non-destructive observation. |
| `XML Documentation - Create.md` / `- Audit.md` | Adding missing `<summary>` docs, or auditing docs against current signatures. |
| `GitHub Wiki - General.md` / `- Home.md` / `- Benchmark.md` | Editing a wiki page, a `Home` landing page, or a `Benchmark` performance page. |
| `GitHub - Branch Pull.md` / `- Branch Synchronization.md` | Pulling repos to their highest SemVer branch, or running the release/patch-bump workflow. |
| `GitHub - Issues.md` | Creating, commenting on and closing issues — mandatory labels + default assignee, `--body-file`, verifying premises first, and **blocking relationships as GitHub issue dependencies** (`gh api … /dependencies/blocked_by`, cross-repository, set at blocker creation, verified with the `blocking` GET; a blocked issue is not started). |
| `GitHub - Plan Files.md` | Keeping the repository free of plan files — plans live outside the working tree, no plan/scratch `*.md` is ever committed or pushed, and the default is deleting the temporary implementation plan when the issue closes (no archiving into the repo; explicit user instruction wins). |
| `GitHub - Sub-Issues.md` | Creating sub-issues / sub-tasks for a feature — the tracking-issue pattern: a parent tracking issue with a Sub-issues table + one self-contained sub-issue per repository, each referencing the parent. |

> **One data rule worth knowing before it bites you:** a GIS county `code` does **not** identify one row.
> BDOT10k stores one `administrative_areal_2d` feature per polygon part, so 406 county rows cover 380
> codes, and 18 counties have several. Key every write and lookup by county **`id`**, give every
> `LIMIT`/`FirstOrDefault` over that table an explicit `ORDER BY`, and never "deduplicate" those rows —
> for `2412 rybnicki` the largest polygon is only 52 % of the county. Two corollaries that have each
> cost real data: **the number of county ids a caller sent is not evidence about how many parts the code
> has**, so resolve every item against `building_2d` rather than trusting a single id; and a **read** of
> a table keyed on a building must pass `fallbackByReference: true`, because it defaults to `false` and
> a row under a sibling part is then silently not returned. Full model in
> `Coding - GIS Administrative Data.md`.
