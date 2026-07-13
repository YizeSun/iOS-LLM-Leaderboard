# Contributing

Thank you for helping improve iOS-LLM-Leaderboard.

This project values reproducibility, transparent methodology, and practical usefulness for iOS developers. Benchmark quality is more important than benchmark quantity.

## Licensing

By submitting a pull request, you agree that your contribution will be licensed under the same licensing model as this repository (MIT for code and CC BY 4.0 for benchmark data and documentation).

## Ways To Contribute

- Submit benchmark results with reproducible metadata.
- Submit device benchmark results for iPhone, iPad, or Mac.
- Propose new benchmark tasks.
- Improve methodology documents.
- Add example integrations for iOS developers.
- Improve validation and leaderboard tooling.

The official Power contribution path uses the iOS benchmark app described in
[Community Contribution Model](docs/community-contribution-model.md). App
0.8.0 build 10 runs the locked adopted-RC1 contract and exports the reviewable
result; repository tooling adds the contributor manifest without rewriting
those bytes.

## Current Contribution Stage

Power Benchmark 1.0 public result intake is open. Contributors may submit an
immutable App 0.8.0 build 10 export plus its contributor-owned manifest through
the documented Power intake path. The official 1.0 release adopted the frozen
RC1 source contract, so its versioned directory and App-emitted identities are
preserved intentionally.

During the current contribution stage:

- benchmark and methodology proposals are welcome;
- integration and validation tooling is welcome;
- Power results must use the official App and frozen submission package;
- historical Pilot and Framework v1 examples remain non-official; and
- no contributor or CI job may assign its own verified or ranking status.

Community results use evidence levels. Passing structural validation alone
does not place a result in the default ranking or alter Power 1.0.

## Benchmark Task Contributions

New benchmark tasks must follow [Benchmark Task Specification](methodology/benchmark-specification.md).

Every benchmark task should include:

- required task metadata
- objective and background
- exact input, prompt, IDE context, or measurement setup
- expected output
- automatic and manual evaluation criteria
- pass and failure conditions
- scoring rubric
- reproducibility requirements
- reviewer notes

Place every task in the correct suite directory:

- `benchmarks/suite-a-swift-codegen/`
- `benchmarks/suite-b-on-device-performance/`
- `benchmarks/suite-c-xcode-integration/`
- `benchmarks/suite-d-app-feature-intelligence/`
- `benchmarks/suite-e-runtime-evaluation/`

Do not mix Swift code generation tasks, app feature intelligence tasks, Xcode workflow tasks, runtime measurements, and on-device performance results.

Do not add tasks that depend on private data, undisclosed model access, or unverifiable scoring.

Suite B is transitioning to the workload-centric v2 draft. Do not propose new
Suite B tasks that merely isolate one metric such as TTFT or memory. Propose a
versioned user-experience workload or pipeline profile and identify the common
metrics it collects. See
[Suite B Protocol v2](benchmarks/suite-b-on-device-performance/protocol-v2.md).

## Result Contributions

New benchmark results must follow [Benchmark Result Specification](methodology/benchmark-result-specification.md).

Every result must include:

- required result fields
- task ID and task version
- model and provider metadata
- execution date and evaluator
- score, max score, and pass/fail state
- contributor license confirmation
- suite-specific runtime, device, metric, or output metadata where applicable

Submitted results must include enough reproducibility metadata for independent review. If a field is not applicable, use `null` instead of omitting required fields.

For Suite B result submissions, include prompt token band, output token band, warm-up procedure, measurement procedure, measured run count, aggregation method, cold or warm start state, timing boundaries, failed or interrupted run handling, and per-run metrics when available.

Demo or placeholder data must be clearly marked and must not be used for official leaderboard results.

When the official benchmark app is available, app-generated result bundles
will be the preferred Suite B submission route. Manual submissions will need
to demonstrate equivalent workload, runner, and raw-evidence compatibility.

The historical Benchmark App can generate an offline Pilot Draft submission after the
contributor reviews a unified Suite B result. Validate it with
`scripts/validate_suite_b_submission.py`. A passing package may be reviewed as
Community Submitted, but it is never accepted as official, verified, or added
to the default leaderboard automatically.

For repository placement, rename the untouched App export to
`<submissionID>.json` and add it under `submissions/suite-b/draft/`. See
[Community Submissions](submissions/README.md) for CI and maintainer review
commands.

Power 1.0 uses the App's unmodified adopted-RC1 Power result plus a separate
contributor manifest. Create and validate a package with:

```bash
python3 scripts/create_suite_b_power_submission.py \
  /path/to/app-export.json \
  --output-root submissions/suite-b/power-1.0.0-rc.1/draft \
  --contributor YOUR_GITHUB_HANDLE \
  --conflict-category none \
  --conflict-statement "No conflict of interest disclosed." \
  --accept-declarations
```

Read the current
[Power 1.0 public-intake guide](docs/power-benchmark-1.0-public-intake.md) and
the SHA-256-pinned
[RC1 package definition](docs/power-benchmark-1.0-submission.md) before
accepting the declarations. Valid Draft evidence remains unreviewed and
ranking-ineligible until separate review and publication decisions are merged.

## Data Integrity

Do not invent benchmark results, rankings, device measurements, or performance numbers. Placeholder examples must be clearly labeled as placeholder or demo data.

## Pull Request Checklist

- Documentation is updated.
- New or moved benchmark content is in the correct suite.
- New benchmark tasks follow `methodology/benchmark-specification.md`.
- New benchmark results follow `methodology/benchmark-result-specification.md`.
- Submitted results include reproducibility metadata.
- Placeholder data is clearly labeled.
- JSON files parse successfully and follow `methodology/benchmark-result-specification.md`.
- Generated leaderboard changes are intentional.
- License boundaries remain consistent.
