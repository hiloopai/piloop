"""Pin the public behaviour of piloop: the verdict's bootstrap and the evaluate command's output protocol.

Other tools and ports reproduce these values. Change a test here only together with a CHANGELOG entry.
"""

import json
import math
from pathlib import Path

import pytest
from pydantic import ValidationError

from piloop.plugins.campaign_type.kit.evaluation.evaluate import (
    RESULT,
    UNITS,
    UNITS_SUM_TOLERANCE,
    Failed,
    Measured,
    _check_units,
    run_evaluate,
)
from piloop.plugins.campaign_type.kit.verdicts.verdict_rule.bootstrap import RESAMPLES, SEED, Over, compare, lower_bound
from piloop.plugins.campaign_type.kit.verdicts.verdict_rule.contract import Criterion
from piloop.plugins.metric import Direction

DIFFS = [0.137, -0.052, 0.311, 0.009, -0.274, 0.198, 0.066, -0.013, 0.245, 0.102, -0.087, 0.029]


def test_the_bootstrap_draws_from_cpython_mersenne_twister_with_seed_0() -> None:
    """The lower bound is the sorted sum at index ``int((1 - confidence) * 4000)`` of ``Random(0).choices`` draws."""
    assert (RESAMPLES, SEED) == (4000, 0)
    assert lower_bound(DIFFS, 0.95) == -0.22500000000000003
    assert lower_bound(DIFFS, 0.9) == -0.030000000000000054
    assert lower_bound([1.5], 0.95) == 1.5, 'one unit: every resample is that unit'


def test_the_bootstrap_pairs_units_by_sorted_name_and_measures_gain_in_the_metric_direction() -> None:
    errors = Criterion('errors', Direction.LOWER)
    mine = {'b': 3.0, 'a': 5.0, 'd': 7.0, 'c': 0.0}
    theirs = {'a': 6.0, 'b': 2.0, 'c': 1.0, 'd': 9.0}
    c = compare(errors, 15.0, 18.0, mine, theirs, 0.95)
    assert (c.gain, c.worst, c.count, c.over) == (3.0, lower_bound([1.0, -1.0, 1.0, 2.0], 0.95), 4, Over.UNITS)
    assert c.worst == -1.0


def test_a_result_is_one_json_line_of_finite_metrics_units_and_evidence() -> None:
    line = (
        '{"metrics": {"errors": 3, "seconds": 0.5}, "units": {"errors": {"r1": 2, "r2": 1}}, "evidence": {"e": "x.md"}}'
    )
    result = RESULT.validate_json(line)
    assert (result.metrics, result.units, result.evidence) == (
        {'errors': 3.0, 'seconds': 0.5},
        {'errors': {'r1': 2.0, 'r2': 1.0}},
        {'e': 'x.md'},
    )
    assert RESULT.validate_json('{"metrics": {}}').units == {}, 'units and evidence are optional'
    for bad in ('NaN', 'Infinity', '"1"', 'true', 'null'):
        with pytest.raises(ValueError, match='metrics.errors'):
            RESULT.validate_json(f'{{"metrics": {{"errors": {bad}}}}}')
    with pytest.raises(ValueError, match='Extra inputs are not permitted'):
        RESULT.validate_json('{"metrics": {}, "cost": 1}')


def test_a_failed_or_incomplete_evaluation_gives_an_error(tmp_path: Path) -> None:
    def evaluate(script: str) -> tuple[dict[str, float], str | None]:
        [r] = run_evaluate(
            ['sh', '-c', script],
            cwd=tmp_path,
            log_dir=tmp_path,
            timeout=5,
            required={'errors', 'seconds'},
            known={'errors', 'seconds'},
            max_evidence_bytes=0,
        )
        assert isinstance(r, Measured | Failed), 'no ladder: no rung to stop at'
        return (r.metrics, None) if isinstance(r, Measured) else (r.printed, r.error)

    def write(metrics: dict[str, float]) -> str:
        return f"printf '%s\\n' '{json.dumps({'metrics': metrics})}' >> \"$PILOOP_RESULT_FILE\""

    assert evaluate(write({'errors': 3, 'seconds': 2})) == ({'errors': 3.0, 'seconds': 2.0}, None)
    assert evaluate(f'{write({"errors": 3})}; echo boom >&2; exit 1') == ({'errors': 3.0}, 'evaluate exit 1: boom'), (
        'a non-zero exit keeps what it reported next to the error: a failed evaluation has a cost too'
    )
    assert evaluate(write({'errors': 3})) == ({'errors': 3.0}, 'evaluate reported no value for: seconds')
    assert evaluate('echo METRIC errors=3; echo METRIC seconds=2') == (
        {},
        'evaluate wrote a bad result: it wrote no result to PILOOP_RESULT_FILE',
    ), 'METRIC lines on stdout are only output'


def test_per_unit_results_map_each_metric_to_finite_unit_values_that_sum_to_its_value(tmp_path: Path) -> None:
    path = tmp_path / 'units.json'

    def units(content: object, metrics: dict[str, float]) -> dict[str, dict[str, float]]:
        path.write_text(json.dumps(content))
        try:
            found = UNITS.validate_json(path.read_bytes())
        except ValidationError as e:
            raise ValueError(f'expected {{"<metric>": {{"<unit>": <number>}}}}: {e}') from e
        _check_units(found, metrics)
        return found

    assert UNITS_SUM_TOLERANCE == 1e-3
    assert units({'errors': {'r1': 2, 'r2': 1.0004}}, {'errors': 3.0, 'seconds': 1.0}) == {
        'errors': {'r1': 2.0, 'r2': 1.0004}
    }, 'a relative difference up to 1e-3 is rounding; a metric without units is fine'
    with pytest.raises(ValueError, match="units of 'errors' sum to 3.004, its value is 3"):
        units({'errors': {'r1': 2, 'r2': 1.004}}, {'errors': 3.0})
    with pytest.raises(ValueError, match="units for 'seconds', which has no value"):
        units({'seconds': {'r1': 1}}, {'errors': 3.0})
    with pytest.raises(ValueError, match="no units for 'errors'"):
        units({'errors': {}}, {'errors': 3.0})
    for bad in (math.nan, math.inf, '1', True):
        with pytest.raises(ValueError, match='expected'):
            units({'errors': {'r1': bad}}, {'errors': 1.0})
