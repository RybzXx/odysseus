"""
model_context.py

Query and cache model context window sizes from OpenAI-compatible APIs.
Provides token estimation for context usage tracking.
"""

import ipaddress
import logging
import os  # odysseus-local-served-context
import sys
from typing import Dict, List, Optional, Tuple

from urllib.parse import urlparse

import httpx

logger = logging.getLogger(__name__)

_LOCAL_HOSTS = {"localhost", "127.0.0.1", "0.0.0.0", "::1", "host.docker.internal"}
_PRIVATE_NETWORKS = (
    ipaddress.ip_network("10.0.0.0/8"),
    ipaddress.ip_network("172.16.0.0/12"),
    ipaddress.ip_network("192.168.0.0/16"),
)

# Tailscale uses the CGNAT range 100.64.0.0/10, NOT all of 100.0.0.0/8.
# A bare "100." prefix would classify public addresses (e.g. AWS ranges
# under 100.x outside the CGNAT block) as local; routes/model_routes.py
# already narrows this the same way for endpoint classification.
_TAILSCALE_CGNAT = ipaddress.ip_network("100.64.0.0/10")


def _in_tailscale_range(host: str) -> bool:
    try:
        return ipaddress.ip_address(host) in _TAILSCALE_CGNAT
    except ValueError:
        return False


def _is_private_ip_literal(host: str) -> bool:
    try:
        ip = ipaddress.ip_address(host)
    except ValueError:
        return False
    return any(ip in network for network in _PRIVATE_NETWORKS)


def _normalize_base_for_compare(url: str) -> str:
    url = (url or "").strip().rstrip("/")
    for suffix in ("/chat/completions", "/models", "/completions", "/v1/messages"):
        if url.endswith(suffix):
            url = url[: -len(suffix)].rstrip("/")
    return url


def _configured_endpoint_kind(url: str) -> Optional[str]:
    """Return configured endpoint kind for a chat/base URL when available."""
    target = _normalize_base_for_compare(url)
    if not target:
        return None
    if "core.database" not in sys.modules:
        return None
    try:
        from core.database import SessionLocal, ModelEndpoint
        db = SessionLocal()
        try:
            rows = db.query(ModelEndpoint).filter(ModelEndpoint.is_enabled == True).all()
            for ep in rows:
                base = _normalize_base_for_compare(getattr(ep, "base_url", "") or "")
                if not base:
                    continue
                if target != base and not target.startswith(base + "/"):
                    continue
                kind = (getattr(ep, "endpoint_kind", None) or "auto").strip().lower()
                if kind in ("local", "api", "proxy"):
                    return kind
                if getattr(ep, "api_key", None):
                    parsed = urlparse(base)
                    host = (parsed.hostname or "").lower()
                    path = (parsed.path or "").rstrip("/")
                    if parsed.port != 11434 and "ollama" not in host and (path.endswith("/v1") or "/openai" in path):
                        return "proxy"
                return "auto"
        finally:
            db.close()
    except Exception:
        return None


def is_local_endpoint(url: str) -> bool:
    """Check if URL points to a local/private/tailscale address."""
    kind = _configured_endpoint_kind(url)
    if kind in ("api", "proxy"):
        return False
    if kind == "local":
        return True
    try:
        host = urlparse(url).hostname or ""
        return host in _LOCAL_HOSTS or _is_private_ip_literal(host) or _in_tailscale_range(host)
    except Exception:
        return False

# ---------------------------------------------------------------------------
# Constants
# ---------------------------------------------------------------------------
DEFAULT_CONTEXT = 128000
REQUEST_TIMEOUT = 5

# >>> odysseus-local-served-context
# The window a LOCAL server actually serves, which is not always the window the
# model supports. Ollama's default is far below its models' maximums and the
# OpenAI-compat /v1/models response does not report it, so without this the
# known-table value (131072 for anything matching `qwen3`) is used to budget a
# prompt the server will silently truncate.
#
# Set it in Odysseus's .env to the same number as OLLAMA_CONTEXT_LENGTH on the
# model host, which setup_ollama_host.ps1 owns. Unset = previous behaviour.
LOCAL_SERVED_CONTEXT_ENV = "ODYSSEUS_LOCAL_SERVED_CONTEXT"

# "Positive" alone doesn't catch a fat-fingered extra digit -- a stray zero
# turns this into an implausible ceiling that OVER-budgets every prompt, the
# exact silent-truncation failure this whole mechanism exists to prevent.
# 2x the largest entry in KNOWN_CONTEXT_WINDOWS (1,048,576, Llama 4 / MiMo
# v2.5) -- generous headroom for a real future model, not a real value today.
MAX_PLAUSIBLE_LOCAL_CONTEXT = 2_000_000


def _coerce_served_context_value(raw, label):
    """One validated window, or None. Shared by the default and per-model entries.

    ``label`` names the offending setting in the warning, so a bad per-model
    entry points at that model rather than at the variable as a whole.
    """
    try:
        value = int(raw)
    except ValueError:
        logger.warning("%s=%r is not an integer; ignoring", label, raw)
        return None
    if value <= 0:
        logger.warning("%s=%d must be positive; ignoring", label, value)
        return None
    if value > MAX_PLAUSIBLE_LOCAL_CONTEXT:
        logger.warning(
            "%s=%d exceeds the plausible ceiling (%d); ignoring",
            label, value, MAX_PLAUSIBLE_LOCAL_CONTEXT,
        )
        return None
    return value


def _parse_local_served_context_spec(raw):
    """``(default_ceiling, {model: ceiling})`` from the env var's spec string.

    The window a local server can actually serve is per-model, not per-host:
    KV cache scales with the window, so a 2 GB model has headroom on this
    card that a 25 GB one does not. A single number for every model therefore
    either starves the small models or OOMs the large ones.

    Grammar, backward compatible with the bare integer this used to be:
        8192                          -> default 8192, no overrides
        8192,granite4.2:3b=65536      -> default 8192, that one model 65536
        granite4.2:3b=65536           -> that model only, no default
    Model ids contain ':' (``gemma4:26b``), so '=' separates key from value
    and ',' separates entries. A malformed entry is dropped, never fatal.
    """
    default = None
    per_model = {}
    for entry in raw.split(","):
        entry = entry.strip()
        if not entry:
            continue
        if "=" in entry:
            name, _, value = entry.partition("=")
            name = name.strip()
            ceiling = _coerce_served_context_value(
                value.strip(), "%s[%s]" % (LOCAL_SERVED_CONTEXT_ENV, name)
            )
            if name and ceiling is not None:
                per_model[name] = ceiling
        else:
            default = _coerce_served_context_value(entry, LOCAL_SERVED_CONTEXT_ENV)
    return default, per_model


def local_served_context_ceiling(model=""):
    """The declared local serving window for ``model``, or None when unset.

    A per-model entry wins over the bare default, so an oversized model keeps
    a small window while a small one gets the larger window its VRAM headroom
    actually allows. Called with no model (or a model with no entry) this
    returns the default, which is the whole behaviour of the bare-integer form.

    Malformed entries are dropped rather than fatal: a typo in .env must not
    take the whole endpoint down.
    """
    raw = (os.environ.get(LOCAL_SERVED_CONTEXT_ENV) or "").strip()
    if not raw:
        return None
    default, per_model = _parse_local_served_context_spec(raw)
    if model and model in per_model:
        return per_model[model]
    return default


def is_cloud_served_model(model):
    """True for a model the local server only proxies, executing it remotely.

    Ollama's cloud models are addressed through the same local endpoint URL, so
    `is_local_endpoint()` correctly says "local" while the context window is the
    remote one -- 262144 for `gemma4:31b-cloud` against a locally served 8192.
    Applying the local ceiling to them would throw away 97% of the window they
    actually have, so they are exempt.

    Ollama marks them in the tag: `<model>:cloud` or `<model>:<size>-cloud`.
    """
    tag = (model or "").rsplit(":", 1)[-1].lower()
    return tag == "cloud" or tag.endswith("-cloud")
# <<< odysseus-local-served-context

# Known context windows for major API models (used as fallback when /models
# endpoint doesn't report context_length).
# Substring matching — use the shortest unique prefix so variants get caught.
KNOWN_CONTEXT_WINDOWS = {
    # --- Anthropic ---
    'claude-sonnet-4-5': 200000,
    'claude-sonnet-4-6': 200000,
    'claude-sonnet-4': 200000,
    'claude-opus-4': 200000,
    'claude-haiku-4': 200000,
    'claude-haiku-3-5': 200000,
    'claude-3-5-sonnet': 200000,
    'claude-3-5-haiku': 200000,
    'claude-3-opus': 200000,
    'claude-3-sonnet': 200000,
    'claude-3-haiku': 200000,

    # --- OpenAI ---
    'gpt-5': 400000,
    'gpt-4.1': 1047576,
    'gpt-4.1-mini': 1047576,
    'gpt-4.1-nano': 1047576,
    'gpt-4o': 128000,
    'gpt-4o-mini': 128000,
    'gpt-4-turbo': 128000,
    'gpt-4': 8192,
    'gpt-3.5-turbo': 16385,
    'o1': 200000,
    'o1-mini': 128000,
    'o1-pro': 200000,
    'o3': 200000,
    'o3-mini': 200000,
    'o4-mini': 200000,

    # --- DeepSeek ---
    'deepseek-chat': 64000,
    'deepseek-coder': 64000,
    'deepseek-reasoner': 64000,
    'deepseek-r1': 64000,
    'deepseek-v3': 64000,
    'deepseek-v2': 64000,

    # --- Google ---
    'gemini-2.5-pro': 1048576,
    'gemini-2.5-flash': 1048576,
    'gemini-2.0-flash': 1048576,
    'gemini-1.5-pro': 1048576,
    'gemini-1.5-flash': 1048576,
    'gemma-4': 262144,
    'gemma-3': 128000,
    'gemma-2': 8192,

    # --- Mistral ---
    'mistral-large': 128000,
    'mistral-medium': 32000,
    'mistral-small': 32000,
    'mistral-nemo': 128000,
    'mistral-7b': 32000,
    'mixtral': 32000,
    'codestral': 32000,
    'pixtral': 128000,

    # --- xAI ---
    'grok-4': 131072,
    'grok-3': 131072,
    'grok-2': 131072,

    # --- Meta / Llama ---
    'llama-4': 1048576,
    'llama-3.3': 131072,
    'llama-3.2': 131072,
    'llama-3.1': 131072,
    'llama-3': 131072,

    # --- Qwen ---
    'qwen3': 131072,
    'qwen2.5': 131072,
    'qwen2': 32768,
    'qwq': 32768,

    # --- Cohere ---
    'command-r-plus': 128000,
    'command-r': 128000,
    'command-a': 256000,

    # --- Perplexity ---
    'sonar-pro': 200000,
    'sonar': 128000,

    # --- MiniMax ---
    'minimax': 1000000,

    # --- Moonshot / Kimi ---
    'moonshot': 128000,
    'kimi': 128000,

    # --- Microsoft ---
    'phi-4': 16000,
    'phi-3': 128000,

    # --- Nvidia ---
    'nemotron': 131072,

    # --- Yi ---
    'yi-large': 32768,
    'yi-1.5': 16384,

    # --- 01.ai ---
    'yi-lightning': 16384,

    # --- Nous ---
    'hermes': 131072,
    'nous-hermes': 131072,

    # --- Xiaomi ---
    'mimo-v2.5-pro': 1048576,
    'mimo-v2.5': 1048576,

    # --- Open community ---
    'dolphin': 32768,
    'mythomax': 4096,
    'wizard': 32768,
    'openchat': 8192,
    'solar': 32768,

    # --- Ollama-native tag spelling ---
    # `_lookup_known` requires the key to appear verbatim in the tag, and
    # Ollama's own library names these families with no hyphen between the
    # family and its version digit (`gemma4`, `granite4.2`, `gpt-oss`) --
    # the hyphenated keys above (`gemma-4`, etc.) are the vendor API/HF
    # convention and never match an Ollama tag. Confirmed via `/api/show`
    # model_info on this deployment's own installed models, not assumed:
    #   ollama show gemma4:26b       -> gemma4.context_length      262144
    #   ollama show gpt-oss:20b      -> gptoss.context_length      131072
    #   ollama show granite4.2:30b   -> granite.context_length     131072
    #   ollama show muse-glimmer:30b -> muse-glimmer.context_length 131072
    'gemma4': 262144,
    'gpt-oss': 131072,
    'granite': 131072,
    'muse-glimmer': 131072,
}

# ---------------------------------------------------------------------------
# Cache
# ---------------------------------------------------------------------------
_context_cache: Dict[Tuple[str, str], Tuple[int, bool]] = {}


def _get_context_length_cached(endpoint_url: str, model: str) -> Tuple[int, bool]:
    """Return (context_length, known). ``known`` is False only when the value is a
    bare DEFAULT_CONTEXT fallback (no endpoint report and not in the known table)."""
    configured_kind = _configured_endpoint_kind(endpoint_url)
    is_local = is_local_endpoint(endpoint_url)
    # Key on (endpoint_url, model): the same model id can be served by two
    # different remote endpoints with different real context windows (e.g. a
    # capped proxy vs. the full provider), so caching by model id alone would
    # serve one endpoint's window for the other (issue #2603).
    cache_key = (endpoint_url, model)
    if not is_local and cache_key in _context_cache:
        return _context_cache[cache_key]

    ctx, known = _query_context_length(endpoint_url, model)
    # Only cache non-default values to allow retry on next request.
    # Local endpoints can restart with a different --max-model-len while keeping
    # the same model id, so always re-query them instead of serving stale cache.
    if not is_local and (ctx != DEFAULT_CONTEXT or configured_kind in ("api", "proxy")):
        _context_cache[cache_key] = (ctx, known)
    # >>> odysseus-local-served-context
    # Every public accessor funnels through here, so the ceiling is applied
    # once rather than at each call site. Cloud models are exempt: the local
    # server only proxies them, so its serving window does not bound theirs.
    if is_local and not is_cloud_served_model(model):
        ceiling = local_served_context_ceiling(model)
        if ceiling is not None and ctx > ceiling:
            logger.info(
                "Local endpoint serves %d; capping %s from %d (%s)",
                ceiling, model, ctx, LOCAL_SERVED_CONTEXT_ENV,
            )
            ctx = ceiling
    # <<< odysseus-local-served-context
    logger.info(f"Context length for {model}: {ctx}")
    return ctx, known


def get_context_length(endpoint_url: str, model: str) -> int:
    """Get the context window size for a model.

    Queries /v1/models on the endpoint and looks for context_length
    or context_window fields. Caches result per (endpoint, model).
    Falls back to DEFAULT_CONTEXT if unavailable.
    """
    return _get_context_length_cached(endpoint_url, model)[0]


def get_context_length_known(endpoint_url: str, model: str) -> Tuple[int, bool]:
    """Like ``get_context_length`` but also returns whether the window was actually
    discovered (endpoint-reported or in the known-models table) rather than the bare
    DEFAULT_CONTEXT fallback. Callers that *scale* a budget off the window must not
    trust an unknown value — a fallback 128K isn't proof the model holds 128K
    (review on #4122)."""
    return _get_context_length_cached(endpoint_url, model)


def budget_context_for_model(endpoint_url: str, model: str, *, fallback: int = 0) -> int:
    """Context window to scale the agent input budget against.

    Returns the *freshly discovered* window when it was actually proven
    (endpoint-reported / known table), else 0 so auto-scaling stays conservative.
    Crucially this binds the ``known`` flag to the value it proves — callers must
    not pair this flag with a context length from a *different* lookup (a stale
    local re-query, or a caller that didn't pass one), which would budget off an
    unproven number (review on #4122). On probe error, returns ``fallback`` (the
    caller's best-known value) to preserve prior behaviour."""
    try:
        ctx, known = get_context_length_known(endpoint_url, model)
        return ctx if known else 0
    except Exception:
        return fallback


def _lookup_known(model: str) -> Optional[int]:
    """Check known context windows by substring match.

    Picks the LONGEST matching key so a short key never shadows a more specific
    one. Without this, 'o1' (200k) precedes 'o1-mini' (128k) in the table and a
    first-match return would report o1-mini's window as 200k.
    """
    name = model.lower()
    basename = name.split("/")[-1] if "/" in name else name
    basename = basename.split(":")[0]  # strip :free, :extended etc.
    best_key: Optional[str] = None
    best_ctx: Optional[int] = None
    for key, ctx in KNOWN_CONTEXT_WINDOWS.items():
        if key in basename or key in name:
            if best_key is None or len(key) > len(best_key):
                best_key, best_ctx = key, ctx
    return best_ctx


def _model_ctx_from_entry(m: dict) -> Optional[int]:
    """Extract a positive context window from one /models catalog entry.

    Checks the common top-level fields first, then a nested meta/model_extra
    object. Returns None when no positive window is reported.
    """
    if not isinstance(m, dict):
        return None
    for field in (
        "context_length",
        "context_window",
        "max_model_len",
        "max_context_length",
        "max_seq_len",
    ):
        val = m.get(field)
        if val and isinstance(val, (int, float)) and val > 0:
            return int(val)
    meta = m.get("meta") or m.get("model_extra") or {}
    if isinstance(meta, dict):
        # n_ctx is the actual serving context (set via -c flag in llama.cpp)
        for field in ("n_ctx", "context_length", "context_window", "max_model_len"):
            val = meta.get(field)
            if val and isinstance(val, (int, float)) and val > 0:
                return int(val)
    return None


# Per-endpoint cache of the {model_id: context_length} map parsed from a
# proxy/api catalog. api/proxy endpoints skip the /models download on every
# lookup because a large catalog is expensive; caching the whole map lets us
# pay that download at most once per endpoint instead of once per model.
_catalog_ctx_cache: Dict[str, Dict[str, int]] = {}


def _proxy_catalog_context(endpoint_url: str, model: str) -> Optional[int]:
    """Context window for a model read from the endpoint's /models catalog.

    Fetches the catalog once per endpoint and caches the full id->context map,
    so an api/proxy endpoint serving a model that isn't in KNOWN_CONTEXT_WINDOWS
    (e.g. a new OpenRouter model) still reports its real window instead of the
    bare default. Returns None when the catalog can't be read or doesn't list a
    positive window for the model.
    """
    cat = _catalog_ctx_cache.get(endpoint_url)
    if cat is None:
        from src.endpoint_resolver import build_models_url
        try:
            r = httpx.get(build_models_url(endpoint_url), timeout=REQUEST_TIMEOUT)
        except Exception as e:
            logger.debug(f"Failed to fetch proxy catalog for context length: {e}")
            return None
        if not r.is_success:
            return None
        cat = {}
        try:
            for m in (r.json().get("data") or []):
                mid = m.get("id") if isinstance(m, dict) else None
                ctx = _model_ctx_from_entry(m) if mid else None
                if mid and ctx:
                    cat[mid] = ctx
        except Exception as e:
            logger.debug(f"Failed to parse proxy catalog for context length: {e}")
            return None
        _catalog_ctx_cache[endpoint_url] = cat

    if model in cat:
        return cat[model]
    # Catalog ids may carry a provider prefix (e.g. "openai/gpt-4o") while the
    # session stores the bare id; match on the trailing segment as a fallback.
    base = model.split("/")[-1]
    for mid, ctx in cat.items():
        if mid.split("/")[-1] == base:
            return ctx
    return None


def _query_context_length(endpoint_url: str, model: str) -> Tuple[int, bool]:
    """Query the model API for context length. Returns (context_length, known) where
    ``known`` is False only for the bare DEFAULT_CONTEXT fallback."""
    known = _lookup_known(model)
    api_ctx = None
    configured_kind = _configured_endpoint_kind(endpoint_url)

    # Large OpenAI-compatible proxies can make /models expensive. If the
    # endpoint is explicitly configured as API/proxy, prefer known context
    # metadata (or the default) over downloading the full catalog.
    if configured_kind in ("api", "proxy"):
        if known:
            logger.info(f"Using known context window for {model}: {known}")
            return known, True
        # Not in the known table: read the real window from the catalog (cached
        # once per endpoint) instead of capping every unknown model at the
        # default — that under-reported large windows on aggregators like
        # OpenRouter (issue #4886).
        api_ctx = _proxy_catalog_context(endpoint_url, model)
        if api_ctx:
            logger.info(f"Proxy catalog reports context window for {model}: {api_ctx}")
            return api_ctx, True
        return DEFAULT_CONTEXT, False

    # Try llama.cpp /slots endpoint first — reports actual serving context
    if is_local_endpoint(endpoint_url):
        try:
            base = endpoint_url.split("/v1")[0] if "/v1" in endpoint_url else endpoint_url.rsplit("/", 1)[0]
            r = httpx.get(f"{base}/slots", timeout=REQUEST_TIMEOUT)
            if r.is_success:
                slots = r.json()
                if isinstance(slots, list) and slots:
                    n_ctx = slots[0].get("n_ctx")
                    if n_ctx and isinstance(n_ctx, int) and n_ctx > 0:
                        logger.info(f"llama.cpp /slots reports n_ctx={n_ctx} for {model}")
                        return n_ctx, True
        except Exception:
            pass

    # Ollama /api/show — the model's own GGUF metadata, keyed
    # "<arch>.context_length" (gemma4.context_length, nemotron_h_moe.
    # context_length, ...). Parallel to the /slots probe above but for the other
    # local backend: llama.cpp reports the window it is SERVING, Ollama reports
    # the window the model SUPPORTS. The served window is a separate decision,
    # sent per request as num_ctx and bounded by local_served_context_ceiling().
    #
    # Without this, every Ollama model fell back to KNOWN_CONTEXT_WINDOWS, whose
    # prefix keys are coarse and go stale: 'qwen3' -> 131072 under-reported
    # qwen3.6:35b-a3b's real 262144, and 'nemotron' -> 131072 under-reported
    # nemotron-3.5-lightning:30b's real 1048576. Asking the server removes the
    # table from this path entirely and cannot drift as models change.
    if is_local_endpoint(endpoint_url):
        try:
            base = endpoint_url.split("/v1")[0] if "/v1" in endpoint_url else endpoint_url.rsplit("/", 1)[0]
            r = httpx.post(f"{base}/api/show", json={"model": model}, timeout=REQUEST_TIMEOUT)
            if r.is_success:
                info = (r.json() or {}).get("model_info") or {}
                for key, value in info.items():
                    # Exclude "...rope.scaling.original_context_length": the
                    # pre-scaling training window (gpt-oss reports 4096 there
                    # against a real 131072), not what the model serves.
                    if (
                        key.endswith(".context_length")
                        and "rope" not in key
                        and "original" not in key
                        and isinstance(value, int)
                        and value > 0
                    ):
                        logger.info(f"Ollama /api/show reports context_length={value} for {model}")
                        return value, True
        except Exception:
            pass

    # GitHub Copilot's /models requires auth + X-GitHub-Api-Version headers that
    # aren't available here; an unauthenticated probe just 400s. All Copilot
    # picker models are major API models covered by the known-context table, so
    # rely on that instead of a doomed network call.
    from src.copilot import is_copilot_base
    if is_copilot_base(endpoint_url):
        if known:
            logger.info(f"Using known context window for {model}: {known}")
            return known, True
        return DEFAULT_CONTEXT, False

    from src.endpoint_resolver import build_models_url

    models_url = build_models_url(endpoint_url)
    try:
        r = httpx.get(models_url, timeout=REQUEST_TIMEOUT)
        if r.is_success:
            data = r.json()
            models_list = data.get("data") or []

            for m in models_list:
                mid = m.get("id", "")
                if mid == model or mid.split("/")[-1] == model.split("/")[-1]:
                    api_ctx = _model_ctx_from_entry(m)
                    break
    except Exception as e:
        logger.debug(f"Failed to query context length for {model}: {e}")

    # For local/self-hosted endpoints, trust the API value (user set --max-model-len)
    # For cloud APIs, use the larger value (API can report low defaults)
    if api_ctx and known:
        _is_local = is_local_endpoint(endpoint_url)
        if _is_local and api_ctx < known:
            logger.info(f"Local endpoint reports {api_ctx} for {model} (known max: {known}) — using API value")
            return api_ctx, True
        result = max(api_ctx, known)
        if api_ctx < known:
            logger.info(f"API reported {api_ctx} for {model}, using known {known} instead")
        return result, True
    if api_ctx:
        return api_ctx, True
    if known:
        logger.info(f"Using known context window for {model}: {known}")
        return known, True

    return DEFAULT_CONTEXT, False


def estimate_tokens(messages: List[Dict]) -> int:
    """Rough token estimate for a list of messages.

    Uses chars * 0.3 which is closer to real BPE tokenizer output
    than the commonly-cited chars/4 (which underestimates by ~20-30%).
    Also adds ~4 tokens per message for role/formatting overhead, and counts
    assistant tool_calls (name + arguments) — a tool-only turn carries
    content=None with the real payload in tool_calls, so ignoring them made the
    estimate (and the compaction/trim gates that rely on it) blind to large
    tool arguments.
    """
    total = 0
    for msg in messages:
        total += 4  # per-message overhead (role, separators)
        content = msg.get("content", "")
        if isinstance(content, str):
            total += int(len(content) * 0.3)
        elif isinstance(content, list):
            for item in content:
                if isinstance(item, dict) and item.get("type") == "text":
                    total += int(len(item.get("text", "")) * 0.3)
        # Tool calls carry real payload too: a tool-only assistant turn is stored
        # with content=None and the actual args (e.g. a create_document body) in
        # tool_calls[].function.arguments. Ignoring them made large tool arguments
        # read as ~0 tokens, so the compaction/trim gates missed genuine overflow.
        tool_calls = msg.get("tool_calls")
        if isinstance(tool_calls, list):
            for tc in tool_calls:
                if not isinstance(tc, dict):
                    continue
                fn = tc.get("function") if isinstance(tc.get("function"), dict) else tc
                name = fn.get("name", "") or ""
                args = fn.get("arguments", "") or ""
                if not isinstance(args, str):
                    args = str(args)  # some shapes store arguments as a dict
                total += 4  # per tool-call overhead (id, type, wrapper)
                total += int((len(str(name)) + len(args)) * 0.3)
    return total
