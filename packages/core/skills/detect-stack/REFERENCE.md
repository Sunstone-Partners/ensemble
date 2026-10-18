# detect-stack Reference

Complete reference for the `detect-stack` skill. [SKILL.md](./SKILL.md) has the quick reference, the axis sections and the envelope summary.

## Locating the script

The script is `skills/detect-stack/detect-stack.js` inside the `ensemble-core` plugin. Agents in `ensemble-infrastructure` and `ensemble-quality` call it by that skills-relative path, so `ensemble-core` must be installed alongside them (see the READMEs of those packages). In `ensemble-full` the core skills are mirrored under `skills/core/`, so the script is at `skills/core/detect-stack/detect-stack.js`.

The skill ships as one script plus data:

```text
skills/detect-stack/
  SKILL.md                  quick reference
  REFERENCE.md              this file
  detect-stack.js           CLI, API, the four axis engines, envelope normalization
  performance-benchmark.js  manual benchmark of the tooling axis cache
  patterns/                 framework.json, test.json, tooling.json, cloud.json
  __tests__/                jest suites
```

Requirements: Node.js 18 or later and the `glob` npm package (v10), which is resolved from the repository's `node_modules`.

## CLI reference

```text
detect-stack.js [project-path] [--axis=<axis>] [options]
```

| Option | Value | Applies to | Notes |
|--------|-------|------------|-------|
| `--axis` | `framework`, `test`, `tooling`, `cloud`, `all` | all | Default `all`. Both `--axis=<axis>` and `--axis <axis>` work |
| `--framework` | `nestjs`, `react`, `phoenix`, `rails`, `dotnet`, `blazor` | framework | Skips detection; confidence 1.0, `manual_override: true` |
| `--provider` | `aws`, `gcp`, `azure` | cloud | Case-insensitive; confidence 1.0, `manual_override: true` |
| `--tools` | comma-separated tool names | tooling | Only these tools are evaluated; `all_results` holds only them |
| `--min-confidence` | number, `0 < n <= 1` | tooling, cloud | Replaces the 0.7 threshold. Ignored by the other axes |
| `-h`, `--help` | | | Prints usage, exit 0 |

Flags that do not apply to the selected axis are ignored, so one command line can configure `--axis=all`. A second positional argument, an unknown option, a missing option value, an unknown axis, an unknown override or tool name, a non-numeric `--min-confidence` and a project path that is not a directory are all errors (exit 2, message on stderr, nothing on stdout).

Exit codes:

| Code | Meaning |
|------|---------|
| 0 | Something was detected (`detected: true`). For `--axis=all`: at least one axis |
| 1 | Nothing detected. The JSON envelope is still printed |
| 2 | Usage or runtime error |

`DEBUG=true` makes the test axis log what it finds to stderr.

## JavaScript API

```javascript
const { detect, AXES, FrameworkDetector, TestFrameworkDetector, detectionCache } = require('./detect-stack');
```

| Export | Description |
|--------|-------------|
| `detect(axis, projectPath = cwd, options = {})` | Returns the envelope for `axis` (`framework`, `test`, `tooling`, `cloud`) or `{ axis: 'all', detected, axes }`. Rejects on an unknown axis or invalid override |
| `AXES` | `['framework', 'test', 'tooling', 'cloud']` |
| `FrameworkDetector` | The framework engine class, `new FrameworkDetector(projectRoot, patternsPath, { framework, skipDetection })`. `detect()` returns the raw engine result (`primary`, `confidence`, `alternates`, `details`, `scores`) |
| `TestFrameworkDetector` | The test-runner engine class, `new TestFrameworkDetector(projectPath).detect()` returns the raw engine result |
| `detectionCache` | The tooling axis's in-process LRU cache (`clear()`, `get`, `set`) |

`detect` options:

| Option | Axis | Description |
|--------|------|-------------|
| `framework` | framework | Manual override |
| `skipDetection` | framework | Return an empty result flagged `skipped: true` without scanning |
| `tools` | tooling | Array of tool names to evaluate |
| `useCache` | tooling | Use the in-process cache (default `true`) |
| `provider` | cloud | Manual override |
| `minimumConfidence` | tooling, cloud | Detection threshold (default 0.7; `0` counts as unset) |

Options that do not apply to an axis are ignored.

## Output envelope in full

```text
{
  axis:        'framework' | 'test' | 'tooling' | 'cloud'
  detected:    boolean                  results.length > 0
  primary:     string | null            results[0].name
  confidence:  number                   results[0].confidence, 0 when nothing detected
  threshold:   number | null            minimum confidence to be in results; null on the test axis
  results:     Entry[]                  candidates meeting the detection rule, best first
  all_results: Entry[]                  every candidate evaluated, best first
  manual_override?: true                override flag applied (framework, cloud)
  skipped?:    true                     framework skipDetection
  message?:    string                   test axis, nothing detected
}

Entry = {
  name:          string                 detector name = skill name
  display_name:  string
  confidence:    number
  signals:       { [signal]: boolean }
  signal_count:  number                 count of true signals
  ...axis-specific fields
}
```

What counts as detected, per axis:

| Axis | `results` holds | `all_results` holds | `threshold` |
|------|-----------------|---------------------|-------------|
| framework | frameworks with confidence at or above the threshold, at most `maxCandidates` (3) | all six frameworks; those without any signal are last at confidence 0 | 0.8 (`detectionConfig.confidenceThreshold`) |
| test | every runner with confidence above 0 | all five runners | `null` |
| tooling | tools at or above the threshold | every tool evaluated (those selected by `tools`) | 0.7, or `minimumConfidence` |
| cloud | providers at or above the threshold (several for multi-cloud) | all three providers | 0.7, or `minimumConfidence` |

Signal names (the keys of `signals`):

| Axis | Signal names |
|------|--------------|
| framework | `packageJson`, `gemfile`, `mixExs`, `csproj`, `files`, `imports` (only those configured for the framework) |
| test | `configFile`, `packageDependency`, `testDirectory`, `testFiles` |
| tooling | the keys under `detection_signals` of the tool in `patterns/tooling.json` (`chart_yaml`, `values_yaml`, `fly_toml`, ...) |
| cloud | `terraform`, `npm`, `python`, `cli`, `docker`, `config` |

Axis-specific entry fields:

| Axis | Field | Meaning |
|------|-------|---------|
| framework | `details` | `{ [signal]: { matches, weight, score } }` for each signal that fired; `{ manualOverride: { matches: 1, weight: 100, score: 100 } }` for an override |
| test | `language` | Language label from the patterns file |
| test | `version` | Version of the matched dependency (`^`/`~` stripped), `"unknown"` when found but not extractable, `null` when no dependency was found |
| test | `config_files` | The first config file found, as a one-element array, or `[]` |
| test | `test_directory` | The first test directory found, or `null` |
| test | `test_pattern` | The runner's first test-file pattern when any test file exists (not necessarily the pattern that matched), or `null` |
| tooling | `description` | One-line description of the tool |
| tooling | `high_confidence` | A signal with weight 0.7 or more fired |

Example for the `cloud` axis (an AWS project with Terraform, an SDK dependency and a deploy script):

```jsonc
{
  "axis": "cloud",
  "detected": true,
  "primary": "aws",
  "confidence": 0.8555555555555556,
  "threshold": 0.7,
  "results": [
    {
      "name": "aws",
      "display_name": "Amazon Web Services (AWS)",
      "confidence": 0.8555555555555556,
      "signals": { "terraform": true, "npm": true, "python": false, "cli": true, "docker": false, "config": false },
      "signal_count": 3
    }
  ],
  "all_results": [
    // every provider, best first; abbreviated here, entries have the full shape
    { "name": "aws", "confidence": 0.8555555555555556, "signal_count": 3 },
    { "name": "gcp", "confidence": 0, "signal_count": 0 },
    { "name": "azure", "confidence": 0, "signal_count": 0 }
  ]
}
```

A manual override on the framework axis:

```jsonc
{
  "axis": "framework",
  "detected": true,
  "primary": "rails",
  "confidence": 1,
  "threshold": 0.8,
  "results": [
    {
      "name": "rails",
      "display_name": "Ruby on Rails",
      "confidence": 1,
      "signals": {},
      "signal_count": 0,
      "details": { "manualOverride": { "matches": 1, "weight": 100, "score": 100 } }
    }
  ],
  "all_results": [
    // identical to results for an override
  ],
  "manual_override": true
}
```

`--axis=all`:

```jsonc
{
  "axis": "all",
  "detected": true,
  "axes": { "framework": {}, "test": {}, "tooling": {}, "cloud": {} }   // each value is a full envelope
}
```

The axes run concurrently.

## Axis internals

### Framework engine

Signals are collected, scored, boosted and ranked in this order:

1. `package.json` (merged `dependencies` and `devDependencies`), `Gemfile`, `mix.exs` and the first `*.csproj` are read; a package signal fires when at least `minMatches` of the listed names are present.
2. File signals: each `required` file that exists adds 2 matches, each `optional` file 1 (wildcards via glob).
3. Import signals: up to 20 source files with the configured extensions (ignoring `node_modules`, `dist`, `build`, `vendor`); each file adds the number of the framework's regex patterns it contains.
4. `confidence = sum(matches x weight) / (3 x sum of the weights of the signals the framework defines)`, then multiplied by every boost factor whose indicator is present. Boost indicators are file checks or text searches over the first 10 matching files.
5. Frameworks at or above `confidenceThreshold` are sorted by confidence and cut to `maxCandidates`.

Per-framework configuration (weights; `files`: required files count double):

| Framework | Package signal | Files | Imports | Boosts |
|-----------|----------------|-------|---------|--------|
| `nestjs` | weight 10, 2 of `@nestjs/core`, `@nestjs/common`, `@nestjs/platform-express` | weight 8; required `nest-cli.json`, `tsconfig.json`; optional `src/main.ts`, `src/app.module.ts`, `src/app.controller.ts` | weight 7, `.ts` | `nest-cli.json` x1.5, `@Module(` x1.3, `@Controller(` x1.2 |
| `react` | weight 10, 1 of `react`, `react-dom` | weight 7; optional `public/index.html`, `src/App.js`, `src/App.tsx`, `src/index.js`, `src/index.tsx` | weight 8, `.jsx` `.tsx` `.js` `.ts` | JSX/TSX files x1.4, `useState`/`useEffect` x1.3, `createRoot` x1.2 |
| `phoenix` | weight 10, 2 of `{:phoenix,`, `{:phoenix_ecto,`, `{:phoenix_html,`, `{:phoenix_live_view,` in `mix.exs` | weight 8; required `mix.exs`, `config/config.exs`; optional `lib/*_web/endpoint.ex`, `lib/*_web/router.ex`, `lib/*/application.ex` | weight 7, `.ex` `.exs` | `Phoenix.Endpoint` x1.5, `Phoenix.Router` x1.3, `Phoenix.LiveView` x1.4 |
| `rails` | weight 10, 1 of `gem 'rails'`, `gem "rails"`, `gem 'activesupport'`, `gem 'actionpack'` in `Gemfile` | weight 9; required `Gemfile`, `config/application.rb`; optional `config/routes.rb`, `app/controllers/application_controller.rb`, `config/environment.rb`, `Rakefile` | weight 7, `.rb` | `config/application.rb` x1.5, `config/routes.rb` x1.3, `ActiveRecord::Base` x1.2 |
| `dotnet` | weight 10, 1 of `Microsoft.AspNetCore`, `.Mvc`, `Microsoft.EntityFrameworkCore` package references or `Microsoft.NET.Sdk.Web` SDK | weight 8; required `*.csproj`; optional `Program.cs`, `Startup.cs`, `appsettings.json`, `Controllers/*.cs` | weight 7, `.cs` | `Program.cs` x1.4, `[ApiController]` x1.3, `Microsoft.EntityFrameworkCore` x1.2 |
| `blazor` | weight 10, 1 of the `Microsoft.AspNetCore.Components` package references or the `BlazorWebAssembly`/`Web` SDK | weight 9; required `*.csproj`; optional `App.razor`, `Pages/*.razor`, `_Imports.razor`, `wwwroot/index.html` | weight 8, `.razor` `.cs` | `.razor` files x1.6, `@page` x1.4, `ComponentBase` x1.3 |

The full pattern lists (import regexes, all package names) are in `patterns/framework.json`.

### Test-runner engine

For each runner in `patterns/test.json`, in this order: the first existing file of `configFiles` adds `configFile` (0.4); `packageFiles` (globs allowed) are read and the first file containing one of `packageIndicators` (plain substring match) adds `packageDependency` (0.3) and yields the version (`package.json` dependency version, `requirements*` `name==x.y`, Gemfile `~>`, `csproj` `PackageReference Version`); the first existing directory of `testDirectories` adds `testDirectory` (0.2); any file matching `testPatterns` (ignoring a top-level `node_modules`, `vendor`, `.git`) adds `testFiles` (0.1). The sum is capped at 1.0. Runners with confidence 0 are left out of `results`.

### Tooling engine

- Each tool's signals are evaluated concurrently, and the tools are evaluated concurrently.
- Signal types in `patterns/tooling.json`: `files` (direct paths are checked for existence; glob patterns match regular files within 3 path levels), `directories`, and `file_pattern` or `file_patterns` plus `patterns` (regexes over the matching regular files within 5 path levels; the first matching file is enough). Patterns such as `*.yaml` and `*.sh` match the project directory only, so the `cli`, `api_version`, `kind_field`, `application_yaml` and `fly_cli` signals read root-level files. A signal with `files` is evaluated by existence only, even if it also lists `patterns`. Glob matches are regular files only: symlinks are skipped.
- Ignore list for file checks and content scans: `**/node_modules/**`, `**/.git/**`, `**/vendor/**`.
- Results are cached for 5 minutes in an LRU cache (100 entries) keyed by the project path and the modification times of the primary signal files (signals of weight 0.5 or more that use `files`). `useCache: false` bypasses it. The cache lives in the process, so the CLI never benefits from it; it matters for library callers.
- `high_confidence` is `true` when a signal of weight 0.7 or more fired.
- Targets from the original design: detection under 100 ms on average, at least 95% accuracy for Helm and Kubernetes, under 5% false positives, several tools detected simultaneously.

`performance-benchmark.js` measures the tooling axis with and without the cache. Run it from the root of a project that contains a `fly.toml` (its accuracy check expects Fly.io to be detected):

```bash
node skills/detect-stack/performance-benchmark.js
```

### Cloud engine

For each provider in `patterns/cloud.json`: `terraform` scans every `*.tf` file for the provider's patterns; `npm` and `python` scan the root `package.json` and `requirements.txt`; `cli` scans every `*.sh`; `docker` scans every `Dockerfile*`; `config` checks that any listed path exists. A signal is true when it has at least one match. Confidence follows the shared formula in SKILL.md, using the provider's `confidence_boost`. Providers are sorted by confidence, and `results` keeps those at or above the threshold.

## Pattern files

| File | Top-level keys | Entry shape |
|------|----------------|-------------|
| `framework.json` | `frameworks`, `detectionConfig` | `name`, `category`, `language`, `patterns` (`packageJson` or `gemfile` or `mixExs` or `csproj`, `files`, `imports`), `boostFactors`. `detectionConfig`: `confidenceThreshold`, `maxCandidates`, `weights` |
| `test.json` | `frameworks` | `name`, `language`, `configFiles`, `packageFiles`, `packageIndicators`, `testPatterns`, `testDirectories`, `confidenceWeights` (`configFile`, `packageDependency`, `testDirectory`, `testFiles`) |
| `tooling.json` | `version`, `tools`, `detection_rules` | `name`, `description`, `confidence_boost`, `detection_signals` (each with `weight` and `files`, `directories` or `file_pattern(s)` plus `patterns`). Rules: `minimum_confidence`, `minimum_signals_for_boost` |
| `cloud.json` | `version`, `providers`, `detection_rules` | `name`, `confidence_boost`, `detection_signals` (`terraform`, `npm`, `python`, `cli`, `docker` with `weight` and `patterns`; `config` with `weight` and `files`). Rules as for tooling |

Keys that exist in the files but are not read: `devDependencies` and `configFiles` entries in `framework.json`, `weights` in `detectionConfig`, `detection_rules.multi_signal_boost` in `tooling.json` and `cloud.json`, and `file` on cloud signals.

## Inherited limitations

These behaviours come from the four detectors and were deliberately not changed by the merge; they are covered by tests so a change is visible.

- **Cloud: one or two signals never reach the default threshold.** Confidence is the detected weight over the total (1.8), so a lone Terraform signal scores 0.28 and the 3-signal boost is out of reach with two. A Terraform-only project is not "detected"; it appears as the top entry of `all_results` and passes with `--min-confidence`. The original test script asserted the opposite and failed 42 of its 59 assertions against this scoring.
- **Tooling: content signals read root-level files only.** `*.yaml` and `*.sh` in `file_pattern` do not descend, so `k8s/deployment.yaml` does not fire `api_version` or `kind_field` and `scripts/deploy.sh` does not fire a `cli` signal. The same holds for `fly_cli`'s `*.{sh,yml,yaml}`. The original tooling script also contained a recursive `**/*.sh` scanner that nothing called; it was not carried over.
- **Tooling: `dockerfile_flyio` is existence-only.** Any root `Dockerfile` adds 0.05 to Fly.io; its `patterns` are listed but not evaluated.
- **Tooling: the cache key ignores the threshold and the `tools` filter.** Within one process, two calls on an unchanged project with different options can return the first call's result. Pass `useCache: false` to avoid that.
- **Framework: confidence is unbounded.** Sums beyond the assumed 3 matches per signal and boost factors can exceed 1.0.
- **Framework: `.csproj` matching is by substring and reads only the first project file.** A Blazor project also satisfies .NET package references, so both can appear in `results`.
- **Test: `test_pattern` is the runner's first pattern, and a bare `test/` or `tests/` directory credits pytest, xUnit and ExUnit with 0.2.** A `jest` key inside `package.json` is not a config signal (the dependency signal covers `package.json`).
- **Test: only a top-level `node_modules` is excluded when looking for test files.** In monorepos, test files inside nested `node_modules` can count.
- **`--min-confidence 0` is treated as unset** by the engines, so the CLI rejects it.
- **Short cloud patterns match loosely**: the `az` and `gcloud` command prefixes and `azure-` are plain substrings.

## Migration from the four detector skills

`detect-stack` replaces `framework-detector`, `test-detector` (both in `ensemble-core`), `tooling-detector` and `cloud-provider-detector` (both were in `ensemble-infrastructure`).

### Commands

| Former invocation | Now |
|-------------------|-----|
| `node skills/framework-detector/detect-framework.js [path] [--framework x]` | `node skills/detect-stack/detect-stack.js [path] --axis=framework [--framework=x]` |
| `node skills/test-detector/detect-framework.js [path]` | `node skills/detect-stack/detect-stack.js [path] --axis=test` |
| `node skills/tooling-detector/detect-tooling.js [path] [--tools a,b] [--min-confidence n]` | `node skills/detect-stack/detect-stack.js [path] --axis=tooling [--tools=a,b] [--min-confidence=n]` |
| `node skills/tooling-detector/detect-tooling.js [path] --tool x` | `--axis=tooling --tools=x` |
| `node skills/cloud-provider-detector/detect-cloud-provider.js [path] [--provider p] [--min-confidence n]` | `node skills/detect-stack/detect-stack.js [path] --axis=cloud [--provider=p] [--min-confidence=n]` |

Exit codes are now the same everywhere (0 detected, 1 nothing detected, 2 error). The framework detector used to exit 0 when nothing was detected, and the framework and test detectors used 1 for errors.

Programmatic use: `new FrameworkDetector(...)` and `new TestFrameworkDetector(...)` are still exported with the same constructors and methods. `detectTooling`, `detectTool` and `detectCloudProvider` are replaced by `detect('tooling' | 'cloud', path, options)`.

### Output fields

| Former field | Now |
|--------------|-----|
| framework `primary`, `confidence` | `primary`, `confidence` |
| framework `alternates[].framework`, `.confidence` | `results[1..].name`, `.confidence` |
| framework `details[name]` | `results[i].details` and `all_results[i].details` |
| framework `manualOverride`, `skipped` | `manual_override`, `skipped` |
| test `detected`, `primary`, `message` | unchanged |
| test `frameworks[]` | `results[]` |
| test `displayName`, `configFiles`, `testDirectory`, `testPattern` | `display_name`, `config_files`, `test_directory`, `test_pattern` |
| tooling `tools[]` | `results[]` |
| tooling `tools[].tool`, `tools[].name` | `results[].name`, `results[].display_name` |
| tooling `detection_summary` | `threshold`, `results.length`, `all_results.length` |
| tooling `performance.detection_time_ms` | removed (time the command instead) |
| cloud `provider`, `name` | `primary`, `results[0].display_name` |
| cloud `confidence`, `signals`, `signal_count` | `confidence`, `results[0].signals`, `results[0].signal_count` |
| cloud `manual_override` | `manual_override` |
| cloud `all_results[].provider`, `.name` | `all_results[].name`, `.display_name` |

New: `axis`, `threshold`, `signals` and `signal_count` on framework and test entries, `all_results` on every axis (every candidate, including zero-confidence ones), and `results` on the cloud axis listing every provider above the threshold (the old output named only the top provider).

### What changed on purpose

- One output envelope (above) instead of three shapes, and one set of exit codes.
- Input validation: unknown tool and provider names are errors (the old tooling run returned nothing or crashed, the old cloud run silently ignored an unknown `--provider`), `--min-confidence` must be a number in `(0, 1]`, a project path must be a directory, unknown options are errors, and `--tool` is folded into `--tools`. Options after `--tool` were previously ignored.
- The tooling axis uses `glob` instead of `fast-glob`, with the same patterns, ignore lists, depth limits and regular-files-only matching (symlinks are skipped). `fast-glob` is not a dependency of this repository, so the old tooling detector could not run here.
- Documentation corrections: the cloud boost is `confidence_boost` (0.3), not 0.2; the test axis includes ExUnit and the tooling axis Fly.io, ArgoCD and Kustomize (the old SKILL.md files omitted them); Kubernetes manifests must be at the project root for the YAML content signals; the framework detector does not do early exits or parallel checks.

### What is unchanged

Every weight, threshold, boost, pattern list, sampling and depth limit, the confidence formulas, manual override semantics, the test axis's lack of a threshold, and the tooling cache. The pattern files were moved unchanged (`framework-patterns.json` to `patterns/framework.json`, the test detector's `framework-patterns.json` to `patterns/test.json`, `tooling-patterns.json` to `patterns/tooling.json`, `cloud-provider-patterns.json` to `patterns/cloud.json`). The engines were compared with the original detectors on generated projects covering every framework, runner, tool and provider (including symlinks) and on packages of this repository, with identical confidences, signals and details on every axis.

## Version history

- **detect-stack**: merges `framework-detector` 1.0.0, `test-detector` 1.0.0, `tooling-detector` 2.0.0 and `cloud-provider-detector` 1.0.0 into one skill with a shared CLI and envelope.
- **tooling-detector 1.0.0** (2025-10-23): initial release with Helm detection (`Chart.yaml`, `values.yaml`, `templates/`), Kubernetes detection (`apiVersion`, `kind`, `kustomization.yaml`), Kustomize detection, ArgoCD detection, multi-signal confidence scoring, and a performance target of under 100 ms. Version 2.0.0 of its script added Fly.io, the LRU cache, parallel detection and depth-limited globbing.
