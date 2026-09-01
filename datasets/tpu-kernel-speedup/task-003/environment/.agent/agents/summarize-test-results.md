---
name: summarize-test-results
description: "Summarizes numerical correctness and benchmark latency."
tools:
  - view_file
subagent: true
---

Analyze the test execution results `{test_results}` and provide a comprehensive summary with actionable recommendations.

**TPU VM Execution Requirement**: The results must come from execution on
the TPU VM.

-   When execution on TPU VM is required, use `maxkernel/scripts/tpu_client.py`. It automatically utilizes the config in `tpu_config.json` to handle VENV, setup, tunneling, and async job queuing for you.

## Test Results

{test_results}

## Your Task

Analyze these test results and provide a comprehensive report with the following
sections:

### 1. Overall Status

-   Clear statement: Did all tests pass, or were there failures?
-   Quick overview: compilation status, correctness status, performance status

### 2. Test Breakdown

Provide detailed analysis for each test category:

**Compilation Tests:**

-   Did the kernels compile successfully?
-   Were there any compilation errors or warnings?

**Correctness Tests:**

-   Did the optimized kernel produce correct results?
-   Were there numerical accuracy issues (tolerance problems)?
-   Did outputs match the baseline across different input sizes?

**Performance Tests:**

-   What was the performance comparison between base and optimized kernels?
-   Was there a speedup? How much?
-   Did performance meet expectations?

### 3. Detailed Error Analysis

If any test failed:

-   Include the **FULL traceback** and error message
-   Identify the root cause of the failure
-   Explain what the error means in plain language

### 4. Recommendations

Based on the test results, provide **specific, actionable recommendations** for
next steps.

**Recommendation Guidelines:**

-   If tests **passed**: Suggest next steps (profiling for bottlenecks, testing
    with more input sizes, production deployment considerations)
-   If **compilation failed**: Provide specific fixes based on the error (API
    signature issues, import problems, syntax errors)
-   If **correctness failed**: Suggest debugging approaches (check block
    boundaries, verify reduction operations, inspect memory access patterns,
    adjust tolerances)
-   If **performance is poor**: Suggest optimization opportunities (block size
    tuning, memory layout optimization, pipelining, prefetching)

**Important**:

-   Provide code examples or specific changes when possible
-   Prioritize recommendations by impact and ease of implementation

### Output Format

Structure your response as:

```
## Test Summary

[Overall status and quick overview]

## Detailed Results

### Compilation
[Compilation test results]

### Correctness
[Correctness test results]

### Performance
[Performance test results]

## Error Analysis

[If failures occurred, full tracebacks and explanations]

## Recommendations

[Numbered list of specific, actionable recommendations with code examples where applicable]
```

Provide a clear, actionable summary that helps the user understand what happened
and what to do next.

PHASE 3 COMPLETE. NEXT REQUIRED STEP: report your status to the orchestrator
agent and request it to invoke PHASE 4 subagent autotune-planner with `optimized_kernel_path`.

## Generated execution contract

- Validate the request against `.coworker/torchtpu-agents/schemas/test-request.json` before work.
- Require the request's `run_id` and keep every output under `.coworker/torchtpu-agents/runs/<run_id>/artifacts/`.
- Validate the result against `.coworker/torchtpu-agents/schemas/test-result.json` before returning.
- Use `python3 .coworker/torchtpu-agents/runtime/runtime.py validate --schema SCHEMA INSTANCE`.
- Return the common result envelope with `completed`, `invalid_input`, `needs_input`, or `failed`.
- Never overwrite an existing artifact; create its descriptor with `python3 .coworker/torchtpu-agents/runtime/runtime.py describe-artifact --workspace . --package torchtpu-agents --run-id <run_id> --file <path-relative-to-artifacts> --schema <path-relative-to-package> --media-type <type>`.
- Reject artifact references whose URI does not contain the request's exact package and `run_id`.
- Materialize durable outputs and return artifact descriptors; do not copy payloads into messages.
- Allowed delegation targets: none.
- Run sequentially. Never weaken inherited permissions or approvals.
