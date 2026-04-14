"""
AI Router — Lightweight model routing for Claude Code.

Usage:
    from ai_router import route, verify, query, get_costs, print_cost_report

    # Route a task to the best model automatically
    # (if the task type is in auto_verify_task_types, verification happens
    #  automatically and the result includes verifier feedback)
    result = route(
        content="Review this code for security issues:\n```python\n...\n```",
        task_type="code-review",
        context="This is a Flask web app handling user authentication.",
        complexity_hint=None  # optional 1-100 override
    )
    print(result.content)
    print(f"Cost: ${result.total_cost_usd:.4f} via {result.model_name}")
    if result.verification:
        print(f"Verified by: {result.verification.verifier_model}")
        print(f"Verdict: {result.verification.verdict}")

    # Explicitly verify any result (even if not auto-verified)
    result = route(content="...", task_type="documentation")
    check = verify(result)
    print(check.verdict)        # "VERIFIED" or "ISSUES_FOUND"
    print(check.issues)         # list of issues if any

    # Force a specific model
    result = query(
        model="gemini-flash",
        content="Reformat this JSON:\n...",
        task_type="formatting"
    )

    # Get cost report (includes verification costs)
    costs = get_costs()
    print_cost_report()

Session logging is handled externally by the caller (Claude Code) via
the SessionLog class:

    from ai_router.session_log import SessionLog

    log = SessionLog("docs/session-sets/my-feature")
    log.log_step(session_number=1, step_number=1, ...)
"""

from .config import load_config
from .models import estimate_complexity, pick_model
from .providers import call_model
from .prompting import build_prompt
from .rate_limiter import RateLimiter
from .session_log import SessionLog
from .escalation import should_escalate, get_escalation_model
from .verification import (
    pick_verifier_model, build_verification_prompt,
    parse_verification_response
)

from dataclasses import dataclass, field
from typing import Optional
import time
import os

# Module-level singletons, initialized on first call
_config = None
_rate_limiters = {}


def _init():
    global _config, _rate_limiters
    if _config is None:
        config_path = os.environ.get("AI_ROUTER_CONFIG")  # None → uses __file__-relative default
        _config = load_config(config_path)
        for provider_name, provider_cfg in _config["providers"].items():
            _rate_limiters[provider_name] = RateLimiter(
                provider_cfg["rate_limit"]["requests_per_minute"],
                provider_cfg["rate_limit"]["tokens_per_minute"]
            )


@dataclass
class VerificationResult:
    verdict: str               # "VERIFIED" or "ISSUES_FOUND"
    verified: bool             # True if verdict == "VERIFIED"
    issues: list               # list of issue dicts if any
    verifier_model: str        # which model verified
    verifier_provider: str     # which provider (for cross-provider confirmation)
    generator_model: str       # which model generated the original
    generator_provider: str    # which provider generated the original
    verifier_input_tokens: int
    verifier_output_tokens: int
    verifier_cost_usd: float
    raw_response: str          # full verifier response text


@dataclass
class RouteResult:
    content: str
    model_name: str
    model_id: str
    tier: int
    input_tokens: int
    output_tokens: int
    cost_usd: float            # cost of the generation call only
    total_cost_usd: float      # generation + verification combined
    complexity_score: int
    escalated: bool
    escalation_history: list   # [(model, reason), ...]
    elapsed_seconds: float
    verification: Optional[VerificationResult] = None  # populated if verified


def route(
    content: str,
    task_type: str = "general",
    context: str = "",
    complexity_hint: Optional[int] = None,
    max_tier: int = 3
) -> RouteResult:
    """
    Route a task to the best model based on complexity estimation.

    Args:
        content: The main content/prompt for the AI (code, text, question).
        task_type: One of the task types in router-config.yaml
                   (code-review, documentation, analysis, etc.)
        context: Additional context (project info, existing patterns, etc.)
        complexity_hint: Optional manual complexity score (1-100).
                         If provided, weighted into the estimate.
        max_tier: Maximum tier to use (for cost-capped runs).

    Returns:
        RouteResult with the AI response and metadata.
        The caller is responsible for logging via SessionLog.log_step().
    """
    _init()

    # 1. Estimate complexity
    full_prompt_text = f"{content}\n{context}"
    score = estimate_complexity(
        text=full_prompt_text,
        task_type=task_type,
        hint=complexity_hint,
        config=_config["complexity"]
    )

    # 2. Pick model
    model_name = pick_model(score, max_tier, task_type, _config)
    model_cfg = _config["models"][model_name]

    # 3. Build prompt with model-specific formatting
    system_prompt, user_message = build_prompt(
        content=content,
        context=context,
        task_type=task_type,
        model_cfg=model_cfg,
        config=_config
    )

    # 4. Execute with escalation loop
    escalation_history = []
    current_model_name = model_name

    while True:
        current_cfg = _config["models"][current_model_name]
        provider_name = current_cfg["provider"]

        # Rate limit
        _rate_limiters[provider_name].wait()

        # Call API
        start = time.time()
        result = call_model(
            provider_name=provider_name,
            model_id=current_cfg["model_id"],
            system_prompt=system_prompt,
            user_message=user_message,
            max_tokens=current_cfg["max_output_tokens"],
            config=_config["providers"][provider_name]
        )
        elapsed = time.time() - start

        # Check if escalation needed
        if _config["escalation"]["enabled"] and should_escalate(
            result, _config["escalation"]
        ):
            next_model = get_escalation_model(
                current_model_name, _config,
                len(escalation_history)
            )
            if next_model:
                reason = _classify_escalation_reason(result, _config)
                escalation_history.append((current_model_name, reason))
                current_model_name = next_model
                # Rebuild prompt for new model's provider
                new_cfg = _config["models"][current_model_name]
                system_prompt, user_message = build_prompt(
                    content=content,
                    context=context,
                    task_type=task_type,
                    model_cfg=new_cfg,
                    config=_config
                )
                continue
            # else: max escalations reached, use what we have
        break

    # 5. Calculate cost
    cost = _calculate_cost(
        result.input_tokens,
        result.output_tokens,
        _config["models"][current_model_name]
    )

    # 6. Build initial result
    route_result = RouteResult(
        content=result.content,
        model_name=current_model_name,
        model_id=_config["models"][current_model_name]["model_id"],
        tier=_config["models"][current_model_name]["tier"],
        input_tokens=result.input_tokens,
        output_tokens=result.output_tokens,
        cost_usd=cost,
        total_cost_usd=cost,
        complexity_score=score,
        escalated=len(escalation_history) > 0,
        escalation_history=escalation_history,
        elapsed_seconds=elapsed,
        verification=None
    )

    # 7. Auto-verify if this task type is configured for it
    v_config = _config.get("verification", {})
    auto_types = v_config.get("auto_verify_task_types", [])

    if (v_config.get("enabled", False)
            and task_type in auto_types):
        verification = _run_verification(
            route_result=route_result,
            original_task=user_message,
            task_type=task_type
        )
        if verification:
            route_result.verification = verification
            route_result.total_cost_usd = cost + verification.verifier_cost_usd

            # If on_disagreement == "merge" and issues were found,
            # append verifier feedback to the content
            on_disagree = (v_config.get("settings", {})
                           .get("on_disagreement", "flag"))
            if (not verification.verified
                    and on_disagree == "merge"):
                route_result.content = _merge_with_verification(
                    result.content, verification
                )
            elif (not verification.verified
                    and on_disagree == "re-route"):
                route_result = _tiebreaker_reroute(
                    route_result, user_message, task_type,
                    verification, v_config
                )

    return route_result


def query(
    model: str,
    content: str,
    task_type: str = "general",
    context: str = ""
) -> RouteResult:
    """
    Call a specific model directly, bypassing complexity estimation.
    Use when you know which model you want.
    """
    _init()

    model_cfg = _config["models"][model]
    provider_name = model_cfg["provider"]

    system_prompt, user_message = build_prompt(
        content=content,
        context=context,
        task_type=task_type,
        model_cfg=model_cfg,
        config=_config
    )

    _rate_limiters[provider_name].wait()

    start = time.time()
    result = call_model(
        provider_name=provider_name,
        model_id=model_cfg["model_id"],
        system_prompt=system_prompt,
        user_message=user_message,
        max_tokens=model_cfg["max_output_tokens"],
        config=_config["providers"][provider_name]
    )
    elapsed = time.time() - start

    cost = _calculate_cost(
        result.input_tokens, result.output_tokens, model_cfg
    )

    return RouteResult(
        content=result.content,
        model_name=model,
        model_id=model_cfg["model_id"],
        tier=model_cfg["tier"],
        input_tokens=result.input_tokens,
        output_tokens=result.output_tokens,
        cost_usd=cost,
        total_cost_usd=cost,
        complexity_score=-1,
        escalated=False,
        escalation_history=[],
        elapsed_seconds=elapsed,
        verification=None
    )


def verify(
    route_result: RouteResult,
    original_task: str = "",
    task_type: str = "general"
) -> VerificationResult:
    """
    Independently verify a RouteResult using a model from a different provider.

    Args:
        route_result: The result from route() or query() to verify.
        original_task: The original task/prompt (if not provided, the
                       verifier only sees the response, not the task).
        task_type: Task type for context in the verification prompt.

    Returns:
        VerificationResult with verdict, issues, and cost.
    """
    _init()
    result = _run_verification(route_result, original_task, task_type)
    if result is None:
        raise RuntimeError(
            f"No cross-provider verifier available for "
            f"model '{route_result.model_name}'"
        )
    return result


def _run_verification(
    route_result: RouteResult,
    original_task: str,
    task_type: str
) -> Optional[VerificationResult]:
    """Internal: execute a verification call."""
    v_config = _config.get("verification", {})
    settings = v_config.get("settings", {})

    # 1. Pick verifier model (must be different provider)
    verifier_name = pick_verifier_model(
        generator_model=route_result.model_name,
        config=_config
    )
    if verifier_name is None:
        return None

    verifier_cfg = _config["models"][verifier_name]
    verifier_provider = verifier_cfg["provider"]

    # 2. Cost guard: skip if verification would be too expensive
    max_multiplier = settings.get("max_cost_multiplier", 3.0)
    estimated_verify_cost = _calculate_cost(
        route_result.input_tokens + route_result.output_tokens,
        route_result.output_tokens // 2,  # verifier output is typically shorter
        verifier_cfg
    )
    if (route_result.cost_usd > 0
            and estimated_verify_cost > route_result.cost_usd * max_multiplier):
        return None  # too expensive relative to original

    # 3. Build verification prompt
    v_template = _config.get("_verification_template", "")
    system_prompt = verifier_cfg.get(
        "_system_prompt",
        "You are an independent code verifier. Be precise and objective."
    )
    user_message = build_verification_prompt(
        original_task=original_task,
        original_response=route_result.content,
        task_type=task_type,
        template=v_template
    )

    # 4. Call verifier
    _rate_limiters[verifier_provider].wait()

    v_result = call_model(
        provider_name=verifier_provider,
        model_id=verifier_cfg["model_id"],
        system_prompt=system_prompt,
        user_message=user_message,
        max_tokens=verifier_cfg["max_output_tokens"],
        config=_config["providers"][verifier_provider]
    )

    v_cost = _calculate_cost(
        v_result.input_tokens, v_result.output_tokens, verifier_cfg
    )

    # 5. Parse verdict
    verdict, issues = parse_verification_response(v_result.content)

    # 6. Build and return verification result
    generator_cfg = _config["models"][route_result.model_name]

    return VerificationResult(
        verdict=verdict,
        verified=(verdict == "VERIFIED"),
        issues=issues,
        verifier_model=verifier_name,
        verifier_provider=verifier_provider,
        generator_model=route_result.model_name,
        generator_provider=generator_cfg["provider"],
        verifier_input_tokens=v_result.input_tokens,
        verifier_output_tokens=v_result.output_tokens,
        verifier_cost_usd=v_cost,
        raw_response=v_result.content
    )


def _merge_with_verification(
    original_content: str,
    verification: VerificationResult
) -> str:
    """Append verifier feedback to the original response."""
    merged = original_content + "\n\n"
    merged += "---\n"
    merged += (f"**Verification ({verification.verifier_model}, "
               f"{verification.verifier_provider}):** "
               f"{verification.verdict}\n\n")
    if verification.issues:
        for i, issue in enumerate(verification.issues, 1):
            merged += (f"**Issue {i}** "
                       f"[{issue.get('category', '?')} / "
                       f"{issue.get('severity', '?')}]: "
                       f"{issue.get('description', '')}\n")
    return merged


def _tiebreaker_reroute(
    route_result: RouteResult,
    user_message: str,
    task_type: str,
    verification: VerificationResult,
    v_config: dict
) -> RouteResult:
    """When generator and verifier disagree, send to a Tier 3 tiebreaker."""
    tiebreaker_name = v_config.get("settings", {}).get(
        "tiebreaker_model", "opus"
    )
    if tiebreaker_name not in _config["models"]:
        # No tiebreaker available — fall back to merge
        route_result.content = _merge_with_verification(
            route_result.content, verification
        )
        return route_result

    tb_cfg = _config["models"][tiebreaker_name]
    tb_provider = tb_cfg["provider"]

    # Build a tiebreaker prompt with both perspectives
    tb_prompt = (
        "Two AI models disagree on the following task. "
        "Review both responses and produce the correct, authoritative answer.\n\n"
        f"## Original Task\n\n{user_message}\n\n"
        f"## Response A ({route_result.model_name})\n\n"
        f"{route_result.content}\n\n"
        f"## Verification Feedback ({verification.verifier_model})\n\n"
        f"{verification.raw_response}\n\n"
        "## Your Task\n\n"
        "Produce the final, correct response to the original task, "
        "incorporating valid points from both perspectives."
    )

    system_prompt = tb_cfg.get("_system_prompt", "You are an expert.")

    _rate_limiters[tb_provider].wait()

    tb_result = call_model(
        provider_name=tb_provider,
        model_id=tb_cfg["model_id"],
        system_prompt=system_prompt,
        user_message=tb_prompt,
        max_tokens=tb_cfg["max_output_tokens"],
        config=_config["providers"][tb_provider]
    )

    tb_cost = _calculate_cost(
        tb_result.input_tokens, tb_result.output_tokens, tb_cfg
    )

    route_result.content = tb_result.content
    route_result.total_cost_usd += verification.verifier_cost_usd + tb_cost
    route_result.verification = verification
    return route_result


def get_costs(session_set_dir: str) -> dict:
    """Return cost summary from a session set's activity log."""
    log = SessionLog(session_set_dir)
    return log.get_cost_summary()


def print_cost_report(session_set_dir: str):
    """Print a formatted cost report for a session set."""
    log = SessionLog(session_set_dir)
    costs = log.get_cost_summary()

    print("\n" + "=" * 60)
    print("AI ROUTER — COST REPORT")
    print(f"Session Set: {log._data['sessionSetName']}")
    print("=" * 60)
    print(f"Sessions completed: {costs['sessions_completed']} "
          f"of {log.total_sessions}")
    print(f"Sessions remaining: {costs['sessions_remaining']}")
    print(f"Total routed API calls: {costs['total_calls']}")
    print(f"Total routed cost:      ${costs['total_cost']:.4f}")
    print()

    if costs["by_model"]:
        print("By model:")
        for model, data in costs["by_model"].items():
            print(f"  {model:20s}  {data['calls']:3d} calls"
                  f"  ${data['cost']:.4f}")
    print("=" * 60 + "\n")


def _calculate_cost(input_tokens, output_tokens, model_cfg):
    return (
        (input_tokens / 1_000_000) * model_cfg["input_cost_per_1m"]
        + (output_tokens / 1_000_000) * model_cfg["output_cost_per_1m"]
    )


def _classify_escalation_reason(result, config):
    esc = config["escalation"]
    if len(result.content.strip()) == 0:
        return "empty_response"
    if result.stop_reason == "max_tokens":
        return "truncated"
    if result.output_tokens < esc["triggers"]["min_output_tokens"]:
        return "too_short"
    for phrase in esc.get("refusal_phrases", []):
        if phrase in result.content.lower():
            return "refusal"
    return "unknown"
