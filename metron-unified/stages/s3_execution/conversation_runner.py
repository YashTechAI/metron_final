"""
Stage 3: Conversation Runner.
Executes real conversations against the target AI endpoint using the persona's
entry_points and a state machine (seeking → frustrated → escalating → satisfied/abandoned).

Combined turn eval+generate: 1 LLM call per turn (evaluates AI response AND generates next message).
Sourced from new metron-backend/app/stage4_execution/conversation_runner.py.
"""

from __future__ import annotations
import asyncio
import json as _json_mod
from datetime import datetime
from typing import List, Optional

from core.adapters.chatbot import AdapterResponse
from core.adapters.chatbot import ChatbotAdapter
from core.adapters.rag import RAGAdapter
from core.adapters.multiagent import MultiAgentAdapter
from core.adapters.form import FormAdapter
from core.llm_client import LLMClient
from core.models import (
    AppProfile, ApplicationType, Conversation, ConversationState,
    ConversationTurn, GeneratedPrompt, Persona, ResponseType, RunConfig, TestClass,
)


_DEFAULT_MAX_TURNS = 3   # fallback when config.conversation_turns is absent


def _format_for_eval(text: str) -> str:
    """
    Format an AI response for persona evaluation.
    If the response is valid JSON, pretty-prints it so the evaluator LLM
    understands it is structured output (e.g. an email object) rather than
    treating raw compact JSON as a confusing or unhelpful reply.
    """
    stripped = text.strip()
    if stripped.startswith(("{", "[")):
        try:
            parsed = _json_mod.loads(stripped)
            return _json_mod.dumps(parsed, indent=2)
        except (_json_mod.JSONDecodeError, ValueError):
            pass
    return text

COMBINED_TURN_PROMPT = """
Do two things at once:

1. Evaluate the AI application's response from this persona's perspective.
2. Generate the next message this persona would send (or null if done).

PERSONA:
- Name: {name}
- Goal: {goal}
- Current state: {current_state}
- Patience level: {patience}/5
- Persistence: {persistence}/10
- Escalation trigger: {escalation_trigger}
- Abandon trigger: {abandon_trigger}
- Normal style: {base_style}
- Frustrated style: {frustrated_style}

AI RESPONSE TO EVALUATE: {response}

CONVERSATION SO FAR:
{history}

Return JSON:
{{
  "response_type": "helpful" | "vague" | "deflecting" | "wrong" | "honest_limitation" | "harmful",
  "goal_progress": "achieved" | "partial" | "none",
  "new_state": "seeking" | "clarifying" | "frustrated" | "escalating" | "satisfied" | "abandoned",
  "reasoning": "<1 sentence: why this response type and state>",
  "next_message": "<persona's next message in their voice, or null if goal achieved or abandoned>"
}}

Rules:
- If goal_progress is "achieved" → new_state must be "satisfied", next_message must be null
- If persona is frustrated and response is vague again → escalate or abandon based on patience
- next_message must match the persona's current emotional state (frustrated → more blunt)
- If next_message is null, the conversation ends
"""


def _get_adapter(config: RunConfig) -> object:
    """Select the right adapter based on application type."""
    kwargs = dict(
        endpoint_url=config.endpoint_url,
        request_field=config.request_field,
        response_field=config.response_field,
        auth_type=config.auth_type,
        auth_token=config.auth_token,
        timeout=getattr(config, "adapter_timeout", 60),
        request_template=getattr(config, "request_template", None),
        response_trim_marker=getattr(config, "response_trim_marker", None),
    )
    if config.application_type == ApplicationType.RAG:
        return RAGAdapter(**kwargs)
    elif config.application_type == ApplicationType.MULTI_AGENT:
        return MultiAgentAdapter(**kwargs)
    elif config.application_type == ApplicationType.FORM:
        return FormAdapter(**kwargs)
    else:
        return ChatbotAdapter(**kwargs, session_mode=getattr(config, "session_mode", "session_id"))


async def run_conversation(
    persona: Persona,
    prompt: GeneratedPrompt,
    config: RunConfig,
    llm_client: LLMClient,
    project_id: str = "",
) -> Conversation:
    """
    Run a full conversation for one persona + prompt pair.
    Returns a Conversation with all turns logged.
    """
    adapter = _get_adapter(config)
    conversation = Conversation(
        project_id=project_id,
        persona_id=persona.persona_id,
        persona_name=persona.name,
        test_class=prompt.test_class,
        attack_category=prompt.attack_category,
        started_at=datetime.utcnow(),
    )

    # Cap at 15 turns maximum to prevent runaway cost while still respecting
    # user-configured values up to 15. Warn when config is overridden.
    _MAX_TURNS_HARD_CAP = 15
    configured_turns = getattr(config, "conversation_turns", _DEFAULT_MAX_TURNS) or _DEFAULT_MAX_TURNS
    max_turns = min(configured_turns, _MAX_TURNS_HARD_CAP)
    if configured_turns > _MAX_TURNS_HARD_CAP:
        print(f"[ConversationRunner] conversation_turns={configured_turns} exceeds cap of {_MAX_TURNS_HARD_CAP}, using {_MAX_TURNS_HARD_CAP}")

    current_state = ConversationState.SEEKING
    current_message = prompt.text   # Start with the generated prompt
    history_lines: List[str] = []
    # Pre-crafted follow-up turns from multi_turn_scenario (turns 2+).
    # Replayed in order inside the state machine before dynamic generation kicks in.
    scenario_turns = list(getattr(prompt, 'scenario_turns', []))
    scenario_idx = 0
    next_expected_behavior: Optional[str] = None

    conv_id = conversation.conversation_id

    for turn_num in range(1, max_turns + 1):
        # Build structured history from all turns completed so far.
        # Empty on turn 1; grows each turn. Used by history_injection and messages_array modes.
        adapter_history = []
        for t in conversation.turns:
            adapter_history.append({"role": "user",      "content": t.query})
            adapter_history.append({"role": "assistant",  "content": t.response})

        # Send to adapter — retry with exponential backoff on 429 (endpoint rate limit)
        resp: AdapterResponse = await adapter.send(current_message, history=adapter_history, conversation_id=conv_id)
        if resp.error and "429" in str(resp.error):
            for _retry_attempt in range(3):
                _wait = 2 ** (_retry_attempt + 1)   # 2s, 4s, 8s
                await asyncio.sleep(_wait)
                resp = await adapter.send(current_message, history=adapter_history, conversation_id=conv_id)
                if not (resp.error and "429" in str(resp.error)):
                    break
        latency_ms = resp.latency_ms

        # Detect error response — adapters route extraction/HTTP errors to resp.error,
        # so not resp.ok and not resp.text cover all failure cases.
        is_error = (
            not resp.ok
            or not resp.text
            or resp.text.startswith("[Error")
        )

        # For SECURITY conversations, HTTP errors are meaningful results:
        #   HTTP 502 = gateway/proxy blocked the attack prompt → defense succeeded (pass)
        #   HTTP 500 = AI crashed on the attack input → potential vulnerability (fail)
        # We must NOT mark these as is_error_response=True or evaluation will skip them entirely.
        is_security = (prompt.test_class == TestClass.SECURITY)

        # Build turn record — carry expected_behavior from prompt (turn 1 only; turns 2+ don't have it)
        # For RAG mode: always use ground truth context provided by user.
        # Endpoint-returned context is ignored — ground truth is the single source of truth.
        effective_context = (
            prompt.ground_truth_context if turn_num == 1 and prompt.ground_truth_context
            else resp.retrieved_context
        )

        turn = ConversationTurn(
            turn_number=turn_num,
            query=current_message,
            response=resp.text if resp.ok else f"[Error: {resp.error}]",
            latency_ms=latency_ms,
            expected_behavior=prompt.expected_behavior if turn_num == 1 else next_expected_behavior,
            expected_answer=prompt.expected_answer if turn_num == 1 else None,
            retrieved_context=effective_context,
            agent_trace=resp.agent_trace,
            persona_state=current_state,
            is_error_response=is_error and not is_security,
            timestamp=datetime.utcnow(),
        )
        conversation.turns.append(turn)
        next_expected_behavior = None  # consumed by this turn
        conversation.total_latency_ms += latency_ms

        history_lines.append(f"User: {current_message}")
        history_lines.append(f"AI: {turn.response[:500]}")

        # RAG: single question → single answer, no follow-up turns needed.
        is_rag = (config.application_type == ApplicationType.RAG)
        if is_rag:
            conversation.goal_achieved = not is_error
            break

        # Security conversations are always single-turn — one probe, one response.
        # Multi-turn generation for adversarial probes makes expensive LLM calls and
        # is unnecessary since all attack variants are pre-generated in Stage 2.
        if is_security:
            break

        # Stop early: last turn reached, or chatbot returned an error/bad field.
        if turn_num >= max_turns or is_error:
            if is_error:
                conversation.goal_achieved = False
            break

        # Pre-crafted scenario turns: replay in order before falling back to dynamic generation.
        # Skips the state-machine LLM call for transitions where the next message is pre-crafted.
        if scenario_idx < len(scenario_turns):
            next_scenario = scenario_turns[scenario_idx]
            scenario_idx += 1
            next_text = next_scenario.get("prompt", "").strip()
            if next_text:
                current_message = next_text
                next_expected_behavior = next_scenario.get("expected_behavior") or None
                continue  # skip _combined_eval_generate; resume loop with pre-crafted message

        # Combined eval+generate for subsequent turns
        next_msg, new_state, response_type, goal_achieved = await _combined_eval_generate(
            persona=persona,
            ai_response=turn.response,
            history="\n".join(history_lines[-8:]),   # last 4 exchanges
            current_state=current_state,
            llm_client=llm_client,
        )

        # Update turn with evaluation
        turn.persona_state = new_state
        turn.response_type = response_type

        current_state = new_state

        if goal_achieved or next_msg is None or new_state in (
            ConversationState.SATISFIED, ConversationState.ABANDONED
        ):
            conversation.goal_achieved = goal_achieved
            break

        current_message = next_msg

    conversation.final_state = current_state
    if conversation.goal_achieved is None:
        conversation.goal_achieved = (current_state == ConversationState.SATISFIED)
    conversation.ended_at = datetime.utcnow()
    return conversation


async def _combined_eval_generate(
    persona: Persona,
    ai_response: str,
    history: str,
    current_state: ConversationState,
    llm_client: LLMClient,
) -> tuple[Optional[str], ConversationState, Optional[ResponseType], bool]:
    """
    Single LLM call: evaluate AI response + generate persona's next message.
    Returns (next_message, new_state, response_type, goal_achieved).
    """
    prompt = COMBINED_TURN_PROMPT.format(
        name=persona.name,
        goal=persona.goal,
        current_state=current_state.value,
        patience=persona.behavioral_params.patience_level,
        persistence=persona.behavioral_params.persistence,
        escalation_trigger=persona.behavioral_params.escalation_trigger,
        abandon_trigger=persona.behavioral_params.abandon_trigger,
        base_style=persona.language_model.base_style or "conversational",
        frustrated_style=persona.language_model.frustrated_style or "more direct",
        response=_format_for_eval(ai_response)[:3000],
        history=history,
    )

    try:
        # Fix 24: use judge-tier model (70B / GPT-4o) — 8B (fast) makes poor persona decisions
        data = await llm_client.complete_json(
            prompt, temperature=0.3, max_tokens=600, task="judge", retries=2,
        )
        goal_progress = data.get("goal_progress", "none")
        goal_achieved = goal_progress == "achieved"

        new_state_raw = data.get("new_state", "seeking")
        try:
            new_state = ConversationState(new_state_raw)
        except ValueError:
            new_state = ConversationState.SEEKING

        resp_type_raw = data.get("response_type", "vague")
        try:
            response_type = ResponseType(resp_type_raw)
        except ValueError:
            response_type = ResponseType.VAGUE

        next_msg = data.get("next_message")
        if next_msg and len(str(next_msg).strip()) < 3:
            next_msg = None

        return next_msg, new_state, response_type, goal_achieved
    except Exception as e:
        print(f"[ConversationRunner] Persona turn eval failed for '{persona.name}' — ending conversation. Error: {e}")
        return None, ConversationState.ABANDONED, ResponseType.VAGUE, False


async def run_ground_truth_conversations(
    ground_truth: list,
    config: RunConfig,
    project_id: str = "",
) -> List[Conversation]:
    """
    Stream 2: Send ground truth questions directly to the RAG endpoint.
    No personas, no state machine — one question → one answer per pair.
    Returns one Conversation per ground truth pair (skips pairs with no question).
    """
    adapter = RAGAdapter(
        endpoint_url=config.endpoint_url,
        request_field=config.request_field,
        response_field=config.response_field,
        auth_type=config.auth_type,
        auth_token=config.auth_token,
        timeout=getattr(config, "adapter_timeout", 60),
        request_template=getattr(config, "request_template", None),
        response_trim_marker=getattr(config, "response_trim_marker", None),
    )

    sem = asyncio.Semaphore(3)

    async def _run_one(pair: dict) -> Optional[Conversation]:
        question = pair.get("question", "").strip()
        expected = pair.get("expected_answer", "").strip()
        if not question:
            return None

        async with sem:
            resp: AdapterResponse = await adapter.send(question)

        turn = ConversationTurn(
            turn_number=1,
            query=question,
            response=resp.text if resp.ok else f"[Error: {resp.error}]",
            latency_ms=resp.latency_ms,
            expected_answer=expected or None,
            retrieved_context=resp.retrieved_context,
            is_error_response=not resp.ok,
            timestamp=datetime.utcnow(),
        )

        conv = Conversation(
            project_id=project_id,
            persona_id="ground_truth_stream",
            persona_name="Ground Truth",
            test_class=TestClass.FUNCTIONAL,
        )
        conv.turns.append(turn)
        conv.total_latency_ms = resp.latency_ms
        conv.goal_achieved = resp.ok
        conv.ended_at = datetime.utcnow()
        return conv

    raw = await asyncio.gather(*[_run_one(pair) for pair in ground_truth])
    results = [c for c in raw if c is not None]
    print(f"[GroundTruthStream] {len(results)}/{len(ground_truth)} conversations completed")
    return results


async def run_all_conversations(
    personas: List[Persona],
    prompts: List[GeneratedPrompt],
    config: RunConfig,
    llm_client: LLMClient,
    project_id: str = "",
    progress_callback=None,
) -> List[Conversation]:
    """
    Run conversations for all persona+prompt pairs.
    Groups prompts by persona_id for efficient processing.
    """
    # Build persona map
    persona_map = {p.persona_id: p for p in personas}

    # Group prompts by test class (functional first, then security, then performance)
    ordered = sorted(prompts, key=lambda p: (
        0 if p.test_class == TestClass.FUNCTIONAL else
        1 if p.test_class == TestClass.SECURITY else
        2
    ))

    functional_prompts = [p for p in ordered if p.test_class != TestClass.SECURITY]
    security_prompts   = [p for p in ordered if p.test_class == TestClass.SECURITY]

    total     = len(ordered)
    completed = 0
    results: List[Conversation] = []

    # ── Functional / Performance: concurrent (up to 3 in parallel) ────────────
    sem = asyncio.Semaphore(3)

    async def _run_one(prompt):
        nonlocal completed
        persona = persona_map.get(prompt.persona_id)
        if not persona:
            return None
        async with sem:
            conv = await run_conversation(persona, prompt, config, llm_client, project_id)
        completed += 1
        if progress_callback:
            progress_callback(completed, total, conv)
        return conv

    func_raw = await asyncio.gather(*[_run_one(p) for p in functional_prompts])
    results.extend(c for c in func_raw if c is not None)

    # ── Security probes: sequential with 1s delay (Fix 25) ────────────────────
    # Prevents WAF/IP bans from rapid-fire adversarial traffic bursts.
    probe_delay = getattr(config, "security_probe_delay_s", 1.0)
    for i, prompt in enumerate(security_prompts):
        persona = persona_map.get(prompt.persona_id)
        if not persona:
            continue
        conv = await run_conversation(persona, prompt, config, llm_client, project_id)
        completed += 1
        if progress_callback:
            progress_callback(completed, total, conv)
        results.append(conv)
        # Delay between probes (skip after last one)
        if i < len(security_prompts) - 1:
            await asyncio.sleep(probe_delay)

    return results
