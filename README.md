# vLLM Pool — Multi-GPU Process Manager with Per-GPU Live Tails

A FastAPI service and minimal UI to manage up to N independent **vLLM** workers (one process per GPU) with a clear separation of concerns:

* **Start Model Panel**: lifecycle & vLLM resource config (per worker / GPU).
* **Generate Panel**: send prompts to **already-running** models only.
* **Per-GPU Live Tail**: SSE streams the **last 5 log/tqdm lines** from each worker; pick the active GPU tail from a dropdown.

Object-oriented core (Python) split into domain types, worker, pool, and an adapter for vLLM.

---

## Features

* ✅ One worker process per GPU with `spawn` start method (safe with PyTorch/vLLM).
* ✅ Load the **same model on multiple GPUs** or different models per GPU.
* ✅ Strict separation: **only** Start panel controls lifecycle; Generate only prompts.
* ✅ **Per-GPU** SSE endpoint streaming log tail every \~2s (tqdm included).
* ✅ Batch generation:

    * **Simple**: array of strings.
    * **Chat**: array of chat items `{messages:[{role, content}], metadata?}`.
* ✅ **Offline mode job intake**: accept generation/chat jobs even before a model is loaded; jobs stay queued and dispatch once the target model starts.
* ✅ Optional post-processing on generation output for simple/chat/offline requests.
* ✅ Optional runtime dependency installation for post-processors using `uv pip install <dependency>` (guarded by env flags).
* ✅ Editable **vLLM resource config** JSON (defaults shown in UI).
* ✅ JSON responses + “Save as JSON” in the UI.
* ✅ Clean OOD design; core logic independent of the web layer.

---

## Project Structure

```
vllm_pool/
├── pyproject.toml
├── README.md
├── .env.example
├── vllm_pool/
│   ├── __init__.py
│   ├── main.py                  # FastAPI app factory + mounts + entry
│   ├── api/
│   │   ├── __init__.py
│   │   ├── models.py            # Pydantic schemas
│   │   ├── router_start.py      # /start, /stop
│   │   ├── router_status.py     # /status, /models, /workers
│   │   ├── router_generate.py   # /generate/simple, /generate/chat
│   │   └── router_events.py     # /events/worker/{key:path} (SSE per worker)
│   ├── core/
│   │   ├── __init__.py
│   │   ├── config.py            # default vLLM config
│   │   ├── types.py             # dataclasses: resource & sampling, chat
│   │   ├── llm_client.py        # vLLM adapter
│   │   ├── post_processor.py    # post-processing + dependency installer
│   │   ├── worker.py            # worker loop + log tail capture
│   │   └── pool.py              # PoolManager: lifecycle, queueing, SSE subs
│   ├── ui/
│   │   ├── __init__.py
│   │   ├── templates/
│   │   │   └── index.html       # Start/Status/Generate UI
│   │   └── static/
│   │       └── app.js           # UI logic + fetch + SSE
│   └── utils/
│       ├── __init__.py
│       └── logging.py
└── scripts/
    └── run.sh
```

---

## Requirements

* Python **3.10+**
* CUDA-capable GPUs with compatible NVIDIA drivers
* PyTorch `>=2.1.0` and vLLM `>=0.5.3`
* Linux recommended (tested with `spawn` start method)

---

## Installation

```bash
# clone your repo
pip install -e .  # uses pyproject.toml; installs fastapi, uvicorn, vllm, torch
```

> If you manage CUDA/PyTorch separately, install the matching `torch` build before `pip install -e .`.

---

## Running
### Basic run:
```bash
uvicorn vllm_pool.main:app --host 0.0.0.0 --port 8000
# or
./scripts/run.sh
```

Open the UI at `http://localhost:8000`.

### HPC:
- Same as basic, then create a reverse ssh tunnel from the local PC: 
```bash
ssh -J <login node> -N -L <remote port>:localhost:<local port> <username>@<compute node>
```
- then just open <localhost:local port> from browser.
---

## UI Workflow

1. **Start model (left)**

    * Enter **Model name** (e.g., `meta-llama/Llama-3.2-1B-Instruct`).
    * Optionally set **GPU id** (0-based). If empty, first free GPU is used.
    * Edit the **vLLM config JSON** (defaults provided).
    * Click **Start**.
    * You can **Stop** a worker by model + GPU id.

2. **Status & Live GPU tail (right)**

    * **Refresh** to view running workers & queues.
    * Select a worker from the dropdown to watch its **live 5-line tail** (tqdm/logs).

3. **Generate (full width)**
   Tabs:

    * **Simple**:

        * Choose **Model** (dropdown of loaded models).
        * Set **Sampling params** JSON.
        * Paste **Prompts JSON** (array of `{prompt, metadata?}` items) or **Upload** a JSON file.
        * Save/load/delete prompt presets in server-side persistent **Prompt Bank** storage.
        * Save/load/delete sampling presets in server-side persistent **Sampling Bank** storage.
        * Optionally provide **Post-processor spec JSON**.
        * Save/load/delete named post-processor presets in server-side persistent storage.
        * Use **Quick script builder** to write Python code in UI and generate a `python_script` post-processor spec automatically.
        * Toggle **Include metadata in output rows** (defaults to enabled).
    * **Chat**:

        * Choose **Model**.
        * Set **Sampling params**.
        * Provide **Messages JSON** (array of chat items) or **Upload**.
        * Save/load/delete prompt presets in server-side persistent **Prompt Bank** storage.
        * Save/load/delete sampling presets in server-side persistent **Sampling Bank** storage.
        * Optionally provide **Post-processor spec JSON**.
        * Save/load/delete named post-processor presets in server-side persistent storage.
        * Use **Quick script builder** to write Python code in UI and generate a `python_script` post-processor spec automatically.
        * **Output field** name (e.g., `"output"`).
        * Toggle **Include metadata in output rows** (defaults to enabled).
    * Results appear below; click **Save as JSON**.
    * For both tabs, you can tick **Submit via offline queue endpoint** to send to `POST /generate/offline` instead of the regular generate endpoints.
    * You can also keep **Auto-start model if missing** enabled so the UI will call `/start` using the Start panel's vLLM config JSON (defaults shown there) before queue submission.

> The Generate panel **never** starts models. If the model isn’t running: API returns **409**.

---

## REST API

### Start a worker

```
POST /start
Content-Type: application/json
```

```json
{
  "model_name": "meta-llama/Llama-3.2-1B-Instruct",
  "config": {
    "gpu_memory_utilization": 0.92,
    "max_model_len": 4096,
    "max_num_seqs": 32,
    "max_num_batched_tokens": 8192,
    "block_size": 16,
    "tensor_parallel_size": 1,
    "dtype": "auto",
    "trust_remote_code": true,
    "disable_log_stats": true,
    "max_parallel_loading_workers": 2
  },
  "gpu_id": 0
}
```

Response:

```json
{ "model_name":"...", "gpu_id":0, "pid":12345, "status":"ready" }
```

### Stop a worker

```
POST /stop
Content-Type: multipart/form-data
```

Form fields: `model_name`, `gpu_id`

### Status / models / workers

* `GET /status` – GPUs, running workers, queues
* `GET /models` – unique set of loaded models
* `GET /workers` – `[{ key: "<model>|<gpu>", model, gpu_id }]`

### Generate (Simple)

```
POST /generate/simple
Content-Type: application/json
```

```json
{
  "model_name": "meta-llama/Llama-3.2-1B-Instruct",
  "prompts": [
    {"prompt": "Hello", "metadata": {"id": "1"}},
    {"prompt": "Explain transformers in 3 bullets", "metadata": {"id": "2"}}
  ],
  "sampling": { "temperature": 0.0, "top_p": 1.0, "max_tokens": 256, "batch_size": 1 },
  "include_metadata": true,
  "post_processor": {
    "name": "identity",
    "config": {},
    "runtime": {"dependencies": [], "auto_install": false},
    "on_error": "fail"
  }
}
```

Response:

```json
{ "job_id": "a1b2c3d4", "result": [ {"id":"1", "output":"..."}, {"id":"2", "output":"..."} ] }
```

### Generate (Chat)

```
POST /generate/chat
Content-Type: application/json
```

```json
{
  "model_name": "meta-llama/Llama-3.2-1B-Instruct",
  "prompts": [
    {
      "messages": [
        {"role": "user", "content": "Summarize attention."}
      ],
      "metadata": {"id": "1"}
    }
  ],
  "sampling": { "temperature": 0.0, "top_p": 1.0, "max_tokens": 256, "batch_size": 1 },
  "output_field": "output",
  "include_metadata": true,
  "post_processor": {
    "name": "identity",
    "config": {},
    "runtime": {"dependencies": [], "auto_install": false},
    "on_error": "fail"
  }
}
```

Response:

```json
{ "job_id": "f00dbabe", "result": [ {"id":"1", "output":"..."} ] }
```

### Generate (Offline Queue)

```
POST /generate/offline
Content-Type: application/json
```

```json
{
  "model_name": "meta-llama/Llama-3.2-1B-Instruct",
  "type": "generate",
  "prompts": [
    {"prompt": "Hello", "metadata": {"id":"1"}},
    {"prompt": "Give me a haiku about CUDA", "metadata": {"id":"2"}}
  ],
  "post_processor": {
    "name": "identity",
    "config": {},
    "runtime": {"dependencies": [], "auto_install": false},
    "on_error": "fail"
  }
}
```

* `type: "generate"` expects `prompts` as items (`[{prompt:"...", metadata?}]`).
* `type: "chat"` expects `prompts` as chat items (`[{messages:[{role, content}], metadata?}]`).
* `sampling` is optional; if omitted the default sampling values are used.
* `include_metadata` is optional for generate/chat jobs and defaults to `true`.
* `post_processor` is optional. If set, result shape becomes `{generation, post_processing}`.
* Response: `202` with `{ "job_id": "...", "status": "queued_offline" }`.

`python_script` processor (for rapid research workflows):

```json
{
  "name": "python_script",
  "config": {
    "entrypoint": "process",
    "code": "def process(generation_json, config):\n    return generation_json"
  },
  "runtime": {
    "dependencies": ["scipy", "numpy"],
    "auto_install": true
  },
  "on_error": "fail"
}
```

Expected script signature:

```python
def process(generation_json, config):
    # return any JSON-serializable output
    return {"your": "result"}
```

Runtime install controls:

* `ALLOW_RUNTIME_DEP_INSTALL` (default `false`): allow/disallow runtime installs.
* `POST_PROCESSOR_MAX_DEPS` (default `20`): maximum dependency strings in one request.
* `POST_PROCESSOR_INSTALL_TIMEOUT_SEC` (default `120`): install timeout per dependency.
* `POST_PROCESSOR_MAX_JSON_BYTES` (default `2097152`): max JSON size for post-processor input/output.

UI state persistence controls:

* `VLLM_UI_STATE_PATH` (default `./data/ui_state.json`): file path for persistent UI state (prompt bank, sampling bank, post-processor presets).

### Per-worker SSE tail

```
GET /events/worker/{key}
# key format: {model}|{gpu_id}, slashes in model preserved via {key:path}
# Example (URL-encoded): /events/worker/meta-llama/Llama-3.2-1B-Instruct%7C0
```

Events:

* `event: tail` `data: {"lines": ["…up to 5 lines…"]}`

> The server sends a snapshot every \~2 seconds, even when idle.

---

## JSON Shapes

* **Sampling params** (both Simple & Chat):

  ```json
  { "temperature": 0.0, "top_p": 1.0, "max_tokens": 256, "batch_size": 1 }
  ```
* **Chat item**:

  ```json
  {
    "messages": [ {"role":"user","content":"Hi"}, {"role":"assistant","content":"..."} ],
    "metadata": { "id":"123" }
  }
  ```

---

## Configuration

Default vLLM config (editable in UI):

```json
{
  "gpu_memory_utilization": 0.92,
  "max_model_len": 4096,
  "max_num_seqs": 32,
  "max_num_batched_tokens": 8192,
  "block_size": 16,
  "tensor_parallel_size": 1,
  "dtype": "auto",
  "trust_remote_code": true,
  "disable_log_stats": true,
  "max_parallel_loading_workers": 2
}
```

Tips:

* For large models or tight VRAM, reduce `max_model_len`, `max_num_batched_tokens`, or `max_num_seqs`.
* Keep `tensor_parallel_size=1` unless you explicitly shard a single model across multiple GPUs (this code runs one model per worker/GPU).

---

## Design Notes (OOD)

* **core/** is framework-free:

    * `types.py` – immutable dataclasses for resource & sampling configs.
    * `llm_client.py` – adapter around `vllm.LLM` (swap or mock in tests).
    * `worker.py` – single-responsibility worker loop; **TailCapture** encapsulates tqdm/log capture.
    * `pool.py` – orchestration (start/stop/queueing/SSE broadcast). UI/HTTP unaware.
* **api/** binds a `PoolManager` instance to FastAPI routers (dependency inversion via `bind()`).
* **ui/** is minimal static HTML + JS; no build step.

---

## Troubleshooting

* **404 on SSE path with model names containing slashes**
  Ensure the route uses `{key:path}`:

  ```python
  @app.get("/events/worker/{key:path}")
  ```
* **“daemonic processes are not allowed to have children”**
  We force `spawn` and set `proc.daemon = False`. Don’t wrap app inside another daemonized process manager.
* **No GPUs detected**
  Check `nvidia-smi`. Make sure the container/host exposes GPUs and CUDA libraries.
* **Out of memory while loading**
  Lower `gpu_memory_utilization` or reduce `max_model_len`/`max_num_batched_tokens`/`max_num_seqs`.
* **SSE shows nothing**
  Worker might be idle; tail snapshots still arrive but could be empty. Start a job or watch model load logs.

---

## Development

Run app in dev:

```bash
uvicorn vllm_pool.main:app --reload --host 0.0.0.0 --port 8000
```

Suggested tests (pytest):

* `TailCapture` CR/newline behavior.
* Worker happy-path simple/chat.
* Pool queueing: multiple jobs, single model, single GPU.
* Routers with FastAPI `TestClient`.

---



## License

MIT (or your choice). Add your license text here.
