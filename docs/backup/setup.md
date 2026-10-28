# Complete Local Setup

[Repository overview](README.original.md) | [Documentation guide](index.md) |
**Setup** | [Architecture](architecture.md) |
[Add a service](adding-a-service.md)

This procedure reproduces the validated stack on a Linux x86-64 machine with
an Intel GPU. The containerized path runs Hermes, the operator UI, local MCP
simulations, and OVMS through Docker Compose. The legacy host setup remains
available through `scripts/setup.sh`.

## 1. Prerequisites

- Linux with an Intel GPU render node at `/dev/dri/renderD*`.
- Git, curl, and Python 3.11 or newer. The Python venv package is preferred.
- Docker Engine with permission to run containers as the current user.
- About 8 GB free disk for the model, image, and setup environment.
- Network access to GitHub, Docker Hub, PyPI, and Hugging Face.

On Ubuntu or Debian, install host tools and Docker as follows. Log out and back
in after adding the Docker group.

```bash
sudo apt-get update
sudo apt-get install -y ca-certificates curl git python3 python3-venv
curl -fsSL https://get.docker.com -o /tmp/get-docker.sh
sudo sh /tmp/get-docker.sh
sudo usermod -aG docker "$USER"
```

Then verify the two hardware/runtime requirements:

```bash
ls /dev/dri/renderD*
docker run --rm hello-world
```

Use the official Docker Engine instructions for non-Debian distributions. Do
not run the setup as root; the script writes Hermes state and models under the
current user's home directory.

### Proxy environments

The script honors standard proxy variables. Set these before setup when needed:

```bash
export HTTP_PROXY=http://proxy.example:port
export HTTPS_PROXY="$HTTP_PROXY"
export NO_PROXY=localhost,127.0.0.1,::1
export http_proxy="$HTTP_PROXY"
export https_proxy="$HTTPS_PROXY"
export no_proxy="$NO_PROXY"
```

If TLS is intercepted, configure the system or Docker daemon to trust the
organization's proxy CA; do not disable TLS verification. The image build needs
network access to the Hermes installer and Python package indexes.

## 2. Run setup

```bash
git clone https://github.com/intel-retail/qsr-agent.git
cd qsr-agent
make download-models
make up
```

Every `make up` run copies `.env.example` to `.env`, replacing any existing
`.env`. The example uses a repo-local `./models`; edit `.env.example` for remote
SAD MCP or other overrides. Edits made directly to `.env` are
lost.

`make up` validates Docker, Intel render-device access, and the existing model,
then runs `docker compose up -d`. By default it pulls the pre-built image from
the registry (`REGISTRY=true`); use `make up REGISTRY=false` to build from source
instead. Override the image with `REGISTRY_URL` and `TAG` (default
`intel/qsr-agent:latest`). `make up` stops with an error if `MODEL_ID` is not
set or the model is not under `MODEL_ROOT/MODEL_ID`. Useful commands:

```bash
make download-models
make logs
make status
make down
```

### Model selection

`MODEL_ID` in `.env.example` is the only place the model is set (default
`OpenVINO/Qwen3-8B-int4-ov`, ~5 GB). OVMS serves it and Hermes uses it as its
default model; no other file needs to change.

`make download-models` refreshes `.env` from `.env.example` and downloads
`MODEL_ID` from Hugging Face into `MODEL_ROOT` (default `./models`). Known models
are pinned to a validated revision; any other model downloads `main`. Set
`MODEL_REVISION` to pin a specific commit.

| `MODEL_ID` | Pinned revision | Size |
|---|---|---|
| `OpenVINO/Qwen3-8B-int4-ov` (default) | `5c47abf4b8e12ebe8e99745bb0c1ec17e0c0abcc` | ~5 GB |
| `OpenVINO/Qwen3-30B-A3B-Instruct-2507-int4-ov` | `9268a085a48d496cce87d569f008975258bb70df` | ~16 GB |

To switch models, edit `MODEL_ID` in `.env.example`, then:

```bash
make download-models
make up
```

Use an OpenVINO model that supports tool calling; OVMS runs it with
`--tool_parser hermes3`.

### Image source (pull vs build)

`make up` and `make build` select the agent image with these variables:

| Variable | Default | Effect |
|---|---|---|
| `REGISTRY` | `true` | `true` pulls the pre-built image; `false` builds from source. |
| `REGISTRY_URL` | `intel/` | Registry/namespace prefix for the image. |
| `TAG` | `latest` | Image tag. |

The image reference is `${REGISTRY_URL}qsr-agent:${TAG}` (default
`intel/qsr-agent:latest`).

```bash
make up                                            # pull the pre-built image (default)
make up REGISTRY=false                             # build from source instead
make up REGISTRY_URL=myreg.io/team/ TAG=2026.2.0   # custom registry/tag
```

Use `REGISTRY=false` until the image has been published to the registry.

The agent image installs Hermes and the MCP service dependencies at build time.
Hermes configuration/history and autonomy proposals are persisted in named
volumes. OVMS mounts `MODEL_ROOT` read-only and is available to the agent at
`http://ovms:8000/v3` inside the Compose network.

Register services in `agent-config/hermes/remote-mcp.example.yaml`, setting each
`url` to an address reachable from the QSR container. A loopback URL on the
service machine will not reach the QSR container.

### Legacy host setup

`./scripts/setup.sh` remains available for installing Hermes and running the UI
on the host. It is idempotent and performs these operations (the UI build
needs Node.js >= 20.19; see [Operator UI](operator-ui.md)):

1. Validates Linux, Python, Docker, and `/dev/dri` access.
2. Installs Hermes with its official installer when `hermes` is absent.
3. Installs model/YAML helpers in `.venv/qsr-setup`; when venv support is
  unavailable, it uses an isolated `.venv/qsr-setup-target` directory.
4. Downloads the `MODEL_ID` set in `.env.example` (at its pinned revision) to
  `<repo>/models`; an exported `MODEL_ID` overrides it.
5. Pulls the OVMS GPU image and starts `ovms-qwen3-30b-a3b` on loopback port 8000.
6. Installs the weather MCP service from `services/weather` into the MCP venv and
  starts it on `127.0.0.1:8090`, sending `weather_changed` events to the
  Operator UI. Set `START_WEATHER=false` to manage it yourself.
7. Backs up and merges `~/.hermes/config.yaml`; unrelated settings survive.
8. Registers Kiosk and Order Accuracy as local stdio MCP servers and Weather as
  a Streamable HTTP server (enabled only when reachable).
9. Validates OVMS, Hermes, MCP discovery, and service tests.

Validated artifact identities are pinned by default:

| Component | Identity |
|---|---|
| Hermes | v0.20.5 configuration schema 38 or a compatible newer install |
| Qwen model | `MODEL_ID` from `.env.example`, pinned per model (see [Model selection](#model-selection)) |
| OVMS GPU image | `sha256:2a52cd2bc62d984f35f12b1cf58bb5dffe5f5d57b6ef3349b1b37229a768806b` |

Useful overrides:

```bash
MODEL_ROOT=/data/models OVMS_PORT=8010 ./scripts/setup.sh
HERMES_CONFIG=/data/hermes/config.yaml ./scripts/setup.sh
```

Change demo weather with `.venv/mcp/bin/weather-simulator set rain --temperature 12`,
or `POST http://127.0.0.1:8090/simulator/weather`. Its log is
`/tmp/qsr-weather-service.log`.

Keep the same overrides when later running `./scripts/setup.sh --check`.

## 3. What Hermes receives

The setup merges [the reusable settings](../../agent-config/hermes/config.example.yaml)
and [local test registrations](../../tests/mcp-services/hermes-mcp.example.yaml).
The essential settings are:

```yaml
model:
  default: ${MODEL_ID}   # expanded from .env.example at start-up
  provider: local-ovms
  base_url: http://127.0.0.1:8000/v3
  context_length: 65536
  max_tokens: 9000
providers:
  local-ovms:
    name: Local OVMS
    base_url: http://127.0.0.1:8000/v3
    default_model: ${MODEL_ID}
    request_timeout_seconds: 1800
    stale_timeout_seconds: 1800
tools:
  tool_search:
    enabled: false
skills:
  external_dirs:
    - /absolute/path/to/qsr-agent/qsr-skills
```

`tool_search` is intentionally disabled while the MCP catalog is small. This
passes actual MCP schemas to Qwen and avoids the deferred
`tool_search -> tool_describe -> tool_call` wrapper that caused malformed calls.
The broad built-in-tool disable used during the earlier CPU/Ollama experiment
is not required for the final OVMS/Qwen3 setup. No Hermes source patch is
required.

Restart an interactive Hermes process after any configuration or skill change.

## 4. Exact OVMS bring-up

The setup script runs the equivalent of this validated command:

```bash
MODEL_ROOT="$PWD/models"
MODEL_ID=$(sed -n 's/^MODEL_ID=//p' .env.example)
RENDER_NODE=$(find /dev/dri -maxdepth 1 -name 'renderD*' -print -quit)
RENDER_GROUP=$(stat -c '%g' "$RENDER_NODE")

docker rm -f ovms-qwen3-30b-a3b 2>/dev/null || true
docker run -d --name ovms-qwen3-30b-a3b --restart unless-stopped \
  --user "$(id -u):$(id -g)" \
  -p 127.0.0.1:8000:8000 \
  -v "$MODEL_ROOT:/models" \
  --device /dev/dri \
  --group-add "$RENDER_GROUP" \
  openvino/model_server@sha256:2a52cd2bc62d984f35f12b1cf58bb5dffe5f5d57b6ef3349b1b37229a768806b \
  --rest_port 8000 \
  --model_repository_path /models \
  --source_model "$MODEL_ID" \
  --target_device GPU \
  --tool_parser hermes3 \
  --task text_generation
```

`--tool_parser hermes3` is required for OpenAI-style tool calls. Confirm model
availability with:

```bash
curl -fsS http://127.0.0.1:8000/v3/models
docker logs ovms-qwen3-30b-a3b
```

## 5. Run and verify

Start Hermes from the repository so it reads the project `AGENTS.md`:

```bash
cd qsr-agent
hermes
```

Reproducible one-shot questions:

```bash
hermes -z 'What is the current restaurant queue count?' --cli
hermes -z 'What is the current order accuracy rate?' --cli
```

Independent checks:

```bash
./scripts/setup.sh --check
hermes mcp test kiosk
hermes mcp test order-accuracy
.venv/mcp/bin/python tests/mcp-services/call_tool.py order-accuracy get_order_accuracy_context
```

The expected simulated accuracy is 87.5%: 21 accurate of 24 observed in a
30-minute window. A valid answer must come from an MCP call, not memory.

## 6. Optional containerized MCP services

This validates remote Streamable HTTP topology. It does not containerize
Hermes or OVMS:

```bash
docker build -f tests/mcp-services/Dockerfile -t qsr-mcp-service:local .
docker run --rm -p 127.0.0.1:8001:8000 \
  -e QSR_SERVICE=kiosk qsr-mcp-service:local
docker run --rm -p 127.0.0.1:8002:8000 \
  -e QSR_SERVICE=order-accuracy qsr-mcp-service:local
```

For production, put each `/mcp` endpoint behind HTTPS with bearer-token or
mTLS validation and restrict ingress to the agent host. Merge the shape in
`agent-config/hermes/remote-mcp.example.yaml` only after the endpoint passes
`hermes mcp test <name>`.

## Troubleshooting

| Symptom | Resolution |
|---|---|
| `hermes` not found after install | Run `export PATH="$HOME/.local/bin:$PATH"`, then open a new shell. |
| Model download fails in OVMS | Use the setup script; it downloads on the host and mounts the files. |
| OVMS cannot use GPU | Verify `/dev/dri/renderD*`, Docker permissions, and the render group passed to the container. |
| Config change appears ignored | Exit and restart the interactive Hermes process. |
| `-t order-accuracy` works but normal mode fails | Confirm `tools.tool_search.enabled` is `false` and the domain is in `platform_toolsets.cli`. |
| MCP is listed but answers are unsupported | Run `hermes mcp test`, then confirm the service observed `tools/call`. |
| `GET /mcp` returns 400 or 406 | The route exists; Streamable HTTP requires an initialized MCP session. |
| Same-host Docker callback fails | Use `host.docker.internal` plus the Linux `host-gateway` mapping; `127.0.0.1` inside a container refers to that container. |
| Python has no venv support | Setup automatically uses isolated `pip --target`; install `python3-venv` if the fallback is unavailable. |

---

[Previous: Documentation guide](index.md) |
[Next: Architecture](architecture.md)
