"""Built-in bench candidate presets.

Curated comparison setups so users can reproduce known benchmarks with one
flag instead of typing N `--candidate` lines.

Presets come in two families, matching the two backend families:

- **API presets** (`paper*`, `frontier*`) route every candidate through
  OpenRouter, which is what makes cross-vendor comparison possible at all — no
  agent CLI serves a third party's models. These need `OPENROUTER_API_KEY` and
  bill per token.
- **CLI presets** (`claude-*`, `cross-backend-*`) run candidates through a local
  agent CLI on a subscription. Nothing is billed per token, but the candidate
  set is limited to what those CLIs serve.

The two families are **not comparable to each other**: the prompts match, but
under a CLI backend the harness delegates the tool loop to the CLI rather than
driving it, so compare within a family. The numbers in
`docs/BENCH_RESULTS.md` were produced by the API presets.

Substitutions in the "paper" preset
-----------------------------------
The Google Co-Scientist paper compared their system against:

    Gemini 2.0 Flash Thinking Experimental 12-19
    Gemini 2.0 Pro Experimental
    OpenAI o1

across 15 expert-curated research goals. Of those, OpenRouter currently
serves only `openai/o1`; the experimental Gemini 2.0 Thinking and Pro
Experimental branches were retired. We substitute the closest current
analogues and document the swap so reported numbers are interpretable:

    paper-baseline                            current substitute
    ----------------------------------------  --------------------------------
    Gemini 2.0 Flash Thinking Experimental    google/gemini-2.0-flash-001
       (Thinking branch deprecated; production 2.0 Flash is the closest)
    Gemini 2.0 Pro Experimental               google/gemini-2.5-pro
       (2.0 Pro Experimental removed; 2.5 Pro is the current Pro-tier Gemini)
    OpenAI o1                                 openai/o1               (exact)
    Claude Haiku (added by user request)      anthropic/claude-haiku-4.5

What carries across both families is the science: the paper's AML
drug-repurposing goal and its top-3 gold set.

Judge model is configurable via --judge as "<provider>:<model>". Pick a judge in
the same family as the candidates — `openrouter:google/gemini-3-flash-preview`
for the API presets, `claude_cli:sonnet` for the CLI presets.
"""

from __future__ import annotations

from dataclasses import dataclass

from .goldset import AML_REPURPOSING_PAPER_TOP3, GoldSet
from .runner import BenchCandidate


@dataclass(frozen=True)
class BenchPreset:
    name: str
    description: str
    candidates: tuple[BenchCandidate, ...]
    suggested_judge: str        # "provider:model"
    # Optional preset defaults — let the CLI invoke a preset without forcing
    # the user to retype the goal or attach a gold set.
    default_goal: str | None = None
    goldset: GoldSet | None = None


_PAPER_CANDIDATES: tuple[BenchCandidate, ...] = (
    BenchCandidate(
        label="gemini-2-flash-thinking",
        provider="openrouter",
        model="google/gemini-2.0-flash-001",
    ),
    BenchCandidate(
        label="gemini-2-pro",
        provider="openrouter",
        model="google/gemini-2.5-pro",
    ),
    BenchCandidate(
        label="openai-o1",
        provider="openrouter",
        model="openai/o1",
    ),
    BenchCandidate(
        label="claude-haiku-4.5",
        provider="openrouter",
        model="anthropic/claude-haiku-4.5",
    ),
)


# Claude Code tiers. Spans the capability range so the bench still surfaces
# a quality gradient, even though nothing is billed per token any more.
_CLAUDE_CANDIDATES: tuple[BenchCandidate, ...] = (
    BenchCandidate(label="opus", provider="claude_cli", model="opus"),
    BenchCandidate(label="sonnet", provider="claude_cli", model="sonnet"),
    BenchCandidate(label="haiku", provider="claude_cli", model="haiku"),
)


# The AML drug-repurposing goal mirrors the exact methodology in the
# Co-Scientist paper:
#   - Ranked list of repurposing candidates for AML.
#   - Candidates must NOT have been previously repurposed for AML.
#   - There must be NO prior preclinical evidence supporting the candidate
#     in AML.
#   - The system uses only its internal knowledge — no DepMap dependency
#     scores, no genomic priors, no human expert feedback.
#
# We additionally tell models to NAME the specific drug (INN, brand, or
# research code) rather than a drug class so the gold-set matcher can
# score recall against named entities.
_PAPER_AML_GOAL = (
    "Produce a ranked list of drug repurposing candidates for acute "
    "myeloid leukemia (AML), strictly under the following constraints:\n\n"
    "(1) Each candidate must NOT have prior published evidence of being "
    "repurposed for AML, and there must be no preclinical studies in AML "
    "for the proposed compound at the time of writing.\n"
    "(2) Use only your internal knowledge. Do NOT assume access to DepMap "
    "dependency scores, gene-essentiality datasets, transcriptomic "
    "screens, or human expert curation. No external inputs.\n"
    "(3) Name the specific compound (INN, brand name, or research-code "
    "alias) — do not propose generic drug classes (e.g. \"MEK inhibitors\")."
    " Cover diverse mechanisms across the ranked list (avoid 5 ideas all "
    "hitting the same pathway).\n\n"
    "For each candidate hypothesis, give: the named compound, the "
    "molecular mechanism by which it would act against AML blasts or "
    "leukemic stem cells (with the specific target/pathway), the "
    "scientific reasoning that licenses the AML hypothesis even though "
    "no AML-specific evidence currently exists, and one concrete in vitro "
    "or in vivo experiment that would falsify the hypothesis."
)


def _vs_raw(candidates: tuple[BenchCandidate, ...]) -> tuple[BenchCandidate, ...]:
    """Double every candidate: once in pipeline mode, once in direct mode.

    This is the apples-to-apples comparison of co-scientist's multi-agent
    Generation harness against a raw single-shot LM call on the same goal.
    The label gets a `[pipe]` / `[raw]` suffix so the result table makes
    the distinction obvious.
    """
    out: list[BenchCandidate] = []
    for c in candidates:
        out.append(BenchCandidate(
            label=f"{c.label}[pipe]", provider=c.provider, model=c.model,
            mode="pipeline",
        ))
        out.append(BenchCandidate(
            label=f"{c.label}[raw]", provider=c.provider, model=c.model,
            mode="direct",
        ))
    return tuple(out)


_FRONTIER_CANDIDATES: tuple[BenchCandidate, ...] = (
    BenchCandidate(
        label="claude-opus-4.7",
        provider="openrouter",
        # OpenRouter uses dots in the version suffix.
        model="anthropic/claude-opus-4.7",
    ),
    BenchCandidate(
        label="gpt-5",
        provider="openrouter",
        model="openai/gpt-5",
    ),
    BenchCandidate(
        label="gemini-3-pro",
        provider="openrouter",
        model="google/gemini-3.1-pro-preview",
    ),
    BenchCandidate(
        label="gemini-3-flash",
        provider="openrouter",
        model="google/gemini-3-flash-preview",
    ),
)


# Cross-backend set. Codex requires a ChatGPT account entitled to the model —
# check with `codex exec -m <model>` before running this preset, since an
# unentitled model fails the run rather than degrading.
_CROSS_BACKEND_CANDIDATES: tuple[BenchCandidate, ...] = (
    BenchCandidate(label="claude-opus", provider="claude_cli", model="opus"),
    BenchCandidate(label="claude-sonnet", provider="claude_cli", model="sonnet"),
    BenchCandidate(label="codex", provider="codex_cli", model="gpt-5.6-codex"),
)


PRESETS: dict[str, BenchPreset] = {
    "paper": BenchPreset(
        name="paper",
        description=(
            "Reproduce the Co-Scientist paper's preference-ranking comparison "
            "(plus Haiku) using current OpenRouter models. See module docstring "
            "for the substitutions we had to make for retired experimental models."
        ),
        candidates=_PAPER_CANDIDATES,
        suggested_judge="openrouter:google/gemini-3-flash-preview",
    ),
    "paper-aml": BenchPreset(
        name="paper-aml",
        description=(
            "Reproduce the paper's AML repurposing benchmark under its "
            "strict methodology: candidates with NO prior repurposing "
            "evidence and NO preclinical evidence in AML, no external "
            "inputs (DepMap, expert feedback). Recall is scored against "
            "the top-3 candidates the paper surfaced: Nanvuranlat, KIRA6, "
            "and Leflunomide. Uses the same candidate set + judge as the "
            "`paper` preset."
        ),
        candidates=_PAPER_CANDIDATES,
        suggested_judge="openrouter:google/gemini-3-flash-preview",
        default_goal=_PAPER_AML_GOAL,
        goldset=AML_REPURPOSING_PAPER_TOP3,
    ),
    "paper-aml-vs-raw": BenchPreset(
        name="paper-aml-vs-raw",
        description=(
            "AML repurposing benchmark for the paper's baseline models, "
            "under the strict no-prior-evidence methodology — each model "
            "runs TWICE: once through the full co-scientist Generation "
            "pipeline (literature tools + tool loop + dedup) and once as a "
            "single raw LM call. Isolates how much of the system's "
            "performance comes from the multi-agent harness vs the model "
            "itself. Same top-3 gold set as `paper-aml`."
        ),
        candidates=_vs_raw(_PAPER_CANDIDATES),
        suggested_judge="openrouter:google/gemini-3-flash-preview",
        default_goal=_PAPER_AML_GOAL,
        goldset=AML_REPURPOSING_PAPER_TOP3,
    ),
    "frontier-aml-vs-raw": BenchPreset(
        name="frontier-aml-vs-raw",
        description=(
            "Same setup as `paper-aml-vs-raw` but with current frontier "
            "models (Claude Opus 4.7, GPT-5, Gemini 3 Pro, Gemini 3 Flash). "
            "Lets you see whether the multi-agent harness still adds value "
            "with stronger base models."
        ),
        candidates=_vs_raw(_FRONTIER_CANDIDATES),
        suggested_judge="openrouter:google/gemini-3-flash-preview",
        default_goal=_PAPER_AML_GOAL,
        goldset=AML_REPURPOSING_PAPER_TOP3,
    ),
    "claude-aml": BenchPreset(
        name="claude-aml",
        description=(
            "The paper's AML repurposing benchmark under its strict "
            "methodology: candidates with NO prior repurposing evidence and "
            "NO preclinical evidence in AML, no external inputs (DepMap, "
            "expert feedback). Recall is scored against the top-3 candidates "
            "the paper surfaced: Nanvuranlat, KIRA6, and Leflunomide. Runs "
            "the three Claude Code tiers."
        ),
        candidates=_CLAUDE_CANDIDATES,
        suggested_judge="claude_cli:sonnet",
        default_goal=_PAPER_AML_GOAL,
        goldset=AML_REPURPOSING_PAPER_TOP3,
    ),
    "claude-aml-vs-raw": BenchPreset(
        name="claude-aml-vs-raw",
        description=(
            "AML repurposing benchmark where each Claude tier runs TWICE: "
            "once through the full co-scientist Generation pipeline "
            "(literature tools + dedup) and once as a single raw call. "
            "Isolates how much performance comes from the multi-agent "
            "harness versus the model itself. Same gold set as `claude-aml`."
        ),
        candidates=_vs_raw(_CLAUDE_CANDIDATES),
        suggested_judge="claude_cli:sonnet",
        default_goal=_PAPER_AML_GOAL,
        goldset=AML_REPURPOSING_PAPER_TOP3,
    ),
    "cross-backend-aml": BenchPreset(
        name="cross-backend-aml",
        description=(
            "Claude Code versus Codex on the AML repurposing benchmark. "
            "Requires both CLIs installed and signed in, and a ChatGPT "
            "account entitled to the Codex model — verify with "
            "`co-scientist doctor` after setting [llm] provider = codex_cli."
        ),
        candidates=_CROSS_BACKEND_CANDIDATES,
        suggested_judge="claude_cli:sonnet",
        default_goal=_PAPER_AML_GOAL,
        goldset=AML_REPURPOSING_PAPER_TOP3,
    ),
}


def get_preset(name: str) -> BenchPreset:
    try:
        return PRESETS[name]
    except KeyError as e:
        names = ", ".join(sorted(PRESETS))
        raise KeyError(f"unknown bench preset {name!r}; available: {names}") from e
