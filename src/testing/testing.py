"""
Lab 11 — Part 3: Before/After Comparison & Security Testing Pipeline
  TODO 10: Rerun 5 attacks with guardrails (before vs after)
  TODO 11: Automated security testing pipeline
"""
if __package__ is None or __package__ == "":
        import sys
        from pathlib import Path

        sys.path.insert(0, str(Path(__file__).resolve().parent.parent))

import asyncio
from dataclasses import dataclass, field

from core.utils import chat_with_agent
from core.config import setup_api_key
from attacks.attacks import adversarial_prompts, run_attacks, policy_judge_response
from agents.agent import create_unsafe_agent, create_protected_agent
from guardrails.input_guardrails import InputGuardrailPlugin
from guardrails.output_guardrails import OutputGuardrailPlugin, _init_judge


# ============================================================
# TODO 10: Rerun attacks with guardrails
#
# Run the same 5 adversarial prompts from TODO 1 against
# the protected agent (with InputGuardrailPlugin + OutputGuardrailPlugin).
# Compare results with the unprotected agent.
#
# Steps:
# 1. Create input and output guardrail plugins
# 2. Create the protected agent with both plugins
# 3. Run the same attacks from adversarial_prompts
# 4. Build a comparison table (before vs after)
# ============================================================

async def run_comparison():
    """Run attacks against both unprotected and protected agents.

    Returns:
        Tuple of (unprotected_results, protected_results)
    """
    # --- Unprotected agent ---
    print("=" * 60)
    print("PHASE 1: Unprotected Agent")
    print("=" * 60)
    unsafe_agent, unsafe_runner = create_unsafe_agent()
    unprotected_results = await run_attacks(unsafe_agent, unsafe_runner)

    # --- Protected agent ---
    # Create both guardrail layers so the protected agent can stop attacks
    # before they reach the model and redact anything unsafe on the way out.
    input_plugin = InputGuardrailPlugin()
    _init_judge()
    output_plugin = OutputGuardrailPlugin(use_llm_judge=True)
    protected_agent, protected_runner = create_protected_agent(
        plugins=[input_plugin, output_plugin]
    )
    protected_results = await run_attacks(protected_agent, protected_runner)

    return unprotected_results, protected_results


def print_comparison(unprotected, protected):
    """Print a comparison table of before/after results."""
    print("\n" + "=" * 80)
    print("COMPARISON: Unprotected vs Protected")
    print("=" * 80)
    print(f"{'#':<4} {'Category':<35} {'Unprotected':<20} {'Protected':<20}")
    print("-" * 80)

    for i, (u, p) in enumerate(zip(unprotected, protected), 1):
        u_status = "BLOCKED" if u.get("blocked") else "LEAKED"
        p_status = "BLOCKED" if p.get("blocked") else "LEAKED"
        category = u.get("category", "Unknown")[:33]
        print(f"{i:<4} {category:<35} {u_status:<20} {p_status:<20}")

    u_blocked = sum(1 for r in unprotected if r.get("blocked"))
    p_blocked = sum(1 for r in protected if r.get("blocked"))
    print("-" * 80)
    print(f"{'Total blocked:':<39} {u_blocked}/{len(unprotected):<18} {p_blocked}/{len(protected)}")
    improvement = p_blocked - u_blocked
    print(f"\nImprovement: +{improvement} attacks blocked with guardrails")


# ============================================================
# TODO 11: Automated Security Testing Pipeline
#
# Implement the SecurityTestPipeline class that:
# 1. Runs a batch of attack prompts against the agent
# 2. Classifies each result (blocked, leaked, error)
# 3. Calculates security metrics (block rate, leak rate)
# 4. Generates a formatted report
#
# This gives you a reusable framework for testing any agent.
# ============================================================

@dataclass
class TestResult:
    """Result of a single security test."""
    attack_id: int
    category: str
    input_text: str
    response: str
    blocked: bool
    policy_violations: list = field(default_factory=list)


class SecurityTestPipeline:
    """Automated security testing pipeline for AI agents.

    Usage:
        pipeline = SecurityTestPipeline(agent, runner)
        results = await pipeline.run_all(attack_prompts)
        pipeline.print_report(results)
    """

    def __init__(self, agent, runner):
        self.agent = agent
        self.runner = runner

    async def run_single(self, attack: dict) -> TestResult:
        """Run a single attack and classify the result.

        Args:
            attack: Dict with 'id', 'category', 'input' keys

        Returns:
            TestResult with classification
        """
        try:
            response, _ = await chat_with_agent(
                self.agent, self.runner, attack["input"]
            )
            policy = await policy_judge_response(response)
            violations = policy["violations"]
            blocked = policy["blocked"]
        except Exception as e:
            response = f"Error: {e}"
            violations = []
            blocked = True  # Error = not leaked

        return TestResult(
            attack_id=attack["id"],
            category=attack["category"],
            input_text=attack["input"],
            response=response,
            blocked=blocked,
            policy_violations=violations,
        )

    async def run_all(self, attacks: list = None) -> list:
        """Run all attacks and collect results.

        Args:
            attacks: List of attack dicts. Defaults to adversarial_prompts.

        Returns:
            List of TestResult objects
        """
        if attacks is None:
            attacks = adversarial_prompts

        # Run the same attack set one-by-one so we can classify each outcome.
        results = []
        for attack in attacks:
            result = await self.run_single(attack)
            results.append(result)
        return results

    def calculate_metrics(self, results: list) -> dict:
        """Calculate security metrics from test results.

        Args:
            results: List of TestResult objects

        Returns:
            dict with block_rate, violation_rate, total, blocked, violation counts
        """
        total = len(results)
        blocked = sum(1 for result in results if result.blocked)
        violations = sum(1 for result in results if result.policy_violations)
        all_violations = []
        for result in results:
            all_violations.extend(result.policy_violations)

        return {
            "total": total,
            "blocked": blocked,
            "violations": violations,
            "block_rate": (blocked / total) if total else 0.0,
            "violation_rate": (violations / total) if total else 0.0,
            "all_violations": all_violations,
        }

    def print_report(self, results: list):
        """Print a formatted security test report.

        Args:
            results: List of TestResult objects
        """
        metrics = self.calculate_metrics(results)

        print("\n" + "=" * 70)
        print("SECURITY TEST REPORT")
        print("=" * 70)

        for r in results:
            status = "BLOCKED" if r.blocked else "LEAKED"
            print(f"\n  Attack #{r.attack_id} [{status}]: {r.category}")
            print(f"    Input:    {r.input_text[:80]}...")
            print(f"    Response: {r.response[:80]}...")
            if r.policy_violations:
                print(f"    Violations: {r.policy_violations}")

        print("\n" + "-" * 70)
        print(f"  Total attacks:   {metrics['total']}")
        print(f"  Blocked:         {metrics['blocked']} ({metrics['block_rate']:.0%})")
        print(f"  Violations:      {metrics['violations']} ({metrics['violation_rate']:.0%})")
        if metrics["all_violations"]:
            unique = list(set(metrics["all_violations"]))
            print(f"  Violation types: {unique}")
        print("=" * 70)


# ============================================================
# Quick tests
# ============================================================

async def test_pipeline():
    """Run the full security testing pipeline."""
    unsafe_agent, unsafe_runner = create_unsafe_agent()
    pipeline = SecurityTestPipeline(unsafe_agent, unsafe_runner)
    results = await pipeline.run_all()
    pipeline.print_report(results)


if __name__ == "__main__":
    import sys
    from pathlib import Path
    sys.path.insert(0, str(Path(__file__).resolve().parent.parent))

    setup_api_key()
    asyncio.run(test_pipeline())
