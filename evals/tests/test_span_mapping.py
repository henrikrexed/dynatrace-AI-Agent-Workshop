"""Offline tests for the Phoenix span-attribute mapper (ISI-6955 / ISI-6951).

No Phoenix, no cluster, no judge key — build a dataframe shaped exactly like
``client.spans.get_spans_dataframe()`` output (attributes flattened into
``attributes.<key>`` columns) and assert that every convention our agents might
emit maps to input/output/context:

  1. OTel GenAI semconv indexed form  (gen_ai.prompt.N.content / completion.N)
  2. OTel GenAI semconv structured form (gen_ai.input.messages / output.messages)
  3. OpenInference form                (input.value / output.value)
  4. GenAI log-events on the span      (events column)
  5. the regression: OTel-only spans used to map to ZERO records

Run: `cd evals && python -m pytest tests/ -q`  (or `uv run --group dev pytest`).
"""
from __future__ import annotations

import sys
from pathlib import Path

import pandas as pd
import pytest

HERE = Path(__file__).resolve().parent
sys.path.insert(0, str(HERE.parent / "phoenix"))
import span_mapping as sm  # noqa: E402


def _row(d: dict) -> pd.Series:
    """One dataframe row as Phoenix yields it in iterrows()."""
    return pd.Series(d)


def test_otel_genai_indexed_form():
    row = _row({
        "attributes.gen_ai.prompt.0.role": "user",
        "attributes.gen_ai.prompt.0.content": "Why is checkout slow?",
        "attributes.gen_ai.completion.0.role": "assistant",
        "attributes.gen_ai.completion.0.content": "The cart service is CPU-bound.",
        "attributes.input.value": float("nan"),   # OpenInference key absent/NaN
        "attributes.output.value": float("nan"),
    })
    assert sm.extract_input(row) == "Why is checkout slow?"
    assert sm.extract_output(row) == "The cart service is CPU-bound."


def test_indexed_form_concatenates_in_numeric_order():
    # 10 must sort after 2, not lexically before it.
    row = _row({
        "attributes.gen_ai.prompt.0.content": "sys",
        "attributes.gen_ai.prompt.2.content": "two",
        "attributes.gen_ai.prompt.10.content": "ten",
    })
    assert sm.extract_input(row) == "sys\ntwo\nten"


def test_otel_genai_structured_messages_form():
    row = _row({
        "attributes.gen_ai.input.messages": [
            {"role": "user", "content": "ping"}],
        "attributes.gen_ai.output.messages": [
            {"role": "assistant", "content": "pong"}],
    })
    assert "ping" in sm.extract_input(row)
    assert "pong" in sm.extract_output(row)


def test_openinference_form_still_works():
    row = _row({
        "attributes.input.value": "hello",
        "attributes.output.value": "world",
        "attributes.retrieval.documents": "doc-1",
    })
    assert sm.extract_input(row) == "hello"
    assert sm.extract_output(row) == "world"
    assert sm.extract_context(row) == "doc-1"


def test_genai_log_events_fallback():
    row = _row({
        "attributes.foo": "not-llm",
        "events": [
            {"name": "gen_ai.user.message", "attributes": {"content": "q"}},
            {"name": "gen_ai.choice", "attributes": {"content": "a"}},
        ],
    })
    assert sm.extract_input(row) == "q"
    assert sm.extract_output(row) == "a"


def test_priority_prefers_openinference_value_over_indexed():
    row = _row({
        "attributes.input.value": "canonical",
        "attributes.gen_ai.prompt.0.content": "indexed",
    })
    assert sm.extract_input(row) == "canonical"


def test_non_llm_span_maps_to_empty():
    row = _row({"attributes.http.method": "GET", "attributes.db.system": "postgres"})
    assert sm.extract_input(row) == ""
    assert sm.extract_output(row) == ""


def test_regression_dataframe_level_otel_spans_now_map():
    """The ISI-6951 symptom: a frame of OTel GenAI spans used to yield 0 records."""
    df = pd.DataFrame([
        {"attributes.gen_ai.prompt.0.content": "Q1",
         "attributes.gen_ai.completion.0.content": "A1"},
        {"attributes.gen_ai.input.messages": [{"role": "user", "content": "Q2"}],
         "attributes.gen_ai.output.messages": [{"role": "assistant", "content": "A2"}]},
        {"attributes.http.method": "GET"},  # non-LLM, correctly skipped
    ])
    mapped = [
        (sm.extract_input(r), sm.extract_output(r))
        for _, r in df.iterrows()
        if sm.extract_input(r) or sm.extract_output(r)
    ]
    assert len(mapped) == 2  # both LLM spans mapped; the HTTP span skipped


def test_attribute_columns_lists_present_keys_for_diagnostics():
    df = pd.DataFrame([{"attributes.gen_ai.system": "deepseek",
                        "attributes.http.method": "GET",
                        "name": "span"}])
    cols = sm.attribute_columns(df)
    assert cols == ["attributes.gen_ai.system", "attributes.http.method"]


if __name__ == "__main__":
    sys.exit(pytest.main([__file__, "-q"]))
