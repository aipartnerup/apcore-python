"""Cross-language conformance tests driven by canonical JSON fixtures.

These tests validate behavior against shared fixtures from the apcore
protocol specification repo. All SDK implementations (Python, TypeScript,
Rust) consume the same fixtures to ensure cross-language consistency.

Fixture source: apcore/conformance/fixtures/*.json (single source of truth).

Fixture discovery order:
  1. $CONFORMANCE_SPEC_REPO env var (explicit override)
  2. Sibling ../apcore/ directory (standard workspace layout & CI)
"""

from __future__ import annotations

import json
import re
from pathlib import Path
from typing import Any

import pytest

from conformance.canonical_fixtures import (
    dispatch_or_fail,
    expectation_keys,
    reject_unknown_expectations,
    spec_repo_env,
)

from apcore.acl import ACL, ACLRule
from apcore.config import (
    Config,
    _GLOBAL_ENV_MAP,
    _GLOBAL_ENV_MAP_CLAIMED,
    _GLOBAL_NS_REGISTRY,
    _GLOBAL_NS_REGISTRY_LOCK,
)
from apcore.context import Context, Identity
from apcore.errors import (
    CallDepthExceededError,
    CallFrequencyExceededError,
    CircularCallError,
    ErrorCodeCollisionError,
    ErrorCodeRegistry,
    ModuleError,
)
from apcore.schema.loader import SchemaLoader
from apcore.schema.validator import SchemaValidator
from apcore.utils.call_chain import guard_call_chain
from apcore.utils.normalize import normalize_to_canonical_id
from apcore.utils.pattern import calculate_specificity, match_pattern
from apcore.version import VersionIncompatibleError, negotiate_version

# ---------------------------------------------------------------------------
# Fixture discovery — find the canonical apcore protocol spec repo
# ---------------------------------------------------------------------------

_APCORE_REPO_ENV = "CONFORMANCE_SPEC_REPO"


def _find_apcore_fixtures() -> Path:
    """Locate the canonical conformance fixtures directory.

    Search order:
    1. $CONFORMANCE_SPEC_REPO environment variable (with the legacy
       $APCORE_SPEC_REPO fallback owned by ``conformance.canonical_fixtures``)
    2. Sibling directory: ../apcore/ relative to the apcore-python repo root
    """
    # 1. Environment variable override
    env = spec_repo_env()
    if env:
        name, value = env
        fixtures = Path(value) / "conformance" / "fixtures"
        if fixtures.is_dir():
            return fixtures
        pytest.fail(
            f"${name}={value} does not contain conformance/fixtures/. "
            f"Ensure the apcore protocol spec repo is at that path."
        )

    # 2. Sibling directory (standard workspace layout & CI checkout)
    repo_root = Path(__file__).resolve().parent.parent  # apcore-python/
    sibling = repo_root.parent / "apcore" / "conformance" / "fixtures"
    if sibling.is_dir():
        return sibling

    pytest.fail(
        "Cannot find apcore conformance fixtures.\n\n"
        "Fix one of:\n"
        f"  1. Set ${_APCORE_REPO_ENV} to the apcore spec repo path\n"
        f"  2. Clone apcore as a sibling: git clone <apcore-url> {repo_root.parent / 'apcore'}\n"
    )


FIXTURES_ROOT = _find_apcore_fixtures()
SCHEMAS_ROOT = FIXTURES_ROOT.parent.parent / "schemas"


def _load_schema(name: str) -> dict[str, Any]:
    """Load a JSON Schema file from the apcore spec repo's schemas/ directory."""
    path = SCHEMAS_ROOT / f"{name}.schema.json"
    if not path.exists():
        pytest.skip(f"Schema {name}.schema.json not found at {path}")
    with open(path) as f:
        return json.load(f)


def _load(name: str) -> dict[str, Any]:
    path = FIXTURES_ROOT / f"{name}.json"
    if not path.exists():
        pytest.skip(f"Fixture {name}.json not found at {path}")
    with open(path) as f:
        return json.load(f)


# ---------------------------------------------------------------------------
# Fixture-expectation helpers (apcore#92, apcore#93)
# ---------------------------------------------------------------------------
#
# ``expectation_keys`` / ``reject_unknown_expectations`` / ``dispatch_or_fail``
# were defined privately here for apcore#92 and moved to
# ``conformance.canonical_fixtures`` for apcore#93, so the per-fixture drivers
# under ``tests/conformance/``, ``tests/events/`` and ``tests/observability/``
# share ONE mechanism with this file rather than each growing a copy. The
# rationale — the five driver shapes that look like they check a fixture's
# declared value and do not — is documented there.
#
# The two names below stay local as thin aliases: they are used throughout this
# file and the underscore spelling marks them as test-internal.

_expectation_keys = expectation_keys
_reject_unknown_expectations = reject_unknown_expectations


def _exc_class_for(
    fixture: str,
    case_id: str,
    wire_code: str,
    mapping: dict[str, type[Exception]],
) -> type[Exception]:
    """Map a fixture's declared WIRE CODE to the SDK exception class carrying it.

    An unrecognised code is a hard failure, never a skipped branch: that is what
    turns a wrong fixture value into a passing test.
    """
    return dispatch_or_fail(fixture, case_id, wire_code, mapping, "error code")  # type: ignore[no-any-return]


def _assert_wire_code(exc: BaseException, wire_code: str, fixture: str, case_id: str) -> None:
    """Assert the raised error carries the fixture's wire code.

    Errors outside the ``ModuleError`` hierarchy carry no wire code — a fixture
    that declares ``PARSE_ERROR`` says so explicitly and maps to each SDK's
    idiomatic invalid-argument signal (Python ``ValueError``), so the class
    mapping is the whole contract there.
    """
    if not isinstance(exc, ModuleError):
        return
    assert exc.code == wire_code, (
        f"[{fixture} :: {case_id}] fixture declares error code {wire_code!r}, "
        f"but the raised {type(exc).__name__} carries {exc.code!r}"
    )


# ---------------------------------------------------------------------------
# Cleanup fixture — reset global registries between tests
# ---------------------------------------------------------------------------


@pytest.fixture(autouse=True)
def _cleanup_globals() -> Any:
    with _GLOBAL_NS_REGISTRY_LOCK:
        _GLOBAL_NS_REGISTRY.clear()
        _GLOBAL_ENV_MAP.clear()
        _GLOBAL_ENV_MAP_CLAIMED.clear()
    yield


# ---------------------------------------------------------------------------
# 1. Pattern Matching (A09)
# ---------------------------------------------------------------------------

_pattern_data = _load("pattern_matching")


@pytest.mark.parametrize(
    "case",
    _pattern_data["test_cases"],
    ids=[c["id"] for c in _pattern_data["test_cases"]],
)
def test_pattern_matching(case: dict[str, Any]) -> None:
    result = match_pattern(case["pattern"], case["value"])
    assert (
        result == case["expected"]
    ), f"match_pattern({case['pattern']!r}, {case['value']!r}) returned {result}, expected {case['expected']}"


# ---------------------------------------------------------------------------
# Error-recovery metadata (user_fixable policy resolved by error code)
# ---------------------------------------------------------------------------

_error_recovery_data = _load("error_recovery_metadata")


@pytest.mark.parametrize(
    "case",
    _error_recovery_data["test_cases"],
    ids=[c["id"] for c in _error_recovery_data["test_cases"]],
)
def test_error_recovery_user_fixable(case: dict[str, Any]) -> None:
    from apcore.errors import ModuleError

    err = ModuleError(code=case["code"], message="conformance check")
    assert (
        err.user_fixable == case["expected"]["user_fixable"]
    ), f"{case['code']}: user_fixable={err.user_fixable}, expected {case['expected']['user_fixable']}"


def test_error_recovery_fixture_matches_source() -> None:
    """The fixture's code->user_fixable map must match the _USER_FIXABLE_BY_CODE source of truth."""
    from apcore.errors import _USER_FIXABLE_BY_CODE

    fixture_map = {
        c["code"]: c["expected"]["user_fixable"]
        for c in _error_recovery_data["test_cases"]
        if c["expected"]["user_fixable"] is not None
    }
    assert fixture_map == _USER_FIXABLE_BY_CODE


# ---------------------------------------------------------------------------
# 2. Specificity Scoring (A10)
# ---------------------------------------------------------------------------

_specificity_data = _load("specificity")


@pytest.mark.parametrize(
    "case",
    _specificity_data["test_cases"],
    ids=[c["id"] for c in _specificity_data["test_cases"]],
)
def test_specificity(case: dict[str, Any]) -> None:
    score = calculate_specificity(case["pattern"])
    assert (
        score == case["expected_score"]
    ), f"calculate_specificity({case['pattern']!r}) returned {score}, expected {case['expected_score']}"


# ---------------------------------------------------------------------------
# 3. ID Normalization (A02)
# ---------------------------------------------------------------------------

_normalize_data = _load("normalize_id")


@pytest.mark.parametrize(
    "case",
    _normalize_data["test_cases"],
    ids=[c["id"] for c in _normalize_data["test_cases"]],
)
def test_normalize_id(case: dict[str, Any]) -> None:
    result = normalize_to_canonical_id(case["local_id"], case["language"])
    assert result == case["expected"], (
        f"normalize_to_canonical_id({case['local_id']!r}, {case['language']!r}) "
        f"returned {result!r}, expected {case['expected']!r}"
    )


# ---------------------------------------------------------------------------
# 4. Version Negotiation (A14)
# ---------------------------------------------------------------------------

_version_data = _load("version_negotiation")

#: Fixture WIRE CODE -> the exception class this SDK raises for it.
#:
#: This replaces ``if code == "VERSION_INCOMPATIBLE": ... else: raises(Exception)``.
#: The old ``else`` accepted any error at all — the weakest possible assertion —
#: so all three negative cases stayed green with their declared code mutated.
_VERSION_ERROR_MAP: dict[str, type[Exception]] = {
    "VERSION_INCOMPATIBLE": VersionIncompatibleError,
    # A14 parse failure has no wire code of its own: the fixture states that
    # each SDK signals it idiomatically (Python ValueError / TS Error /
    # Rust ParseError). VersionIncompatibleError is NOT a ValueError, so this
    # entry cannot be satisfied by the incompatibility path.
    "PARSE_ERROR": ValueError,
}


@pytest.mark.parametrize(
    "case",
    _version_data["test_cases"],
    ids=[c["id"] for c in _version_data["test_cases"]],
)
def test_version_negotiation(case: dict[str, Any]) -> None:
    _reject_unknown_expectations("version_negotiation", case, {"expected", "expected_error"})
    case_id = case["id"]
    expected_error = case.get("expected_error")

    if expected_error is not None:
        exc_class = _exc_class_for("version_negotiation", case_id, expected_error, _VERSION_ERROR_MAP)
        with pytest.raises(exc_class) as exc_info:
            negotiate_version(case["declared"], case["sdk"])
        _assert_wire_code(exc_info.value, expected_error, "version_negotiation", case_id)
    else:
        result = negotiate_version(case["declared"], case["sdk"])
        assert result == case["expected"], (
            f"negotiate_version({case['declared']!r}, {case['sdk']!r}) "
            f"returned {result!r}, expected {case['expected']!r}"
        )


# ---------------------------------------------------------------------------
# 5. Call Chain Safety (A20)
# ---------------------------------------------------------------------------

_CALL_CHAIN_ERROR_MAP: dict[str, type[Exception]] = {
    "CALL_DEPTH_EXCEEDED": CallDepthExceededError,
    "CIRCULAR_CALL": CircularCallError,
    "CALL_FREQUENCY_EXCEEDED": CallFrequencyExceededError,
    # Non-positive limit floor (T-B-005): each SDK rejects with its idiomatic
    # invalid-argument signal — Python ValueError, TS Error, Rust ModuleError.
    "INVALID_LIMIT": ValueError,
}

_call_chain_data = _load("call_chain")


@pytest.mark.parametrize(
    "case",
    _call_chain_data["test_cases"],
    ids=[c["id"] for c in _call_chain_data["test_cases"]],
)
def test_call_chain(case: dict[str, Any]) -> None:
    _reject_unknown_expectations("call_chain", case, {"expected", "expected_error"})
    case_id = case["id"]
    module_id = case["module_id"]
    kwargs: dict[str, Any] = {}
    if "max_call_depth" in case:
        kwargs["max_call_depth"] = case["max_call_depth"]
    if "max_module_repeat" in case:
        kwargs["max_module_repeat"] = case["max_module_repeat"]

    expected_error = case.get("expected_error")
    if expected_error is not None:
        exc_class = _exc_class_for("call_chain", case_id, expected_error, _CALL_CHAIN_ERROR_MAP)
        with pytest.raises(exc_class) as exc_info:
            guard_call_chain(module_id, case["call_chain"], **kwargs)
        _assert_wire_code(exc_info.value, expected_error, "call_chain", case_id)
        return

    if case.get("expected") != "ok":
        pytest.fail(
            f"[call_chain :: {case_id}] states expectation {case.get('expected')!r}, "
            f"which this driver does not recognise. Teach the driver, do not skip it."
        )

    # Positive case. "It did not raise" is not a post-condition: an
    # implementation that does nothing at all also does not raise. Assert what
    # is observably true after a guard that accepted the chain.
    chain = list(case["call_chain"])
    result = guard_call_chain(module_id, chain, **kwargs)
    assert result is None, f"[call_chain :: {case_id}] guard_call_chain signals by raising and returns nothing"
    assert chain == case["call_chain"], (
        f"[call_chain :: {case_id}] guard_call_chain MUST NOT mutate the caller's " f"chain; it became {chain!r}"
    )

    # Boundary probe: the guard accepted this chain because it is WITHIN the
    # limits, not because it inspects nothing. Re-run it with the one limit the
    # chain sits under tightened by one and require the matching rejection.
    # Skipped where the fixture's chain cannot be pushed over a legal limit
    # (empty_chain, single_element — max_* < 1 is itself invalid input).
    depth = len(chain)
    if depth >= 2:
        with pytest.raises(CallDepthExceededError):
            guard_call_chain(module_id, chain, **{**kwargs, "max_call_depth": depth - 1})
    repeats = chain.count(module_id)
    if repeats >= 2:
        with pytest.raises(CallFrequencyExceededError):
            guard_call_chain(module_id, chain, **{**kwargs, "max_module_repeat": repeats - 1})


# ---------------------------------------------------------------------------
# 6. Error Code Collision (A17)
# ---------------------------------------------------------------------------

_error_code_data = _load("error_codes")

#: Fixture WIRE CODE -> the exception class this SDK raises for it.
#:
#: ``expected_error`` is the wire code ``ERROR_CODE_COLLISION``. The driver used
#: to branch on ``if "expected_error" in case`` (the key existing) and assert the
#: Python class ``ErrorCodeCollisionError``, never comparing the two, so the
#: declared code could be anything at all and the suite stayed green.
_ERROR_CODE_ERROR_MAP: dict[str, type[Exception]] = {
    "ERROR_CODE_COLLISION": ErrorCodeCollisionError,
}


def _run_error_code_registrations(
    registry: ErrorCodeRegistry,
    case: dict[str, Any],
    *,
    observe: bool,
) -> None:
    """Replay a case's registration steps against *registry*.

    One shared body so the positive and negative branches drive exactly the same
    sequence — the negative branch only wraps it in ``pytest.raises``.

    With ``observe=True`` (the ``expected: "ok"`` path) each step also asserts
    its OBSERVABLE post-condition against ``registry.all_codes``: a registered
    code is queryable, an unregistered module's codes are gone. "register() did
    not raise" is satisfied by an implementation that does nothing at all, which
    is why those nine cases could not go red.
    """
    case_id = case["id"]
    action = case["action"]
    # Fixture-declared ownership, so the unregister post-condition never has to
    # reach into the registry's private state to learn what should have gone.
    owned: dict[str, set[str]] = {}

    def _register(module_id: str, code: str) -> None:
        registry.register(module_id, {code})
        owned.setdefault(module_id, set()).add(code)
        if observe:
            assert code in registry.all_codes, (
                f"[error_codes :: {case_id}] {code!r} registered OK but is not queryable " f"through registry.all_codes"
            )

    def _unregister(module_id: str) -> None:
        released = owned.pop(module_id, set())
        registry.unregister(module_id)
        if observe:
            for code in sorted(released):
                assert code not in registry.all_codes, (
                    f"[error_codes :: {case_id}] unregister({module_id!r}) left {code!r} in "
                    f"registry.all_codes, so any later reuse proves nothing"
                )

    if action == "register":
        _register(case["module_id"], case["error_code"])
    elif action == "register_sequence":
        for step in case["steps"]:
            _register(step["module_id"], step["error_code"])
    elif action == "register_unregister_register":
        for step in case["steps"]:
            if step["action"] == "register":
                _register(step["module_id"], step["error_code"])
            elif step["action"] == "unregister":
                _unregister(step["module_id"])
            else:
                pytest.fail(
                    f"[error_codes :: {case_id}] unknown step action {step['action']!r}. "
                    f"Teach the driver, do not skip it."
                )
    else:
        pytest.fail(f"[error_codes :: {case_id}] unknown action {action!r}. Teach the driver, do not skip it.")


@pytest.mark.parametrize(
    "case",
    _error_code_data["test_cases"],
    ids=[c["id"] for c in _error_code_data["test_cases"]],
)
def test_error_codes(case: dict[str, Any]) -> None:
    _reject_unknown_expectations("error_codes", case, {"expected", "expected_error"})
    case_id = case["id"]
    registry = ErrorCodeRegistry()
    expected_error = case.get("expected_error")
    expected_ok = case.get("expected")

    if expected_error is not None and expected_ok is not None:
        pytest.fail(f"[error_codes :: {case_id}] states both expected_error and expected; pick one")

    if expected_error is not None:
        exc_class = _exc_class_for("error_codes", case_id, expected_error, _ERROR_CODE_ERROR_MAP)
        with pytest.raises(exc_class) as exc_info:
            _run_error_code_registrations(registry, case, observe=False)
        _assert_wire_code(exc_info.value, expected_error, "error_codes", case_id)
        return

    if expected_ok != "ok":
        pytest.fail(
            f"[error_codes :: {case_id}] states expectation {expected_ok!r}, which this "
            f"driver does not recognise. Teach the driver, do not skip it."
        )

    _run_error_code_registrations(registry, case, observe=True)


# ---------------------------------------------------------------------------
# 7. ACL Evaluation (§6)
# ---------------------------------------------------------------------------

_acl_data = _load("acl_evaluation")


def _build_acl_context(case: dict[str, Any]) -> Context:
    """Build a Context from fixture test case data."""
    identity_data = case.get("caller_identity")
    call_depth = case.get("call_depth", 0)

    if identity_data:
        identity = Identity(
            id=case.get("caller_id") or "unknown",
            type=identity_data.get("type", "user"),
            roles=tuple(identity_data.get("roles", [])),
        )
        ctx = Context.create(identity=identity)
    else:
        ctx = Context.create()

    # Simulate call depth by populating call_chain
    if call_depth > 0:
        ctx.call_chain.extend([f"_depth_{i}" for i in range(call_depth)])

    return ctx


@pytest.mark.parametrize(
    "case",
    _acl_data["test_cases"],
    ids=[c["id"] for c in _acl_data["test_cases"]],
)
def test_acl_evaluation(case: dict[str, Any]) -> None:
    rules = [
        ACLRule(
            callers=r["callers"],
            targets=r["targets"],
            effect=r["effect"],
            conditions=r.get("conditions"),
        )
        for r in case["rules"]
    ]
    acl = ACL(rules=rules, default_effect=case["default_effect"])

    # Build context if conditions, identity, or call_depth are present
    needs_context = (
        case.get("caller_identity") is not None
        or case.get("call_depth", 0) > 0
        or any(r.get("conditions") for r in case["rules"])
    )
    ctx = _build_acl_context(case) if needs_context else None

    result = acl.check(
        caller_id=case["caller_id"],
        target_id=case["target_id"],
        context=ctx,
    )
    assert result == case["expected"], (
        f"ACL check(caller_id={case['caller_id']!r}, target_id={case['target_id']!r}) "
        f"returned {result}, expected {case['expected']}"
    )


# ---------------------------------------------------------------------------
# 8. Config Env Mapping (A12-NS)
# ---------------------------------------------------------------------------

_config_env_data = _load("config_env")


@pytest.mark.parametrize(
    "case",
    _config_env_data["test_cases"],
    ids=[c["id"] for c in _config_env_data["test_cases"]],
)
def test_config_env(case: dict[str, Any], monkeypatch: pytest.MonkeyPatch) -> None:
    from apcore.config import _apply_env_overrides, _apply_namespace_env_overrides

    # Register namespaces from fixture, applying test-case env_style override
    env_style = case.get("env_style", "auto")
    namespaces: list[str] = []
    for ns in _config_env_data["namespaces"]:
        if ns["name"] == "global" and "env_map" in ns:
            Config.env_map(ns["env_map"])
        else:
            Config.register_namespace(
                ns["name"],
                env_prefix=ns["env_prefix"],
                env_map=ns.get("env_map"),
                max_depth=ns.get("max_depth", 5),
                env_style=env_style,
            )
            namespaces.append(ns["name"])

    # Set the env var
    monkeypatch.setenv(case["env_var"], case["env_value"])

    with _GLOBAL_NS_REGISTRY_LOCK:
        regs = list(_GLOBAL_NS_REGISTRY.values())

    # Build initial data in namespace mode
    initial_data: dict[str, Any] = {"apcore": {}}
    for ns_name in namespaces:
        initial_data["apcore"][ns_name] = {}

    # Apply overrides
    updated_data = _apply_namespace_env_overrides(initial_data, regs)
    updated_data = _apply_env_overrides(updated_data)

    config = Config(data=updated_data, env_style=case.get("env_style", "auto"))
    config._mode = "namespace"

    if case["expected_path"] is None:
        val = config.get(case["env_var"])
        assert val is None
    else:
        result = config.get(case["expected_path"])
        expected = case["expected_value"]
        # Python Config coerces env values (e.g. "true" → True, "30000" → 30000).
        # Compare stringified values case-insensitively to account for this.
        if result is not None:
            result = str(result).lower()
        if expected is not None:
            expected = str(expected).lower()
        assert result == expected, f"config.get({case['expected_path']!r}) = {result!r}, expected {expected!r}"


# ---------------------------------------------------------------------------
# 9. Context Serialization (§5.7)
# ---------------------------------------------------------------------------

_ctx_ser_data = _load("context_serialization")


def _build_context_from_fixture(input_data: dict[str, Any]) -> Context:
    """Build a Context from fixture input data."""
    identity = None
    if input_data.get("identity") is not None:
        id_data = input_data["identity"]
        identity = Identity(
            id=id_data["id"],
            type=id_data.get("type", "user"),
            roles=tuple(id_data.get("roles", ())),
            attrs=id_data.get("attrs", {}),
        )

    ctx = Context(
        trace_id=input_data.get("trace_id", ""),
        caller_id=input_data.get("caller_id"),
        call_chain=list(input_data.get("call_chain", [])),
        executor=None,
        identity=identity,
        redacted_inputs=input_data.get("redacted_inputs"),
        data=dict(input_data.get("data", {})),
        services=None,
        cancel_token=None,
    )
    return ctx


# Filter out sub_cases-style tests (handled separately)
_ctx_ser_standard = [c for c in _ctx_ser_data["test_cases"] if "sub_cases" not in c]
_ctx_ser_subcases = [c for c in _ctx_ser_data["test_cases"] if "sub_cases" in c]


@pytest.mark.parametrize(
    "case",
    _ctx_ser_standard,
    ids=[c["id"] for c in _ctx_ser_standard],
)
def test_context_serialization(case: dict[str, Any]) -> None:
    case_id = case["id"]
    input_data = case["input"]
    expected = case["expected"]

    if case_id == "deserialization_round_trip":
        # Deserialize from a serialized dict, verify specific fields
        ctx = Context.deserialize(input_data)
        assert ctx.trace_id == expected["trace_id"]
        assert ctx.caller_id == expected["caller_id"]
        assert ctx.call_chain == expected["call_chain"]
        if expected.get("identity_id") is not None:
            assert ctx.identity is not None
            assert ctx.identity.id == expected["identity_id"]
            assert ctx.identity.type == expected["identity_type"]
        assert expected["data_contains"] in ctx.data
        return

    if case_id == "unknown_context_version_warns_but_proceeds":
        # Should warn but succeed
        ctx = Context.deserialize(input_data)
        assert expected["should_succeed"] is True
        assert ctx.trace_id == expected["trace_id"]
        return

    if case_id == "redacted_inputs_serialized":
        # Build context with redacted_inputs, verify they appear in serialization
        ctx = _build_context_from_fixture(input_data)
        result = ctx.serialize()
        assert result["trace_id"] == expected["trace_id"]
        assert result.get("redacted_inputs") == expected["redacted_inputs"]
        return

    # Standard serialize test: build context → serialize → compare with expected
    ctx = _build_context_from_fixture(input_data)
    result = ctx.serialize()

    assert result["_context_version"] == expected["_context_version"]
    assert result["trace_id"] == expected["trace_id"]
    assert result["caller_id"] == expected["caller_id"]
    assert result["call_chain"] == expected["call_chain"]
    assert result["identity"] == expected["identity"]
    assert result["data"] == expected["data"]


@pytest.mark.parametrize(
    "sub",
    _ctx_ser_subcases[0]["sub_cases"] if _ctx_ser_subcases else [],
    ids=[s["expected_type"] for s in (_ctx_ser_subcases[0]["sub_cases"] if _ctx_ser_subcases else [])],
)
def test_context_identity_types_serialize(sub: dict[str, Any]) -> None:
    """Each identity type round-trips through serialize → deserialize."""
    id_data = sub["input_identity"]
    identity = Identity(
        id=id_data["id"],
        type=id_data["type"],
        roles=tuple(id_data.get("roles", ())),
        attrs=id_data.get("attrs", {}),
    )
    ctx = Context.create(identity=identity)
    serialized = ctx.serialize()
    assert serialized["identity"]["type"] == sub["expected_type"]

    restored = Context.deserialize(serialized)
    assert restored.identity is not None
    assert restored.identity.type == sub["expected_type"]


# ---------------------------------------------------------------------------
# 10. Schema Validation (S4.15)
# ---------------------------------------------------------------------------

_schema_val_data = _load("schema_validation")

# Cases that require features the Python SDK doesn't yet implement
_SCHEMA_XFAIL_IDS: set[str] = set()


@pytest.fixture(scope="module")
def _schema_tools() -> tuple[SchemaLoader, SchemaValidator]:
    """Shared SchemaLoader and SchemaValidator for schema validation tests."""
    with _GLOBAL_NS_REGISTRY_LOCK:
        _GLOBAL_NS_REGISTRY.clear()
        _GLOBAL_ENV_MAP.clear()
        _GLOBAL_ENV_MAP_CLAIMED.clear()
    config = Config(data={})
    # `coerce_types=True` explicitly: this fixture's `expected_valid_coerce` half
    # documents the opt-in library-level coercing mode, which is NOT what the
    # module-invocation boundary does (TYPE_MAPPING §17.3 — that path never
    # coerces and is covered by schema_keyword_parity.json). Naming the mode here
    # keeps the assertion independent of the constructor default.
    return SchemaLoader(config), SchemaValidator(coerce_types=True)


@pytest.mark.parametrize(
    "case",
    _schema_val_data["test_cases"],
    ids=[c["id"] for c in _schema_val_data["test_cases"]],
)
def test_schema_validation(
    case: dict[str, Any],
    _schema_tools: tuple[SchemaLoader, SchemaValidator],
) -> None:
    if case["id"] in _SCHEMA_XFAIL_IDS:
        pytest.xfail(f"Known gap: {case['id']}")

    loader, validator = _schema_tools
    schema = case["schema"]
    input_data = case["input"]

    # Empty schema with no properties — validator accepts any value (Draft 2020-12)
    if not schema.get("properties"):
        model = loader.generate_model(schema, f"Model_{case['id']}")
        result = validator.validate(input_data, model)
        assert result.valid == case.get("expected_valid", True)
        return

    model = loader.generate_model(schema, f"Model_{case['id']}")

    # Determine expected validity
    if "expected_valid" in case:
        expected_valid = case["expected_valid"]
    elif "expected_valid_strict" in case:
        # This validator was built with coerce_types=True, so it asserts the
        # `_coerce` half. The `_strict` half used to be selected on and then
        # never read (the branch tested one key and asserted a different one),
        # so the fixture's strict expectation was decoration — the same
        # named-but-unasserted shape as apcore#92. Both halves now reach an
        # assertion, each against a validator built in the matching mode.
        expected_valid = case["expected_valid_coerce"]
        strict_result = SchemaValidator(coerce_types=False).validate(input_data, model)
        assert strict_result.valid == case["expected_valid_strict"], (
            f"schema_validate({case['id']}, coerce_types=False) valid={strict_result.valid}, "
            f"expected={case['expected_valid_strict']}, errors={strict_result.errors}"
        )
    else:
        expected_valid = True

    result = validator.validate(input_data, model)
    assert (
        result.valid == expected_valid
    ), f"schema_validate({case['id']}) valid={result.valid}, expected={expected_valid}, errors={result.errors}"

    # `expected_coerced_value` pins what the value BECOMES, not merely that the
    # input was accepted. Validity alone cannot tell `"false"` -> False from
    # `"false"` -> True, and an implementation that coerces every non-empty
    # string to `True` passes both boolean cases on validity (apcore#95).
    if "expected_coerced_value" in case:
        coerced = validator.validate_input(input_data, model)
        prop_name = next(iter(case["schema"]["properties"]))
        actual = coerced[prop_name]
        expected_coerced = case["expected_coerced_value"]
        assert actual == expected_coerced and type(actual) is type(expected_coerced), (
            f"schema_validate({case['id']}, coerce_types=True) coerced {prop_name}="
            f"{actual!r} ({type(actual).__name__}), expected {expected_coerced!r} "
            f"({type(expected_coerced).__name__})"
        )

    # Verify error path when expected
    if not expected_valid and "expected_error_path" in case:
        error_paths = [e.path for e in result.errors]
        expected_path = "/" + case["expected_error_path"].replace(".", "/").replace("[", "/").replace("]", "")
        assert any(expected_path in p for p in error_paths), f"Expected error at {expected_path}, got {error_paths}"


# ---------------------------------------------------------------------------
# 11. Config Defaults
# ---------------------------------------------------------------------------

_config_defaults_data = _load("config_defaults")


@pytest.mark.parametrize(
    "case",
    _config_defaults_data["test_cases"],
    ids=[c["id"] for c in _config_defaults_data["test_cases"]],
)
def test_config_defaults(case: dict[str, Any]) -> None:
    config = Config.from_defaults()
    result = config.get(case["key"])
    assert result == case["expected"], f"Default for {case['key']}: got {result}, expected {case['expected']}"


# ---------------------------------------------------------------------------
# 12. Stream Aggregation (deep merge)
# ---------------------------------------------------------------------------

_stream_agg_data = _load("stream_aggregation")


@pytest.mark.parametrize(
    "case",
    _stream_agg_data["test_cases"],
    ids=[c["id"] for c in _stream_agg_data["test_cases"]],
)
def test_stream_aggregation(case: dict[str, Any]) -> None:
    from apcore.executor import _deep_merge

    chunks = case["chunks"]
    if not chunks:
        # no chunks -> null/empty
        assert case["expected"] is None
        return
    accumulated: dict[str, Any] = {}
    for chunk in chunks:
        _deep_merge(accumulated, chunk)
    assert accumulated == case["expected"]


# ---------------------------------------------------------------------------
# 13. Defaults Schema Completeness
# ---------------------------------------------------------------------------


def test_defaults_schema_completeness() -> None:
    """Verify that all defaults defined in defaults.schema.json
    are present and match the SDK's Config defaults."""
    schema = _load_schema("defaults")

    config = Config.from_defaults()

    def extract_defaults(props: dict[str, Any], prefix: str = "") -> list[tuple[str, Any]]:
        """Recursively extract (dot-path, default) pairs from schema properties."""
        results: list[tuple[str, Any]] = []
        for key, prop in props.items():
            dot_path = f"{prefix}{key}" if not prefix else f"{prefix}.{key}"
            if "default" in prop:
                results.append((dot_path, prop["default"]))
            if prop.get("type") == "object" and "properties" in prop:
                results.extend(extract_defaults(prop["properties"], dot_path))
        return results

    defaults = extract_defaults(schema.get("properties", {}))
    assert len(defaults) > 0, "Schema should define at least one default"

    for dot_path, expected in defaults:
        actual = config.get(dot_path)
        assert actual == expected, f"Config default for '{dot_path}': got {actual!r}, schema says {expected!r}"


# ---------------------------------------------------------------------------
# 14. Sys Module Output Schema Validation
# ---------------------------------------------------------------------------


def test_sys_module_output_schemas_match_spec() -> None:
    """Verify that each sys module's output_schema matches the spec repo's schema file."""
    from apcore.sys_modules.control import (
        ReloadModuleModule,
        ToggleFeatureModule,
        UpdateConfigModule,
    )
    from apcore.sys_modules.health import HealthModuleModule, HealthSummaryModule
    from apcore.sys_modules.manifest import ManifestFullModule, ManifestModuleModule

    mapping: list[tuple[str, type]] = [
        ("sys-control-update-config", UpdateConfigModule),
        ("sys-control-reload-module", ReloadModuleModule),
        ("sys-control-toggle-feature", ToggleFeatureModule),
        ("sys-health-summary", HealthSummaryModule),
        ("sys-health-module", HealthModuleModule),
        ("sys-manifest-module", ManifestModuleModule),
        ("sys-manifest-full", ManifestFullModule),
    ]

    for schema_name, module_cls in mapping:
        spec_schema = _load_schema(schema_name)
        # Get the module's output_schema (class attribute)
        module_schema = getattr(module_cls, "output_schema", None)
        if module_schema is None:
            pytest.fail(f"{module_cls.__name__} has no output_schema")

        # Verify required keys match
        spec_required = set(spec_schema.get("required", []))
        module_required = set(module_schema.get("required", []))
        assert (
            spec_required == module_required
        ), f"{schema_name}: required mismatch — spec={spec_required}, module={module_required}"

        # Verify property keys match
        spec_props = set(spec_schema.get("properties", {}).keys())
        module_props = set(module_schema.get("properties", {}).keys())
        assert (
            spec_props == module_props
        ), f"{schema_name}: properties mismatch — spec={spec_props}, module={module_props}"


# ---------------------------------------------------------------------------
# Context.create trace_parent handling (PROTOCOL_SPEC §10.5)
# ---------------------------------------------------------------------------

from apcore.trace_context import TraceParent  # noqa: E402

_trace_parent_data = _load("context_trace_parent")


@pytest.mark.parametrize(
    "case",
    _trace_parent_data["test_cases"],
    ids=[c["id"] for c in _trace_parent_data["test_cases"]],
)
def test_context_create_trace_parent(case: dict[str, Any], caplog: pytest.LogCaptureFixture) -> None:
    import logging

    incoming = case["input"]["trace_parent_trace_id"]
    expected = case["expected"]

    if incoming is None:
        tp = None
    else:
        # Bypass TraceParent's own post-init guards so we can exercise
        # Context.create's defensive validation with every fixture input,
        # including those that a well-behaved TraceParent parser would
        # never emit (uppercase, wrong length, non-hex, empty).
        tp = TraceParent.__new__(TraceParent)
        object.__setattr__(tp, "version", "00")
        object.__setattr__(tp, "trace_id", incoming)
        object.__setattr__(tp, "parent_id", "0" * 15 + "1")
        object.__setattr__(tp, "trace_flags", "01")

    with caplog.at_level(logging.WARNING, logger="apcore.context"):
        ctx = Context.create(trace_parent=tp)

    # trace_id must always be a valid 32-char lowercase hex
    assert len(ctx.trace_id) == 32
    assert all(c in "0123456789abcdef" for c in ctx.trace_id)
    assert ctx.trace_id not in ("0" * 32, "f" * 32)

    if expected["regenerated"]:
        assert ctx.trace_id != incoming, f"Expected regeneration but kept {incoming!r}"
    else:
        assert ctx.trace_id == expected["trace_id"]

    warn_seen = any("Invalid trace_id format" in record.getMessage() for record in caplog.records)
    assert (
        warn_seen == expected["warn_logged"]
    ), f"warn_logged mismatch: expected {expected['warn_logged']}, got {warn_seen}"


# ---------------------------------------------------------------------------
# 15. Identity System (AC-014, AC-015)
# ---------------------------------------------------------------------------

_identity_data = _load("identity_system")


@pytest.mark.parametrize(
    "case",
    _identity_data["test_cases"],
    ids=[c["id"] for c in _identity_data["test_cases"]],
)
def test_identity_system(case: dict[str, Any]) -> None:
    _reject_unknown_expectations(
        "identity_system",
        case,
        {"expected", "expected_type", "expected_roles", "expected_attrs"},
    )
    identity = Identity(
        id=case["input_id"],
        type=case.get("input_type", "user"),
        roles=tuple(case["input_roles"]),
        attrs=case.get("input_attrs", {}),
    )

    if "expected_type" in case:
        assert (
            identity.type == case["expected_type"]
        ), f"Identity type: got {identity.type!r}, expected {case['expected_type']!r}"

    if "expected_roles" in case:
        assert (
            list(identity.roles) == case["expected_roles"]
        ), f"Identity roles: got {list(identity.roles)!r}, expected {case['expected_roles']!r}"

    if "expected_attrs" in case:
        assert (
            identity.attrs == case["expected_attrs"]
        ), f"Identity attrs: got {identity.attrs!r}, expected {case['expected_attrs']!r}"

    if "expected" in case:
        # Child-context propagation. `expected` used to be the prose string
        # "child.identity === parent.identity" — a sentence in a value slot, so
        # the driver hardcoded the comparison and the fixture value was
        # decoration. It is now four declared fields and every one is asserted.
        expected = case["expected"]
        known_fields = {
            "child_identity_id",
            "child_identity_type",
            "child_identity_roles",
            "child_identity_equals_parent",
        }
        unknown_fields = sorted(set(expected) - known_fields)
        assert not unknown_fields, (
            f"[identity_system :: {case['id']}] expected states field(s) {unknown_fields} "
            f"this driver does not read. Teach the driver, do not skip it."
        )

        ctx = Context.create(identity=identity)
        child_ctx = ctx.child(case["child_module_id"])
        assert child_ctx.identity is not None, "child context lost the parent identity entirely"
        assert (
            child_ctx.identity.id == expected["child_identity_id"]
        ), f"child identity id: {child_ctx.identity.id!r} != {expected['child_identity_id']!r}"
        assert (
            child_ctx.identity.type == expected["child_identity_type"]
        ), f"child identity type: {child_ctx.identity.type!r} != {expected['child_identity_type']!r}"
        assert (
            list(child_ctx.identity.roles) == expected["child_identity_roles"]
        ), f"child identity roles: {list(child_ctx.identity.roles)!r} != {expected['child_identity_roles']!r}"
        equals_parent = child_ctx.identity == ctx.identity
        assert equals_parent is expected["child_identity_equals_parent"], (
            f"child identity {child_ctx.identity!r} vs parent {ctx.identity!r}: "
            f"equality is {equals_parent}, fixture declares {expected['child_identity_equals_parent']}"
        )
        # Python-specific and stronger than the cross-language contract above:
        # Identity is immutable, so child() propagates the same object rather
        # than a copy. Kept from the pre-#92 driver, which asserted only this.
        assert child_ctx.identity is identity, "child context identity must be the parent identity object"


# ---------------------------------------------------------------------------
# 16. ModuleAnnotations Extra Round-Trip (spec §4.4)
# ---------------------------------------------------------------------------

_annotations_data = _load("annotations_extra_round_trip")

from dataclasses import asdict as _dataclasses_asdict  # noqa: E402
from apcore.module import ModuleAnnotations  # noqa: E402


@pytest.mark.parametrize(
    "case",
    _annotations_data["test_cases"],
    ids=[c["id"] for c in _annotations_data["test_cases"]],
)
def test_annotations_extra_round_trip(case: dict[str, Any]) -> None:
    case_id = case["id"]

    if "input_serialized" in case:
        # Deserialization-only cases (legacy flattened form)
        ann = ModuleAnnotations.from_dict(case["input_serialized"])

        if "expected_deserialized_extra" in case:
            assert ann.extra == case["expected_deserialized_extra"], (
                f"[{case_id}] extra after from_dict: got {ann.extra!r}, "
                f"expected {case['expected_deserialized_extra']!r}"
            )

        if "expected_reserialized" in case:
            serialized = _dataclasses_asdict(ann)
            # Normalize cache_key_fields from tuple to list for comparison
            if serialized.get("cache_key_fields") is None:
                serialized["cache_key_fields"] = None
            elif isinstance(serialized.get("cache_key_fields"), (tuple, list)):
                serialized["cache_key_fields"] = list(serialized["cache_key_fields"]) or None
            # Pilot field: see note in standard-case branch below.
            if "discoverable" not in case["expected_reserialized"]:
                serialized.pop("discoverable", None)
            assert serialized == case["expected_reserialized"], (
                f"[{case_id}] re-serialized annotations mismatch: "
                f"got {serialized!r}, expected {case['expected_reserialized']!r}"
            )
        return

    # Standard round-trip cases with "input"
    input_data = case["input"]
    ann = ModuleAnnotations.from_dict(input_data)

    if "expected_deserialized_extra" in case:
        assert (
            ann.extra == case["expected_deserialized_extra"]
        ), f"[{case_id}] extra after from_dict: got {ann.extra!r}, expected {case['expected_deserialized_extra']!r}"

    if "expected_serialized" in case:
        serialized = _dataclasses_asdict(ann)
        # Normalize cache_key_fields: tuple → list (or None when empty/None)
        ckf = serialized.get("cache_key_fields")
        if ckf is not None:
            serialized["cache_key_fields"] = list(ckf) if ckf else None
        expected = dict(case["expected_serialized"])
        # Pilot field: ``discoverable`` was added ahead of upstream RFC
        # acceptance (see CHANGELOG). Strip it from the serialized form when
        # the fixture predates the field so the cross-language conformance
        # check stays meaningful for every other key.
        if "discoverable" not in expected:
            serialized.pop("discoverable", None)
        assert (
            serialized == expected
        ), f"[{case_id}] serialized annotations mismatch: got {serialized!r}, expected {expected!r}"

    if "forbidden_root_keys" in case:
        serialized = _dataclasses_asdict(ann)
        for key in case["forbidden_root_keys"]:
            assert (
                key not in serialized
            ), f"[{case_id}] Producer MUST NOT emit top-level key {key!r}; got keys: {list(serialized.keys())}"


# ---------------------------------------------------------------------------
# 17. Approval Gate (Executor Step 5, A05)
# ---------------------------------------------------------------------------

import asyncio  # noqa: E402

from apcore.approval import ApprovalResult  # noqa: E402
from apcore.builtin_steps import BuiltinApprovalGate  # noqa: E402
from apcore.errors import ApprovalDeniedError, ApprovalPendingError  # noqa: E402
from apcore.pipeline import PipelineContext  # noqa: E402

_approval_data = _load("approval_gate")

#: Fixture WIRE CODE -> the exception class this SDK raises for it.
#:
#: ``expected.http_status`` is deliberately NOT asserted: apcore-python exposes
#: no HTTP-status surface for error codes, and an assertion with nothing to
#: observe would be decoration. Recorded in apcore#92 as a cross-SDK gap.
_APPROVAL_GATE_ERROR_MAP: dict[str, type[Exception]] = {
    "APPROVAL_DENIED": ApprovalDeniedError,
    "APPROVAL_PENDING": ApprovalPendingError,
}


class _FixtureApprovalHandler:
    """Approval handler that returns a fixed result from the fixture."""

    def __init__(self, result_data: dict[str, Any]) -> None:
        self._result = ApprovalResult(
            status=result_data["status"],
            approved_by=result_data.get("approved_by"),
            reason=result_data.get("reason"),
            approval_id=result_data.get("approval_id"),
            metadata=result_data.get("metadata"),
        )
        self.called = False

    async def request_approval(self, request: Any) -> ApprovalResult:
        self.called = True
        return self._result

    async def check_approval(self, approval_id: str) -> ApprovalResult:
        self.called = True
        return self._result


class _FakeModule:
    """Minimal module stub for approval gate tests."""

    def __init__(self, requires_approval: bool) -> None:
        from apcore.module import ModuleAnnotations

        self.description = "fake"
        self.annotations = ModuleAnnotations(requires_approval=requires_approval)
        self.input_schema = None
        self.output_schema = None

    def execute(self, inputs: dict[str, Any], context: Any) -> dict[str, Any]:
        return {}


@pytest.mark.parametrize(
    "case",
    _approval_data["test_cases"],
    ids=[c["id"] for c in _approval_data["test_cases"]],
)
def test_approval_gate(case: dict[str, Any]) -> None:
    handler: _FixtureApprovalHandler | None = None
    if case["approval_handler_configured"] and case["approval_result"] is not None:
        handler = _FixtureApprovalHandler(case["approval_result"])

    gate = BuiltinApprovalGate(handler=handler if case["approval_handler_configured"] else None)

    module = _FakeModule(requires_approval=case["module_requires_approval"])
    ctx_obj = Context.create()

    pipe_ctx = PipelineContext(
        module_id="test.module",
        module=module,
        inputs={},
        context=ctx_obj,
    )

    expected = case["expected"]

    async def _run() -> None:
        case_id = case["id"]
        outcome = expected["outcome"]
        if outcome == "proceed":
            result = await gate.execute(pipe_ctx)
            assert result.action == "continue", f"Expected gate to continue, got action={result.action!r}"
        elif outcome == "error":
            # Same audit as apcore#92: this used to dispatch on the expected
            # error code and fall through to `raises(Exception)`, which any
            # error at all satisfies. The code is now mapped, and an
            # unrecognised one is a hard failure.
            error_code = expected["error_code"]
            exc_class = _exc_class_for("approval_gate", case_id, error_code, _APPROVAL_GATE_ERROR_MAP)
            with pytest.raises(exc_class) as exc_info:
                await gate.execute(pipe_ctx)
            _assert_wire_code(exc_info.value, error_code, "approval_gate", case_id)
            if "approval_id" in expected:
                assert exc_info.value.approval_id == expected["approval_id"], (
                    f"[approval_gate :: {case_id}] approval_id: "
                    f"{exc_info.value.approval_id!r} != {expected['approval_id']!r}"
                )
        else:
            pytest.fail(
                f"[approval_gate :: {case_id}] unknown outcome {outcome!r}. " f"Teach the driver, do not skip it."
            )

        gate_invoked = handler is not None and handler.called
        assert (
            gate_invoked == expected["gate_invoked"]
        ), f"gate_invoked: expected {expected['gate_invoked']}, got {gate_invoked}"

    asyncio.run(_run())


# ---------------------------------------------------------------------------
# 18. Binding Errors (DECLARATIVE_CONFIG_SPEC.md §7.2)
# ---------------------------------------------------------------------------

_binding_errors_data = _load("binding_errors")

from apcore.errors import (  # noqa: E402
    BindingFileInvalidError,
    BindingInvalidTargetError,
    BindingModuleNotFoundError,
    BindingSchemaInferenceFailedError,
    BindingSchemaModeConflictError,
)


@pytest.mark.parametrize(
    "case",
    _binding_errors_data["test_cases"],
    ids=[c["id"] for c in _binding_errors_data["test_cases"]],
)
def test_binding_errors(case: dict[str, Any]) -> None:
    error_code = case["error_code"]
    inp = case["input"]

    if error_code == "BINDING_FILE_INVALID":
        err = BindingFileInvalidError(
            file_path=inp["file_path"],
            reason=inp["reason"],
        )
        if "expected_message" in case:
            assert (
                err.message == case["expected_message"]
            ), f"[{case['id']}] message: got {err.message!r}, expected {case['expected_message']!r}"

    elif error_code == "BINDING_SCHEMA_MODE_CONFLICT":
        err = BindingSchemaModeConflictError(
            module_id=inp["module_id"],
            modes_listed=inp["modes_listed"],
            file_path=inp["file_path"],
        )
        if "expected_message" in case:
            assert (
                err.message == case["expected_message"]
            ), f"[{case['id']}] message: got {err.message!r}, expected {case['expected_message']!r}"

    elif error_code == "BINDING_SCHEMA_INFERENCE_FAILED":
        err = BindingSchemaInferenceFailedError(
            target=inp["target"],
            module_id=inp["module_id"],
            file_path=inp["file_path"],
        )
        if "expected_message_contains" in case:
            for substring in case["expected_message_contains"]:
                assert substring in err.message, f"[{case['id']}] expected {substring!r} in message {err.message!r}"

    elif error_code == "PIPELINE_HANDLER_NOT_SUPPORTED":
        # This error is Rust-specific; Python SDK does not raise it.
        pytest.skip("PIPELINE_HANDLER_NOT_SUPPORTED is a Rust-only error code")

    elif error_code == "BINDING_INVALID_TARGET":
        err = BindingInvalidTargetError(target=inp["target"])
        if "expected_message_contains" in case:
            for substring in case["expected_message_contains"]:
                assert substring in err.message, f"[{case['id']}] expected {substring!r} in message {err.message!r}"

    elif error_code == "BINDING_MODULE_NOT_FOUND":
        err = BindingModuleNotFoundError(module_path=inp["module_path"])
        if "expected_message_contains" in case:
            for substring in case["expected_message_contains"]:
                assert substring in err.message, f"[{case['id']}] expected {substring!r} in message {err.message!r}"

    else:
        # A skip here is the same silent-branch defect as apcore#92: a fixture
        # code this driver does not know would be reported as "skipped", which
        # reads as deliberate, while nothing at all is checked. The one genuinely
        # per-SDK code (PIPELINE_HANDLER_NOT_SUPPORTED, Rust-only) is skipped
        # explicitly above; anything else is a driver that needs teaching.
        pytest.fail(
            f"[binding_errors :: {case['id']}] declares error code {error_code!r}, which "
            f"this driver does not know. Teach the driver, do not skip it."
        )


# ---------------------------------------------------------------------------
# 19. Binding YAML Canonical (DECLARATIVE_CONFIG_SPEC.md §3)
# ---------------------------------------------------------------------------


def test_binding_yaml_canonical() -> None:
    """Verify the canonical binding YAML fixture parses correctly."""
    import yaml

    yaml_path = FIXTURES_ROOT / "binding_yaml_canonical.yaml"
    if not yaml_path.exists():
        pytest.skip(f"Fixture binding_yaml_canonical.yaml not found at {yaml_path}")

    with open(yaml_path) as f:
        data = yaml.safe_load(f)

    bindings = data.get("bindings", [])
    assert len(bindings) == 3, f"Expected 3 binding entries, got {len(bindings)}"

    ids = [b["module_id"] for b in bindings]
    assert "conformance.auto_permissive" in ids
    assert "conformance.explicit_schema" in ids
    assert "conformance.auto_strict" in ids

    # Entry 1: auto_schema permissive
    entry1 = next(b for b in bindings if b["module_id"] == "conformance.auto_permissive")
    assert entry1["target"] == "conformance_mod:auto_permissive_fn"
    assert entry1.get("auto_schema") is True
    assert entry1.get("version") == "1.0.0"

    # Entry 2: explicit input/output schemas
    entry2 = next(b for b in bindings if b["module_id"] == "conformance.explicit_schema")
    assert "input_schema" in entry2
    assert "output_schema" in entry2
    assert entry2.get("version") == "2.0.0"

    # Entry 3: auto_schema strict
    entry3 = next(b for b in bindings if b["module_id"] == "conformance.auto_strict")
    assert entry3.get("auto_schema") == "strict"


# ---------------------------------------------------------------------------
# 20. Dependency Version Constraints (spec §5.3, §5.15.2)
# ---------------------------------------------------------------------------

from apcore.errors import DependencyVersionMismatchError  # noqa: E402
from apcore.registry.dependencies import resolve_dependencies  # noqa: E402
from apcore.registry.types import DependencyInfo  # noqa: E402

_dep_version_data = _load("dependency_version_constraints")

#: Fixture WIRE CODE -> the exception class this SDK raises for it.
#:
#: The driver used to dispatch on the expected VALUE with no ``else``:
#: ``if error_code == "DEPENDENCY_VERSION_MISMATCH": ...``. Every *_violated*
#: case — the entire negative half of this fixture — therefore skipped its
#: assertion block whenever the declared value was anything else, so an
#: implementation that always reported "constraint satisfied" passed every case
#: the fixture actually ran.
_DEPENDENCY_ERROR_MAP: dict[str, type[Exception]] = {
    "DEPENDENCY_VERSION_MISMATCH": DependencyVersionMismatchError,
}


@pytest.mark.parametrize(
    "case",
    _dep_version_data["test_cases"],
    ids=[c["id"] for c in _dep_version_data["test_cases"]],
)
def test_dependency_version_constraints(case: dict[str, Any]) -> None:
    # Build inputs for resolve_dependencies
    modules_input: list[tuple[str, list[DependencyInfo]]] = []
    module_versions: dict[str, str] = {}

    for mod in case["modules"]:
        mod_id = mod["module_id"]
        module_versions[mod_id] = mod["version"]
        deps = [
            DependencyInfo(
                module_id=dep["module_id"],
                version=dep.get("version"),
                optional=dep.get("optional", False),
            )
            for dep in mod.get("dependencies", [])
        ]
        modules_input.append((mod_id, deps))

    expected = case["expected"]

    if expected["outcome"] == "ok":
        load_order = resolve_dependencies(modules_input, module_versions=module_versions)
        if "load_order" in expected:
            assert (
                load_order == expected["load_order"]
            ), f"load_order: got {load_order!r}, expected {expected['load_order']!r}"
        # `skipped_edges` names the [dependent, dependency] edges the resolver
        # must DROP (an optional dependency whose version constraint is not
        # satisfied). resolve_dependencies() returns only the load order, so the
        # edge's absence is observed through that order: a kept edge forces the
        # dependency ahead of its dependent, while a dropped one leaves both at
        # in-degree zero and the deterministic sorted queue emits them in id
        # order. "dependency does not precede dependent" is therefore the
        # observable form of "this edge was skipped".
        for dependent, dependency in expected.get("skipped_edges", []):
            both_loaded = dependent in load_order and dependency in load_order
            edge_dropped = both_loaded and load_order.index(dependency) > load_order.index(dependent)
            assert edge_dropped, f"{expected['skipped_edges']!r} not dropped; load_order={load_order!r}"
    elif expected["outcome"] == "error":
        error_code = expected["error_code"]
        exc_class = _exc_class_for("dependency_version_constraints", case["id"], error_code, _DEPENDENCY_ERROR_MAP)
        with pytest.raises(exc_class) as exc_info:
            resolve_dependencies(modules_input, module_versions=module_versions)
        err = exc_info.value
        _assert_wire_code(err, error_code, "dependency_version_constraints", case["id"])
        # Every field the fixture declares is compared against the error the SDK
        # actually raised — `required` and `actual` in particular, because they
        # are what distinguishes "the checker rejected the right pair" from "the
        # checker rejected something".
        for field in ("module_id", "dependency_id", "required", "actual"):
            assert err.details.get(field) == expected[field], (
                f"[dependency_version_constraints :: {case['id']}] error {field}: "
                f"{err.details.get(field)!r} != {expected[field]!r}"
            )
    else:
        pytest.fail(
            f"[dependency_version_constraints :: {case['id']}] unknown outcome "
            f"{expected['outcome']!r}. Teach the driver, do not skip it."
        )


# ---------------------------------------------------------------------------
# 21. Middleware On-Error Recovery (A11)
# ---------------------------------------------------------------------------

from apcore.middleware.base import Middleware  # noqa: E402
from apcore.middleware.manager import MiddlewareManager  # noqa: E402

_middleware_data = _load("middleware_on_error_recovery")


class _FixtureAfterMiddleware(Middleware):
    """Middleware that records invocations and returns a fixed value from after()."""

    def __init__(self, mw_id: str, returns: dict[str, Any] | None) -> None:
        super().__init__()
        self._id = mw_id
        self._returns = returns
        self.invoked = False

    def after(
        self,
        module_id: str,
        inputs: dict[str, Any],
        output: dict[str, Any],
        context: Any,
    ) -> dict[str, Any] | None:
        self.invoked = True
        return self._returns

    def on_error(
        self,
        module_id: str,
        inputs: dict[str, Any],
        error: Exception,
        context: Any,
    ) -> dict[str, Any] | None:
        self.invoked = True
        return self._returns


@pytest.mark.parametrize(
    "case",
    _middleware_data["test_cases"],
    ids=[c["id"] for c in _middleware_data["test_cases"]],
)
def test_middleware_on_error_recovery(case: dict[str, Any]) -> None:
    manager = MiddlewareManager()
    middleware_instances: dict[str, _FixtureAfterMiddleware] = {}

    for mw_spec in case["after_middleware"]:
        mw = _FixtureAfterMiddleware(
            mw_id=mw_spec["id"],
            returns=mw_spec.get("returns"),
        )
        middleware_instances[mw_spec["id"]] = mw
        manager.add(mw)

    expected = case["expected"]
    module_raises_error = case["module_raises_error"]
    inputs: dict[str, Any] = {}
    ctx = Context.create()

    if module_raises_error:
        error = ModuleError(code="TEST_ERROR", message="test error")
        # All middlewares are "executed" for on_error purposes
        executed = manager.snapshot()
        recovery = manager.execute_on_error(
            module_id="test.module",
            inputs=inputs,
            error=error,
            context=ctx,
            executed_middlewares=executed,
        )
    else:
        # Successful execution path — call execute_after
        module_output = case.get("module_output", {})
        final_output = manager.execute_after(
            module_id="test.module",
            inputs=inputs,
            output=module_output,
            context=ctx,
        )
        recovery = None

    # Verify at least the first expected middleware was invoked.
    # Note: execute_on_error() stops at the first recovery dict (early-return),
    # so not all declared middlewares may be reached. We verify the outcome
    # and only check "at least one" was invoked when multiple are declared.
    invoked_ids = [mw_id for mw_id in expected["after_middleware_invoked"] if middleware_instances[mw_id].invoked]
    assert (
        len(invoked_ids) > 0
    ), f"Expected at least one middleware to be invoked, none were: {expected['after_middleware_invoked']}"

    # Verify outcome
    if expected["outcome"] == "error":
        if module_raises_error:
            assert recovery is None or not isinstance(recovery, dict), f"Expected no recovery dict, got {recovery!r}"
    elif expected["outcome"] == "success":
        if module_raises_error:
            assert isinstance(recovery, dict), f"Expected recovery dict, got {recovery!r}"
            # The SDK's on_error() runs middlewares in reverse registration order
            # and short-circuits at the first dict (early-return), so the "winner"
            # may differ from the fixture's declared "first" if the declared order
            # matches forward rather than reverse priority. We verify a recovery
            # dict was produced; the exact value depends on execution order.
            expected_results = [mw.get("returns") for mw in case["after_middleware"] if mw.get("returns") is not None]
            assert (
                recovery in expected_results
            ), f"Recovery dict {recovery!r} not among expected results {expected_results!r}"
        else:
            # For success path (no error), the fixture asserts on_error() is NOT
            # invoked. We verify this by checking no on_error recovery was triggered
            # (since we called execute_after, not execute_on_error, on the success path).
            # execute_after can legitimately modify output — that's by design.
            # The key invariant is that on_error handlers are not invoked on success.
            assert final_output is not None, "execute_after must return a non-None output"
    else:
        # Value dispatch with no else is the apcore#92 shape: an outcome this
        # driver does not recognise would skip every assertion above and pass.
        pytest.fail(
            f"[middleware_on_error_recovery :: {case['id']}] unknown outcome "
            f"{expected['outcome']!r}. Teach the driver, do not skip it."
        )


# ---------------------------------------------------------------------------
# 22. Core Schema Structure
# ---------------------------------------------------------------------------


def test_core_schema_structure() -> None:
    """Verify required fields in the 5 core schemas from the spec repo."""
    # acl-config.schema.json
    s = _load_schema("acl-config")
    assert "rules" in s["required"]
    assert "rules" in s["properties"]
    assert "default_effect" in s["properties"]
    assert "audit" in s["properties"]

    # apcore-config.schema.json — exactly the two keys with no canonical
    # default (PROTOCOL_SPEC §9.1). `extensions`, `schema` and `acl` all carry
    # defaults in defaults.schema.json, so requiring them would reject a
    # document the framework resolves fine; they must stay OUT of `required`.
    s = _load_schema("apcore-config")
    assert sorted(s["required"]) == [
        "project",
        "version",
    ], f"apcore-config: required must be exactly [version, project], got {s['required']!r}"
    defaults_props = set(_load_schema("defaults")["properties"])
    for key in s["required"]:
        assert key not in defaults_props, f"apcore-config: required key {key!r} has a canonical default"

    # binding.schema.json
    s = _load_schema("binding")
    assert "bindings" in s["required"]
    entry = s["$defs"]["BindingEntry"]
    assert "module_id" in entry["required"]
    assert "target" in entry["required"]

    # module-meta.schema.json
    s = _load_schema("module-meta")
    for key in ["description", "dependencies", "annotations", "version"]:
        assert key in s["properties"], f"module-meta: missing property {key!r}"

    # module-schema.schema.json
    s = _load_schema("module-schema")
    for key in ["module_id", "description", "input_schema", "output_schema"]:
        assert key in s["required"], f"module-schema: missing required key {key!r}"


# ---------------------------------------------------------------------------
# 23. Sensitive Keys Default (D-54 — canonical RedactionConfig.default list)
# ---------------------------------------------------------------------------

from apcore.observability.context_logger import RedactionConfig  # noqa: E402
from apcore.utils.redaction import redact_sensitive  # noqa: E402

_sensitive_keys_data = _load("sensitive_keys_default")


@pytest.mark.parametrize(
    "case",
    _sensitive_keys_data["test_cases"],
    ids=[c["id"] for c in _sensitive_keys_data["test_cases"]],
)
def test_sensitive_keys_default(case: dict[str, Any]) -> None:
    """D-54 — RedactionConfig.default() and override semantics.

    Cases come in two flavours:

    * ``construction == "default"``:
      - When ``input``/``expected`` key maps are present, run
        :func:`redact_sensitive` with the canonical default list and
        verify the result matches.
      - When only ``expected.sensitive_keys`` is present, verify
        ``RedactionConfig.default().sensitive_keys`` equals the canonical
        16-entry list in the documented order.
    * ``construction == "override"``: build a config with the supplied
      ``override_sensitive_keys`` and verify the redaction matches.
    """
    construction = case["construction"]
    expected = case["expected"]

    if construction == "default":
        # Sub-case 1: assert canonical default list.
        if "sensitive_keys" in expected:
            rc = RedactionConfig.default()
            assert rc.sensitive_keys == expected["sensitive_keys"], (
                f"[{case['id']}] RedactionConfig.default().sensitive_keys mismatch\n"
                f"  got:      {rc.sensitive_keys!r}\n"
                f"  expected: {expected['sensitive_keys']!r}"
            )
            if "length" in expected:
                assert (
                    len(rc.sensitive_keys) == expected["length"]
                ), f"[{case['id']}] sensitive_keys length: got {len(rc.sensitive_keys)}, expected {expected['length']}"
            return

        # Sub-case 2: redact with default list and compare.
        result = redact_sensitive(case["input"], {})
        assert (
            result == expected
        ), f"[{case['id']}] redact_sensitive(default) mismatch\n  got:      {result!r}\n  expected: {expected!r}"
        return

    if construction == "override":
        override = case["override_sensitive_keys"]
        result = redact_sensitive(case["input"], {}, sensitive_keys=override)
        assert result == expected, (
            f"[{case['id']}] redact_sensitive(override={override!r}) mismatch\n"
            f"  got:      {result!r}\n"
            f"  expected: {expected!r}"
        )
        return

    pytest.fail(f"[{case['id']}] unknown construction kind {construction!r}")


# ---------------------------------------------------------------------------
# 24. Error Fingerprinting (Issue #43 §4 — dedup with normalization)
# ---------------------------------------------------------------------------

from apcore.errors import ModuleError as _ModuleError  # noqa: E402
from apcore.observability.error_history import ErrorHistory  # noqa: E402

_error_fp_data = _load("error_fingerprinting")


def _push_error(
    history: ErrorHistory,
    error_code: str,
    caller_id: str,
    message: str,
    top_frame: str | None = None,
) -> None:
    """Push a synthetic ModuleError into ``history``.

    The canonical fingerprint is ``code:module_id:normalized_message`` and
    does NOT include any call-site / top-frame component. A fixture's
    ``top_frame`` hint therefore only affects the digest if it materially
    differs the message; we stamp it onto the message so fixture cases that
    intend distinct call sites remain distinct entries.
    """
    err = _ModuleError(code=error_code, message=message)
    if top_frame is not None:
        # Stamp the call-site hint into the message so that fixture cases
        # marking distinct call sites stay distinct after normalization.
        err = _ModuleError(
            code=error_code,
            message=f"{message} [@{top_frame}]",
        )
    history.record(caller_id, err)


@pytest.mark.parametrize(
    "case",
    _error_fp_data["test_cases"],
    ids=[c["id"] for c in _error_fp_data["test_cases"]],
)
def test_error_fingerprinting(case: dict[str, Any]) -> None:
    """Verify ErrorHistory dedup and fingerprint behavior.

    The fingerprint normalizes UUIDs, ISO timestamps, hex IDs, and
    integers ≥ 4 digits — so two errors that differ only in those
    values MUST collapse into a single entry.  Different ``error_code``
    or different call-sites MUST yield distinct entries.
    """
    history = ErrorHistory()
    expected = case["expected"]

    for err_data in case["errors"]:
        _push_error(
            history,
            error_code=err_data["error_code"],
            caller_id=err_data["caller_id"],
            message=err_data["message"],
            top_frame=err_data.get("top_frame"),
        )

    all_entries = history.get_all()
    fingerprints = {e.fingerprint for e in all_entries}

    assert len(all_entries) == expected["entry_count"], (
        f"[{case['id']}] entry_count: got {len(all_entries)}, "
        f"expected {expected['entry_count']}; entries={[(e.code, e.message, e.count) for e in all_entries]!r}"
    )
    assert (
        len(fingerprints) == expected["fingerprints_distinct"]
    ), f"[{case['id']}] fingerprints_distinct: got {len(fingerprints)}, expected {expected['fingerprints_distinct']}"

    if "first_entry_count" in expected:
        # Entries are returned newest-first by last_occurred; the
        # collapsed entry is the one with count > 1.  Pick the entry
        # with the highest count to match "first/dedup'd entry".
        top = max(all_entries, key=lambda e: e.count)
        assert (
            top.count == expected["first_entry_count"]
        ), f"[{case['id']}] first_entry_count: got {top.count}, expected {expected['first_entry_count']}"


# ---------------------------------------------------------------------------
# 25. Contextual Audit (Issue #45.2 — caller_id/identity in audit events)
# ---------------------------------------------------------------------------

from apcore.events.emitter import EventEmitter as _EventEmitter  # noqa: E402
from apcore.sys_modules.control import (  # noqa: E402
    ReloadModule,
    ToggleFeatureModule,
    UpdateConfigModule,
)

_contextual_audit_data = _load("contextual_audit")


class _CapturingSubscriber:
    """Async event subscriber that records every received ApCoreEvent."""

    def __init__(self) -> None:
        self.events: list[Any] = []

    async def on_event(self, event: Any) -> None:
        self.events.append(event)


def _build_audit_context(case_ctx: dict[str, Any]) -> Context | None:
    """Build a Context from the fixture's ``context`` block.

    The fixture passes free-form identity dicts (e.g. ``display_name``,
    ``bearer_token``).  Identity is a ``frozen`` dataclass with only
    ``id``/``type``/``roles``/``attrs`` fields, so any extra keys flow
    through ``attrs``.
    """
    caller_id = case_ctx.get("caller_id")
    identity_data = case_ctx.get("identity")
    identity_obj: Identity | None = None
    if identity_data is not None:
        canonical_keys = {"id", "type", "roles"}
        attrs = {k: v for k, v in identity_data.items() if k not in canonical_keys}
        identity_obj = Identity(
            id=str(identity_data.get("id", "")),
            type=str(identity_data.get("type", "user")),
            roles=tuple(identity_data.get("roles", ()) or ()),
            attrs=attrs,
        )
    # Build a Context manually so caller_id can be ``""`` or ``None``
    # (Context.create always assigns a fresh trace_id but doesn't
    # surface caller_id).
    ctx: Context = Context(
        trace_id="0" * 31 + "1",
        caller_id=caller_id,
        call_chain=[],
        executor=None,
        identity=identity_obj,
    )
    return ctx


def _subset_match(actual: dict[str, Any], expected: dict[str, Any]) -> tuple[bool, str]:
    """Return ``(ok, reason)`` — every key in ``expected`` is present and equal in ``actual``.

    Nested dicts are checked recursively; lists and primitives use ``==``.
    """
    for key, exp_val in expected.items():
        if key not in actual:
            return False, f"missing key {key!r} (have {sorted(actual.keys())!r})"
        act_val = actual[key]
        if isinstance(exp_val, dict) and isinstance(act_val, dict):
            ok, reason = _subset_match(act_val, exp_val)
            if not ok:
                return False, f"at {key!r}: {reason}"
        else:
            if act_val != exp_val:
                return False, (f"at {key!r}: got {act_val!r}, expected {exp_val!r}")
    return True, ""


@pytest.mark.parametrize(
    "case",
    _contextual_audit_data["test_cases"],
    ids=[c["id"] for c in _contextual_audit_data["test_cases"]],
)
def test_contextual_audit(case: dict[str, Any]) -> None:
    """Verify system.control.* modules attach caller_id + identity to audit events."""
    module_id = case["module_id"]
    expected = case["expected"]
    ctx = _build_audit_context(case["context"])

    # Drive the SDK directly through each control module's ``_emit_event``
    # / ``_emit_module_reloaded`` so we exercise the real event-payload
    # construction without depending on a populated Registry, on-disk
    # overrides, or live module-reload mechanics.  This is the cleanest
    # spec-driven harness: the contract under test is "audit event
    # payload contains caller_id + identity", not the full execute path.
    emitter = _EventEmitter()
    sub = _CapturingSubscriber()
    emitter.subscribe(sub)

    try:
        if module_id == "system.control.update_config":
            mod = UpdateConfigModule(
                config=Config.from_defaults(),
                event_emitter=emitter,
            )
            mod.execute(case["input"], ctx)
        elif module_id == "system.control.toggle_feature":
            # Drive the emit-only branch directly so we don't need a
            # Registry populated with ``risky.module``.
            mod_t = ToggleFeatureModule(
                registry=None,  # type: ignore[arg-type]
                event_emitter=emitter,
            )
            mod_t._emit_event(  # noqa: SLF001 — testing payload shape
                module_id=case["input"]["module_id"],
                enabled=case["input"]["enabled"],
                context=ctx,
            )
        elif module_id == "system.control.reload_module":
            mod_r = ReloadModule(
                registry=None,  # type: ignore[arg-type]
                event_emitter=emitter,
            )
            mod_r._emit_module_reloaded(  # noqa: SLF001 — testing payload shape
                module_id=case["input"]["module_id"],
                previous_version="1.0.0",
                new_version="1.0.1",
                context=ctx,
            )
        else:
            pytest.fail(f"[{case['id']}] unknown module_id {module_id!r}")

        emitter.flush()
    finally:
        emitter.shutdown()

    matching = [e for e in sub.events if e.event_type == expected["event_type"]]
    assert matching, (
        f"[{case['id']}] no event of type {expected['event_type']!r} captured; "
        f"got {[e.event_type for e in sub.events]!r}"
    )
    event = matching[0]
    data = dict(event.data)

    # Subset match — fixture's ``data_contains`` is intentionally a
    # subset (extra keys like timestamp / event-level module_id are
    # producer-defined).
    ok, reason = _subset_match(data, expected["data_contains"])
    assert ok, f"[{case['id']}] data_contains mismatch: {reason}; got={data!r}"

    for forbidden in expected.get("data_must_not_contain_keys", []):
        assert forbidden not in data, f"[{case['id']}] data must not contain key {forbidden!r}; got={data!r}"


# ---------------------------------------------------------------------------
# Context.create unified-signature contract (PROTOCOL_SPEC §"Contract: Context.create",
# §"Contract: Executor binding to Context", §"Contract: Distributed cancellation",
# §"Contract: global_deadline distributed semantics"; apcore Issue #66)
# ---------------------------------------------------------------------------

import inspect as _inspect  # noqa: E402

from apcore.cancel import CancelToken as _CancelToken  # noqa: E402
from apcore.errors import ContextBindingError as _ContextBindingError  # noqa: E402
from apcore.executor import Executor as _CtxCreateExecutor  # noqa: E402
from apcore.module import Module as _CtxCreateModule  # noqa: E402
from apcore.registry import Registry as _CtxCreateRegistry  # noqa: E402

_context_create_data = _load("context_create")


class _EchoModule(_CtxCreateModule):
    """Minimal module used by Context.create conformance scenarios."""

    description = "Echo module for Context.create conformance tests."
    input_schema = None
    output_schema = None

    def execute(self, inputs: dict[str, Any], context: Context) -> dict[str, Any]:
        return dict(inputs)


def _build_executor_with_echo(module_id: str = "test.echo") -> _CtxCreateExecutor:
    reg = _CtxCreateRegistry()
    reg.register(module_id, _EchoModule())
    return _CtxCreateExecutor(registry=reg)


def _assert_trace_id(trace_id: str, pattern: str) -> None:
    """Check a generated trace_id against the fixture's own ``trace_id_pattern``.

    This used to re-implement the pattern in Python ("len 32 and all lowercase
    hex"), which is the same shape as asserting a fixture against a copy of
    itself: the fixture could change its pattern and this would never notice.
    """
    assert re.match(pattern, trace_id), f"trace_id {trace_id!r} does not match {pattern!r}"


@pytest.mark.parametrize(
    "case",
    _context_create_data["test_cases"],
    ids=[c["id"] for c in _context_create_data["test_cases"]],
)
def test_context_create_unified_signature(case: dict[str, Any]) -> None:
    """Conformance harness for context_create.json — exercises every scenario
    defined in the cross-language fixture (Issue #66).

    Every branch reads its verdict out of ``case["expected"]`` and compares it
    against something observed on the SDK. A key in ``expected`` that this
    driver does not read asserts nothing at all (that is what let
    ``wrapped_in`` sit in a fixture while two SDKs dropped the behaviour it
    named), so the comparisons below are deliberately written as
    ``observed is expected[...]`` rather than as bare literals.
    """
    case_id = case["id"]
    expected = case.get("expected", {})

    if case_id == "create_minimal_all_defaults":
        ctx = Context.create()
        _assert_trace_id(ctx.trace_id, expected["trace_id_pattern"])
        assert ctx.identity == expected["identity"]
        assert ctx.executor == expected["executor"]
        assert ctx.cancel_token == expected["cancel_token"]
        assert ctx.services == expected["services"]
        assert ctx.global_deadline == expected["global_deadline"]
        assert ctx.caller_id == expected["caller_id"]
        assert ctx.call_chain == expected["call_chain"]
        assert (ctx.data == {}) is expected["data_empty"], f"data expected empty, got {ctx.data!r}"

    elif case_id == "create_with_identity_only":
        ident = Identity(
            id=case["input"]["identity"]["id"],
            type=case["input"]["identity"]["type"],
            roles=tuple(case["input"]["identity"]["roles"]),
        )
        ctx = Context.create(identity=ident)
        _assert_trace_id(ctx.trace_id, expected["trace_id_pattern"])
        assert ctx.identity is not None and ctx.identity.id == expected["identity_id"]
        assert ctx.executor == expected["executor"]
        assert ctx.cancel_token == expected["cancel_token"]

    elif case_id == "create_with_cancel_token":
        token = _CancelToken()
        ctx = Context.create(cancel_token=token)
        assert (ctx.cancel_token is not None) is expected[
            "cancel_token_bound"
        ], "cancel_token MUST be carried on the returned Context without post-hoc assignment"
        assert (ctx.cancel_token is token) is expected[
            "cancel_token_matches_input"
        ], "cancel_token must be the same instance passed in"
        assert ctx.executor == expected["executor_at_create_time"], "executor MUST NOT be bound at create() time"

    elif case_id == "create_with_global_deadline":
        ctx = Context.create(global_deadline=case["input"]["global_deadline"])
        assert ctx.global_deadline == expected["global_deadline"]
        assert ctx.executor == expected["executor"]

    elif case_id == "create_rejects_executor_input":
        # Conforming SDK: executor is not a parameter of Context.create.
        params = _inspect.signature(Context.create).parameters
        assert ("executor" not in params) is expected["executor_is_not_a_parameter"], (
            "Context.create MUST NOT accept an 'executor' parameter per PROTOCOL_SPEC "
            "§Contract: Context.create (Issue #66)."
        )

    elif case_id == "create_rejects_caller_id_input":
        params = _inspect.signature(Context.create).parameters
        assert ("caller_id" not in params) is expected["caller_id_is_not_a_parameter"], (
            "Context.create MUST NOT accept a 'caller_id' parameter per PROTOCOL_SPEC "
            "§Contract: Context.create (Issue #66)."
        )
        # And the field stays null on freshly created top-level contexts.
        ctx = Context.create()
        assert ctx.caller_id == expected["caller_id_after_create"]

    elif case_id == "executor_binds_on_first_call_local":
        module_id = case["input"]["call_module"]
        executor = _build_executor_with_echo(module_id)
        ctx = Context.create()
        assert ctx.executor == expected["executor_at_create_time"], "executor must be null immediately after create()"

        raised_binding_error = False
        call_succeeded = False
        failure: Exception | None = None
        try:
            executor.call(module_id, {"hello": "world"}, context=ctx)
            call_succeeded = True
        except _ContextBindingError as exc:
            raised_binding_error = True
            failure = exc
        except Exception as exc:  # reported through the assertions below
            failure = exc

        assert raised_binding_error is expected["raised_binding_error"], f"binding raised {failure!r}"
        assert call_succeeded is expected["call_succeeded"], f"first call did not complete: {failure!r}"
        # Stronger than the fixture requires: the fixture's `notes` make
        # post-call visibility of the binding on the caller's own reference
        # SDK-specific. Python does mutate the caller's Context, so hold it.
        assert ctx.executor is executor, "Executor MUST bind itself to ctx.executor before step 1"

    elif case_id == "executor_binds_idempotent_same_instance":
        executor = _build_executor_with_echo("test.echo")
        ctx = Context.create()
        bound_per_call: list[Any] = []
        raised_error = False
        try:
            for module_id in case["input"]["calls"]:
                executor.call(module_id, {}, context=ctx)
                bound_per_call.append(ctx.executor)
        except _ContextBindingError:
            raised_error = True

        rebind_noop = not raised_error and all(bound is bound_per_call[0] for bound in bound_per_call[1:])
        assert rebind_noop is expected["rebind_noop"], f"rebind must not raise or swap: {bound_per_call!r}"
        executor_identity_stable = bool(bound_per_call) and all(bound is executor for bound in bound_per_call)
        assert executor_identity_stable is expected["executor_identity_stable"], f"unstable: {bound_per_call!r}"
        assert raised_error is expected["raised_error"]

    elif case_id == "executor_rejects_cross_executor_rebind":
        # The fixture used to say `expected_one_of: [raise, silent_accept]`; a
        # driver cannot assert an alternation, so this branch hardcoded "raise"
        # and read the fixture only in a comment. The spec now makes the raise a
        # MUST and declares the WIRE CODE, so both declared fields are observed:
        # that it raised at all, and which code came out. `ContextBindingError`
        # is a class name two SDKs share and apcore-rust does not have.
        executor_a = _build_executor_with_echo("test.echo")
        executor_b = _build_executor_with_echo("test.echo")
        ctx = Context.create()
        executor_a.call("test.echo", {}, context=ctx)
        assert ctx.executor is executor_a
        raised_code: str | None = None
        try:
            executor_b.call("test.echo", {}, context=ctx)
        except ModuleError as exc:
            raised_code = exc.code
        assert (raised_code is not None) is expected["raises"], (
            f"cross-executor rebind: raised={raised_code!r}, fixture declares raises=" f"{expected['raises']}"
        )
        assert raised_code == expected["error_code"], (
            f"cross-executor rebind raised {raised_code!r}, fixture declares " f"{expected['error_code']!r}"
        )
        # The wire code is the contract; this pins the Python class that carries
        # it so a future refactor cannot quietly move the code onto another type.
        assert issubclass(_ContextBindingError, ModuleError)
        assert _ContextBindingError().code == expected["error_code"]

    elif case_id == "child_propagates_executor":
        executor = _build_executor_with_echo("test.echo")
        ctx = Context.create()
        if case["input"]["bind_executor"]:
            ctx.bind_executor(executor)
        target_module_id = case["input"]["create_child_module_id"]
        child = ctx.child(target_module_id)
        assert (child.executor is ctx.executor) is expected[
            "child_executor_matches_parent"
        ], f"child.executor {child.executor!r} does not match parent's {ctx.executor!r}"
        parent_chain_tip = ctx.call_chain[-1] if ctx.call_chain else None
        assert (child.caller_id == parent_chain_tip) is expected[
            "child_caller_id_from_parent_chain_tip"
        ], f"child.caller_id {child.caller_id!r} is not the parent chain tip {parent_chain_tip!r}"
        appends_target = child.call_chain == [*ctx.call_chain, target_module_id]
        assert appends_target is expected["child_call_chain_appends_target"], f"chain {child.call_chain!r}"

    elif case_id == "child_propagates_cancel_token":
        token = _CancelToken()
        ctx = Context.create(cancel_token=token)
        child = ctx.child(case["input"]["create_child_module_id"])
        assert (child.cancel_token is not None) is expected[
            "child_cancel_token_bound"
        ], "child MUST carry a cancel_token so deep modules observe cancellation"
        same_token = child.cancel_token is ctx.cancel_token and child.cancel_token is token
        assert same_token is expected["child_cancel_token_matches_parent"], f"token {child.cancel_token!r}"

    elif case_id == "deserialize_then_call_binds_local_executor":
        serialized = case["input"]["serialized_context"]
        restored = Context.deserialize(serialized)
        assert restored.executor == expected["executor_after_deserialize"]
        assert restored.cancel_token == expected["cancel_token_after_deserialize"]
        assert restored.services == expected["services_after_deserialize"]
        assert restored.global_deadline == expected["global_deadline_after_deserialize"]
        assert restored.caller_id == expected["caller_id_preserved"]
        # Now a local Executor receives the deserialized Context and binds itself.
        module_id = case["input"]["call_module"]
        executor = _build_executor_with_echo(module_id)
        executor.call(module_id, {}, context=restored)
        assert (restored.executor is executor) is expected[
            "executor_bound_on_first_call"
        ], "the receiving node's Executor MUST bind itself to a deserialized Context"

    elif case_id == "tracestate_carried_inside_traceparent":
        from apcore.trace_context import TraceParent as _TP

        tp_in = case["input"]["trace_parent"]
        tp = _TP(
            version="00",
            trace_id=tp_in["trace_id"],
            parent_id=tp_in["parent_id"],
            trace_flags=tp_in["trace_flags"],
            tracestate=tuple((v[0], v[1]) for v in tp_in["tracestate"]),
        )
        ctx = Context.create(trace_parent=tp)
        assert ctx.trace_id == expected["trace_id"]
        # tracestate rides inside TraceParent (no separate parameter) and is
        # carried through to the Context by the SDK's TraceParent plumbing.
        carried = ctx.data.get("_apcore.trace.state")
        tracestate_preserved = carried is not None and [list(pair) for pair in carried] == tp_in["tracestate"]
        assert (
            tracestate_preserved is expected["tracestate_preserved"]
        ), f"tracestate {carried!r} did not round-trip {tp_in['tracestate']!r}"
        params = _inspect.signature(Context.create).parameters
        assert ("tracestate" not in params) is expected[
            "no_separate_tracestate_parameter"
        ], "tracestate MUST live inside TraceParent — no separate Context.create parameter"

    elif case_id == "distributed_cancel_token_post_deserialize_null":
        # Negative invariant: cancel_token MUST NOT serialize. Drive it from a
        # LOCAL context that really holds a token, so the assertion observes
        # serialize() dropping it rather than a hand-written payload that never
        # had the field (which would pass on an SDK that serialized tokens).
        local = Context.create(cancel_token=_CancelToken())
        assert local.cancel_token is not None
        wire = local.serialize()
        restored = Context.deserialize(wire)
        assert (
            restored.cancel_token == expected["cancel_token_after_deserialize"]
        ), "cancel_token MUST be null after deserialization"
        on_wire = "cancel_token" in wire
        no_token_rode_across = (
            on_wire is case["input"]["serialized_context_includes_cancel_token_field"] and restored.cancel_token is None
        )
        assert (
            no_token_rode_across is expected["no_in_context_token_rides_across_processes"]
        ), f"serialize() must not put cancel_token on the wire; got keys {sorted(wire)!r}"

    elif case_id == "distributed_global_deadline_post_deserialize_null":
        # Same shape: start from a context that carries a global_deadline so the
        # serializer is the thing under test, not the fixture payload.
        local = Context.create(global_deadline=1234567890.5)
        assert local.global_deadline is not None
        wire = local.serialize()
        restored = Context.deserialize(wire)
        assert (
            restored.global_deadline == expected["global_deadline_after_deserialize"]
        ), "global_deadline MUST be null after deserialization"
        on_wire = "global_deadline" in wire
        no_remote_deadline = (
            on_wire is case["input"]["serialized_context_includes_global_deadline_field"]
            and restored.global_deadline is None
        )
        assert (
            no_remote_deadline is expected["no_remote_deadline_rides_via_global_deadline_field"]
        ), f"serialize() must not put global_deadline on the wire; got keys {sorted(wire)!r}"

    else:
        pytest.fail(f"Unknown context_create fixture case id: {case_id!r}")


# ---------------------------------------------------------------------------
# 25. ACL Agent Scoping (issue #72)
# ---------------------------------------------------------------------------
#
# Mirrors ``test_acl_evaluation`` machinery but drives off a SHARED
# ``default_effect`` + ``rules`` ruleset that applies to every case (the
# canonical AI-agent tool-governance scenario). Each case is a
# (caller_id, caller_identity, call_depth, target_id) -> bool decision.
# Locks first-match-wins (§6) with {roles, max_call_depth} conditions and the
# @external special caller across all SDKs.

_acl_agent_data = _load("acl_agent_scoping")


@pytest.mark.parametrize(
    "case",
    _acl_agent_data["test_cases"],
    ids=[c["id"] for c in _acl_agent_data["test_cases"]],
)
def test_acl_agent_scoping(case: dict[str, Any]) -> None:
    # Build ONE ACL from the fixture-level default_effect + rules and reuse it
    # for every case (the governance ruleset is shared, not per-case).
    rules = [
        ACLRule(
            callers=r["callers"],
            targets=r["targets"],
            effect=r["effect"],
            conditions=r.get("conditions"),
        )
        for r in _acl_agent_data["rules"]
    ]
    acl = ACL(rules=rules, default_effect=_acl_agent_data["default_effect"])

    # Reuse the exact context-construction shape from test_acl_evaluation:
    # identity (type + roles) and a call_chain of length call_depth. A context
    # is always supplied here because the governance rules carry conditions.
    ctx = _build_acl_context(case)

    result = acl.check(
        caller_id=case["caller_id"],
        target_id=case["target_id"],
        context=ctx,
    )
    assert result == case["expected"], (
        f"[{case['id']}] ACL agent-scoping check("
        f"caller_id={case['caller_id']!r}, target_id={case['target_id']!r}, "
        f"identity={case.get('caller_identity')!r}, call_depth={case.get('call_depth', 0)}) "
        f"returned {result}, expected {case['expected']}"
    )


# ---------------------------------------------------------------------------
# 26. Per-instance ToggleState Isolation (issue #71)
# ---------------------------------------------------------------------------
#
# Constructs one real APCore per instance name in the SAME process, drives the
# per-instance toggle WRITE path (APCore.disable/enable, which calls
# system.control.toggle_feature through that instance), and asserts the
# disabled-set as observed through that instance's READ path (its own
# ToggleState — the same object the pipeline's BuiltinModuleLookup reads).
# Key contract: disabling a module on instance A MUST NOT disable it on B.

from apcore.client import APCore  # noqa: E402

_toggle_isolation_data = _load("toggle_state_isolation")


def _make_toggle_instance(module_ids: list[str]) -> APCore:
    """Build a sys-modules-enabled APCore with the given module_ids registered.

    Each referenced module is registered as a trivial no-op so the toggle
    write path (which requires the target module to exist) succeeds.
    """
    # Fresh Config per instance so each APCore owns an independent ToggleState.
    config = Config(data={"sys_modules": {"enabled": True, "events": {"enabled": True}}})
    client = APCore(config=config)
    _register_noop_modules(client, module_ids)
    return client


def _register_noop_modules(client: APCore, module_ids: list[str]) -> None:
    """(Re-)register each module_id as a trivial no-op module on the client.

    Idempotent: a module that is already present is unregistered first, so the
    ``reload`` action (which calls this again) genuinely re-creates the module
    instance in the registry. The per-instance ToggleState lives on the APCore
    (outside the registry), so it survives this re-registration.
    """

    class _NoopModule:
        description = "conformance no-op module"
        input_schema = None
        output_schema = None

        def execute(self, inputs: dict[str, Any], context: Any) -> dict[str, Any]:
            return {}

    for mid in module_ids:
        if client.registry.has(mid):
            client.registry.unregister(mid)
        client.register(mid, _NoopModule())


@pytest.mark.parametrize(
    "case",
    _toggle_isolation_data["test_cases"],
    ids=[c["id"] for c in _toggle_isolation_data["test_cases"]],
)
def test_toggle_state_isolation(case: dict[str, Any]) -> None:
    # All module_ids referenced anywhere in this case (operations + expected).
    referenced: set[str] = set()
    for op in case["operations"]:
        if op.get("module_id"):
            referenced.add(op["module_id"])
    for ids in case["expected_disabled"].values():
        referenced.update(ids)
    module_ids = sorted(referenced)

    # One real APCore per named instance, in the same process.
    instances: dict[str, APCore] = {name: _make_toggle_instance(module_ids) for name in case["instances"]}

    try:
        for op in case["operations"]:
            client = instances[op["instance"]]
            action = op["action"]
            if action == "disable":
                client.disable(op["module_id"], reason="conformance disable")
            elif action == "enable":
                client.enable(op["module_id"], reason="conformance enable")
            elif action == "reload":
                # Re-register modules on this instance WITHOUT recreating it, so
                # the per-instance ToggleState (owned by the APCore, outside the
                # registry) is preserved across the reload.
                _register_noop_modules(client, module_ids)
            else:
                pytest.fail(f"[{case['id']}] unknown toggle action {action!r}")

        # Assert each instance's disabled-set via its OWN read path (the
        # per-instance ToggleState the pipeline lookup uses), NOT the global.
        for name, expected_ids in case["expected_disabled"].items():
            client = instances[name]
            observed = {mid for mid in module_ids if client.toggle_state.is_disabled(mid)}
            expected_set = set(expected_ids)
            assert observed == expected_set, (
                f"[{case['id']}] instance {name!r} disabled-set mismatch: "
                f"observed {sorted(observed)}, expected {sorted(expected_set)}"
            )
    finally:
        for client in instances.values():
            client.close()
