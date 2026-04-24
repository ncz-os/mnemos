"""Shared globals, lifespan, and DB/cache helpers for MNEMOS API."""
import hashlib
import json
import logging
import os
import sys
try:
    import tomllib
except ModuleNotFoundError:
    import tomli as tomllib
from contextlib import asynccontextmanager
from typing import Optional

import asyncpg
import httpx
from fastapi import HTTPException
import redis.asyncio as aioredis

sys.path.insert(0, os.path.dirname(os.path.dirname(__file__)))
from config import PG_CONFIG
from inference_backend import get_backend as _get_backend
from graeae.engine import get_graeae_engine  # noqa: F401 — re-exported for handlers

from .models import MemoryItem

logger = logging.getLogger(__name__)

# Compression thresholds
COMPRESSION_RESULT_SET_THRESHOLD = 50 * 1024   # 50 KB
COMPRESSION_ITEM_THRESHOLD = 5 * 1024           # 5 KB per item

# Background task registry — prevents dangling tasks at shutdown
_background_tasks: set = set()

# Worker health tracking
_worker_status: dict = {
    "distillation_worker": "idle",  # idle, healthy, error
    "last_heartbeat": None,
}


def _schedule_background(coro) -> None:
    """Schedule a fire-and-forget coroutine with lifecycle tracking.

    Unlike asyncio.create_task(), tasks created here are tracked in
    _background_tasks so the lifespan teardown can await them before
    closing the DB pool.
    """
    import asyncio as _asyncio
    task = _asyncio.create_task(coro)
    _background_tasks.add(task)
    task.add_done_callback(_background_tasks.discard)

# DB config sourced from config.PG_CONFIG (env > config.toml > defaults)

# Embedding config (for vector search, MOD-02)
_EMBED_HOST = os.getenv('OLLAMA_EMBED_HOST', 'http://localhost:11434')
_EMBED_MODEL = os.getenv('OLLAMA_EMBED_MODEL', 'nomic-embed-text')
_EMBED_TIMEOUT = float(os.getenv('OLLAMA_EMBED_TIMEOUT', '10'))

# ── Singleton globals ────────────────────────────────────────────────────────
_pool: Optional[asyncpg.Pool] = None
_cache: Optional[aioredis.Redis] = None
_inference_backend = None  # initialized on startup via _get_backend()
_rls_enabled: bool = False   # set from config at startup; read by handlers


def get_inference_backend():
    """Get the distillation backend (Ollama or LlamaCpp)."""
    global _inference_backend
    if _inference_backend is None:
        _inference_backend = _get_backend()
    return _inference_backend


def _load_config() -> dict:
    """Load config.toml from standard locations. Returns empty dict if not found."""
    candidates = [
        os.path.join(os.path.dirname(os.path.dirname(__file__)), "config.toml"),
        "/etc/mnemos/config.toml",
    ]
    for path in candidates:
        if os.path.exists(path):
            try:
                with open(path, "rb") as f:
                    return tomllib.load(f)
            except Exception as e:
                logger.warning(f"Failed to parse {path}: {e}")
    return {}


# ── Distillation Worker Wrapper ─────────────────────────────────────────────────

async def _run_distillation_worker():
    """Supervised distillation worker loop — restarts on unhandled errors.

    Dispatches unoptimized memories through the compression stack:
      1. LETHE (local CPU compression, fast)
      2. ALETHEIA (GPU token-level compression, offline batch)
      3. ANAMNESIS (LLM fact extraction, archival)

    Previously a single crash set status to 'idle' and left the worker
    permanently dead for the rest of the process lifetime. We now restart
    with exponential backoff up to 5 minutes. asyncio.CancelledError (shutdown)
    propagates so the lifespan drain works correctly.
    """
    import asyncio
    global _worker_status

    try:
        from distillation_worker import MemoryDistillationWorker
    except ImportError as e:
        logger.warning(f"Distillation worker not available: {e}")
        _worker_status["distillation_worker"] = "unavailable"
        return

    backoff = 1.0
    while True:
        worker = MemoryDistillationWorker()
        try:
            _worker_status["distillation_worker"] = "starting"
            await worker.start()
            # Graceful exit (worker.start() returned) — stop supervising.
            _worker_status["distillation_worker"] = "idle"
            return
        except asyncio.CancelledError:
            logger.info("Distillation worker cancelled (shutdown)")
            _worker_status["distillation_worker"] = "idle"
            raise
        except Exception as e:
            _worker_status["distillation_worker"] = "error"
            logger.exception(f"Distillation worker crashed: {e} — restarting in {backoff:.0f}s")
        finally:
            try:
                if getattr(worker, "db_pool", None):
                    await worker.db_pool.close()
            except Exception:
                pass
        try:
            await asyncio.sleep(backoff)
        except asyncio.CancelledError:
            _worker_status["distillation_worker"] = "idle"
            raise
        backoff = min(backoff * 2, 300.0)  # cap at 5 minutes


# ── App lifespan ─────────────────────────────────────────────────────────────

@asynccontextmanager
async def lifespan(app):
    """FastAPI lifespan: initialize and teardown DB pool, Redis, inference provider, and workers."""
    global _pool, _cache, _rls_enabled, _worker_status
    logger.info("Starting MNEMOS API Server v3.0.0 (gateway + sessions + DAG + workers)")

    config = _load_config()

    try:
        _pool = await asyncpg.create_pool(
            user=PG_CONFIG['user'],
            password=PG_CONFIG['password'],
            database=PG_CONFIG['database'],
            host=PG_CONFIG['host'],
            port=PG_CONFIG['port'],
            min_size=PG_CONFIG['pool_min_size'],
            max_size=PG_CONFIG['pool_max_size'],
        )
        app.state.pool = _pool   # auth.py reads this via request.app.state.pool
        logger.info(
            f"asyncpg connection pool initialized "
            f"(min={PG_CONFIG['pool_min_size']}, max={PG_CONFIG['pool_max_size']})"
        )
    except Exception as e:
        logger.error(f"Failed to create DB pool: {e}")
        raise

    # Configure auth (personal profile: auth.enabled=false → no-op beyond singleton)
    from api.auth import configure_auth
    configure_auth(config.get("auth", {}))

    # RLS enforcement flag
    _rls_enabled = config.get("multiuser", {}).get("rls_enabled", False)
    if _rls_enabled:
        logger.info("Row Level Security: ENABLED (team/enterprise profile)")
    else:
        logger.info("Row Level Security: DISABLED (personal profile)")

    _redis_url = os.getenv("MNEMOS_REDIS_URL") or os.getenv("REDIS_URL") or "redis://localhost:6379"
    try:
        _cache = aioredis.from_url(_redis_url, decode_responses=True)
        await _cache.ping()
        app.state.cache = _cache
        logger.info(f"Redis cache connected ({_redis_url})")
    except Exception as e:
        logger.warning(f"Redis unavailable at {_redis_url}, caching disabled: {e}")
        _cache = None
        app.state.cache = None

    backend = get_inference_backend()
    healthy = await backend.health_check()
    if healthy:
        logger.info("[backend] Distillation backend CONNECTED")
    else:
        logger.warning("[backend] Distillation backend UNREACHABLE - compression disabled")

    # Start background distillation worker (optional)
    worker_enabled = config.get("worker", {}).get("enabled", True)
    if worker_enabled and _pool:
        logger.info("Launching background distillation worker")
        _schedule_background(_run_distillation_worker())
        import asyncio as _asyncio
        await _asyncio.sleep(0.5)  # Give worker time to initialize
    else:
        logger.info("Background distillation worker disabled")
        _worker_status["distillation_worker"] = "disabled"

    # Webhook delivery recovery worker (v3.0.0 — picks up pending/retrying deliveries)
    if _pool:
        logger.info('Launching webhook delivery recovery worker')
        from api.webhook_dispatcher import recovery_worker_loop as _webhook_recovery
        _schedule_background(_webhook_recovery(_pool))

    # Federation sync worker (v3.0.0 — pulls from remote peers on their intervals)
    if _pool:
        logger.info('Launching federation sync worker')
        from api.federation import federation_worker_loop as _federation_worker
        _schedule_background(_federation_worker(_pool))

    # OAuth expired-session GC worker (v3.0.0)
    if _pool:
        import asyncio as _asyncio
        async def _oauth_gc_loop():
            from api.oauth import gc_expired_sessions
            while True:
                try:
                    await _asyncio.sleep(3600)  # hourly
                    deleted = await gc_expired_sessions(_pool)
                    if deleted:
                        logger.info(f'oauth gc: deleted {deleted} expired sessions')
                except _asyncio.CancelledError:
                    raise
                except Exception:
                    logger.exception('oauth gc iteration failed')
        _schedule_background(_oauth_gc_loop())

    yield

    if _background_tasks:
        logger.info(f"Draining {len(_background_tasks)} background task(s)…")
        import asyncio as _asyncio
        await _asyncio.gather(*list(_background_tasks), return_exceptions=True)

    if _pool:
        await _pool.close()
        logger.info("DB pool closed")
    if _cache:
        await _cache.aclose()
        logger.info("Redis cache closed")
    await backend.close()
    logger.info("Shutting down MNEMOS API Server")


# ── Shared helpers ────────────────────────────────────────────────────────────

def _get_cache_key(prefix: str, *args) -> str:
    """Generate a stable, prefixed cache key.

    The namespace prefix ("mnemos:<prefix>:") is preserved so a pattern-based
    invalidation (SCAN MATCH "mnemos:search:*") can target only our keys.
    """
    raw = prefix + ":" + ":".join(str(a) for a in args)
    digest = hashlib.md5(raw.encode(), usedforsecurity=False).hexdigest()
    return f"mnemos:{prefix}:{digest}"


async def _get_db():
    """Acquire a connection from the pool."""
    global _pool
    if not _pool:
        raise HTTPException(status_code=503, detail="Database pool not available")
    return _pool.acquire()


_MEMORY_COLS = (
    "id, content, category, subcategory, created, updated, "
    "metadata, quality_rating, compressed_content, verbatim_content, "
    "owner_id, group_id, namespace, permission_mode, "
    "source_model, source_provider, source_session, source_agent"
)


def _row_to_memory(row, include_compressed: bool = False) -> MemoryItem:
    raw_meta = row.get('metadata')
    if isinstance(raw_meta, str):
        try:
            raw_meta = json.loads(raw_meta)
        except Exception:
            raw_meta = None
    elif not isinstance(raw_meta, dict):
        raw_meta = None
    return MemoryItem(
        id=row['id'],
        content=row['content'],
        category=row['category'],
        subcategory=row.get('subcategory'),
        created=row['created'].isoformat() if row['created'] else '',
        updated=row['updated'].isoformat() if row.get('updated') else None,
        metadata=raw_meta if raw_meta else None,
        quality_rating=row.get('quality_rating'),
        compressed_content=row.get('compressed_content') if include_compressed else None,
        verbatim_content=row.get('verbatim_content'),
        owner_id=row.get('owner_id'),
        group_id=row.get('group_id'),
        namespace=row.get('namespace'),
        permission_mode=row.get('permission_mode'),
        source_model=row.get('source_model'),
        source_provider=row.get('source_provider'),
        source_session=row.get('source_session'),
        source_agent=row.get('source_agent'),
    )


async def _get_embedding(text: str) -> list:
    """Get embedding vector from nomic-embed-text on inference-server. Returns [] on failure."""
    try:
        async with httpx.AsyncClient(timeout=_EMBED_TIMEOUT) as client:
            r = await client.post(
                f"{_EMBED_HOST}/api/embeddings",
                json={"model": _EMBED_MODEL, "prompt": text[:2000]},
            )
            r.raise_for_status()
            return r.json().get("embedding", [])
    except Exception as e:
        logger.warning(f"[EMBED] Failed to get embedding: {e}")
        return []


async def _vector_search(conn, embedding: list, limit: int,
                         category=None, subcategory=None, select_cols=None,
                         source_provider=None, source_model=None,
                         source_agent=None, namespace=None,
                         owner_id=None) -> list:
    """pgvector cosine similarity search. Returns rows ordered by similarity desc.

    The vector is always $1 — used in both the SELECT similarity expression and
    the ORDER BY clause.  Passing it as a parameter (not interpolated into the
    query string) eliminates any injection risk from a poisoned embedding response.
    Supports optional provenance filters (source_provider, source_model,
    source_agent, namespace) ANDed into the WHERE clause. `owner_id` (v3.1.2
    Tier 3 app-layer filter) similarly scopes the result set when the caller
    passes it — non-root callers from /memories/search pin this to their
    user_id for defense-in-depth against RLS being disabled.
    """
    if select_cols is None:
        select_cols = _MEMORY_COLS
    # float() cast guards against non-numeric values in the embedding response
    vec_str = "[" + ",".join(str(float(x)) for x in embedding) + "]"
    # $1 is the vector — referenced in SELECT and ORDER BY, never interpolated
    sim_col = "1 - (embedding <=> $1::vector) AS similarity"

    # Dynamic WHERE builder: $1=vec_str, filter params at $2+, limit always last
    params: list = [vec_str]
    conditions: list = ["embedding IS NOT NULL"]
    for col, val in [("category", category), ("subcategory", subcategory),
                     ("source_provider", source_provider), ("source_model", source_model),
                     ("source_agent", source_agent), ("namespace", namespace),
                     ("owner_id", owner_id)]:
        if val is not None:
            params.append(val)
            if col == "owner_id":
                # v3.2 H1 fix: federated memories carry owner_id='federation'
                # and must be readable alongside the caller's own rows.
                # Mutation paths still hard-filter by owner_id (caller
                # can't update/delete federated rows) — this only affects
                # the read helpers used by search/rehydrate/gateway.
                conditions.append(
                    f"(owner_id=${len(params)} OR federation_source IS NOT NULL)"
                )
            else:
                conditions.append(f"{col}=${len(params)}")
    params.append(limit)
    limit_ph = f"${len(params)}"

    where = " AND ".join(conditions)
    sql = (f"SELECT {select_cols}, {sim_col} FROM memories "
           f"WHERE {where} ORDER BY embedding <=> $1::vector LIMIT {limit_ph}")
    try:
        return await conn.fetch(sql, *params)
    except Exception as e:
        logger.error(f"[VECTOR] pgvector search failed: {e}")
        return []


async def _fts_fetch(conn, query: str, limit: int,
                     category=None, subcategory=None, select_cols=None,
                     source_provider=None, source_model=None,
                     source_agent=None, namespace=None,
                     owner_id=None):
    """FTS search with ILIKE fallback. Shared by /memories/search and /memories/rehydrate.

    Uses plainto_tsquery (not to_tsquery) so user input is treated as plain text —
    tsquery operators like |, !, & are not interpreted.  This prevents tsquery
    operator injection while preserving full-text search quality.
    Supports optional provenance filters (source_provider, source_model,
    source_agent, namespace) ANDed into the WHERE clause. `owner_id` (v3.1.2
    Tier 3) scopes the result set to a single owner when supplied; callers
    from non-root /memories/search pin it to user.user_id.
    """
    if select_cols is None:
        select_cols = _MEMORY_COLS
    clean_query = query.strip()
    rank_col = "ts_rank(to_tsvector('english', content), plainto_tsquery('english', $1)) as rank"

    # Dynamic WHERE builder: $1=query, $2=limit; filter params at $3+
    params: list = [clean_query, limit]
    conditions: list = ["to_tsvector('english', content) @@ plainto_tsquery('english', $1)"]
    for col, val in [("category", category), ("subcategory", subcategory),
                     ("source_provider", source_provider), ("source_model", source_model),
                     ("source_agent", source_agent), ("namespace", namespace),
                     ("owner_id", owner_id)]:
        if val is not None:
            params.append(val)
            if col == "owner_id":
                # v3.2 H1 fix: federated memories carry owner_id='federation'
                # and must be readable alongside the caller's own rows.
                # Mutation paths still hard-filter by owner_id (caller
                # can't update/delete federated rows) — this only affects
                # the read helpers used by search/rehydrate/gateway.
                conditions.append(
                    f"(owner_id=${len(params)} OR federation_source IS NOT NULL)"
                )
            else:
                conditions.append(f"{col}=${len(params)}")

    where = " AND ".join(conditions)
    sql = (f"SELECT {select_cols}, {rank_col} FROM memories "
           f"WHERE {where} ORDER BY rank DESC LIMIT $2")
    try:
        return await conn.fetch(sql, *params)
    except Exception:
        logger.warning(f"[FTS] falling back to ILIKE for: {query[:50]!r}")
        like_q = f"%{query}%"
        # Rebuild for ILIKE: $1=like_q, $2=limit; filter params at $3+
        ilike_params: list = [like_q, limit]
        ilike_conditions: list = ["content ILIKE $1"]
        for col, val in [("category", category), ("subcategory", subcategory),
                         ("source_provider", source_provider), ("source_model", source_model),
                         ("source_agent", source_agent), ("namespace", namespace),
                         ("owner_id", owner_id)]:
            if val is not None:
                ilike_params.append(val)
                if col == "owner_id":
                    # H1 fix — see _fts_fetch FTS branch above.
                    ilike_conditions.append(
                        f"(owner_id=${len(ilike_params)} OR federation_source IS NOT NULL)"
                    )
                else:
                    ilike_conditions.append(f"{col}=${len(ilike_params)}")
        ilike_where = " AND ".join(ilike_conditions)
        ilike_sql = (f"SELECT {select_cols} FROM memories "
                     f"WHERE {ilike_where} ORDER BY created DESC LIMIT $2")
        try:
            return await conn.fetch(ilike_sql, *ilike_params)
        except Exception as e2:
            logger.error(f"[FTS] Both FTS and ILIKE failed: {e2}")
            return []
