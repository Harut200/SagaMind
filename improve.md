# improve.md — Full Production Roadmap

End-to-end gap analysis of SagaMind. Every open item carries a severity rating, root-cause
diagnosis, exact code location, and a concrete fix prescription. Closed items are kept for
historical reference with their remediation summary.

**Current state (2026-06-07):** 141 tests pass, 2 skipped; ruff clean, format clean. Core
saga/memory/verifier/speculative/gRPC surfaces implemented, plus durable-saga reliability
(pool, idempotency, dead-letter), per-tool schema validation, request-ID correlation,
DBSCAN consolidation, embedding LRU cache, Neo4j retries, pluggable tool registry,
APScheduler sleep-cycle, property-based tests, and CI integration/gRPC/Docker/Dependabot.
Remaining work is mostly performance (push retention to SQL, native cosine kernel) and the
forward feature roadmap (distributed sagas, GraphRAG, HITL gate, replay, SDK).

Legend: **[BUG]** real defect · **[STUB]** advertised but not implemented · **[GAP]** missing
for production · **[PERF]** measurable speed opportunity · **[FEAT]** new capability.
Status: ✅ done · 🟡 partial · ⬜ not started.

---

## 0. Master status table

| # | Item | Type | Severity | Status |
|---|------|------|----------|--------|
| 1 | `psycopg2.pool` submodule never imported — DB always fell back to memory | BUG | P0 | ✅ |
| 2 | WASM sandbox isolated path + fuel exist; host tools still run outside microVM | STUB/SEC | P0 | 🟡 |
| 3 | Z3 verifier ignored arbitrary invariants — only hardcoded `str.prefixof` | STUB | P0 | ✅ |
| 4 | No API auth / rate-limiting / CORS | GAP/SEC | P0 | ✅ |
| 5 | Default secrets committed; no fail-closed in production | GAP/SEC | P0 | ✅ |
| 6 | Saga state in-process only; lost on crash (Redis unused) | GAP | P0 | ✅ |
| 7 | gRPC surface missing despite ports + deps | STUB | P1 | ✅ |
| 8 | Speculative execution was an `asyncio.sleep` mock, unwired | STUB | P1 | ✅ |
| 9 | Consolidation O(n²) pure-Python; LLM distillation unwired | STUB/PERF | P1 | ✅ |
| 10 | No embedding generation (dummy `[0.1]*1536` vector at query time) | GAP | P1 | ✅ |
| 11 | No CI, no coverage gate, no pre-commit, no integration tests | GAP | P1 | ✅ |
| 12 | Decay path mixed naive/aware datetimes → `TypeError` in dashboard | BUG | P1 | ✅ |
| 13 | Vector/decay math in pure Python | PERF | P2 | 🟡 |
| 14 | `SagaStateStore` uses single Postgres connection, not a pool | BUG | P1 | ✅ |
| 15 | Per-tool argument schema validation absent; `DATABASE_QUERY` takes raw SQL | GAP/SEC | P0 | ✅ |
| 16 | `SagaTransaction` dataclass dead-code; coordinator uses raw `dict` | GAP | P2 | ✅ |
| 17 | Unknown-saga `execute_saga` silently auto-creates saga as `default_tenant` | BUG | P1 | ✅ |
| 18 | No saga step idempotency key — duplicate submission double-executes | GAP | P1 | ✅ |
| 19 | Embedding calls not cached; repeated identical queries hit OpenAI every time | PERF/COST | P2 | ✅ |
| 20 | In-memory saga state mirror in `SagaStateStore` never pruned — memory leak | BUG | P2 | ✅ |
| 21 | No request-ID / correlation-ID propagation across log lines | GAP | P2 | ✅ |
| 22 | Consolidation uses connected-components, not density clustering (DBSCAN) | PERF/STUB | P2 | ✅ |
| 23 | Retention math computed per-row in Python; should push to TimescaleDB SQL | PERF | P2 | ⬜ |
| 24 | gRPC server requires `make proto` codegen; not automated in CI | GAP | P2 | ✅ |
| 25 | No Postgres connection reconnect / health-check after drop | BUG | P1 | ✅ |
| 26 | Integration test suite not wired into CI (only runs locally `RUN_INTEGRATION=1`) | GAP | P1 | ✅ |
| 27 | Pluggable tool registry absent; allow-list is a hardcoded `frozenset` | GAP/FEAT | P2 | ✅ |
| 28 | No scheduler for consolidation "sleep cycle" — manual POST only | GAP | P2 | ✅ |
| 29 | No dead-letter / human-intervention path for `COMPENSATION_FAILED` sagas | GAP | P1 | ✅ |
| 30 | No timeouts or retries on Neo4j / LLM / Z3 external calls | GAP | P1 | 🟡 |
| 31 | `/memory/active` returns unbounded result set — no pagination | GAP | P2 | ✅ |
| 32 | Distributed saga orchestration (Temporal/Celery) — single-process only | FEAT | P2 | ⬜ |
| 33 | GraphRAG-style retrieval: Neo4j graph never feeds agent context | FEAT | P2 | ⬜ |
| 34 | Human-in-the-loop saga gate: pause for approval before high-risk step | FEAT | P3 | ⬜ |
| 35 | Replay / time-travel debugging from durable step log | FEAT | P3 | ⬜ |
| 36 | WebSocket / SSE streaming of step events to clients | FEAT | P3 | ⬜ |
| 37 | OPA / Rego policy engine alongside Z3 for authorization rules | FEAT | P3 | ⬜ |
| 38 | Memory importance reinforcement learning from retrieval outcomes | FEAT | P3 | ⬜ |
| 39 | SDK / client library (Python first) | FEAT | P3 | ⬜ |
| 40 | Rust/PyO3 native extension for cosine distance kernel | PERF | P3 | ⬜ |
| 41 | Dependabot / Renovate for dependency freshness | GAP | P3 | ✅ |
| 42 | `mypy` `disallow_untyped_defs = false` — type annotations incomplete | GAP | P3 | ⬜ |
| 43 | Property-based tests (Hypothesis) for saga FSM and decay math | GAP | P2 | ✅ |

---

## 1. Bugs — must fix before any production traffic

### 1.1 ✅ [BUG] `psycopg2.pool` never imported — DB always fell back to memory
**Fixed.** `from psycopg2 import pool as pg_pool`. The store now connects correctly and
registers the pgvector type adapter.

### 1.2 ✅ [BUG] `SagaStateStore` uses a single Postgres connection, not a pool

**Fixed.** `_try_postgres` now builds a `pool.ThreadedConnectionPool(minconn=2, maxconn=10)`;
`_pg_conn`/`_pg_return` checkout/return with reconnect-on-stale, `close()` calls `closeall()`.
Original diagnosis kept below for context.

**Location:** `src/orchestrator/state_store.py:77` — `psycopg2.connect(...)` returns one
connection with `autocommit = True`.

**Problem:** A production API handles concurrent requests. Two saga steps executing in
parallel (or `/saga/step` + `/saga/{id}/status` simultaneous) will race over a single
`psycopg2` connection — `psycopg2` is not thread-safe on one connection. After a network
hiccup the dropped connection is never re-established; all subsequent calls fall silently to
the in-memory mirror with no `RUNNING` → `ROLLED_BACK` state transition for the broken
transactions.

**Fix:**
```python
from psycopg2 import pool as pg_pool

self._pg_pool = pg_pool.ThreadedConnectionPool(
    minconn=2, maxconn=10,
    host=settings.db_host, port=settings.db_port,
    dbname=settings.db_name, user=settings.db_user, password=settings.db_pass,
)
```
Use `self._pg_pool.getconn()` / `putconn()` in a `try/finally` block within each method.
Replace the current `self._pg` single-connection path. Add a `close()` that calls
`self._pg_pool.closeall()`.

### 1.3 ✅ [BUG] `execute_saga` silently auto-creates a saga for unknown `saga_id`

**Fixed.** Raises `CoordinatorError("Saga '...' not found. Call start_transaction_log first.")`;
`/saga/step` catches it → HTTP 404. Original diagnosis kept below for context.

**Location:** `src/orchestrator/coordinator.py:135`
```python
if saga_id not in self.active_sagas:
    self.start_transaction_log(saga_id, "Workflow Execution", "default_tenant")
```

**Problem:** If a client sends a `POST /saga/step` with a fabricated or expired `saga_id`,
the coordinator silently creates a new saga owned by `"default_tenant"` and runs the step.
This bypasses tenant isolation entirely — any client can inject steps into any tenant's
resource namespace by guessing or reusing a saga ID.

**Fix:** Raise `CoordinatorError` (HTTP 404) when the saga is not found:
```python
if saga_id not in self.active_sagas:
    raise CoordinatorError(f"Saga '{saga_id}' not found or has already terminated.")
```
The `/saga/step` endpoint should catch `CoordinatorError` and return 404.

### 1.4 ✅ [BUG] In-memory saga state mirror in `SagaStateStore` never pruned

**Fixed.** `_state`/`_comps` are written only when `self.backend == "memory"`. Original
diagnosis kept below for context.

**Location:** `src/orchestrator/state_store.py:141-143`
```python
rec = self._state.setdefault(saga_id, {"saga_id": saga_id, "metadata": {}})
rec["status"] = status
rec["metadata"].update(metadata or {})
```

**Problem:** `write_transaction_state` always updates `self._state` regardless of backend.
In a long-running service processing thousands of sagas/day, `_state` grows without bound.
At 1 000 sagas/day with average 2 KB of metadata each, this is ~2 MB/day — not catastrophic,
but it never shrinks.

**Fix:** Only write to `_state` when `self.backend == "memory"`. When using Postgres or Redis,
there is no reason to mirror every write into a Python dict:
```python
def write_transaction_state(self, saga_id, status, metadata):
    if self.backend == "postgres":
        self._pg_write_state(saga_id, status, metadata)
    elif self.backend == "redis":
        ...
    else:  # memory backend only
        rec = self._state.setdefault(saga_id, {"saga_id": saga_id, "metadata": {}})
        rec["status"] = status
        rec["metadata"].update(metadata or {})
```

### 1.5 ✅ [BUG] Postgres connection not re-established after drop

**Fixed via the pool (§1.2).** `_pg_conn()` retries `getconn()` through `_try_postgres()`
reconnect on failure; pool manages connection lifecycle/health. Original diagnosis below.

**Location:** `src/orchestrator/state_store.py` — all methods call `self._pg.cursor()`.

**Problem:** If the Postgres server drops idle connections (common: `idle_in_transaction_session_timeout`,
TCP keepalive failures, Postgres restart), the single connection becomes unusable. All subsequent
`cursor()` calls raise `InterfaceError: connection already closed`, which the calling code does
not catch → exception propagates to the HTTP handler → 500.

**Fix (with pool, §1.2):** The pool handles connection lifecycle. Without the pool: wrap each
`cursor()` call in a reconnect guard:
```python
def _pg_cursor(self):
    try:
        return self._pg.cursor()
    except psycopg2.InterfaceError:
        self._try_postgres()  # reconnect
        return self._pg.cursor()
```
With a pool this is unnecessary — always prefer the pool approach.

---

## 2. Security — must close before any real deployment

### 2.1 🟡 [STUB/SEC] Built-in tools still run on the host; microVM not the default

**Location:** `src/orchestrator/sandbox.py:62-74` (`execute` dispatch).
`WRITE_FILE` → `_write_file` → `open(safe_path, "w")` on the host OS.
`run_wasm_module` (the real isolation primitive) is implemented but only called by
external callers who explicitly hand it `.wasm` bytes — the built-in reference tools do
not go through it.

**What this means in practice:** A path-jail (`contain_path`) and a tool allow-list are in
place, which defends against simple traversal. But the executing process still has full OS
access: it can open network sockets, spawn subprocesses, read files outside the jail if a
symlink is planted after the jail check, and exhaust CPU/RAM freely. This is not a sandbox —
it is a best-effort filter.

**What production requires (strongest to weakest):**

1. **WASI as the default (recommended, already partially wired):**  
   Compile every reference tool to a WASI module (Rust or C via `wasi-sdk`). Load them with
   `run_wasm_module`. The guest is fuel-limited and can only see the preopened workspace
   directory — no sockets, no `/proc`, no host path escape. CPU exhaustion is bounded by fuel.
   `wasmtime` already handles this; the wiring is in place, tools just need to be compiled.

2. **gVisor (runsc) or Firecracker microVM:**  
   Wrap each step execution in a rootless `docker run --runtime=runsc` or a Firecracker VM.
   More overhead (50-200 ms cold-start per step) but no dependency on tools being compiled to
   WASM. Suitable for arbitrary language tools.

3. **At minimum (current + hardening):**  
   - Use `O_NOFOLLOW` when opening files (prevents TOCTOU symlink swaps between `contain_path`
     and `open`). Python: `os.open(path, os.O_WRONLY|os.O_CREAT|os.O_NOFOLLOW)`.
   - Drop unnecessary capabilities in the container (`cap_drop: [ALL]`; already in compose but
     verify the API service entry too).
   - Set `ulimit -n` (open files) and cgroup CPU/memory limits on the process so a misbehaving
     tool cannot starve the host.

**Concrete next step:** Write `tools/write_file.rs` (a tiny WASI module that reads `args[1]`
path + `args[2]` content and writes it), compile via `cargo build --target wasm32-wasi`,
embed the bytes in `sandbox.py`, and redirect `_ALLOWED_ACTIONS["WRITE_FILE"]` to
`run_wasm_module(WRITE_FILE_WASM, ...)`. All existing tests pass because `SandboxResult`
interface is unchanged.

### 2.2 ✅ [GAP/SEC] Per-tool argument schema validation absent; `DATABASE_QUERY` takes raw SQL

**Fixed.** `src/main.py` adds `WriteFileArgs`/`DatabaseQueryArgs(table, operation: Literal[...],
filters)`/`NoopArgs` Pydantic schemas + `_validate_tool_args()` gate before sandbox dispatch —
no raw SQL string accepted. Original diagnosis kept below for context.

**Location:** `src/orchestrator/sandbox.py:72`
```python
if tool == "DATABASE_QUERY":
    return SandboxResult(success=True, data={"affected_rows": 1})
```
`StepProposal.arguments` (`src/main.py:180`) is `dict[str, Any]` with no validation.

**Problem:** Two attack surfaces:
1. A caller can submit `{"tool_name": "DATABASE_QUERY", "arguments": {"sql": "DROP TABLE saga_transactions;"}}`.
   The reference stub returns immediately without executing, but any real implementation that
   replaces the stub will inherit this injection surface.
2. Even non-malicious callers can submit structurally invalid arguments
   (e.g. `WRITE_FILE` with `path` missing) — currently these fail at runtime with an
   unstructured Python error traceback in the log rather than a clean validation error.

**Fix: two-layer validation**

Layer 1 — API schema (`src/main.py`): replace `arguments: dict[str, Any]` with a discriminated
union:
```python
class WriteFileArgs(BaseModel):
    path: str
    content: str = ""

class DatabaseQueryArgs(BaseModel):
    table: str                   # named table only, no raw SQL
    operation: Literal["SELECT", "INSERT", "UPDATE", "DELETE"]
    filters: dict[str, Any] = {}

ToolArguments = Annotated[WriteFileArgs | DatabaseQueryArgs | ..., Field(discriminator="tool_name")]
```

Layer 2 — sandbox allow-list cross-check (`src/orchestrator/sandbox.py`): even if the API
schema is bypassed (e.g. via gRPC), the sandbox validates argument keys against a per-tool
schema before execution:
```python
_TOOL_SCHEMAS: dict[str, type] = {
    "WRITE_FILE": WriteFileArgsSchema,
    "DATABASE_QUERY": DatabaseQueryArgsSchema,
}
def execute(self, action):
    if action.tool_name not in _TOOL_SCHEMAS:
        raise SandboxError(...)
    _TOOL_SCHEMAS[action.tool_name](**action.arguments)  # pydantic validate
    ...
```
For `DATABASE_QUERY`: never accept a raw SQL string. Accept a table name + operation enum +
named parameter dict; build the parameterized query server-side.

### 2.3 ✅ [GAP] No saga step idempotency keys

**Fixed.** `SagaStep.idempotency_key`, `StepProposal.idempotency_key`,
`SagaStateStore.step_already_committed`/`mark_step_committed` (table `saga_step_idempotency`),
coordinator short-circuits already-committed steps before re-execution. Original diagnosis
kept below for context.

**Location:** `src/orchestrator/coordinator.py:120-188` (`execute_saga`).

**Problem:** If a client submits `POST /saga/step` and the connection drops before it gets
the response, it will retry. The second submission executes the step again — double-writes a
file, double-inserts a database row, double-charges a payment. Saga semantics guarantee
*consistency*, not *idempotency*.

**Fix:** Accept an optional `idempotency_key` in `StepProposal` (a client-generated UUID).
Store it in `saga_compensations` (or a separate `saga_step_idempotency` table). On retry,
look up the key; if found, return the cached result without re-executing:
```python
class StepProposal(BaseModel):
    ...
    idempotency_key: str | None = None

# In coordinator.execute_saga:
if step.idempotency_key and self.db.step_already_committed(saga_id, step.idempotency_key):
    completed.append(step)
    continue  # skip execution, treat as already committed
```

---

## 3. Correctness gaps

### 3.1 ✅ [GAP] `SagaTransaction` dataclass is dead code; coordinator uses raw `dict`

**Fixed.** `active_sagas: dict[str, SagaTransaction]`; `start_transaction_log` constructs the
dataclass; `get_saga_status` reads typed attributes. Original diagnosis kept below.

**Location:** `src/models.py:131-144` (`SagaTransaction` defined).
`src/orchestrator/coordinator.py:107-114` (`start_transaction_log` builds a raw dict).

**Problem:** `SagaTransaction` has typed fields (`saga_id: str`, `goal: str`, etc.) but
`self.active_sagas` is `dict[str, dict[str, Any]]`. The dict grows with ad-hoc keys
(`"completed_steps"`, `"start_time"`, etc.) that are not declared anywhere. mypy cannot
check key access; a typo silently returns `None` instead of failing fast. `get_saga_status`
does attribute-like dict access with no error if a key is missing.

**Fix:** Replace `dict[str, dict[str, Any]]` with `dict[str, SagaTransaction]` in the
coordinator. Deserialize from the dict on recovery, serialize to dict for JSON responses.
Update `start_transaction_log` to construct a `SagaTransaction` dataclass:
```python
from src.models import SagaTransaction

self.active_sagas: dict[str, SagaTransaction] = {}

def start_transaction_log(self, saga_id, goal, tenant_id):
    import time
    self.active_sagas[saga_id] = SagaTransaction(
        saga_id=saga_id, tenant_id=tenant_id, goal=goal,
        status=SagaStatus.RUNNING.value, start_time=time.time(),
    )
```
`get_saga_status` then uses `dataclasses.asdict()` for serialization — no manual dict key
access.

### 3.2 ✅ [GAP] No request-ID / correlation-ID in logs

**Fixed.** `ContextVar[str]` + Starlette middleware `inject_request_id` sets `X-Request-ID`
(generated if absent), echoes it on the response. Original diagnosis kept below.

**Location:** `src/main.py` — no middleware injects a request ID. `src/logging_config.py`
has no request-ID filter.

**Problem:** When a saga step fails, the log has `[SAGA-<id>]` prefixes in the coordinator
but the inbound HTTP request, verifier call, and sandbox call log under different names with
no shared correlation key. Debugging across subsystems requires grepping by saga ID, which
only works if every log line includes it (they don't — verifier and sandbox log without it).

**Fix:** Add a `contextvars.ContextVar[str]` for request ID. Inject it in a Starlette middleware:
```python
from contextvars import ContextVar
import uuid

_request_id: ContextVar[str] = ContextVar("request_id", default="")

@app.middleware("http")
async def inject_request_id(request: Request, call_next):
    rid = request.headers.get("X-Request-ID") or uuid.uuid4().hex[:12]
    token = _request_id.set(rid)
    response = await call_next(request)
    response.headers["X-Request-ID"] = rid
    _request_id.reset(token)
    return response
```
Add a `logging.Filter` subclass that reads `_request_id.get()` and injects it into every
`LogRecord`. Configure it in `configure_logging()`. Now every log line — across verifier,
sandbox, coordinator — carries the same request ID.

### 3.3 ✅ [GAP] gRPC server requires `make proto` codegen before it can start

**Fixed.** CI `grpc` job runs `scripts/gen_proto.sh` then smoke-tests `build_servicer()`.
Original diagnosis kept below.

**Location:** `src/grpc_server.py:_load_stubs()` — raises `ImportError` with a helpful
message if `src/generated/` is absent.

**Problem:** The generated stubs (`src/generated/sagamind_pb2.py`, `sagamind_pb2_grpc.py`)
are not committed (correct) but also not generated in CI. Any developer who clones the repo
and runs `make grpc` without first running `make proto` gets a runtime error. The CI
workflow has no `grpc` job that tests the gRPC server boots.

**Fix (two parts):**

1. Add a CI job:
```yaml
grpc:
  name: gRPC codegen + smoke test
  runs-on: ubuntu-latest
  steps:
    - uses: actions/checkout@v4
    - uses: actions/setup-python@v5
      with: {python-version: "3.11", cache: pip}
    - run: pip install -e ".[dev,grpc]"
    - run: bash scripts/gen_proto.sh
    - run: python -c "from src.grpc_server import build_servicer; build_servicer()"
```

2. In `Makefile`, make `grpc` depend on `proto`:
```makefile
grpc: proto
    python src/grpc_server.py
```

### 3.4 🟡 [GAP] No timeouts or retries on external calls

**Partially fixed.** `neo4j_store.py` now wraps `upsert_relationship`/`get_neighbors`/
`get_all_relationships` in a `tenacity` retry (`stop_after_attempt(3)`,
`wait_exponential`) and sets `connection_timeout=settings.neo4j_timeout_s` on the driver.
**Still open:** `consolidation._llm_summarize` has no timeout/retry on the LLM client call.
Original diagnosis kept below.

**Locations:**
- `src/memory/neo4j_store.py` — `driver.session().execute_write(...)` has no timeout.
- `src/memory/consolidation.py:_llm_summarize` — `self.llm.summarize(prompt)` has no timeout.
- `src/verifier/z3_prover.py` — Z3 solver timeout exists (`settings.z3_timeout_ms`) but
  Neo4j and LLM do not.

**Problem:** A slow Neo4j query (e.g. graph traversal over a large concept graph) or a
hanging LLM call will hold a FastAPI worker thread indefinitely, exhausting the thread pool
and making the API unresponsive to all tenants.

**Fix:**
```python
# Neo4j — use driver-level timeout:
with self.driver.session() as session:
    session.execute_write(tx_fn, timeout=30)  # seconds

# LLM — use httpx with timeout:
response = client.post(url, json=payload, timeout=httpx.Timeout(10.0, connect=5.0))

# Any blocking call in an async context — wrap with asyncio.wait_for:
result = await asyncio.wait_for(
    asyncio.to_thread(self.graph.get_neighbors, concept),
    timeout=10.0,
)
```
For retries, use `tenacity` (already a reasonable dep for this stack):
```python
from tenacity import retry, stop_after_attempt, wait_exponential, retry_if_exception_type

@retry(stop=stop_after_attempt(3), wait=wait_exponential(multiplier=0.5, max=4),
       retry=retry_if_exception_type(neo4j.exceptions.TransientError))
def _neo4j_write(self, fn, *args):
    ...
```

### 3.5 ✅ [GAP] No dead-letter / escalation path for `COMPENSATION_FAILED` sagas

**Fixed.** `_handle_compensation_failure()` marks the saga and calls `db.push_dead_letter()`
(table `saga_dead_letters`); `GET /saga/dead-letters` exposes `list_dead_letters()` for
operator review. Original diagnosis kept below.

**Location:** `src/orchestrator/coordinator.py:213-231` — `execute_compensations` logs
`CRITICAL` and returns when a compensation fails.

**Problem:** When a saga's compensation fails, the system is in an inconsistent state — some
mutations committed, some not reversed. This is logged as `CRITICAL` but nothing else happens.
No operator is paged. No ticket is created. The saga is marked `COMPENSATION_FAILED` in the
state store and forgotten. Without a recovery path, the environment stays inconsistent forever.

**Fix:**
1. On `COMPENSATION_FAILED`, publish an event to a dead-letter queue (Redis `LPUSH`
   `sagas:dead_letter`, or a Postgres `saga_dead_letters` table):
```python
if self.db and hasattr(self.db, "push_dead_letter"):
    self.db.push_dead_letter(saga_id, step.step_name, step.error)
```
2. Expose `GET /saga/dead-letters` endpoint so operators can inspect and manually resolve.
3. Emit a Prometheus counter (already `metrics.inc("compensations_failed")`) and configure
   an alert rule: any non-zero rate of `compensations_failed_total` → PagerDuty / OpsGenie.
4. Document the manual resolution runbook in `CONTRIBUTING.md`.

### 3.6 ✅ [GAP] `/memory/active` has no pagination

**Fixed.** `limit: int = Query(default=20, ge=1, le=200)` / `offset: int = Query(default=0,
ge=0)`; `retrieve_similar_memories(..., limit, offset)` pushes `LIMIT`/`OFFSET` into the SQL
(and the in-memory fallback). Original diagnosis kept below.

**Location:** `src/main.py:279-298` — `timescale.retrieve_similar_memories(tenant_id, vector)`
returns all matching rows; the endpoint returns them all.

**Problem:** A tenant with 100 000 memories will return a multi-MB JSON response, exhausting
the request-size limit (1 MiB default) or causing OOM in the response serialization path.

**Fix:** Add `limit` and `offset` query parameters:
```python
@app.get("/memory/active", dependencies=_PROTECTED)
def get_active_memories(
    tenant_id: str,
    query: str | None = None,
    limit: int = Query(default=20, ge=1, le=200),
    offset: int = Query(default=0, ge=0),
) -> dict[str, Any]:
    ...
    memories = timescale.retrieve_similar_memories(tenant_id, query_vector, limit=limit, offset=offset)
    ...
    return {"active_memories": active, "limit": limit, "offset": offset, "count": len(active)}
```
Update `TimescaleMemoryStore.retrieve_similar_memories` to pass `LIMIT` and `OFFSET` to
the SQL query.

---

## 4. Performance — measurable hot paths

### 4.1 🟡 Vector math — NumPy vectorized (done for consolidation; partial elsewhere)

**Done:** `consolidation._distance_matrix` is NumPy-vectorized. Batch decay in
`decay.calculate_retention_batch` is NumPy-vectorized.

**Still needed:**
- `timescale_store._fallback_similarity` uses a Python `sum()` cosine loop for every pair
  in the fallback in-memory store. Replace with the same NumPy matrix approach used in
  consolidation.
- `z3_prover` builds Python `dict` → SMT-LIB2 string via string formatting for every
  argument. For large argument payloads this is fine (Z3 is the bottleneck), but profile
  before assuming.

### 4.2 ⬜ [PERF] Push retention math to TimescaleDB SQL

**Location:** `src/memory/timescale_store.py:retrieve_similar_memories` + `src/main.py:296`.

**Problem:** Currently: fetch all episodic rows into Python, compute retention per row in
Python, filter by `>= tau`. For a tenant with 100 000 memories this materializes ~150 MB
of embedding vectors into Python just to discard 80% of them.

**Fix:** Move retention filtering into SQL. TimescaleDB supports arbitrary SQL expressions:
```sql
SELECT *,
    EXP(-EXTRACT(EPOCH FROM (now() - last_retrieved_at))
        / GREATEST(
            :s_init * (1.0 + :gamma * LN(retrieval_count + 1)) * importance_score,
            1e-9
        )
    ) AS retention
FROM episodic_memories
WHERE tenant_id = :tenant_id
  AND embedding <=> :query_vec < :distance_threshold
  AND EXP(-EXTRACT(EPOCH FROM (now() - last_retrieved_at))
        / GREATEST(:s_init * (1.0 + :gamma * LN(retrieval_count + 1)) * importance_score, 1e-9)
    ) >= :tau
ORDER BY embedding <=> :query_vec
LIMIT :limit;
```
This is a single network round-trip instead of N round-trips + Python for-loop. At 100 K
memories this is typically 10-100x faster end-to-end.

Add `S_INIT`, `GAMMA`, and `TAU` as query parameters passed from `settings` so the SQL
expression stays in sync with the Python implementation.

### 4.3 ✅ [PERF/STUB] Replace connected-components clustering with DBSCAN

**Fixed.** `_cluster()` tries `sklearn.cluster.DBSCAN(eps, min_samples=2, metric="cosine")`
on unit-normalized vectors first (label `-1` = noise, skipped), falls back to
connected-components when sklearn is absent or embeddings are ragged. Tests updated:
`test_isolated_vectors_treated_as_noise` (0 clusters) + new
`test_two_dense_groups_form_two_clusters`. Original diagnosis kept below.

**Location:** `src/memory/consolidation.py:_cluster`.

**Problem:** The current implementation is single-linkage connected-components — every node
within `eps` distance of *any* cluster member joins. This has two issues:
1. With a low `eps` it produces many single-node clusters (noise treated as signal).
2. With a high `eps` it merges unrelated memories into one "concept" (chaining effect).
DBSCAN with `min_samples=2` correctly treats isolated points as noise and respects density,
which is what a "sleep cycle consolidation" should do.

**Fix:** `scikit-learn` is already a dashboard dependency:
```python
from sklearn.cluster import DBSCAN

def _cluster(self, episodes, eps=0.2, min_samples=2):
    embeddings = np.array([_embedding(ep) for ep in episodes], dtype=float)
    # Normalize for cosine metric
    norms = np.linalg.norm(embeddings, axis=1, keepdims=True)
    norms[norms == 0] = 1.0
    unit = embeddings / norms
    labels = DBSCAN(eps=eps, min_samples=min_samples, metric="cosine").fit_predict(unit)
    clusters = {}
    for idx, label in enumerate(labels):
        if label == -1:
            continue  # noise
        clusters.setdefault(label, []).append(episodes[idx])
    return clusters
```
This change will alter cluster counts — existing tests that assert specific cluster counts
need updating. Write new tests that assert: noise points (isolated) are excluded, dense
groups are merged, and the total number of graph edges written equals the expected value.

### 4.4 ✅ [PERF] Embedding result caching

**Fixed (in-process LRU; Redis tier still open as a future option).**
Module-level `@lru_cache(maxsize=4096)` on `_cached_embed(text, model, dim, client)`;
`EmbeddingService.embed()` delegates to it. Original diagnosis kept below.

**Location:** `src/memory/embedding.py:embed`.

**Problem:** The `EmbeddingService.embed` method is called on every `/memory/active` request
and on every write. If the same query string (`"agent planning"`) appears 100 times/min, it
makes 100 identical OpenAI API calls at ~$0.00002 per call. At 100 RPM this is negligible,
but at 100 000 RPM it is significant and adds 50-200 ms latency per call.

**Fix:** Add an LRU cache keyed on the input string + model name:
```python
from functools import lru_cache

@lru_cache(maxsize=4096)
def _cached_embed(self, text: str, model: str) -> tuple[float, ...]:
    return tuple(self._call_openai(text, model))

def embed(self, text: str) -> list[float]:
    return list(self._cached_embed(text, self.model))
```
For a distributed deployment, promote to Redis with a TTL (embeddings for the same model
version are stable; a 24 h TTL is safe):
```python
cache_key = f"emb:{model}:{hashlib.sha256(text.encode()).hexdigest()}"
if cached := redis.get(cache_key):
    return json.loads(cached)
vec = self._call_openai(text)
redis.setex(cache_key, 86400, json.dumps(vec))
return vec
```

### 4.5 ⬜ [PERF] Rust/PyO3 native extension for cosine distance kernel

**When to reach for this:** Only after §4.1–4.4 are implemented and profiling (`py-spy
record -o profile.svg -- uvicorn src.main:app`) shows the cosine kernel still dominates.
For most workloads, NumPy + BLAS is already C-speed and Rust will not move the needle.

**If profiling confirms:** Write `sagamind_native/src/lib.rs` using PyO3 + `ndarray`:
```rust
use ndarray::{Array2, Axis};
use numpy::{IntoPyArray, PyArray2, PyReadonlyArray2};
use pyo3::prelude::*;

#[pyfunction]
fn cosine_distance_matrix<'py>(
    py: Python<'py>,
    m: PyReadonlyArray2<'py, f32>,
) -> &'py PyArray2<f32> {
    let a = m.as_array();
    let norms = a.map_axis(Axis(1), |row| row.dot(&row).sqrt());
    // normalize rows, compute A @ A^T, return 1 - result
    ...
}
```
Package with `maturin`. This yields SIMD-vectorized distances without leaving Python's
package model. Reserve for when `n > 50 000` and the NumPy path is verified to be the
bottleneck.

### 4.6 ⬜ [PERF] pgvector HNSW index tuning

**Location:** `migrations/001_init.sql` — HNSW index is created with defaults.

**Problem:** The default `hnsw (m=16, ef_construction=64)` index is a good starting point
but for 1536-dim OpenAI embeddings with cosine distance, production workloads may need
tuning. Un-tuned HNSW can have lower recall than expected at high QPS.

**Fix:** After collecting production query patterns, benchmark with:
```sql
-- Query-time ef_search (higher = more recall, slower):
SET hnsw.ef_search = 100;  -- default 40

-- Rebuild index with tuned parameters:
DROP INDEX IF EXISTS episodic_memories_embedding_hnsw;
CREATE INDEX episodic_memories_embedding_hnsw
    ON episodic_memories
    USING hnsw (embedding vector_cosine_ops)
    WITH (m = 24, ef_construction = 128);
```
Add `EF_SEARCH` to `Settings` and pass it via `SET LOCAL hnsw.ef_search = :ef;` on each
connection checkout.

---

## 5. CI/CD gaps

### 5.1 ✅ Integration tests not wired into CI

**Fixed.** `ci.yml` adds an `integration` job (PR-only) with TimescaleDB + Redis + Neo4j
service containers running `RUN_INTEGRATION=1 pytest -m integration`.

<!-- Original plan kept below for reference of the exact service-container config used. -->

**Fix:** Add a CI job with Docker service containers:
```yaml
integration:
  name: Integration (live backends)
  runs-on: ubuntu-latest
  services:
    timescaledb:
      image: timescale/timescaledb:latest-pg16
      env:
        POSTGRES_USER: sagamind_user
        POSTGRES_PASSWORD: sagamind_secure_pass_2026
        POSTGRES_DB: sagamind
      ports: ["5432:5432"]
      options: >-
        --health-cmd "pg_isready -U sagamind_user -d sagamind"
        --health-interval 10s --health-timeout 5s --health-retries 5
    redis:
      image: redis:7-alpine
      ports: ["6379:6379"]
    neo4j:
      image: neo4j:5
      env:
        NEO4J_AUTH: neo4j/sagamind_secure_neo_2026
      ports: ["7687:7687"]
  steps:
    - uses: actions/checkout@v4
    - uses: actions/setup-python@v5
      with: {python-version: "3.11", cache: pip}
    - run: pip install -e ".[dev,redis,integration]"
    - run: RUN_INTEGRATION=1 pytest -m integration --tb=short
      env:
        DB_HOST: 127.0.0.1
        NEO4J_URI: bolt://127.0.0.1:7687
        REDIS_HOST: 127.0.0.1
```
Gate this on PRs to `main` only (not every push) to manage CI cost.

### 5.2 ✅ No container build / publish job in CI

**Fixed.** `ci.yml` adds a `docker` job (`needs: [lint, test]`, builds via
`docker/build-push-action`, pushes only on `main`).

**Problem:** The Dockerfile is hardened (non-root, healthcheck, `no-new-privileges`) but is
never built in CI. A merge that breaks the Docker image won't be caught until someone runs
`docker compose up --build` manually.

**Fix:**
```yaml
docker:
  name: Docker build
  runs-on: ubuntu-latest
  needs: [lint-type, test]
  steps:
    - uses: actions/checkout@v4
    - uses: docker/setup-buildx-action@v3
    - name: Build image
      uses: docker/build-push-action@v5
      with:
        context: .
        push: ${{ github.ref == 'refs/heads/main' }}
        tags: ghcr.io/${{ github.repository }}:${{ github.sha }}
        cache-from: type=gha
        cache-to: type=gha,mode=max
```

### 5.3 ✅ gRPC codegen not in CI

Covered in §3.3 — `grpc` CI job added.

### 5.4 ✅ No Dependabot / Renovate configuration

**Fixed.** `.github/dependabot.yml` added: pip (weekly, dev-deps/observability groups,
ignores major pydantic/fastapi bumps), docker (weekly), github-actions (weekly).

**Problem:** No `dependabot.yml` or `renovate.json`. Dependency versions in `pyproject.toml`
are lower-bounded (`>=`) with no upper bounds — any transitive upgrade can silently
introduce a breaking change or a CVE.

**Fix:** Add `.github/dependabot.yml`:
```yaml
version: 2
updates:
  - package-ecosystem: "pip"
    directory: "/"
    schedule:
      interval: "weekly"
    groups:
      dev-deps:
        patterns: ["pytest*", "ruff", "mypy*", "httpx"]
  - package-ecosystem: "docker"
    directory: "/"
    schedule:
      interval: "weekly"
  - package-ecosystem: "github-actions"
    directory: "/"
    schedule:
      interval: "weekly"
```

### 5.5 ⬜ `mypy` has `disallow_untyped_defs = false`; many functions untyped

**Location:** `pyproject.toml:[tool.mypy]` — `disallow_untyped_defs = false`.

**Problem:** mypy only catches type errors in functions that have annotations. Untyped
functions (`def start_transaction_log(self, saga_id, goal, tenant_id):`) pass mypy
silently regardless of what they do. The project advertises `Typing :: Typed` in its
classifiers but is not actually fully typed.

**Fix (gradual tightening):**
1. Enable `disallow_untyped_defs = true` per module as annotations are added.
2. Add `# type: ignore[no-untyped-def]` only where a third-party API forces it.
3. Target `disallow_untyped_defs = true` globally within two release cycles.
4. Add `--strict` to the mypy CI command once coverage is high.

### 5.6 ✅ No property-based tests for saga FSM or decay math

**Fixed.** `tests/test_property_based.py` (gated by `pytest.importorskip("hypothesis")`):
saga-always-terminal (200 examples), fully-committed-saga (100), retention-in-[0,1] (500),
deterministic-embedding-unit-norm (100), `contain_path`-stays-inside-root (200).

**Problem:** The saga state machine has a complex transition graph (PENDING → RUNNING →
COMMITTED / COMPENSATING → ROLLED_BACK / COMPENSATION_FAILED). Unit tests cover
specific paths but not the invariant: *"any sequence of valid inputs must leave the saga in
a terminal consistent state."* Hypothesis can generate adversarial step sequences.

**Fix — saga FSM:**
```python
from hypothesis import given, strategies as st

valid_step = st.fixed_dictionaries({
    "step_name": st.text(min_size=1, max_size=20),
    "tool_name": st.sampled_from(["WRITE_FILE", "NOOP"]),
    ...
})

@given(steps=st.lists(valid_step, min_size=0, max_size=10))
def test_saga_always_terminates_consistently(steps):
    coord = SagaTransactionCoordinator(mock_verifier, mock_sandbox)
    saga_id = "test-saga"
    coord.execute_saga(saga_id, build_steps(steps))
    final = coord.active_sagas[saga_id]["status"]
    assert final in {s.value for s in SagaStatus if s.name in
                     ("COMMITTED", "ROLLED_BACK", "COMPENSATION_FAILED")}
```

**Fix — decay math:**
```python
@given(
    s_init=st.floats(0.01, 100.0),
    importance=st.floats(0.0, 1.0),
    n_access=st.integers(0, 10000),
    elapsed_hours=st.floats(0.0, 8760.0),
)
def test_retention_always_in_unit_interval(s_init, importance, n_access, elapsed_hours):
    r = calculate_retention_scalar(s_init, importance, n_access, elapsed_hours)
    assert 0.0 <= r <= 1.0
```

---

## 6. Feature roadmap (beyond production parity)

### 6.1 ✅ Pluggable tool registry

**Fixed.** `ToolDefinition` dataclass (`handler`, `compensation_handler`,
`wasm_module_path`, `description`) + `ToolRegistry` (`register`/`get`/
`is_compensation_allowed`/`allowed_actions`/`allowed_compensations`); module-level
`registry` singleton. `WasmSandbox.execute`/`execute_compensation` delegate to it,
replacing the hardcoded `frozenset` allow-list. Original design kept below.

**Problem:** `_ALLOWED_ACTIONS` is `frozenset({"WRITE_FILE", "DATABASE_QUERY", "NOOP"})`.
Adding a new tool requires editing `sandbox.py` — it is not extensible by users without
forking the codebase. There is no way to declare a tool's forward action, compensation,
invariant schema, and argument schema as a unit.

**Design:**
```python
@dataclass
class ToolDefinition:
    name: str
    description: str
    argument_schema: type[BaseModel]    # pydantic for validation
    compensation_name: str
    compensation_schema: type[BaseModel]
    default_invariant: str = ""         # SMT-LIB2 string, empty = no Z3 check
    wasm_module_path: str | None = None # if set, run via run_wasm_module

class ToolRegistry:
    _tools: dict[str, ToolDefinition] = {}

    def register(self, tool: ToolDefinition) -> None:
        self._tools[tool.name] = tool

    def get(self, name: str) -> ToolDefinition:
        if name not in self._tools:
            raise SandboxError(f"Unknown tool: {name!r}")
        return self._tools[name]

registry = ToolRegistry()
registry.register(ToolDefinition("WRITE_FILE", ..., wasm_module_path="tools/write_file.wasm"))
```
`WasmSandbox.execute` delegates to `registry.get(tool_name)` instead of hardcoded `if/elif`.
Users register custom tools in their entry-point before starting the server.

### 6.2 ✅ Scheduled sleep-cycle consolidation

**Fixed.** `AsyncIOScheduler` (lazy-imported, no-op when `apscheduler` absent) starts in the
FastAPI lifespan when `settings.consolidation_cron` is set, running
`consolidator.run_consolidation_cycle` on the configured cron expression. Original design
kept below.

**Problem:** `POST /memory/consolidate` must be called manually. A real cognitive memory
system runs consolidation automatically on a schedule (analogous to overnight sleep).

**Fix:** Add APScheduler (lightweight, no broker required):
```python
from apscheduler.schedulers.asyncio import AsyncIOScheduler

scheduler = AsyncIOScheduler()
scheduler.add_job(
    func=lambda: consolidator.run_consolidation_cycle("*"),  # all tenants
    trigger="cron",
    hour="*/6",   # every 6 hours, configurable via settings
    id="sleep_cycle",
)
```
Start `scheduler.start()` in the FastAPI lifespan `startup` hook. Add
`CONSOLIDATION_SCHEDULE_CRON` to `Settings`. Expose `GET /admin/scheduler/status` to see
next-run time.

### 6.3 ⬜ Distributed saga orchestration (Temporal / Celery)

**Current limitation:** All saga steps execute in the same process. Crash = all in-flight
sagas lose their execution context (state is now persisted, but *execution* is not resumable —
only rollback is possible on recovery). Cross-service sagas (step A runs in service X, step B
in service Y) are impossible.

**Recommended approach — Temporal:**  
Temporal's workflow model is a near-exact semantic match for the saga pattern: durable
execution, deterministic replay, built-in compensation via `compensate_async`. The saga
coordinator maps naturally to a `@workflow.defn` class:
```python
@workflow.defn
class SagaWorkflow:
    @workflow.run
    async def run(self, steps: list[StepConfig]) -> SagaResult:
        completed = []
        try:
            for step in steps:
                result = await workflow.execute_activity(
                    execute_step, step,
                    start_to_close_timeout=timedelta(seconds=30),
                )
                completed.append(step)
        except Exception:
            for s in reversed(completed):
                await workflow.execute_activity(compensate_step, s, ...)
            raise
```
This gives distributed execution, at-most-once delivery (with idempotency keys, §2.3),
automatic replay on crash, and a built-in UI for saga inspection.

**Lower-effort alternative — Celery:**  
Use Celery task chains with Redis/RabbitMQ as broker. Less powerful than Temporal (no
deterministic replay) but works with the existing Redis dependency.

### 6.4 ⬜ GraphRAG-style memory retrieval via Neo4j

**Problem:** The semantic graph accumulates concept relationships from consolidation but they
are never used in retrieval. `/memory/active` does pure vector similarity; it ignores
concept-level structure. An agent asking "what do I know about planning?" gets raw episode
vectors, not the distilled concept "Strategic Planning" that consolidation derived.

**Design:**
1. When query embedding arrives, find the top-k similar concepts in Neo4j:
```cypher
MATCH (c:Concept)
RETURN c.name, c.embedding <=> $query_vec AS dist
ORDER BY dist LIMIT 5
```
2. Expand each concept's neighborhood (1-2 hops) to get related agent roles and episode
   summaries.
3. Re-rank the vector-retrieved episodes by combining cosine similarity with graph proximity
   (e.g. `score = 0.7 * vector_sim + 0.3 * (1 / (1 + graph_hops))`).
4. Return a unified ranked result with provenance (`source: "vector" | "graph"`).

### 6.5 ⬜ Human-in-the-loop saga gate

**Use case:** A saga step proposes to `DELETE_FILE path=/critical/config.yaml`. The Z3 gate
verifies path containment. But no human reviews it before execution.

**Design:**
- Add `requires_approval: bool = False` to `SagaStep`.
- When `requires_approval=True`, the coordinator pauses the saga (`SagaStatus.AWAITING_APPROVAL`),
  persists the step payload in the state store, and returns HTTP 202 (Accepted) with a
  `approval_token`.
- Expose `POST /saga/{id}/approve` and `POST /saga/{id}/reject` endpoints (admin-only key).
- On approve, resume execution from the paused step. On reject, trigger compensations.
- Add a timeout: if not approved within N minutes, auto-reject and roll back.

### 6.6 ⬜ Replay and time-travel debugging

**Problem:** When a saga fails in production, the only post-mortem is the log. There is no
way to replay the exact step sequence with the exact arguments to reproduce the failure or
validate a fix.

**Design:**
- The durable compensation log (`saga_compensations`) already stores step arguments. Extend
  it to store forward-action arguments and their results too:
```sql
ALTER TABLE saga_compensations ADD COLUMN forward_arguments JSONB;
ALTER TABLE saga_compensations ADD COLUMN result JSONB;
```
- Add `POST /saga/{id}/replay` that re-runs the stored steps against a dry-run sandbox
  (validation only, no side effects) and returns what *would* happen.
- Add `GET /saga/{id}/history` that returns the full ordered step log with timing.

### 6.7 ⬜ WebSocket / SSE streaming of saga events

**Problem:** The Streamlit dashboard re-runs the saga engine locally (not via the API),
so it has no connection to a production deployment. Clients building UI on the API must
poll `GET /saga/{id}/status` — inefficient.

**Fix:** Add a Server-Sent Events (SSE) endpoint that streams saga step events:
```python
from sse_starlette.sse import EventSourceResponse

@app.get("/saga/{saga_id}/stream")
async def stream_saga(saga_id: str):
    async def generator():
        while True:
            state = coordinator.get_saga_status(saga_id)
            yield {"event": "status", "data": json.dumps(state)}
            if state["status"] in {"COMMITTED", "ROLLED_BACK", "COMPENSATION_FAILED"}:
                break
            await asyncio.sleep(0.5)
    return EventSourceResponse(generator())
```
The dashboard can then subscribe to SSE instead of running the engine locally.

### 6.8 ⬜ Multi-tenancy hardening

**Current state:** `tenant_id` is a `str` field trusted from the request body. Tenant A
can pass `tenant_id="tenant_b"` and read or write tenant B's memories.

**Required for any shared deployment:**
1. Bind `tenant_id` to the API key, not the request body. The key authenticates the tenant;
   the coordinator enforces it.
2. Add row-level security in TimescaleDB:
```sql
ALTER TABLE episodic_memories ENABLE ROW LEVEL SECURITY;
CREATE POLICY tenant_isolation ON episodic_memories
    USING (tenant_id = current_setting('app.tenant_id'));
```
3. Per-tenant rate limits (separate from the global rate limiter).
4. Per-tenant memory quotas enforced before write (`SELECT COUNT(*) FROM episodic_memories
   WHERE tenant_id = :tid` + configurable limit).
5. Audit log for all cross-tenant operations.

### 6.9 ⬜ Python SDK / client library

**Problem:** Callers must hand-roll HTTP requests to the API. No client validates the
request schema before sending. Error messages are raw FastAPI `detail` strings.

**Design — auto-generated from OpenAPI:**
```bash
openapi-python-client generate --url http://localhost:8000/openapi.json \
    --meta setup --output-path sdk/
```
Then layer a high-level API on top:
```python
from sagamind import SagaMindClient

client = SagaMindClient(base_url="http://api.sagamind.io", api_key="sk-...")
saga = client.sagas.start(tenant_id="t1", goal="process user upload")
saga.step("write_file", path="/workspace/out.txt", content="hello")
saga.commit()
```

---

## 7. Suggested sequencing (realistic sprint order)

### Sprint 1 — Production safety ✅ DONE
1. ✅ **§1.2** — `ThreadedConnectionPool`.
2. ✅ **§1.3** — Reject unknown `saga_id`.
3. ✅ **§2.2** — Per-tool argument schema validation; no raw SQL.
4. ✅ **§2.3** — Idempotency key support.
5. ✅ **§3.5** — Dead-letter queue + `/saga/dead-letters`.
6. ✅ **§5.1** — Integration tests wired into CI.

### Sprint 2 — Reliability and observability — mostly done
7. 🟡 **§3.4** — Neo4j timeouts + `tenacity` retries done; **LLM call in `consolidation._llm_summarize` still has no timeout/retry — only remaining item here.**
8. ✅ **§3.2** — Request-ID correlation in logs.
9. ✅ **§3.6** — Paginate `/memory/active`.
10. ✅ **§3.1** — `SagaTransaction` dataclass wired into coordinator.
11. ✅ **§1.4** — In-memory state mirror growth fixed.
12. ✅ **§5.3** — gRPC codegen CI job.

### Sprint 3 — Performance — partially done; remaining is genuinely open
13. ⬜ **§4.2** — Push retention filtering to TimescaleDB SQL. *(Open — highest-value remaining perf item; 100K-memory tenants still materialize full result sets into Python.)*
14. ✅ **§4.3** — DBSCAN clustering.
15. ✅ **§4.4** — LRU cache for embedding results (Redis tier still a future option, not required).
16. ⬜ **§4.6** — Tune pgvector HNSW index parameters under load. *(Open — needs production query-pattern data to tune meaningfully; revisit once there's real traffic.)*

### Sprint 4 — Features (differentiation) — registry + scheduler done; retrieval/streaming open
17. ✅ **§6.1** — Pluggable tool registry (WASM-compiled reference tools per §2.1 still future work).
18. ✅ **§6.2** — APScheduler sleep-cycle consolidation.
19. ⬜ **§6.4** — GraphRAG retrieval integrating the Neo4j concept graph. *(Open — concept graph is populated by consolidation but never read back during retrieval.)*
20. ⬜ **§6.7** — SSE streaming for saga step events; update dashboard to consume the API. *(Open.)*

### Sprint 5 — Scale and ecosystem — all open, lowest priority
21. ⬜ **§6.3** — Temporal-backed distributed saga orchestration.
22. ⬜ **§6.5** — Human-in-the-loop approval gate.
23. ⬜ **§6.6** — Replay / time-travel debugging endpoint.
24. ⬜ **§6.8** — Multi-tenancy row-level security + per-tenant quotas.
25. ⬜ **§6.9** — Python client SDK.
26. ⬜ **§4.5** — Rust/PyO3 cosine kernel (only if profiling proves it necessary — unlikely at current scale).

---

## 7.1 What's left, in priority order

1. **§4.2** (Sprint 3, item 13) — push retention math to SQL. Real perf win once memory counts grow; currently the only "production safety" perf gap left.
2. **§3.4 LLM timeout** — one missing line in `consolidation._llm_summarize`; trivial, just not done yet.
3. **§6.4 GraphRAG retrieval** — the semantic graph is built but unused; closing this loop is the highest-leverage *feature* gap (makes consolidation actually pay off).
4. **§6.7 SSE streaming** — moderate effort, decouples the dashboard from running the engine locally.
5. Everything in Sprint 5 — genuinely "scale" concerns (distributed orchestration, HITL, replay, multi-tenancy, SDK). Don't start until there's a concrete driver (real multi-tenant load, compliance ask, or external-client demand).

---

## 8. Where a faster language actually helps

Most of SagaMind is I/O-bound (DB, LLM, Neo4j, gRPC). Python is not the bottleneck there.

| Layer | CPU hot? | Right tool |
|-------|----------|------------|
| Saga coordinator | No — async wait on verifier + sandbox | Stay Python |
| FastAPI routing | No — async I/O | Stay Python/uvicorn |
| Z3 verification | Z3 is C; Python is thin wrapper | Stay Python |
| Cosine distance matrix | Yes — for n > 10 K | NumPy (BLAS) first; Rust/PyO3 if still slow |
| Decay math | Yes — for n > 100 K rows | Push to SQL first; NumPy second |
| WASM sandbox runtime | Already Rust (wasmtime) | Done |
| gRPC transport | grpcio is C; Python is thin wrapper | Stay Python |
| High-QPS HTTP gateway | Possibly — at > 10 K RPS | Go (net/http) or Rust (axum) *if* uvicorn saturates |

**Order of operations:** profile with `py-spy` → vectorize with NumPy → push to SQL →
Rust/PyO3 for the one proven kernel → service rewrite for the one proven bottleneck.
Do not rewrite saga coordination, FastAPI routing, or consolidation logic in another language —
they are I/O-bound and the rewrite cost exceeds any benefit.

---

*Generated from full E2E read of `src/`, `tests/`, `app_demo.py`, `Dockerfile`,
`docker-compose.yml`, `.github/workflows/ci.yml`, `pyproject.toml`, `proto/`, `alembic/`,
`migrations/`, `scripts/`. See `CLAUDE.md` for day-to-day working conventions.*
