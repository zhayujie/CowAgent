# encoding:utf-8

"""Per-provider model catalog: user overrides layered on the built-in presets.

The catalog is an OVERLAY, not a replacement. A provider's built-in preset
models remain the base list; the catalog only records what the user actually
changed on top of them:

- ``overrides``: entries the user edited or added. An override matched by name
  to a preset replaces that preset's metadata; an override with a new name is
  an added model.
- ``hidden``: preset model names the user removed (tombstones), so a deleted
  preset is not silently restored on the next read.

Anything the user did not touch is never persisted, so preset metadata (context
window, max output, capabilities) keeps following the code-side constants and a
later constant bump reaches every user who never overrode that model.

Storage (``get_data_root()/system/models.json``)::

    {
        "providers": {
            "zhipu": {
                "overrides": [
                    {"name": "glm-5.3", "capabilities": ["text"],
                     "context_window": 2000000}
                ],
                "hidden": ["glm-4.7"]
            },
            "custom:3f2a9c1b": {"overrides": [ ... ], "hidden": []}
        }
    }

A custom (OpenAI-compatible) provider has no presets, so its ``overrides`` are
simply its whole model list and ``hidden`` stays empty. Its entries may also
carry an optional ``alias``, the name shown in model pickers.
"""

from copy import deepcopy
import json
import os
import threading

from common.atomic_write import write_json_atomic
from common.log import logger

# Legacy: catalogs used to live under this key in config.json (pre-overlay),
# where each provider stored a full replacement list. On the first read after
# the upgrade we migrate any such entries into the overlay store (as overrides)
# and strip the key from config.json, so an early adopter keeps their models.
LEGACY_CATALOG_KEY = "provider_model_catalog"

# Capability tags route a model into the matching tool position. "text" marks
# a conversational model: only text-tagged entries appear in the main-model
# (chat) dropdown and the conversation switcher. A model may hold several
# tags (e.g. text + vision for a VL model).
VALID_CAPABILITIES = ("text", "vision", "video", "image", "embedding", "asr", "tts")
DEFAULT_CAPABILITIES = ["text"]

# Optional display name for a custom provider's model (e.g. "DeepSeek-Flash"
# for a gateway's "deepseek/deepseek-flash"). Display only: requests, session
# prefs and logs always use the real name.
MAX_ALIAS_LENGTH = 64

# Reasoning control for a custom provider's model. A gateway fronts models
# from many vendors, so only the user knows which parameter a given model
# accepts and with which values. The catalog carries that declaration:
#
#   {"param": "reasoning_effort", "options": ["minimal", "low"],
#    "default": "minimal"}
#   {"param": "thinking", "options": ["enabled", "disabled"],
#    "default": "disabled"}
#
# ``reasoning_effort`` is the vendor's effort tier (the model always thinks
# and the tier shapes the trace); ``thinking`` is the on/off switch some
# models expose instead. Request and response shapes stay untouched.
REASONING_PARAMS = ("reasoning_effort", "thinking")


def _store_path() -> str:
    """Path to the catalog overlay under the instance's shared workspace
    (``<workspace>/system/models.json``, e.g. ``~/cow/system/models.json``)."""
    from common import state_dir
    return str(state_dir.models_catalog_file())


def _normalize_reasoning(raw) -> dict:
    """Validate a model-level reasoning declaration.

    The user states which parameter the model understands and which values
    it accepts; CowAgent then sends exactly that and nothing else, so a
    gateway can front models with completely different protocols.
    """
    if not isinstance(raw, dict):
        raise ValueError("reasoning must be an object")

    param = str(raw.get("param") or "reasoning_effort").strip()
    if param not in REASONING_PARAMS:
        raise ValueError(
            "reasoning.param must be one of: %s" % ", ".join(REASONING_PARAMS))

    options = raw.get("options")
    if isinstance(options, str):
        options = [options]
    if not isinstance(options, list):
        raise ValueError("reasoning.options must be a non-empty list")
    values = []
    for value in options:
        value = str(value or "").strip()
        if value and value not in values:
            values.append(value)
    if not values:
        raise ValueError("reasoning.options must be a non-empty list")

    default = str(raw.get("default") or values[0]).strip()
    if default not in values:
        raise ValueError("reasoning.default must be one of reasoning.options")

    reasoning = {"param": param, "options": values, "default": default}
    # A model whose only knob is the effort tier always thinks: the tier
    # shapes the trace, so the generic thinking toggle must not silence it.
    # A model exposing the on/off switch instead has no tiers to speak of.
    thinking_only = raw.get("thinking_only")
    if thinking_only is None:
        thinking_only = param == "reasoning_effort"
    reasoning["thinking_only"] = bool(thinking_only)
    return reasoning


def normalize_entry(raw) -> dict:
    """Validate one catalog entry, filling defaults. Raises ValueError."""
    if not isinstance(raw, dict):
        raise ValueError("model entry must be an object")
    name = str(raw.get("name") or "").strip()
    if not name:
        raise ValueError("model name is required")

    caps = raw.get("capabilities")
    if caps in (None, ""):
        caps = list(DEFAULT_CAPABILITIES)
    if isinstance(caps, str):
        caps = [caps]
    if not isinstance(caps, list):
        raise ValueError(f"capabilities for {name} must be a list")
    # Silently drop unrecognized tags (e.g. hand-edited config) instead of
    # rejecting the whole entry — the UI only ever offers valid ones.
    caps = [c for c in (str(x).strip().lower() for x in caps) if c in VALID_CAPABILITIES]
    # A model with no tags would be unreachable everywhere (not text, not any
    # capability), so an empty set falls back to the default: text.
    if not caps:
        caps = list(DEFAULT_CAPABILITIES)

    entry = {"name": name, "capabilities": caps}
    for key in ("context_window", "max_output_tokens"):
        value = raw.get(key)
        if value in (None, ""):
            continue
        try:
            value = int(value)
        except (TypeError, ValueError, OverflowError):
            raise ValueError(f"{key} for {name} must be a positive integer")
        if value <= 0:
            raise ValueError(f"{key} for {name} must be a positive integer")
        entry[key] = value

    alias = str(raw.get("alias") or "").strip()[:MAX_ALIAS_LENGTH]
    if alias and alias != name:
        entry["alias"] = alias

    reasoning = raw.get("reasoning")
    if reasoning not in (None, ""):
        entry["reasoning"] = _normalize_reasoning(reasoning)
    return entry


def _normalize_provider_doc(raw) -> dict:
    """Coerce one provider's stored doc into {overrides: [...], hidden: [...]}.

    Accepts the legacy shape too — a bare list of entries is read as overrides
    with no tombstones — so an older config or a hand-edit still loads."""
    overrides = []
    hidden = []
    if isinstance(raw, list):
        entries = raw
        raw_hidden = []
    elif isinstance(raw, dict):
        entries = raw.get("overrides")
        raw_hidden = raw.get("hidden")
    else:
        return {"overrides": [], "hidden": []}

    if not isinstance(entries, list):
        entries = []
    if not isinstance(raw_hidden, list):
        raw_hidden = []
    for e in entries:
        try:
            overrides.append(normalize_entry(e))
        except (ValueError, TypeError, AttributeError):
            continue  # unparseable entry: skip rather than break reads
    seen = set()
    for name in raw_hidden:
        name = str(name or "").strip()
        if name and name not in seen:
            seen.add(name)
            hidden.append(name)
    return {"overrides": overrides, "hidden": hidden}


def _migrate_legacy_config() -> dict:
    """One-shot import of the pre-overlay ``provider_model_catalog`` (a full
    replacement list per provider) into the overlay store, then drop it from
    config.json. Returns the migrated store, or {} when there is nothing to do.

    The old lists become ``overrides`` with no tombstones — the closest overlay
    to the old "replace the preset list" behaviour — so an early adopter keeps
    exactly the models they had. Best effort: any failure just leaves the old
    key in place and yields {}."""
    try:
        from config import conf
        legacy = conf().get(LEGACY_CATALOG_KEY)
    except Exception:
        return {}
    if not isinstance(legacy, dict) or not legacy:
        return {}

    providers = {}
    for pid, entries in legacy.items():
        if not isinstance(entries, list):
            continue
        doc = _normalize_provider_doc(entries)
        if doc["overrides"]:
            providers[pid] = doc
    store = {"providers": providers}
    try:
        _write_store(store)
        _strip_legacy_config_key()
        logger.info(f"[ModelCatalog] migrated {len(providers)} legacy provider catalogs to overlay store")
    except OSError as e:
        logger.warning(f"[ModelCatalog] legacy migration failed: {e}")
        return {}
    return store


def _strip_legacy_config_key() -> None:
    """Remove ``provider_model_catalog`` from the in-memory config and its
    config.json file, so the migration runs only once."""
    try:
        from config import conf, get_data_root
    except Exception:
        return
    conf().pop(LEGACY_CATALOG_KEY, None)
    cfg_path = os.path.join(get_data_root(), "config.json")
    if not os.path.exists(cfg_path):
        return
    try:
        with open(cfg_path, "r", encoding="utf-8") as f:
            data = json.load(f)
    except (OSError, ValueError):
        return
    if LEGACY_CATALOG_KEY in data:
        data.pop(LEGACY_CATALOG_KEY, None)
        write_json_atomic(cfg_path, data)


def _read_store() -> dict:
    """Load the overlay store, healing entries and absorbing legacy shapes.

    Never raises: a corrupt file yields an empty store rather than taking the
    whole models view down."""
    path = _store_path()
    raw = None
    if os.path.exists(path):
        try:
            with open(path, "r", encoding="utf-8") as f:
                raw = json.load(f)
        except (OSError, ValueError) as e:
            logger.warning(f"[ModelCatalog] failed to read {path}: {e}")
            raw = None
    else:
        # No overlay file yet: this may be a fresh install or an upgrade from a
        # build that stored catalogs in config.json. Migrate the latter once.
        migrated = _migrate_legacy_config()
        if migrated.get("providers"):
            return migrated

    providers = {}
    if isinstance(raw, dict):
        src = raw.get("providers")
        if isinstance(src, dict):
            for pid, doc in src.items():
                providers[pid] = _normalize_provider_doc(doc)
    return {"providers": providers}


def _write_store(store: dict) -> None:
    path = _store_path()
    os.makedirs(os.path.dirname(path), exist_ok=True)
    write_json_atomic(path, store)


# In-memory cache so the budget/request paths (called every LLM turn) don't hit
# disk. Invalidated on every write, which all goes through this module.
_cache = None
_store_lock = threading.RLock()


def _load() -> dict:
    global _cache
    with _store_lock:
        if _cache is None:
            _cache = _read_store()
        return _cache


def _invalidate() -> None:
    global _cache
    with _store_lock:
        _cache = None


def get_catalog_map() -> dict:
    """Override entries per provider (provider id -> [entries]).

    These are the user's overrides only, NOT the merged list — callers layer
    them onto the presets. Empty when a provider has no overrides."""
    out = {}
    for pid, doc in _load()["providers"].items():
        if doc["overrides"]:
            out[pid] = [deepcopy(e) for e in doc["overrides"]]
    return out


def get_hidden_map() -> dict:
    """Removed preset names per provider (provider id -> [names]) — tombstones
    the merge step subtracts from the preset base list."""
    out = {}
    for pid, doc in _load()["providers"].items():
        if doc["hidden"]:
            out[pid] = list(doc["hidden"])
    return out


def get_catalog(provider_id) -> list:
    """Return the override entries for one provider (empty when absent)."""
    if not provider_id:
        return []
    doc = _load()["providers"].get(provider_id)
    return [deepcopy(e) for e in doc["overrides"]] if doc else []


def get_hidden(provider_id) -> list:
    """Return the tombstoned preset names for one provider."""
    if not provider_id:
        return []
    doc = _load()["providers"].get(provider_id)
    return list(doc["hidden"]) if doc else []


def save_catalog(provider_id, models, hidden=None) -> list:
    """Replace one provider's overlay (overrides + hidden tombstones).

    An empty overrides list with no tombstones drops the provider entirely,
    which restores the pure preset behaviour."""
    if not provider_id:
        raise ValueError("provider id is required")
    if not isinstance(models, list):
        raise ValueError("models must be a list")
    entries = [normalize_entry(m) for m in models]
    if not str(provider_id).startswith("custom:"):
        # Aliases are for custom providers only: a built-in vendor's model
        # names are already readable. The same holds for the reasoning
        # declaration — a built-in vendor's protocol is known from the code,
        # so only a custom gateway needs to state it.
        for entry in entries:
            entry.pop("alias", None)
            entry.pop("reasoning", None)
    names = [e["name"] for e in entries]
    if len(names) != len(set(names)):
        raise ValueError("duplicate model name in catalog")

    tombstones = []
    seen = set()
    for name in hidden or []:
        name = str(name or "").strip()
        if name and name not in seen and name not in names:
            # A name that is both overridden and hidden makes no sense; the
            # override wins, so it is never tombstoned.
            seen.add(name)
            tombstones.append(name)

    # Serialize the whole read-modify-write interval, including invalidation.
    with _store_lock:
        store = _read_store()
        providers = store["providers"]
        if entries or tombstones:
            providers[provider_id] = {"overrides": entries, "hidden": tombstones}
        else:
            providers.pop(provider_id, None)
        _write_store(store)
        _invalidate()

    logger.info(
        f"[ModelCatalog] provider {provider_id} saved: "
        f"{len(entries)} overrides, {len(tombstones)} hidden"
    )
    return entries


def remove_catalog(provider_id) -> None:
    """Drop one provider's overlay if present (used on provider delete)."""
    try:
        save_catalog(provider_id, [], [])
    except (OSError, ValueError) as e:
        logger.warning(f"[ModelCatalog] failed to remove catalog for {provider_id}: {e}")


def resolve_model_meta(provider_id, model_name) -> dict:
    """Catalog OVERRIDE metadata for one model, or {} when the user never
    overrode it.

    Returning {} for an untouched preset is deliberate: the budget resolver
    then falls back to the code-side constants, so a later constant change
    reaches users who never customized that model."""
    name = str(model_name or "").strip()
    if not provider_id or not name:
        return {}
    for entry in get_catalog(provider_id):
        if entry.get("name") == name:
            return entry
    return {}
