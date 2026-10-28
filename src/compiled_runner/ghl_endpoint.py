"""
Generic GHL webhook -> compiled LangGraph agent -> GHL reply endpoint.

    Every compiled agent wired to a real GHL webhook needs the exact same
    plumbing (202 immediately, per-thread debounce, session resolution with
    the terminal-state fix, run_in_threadpool for the graph.invoke() deadlock,
    idempotency by execution_id, reply via send_ghl_message_async, mirror the
    turn into `conversations`). Only the agent identity, phone allowlist, and
    debounce window differ -- see family_aims_sam_text/endpoint.py's own
    docstring for the diagnosis behind each of the fixes baked in here. One
    agent's endpoint module is now just a `CompiledAgentGhlConfig` plus a call
    to `build_compiled_agent_router` instead of duplicating this file.
"""

from __future__ import annotations

import asyncio
import logging
import os
from dataclasses import dataclass, field
from typing import Any, Callable

from fastapi import APIRouter, status
from langgraph.types import Command
from starlette.concurrency import run_in_threadpool

from agent_compiler.runtime.graph_builder import fresh_state
import httpx
from agent_compiler.runtime.session_resolver import resolve_session
from agents.helpers.ghl import GhlClientConfig, search_conversation_channel_async, send_ghl_message_async
from agents.helpers.text import normalize_channel
from agents.helpers.ghl_request import GhlAgentRequest
from agents.helpers.runner import derive_execution_id
from compiled_runner.loader import load_compiled_agent, message_buffer
from compiled_runner.postgres import (
    claim_conversations_needing_closing_message,
    reset_closing_message_claim,
    mark_closing_message_sent,
    postgres_enabled,
    upsert_conversation,
)


@dataclass(frozen=True)
class CompiledAgentGhlConfig:
    """
Everything that differs from one compiled agent's GHL endpoint to another.
"""

    slug: str
    """Must match a folder under compiled_agents/."""
    path: str
    """Route path, e.g. "/sam_text" -> mounted as POST {path}."""
    allowed_phones: frozenset[str]
    """Normalized (no spaces/dashes/parens) E.164 numbers this pilot accepts.
    Ignored entirely when `enforce_phone_whitelist` is False."""
    debounce_seconds: float
    ghl_client_config: Callable[[], GhlClientConfig]
    """Returns the GhlClientConfig to send replies with -- typically reuses
    an existing agent.json's ghl/runtime/messaging sections (base_url,
    token env var, channel map -- none of that is agent-specific)."""
    enforce_phone_whitelist: bool = True
    """Kill switch for the pilot gate, per agent -- False lets every phone
    through regardless of `allowed_phones` (e.g. once an agent is cleared
    to go live). Defaults to True so an agent stays gated unless a caller
    explicitly opts out; see each agent's own text.py for the .env var
    that drives this (load_phone_whitelist's own docstring)."""
    closing_message_lookback_days: float = 3.0
    """How many days back `run_closing_sweep_once` still considers a
    candidate -- a safety bound, not the trigger itself (that's always
    ~23h45m of inactivity, see postgres.CLOSING_MESSAGE_INACTIVITY_THRESHOLD,
    a WhatsApp platform constant, not a per-agent choice). Guards against a
    sweep that was down for a while suddenly messaging contacts from
    long-dead conversations once it catches back up. One .env var per
    agent, same pattern as debounce_seconds -- see each agent's own
    text.py."""
    closing_message: "str | dict[str, str] | None" = None
    """Override for the text sent by the closing sweep. A plain string
    always wins; a dict is looked up by the thread's preferred_language
    (falls back to the built-in ES/EN/PT default). None uses the built-in
    default entirely -- deliberately generic ("puede ser de cualquiera"),
    since the sweep's only job is to get *something* out before Meta's 24h
    window closes, not to carry flow-specific content."""
    redirect_widget_to_whatsapp: bool = True
    """(2026-10-02, pedido directamente) If True, an inbound message from
    the widget (LIVE_CHAT) is responded to via WhatsApp instead. Enabled
    by default; el widget solo se usa para el primer contacto."""
    unsupported_media_message: "str | dict[str, str] | None" = None
    """Override for the reply sent when a message arrives with no text (a
    video, audio or sticker reaches GHL with an empty body) in the middle of
    a conversation. Same shape as `closing_message`: a plain string always
    wins; a dict is looked up by the conversation's language (falls back to
    the built-in ES/EN/PT default). The graph is not invoked, so the pending
    question stays pending."""
    turn_lock_timeout_seconds: float = field(
        default_factory=lambda: float(os.getenv("GHL_TURN_LOCK_TIMEOUT_SECONDS", "60"))
    )
    """Longest a flushed turn waits for the previous turn of the same conversation to finish before
    running anyway. Turns of one conversation run one at a time, so a message that arrives while the
    agent is still answering (a slow availability check, say) is answered after it, from the state
    that turn left, instead of racing it on the same checkpoint. The limit only exists so a hung turn
    cannot block the conversation forever. Same default for every agent; override per agent here or
    for all with GHL_TURN_LOCK_TIMEOUT_SECONDS."""


_DEFAULT_CLOSING_MESSAGES: dict[str, str] = {
    "es": "Gracias por contactarte con nosotros. Si tienes alguna otra pregunta, no dudes en escribirnos. ¡Que tengas un buen día!",
    "en": "Thank you for reaching out to us. If you have any other questions, feel free to write to us anytime. Have a great day!",
    "pt": "Obrigado por entrar em contato conosco. Se tiver mais alguma pergunta, não hesite em nos escrever. Tenha um ótimo dia!",
}


def _closing_message_text(cfg: CompiledAgentGhlConfig, preferred_language: "str | None") -> str:
    if isinstance(cfg.closing_message, str):
        return cfg.closing_message
    messages = cfg.closing_message if isinstance(cfg.closing_message, dict) else _DEFAULT_CLOSING_MESSAGES
    lang = (preferred_language or "es").lower()
    return messages.get(lang) or messages.get("es") or next(iter(messages.values()))


_DEFAULT_UNSUPPORTED_MEDIA_MESSAGES: dict[str, str] = {
    "es": "No pude entender ese mensaje. Por ahora solo puedo responderte por texto.",
    "en": "I couldn't understand that message. For now I can only reply to text.",
    "pt": "Não consegui entender essa mensagem. Por enquanto só posso responder por texto.",
}

_LANGUAGE_CODES = {"spanish": "es", "english": "en", "portuguese": "pt"}


def _unsupported_media_text(cfg: CompiledAgentGhlConfig, language: "str | None") -> str:
    if isinstance(cfg.unsupported_media_message, str):
        return cfg.unsupported_media_message
    messages = (
        cfg.unsupported_media_message
        if isinstance(cfg.unsupported_media_message, dict)
        else _DEFAULT_UNSUPPORTED_MEDIA_MESSAGES
    )
    raw = (language or "es").strip().lower()
    code = _LANGUAGE_CODES.get(raw, raw)
    return messages.get(code) or messages.get("es") or next(iter(messages.values()))


def _normalize_phone(raw: object) -> str:
    return str(raw or "").replace(" ", "").replace("-", "").replace("(", "").replace(")", "")


# Manual-testing reset marker (2026-09-29, pedido directamente): the classic
# /sam agent had its own version of this ("</>", see agents/helpers/history.py
# ::DEFAULT_RESET_MARKER), but it's not going to be used going forward and,
# separately, never actually matched anyway -- a real GHL/WhatsApp payload
# sends "<\>" (one literal backslash), confirmed live against the exact
# payload shared this session, not "</>" (forward slash). sam_text doesn't
# share any code with that agent (never calls agents.helpers.runner or
# apply_reset_marker -- its "memory" is the LangGraph checkpoint, not
# re-fetched GHL history), so this is its own, independent mechanism.
# Three spellings accepted, so a tester doesn't have to remember which one
# actually reaches the LLM unmangled: "<\>" (what a real payload sends),
# "<\\>" (two backslashes -- what typing the JSON-escaped form seen in a
# logged payload literally into WhatsApp produces), and "</>" (forward
# slash, kept for muscle memory from the classic agent's own marker).
_RESET_MARKERS = ("<\\>", "<\\\\>", "</>")


def _strip_reset_marker(message: str) -> tuple[str, bool]:
    """
If `message` starts with a reset marker (either slash direction,

    see _RESET_MARKERS), returns (message with the marker removed, True).
        Otherwise returns (message unchanged, False). Whitespace around the
        marker is ignored on both sides.

    Parameters:
        message: Description.

    Returns:
        The result.
"""
    stripped = message.lstrip()
    for marker in _RESET_MARKERS:
        if stripped.startswith(marker):
            return stripped[len(marker):].strip(), True
    return message, False


GHL_TEXT_HISTORY_MAX_DAYS = float(os.getenv("GHL_TEXT_HISTORY_MAX_DAYS", "7"))
"""Shared across every text agent wired here (2026-09-29, pedido directamente)
-- unlike debounce_seconds/closing_message_lookback_days, this is deliberately
ONE .env var for all of them, not one per agent. How many days of inactivity
before resolve_session treats the next inbound message as a brand-new
conversation instead of resuming the existing one.

Previously this was each agent's own compiled session_timeout_minutes
(manifest.yaml -- content, requires a recompile to change). This env var is
now the authoritative source for the real GHL webhook pipeline (_run_turn
below); each agent's own artifact.session_timeout_minutes is left as-is in
the DSL and still governs compiled_runner/endpoint.py's generic test-chat
tool, which isn't text-agent-specific and has nothing to do with GHL."""

GHL_TEXT_SESSION_TIMEOUT_MINUTES = GHL_TEXT_HISTORY_MAX_DAYS * 24 * 60


_FALSE_STRINGS = {"0", "false", "no", "off"}


def load_phone_whitelist(
    list_env_var: str, enforce_env_var: str, default_phones: str = ""
) -> tuple[frozenset[str], bool]:
    """
Reads one agent's phone pilot gate from two .env vars, instead of a

    hardcoded frozenset in that agent's own text.py -- moved here 2026-09-29
        so the actual numbers (and whether the gate applies at all) can change
        without touching code or redeploying.

        `list_env_var`: comma-separated E.164 numbers, e.g.
            "+573215616921,+573007011593". Spaces around commas are trimmed;
            each number is normalized the same way an inbound request's phone
            is (see _normalize_phone) so formatting differences never cause a
            silent mismatch.
        `enforce_env_var`: "true"/"false" (also accepts 1/0, yes/no, on/off,
            case-insensitive). Defaults to enforcing (True) if unset or
            unrecognized -- an agent stays gated unless a caller explicitly
            opts out, never the other way around by accident. This is the
            switch to flip when an agent is cleared to go live: set it to
            false and every phone gets through, no code change needed.
        `default_phones`: used only if `list_env_var` isn't set in .env at all
            -- lets a caller keep working with zero .env setup, same as
            before this moved out of hardcoded Python.

    Parameters:
        list_env_var: Description.
        enforce_env_var: Description.
        default_phones: Description.

    Returns:
        The result.
"""
    raw_phones = os.getenv(list_env_var, default_phones)
    phones = frozenset(_normalize_phone(p) for p in raw_phones.split(",") if p.strip())

    raw_enforce = os.getenv(enforce_env_var, "true").strip().lower()
    enforce = raw_enforce not in _FALSE_STRINGS  # anything unrecognized defaults to enforcing, not open

    return phones, enforce


@dataclass
class _PendingTurn:
    """
Text accumulated for one thread_id, waiting out the debounce window.
"""

    execution_ids: list[str] = field(default_factory=list)
    message_parts: list[str] = field(default_factory=list)
    last_request: object = None
    flush_task: "asyncio.Task | None" = None


async def run_closing_sweep_once(cfg: CompiledAgentGhlConfig) -> int:
    """
One pass: find every thread of `cfg.slug` sitting at 23:45+ of

    inactivity with no closing message sent yet for this window, and send
        one. Module-level (not a closure inside build_compiled_agent_router)
        so it's directly testable/callable without spinning up the router.

        Deliberately bypasses the compiled graph entirely -- there's no new
        user message to run it against, and the message is intentionally
        generic (see CompiledAgentGhlConfig.closing_message's own docstring),
        so a direct send_ghl_message_async call is simpler and correct.

        Returns how many closing messages were actually sent (tests read this;
        production code doesn't need to).

    Parameters:
        cfg: Description.

    Returns:
        The result.
"""
    logger = logging.getLogger(f"compiled_runner.ghl_endpoint.{cfg.slug}")
    # Atomically claim candidates to avoid duplicate sends across processes
    candidates = await run_in_threadpool(
        claim_conversations_needing_closing_message, cfg.slug, cfg.closing_message_lookback_days
    )
    sent = 0
    for row in candidates:
        thread_id = row["thread_id"]
        try:
            # If conversation was widget and the agent is configured
            # to redirect, send closing message via WhatsApp (2026-09-30)
            reply_channel = row.get("channel")
            if cfg.redirect_widget_to_whatsapp:
                ch = normalize_channel(reply_channel)
                if ch in {"LIVE_CHAT", "WEBCHAT", "TYPE_WEBCHAT"}:
                    reply_channel = "WHATSAPP"

            # Send directly; if GHL rejects (e.g., missing contact/conversation),
            # we'll catch the error and release the claim below.
            await send_ghl_message_async(
                contact_id=row["contact_id"],
                message=_closing_message_text(cfg, row.get("preferred_language")),
                channel=reply_channel,
                exec_id=f"{cfg.slug}:closing:{thread_id}",
                config=cfg.ghl_client_config(),
                location_id=row["location_id"],
                logger=logger,
            )
            logger.info("[%s] Closing message sent after ~24h of inactivity.", thread_id)
            sent += 1
        except httpx.HTTPStatusError as exc:
            code = exc.response.status_code if exc.response is not None else None
            canonical = None
            try:
                canonical = (exc.response.json() if exc.response is not None else {}).get("canonicalCode")
            except Exception:
                canonical = None
            if code == 400 and canonical == "CONVERSATIONS_CONTACT_NOT_FOUND":
                logger.warning(
                    "[%s] Skipping closing message: contact not found (400, canonical=%s).",
                    thread_id,
                    canonical,
                )
                # Do not retry this window: mark as sent to suppress future picks
                try:
                    await run_in_threadpool(
                        mark_closing_message_sent, cfg.slug, row["location_id"], row["contact_id"]
                    )
                except Exception:
                    logger.warning(
                        "[%s] Failed to mark closing message sent after contact-missing (non-fatal).",
                        thread_id,
                        exc_info=True,
                    )
            else:
                logger.error("[%s] Failed to send closing message.", thread_id, exc_info=True)
                # Allow a future sweep to retry: clear claim
                try:
                    await run_in_threadpool(
                        reset_closing_message_claim, cfg.slug, row["location_id"], row["contact_id"]
                    )
                except Exception:
                    logger.warning(
                        "[%s] Failed to reset closing message claim after send error (non-fatal).",
                        thread_id,
                        exc_info=True,
                    )
        except Exception:
            logger.error("[%s] Failed to send closing message.", thread_id, exc_info=True)
            try:
                await run_in_threadpool(
                    reset_closing_message_claim, cfg.slug, row["location_id"], row["contact_id"]
                )
            except Exception:
                logger.warning(
                    "[%s] Failed to reset closing message claim after send error (non-fatal).",
                    thread_id,
                    exc_info=True,
                )
    return sent


async def _closing_sweep_loop(cfg: CompiledAgentGhlConfig) -> None:
    logger = logging.getLogger(f"compiled_runner.ghl_endpoint.{cfg.slug}")
    interval_seconds = float(os.getenv("CLOSING_MESSAGE_SWEEP_INTERVAL_SECONDS", "300"))
    startup_delay = float(os.getenv("CLOSING_MESSAGE_SWEEP_STARTUP_DELAY_SECONDS", "10"))
    # Give the app a brief window to handle first user messages on cold start
    # before the sweep kicks in (avoids contention in serverless environments).
    if startup_delay > 0:
        try:
            await asyncio.sleep(startup_delay)
        except asyncio.CancelledError:
            return
    while True:
        try:
            await run_closing_sweep_once(cfg)
        except Exception:
            logger.error("Closing-message sweep iteration failed.", exc_info=True)
        await asyncio.sleep(interval_seconds)


async def resolve_reply_channel(
    request: GhlAgentRequest,
    remembered: "str | None",
    config: GhlClientConfig,
    logger: logging.Logger,
) -> "str | None":
    """
    The channel a reply goes out through. A payload without message.type (the one a workflow
    sends when the contact is created by their first message) carries no channel, and a reply
    with none falls to the default Live_Chat. Order: the payload, the last channel seen on this
    thread, the contact's conversation in GHL, then a WhatsApp attribution medium. When none is
    usable the payload's own value is returned and the default applies.
    """

    def usable(channel: "str | None") -> bool:
        return normalize_channel(channel) in config.channel_type_map

    channel = request.channel
    if not usable(channel):
        channel = remembered
    if not usable(channel):
        channel = await search_conversation_channel_async(request.contact_id, request.location_id, config, logger)
    if not usable(channel):
        contact = request.contact or {}
        sources = (contact.get("lastAttributionSource"), contact.get("attributionSource"))
        if any(isinstance(src, dict) and normalize_channel(src.get("medium")) == "WHATSAPP" for src in sources):
            channel = "WHATSAPP"
    return channel if usable(channel) else request.channel


def build_compiled_agent_router(cfg: CompiledAgentGhlConfig) -> APIRouter:
    """
Build a self-contained router for one compiled agent's GHL webhook.

    State (processing_messages, pending turns) is local to this call, so
        two agents built from this factory never share or race on each
        other's in-flight messages, even though the shapes are identical.

    Parameters:
        cfg: Description.

    Returns:
        The result.
"""
    router = APIRouter()
    logger = logging.getLogger(f"compiled_runner.ghl_endpoint.{cfg.slug}")

    processing_messages: set[str] = set()
    pending_turns: dict[str, _PendingTurn] = {}
    turn_locks: dict[str, asyncio.Lock] = {}
    known_channels: dict[str, str] = {}

    async def _resolve_channel(request: GhlAgentRequest, thread_id: str, execution_id: str) -> "str | None":
        channel = await resolve_reply_channel(request, known_channels.get(thread_id), cfg.ghl_client_config(), logger)
        if normalize_channel(channel) and normalize_channel(request.channel) != normalize_channel(channel):
            logger.info("[%s] Payload had no usable channel (%r); replying through %s.", execution_id, request.channel, channel)
        if normalize_channel(channel) in cfg.ghl_client_config().channel_type_map:
            known_channels[thread_id] = channel
        return channel

    # Not a locally-scoped subclass: with `from __future__ import
    # annotations`, FastAPI resolves a parameter's type hint by name from
    # the function's __globals__ at route-registration time -- a class
    # defined inside this factory function isn't reachable that way, so
    # `request` silently fell back to being treated as a query param
    # instead of the JSON body (found live: every call 422'd on "request
    # missing"). GhlAgentRequest is already generic across agents, so
    # there's nothing a subclass would add here anyway.
    @router.post(cfg.path, status_code=status.HTTP_202_ACCEPTED)
    async def endpoint(request: GhlAgentRequest):
        phone = _normalize_phone((request.contact or {}).get("phone"))
        if cfg.enforce_phone_whitelist and phone not in cfg.allowed_phones:
            logger.info("Ignoring message from non-allowed phone: %s", phone)
            return {"status": "ignored", "reason": "phone_not_allowed"}

        if not request.location_id or not request.contact_id:
            logger.warning("Missing location_id/contact_id, dropping request.")
            return {"status": "ignored", "reason": "missing_ids"}

        execution_id = derive_execution_id(request, prefix=cfg.slug)
        logger.info(
            "[%s] Received request: conversation_id=%s contact_id=%s location_id=%s",
            execution_id,
            request.conversation_id,
            request.contact_id,
            request.location_id,
        )

        if execution_id in processing_messages:
            logger.info("[%s] Already processing/processed, skipping.", execution_id)
            return {"status": "duplicate", "execution_id": execution_id}
        processing_messages.add(execution_id)

        # Prefixed with the agent slug: makes "which agent is this" visible
        # at a glance in a shared Postgres, and keeps two different agents
        # talking to the same contact from colliding on the exact same
        # thread_id and corrupting each other's state.
        thread_id = f"{cfg.slug}:{request.location_id}:{request.contact_id}"
        turn = pending_turns.get(thread_id)
        if turn is None:
            turn = _PendingTurn()
            pending_turns[thread_id] = turn
        elif turn.flush_task is not None:
            turn.flush_task.cancel()

        turn.execution_ids.append(execution_id)
        if request.message:
            turn.message_parts.append(str(request.message))
        turn.last_request = request
        turn.flush_task = asyncio.create_task(_debounced_flush(thread_id))

        return {"status": "accepted", "execution_id": execution_id, "debounce_seconds": cfg.debounce_seconds}

    async def _debounced_flush(thread_id: str) -> None:
        try:
            await asyncio.sleep(cfg.debounce_seconds)
            # The turn stays pending while it waits for the conversation's previous turn:
            # a message that arrives meanwhile is merged into it (and restarts this flush).
            lock = turn_locks.setdefault(thread_id, asyncio.Lock())
            holds_lock = False
            try:
                await asyncio.wait_for(lock.acquire(), timeout=cfg.turn_lock_timeout_seconds)
                holds_lock = True
            except asyncio.TimeoutError:
                logger.warning(
                    "[%s] Previous turn still running after %ss; running this one anyway.",
                    thread_id,
                    cfg.turn_lock_timeout_seconds,
                )
        except asyncio.CancelledError:
            return  # a newer message reset the timer -- this flush is stale

        try:
            turn = pending_turns.pop(thread_id, None)
            if turn is None:
                return
            await _run_turn(thread_id, turn)
        finally:
            if holds_lock:
                lock.release()
            if not lock.locked() and thread_id not in pending_turns and turn_locks.get(thread_id) is lock:
                turn_locks.pop(thread_id, None)

    async def _run_turn(thread_id: str, turn: _PendingTurn) -> None:
        request = turn.last_request
        combined_message = "\n".join(turn.message_parts).strip()
        combined_message, reset_requested = _strip_reset_marker(combined_message)
        execution_id = turn.execution_ids[-1]
        logger.info("[%s] Combined inbound length=%s part_count=%s", execution_id, len(combined_message), len(turn.message_parts))
        if len(turn.execution_ids) > 1:
            logger.info(
                "[%s] Flushing %s buffered message(s) for thread=%s after %ss of inactivity.",
                execution_id,
                len(turn.execution_ids),
                thread_id,
                cfg.debounce_seconds,
            )

        try:
            config = {"configurable": {"thread_id": thread_id}}
            artifact, graph = load_compiled_agent(cfg.slug)

            buffer: list[str] = []
            message_buffer.set(buffer)

            snapshot = graph.get_state(config)
            resolution = resolve_session(snapshot.values, GHL_TEXT_SESSION_TIMEOUT_MINUTES)
            if resolution == "continuing" and not (snapshot.next or snapshot.interrupts):
                # resolve_session only knows elapsed time, not whether the
                # graph actually has a pending interrupt -- a thread that
                # already reached a terminal node (snapshot.next == ()) has
                # nothing to resume, so Command(resume=...) would silently
                # do nothing. Treat this as the start of a fresh conversation.
                # A question that re-asks itself after a global-router match
                # (e.g. a language switch) is pending in snapshot.interrupts
                # while snapshot.next is already empty -- that one resumes.
                resolution = "new"
            if reset_requested:
                resolution = "new"
                logger.info("[%s] Reset marker detected -- forcing a fresh conversation.", execution_id)
            logger.info("[%s] thread=%s session=%s", execution_id, thread_id, resolution)

            # graph.invoke() is synchronous and blocking; a tool call this
            # graph makes (e.g. check_visa) hits this same server over HTTP,
            # so it must run off the event loop or that self-call deadlocks
            # against the frozen loop until the tool's own timeout kills it.
            if resolution in ("new", "stale"):
                state = fresh_state(
                    artifact,
                    contact=request.contact,
                    seed_history=[f"user: {combined_message}"] if combined_message else [],
                    seed_last_user_message=combined_message,
                )
                result = await run_in_threadpool(graph.invoke, state, config)
            else:
                if not combined_message:
                    # No text mid-conversation: a video, audio or sticker. Answer with the fixed
                    # message and leave the graph (and its pending question) untouched.
                    slots = (snapshot.values or {}).get("slots") or {}
                    language = slots.get("preferred_language") or (request.contact or {}).get("language")
                    buffer.append(_unsupported_media_text(cfg, language))
                    result = {}
                else:
                    result = await run_in_threadpool(graph.invoke, Command(resume=combined_message), config)

            interrupts = result.get("__interrupt__")
            if interrupts:
                buffer.extend(interrupts[0].value.get("prompt", []))

            final_state = graph.get_state(config).values
            channel = await _resolve_channel(request, thread_id, execution_id)
            upsert_conversation(
                thread_id=thread_id,
                agent_slug=cfg.slug,
                location_id=request.location_id,
                contact_id=request.contact_id,
                contact=final_state.get("contact"),
                slots=final_state.get("slots"),
                current_state=final_state.get("current_state"),
                last_user_message=final_state.get("last_user_message"),
                history=final_state.get("history"),
                channel=channel,
            )

            reply_text = "\n\n".join(buffer).strip()
            if reply_text:
                # If message came from widget and the agent is configured,
                # respond via WhatsApp (2026-09-30). Accept common synonyms.
                reply_channel = channel
                if cfg.redirect_widget_to_whatsapp:
                    ch = normalize_channel(reply_channel)
                    if ch in {"LIVE_CHAT", "WEBCHAT", "TYPE_WEBCHAT"}:
                        logger.info(
                            "[%s] Inbound channel was widget (%s), redirecting reply to WHATSAPP.",
                            execution_id,
                            ch,
                        )
                        reply_channel = "WHATSAPP"

                await send_ghl_message_async(
                    contact_id=request.contact_id,
                    message=reply_text,
                    channel=reply_channel,
                    exec_id=execution_id,
                    config=cfg.ghl_client_config(),
                    location_id=request.location_id,
                    reply_message_id=request.messageId,
                    logger=logger,
                )
                logger.info("[%s] Reply sent to GHL.", execution_id)
            else:
                logger.info(
                    "[%s] No reply text (empty buffer). resolution=%s combined_len=%s interrupts=%s",
                    execution_id,
                    resolution,
                    len(combined_message),
                    bool(interrupts),
                )

        except Exception:
            logger.error("[%s] Background execution failed.", execution_id, exc_info=True)
        finally:
            for eid in turn.execution_ids:
                processing_messages.discard(eid)

    @router.on_event("startup")
    async def _start_closing_sweep() -> None:
        if postgres_enabled():
            asyncio.create_task(_closing_sweep_loop(cfg))

    return router
