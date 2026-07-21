# immich-ml-proxy

A small reverse proxy in front of `immich-machine-learning` that routes each
`/predict` request to one of two backends based on the task key(s) inside
its `entries` field:

- `ocr` → the OCR backend (intended to be a CPU-only `immich-ml` replica)
- anything else (`clip`, `facial-recognition`, ...) → the default backend
  (the GPU `immich-ml-gpu` replicas)

## Why

`immich-ml-gpu`'s two 1080 Tis (11GB VRAM each) run all three model
pipelines per replica. Once `clip` + `facial-recognition` + `ocr`'s ONNX
Runtime CUDA arenas are all resident, there's ~100MB of headroom left, and
OCR's recognition stage (which batches per detected text-line, with no
fixed-size arena) throws CUDA OOM errors under concurrent load. Immich never
sends more than one task type per request, so
routing by top-level JSON key lets OCR run on CPU — where its ~20MB of
weights are trivial to host — without touching `clip`/`facial-recognition`'s
GPU placement at all.

## Configuration

All configuration is via environment variables:

| Var | Required | Default | Description |
|---|---|---|---|
| `LISTEN_ADDR` | no | `:3003` | address the proxy listens on |
| `DEFAULT_BACKEND_URL` | yes | — | base URL of the GPU backend, e.g. `https://immich-ml-gpu.example.internal` |
| `DEFAULT_BACKEND_BASIC_AUTH_USERNAME` | no | — | HTTP Basic Auth username sent to the GPU backend; must be set together with the password below |
| `DEFAULT_BACKEND_BASIC_AUTH_PASSWORD` | no | — | HTTP Basic Auth password sent to the GPU backend |
| `OCR_BACKEND_URL` | yes | — | base URL of the OCR/CPU backend, e.g. `http://immich-ml.immich-ml.svc.cluster.local:3003` |
| `OCR_BACKEND_BASIC_AUTH_USERNAME` | no | — | HTTP Basic Auth username sent to the OCR backend; must be set together with the password below |
| `OCR_BACKEND_BASIC_AUTH_PASSWORD` | no | — | HTTP Basic Auth password sent to the OCR backend |
| `OCR_TASK_KEYS` | no | `ocr` | comma-separated top-level JSON keys routed to the OCR backend |
| `REQUEST_TIMEOUT` | no | `60s` | per-request upstream timeout |
| `MAX_BODY_BYTES` | no | `52428800` (50MiB) | cap on buffered request body size |
| `LOG_LEVEL` | no | `info` | `debug`, `info`, `warn`, or `error` |

Basic Auth credentials are per-backend and optional. When set, the proxy
sends them to that backend on every request, replacing any `Authorization`
header the original client sent — the two backends' credentials are never
mixed up, and a client can't smuggle its own credentials past the proxy.

Both backend URLs may use `http://` or `https://` independently — the proxy
doesn't care which scheme a given backend uses.

The proxy dials a fresh connection per backend request rather than reusing
keep-alive connections. This is deliberate: Kubernetes Services load-balance
per TCP connection, not per request, so a pooled connection would keep
riding whichever pod it first connected to for every request that reuses
it - silently pinning all traffic to one pod regardless of replica count.
Each request re-resolving and re-dialing is what makes multi-replica
backends actually get load-balanced across.

## Endpoints

- `POST /predict` (or any path) — proxied to the routed backend, unmodified.
- `GET /healthz` — liveness; always 200.
- `GET /readyz` — readiness; 200 once config has loaded (does not probe
  backends, to avoid readiness flapping during a backend rollout).
- `GET /metrics` — Prometheus exposition:
  - `immich_ml_proxy_requests_total{backend,reason}`
  - `immich_ml_proxy_route_fallback_total{reason}`
  - `immich_ml_proxy_upstream_errors_total{backend}`
  - `immich_ml_proxy_request_duration_seconds{backend}`

  `deploy/kustomize/base/prometheusrule.yaml` has alerting rules for these,
  and `deploy/grafana/dashboard.json` is a matching dashboard (traffic,
  routing breakdown, latency percentiles, Go runtime) - see
  `deploy/grafana/kustomization.yaml` for how to provision it via a
  `grafana_dashboard`-labeled ConfigMap (kube-prometheus-stack's Grafana
  sidecar convention).

## Routing behavior

`/predict` requests are `multipart/form-data`, not raw JSON: immich-ml's
FastAPI endpoint takes an `entries` form field (a JSON string keyed by task,
e.g. `{"ocr": {...}}`) alongside separate `image`/`text` parts. The proxy
extracts just the `entries` part to make its routing decision, then forwards
the entire original request unmodified - it never re-encodes or alters the
multipart body.

Routing fails open to the default (GPU) backend whenever the request can't
be confidently classified — non-`/predict` paths, a body that isn't
multipart, a missing `entries` part, or an `entries` value that doesn't
decode as a JSON object. This means a request Immich would have sent
successfully always gets forwarded somewhere; it's never rejected because
the proxy couldn't parse it. Watch `immich_ml_proxy_route_fallback_total`
for how often that's happening.

## Development

```sh
go test ./... -race -cover
golangci-lint run
```

```sh
DEFAULT_BACKEND_URL=https://immich-ml-gpu.example.internal \
OCR_BACKEND_URL=http://immich-ml.immich-ml.svc.cluster.local:3003 \
go run ./cmd/proxy
```

## Repo layout

```
cmd/proxy/            entrypoint: config load, server start, graceful shutdown
internal/config/       env-var config loading + validation
internal/router/        routing decision: JSON top-level key -> backend
internal/proxy/          HTTP handler: buffer, route, forward, stream response
internal/metrics/        Prometheus metric definitions
deploy/kustomize/        Deployment/Service/ConfigMap for this proxy
```

Code lives under `internal/` rather than `pkg/` (unlike some sibling `pu-*`
Go services) — this is a standalone binary with no intended external
importers, and `internal/` is the stronger Go convention for that case.

## Deployment status

This repo builds and tests the proxy itself. Wiring it into the platform —
an ArgoCD `Application` deploying `deploy/kustomize/`, and repointing
tenant Immich config (`immich-charts/charts/immich-tenants/files/
immich-config-general.yaml`'s `machineLearning.urls`) at this proxy instead
of directly at `immich-ml-gpu` — is a follow-up, blocked on fixing the
existing CPU-only `immich-ml` release's pod scheduling (currently 0/1
available in the `immich-ml` namespace).
