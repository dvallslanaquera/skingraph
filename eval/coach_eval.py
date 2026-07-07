# Coach faithfulness eval — deterministic mandated-content coverage.
#
#   poetry run python -m eval.coach_eval               # report coverage
#   poetry run python -m eval.coach_eval --min-coverage 1.0   # CI gate
#   poetry run python -m eval.coach_eval --save data/coach_eval.json
#
# The coach is the ONLY LLM in the safety path, so it is the one generative step
# whose output can silently drop a safety finding — "a defect, not a UI glitch"
# (project brief). This harness measures the property that matters for a grounded
# safety writer: *mandated-content coverage* — every deterministic safety caution
# the pipeline computed for a (profile, product) pair must survive into the
# rendered card's warnings.
#
# It is deliberately model-free and gateable. The coach injects its
# safety-critical cautions (pregnancy / dehydration / sun-sensitivity /
# introduction pacing) into the card in code — `ja.warnings = extra_ja +
# ja.warnings` — so we stub the Gemini call to return EMPTY warnings and assert
# the deterministic cautions still land. That is faithfulness reduced to set
# inclusion: it cannot be gamed, it needs no API key, and it maps one-to-one onto
# the safety requirement. The fixtures below are an INDEPENDENT specification of
# what each profile+product MUST surface, not a mirror of the implementation, so
# dropping (say) Retinol from the pregnancy set is caught here as a regression.
#
# The LLM-as-judge layer for 薬機法 tone / over-claiming is a documented
# follow-up (EVAL-OPS.md §8), not a prerequisite: tone is not gateable the way
# set inclusion is.
import argparse
import json
import sys
from contextlib import contextmanager
from unittest.mock import MagicMock

from src.nodes import coach
from src.state import (
    CoachResponse,
    Recommendation,
    RoutineProduct,
    SafetyAudit,
    UserProfile,
)

# --- fixtures -----------------------------------------------------------------
# Each fixture is a (profile, product) scenario plus the safety cautions that
# MUST appear in the rendered card, per language. `ingredients` are
# (name_raw, canonical_INCI) pairs; the coach reasons over the INCI side.


def _std(*pairs: tuple[str, str]) -> list[dict]:
    """Normalizer-shaped ingredient rows from (raw, INCI) pairs."""
    return [
        {"name_raw": raw, "name_standardized": inci, "is_active": None, "source_language": "JP"}
        for raw, inci in pairs
    ]


FIXTURES: list[dict] = [
    {
        "id": "pregnant_retinol",
        "note": "Retinol is pregnancy-flagged AND photosensitising.",
        "ingredients": _std(("レチノール", "Retinol")),
        "profile": UserProfile(is_pregnant=True, skin_type="dry"),
        "routine_products": [],
        "must_include_en": ["Pregnancy caution", "Retinol", "Sun-sensitivity caution"],
        "must_include_ja": ["妊娠中の注意", "紫外線に注意"],
    },
    {
        "id": "pregnant_clean",
        "note": "No flagged ingredient → generic pregnancy consult caution.",
        "ingredients": _std(("水", "Water")),
        "profile": UserProfile(is_pregnant=True),
        "routine_products": [],
        "must_include_en": ["consult a doctor"],
        "must_include_ja": ["医師にご相談"],
    },
    {
        "id": "drying_alcohol",
        "note": "Alcohol Denat. is barrier-stripping → dehydration caution.",
        "ingredients": _std(("変性アルコール", "Alcohol Denat.")),
        "profile": UserProfile(skin_type="oily"),
        "routine_products": [],
        "must_include_en": ["Dehydration caution", "Alcohol Denat."],
        "must_include_ja": ["乾燥に注意"],
    },
    {
        "id": "sensitive_strong_active",
        "note": "Sensitive skin + a retinoid → one-at-a-time patch-test pacing.",
        "ingredients": _std(("レチノール", "Retinol")),
        "profile": UserProfile(skin_type="sensitive"),
        "routine_products": [],
        "must_include_en": ["patch-test", "Sun-sensitivity caution"],
        "must_include_ja": ["パッチテスト", "紫外線に注意"],
    },
    {
        "id": "pacing_from_shelf",
        "note": "New retinoid while an exfoliating acid is already on the shelf.",
        "ingredients": _std(("レチノール", "Retinol")),
        "profile": UserProfile(skin_type="dry"),
        "routine_products": [
            RoutineProduct(
                product_id="p1",
                brand="Acme",
                product_name="BHA Peel",
                ingredients=["Salicylic Acid"],
            )
        ],
        "must_include_en": ["Introduction caution", "Sun-sensitivity caution"],
        "must_include_ja": ["導入の注意", "紫外線に注意"],
    },
    {
        "id": "photosensitiser_only",
        "note": "Glycolic Acid raises sun sensitivity; dry skin, no shelf, not pregnant.",
        "ingredients": _std(("グリコール酸", "Glycolic Acid")),
        "profile": UserProfile(skin_type="dry"),
        "routine_products": [],
        "must_include_en": ["Sun-sensitivity caution", "Glycolic Acid"],
        "must_include_ja": ["紫外線に注意"],
    },
    {
        "id": "clean_no_profile",
        "note": "Nothing hazardous, anonymous scan → no fabricated cautions.",
        "ingredients": _std(("水", "Water"), ("グリセリン", "Glycerin")),
        "profile": None,
        "routine_products": [],
        "must_include_en": [],
        "must_include_ja": [],
    },
]


# --- model-free coach run -----------------------------------------------------


def _stub_response() -> CoachResponse:
    """A minimal CoachResponse with EMPTY warnings.

    The coach prepends its deterministic safety cautions to whatever the model
    returns, so an empty-warning stub isolates exactly the code-injected content
    the eval is asserting on.
    """
    card = Recommendation(product="Brand — Product", timing="PM", frequency="Daily")
    return CoachResponse(
        recommendation_score=3,
        japanese=card.model_copy(),
        english=card.model_copy(),
    )


@contextmanager
def _stubbed_coach_llm():
    """Replace coach's Gemini client with one that returns _stub_response()."""
    structured = MagicMock()
    structured.invoke = MagicMock(return_value=_stub_response())
    chat = MagicMock()
    chat.with_structured_output.return_value = structured
    original = coach.ChatGoogleGenerativeAI
    coach.ChatGoogleGenerativeAI = MagicMock(return_value=chat)  # type: ignore[assignment]
    try:
        yield
    finally:
        coach.ChatGoogleGenerativeAI = original  # type: ignore[assignment]


def run_fixture(fixture: dict) -> dict:
    """Run the coach on one fixture and score deterministic-caution coverage."""
    from tests.helpers import make_extraction  # local: keeps eval import light

    state = {
        "safety_report": SafetyAudit(safety_score=0.8),
        "standardized_ingredients": fixture["ingredients"],
        "extracted_data": make_extraction(brand="Brand", product_name="Product"),
        "user_profile": fixture["profile"],
        "routine_products": fixture["routine_products"],
    }
    with _stubbed_coach_llm():
        cards = coach.coach_node(state)["coach_cards"]

    en = "\n".join(cards.english.warnings)
    ja = "\n".join(cards.japanese.warnings)

    required = [("en", s) for s in fixture["must_include_en"]] + [
        ("ja", s) for s in fixture["must_include_ja"]
    ]
    missing = [
        f"[{lang}] {needle}"
        for lang, needle in required
        if needle not in (en if lang == "en" else ja)
    ]
    return {
        "id": fixture["id"],
        "required": len(required),
        "covered": len(required) - len(missing),
        "missing": missing,
        "en_warnings": cards.english.warnings,
        "ja_warnings": cards.japanese.warnings,
    }


# --- reporting + gate ---------------------------------------------------------


def _aggregate(results: list[dict]) -> dict:
    required = sum(r["required"] for r in results)
    covered = sum(r["covered"] for r in results)
    return {
        "fixtures": len(results),
        "required": required,
        "covered": covered,
        "coverage": round(covered / required, 3) if required else 1.0,
        "failing": [r["id"] for r in results if r["missing"]],
    }


def print_report(results: list[dict]) -> None:
    print("\n" + "=" * 70)
    print("  COACH FAITHFULNESS — deterministic safety-caution coverage")
    print("=" * 70)
    for r in results:
        mark = "OK " if not r["missing"] else "FAIL"
        print(f"\n[{mark}] {r['id']}  ({r['covered']}/{r['required']} required cautions)")
        for m in r["missing"]:
            print(f"    DROPPED: {m}")
    agg = _aggregate(results)
    print("\n" + "-" * 70)
    print(f"  coverage: {agg['covered']}/{agg['required']} = {agg['coverage']:.3f}")
    if agg["failing"]:
        print(f"  failing fixtures: {', '.join(agg['failing'])}")
    print("=" * 70 + "\n")


def apply_gate(results: list[dict], min_coverage: float | None) -> None:
    if min_coverage is None:
        return
    agg = _aggregate(results)
    if agg["coverage"] < min_coverage:
        sys.exit(
            f"COACH FAITHFULNESS GATE FAILED: coverage {agg['coverage']:.3f} < "
            f"floor {min_coverage:.2f} — the coach dropped a mandated safety "
            f"caution for: {', '.join(agg['failing'])}"
        )
    print(
        f"COACH FAITHFULNESS GATE PASSED: coverage {agg['coverage']:.3f} "
        f">= floor {min_coverage:.2f}"
    )


def parse_args() -> argparse.Namespace:
    parser = argparse.ArgumentParser(
        description="Assert every deterministic safety caution survives into the coach card."
    )
    parser.add_argument(
        "--min-coverage",
        type=float,
        default=None,
        help="Fail (exit 1) if mandated-caution coverage is below this (CI gate uses 1.0).",
    )
    parser.add_argument("--save", metavar="PATH", help="Write full results as JSON to PATH.")
    return parser.parse_args()


def main() -> None:
    if hasattr(sys.stdout, "reconfigure"):
        sys.stdout.reconfigure(encoding="utf-8")
    args = parse_args()

    results = [run_fixture(f) for f in FIXTURES]
    print_report(results)

    if args.save:
        with open(args.save, "w", encoding="utf-8") as f:
            json.dump(
                {"results": results, "aggregate": _aggregate(results)},
                f,
                ensure_ascii=False,
                indent=2,
            )
        print(f"Results written to {args.save}")

    apply_gate(results, args.min_coverage)


if __name__ == "__main__":
    main()
