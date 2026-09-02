# How to write a new example

Every example is a self-contained Harbor task + Reef harness that `run.sh`
wires together through [reef-eval](https://github.com/Human-Agent-Society/reef-eval).
Copy `recipes/basic/` as a starting point; a method's examples live under
`recipes/<method>/examples/<example>/`; it is the minimal valid structure.

## Directory layout

```text
my_example/
  harbor/                task definition (consumed by reef-eval/Harbor)
    task.toml             metadata, timeouts, resource limits
    instruction.md        the prompt shown to the model
    environment/
      Dockerfile          container image the verifier runs in
    solution/             optional seed/initial solution files
    tests/
      test.sh             verifier: writes reward to /logs/verifier/reward.txt
  harness/                agent harness (imports reef_client, not reef)
    __init__.py           lazily exports HarborAgent
    agent.py              HarborAgent(BaseAgent) — the agent logic
    report.py             optional: post a trainable verifier reward to Reef
  my_example.yaml         Reef service config (recipe, host, token, services)
  run.sh                  starts reef serve, then runs reef-eval with the harness
  pyproject.toml          makes harness/ importable by reef-eval's uvx environment
  README.md               what the example demonstrates and how to run it
```

## No top-level `__init__.py`

The example directory is **not** a Python package. There is no
`my_example/__init__.py`. The `harness/` subdirectory is the package, and
`pyproject.toml` declares it:

```toml
[project]
requires-python = ">=3.12"
dependencies = [
    "reef-client",
    "reef-eval[harbor]",
]

[tool.setuptools.packages.find]
where = ["."]
include = ["harness*"]
```

Only examples that do not use reef-eval (for example, a direct
`reef_client` campaign driver) should omit the reef-eval dependency.

`run.sh` installs it into reef-eval's ephemeral environment with
`--with-editable "$PWD"`.

## harness/`__init__.py`

Lazily export `HarborAgent` so importing the harness package does not require
the `harbor` runtime — reef-eval loads it when resolving
`--agent harness:HarborAgent`:

```python
__all__ = ["HarborAgent"]

def __getattr__(name: str):
    if name == "HarborAgent":
        from .agent import HarborAgent
        return HarborAgent
    raise AttributeError(f"module {__name__!r} has no attribute {name!r}")
```

## harness/`agent.py`

Subclass `harbor.agents.base.BaseAgent`. The `run()` method is the agent
logic: call the model through Reef's `/v1/chat/completions`, write the answer
to the path the instruction names, and stash the inference receipt in
`context.metadata` so the reporter can link the verifier reward back to it.

Connection settings come from environment variables set by `run.sh`:

- `REEF_SERVICE_URL` (required)
- `REEF_SCENARIO` (required)
- `REEF_TOKEN`
- `REEF_TIMEOUT_S`

When the task verifier's reward is feedback consumed by the scenario's recipe,
a background thread watches for Harbor's `result.json` and posts it to Reef via
`harness.report.post_report`. See `basic/harness/agent.py` for the complete
pattern. Do not add that reporter when the harness already posts its training
feedback and the final Harbor reward is evaluation-only; Harbor keeps that
value in the trial result.

## harness/`report.py` (optional)

Extract the verifier reward from Harbor's trial result and post it to Reef as
a report that references the trial's inference receipts. The report id is
deterministic (`uuid5` of the trial id), so a duplicate post is a no-op.

Only use this path when the recipe consumes the verifier reward. A terminal
evaluation that is explicitly ineligible for training belongs in Harbor's
trial result, not in the training scenario's report contract.

## `my_example.yaml`

Reef service config. The minimal record-only config (no training stack) is:

```yaml
reef:
  host: 127.0.0.1
  port: ${REEF_PORT}
  recipe: ${REEF_RECIPE}
  token: ${REEF_TOKEN}
  agent_record_dir: ${REEF_WORK}/agent-record
  artifact_repository: ${REEF_WORK}/artifacts.git
  artifact_work_dir: ${REEF_WORK}/artifact-work
  artifact_cache_dir: ${REEF_WORK}/artifact-cache

services:
  - name: reef
    command: ${PYTHON} -m reef.service
    ready: curl -sf http://127.0.0.1:${reef.port}/healthz
```

For a training example (GPU + Ray + Slime/Megatron + SGLang), see
`tttd/serve.yaml` — it adds `training:` and `services:` blocks for the
training stack under the same `reef:` section.

## `run.sh`

1. Set environment variables (port, token, scenario, work dir); select the
   deployment recipe in YAML.
2. Start `reef serve -c <yaml>` in the background; wait for `/healthz`.
3. Run reef-eval with `--with-editable "$PWD"` (installs `harness/`) and
   `--with reef-client` (installs the SDK from PyPI).
4. reef-eval resolves `--agent harness:HarborAgent` and runs the Harbor task.

See `basic/run.sh` for the minimal version (60 lines). `tttd/run.sh` adds
model download and GPU stack startup.

## harbor/`task.toml`

Declares the task metadata, timeouts, and resource limits:

```toml
version = "1.0"

[metadata]
author_name = "Reef"
difficulty = "easy"
category = "integration"
tags = ["reef", "harbor"]

[verifier]
timeout_sec = 30.0

[agent]
timeout_sec = 300.0

[environment]
build_timeout_sec = 120.0
cpus = 1
memory_mb = 512
storage_mb = 1024
gpus = 0
```

## harbor/`instruction.md`

The prompt shown to the model. Keep it self-contained: the harness reads it
from Harbor's `instruction` argument and passes it to the model.

## harbor/`solutions/` (optional)

Seed or initial solution files the harness loads to bootstrap its search.
The harness reads them at startup (e.g. to seed a PUCT archive or provide a
baseline the model must improve on). Not every task needs this — `basic/`
has none; `tttd/` seeds its archive with empty strings at runtime. The
directory is a convention for when the task ships concrete starting points
that are too large or too structured to inline in code.

## harbor/environment/`Dockerfile`

The container the verifier runs in. Minimal:

```dockerfile
FROM debian:bookworm-slim
WORKDIR /workspace
```

## harbor/tests/`test.sh`

The verifier script. Harbor runs it inside the environment container after
`run()` returns. Write a float to `/logs/verifier/reward.txt`:

```sh
#!/bin/sh
set -eu
if [ -f /workspace/answer.txt ] && [ "$(cat /workspace/answer.txt)" = "391" ]; then
    echo 1 > /logs/verifier/reward.txt
else
    echo 0 > /logs/verifier/reward.txt
fi
```

## Tests

Unit tests for the harness live in `tests/test_<example>_harness.py` at the
repo root. They import directly from
`recipes.<method>.examples.<example>.harness.*` — the test inserts
`REPO_ROOT` into `sys.path` so `recipes/` is importable and each `examples/`
directory resolves as a namespace package (each example's `harness/` has its own `__init__.py`, but
the example directory itself does not).

## Self-containment

Each example must be fully self-contained: no cross-example Python imports.
If two examples share a pattern (scoring, sandboxing, search), each copies
its own copy. The only shared dependencies are external: `reef_client`,
`harbor`, and the `reef` package itself (for `reef serve`).
