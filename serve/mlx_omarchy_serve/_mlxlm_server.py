"""Total-context-capped launcher for mlx_lm.server (pinned 0.31.3).

The upstream server treats --max-tokens as a per-request DEFAULT: a client
may send any prompt plus any max_tokens of its own, and nothing bounds
prompt + output. This shim adds the missing cap at the tokenization trust
boundary — the one place where the full prompt token list exists — and
rejects any request whose prompt + max_tokens exceeds the admitted context
budget before a single token is generated.

Aggregate bound: the serve CLI launches this server with decode and prompt
concurrency 1 and the prompt cache disabled, so exactly ONE request's
tokens are ever resident and the aggregate equals the admitted context.
A larger --prompt-cache-size re-enables prefix caching at a documented
cost: worst-case resident KV becomes (cache + 1) x the admitted context.

Fail-closed pinning: the shim supports exactly the pinned mlx-lm version.
A different mlx_lm.__version__ refuses to launch unless
MLX_OMARCHY_ALLOW_UNPINNED_MLXLM=1 is set explicitly (loud warning); if
the hooked internals moved anyway, the launch still fails loudly instead
of silently dropping the cap.
"""

from __future__ import annotations

import inspect
import json
import os
import sys
import threading
import time

# PairGates: install /v1/internal/memory probe if the patcher is on
# PYTHONPATH. Side-effect import — no-op if absent.
try:
    import _mlxlm_server_with_memory  # noqa: F401
except ImportError:
    pass

LIMIT_ENV = "MLX_OMARCHY_SERVE_CONTEXT_LIMIT"
UNPINNED_ENV = "MLX_OMARCHY_ALLOW_UNPINNED_MLXLM"
SUPPORTED_MLXLM_VERSIONS = ("0.31.3",)


def _mlxlm_version(server_module) -> str:
    for holder in (server_module, getattr(server_module, "_version", None)):
        version = getattr(holder, "__version__", None)
        if version:
            return str(version)
    return "unknown"


def check_pinned(server_module) -> str:
    version = _mlxlm_version(server_module)
    if version in SUPPORTED_MLXLM_VERSIONS:
        return version
    if os.environ.get(UNPINNED_ENV) == "1":
        print(
            f"warning: {UNPINNED_ENV}=1 — mlx-lm {version} is not the pinned "
            f"{SUPPORTED_MLXLM_VERSIONS}; the cap hooks may not hold",
            file=sys.stderr,
        )
        return version
    raise RuntimeError(
        f"mlx-lm {version} is not the pinned version "
        f"{SUPPORTED_MLXLM_VERSIONS}; refusing to launch without the "
        f"verified total-context cap (export {UNPINNED_ENV}=1 to override "
        "explicitly)"
    )


EXPECTED_TOKENIZE_SIGNATURE = ("self", "tokenizer", "request", "args")

TTFT_TRACE_ENV = "MLX_OMARCHY_TTFT_TRACE"
_ttft_armed = {"first_chunk": False}


def _ttft_trace(event: str, **fields) -> None:
    """One JSON line per request boundary when MLX_OMARCHY_TTFT_TRACE=1.

    Timestamps are time.monotonic() seconds, comparable across processes on
    one host; the assistant's ttft-phases.jsonl uses the same clock."""
    if os.environ.get(TTFT_TRACE_ENV) != "1":
        return
    fields["event"] = event
    fields["t"] = time.monotonic()
    print("[ttft] " + json.dumps(fields), flush=True)


def install(server_module, limit: int) -> None:
    generator = server_module.ResponseGenerator
    original = getattr(generator, "_tokenize", None)
    if not callable(original):
        raise RuntimeError(
            "mlx_lm.server.ResponseGenerator._tokenize not found; this shim "
            "does not know this mlx-lm version and refuses to launch without "
            "the total-context cap"
        )
    # Enforced for the pinned version AND any pin bypass: if the internals
    # moved, the cap cannot be proven to hold and the launch refuses.
    try:
        params = tuple(inspect.signature(original).parameters)
    except (TypeError, ValueError):
        params = ()
    if params != EXPECTED_TOKENIZE_SIGNATURE:
        raise RuntimeError(
            "unexpected _tokenize signature "
            f"{params} != {EXPECTED_TOKENIZE_SIGNATURE}; this shim does not "
            "know this mlx-lm build and refuses to launch without the "
            "verified total-context cap"
        )

    def capped(self, tokenizer, request, args):
        _ttft_t0 = time.monotonic()
        result = original(self, tokenizer, request, args)
        prompt = result[0]
        # Upstream semantics (verified in the pinned source): the HTTP
        # handler resolves max_tokens from the body or the CLI default
        # (an int, default 512) and validates int >= 0 BEFORE queuing, so
        # None or negatives never legitimately reach this boundary.
        # 0 generates nothing (bounded); -1 (infinite) is handler-blocked.
        max_tokens = getattr(args, "max_tokens", None)
        if max_tokens is None or isinstance(max_tokens, bool) \
                or not isinstance(max_tokens, int) or max_tokens < 0:
            raise ValueError(
                "request rejected: max_tokens must be a non-negative int at "
                f"the cap boundary, got {max_tokens!r}"
            )
        total = len(prompt) + max_tokens
        if total > limit:
            raise ValueError(
                f"request rejected: prompt ({len(prompt)} tokens) + max_tokens "
                f"({max_tokens}) exceeds the admitted context budget of {limit}; "
                "lower the prompt or max_tokens"
            )
        _ttft_armed["first_chunk"] = True
        _ttft_trace("tokenized", prompt=len(prompt), max_tokens=max_tokens,
                    tokenize_s=round(time.monotonic() - _ttft_t0, 3))
        return result

    generator._tokenize = capped


PROBE_ENV = "MLX_OMARCHY_SERVE_IDS_PROBE"


# ----------------------------------------------------------- speech yield gate
#
# Cooperative TTS scheduling between generation chunks (offline assistant
# design, "Recognition and synthesis"): the assistant coordinator must be able
# to run bounded speech synthesis on the GPU BETWEEN generation chunks instead
# of only after a whole response. Generation happens in this (separate mlx-lm)
# process, so a coordinator-side lock alone cannot stop it: without a real
# pause the server would keep decoding while the voice worker synthesizes —
# overlapping GPU generation and synthesis — and "not reading the SSE stream"
# is only a fake pause (TCP backpressure freezes the loop mid-flight, not at a
# token boundary).
#
# The gate therefore parks the pinned batched decode loop at a genuine chunk
# boundary: BatchGenerator.next() runs one full decode step synchronously and
# returns with every array materialized and all KV caches resident, so a block
# between steps is a GPU-idle boundary with state preserved. The coordinator
# only releases its GPU lock for synthesis AFTER a hold was acknowledged from
# inside this process ("held" means: no step running now and no step can start
# until release), so the no-overlap invariant is provable, not assumed. When
# the pause cannot be proven (unpatched single-path generation, parked-ack
# timeout, wrong secret), hold fails honestly and the assistant keeps today's
# busy rejection. Nothing is ever SIGSTOPed.

YIELD_CONTROL_PATH = "/v1/internal/yield"
YIELD_SECRET_HEADER = "X-MLX-Yield-Secret"
_ACTIVE_GATE: "YieldGate | None" = None
YIELD_HOLD_MAX_SECONDS = 600.0
YIELD_ACK_MAX_SECONDS = 30.0
EXPECTED_NEXT_SIGNATURE = ("self",)
EXPECTED_RUN_SIGNATURE = ("host", "port", "response_generator", "server_class",
                          "handler_class")


class YieldGate:
    """Hold/park state shared by the decode thread and the control route.

    State changes interlock under one condition so a hold can never be
    acknowledged while a decode step is starting: the step side sets
    ``in_step`` and checks ``desire`` in one atomic region, and the control
    side sets ``desire`` and checks ``in_step`` in the same region.
    """

    def __init__(self, hold_max_seconds: float = YIELD_HOLD_MAX_SECONDS):
        self._cond = threading.Condition()
        self._secret: str | None = None
        self._desire = False
        self._parked = False
        self._in_step = False
        self._closed = False
        self._hold_max_seconds = hold_max_seconds
        self.holds_granted = 0
        self.hold_timeouts = 0

    def bind_secret(self, secret) -> None:
        """Bind the secret presented by the current chat stream. Loopback
        trust: generation requests were never authenticated on this server;
        the secret only keeps browsers (no custom headers on simple
        cross-origin requests) and unrelated local tools from flipping the
        gate."""
        if not isinstance(secret, str) or not secret:
            return
        with self._cond:
            self._secret = secret

    def close(self) -> None:
        """Release a parked decode thread at shutdown."""
        with self._cond:
            self._closed = True
            self._desire = False
            self._cond.notify_all()

    def control(self, action, secret, ack_timeout) -> tuple[int, dict]:
        """Handle one control request; returns (http status, payload)."""
        with self._cond:
            if action == "probe":
                if self._secret is None and isinstance(secret, str) and secret:
                    self._secret = secret
                return 200, {"gate": True, "bound": self._secret is not None,
                             "secret_ok": isinstance(secret, str)
                             and secret == self._secret}
            if self._closed:
                return 503, {"error": "worker is shutting down"}
            if not isinstance(secret, str) or secret != self._secret:
                return 403, {"error": "yield secret mismatch"}
            if action == "hold":
                self._desire = True
                if self._in_step or self._parked:
                    deadline = time.monotonic() + min(
                        max(float(ack_timeout), 0.1), YIELD_ACK_MAX_SECONDS)
                    while not self._parked and not self._closed:
                        remaining = deadline - time.monotonic()
                        if remaining <= 0:
                            # Honest failure: no proven pause, no fake one.
                            self._desire = False
                            self.hold_timeouts += 1
                            self._cond.notify_all()
                            return 409, {"held": False,
                                         "reason": "park-ack-timeout"}
                        self._cond.wait(remaining)
                if self._closed:
                    self._desire = False
                    return 503, {"error": "worker is shutting down"}
                self.holds_granted += 1
                return 200, {"held": True}
            if action == "release":
                self._desire = False
                self._cond.notify_all()
                return 200, {"released": True}
            return 400, {"error": "action must be probe, hold or release"}

    # Decode-thread side (called from the wrapped BatchGenerator).
    def _before_step(self) -> None:
        with self._cond:
            self._in_step = True
            if not self._desire:
                return
            self._parked = True
            self._cond.notify_all()
            deadline = time.monotonic() + self._hold_max_seconds
            while self._desire and not self._closed:
                remaining = deadline - time.monotonic()
                if remaining <= 0:
                    # Crash net: an assistant that died mid-hold must not
                    # wedge generation forever. It only fires long after any
                    # bounded synthesis could legitimately take.
                    self._desire = False
                    self._cond.notify_all()
                    break
                self._cond.wait(remaining)
            self._parked = False
            self._cond.notify_all()

    def _after_step(self) -> None:
        with self._cond:
            self._in_step = False
            self._cond.notify_all()


def install_yield_gate(server_module, gate: YieldGate) -> None:
    """Wrap the pinned decode loop and HTTP handler with the yield gate.

    Refuses to launch when the pinned internals moved: an unverified hook
    could silently stop parking or park mid-step, so the shim refuses the
    same way it does for the context cap.
    """
    real_generator = server_module.BatchGenerator
    if getattr(real_generator, "_omarchy_yield_wrapped", False):
        return
    next_params = tuple(inspect.signature(real_generator.next).parameters)
    if next_params != EXPECTED_NEXT_SIGNATURE:
        raise RuntimeError(
            "unexpected BatchGenerator.next signature "
            f"{next_params} != {EXPECTED_NEXT_SIGNATURE}; this shim does not "
            "know this mlx-lm build and refuses to launch with the speech "
            "yield gate")
    run_fn = server_module._run_http_server
    run_params = tuple(inspect.signature(run_fn).parameters)
    if run_params != EXPECTED_RUN_SIGNATURE:
        raise RuntimeError(
            "unexpected _run_http_server signature "
            f"{run_params} != {EXPECTED_RUN_SIGNATURE}; this shim does not "
            "know this mlx-lm build and refuses to launch with the speech "
            "yield gate")

    class _GatedBatchGenerator:
        """Delegates everything; parks at genuine chunk boundaries."""
        _omarchy_yield_wrapped = True

        def __init__(self, *args, **kwargs):
            self._real = real_generator(*args, **kwargs)

        def __getattr__(self, name):
            return getattr(self._real, name)

        def next(self, *args, **kwargs):
            gate._before_step()
            try:
                result = self._real.next(*args, **kwargs)
                if _ttft_armed["first_chunk"]:
                    _ttft_armed["first_chunk"] = False
                    _ttft_trace("first_chunk")
                return result
            finally:
                gate._after_step()

    server_module.BatchGenerator = _GatedBatchGenerator

    base_handler = server_module.APIHandler

    class _GatedHandler(base_handler):
        def do_POST(self):  # noqa: N802 (stdlib API)
            path = self.path.split("?", 1)[0]
            if path == YIELD_CONTROL_PATH:
                return self._handle_yield_control()
            secret = self.headers.get(YIELD_SECRET_HEADER)
            if secret:
                gate.bind_secret(secret)
            return base_handler.do_POST(self)

        def _handle_yield_control(self):
            try:
                length = int(self.headers.get("Content-Length", 0))
                body = json.loads(self.rfile.read(length) or b"{}")
                if not isinstance(body, dict):
                    raise ValueError("body must be a JSON object")
            except (ValueError, OSError):
                self._yield_json(400, {"error": "invalid control body"})
                return
            status, payload = gate.control(
                body.get("action"), body.get("secret"),
                body.get("ack_timeout", YIELD_ACK_MAX_SECONDS))
            self._yield_json(status, payload)

        def _yield_json(self, status, payload):
            raw = json.dumps(payload).encode("utf-8")
            self.send_response(status)
            self.send_header("Content-Type", "application/json")
            self.send_header("Content-Length", str(len(raw)))
            self.end_headers()
            self.wfile.write(raw)

    def _run_with_gate(host, port, response_generator, server_class=None,
                       handler_class=None):
        return run_fn(host, port, response_generator,
                      server_class=server_class or server_module.ThreadingHTTPServer,
                      handler_class=_GatedHandler)

    server_module._run_http_server = _run_with_gate


def install_ids_probe(server_module, emit=None) -> None:
    """Bench-only ids capture for the managed route (default OFF; enabled
    only when MLX_OMARCHY_SERVE_IDS_PROBE=1). Wraps the streaming
    detokenizer classes so every raw sampled token id is recorded at the
    add_token boundary and the completed per-request id list is emitted as
    one `PROBE: {...}` JSON line on stderr at reset(). Nothing on disk is
    touched; with the env unset this function is never called."""
    if emit is None:
        def emit(event):
            print("PROBE:", json.dumps(event), file=sys.stderr, flush=True)
    state = {"ids": []}
    from mlx_lm.tokenizer_utils import (
        NaiveStreamingDetokenizer,
        BPEStreamingDetokenizer,
        SPMStreamingDetokenizer,
        StreamingDetokenizer,
    )

    def wrap(cls):
        if cls is None or getattr(cls, "_ids_probe_installed", False):
            return
        orig_add = getattr(cls, "add_token", None)
        if orig_add is None:
            return

        def add_token_probe(self, token, _orig=orig_add):
            state["ids"].append(int(token))
            _orig(self, token)

        cls.add_token = add_token_probe
        cls._ids_probe_installed = True

        orig_reset = getattr(cls, "reset", None)
        if orig_reset is not None:

            def reset_probe(self, _orig=orig_reset):
                if state["ids"]:
                    import hashlib
                    emit({"event": "generation", "n": len(state["ids"]),
                          "ids_sha16": hashlib.sha256(
                              json.dumps(state["ids"]).encode()).hexdigest()[:16],
                          "ids": state["ids"]})
                    state["ids"] = []
                return _orig(self)

            cls.reset = reset_probe

        # mlx_lm's stream_generate finalizes (never resets) at request end —
        # the server path's actual flush boundary (generate.py:741).
        orig_finalize = getattr(cls, "finalize", None)
        if orig_finalize is not None:

            def finalize_probe(self, _orig=orig_finalize):
                if state["ids"]:
                    import hashlib
                    emit({"event": "generation", "n": len(state["ids"]),
                          "ids_sha16": hashlib.sha256(
                              json.dumps(state["ids"]).encode()).hexdigest()[:16],
                          "ids": state["ids"]})
                    state["ids"] = []
                return _orig(self)

            cls.finalize = finalize_probe

    for cls in (StreamingDetokenizer, NaiveStreamingDetokenizer,
                BPEStreamingDetokenizer, SPMStreamingDetokenizer):
        wrap(cls)

    # Third capture site: the BATCHED branch (mlx_lm/server.py:884) feeds
    # generated tokens to the detokenizer via add_token but NEVER calls
    # reset/finalize — the batch flush boundary is BatchGenerator.remove
    # (finished uids) and close. With the managed CLI's decode_concurrency
    # of 1, the accumulated state at remove time is exactly the finished
    # request's token array.
    batch_cls = getattr(server_module, "BatchGenerator", None)

    def _flush_uids(uids=None):
        import hashlib
        store = state.get("by_uid", {})
        done = list(store) if not uids else [u for u in uids if u in store]
        for uid in done:
            ids = store.pop(uid)
            emit({"event": "generation", "n": len(ids),
                  "ids_sha16": hashlib.sha256(
                      json.dumps(ids).encode()).hexdigest()[:16],
                  "ids": ids})

    if batch_cls is not None and not getattr(batch_cls, "_ids_probe_flush",
                                             False):
        orig_next = getattr(batch_cls, "next", None)
        if orig_next is not None:
            # Primary batched capture: gen_responses carry (.uid, .token) —
            # accumulate per uid and emit each uid's array when the server
            # removes that uid (request completion).
            def next_probe(self, *_a, _orig=orig_next, **_k):
                prompt_responses, gen_responses = _orig(self, *_a, **_k)
                for r in gen_responses or []:
                    token = getattr(r, "token", None)
                    uid = getattr(r, "uid", None)
                    if token is None or uid is None:
                        continue
                    state.setdefault("by_uid", {}).setdefault(
                        uid, []).append(int(token))
                    # The server never resets the detokenizer on this route;
                    # flush a uid's array the moment its generation finishes.
                    if getattr(r, "finish_reason", None) is not None:
                        _flush_uids([uid])
                return prompt_responses, gen_responses
            batch_cls.next = next_probe

        orig_remove = getattr(batch_cls, "remove", None)
        if orig_remove is not None:
            def remove_probe(self, uids, _orig=orig_remove):
                _flush_uids(list(uids) if uids else None)
                return _orig(self, uids)
            batch_cls.remove = remove_probe
        else:
            orig_remove = None
        orig_close = getattr(batch_cls, "close", None)
        if orig_close is not None:
            def close_probe(self, _orig=orig_close):
                _flush_uids(None)
                return _orig(self)
            batch_cls.close = close_probe
        batch_cls._ids_probe_flush = True

    # Second, independent capture site: mlx_lm.server calls stream_generate
    # on the single-stream path (the managed CLI pins decode_concurrency=1,
    # so this is THE generation route). Collect each yielded response's
    # token and flush the per-request array when the generator exhausts —
    # independent of any detokenizer reset/finalize behavior.
    orig_stream = getattr(server_module, "stream_generate", None)
    if orig_stream is not None:
        def stream_probe(*args, **kwargs):
            gen = orig_stream(*args, **kwargs)
            print("shim: stream_probe ENTERED", file=sys.stderr, flush=True)
            count = 0
            while True:
                try:
                    item = next(gen)
                except StopIteration:
                    break
                token = getattr(item, "token", None)
                if token is not None:
                    state["ids"].append(int(token))
                    count += 1
                try:
                    yield item
                except GeneratorExit:
                    # Client disconnected mid-generation: flush what the
                    # request produced so partial arrays are recorded.
                    if count:
                        import hashlib
                        emit({"event": "generation_client_disconnected",
                              "n": len(state["ids"]),
                              "ids": state["ids"]})
                        state["ids"] = []
                    raise
            if count:
                import hashlib
                emit({"event": "generation", "n": len(state["ids"]),
                      "ids_sha16": hashlib.sha256(
                          json.dumps(state["ids"]).encode()).hexdigest()[:16],
                      "ids": state["ids"]})
                state["ids"] = []

        server_module.stream_generate = stream_probe


def main() -> None:
    raw = os.environ.get(LIMIT_ENV, "")
    try:
        limit = int(raw)
    except ValueError:
        print(f"error: {LIMIT_ENV} must be an integer, got {raw!r}", file=sys.stderr)
        raise SystemExit(3)
    if limit <= 0:
        print(f"error: {LIMIT_ENV} must be positive", file=sys.stderr)
        raise SystemExit(3)
    try:
        import mlx_lm.server as server_module
    except ImportError as exc:
        print(f"error: mlx_lm is not installed ({exc})", file=sys.stderr)
        raise SystemExit(3)
    check_pinned(server_module)
    install(server_module, limit)
    gate = None
    if getattr(server_module, "BatchGenerator", None) is not None and getattr(server_module, "_run_http_server", None) is not None:
        gate = YieldGate()
        globals()["_ACTIVE_GATE"] = gate
        install_yield_gate(server_module, gate)
    else:
        # No batched decode surface to park (stub servers, non-batched
        # builds): launch WITHOUT the gate. Assistant speak requests then
        # keep the honest busy refusal instead of a fake pause.
        print("warning: no BatchGenerator surface; speech yield gate disabled",
              file=sys.stderr)
    probe_wanted = os.environ.get(PROBE_ENV) == "1"
    print(f"shim: PROBE_ENV={os.environ.get(PROBE_ENV)!r} "
          f"installing={probe_wanted}", file=sys.stderr, flush=True)
    if probe_wanted:
        install_ids_probe(server_module)
        print("shim: ids probe installed", file=sys.stderr, flush=True)
    pct = getattr(server_module, "_process_control_tokens", None)
    if pct is not None and getattr(pct, "_omarchy_ttft_wrapped", False) is False:
        def traced_pct(ctx, token_stream, _orig=pct):
            stream = _orig(ctx, token_stream)
            first = True

            def traced():
                nonlocal first
                for gen in stream:
                    if first:
                        first = False
                        _ttft_trace("first_control_yield",
                                    buffer=max((len(s) for s in (ctx.sequences or ())),
                                               default=0))
                    yield gen
            return traced()

        traced_pct._omarchy_ttft_wrapped = True
        server_module._process_control_tokens = traced_pct
    # Serving placement (no root): raise uclamp_min on THIS startup thread
    # before the HTTP server and decode threads spawn, so every serving
    # thread inherits the P-cluster boost hint (stock governors). Silent
    # fallback: EPERM / old kernel / off switch -> serving is unchanged.
    try:
        from .perf_placement import apply_from_env
    except ImportError:
        from perf_placement import apply_from_env
    applied, detail = apply_from_env()
    print(f"shim: uclamp placement {'applied' if applied else 'skipped'} "
          f"({detail})", file=sys.stderr, flush=True)
    server_module.main()


if __name__ == "__main__":
    main()
