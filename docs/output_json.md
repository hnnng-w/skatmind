# Output JSON

This document describes the JSON output produced by `skatmind`.

## JSON schema

The output JSON schema is available at:

[`schemas/output.schema.json`](../schemas/output.schema.json)

Structured declarer-concession output uses the focused schema:

[`schemas/declarer_concession_output.schema.json`](../schemas/declarer_concession_output.schema.json)

Structured defender-concession output uses:

[`schemas/defender_concession_output.schema.json`](../schemas/defender_concession_output.schema.json)

Historical declarer-concession output uses:

[`schemas/historical_declarer_concession_output.schema.json`](../schemas/historical_declarer_concession_output.schema.json)

Historical defender-concession output uses:

[`schemas/historical_defender_concession_output.schema.json`](../schemas/historical_defender_concession_output.schema.json)

Historical declarer-card-exposure output uses:

[`schemas/historical_declarer_card_exposure_output.schema.json`](../schemas/historical_declarer_card_exposure_output.schema.json)

Historical defender-open-play output uses:

[`schemas/historical_defender_open_play_output.schema.json`](../schemas/historical_defender_open_play_output.schema.json)

Historical open-card-throw output uses:

[`schemas/historical_open_card_throw_output.schema.json`](../schemas/historical_open_card_throw_output.schema.json)

Accepted declarer-card-exposure output uses:

[`schemas/declarer_card_exposure_output.schema.json`](../schemas/declarer_card_exposure_output.schema.json)

Defender-open-play and exact-proof output use:

[`schemas/defender_open_play_output.schema.json`](../schemas/defender_open_play_output.schema.json)

[`schemas/exact_rest_trick_proof.schema.json`](../schemas/exact_rest_trick_proof.schema.json)

Open-card-throw output and its bounded theoretical assessment use:

[`schemas/open_card_throw_output.schema.json`](../schemas/open_card_throw_output.schema.json)

[`schemas/theoretical_level_assessment.schema.json`](../schemas/theoretical_level_assessment.schema.json)

Ongoing exposure continuation and reusable public-hand output use:

[`schemas/declarer_card_exposure_continuation_output.schema.json`](../schemas/declarer_card_exposure_continuation_output.schema.json)

[`schemas/public_hand_constraint.schema.json`](../schemas/public_hand_constraint.schema.json)

Evidence-constrained hidden-card inference output uses:

[`schemas/hidden_card_inference_summary.schema.json`](../schemas/hidden_card_inference_summary.schema.json)

Explicit flat bounded-Search output uses:

[`schemas/bounded_search_result.schema.json`](../schemas/bounded_search_result.schema.json)

Retrospective bounded-Search output additionally uses:

[`schemas/bounded_search_post_game_review.schema.json`](../schemas/bounded_search_post_game_review.schema.json)

[`schemas/historical_search_review.schema.json`](../schemas/historical_search_review.schema.json)

[`schemas/historical_replay_coaching.schema.json`](../schemas/historical_replay_coaching.schema.json)

[`schemas/bounded_search_evaluation.schema.json`](../schemas/bounded_search_evaluation.schema.json)

Complete historical-list aggregation and compact independent-list comparison use:

[`schemas/fixed_three_player_historical_list_aggregation.schema.json`](../schemas/fixed_three_player_historical_list_aggregation.schema.json)

[`schemas/fixed_three_player_historical_list_comparison.schema.json`](../schemas/fixed_three_player_historical_list_comparison.schema.json)

Automatic Training Dataset preparation and its Plan use:

[`schemas/training_dataset_preparation_output.schema.json`](../schemas/training_dataset_preparation_output.schema.json)

[`schemas/dataset_partition_plan.schema.json`](../schemas/dataset_partition_plan.schema.json)

Opt-in public field provenance uses:

[`schemas/field_provenance.schema.json`](../schemas/field_provenance.schema.json)

The schema is intended as a documentation and validation aid. It checks the main output structure, important summary fields, and stable optional branch structures such as Multi-Step and policy-comparison results.

Generated outputs for selected examples can be validated against the schema with:

```powershell
python scripts/validate_generated_outputs_schema.py
```

The project check script also runs generated-output schema validation:

```powershell
.\scripts\check.ps1
```

Generated-output schema validation uses the real CLI and output writer. Position
scenarios use deterministic settings such as `--samples 20` and `--seed 42`.
Historical Review and Replay Coaching scenarios use their approved deterministic
settings; other historical scenarios use no position-only overrides. The
validator writes temporary output files, parses the generated JSON, validates it
against `schemas/output.schema.json`.

For the validation-layer overview and schema limitations, see:

[Schema validation documentation](schema_validation.md)

## Field-level provenance boundary

Issue #147 adds optional Root `field_provenance` for all seven workflows. It is
omitted by default and included only through Public API
`ExecutionOptionsV1(include_provenance=True)` or CLI `--include-provenance`.

The sidecar contains version `1`, the Root workflow, redaction policy, exactly one
mapped Result attachment, and provenance for artifacts actually returned. The
Result scope is `root_result_without_field_provenance`; artifact scope is
`artifact_document`. Public conversion uses the existing engine-private
redaction helper and recomputes complete coverage against the exact declared
document. It rejects uncovered, orphaned, overlapping, legacy, unavailable, or
unredacted output.

The public bundle does not contain consumed-input, decision, retrospective-
stage, aggregate-stage, or other internal Application attachments. It does not
expose hidden ownership, private proof or Search state, private seeds, caches,
branches, or Principal Variations. Provenance remains separate from Confidence,
quality, calibration, and optimality contracts.

The Training Dataset aggregation artifact maps public artifact name
`opponent_statistics_input` to attachment
`training_dataset/opponent_statistics_input`; the separate export JSON remains
unchanged and contains no nested sidecar. See
[Public field provenance](public_field_provenance.md) for all seven Result
mappings, strict fields, API/CLI examples, and limitations, and
[Complete Result provenance](complete_result_provenance.md) for the internal
source ledgers.

## Output workflows

Position analysis retains the existing top-level result. Supported historical
games instead produce exactly:

```json
{
  "input_file": "examples/historical_grand_normal_completion.json",
  "historical_game_summary": {}
}
```

`historical_game_summary` contains the canonical versioned record, ten derived
tricks, trick and skat points, final 120-point allocation, winner, game result,
game value, overbid, and final settlement. Base output contains no position,
recommendation, simulation, profile, policy, or list result. See
[Historical games](historical_games.md).

Any historical record with either non-terminal continuation also contains
`historical_game_events_summary`. It reports the exact event boundary, stable
participants, only the authorized public hand, continued-play semantics, and
explicit no-proof/no-assignment/no-settlement effects. Claimed declarer levels
remain non-settling provenance. For normal completion,
`final_outcome_source` is `actual_continued_play`; for a later shortening it is
`subsequent_terminal_shortening`, and the existing reason-specific
`historical_game_end_summary` appears beside the event summary. Zero actual plays
after the continuation is valid. See [Historical declarer-card-exposure continuation](historical_declarer_card_exposure_continuation.md)
and [Historical defender open-play continuation](historical_defender_open_play_continuation.md).

For any supported shortened historical end, `derived_tricks` contains only completed prefix tricks.
The summary adds exact play counts and remaining hand sizes, optional incomplete
current-trick plays without a winner, observed/unresolved point accounting, the
stable-ID game-end summary, adjudicated or preserved result, and declared,
accepted, or supported overbid settlement. Accepted exposure emits only the
event-authorized remaining declarer cards; reconstructed defender remaining
hands are not emitted. Historical defender open play adds exact stable-ID proof
metadata, exposing-hand cards, redacted private proof cards, rule assignment,
and final point accounting. See [Historical declarer concessions](historical_declarer_concessions.md),
[Historical defender concessions](historical_defender_concessions.md), and
[Historical declarer card exposure](historical_declarer_card_exposure.md), and
[Historical defender open play](historical_defender_open_play.md). Historical
open card throw emits the stable thrower, canonical confirmed thrown hand,
party-level trick and point assignment, jack-only theoretical assessment, and
shared settlement result without a future-play proof. See
[Historical open card throw](historical_open_card_throw.md).

When `--historical-decision-snapshots` is requested, the summary also contains
`decision_snapshot_summary`. Its version-1 `decision_time` policy provides one
chronological snapshot immediately before each actual supplied play. Normal
completion has 30; each supported shortened end has zero through 29 subject to
its event prerequisites. Each snapshot keeps
the actual card as a retrospective label and limits `visible_state` to the
acting player's remaining hand, legal cards, prior public play, public point and
hand-size state, legitimate skat knowledge, conservative visible matadors, and
ouvert exposure. It excludes final result, overbid, and settlement facts. See
[Historical decision snapshots](historical_decision_snapshots.md).
For either timed continuation, snapshots through `after_play_count` are
unchanged; later actual-card snapshots contain the shrinking exact public hand.
A same-boundary terminal shortening creates no post-event snapshot. Future
terminal evidence, final hidden hands, and settlement never enter earlier review,
Search, or training inputs.

When `--historical-game-review` is requested, the summary also contains
`historical_game_review_summary`. The version-1 object exposes fixed
`immediate_expected_value` and `decision_time` policies, sample/base-seed
settings, one row per actual decision, quality counts, and exactly three player summaries.
Each reviewed row contains all legal candidates, one recommendation, the
existing analysis report, and the existing post-game review shape. Declared-
Ouvert rows additionally expose the exact decision-relative
`public_hand_constraints` used by simulation and follow the ordinary reviewed
path. A row with confirmed failure-to-follow evidence can also contain the same
privacy-safe `hidden_card_inference_summary` as a live decision. See
[Historical game review](historical_game_review.md) and
[`historical_game_review.schema.json`](../schemas/historical_game_review.schema.json).

Historical review quality counts summarize decisions; they are not player
grades, percentages, skill ratings, winners, or rankings. The review evaluates
the immediate heuristic, not perfect-information or complete-contract optimal
play, and is not a training/evaluation dataset record.

When `--historical-search-review` is requested, the historical summary adds
`historical_search_review_summary`. It uses schema version `1`,
`analysis_method: "bounded_search_with_immediate_baseline"`, and
`information_policy: "decision_time"`. Every actual decision contains stable
identity and position metadata, an independently executed Immediate baseline,
the strict bounded Search result, an actual-card comparison, and a Search-versus-
Immediate comparison.

Its top-level and breakdown metrics include:

* `decision_counts` for attempts, availability, and recommendations
* all `status_counts` and exact, sampled, or no-coverage counts
* Search-versus-Immediate recommendation agreement
* actual-card top-1 and top-3 aggregate agreement, based on the number of
  strictly better aggregate candidates so canonical ordering of tied cards does
  not change the metric
* `search_better`, `aggregate_equivalent`, and unavailable comparison counts
* the Search-not-worse `quality_gate`
* totals, mean, nearest-rank p50/p95, and maximum for nodes, selected/completed/
  sampled worlds, depth, and elapsed milliseconds, plus fallback count

Breakdowns use game type, local side, root seat, remaining tricks, Search status,
and coverage. A zero-decision historical record is valid: arrays are empty,
counts and totals are zero, rates and percentiles are null, and the quality gate
passes with zero comparable decisions.

`settings` records the explicit base Search seed, named immutable profile,
expanded requested budget, Immediate sample count, and nullable Immediate base
seed. Each private Search seed is derived from
`historical_bounded_search_decision_v1`, the stable game ID, and decision index;
no derived seed is serialized. Future cards, private historical hands, world
assignments, and settlement do not enter or appear in a decision row.

When `--historical-replay-coaching` is requested, the historical summary adds
`historical_replay_coaching_summary`. The strict report version is `1`, its
method is `historical_replay_coaching_v1`, its information policy is
`decision_time_then_retrospective_attachment`, and its outcome-context policy is
`final_context_after_coaching`. Supplying both Replay Coaching and Historical
Search Review emits both summaries from one shared Search/Immediate pass;
Coaching-only output does not add `historical_search_review_summary`.

The report contains privacy-safe game/player context, public source-review
settings, one chronological assessment per actual card decision, at most five
Key Decisions, bounded Turning Points, one-game player/role/phase/contract
patterns, fixed-template decision and pattern recommendations, complete coverage
counts, exactly three player summaries, two role summaries, three phase
summaries, one contract summary, and separately attached allowlisted final
outcome context. Empty Key Decision, Turning Point, pattern, and recommendation
arrays are valid, and a zero-decision record has an empty assessment array. Null
recommendations use contract-objective wording rather than raw card-point-margin
advice.

Final outcome context describes how the recorded game ended. It is not decision-
time evidence and does not change Coaching classification.

When `--historical-tactical-motif-review` is requested, the historical summary
adds `historical_tactical_motif_review_summary`. The strict report version is
`1`, its method is `historical_tactical_motif_review_v1`, and it contains one
chronological observation per recorded actual Card. Decision Facts precede the
actual Card, immediate current-winner facts follow the Card, and completed-Trick
winner/points and outcome motifs appear only after Trick completion.

The report contains exact motif/family counts, complete Player/role/phase/
contract scopes, complete/partial observation totals, and explicit limitations.
It never contains complete own hands, complete legal-Card sets, hidden ownership,
Search Worlds, Commentary, Response Links, quality labels, signaling,
communication, or causal conclusions. A valid incomplete final Trick yields
partial observations with null completed-Trick fields; zero recorded Cards yield
empty observations and complete zero-count scopes.

The recursive public boundary excludes initial/final/private hands, final hidden
ownership, Skat identities, discards, compatible-world identities and contents,
private Search states, selected worlds, ownership assignments, exact proof
internals, derived child seeds, caches, branches, principal variations, ratings,
grades, and rankings. Aggregate compatible-world counts and coverage remain
privacy-safe evidence metadata. The report makes no causal final-outcome, player-
weakness, permanent-trait, statistical-significance, perfect-play, or optimal
hidden-information claim. See
[Replay coaching contracts](replay_coaching_contracts.md)
and [`historical_replay_coaching.schema.json`](../schemas/historical_replay_coaching.schema.json).

Training-dataset input produces a separate stable branch:

```json
{
  "input_file": "examples/training_dataset_normal_play.json",
  "training_dataset_summary": {
    "schema_version": 1,
    "dataset_id": "online-games-2026",
    "dataset_version": "1",
    "feature_generation_version": 1,
    "target": "actual_card_played",
    "record_count": 2,
    "sample_count": 60,
    "partition_counts": {},
    "records": []
  }
}
```

Every output record preserves provenance and the canonical validated historical
game and contains one ordered sample per snapshot. Zero-sample records remain
present. Sample metadata contains stable
traceability identities. Features contain only decision-time state and use
`me`, `left`, and `right` for player references. The separate label contains the
legal historical actual card. Final results, settlement, recommendations, and
review quality do not appear in features or labels. All three partition counts
are always present and reconcile with total and per-record counts. See
[Training data](training_data.md) and
[`training_dataset_output.schema.json`](../schemas/training_dataset_output.schema.json).

`--evaluate-bounded-search` produces a separate branch instead of
`training_dataset_summary`:

```json
{
  "input_file": "examples/training_dataset_normal_play.json",
  "bounded_search_evaluation_summary": {
    "schema_version": 1,
    "evaluation_method": "bounded_search_vs_immediate_v1",
    "source_dataset": {},
    "settings": {},
    "selection": {},
    "decision_counts": {},
    "status_counts": {},
    "coverage": {},
    "search_vs_immediate_agreement": {},
    "quality_gate": {},
    "actual_card_agreement": {},
    "search_aggregate_quality": {},
    "performance": {},
    "breakdowns": {},
    "records": []
  }
}
```

Selection defaults to `validation` and `test`. `max_decisions` is nullable and
caps one stable global decision prefix. `available_decision_count` counts source
decisions before the cap, `evaluated_decision_count` is the selected prefix, and
`decision_cap_reached` reports truncation. Every selected record remains in
`records`, including records with zero source decisions or an empty evaluated
prefix; `zero_decision_record_count` counts the former.

The quality gate includes only available Search-versus-Immediate comparisons:
`search_not_worse_count` equals strictly better plus equivalent, and violations
equal comparable minus not worse. It passes exactly when violations are zero.
This is Search-aggregate arithmetic, not proof of an optimal policy or calibrated
sample quality. Evaluation breakdowns add `by_partition` to the historical
dimensions. Performance elapsed times are diagnostics and provide no latency
guarantee.

Dataset partition audit produces a separate sample-free branch:

```json
{
  "input_file": "examples/training_dataset_partition_audit.json",
  "dataset_partition_audit_summary": {
    "schema_version": 1,
    "audit_version": 1,
    "source_dataset": {},
    "declared_partition_policy": null,
    "effective_audit_mode": "report_only",
    "compliance_status": "not_evaluated",
    "partition_summary": {},
    "player_summary": {},
    "overlap_summary": {},
    "known_opponent_coverage": {},
    "unseen_player_compliance": {},
    "players": []
  }
}
```

The branch contains complete deterministic exact-ID membership, pairwise and
three-way overlap, directed membership coverage, and unseen-player compliance.
It contains no samples, recommendations, simulations, profiles, or models. See
[Dataset partition policies](dataset_partition_policies.md) and
[`dataset_partition_audit.schema.json`](../schemas/dataset_partition_audit.schema.json).

Automatic Training Dataset preparation produces the separate root-selected
branch:

```json
{
  "input_file": "examples/training_dataset_preparation_known_opponent.json",
  "training_dataset_preparation_summary": {
    "preparation_version": 1,
    "plan": {},
    "training_dataset_input": {},
    "partition_audit": {}
  }
}
```

Those are the exact four result fields. Mode `known_opponent` derives Plan
algorithm `temporal_known_opponent_v1`; `unseen_player` derives
`component_balanced_unseen_player_v1`. For status `complete`, the nested
`training_dataset_input` is a losslessly reusable existing version-1 Training
Dataset, and `partition_audit` exactly matches the Plan audit. Plan and concise
CLI output contain no cards, but the complete wrapper intentionally contains all
source cards inside the nested reusable dataset.

For status `unavailable`, the command still succeeds. The Plan contains the
explicit reason but no assignments, partition summaries, temporal audit, or
partition audit; both wrapper fields `training_dataset_input` and
`partition_audit` are null. There is no partial or fallback result. See
[Automatic dataset preparation contracts](automatic_dataset_preparation_contracts.md)
and [`training_dataset_preparation_output.schema.json`](../schemas/training_dataset_preparation_output.schema.json).

Opponent-statistics input produces a separate stable branch:

```json
{
  "input_file": "examples/opponent_statistics.json",
  "opponent_statistics_summary": {
    "schema_version": 1,
    "record_count": 2,
    "records": []
  }
}
```

Records preserve player identity, optional labels, provenance, total games, and
the original `0..100` percentage-point `statistics`. Separate
`normalized_profile_statistics` values divide each percentage by `100` and copy
`games_played`. When optional `exact_counts` is absent,
`solo_games_played` and `defender_games_played` remain `null`; when present,
their exact values are copied and used as exact derivation evidence. This
includes additive `defender_rate`. `profile_derivation` contains
versioned scoped heuristic confidence, exact or estimated evidence provenance,
all signals and reasons, classification, recommended and nullable actionable
preset, decisive signals, and explanations.
`validation_metadata.percentage_sum_tolerance_points` is always `2.0`. The
derived preset is not applied; no recommendation, simulation, or historical
result is included. See [Opponent statistics](opponent_statistics.md),
[Opponent profile derivation](opponent_profile_derivation.md), and
[`opponent_statistics_output.schema.json`](../schemas/opponent_statistics_output.schema.json).

Historical opponent-statistics aggregation produces another separate branch:

```json
{
  "input_file": "examples/training_dataset_normal_play.json",
  "historical_opponent_statistics_aggregation_summary": {
    "schema_version": 1,
    "aggregation_version": 1,
    "source_dataset": {},
    "selection": {
      "included_partitions": ["train", "validation"],
      "before": "2026-07-21T00:00:00Z",
      "excluded_record_counts_by_partition": {
        "train": 0,
        "validation": 0,
        "test": 0
      },
      "excluded_record_count_by_temporal_cutoff": 0
    },
    "source_record_count": 2,
    "source_game_count": 2,
    "player_count": 3,
    "first_played_at": "2026-07-10T18:00:00+02:00",
    "last_played_at": "2026-07-20T19:00:00+02:00",
    "records": []
  }
}
```

Selected partitions, declared partition policy provenance, and the nullable strict cutoff are preserved. Exclusion
counts distinguish partition filtering from temporal filtering. Every player
record contains `historical_games` provenance, exact counts, exact-count-derived
percentages, normalized statistics, and the unchanged profile derivation.
`source.captured_at` equals that player's latest included source-game instant.
The branch contains no training samples, recommendation, review, policy
application, or quality result. See
[Historical opponent statistics](historical_opponent_statistics.md) and
[`historical_opponent_statistics_aggregation.schema.json`](../schemas/historical_opponent_statistics_aggregation.schema.json).
Normal and shortened records use the same shape. A shortened record contributes only
existing game-level counts and provenance; no event, consent/acceptance, hand, trick, or
unresolved-point detail enters the output or export.

Rolling opponent-policy evaluation produces a dedicated branch:

```json
{
  "input_file": "examples/historical_opponent_policy_evaluation_dataset.json",
  "rolling_opponent_policy_evaluation_summary": {
    "schema_version": 1,
    "evaluation_version": 1,
    "source_dataset": {},
    "selection": {},
    "coverage": {},
    "baseline_results": {},
    "actionable_profile_paired_results": {},
    "breakdowns": {},
    "target_games": []
  }
}
```

Selection metadata identifies `known_opponent` mode and bounded source/target
player overlap without claiming temporal eligibility. The baseline covers every target decision. Profile and paired-baseline metrics
cover only actionable profile predictions. Preferred-card matching is primary;
exact-card matching is the stricter tie-break-sensitive metric. Target games
contain compact as-of player provenance and profiles plus zero through 30 ordered
actual decisions. Empty decision arrays and zero total decisions are valid, and
zero-denominator rates are null. Coverage counts all target participants while
decision breakdowns count only actual actors. Decision objects contain no end
reason, consent, final winner, settlement, unresolved points, or remaining
cards. See
[Rolling opponent-policy evaluation](opponent_policy_evaluation.md) and
[`rolling_opponent_policy_evaluation.schema.json`](../schemas/rolling_opponent_policy_evaluation.schema.json).

## Fixed-three-player historical lists

Single-list input produces exactly:

```json
{
  "input_file": "examples/fixed_three_player_historical_list_mixed.json",
  "fixed_three_player_historical_list_summary": {}
}
```

The summary is the complete existing aggregation serialization: version and
fixed basis, source version and list ID, 36 positions, twelve rounds, Played
Game and Passed Deal counts, declarer result counts, exactly three final player
totals, one progression snapshot per position, ranking status, tied and
lot-required IDs, nullable applied lot, and exactly three final standings. Every
snapshot retains one privacy-safe Entry Fact, three cumulative totals, three
provisional standings, and tied IDs. Passed Deal game, end, declarer, and
settlement fields remain null.

Comparison input produces exactly:

```json
{
  "input_file": "examples/fixed_three_player_historical_list_comparison.json",
  "fixed_three_player_historical_list_comparison_summary": {}
}
```

The compact result preserves the first reference, source order, exactly three
reference-ordered player IDs, one compact summary per source, and one pairwise
comparison per non-reference list. Pairwise list-count and all fourteen player-
total deltas are `comparison - reference`. Table places are retained for each
source. `rank_position_change = reference_rank - comparison_rank`, so a positive
value means movement toward rank 1. Rank status is exactly `available`,
`reference_lot_required`, `comparison_lot_required`, or `both_lot_required`.
When unresolved, all rank fields are null while metric deltas remain present.

Neither output echoes the source list or a Historical Game Record. Public list
output excludes hands, Skat identities, discards, trick cards, private ownership,
Search state, and proof state. Comparison additionally excludes progression and
Entry Facts. The output is descriptive list analysis, not a series, rating,
winner analysis, official cross-list ranking, player-skill claim, or list
recommendation.

## Position top-level fields

Typical top-level fields include:

| Field                            | Meaning                                                     |
| -------------------------------- | ----------------------------------------------------------- |
| `input_file`                     | Source input file.                                          |
| `position`                       | Normalized position data.                                   |
| `settings`                       | Simulation settings.                                        |
| `opponent_policy_settings`       | Global opponent policy configuration.                       |
| `profile_preset_settings`        | Profile-preset configuration.                               |
| `analysis_metadata`              | Strategic and analysis metadata.                            |
| `game_declaration`               | Serializable game declaration.                              |
| `game_value_summary`             | Game value calculation result.                              |
| `overbid_summary`                | Bid-value and overbid evaluation.                           |
| `legal_cards`                    | Legal cards for the current decision.                       |
| `analysis_report`                | Card analysis report.                                       |
| `strategic_summary`              | Human-readable strategic summary.                           |
| `score_summary`                  | Raw known card-point summary.                               |
| `game_result_summary`            | Raw game result before game-end adjustment.                 |
| `adjusted_game_result_summary`   | Game result after game-end adjustment.                      |
| `final_settlement_summary`       | Single-game settlement summary.                             |
| `performance_rating_summary`     | Performance-rating layer.                                   |
| `list_standings_summary`         | Optional fixed three-player list standings.                 |
| `recommendation`                 | Recommended card and reason.                                |
| `recommendation_method_summary`  | Optional explicit-method routing and fallback summary.      |
| `bounded_search_result`          | Optional strict bounded-Search aggregate result or null.    |
| `bounded_search_post_game_review_summary` | Optional flat Search actual-card and Search-versus-Immediate aggregate comparisons. |
| `post_game_review_summary`       | Actual-card comparison and post-game review result.         |
| `multi_step_result`              | Optional multi-step simulation result.                      |
| `policy_comparison_result`       | Optional policy-comparison result.                          |
| `hidden_card_inference_summary`  | Optional exact evidence-constrained compatible-world summary. |
| `information_policy_summary`     | Summary of the active live-vs-post-game information policy. |
| `left_opponent_policy_settings`  | Normalized policy settings for the left opponent.           |
| `right_opponent_policy_settings` | Normalized policy settings for the right opponent.          |
| `opponent_profile_application_summary` | Optional live external-profile binding, precedence, and effective-policy summary. |
| `field_provenance`               | Optional version-1 public-safe provenance for the exact Root Result without this field and for actual artifacts. |

`profile_preset_settings` is emitted in production output and is required by
the output schema.

`recommendation_method_summary` and `bounded_search_result` are emitted only
when input explicitly supplies `recommendation_method`. Omitted-method output
retains the previous field set exactly.

`opponent_profile_application_summary` is emitted only when
`--opponent-statistics-file` is supplied for a live analysis. It records each
side's exact binding, effective manual/external/none profile source, compact
source provenance and derivation, application status, reason, actionable preset,
and effective lead/response policies. Those policies must match the existing
`left_opponent_policy_settings` and `right_opponent_policy_settings`. Source
percentage statistics are not duplicated. See
[Live opponent profiles](live_opponent_profiles.md) and
[`opponent_profile_application.schema.json`](../schemas/opponent_profile_application.schema.json).

## Position

`position` echoes normalized position metadata. It includes `declarer_player`, the concrete declarer seat after input normalization.

`position` describes the normalized input position. For opponent-turn inputs it
can legitimately show `next_player` as `left` or `right`. It is not replaced by
any internally prepared Multi-Step state.

For local declarer inputs that omit `declarer_player`, output uses:

```json
"declarer_player": "me"
```

For local defender inputs, `declarer_player` is required in input and is echoed as `left` or `right`.

## Opponent policy settings

The output contains global and normalized left/right opponent policy settings.

Example:

```json
{
  "opponent_policy_settings": {
    "opponent_lead_policy": "lowest_point",
    "opponent_response_policy": "lowest_point"
  },
  "left_opponent_policy_settings": {
    "opponent_lead_policy": "highest_point",
    "opponent_response_policy": "basic_trick_play"
  },
  "right_opponent_policy_settings": {
    "opponent_lead_policy": "basic_defender_lead",
    "opponent_response_policy": "basic_defender_response"
  }
}
```

Meaning:

| Field                            | Meaning                                                           |
| -------------------------------- | ----------------------------------------------------------------- |
| `opponent_policy_settings`       | Global opponent policy settings and backward-compatible fallback. |
| `left_opponent_policy_settings`  | Normalized policy settings for the left opponent.                 |
| `right_opponent_policy_settings` | Normalized policy settings for the right opponent.                |

The three settings objects are resolved effective settings. Global presets and global
lead/response policies cascade to both sides, and side-specific settings override only
their side.

Multi-step behavior:

* `right` lead uses `right_opponent_policy_settings.opponent_lead_policy`.
* `left` lead uses `left_opponent_policy_settings.opponent_lead_policy`.
* `right` response after a left lead uses `right_opponent_policy_settings.opponent_response_policy`.
* Candidate trick completion uses the same activated response-policy map as immediate analysis.

## Game declaration

Example:

```json
"game_declaration": {
  "game_type": "grand",
  "hand_game": false,
  "ouvert": false,
  "schneider_announced": false,
  "schwarz_announced": false,
  "matadors": 2,
  "bid_value": 72
}
```

`matadors` can be explicitly provided in the input. If it is missing or `null`, the engine may infer it from known declarer-card context where possible, including conservative concrete-declarer completed-trick ownership facts when `cards`, ordered `players`, and concrete `declarer_player` are available.

## Game value summary

Example:

```json
"game_value_summary": {
  "game_type": "grand",
  "is_null_game": false,
  "base_value": 24,
  "game_level": 3,
  "game_value": 72,
  "details": {
    "is_complete": true,
    "matadors": 2,
    "matador_multiplier": 3,
    "hand_game": false,
    "schneider_announced": false,
    "schwarz_announced": false,
    "ouvert": false,
    "modifier_multiplier": 0
  }
}
```

If required inputs are missing and matadors cannot be inferred, `game_value` may be `null`.

Suit and Grand game values are `base_value * game_level`. The supported base
values are Clubs `12`, Spades `11`, Hearts `10`, Diamonds `9`, and Grand `24`.
The game level combines the matador multiplier with supported declaration
modifiers such as Hand, Schneider announced, Schwarz announced, and Ouvert.
Null variants use fixed values: Null `23`, Null Hand `35`, Null Ouvert `46`, and
Null Hand Ouvert `59`.

## Overbid summary

Example:

```json
"overbid_summary": {
  "bid_value": 60,
  "game_value": 48,
  "is_overbid": true,
  "margin": -12,
  "required_game_value": 72,
  "status": "overbid"
}
```

Fields:

| Field                 | Meaning                                                                 |
| --------------------- | ----------------------------------------------------------------------- |
| `bid_value`           | Bid value from input, or `null`.                                        |
| `game_value`          | Calculated game value, or `null`.                                       |
| `is_overbid`          | `true`, `false`, or `null` if unknown.                                  |
| `margin`              | `game_value - bid_value`. Negative means overbid.                       |
| `required_game_value` | Smallest reachable Suit/Grand game value that covers the bid.           |
| `status`              | `not_overbid`, `overbid`, `unknown_bid_value`, or `unknown_game_value`. |
| `impossible_null_settlement` | Calculated replacement summary for the impossible Null branch, otherwise absent; `null` when its selection is missing. |

For a complete impossible Null selection, the dedicated summary is:

```json
"impossible_null_settlement": {
  "replacement_game_type": "clubs",
  "matadors": 1,
  "hand_game": false,
  "base_value": 12,
  "minimum_game_value": 24,
  "required_game_value": 24
}
```

The original Null `game_value`, bid, margin, and overbid status remain visible.
The replacement is not serialized as a changed declaration. Its Hand status
follows the original skat-pickup status; Null ouvert is not transferred.

## Score summary

`score_summary` combines explicit points and completed-trick points.
Explicit side points exclude card points already represented by
`completed_tricks`; completed-trick cards provide their own point contribution.

Example:

```json
"score_summary": {
  "explicit_declarer_points": 20,
  "explicit_defender_points": 10,
  "completed_trick_declarer_points": 31,
  "completed_trick_defender_points": 25,
  "total_declarer_points": 51,
  "total_defender_points": 35
}
```

## Game result summary

`game_result_summary` describes the raw game result before game-end adjustment.
Suit and Grand results use card points. Normally completed Null results use
completed-trick ownership when ten reliable completed tricks are available:
the declarer wins only with zero declarer tricks, and any declarer trick loses
Null even if that trick is worth zero card points. Incomplete Null games remain
incomplete and are not declared wins merely because the declarer has not yet
taken a trick.

The `winner` field represents the game or contract winner, not the side that
won the most tricks.

Example:

```json
"game_result_summary": {
  "declarer_points": 75,
  "defender_points": 45,
  "points_remaining": 0,
  "is_complete": true,
  "winner": "declarer"
}
```

## Adjusted game result summary

`adjusted_game_result_summary` applies a legacy `game_end_reason` or structured
game-shortening adjudication.

For example, if the declarer claims remaining tricks, remaining card points are assigned to the declarer.

For `impossible_null_declaration`, it instead records a final defenders' win
without assigning card points. Raw zero-point values remain visible, while raw
and effective Schneider/Schwarz statuses are `not_applicable` because no card
play occurred.

For structured declarer concession, observed points and `points_remaining` are
preserved. The result is final and adjudicated with defenders as winner,
`remaining_points_recipient: null`, and `remaining_points_assigned: 0`. It does
not manufacture totals summing to 120.

Structured defender concession also preserves both observed totals and
`points_remaining`, with no recipient and zero assigned points. It records the
pre-concession decision, preserves an already-decided winner, and grants only an
undecided game to the declarer. The final winner therefore does not require a
fictitious 120-point total.

Accepted declarer card exposure has the same no-assignment policy. It records a
final adjudicated result for an undecided game, preserves a preexisting winner,
and cannot reverse a preexisting declarer loss. Accepted Schneider or Schwarz
claims do not set achieved-play statuses.

Example:

```json
"adjusted_game_result_summary": {
  "declarer_points": 75,
  "defender_points": 45,
  "points_remaining": 0,
  "is_complete": true,
  "winner": "declarer",
  "game_end_reason": "declarer_claimed_remaining_tricks",
  "remaining_points_recipient": "declarer",
  "remaining_points_assigned": 29
}
```

## Game-shortening summary

`game_shortening_summary` is present only for a structured union member.
Declarer concession records hand-count reconciliation and consent. Defender
concession records the concrete conceding player, concession form, complete
defender joint liability, pre-concession decision, winner basis, deterministic
ISkO sections, no point assignment, and `continued_play_requested: false`.

Declarer card exposure records the exposure form, optional shown defender,
canonical exposed cards, `confirmed` or `not_verifiable` reconciliation, both
accepting defenders and acceptance forms, claimed level, prior decision state,
winner basis, `continued_play_required: false`, and no point assignment.

The defender-open-play member is the bounded exception. It records the exposing
and non-exposing defenders, exposed cards, unresolved-trick count, exact proof
status and quantifiers, deterministic search statistics, a privacy-redacted
canonical line, the rest-trick assignment, winner basis, and applicable ISkO
sections. Completeness comes from exhaustive search, not from the displayed line.
The declarer's and non-exposing defender's exact hands are never emitted.

The open-card-throw member records the concrete throwing player, derived parties,
defender joint liability, canonical thrown cards, `confirmed` or
`not_verifiable` reconciliation, statement provenance, pre-throw decision,
observed and rule-assigned trick and point totals, final winner, open-throw
Schneider and Schwarz flags, and the jack-only theoretical assessment. Only the
thrown hand is public. A non-throwing local hand is redacted, and no exact proof
or hidden complete hand is emitted.

## Game-continuation summary

`game_continuation_summary` is present only for the separate ongoing continuation
union. The declarer-exposure member records version and kind, ISkO section `4.4.4`, concrete declarer,
exposure form, both canonical defender responses, continuing and accepting
defenders, canonical current public cards, `confirmed` or `not_verifiable`
reconciliation, and `visibility_scope: "all_players"`.

`claimed_play_level_status` is
`continuation_required_no_immediate_settlement_effect`. The summary explicitly
reports `game_end_applied: false` and `settlement_applied: false`. It contains no
hidden defender cards, accepted claim, winner, point assignment, or settlement
basis.

The defender-open-play member records sections `4.4.5` and `4.1.6`, concrete
declarer and both defenders, the continuation response, returned/not-physically-
open status, canonical public exposing-defender cards, and `confirmed` or
`not_verifiable` reconciliation. It reports
`not_adjudicated_due_to_continued_play`,
`open_play_consequence_disregarded`, and false proof, game-end, and settlement
flags. It emits no private other hand, proof line, rest-trick or point assignment,
decided winner, or settlement basis.

## Final settlement summary

`final_settlement_summary` describes single-game settlement.

Example:

```json
"final_settlement_summary": {
  "is_complete": true,
  "missing_inputs": [],
  "declarer_won_by_card_points": true,
  "winner": "declarer",
  "game_value": 72,
  "effective_game_value": 72,
  "bid_value": 72,
  "settlement_score": 72,
  "is_loss": false,
  "is_overbid": false,
  "overbid_margin": 0,
  "overbid_status": "not_overbid",
  "overbid_required_game_value": 72
}
```

`effective_game_value` is the value used for settlement scoring.

The public field `declarer_won_by_card_points` is retained for compatibility.
For Suit and Grand it describes the card-point result. For Null it reflects the
base contract result, even though Null is decided by trick ownership rather than
card points.

For completed non-null suit and grand games with achieved Schneider,
`effective_game_value` includes one additional base-value level while
`game_value` remains the declared/pre-result value.

For completed non-null suit and grand games with achieved Schwarz,
`effective_game_value` includes one additional Schwarz base-value level when a
reliable ten-trick completed history proves that the losing side took no tricks.
Schwarz is not inferred from card points. If Schwarz was announced and reliable
trick ownership proves the announcement failed, `is_loss` is `true` and
`settlement_score` is negative even when `winner` and
`declarer_won_by_card_points` show a declarer card-point win.

This slice does not add a public Schwarz-status field to
`final_settlement_summary`. Schwarz settlement is reflected through existing
fields: `effective_game_value`, `settlement_score`, `is_loss`, and the derived
`performance_rating_summary.game_outcome`.

For supported Suit/Grand overbid cases, `effective_game_value` equals `required_game_value`.

For structured declarer concession, `declarer_won_by_card_points` is `null`,
`winner` is `defenders`, and the score is twice the effective value as a loss.
Declared Hand, Schneider, Schwarz, and ouvert levels remain in `game_value`.
`settlement_basis` reports an adjudicated outcome, no achieved Schneider or
Schwarz addition, and whether overbid-required valuation changed the effective
value. An overbid-required level is valuation and is never labeled as achieved.
All four Null variants use their fixed declared values.

For structured defender concession, `settlement_basis` distinguishes an
adjudicated undecided game from a preexisting decision. It separately reports a
mandatory announced or overbid-required level, levels secured during observed
play, and overbid-required valuation. An undecided game does not gain optional
unannounced Schneider or Schwarz. A preexisting loss remains a doubled loss.
All four Null variants use reliable completed declarer-trick ownership rather
than card points and retain their fixed values.

For accepted declarer card exposure, `settlement_basis` separately identifies
declared mandatory, accepted claimed, achieved-during-play, and overbid-required
levels. An undecided Suit or Grand game uses the highest declared mandatory or
accepted claimed play level. Supported overbid requirements must be covered by
that declaration or claim. Null permits only `simple` and uses its fixed value.
No remaining card points are assigned.

For defender open play, `settlement_basis` distinguishes the preexisting
decision, exact proof status, valid or invalid open play, rule-assigned rest
tricks, normally achieved Schneider or Schwarz, mandatory levels awarded under
ISkO 4.1.5, and supported overbid-required valuation. Valid proof assigns every
rest trick and all outstanding points to the defenders. Invalid proof records
the corresponding declarer assignment without treating it as normally achieved
play. An undecided invalid Suit or Grand claim gives the declarer the simple
game unless a bounded mandatory level applies. An undecided invalid Null claim
also gives the declarer the fixed-value contract and does not reinterpret the
rule assignment as a played declarer trick.

For open card throw, `settlement_basis` separates the preexisting decision,
opposing-party rest-trick recipient, final-point Schneider source, rule-state
Schwarz source, jack-only theoretical status, declared mandatory level,
supported overbid requirement, achieved-play flags, and open-throw rule flags.
Suit and Grand reconcile to 120 points and ten party-level tricks. Null uses
completed and rule-assigned declarer tricks, fixed values, and no Schneider or
Schwarz. A preexisting result remains binding even if the later assignment would
otherwise reverse it.

An ongoing continuation does not enter an adjudication settlement path. The
4.4.4 requested level is provenance only; the 4.1.6 request creates no optional
Schneider or Schwarz obligation. The original declaration remains binding, and
the ordinary incomplete `final_settlement_summary` remains incomplete until
actual play supplies a real completed result.

For an impossible Null declaration, `declarer_won_by_card_points` is `null`,
`winner` is `defenders`, and `is_loss` is `true`. Complete replacement metadata
sets `effective_game_value` to its `required_game_value` and scores
`-2 * required_game_value` without requiring points or tricks. Missing metadata
leaves `settlement_score` `null`, sets
`missing_inputs` to `["impossible_null_settlement"]`, and exposes the dedicated
summary as `null`.

For completed Null settlements, the fixed Null variant value is used directly.
A won Null settlement scores `+game_value`; a lost Null settlement scores
`-2 * game_value`. Normally completed Null results are based on reliable
ten-trick ownership, not card-point winner thresholds.

## Information policy summary

`information_policy_summary` describes which information-boundary rules apply to the analysis.

Example for live analysis:

```json
{
  "analysis_mode": "live_decision",
  "skat_visibility": "unknown",
  "game_end_reason": "not_ended",
  "live_information_enforced": true,
  "known_post_game_skat_allowed": false,
  "known_skat_cards_allowed": false,
  "ended_game_allowed": false,
  "unverifiable_completed_trick_winner_metadata_allowed": false
}
```

Example for post-game review:

```json
{
  "analysis_mode": "post_game_review",
  "skat_visibility": "known_post_game",
  "game_end_reason": "normal_completion",
  "live_information_enforced": false,
  "known_post_game_skat_allowed": true,
  "known_skat_cards_allowed": true,
  "ended_game_allowed": true,
  "unverifiable_completed_trick_winner_metadata_allowed": true
}
```

Fields:

| Field                                                  | Meaning                                                                                |
| ------------------------------------------------------ | -------------------------------------------------------------------------------------- |
| `analysis_mode`                                        | Active analysis mode.                                                                  |
| `skat_visibility`                                      | Whether the skat is unknown, declarer-private during play, or known from post-game review. |
| `game_end_reason`                                      | Game-end metadata used for remaining-point assignment.                                 |
| `live_information_enforced`                            | Whether live-information restrictions are active.                                      |
| `known_post_game_skat_allowed`                         | Whether post-game skat visibility is allowed.                                          |
| `known_skat_cards_allowed`                             | Whether known skat cards are allowed in the input under the selected visibility.       |
| `ended_game_allowed`                                   | Whether completed game states are allowed.                                             |
| `unverifiable_completed_trick_winner_metadata_allowed` | Whether winner metadata without full verification context is allowed.                  |
| `public_hand_constraints`                              | Optional rule-authorized exact public hands from declared Ouvert or the supported continuation union. |

Each public-hand constraint identifies its concrete owner, all-player visibility,
count, canonical cards, and source `declared_ouvert`,
`declarer_card_exposure_continuation`, or
`defender_open_play_continuation`. Identical same-player evidence is emitted once;
a disjoint declared-Ouvert hand and public defender continuation hand may both be
present. Other hands, private proof evidence, and hidden skat remain protected.

## Hidden-card inference summary

`hidden_card_inference_summary` is emitted only when attributed public play
provides at least one confirmed legal failure-to-follow constraint. Its stable
strict schema version is `1`. The summary reports:

* `information_cutoff: "current_decision"`, mode
  `exact_evidence_constrained`, and compatible-world model
  `uniform_labeled_assignments`;
* the exact `compatible_world_count`, hypothetical skat size, provenance status,
  and counts of confirmed void evidence and exact public hands;
* confirmed structural evidence, forbidden effective categories, and exact
  per-card `left`/`right`/`skat` ownership probabilities;
* the most likely owner, possible owners, `exact_owner_confirmed`, and confidence
  `confirmed`, `high`, `medium`, or `low`;
* fixed thresholds `0.85` and `0.65`, concentration basis, and
  `confidence_is_calibrated: false`; and
* explicit `behavioral_inference_applied: false`,
  `future_information_used: false`, and privacy fields.

`confirmed` means exactly one compatible owner; otherwise `high` starts at
`0.85`, `medium` at `0.65`, and `low` is below `0.65`. These labels do not add a
constraint or world weight.

Every privacy flag is `false`: no sampled hand, sampled hypothetical skat,
coherent-root ownership, actual historical hidden hand, or dynamic-programming
table is emitted. Ownership marginals summarize all compatible assignments and
do not reveal the private sampled execution root. See
[Hidden-card inference](hidden_card_inference.md).

## Performance rating summary

`performance_rating_summary` is separate from single-game settlement.

Example for a won declarer game with `rating_system = "isko_list"`:

```json
"performance_rating_summary": {
  "is_implemented": false,
  "is_partially_implemented": true,
  "implemented_scope": "declarer_single_game_rating",
  "unsupported_scope": "full_list_series_tournament_rating",
  "rating_system": "isko_list",
  "table_player_count": 3,
  "basis": "individual_game_settlement",
  "game_outcome": "declarer_win",
  "settlement_score": 72,
  "rating_score": 122,
  "declarer_rating_score": 122,
  "declarer_rating_points": 50,
  "counterparty_rating_points": 0,
  "defender_rating_points": 0,
  "unsupported_reason": "full_list_series_tournament_rating_not_implemented"
}
```

Meaning:

| Field                        | Meaning                                      |
| ---------------------------- | -------------------------------------------- |
| `rating_score`               | Alias for `declarer_rating_score`.           |
| `declarer_rating_score`      | `settlement_score + declarer_rating_points`. |
| `declarer_rating_points`     | +50 for declarer win, -50 for declarer loss. |
| `counterparty_rating_points` | Points per counterparty player.              |
| `defender_rating_points`     | Alias for `counterparty_rating_points`.      |
| `implemented_scope`          | Scope currently calculated.                  |
| `unsupported_scope`          | Scope still missing.                         |

## List performance summary

`list_performance_summary` is emitted only when the input contains
`list_performance_input`, `list_game_contributions`, or
`list_analysis_results`.

It is separate from both `performance_rating_summary` and `final_settlement_summary`.

Example:

```json
"list_performance_summary": {
  "rating_system": "isko_list",
  "basis": "aggregated_list_or_series_totals",
  "table_size": 3,
  "player_game_points": 120,
  "own_games_won": 3,
  "own_games_lost": 1,
  "other_players_lost_games": 2,
  "own_game_bonus_points": 100,
  "opponent_loss_bonus_points": 80,
  "total_performance_points": 300
}
```

Meaning:

| Field                        | Meaning                                                       |
| ---------------------------- | ------------------------------------------------------------- |
| `basis`                      | `aggregated_list_or_series_totals`, `normalized_game_contributions`, or `local_analysis_results`. |
| `table_size`                 | Fixed three-player table size used for SkWO-style points.     |
| `player_game_points`         | Already aggregated game points for the rated player.          |
| `own_games_won`              | Count of the rated player's won own games.                    |
| `own_games_lost`             | Count of the rated player's lost own games.                   |
| `other_players_lost_games`   | Count of lost games by the other two players.                 |
| `own_game_bonus_points`      | +50 per own game won and -50 per own game lost.               |
| `opponent_loss_bonus_points` | +40 per lost game by another player at the three-player table.|
| `total_performance_points`   | Sum of game points, own-game bonus points, and opponent-loss bonus points. |

When the summary is derived from `list_game_contributions`, it keeps the same
field set and uses `basis: "normalized_game_contributions"`. No contribution
rows are echoed in the output.

When the summary is derived from `list_analysis_results`, it keeps the same
field set and uses `basis: "local_analysis_results"`. Analysis-result rows are
not echoed in the output.

Existing single-rated-player list modes do not emit `list_standings_summary`.

## Fixed three-player list standings summary

`list_standings_summary` is emitted only when the input contains
`list_standings_input`.

Example:

```json
"list_standings_summary": {
  "rating_system": "isko_list",
  "basis": "fixed_three_player_game_results",
  "table_size": 3,
  "player_count": 3,
  "game_count": 1,
  "ranking_status": "lot_required",
  "lot_required_player_ids": ["bob", "carol"],
  "applied_lot_order": null,
  "standings": [
    {
      "rank": 1,
      "input_order": 1,
      "player_id": "alice",
      "player_label": "Alice",
      "games_played": 1,
      "declarer_games": 1,
      "defender_games": 0,
      "own_games_won": 1,
      "own_games_lost": 0,
      "defender_games_won": 0,
      "defender_games_lost": 0,
      "other_players_lost_games": 0,
      "player_game_points": 96,
      "own_game_bonus_points": 50,
      "opponent_loss_bonus_points": 0,
      "total_performance_points": 146
    }
  ]
}
```

Summary fields:

| Field          | Meaning                                      |
| -------------- | -------------------------------------------- |
| `rating_system` | Always `isko_list`.                        |
| `basis`        | Always `fixed_three_player_game_results`.    |
| `table_size`   | Fixed table size, always `3`.                |
| `player_count` | Number of standings players, always `3`.     |
| `game_count`   | Number of supplied list games.               |
| `ranking_status` | `final` or `lot_required`.                 |
| `lot_required_player_ids` | IDs in the unresolved tie group, or an empty array. |
| `applied_lot_order` | Applied external lot order, or `null`.  |
| `standings`    | Exactly three ranked player rows.            |

Standing row fields:

| Field                         | Meaning                                                    |
| ----------------------------- | ---------------------------------------------------------- |
| `rank`                        | Final rank or shared competition rank for an unresolved tie. |
| `input_order`                 | One-based input position used only for deterministic serialization. |
| `player_id`                   | Stable player identifier.                                  |
| `player_label`                | Optional display label, or `null`.                         |
| `games_played`                | Total number of supplied games.                            |
| `declarer_games`              | Games where this player was declarer.                      |
| `defender_games`              | `game_count - declarer_games`.                             |
| `own_games_won`               | Own declarer games won.                                    |
| `own_games_lost`              | Own declarer games lost.                                   |
| `defender_games_won`          | Defender games where the declarer lost.                    |
| `defender_games_lost`         | Defender games where the declarer won.                     |
| `other_players_lost_games`    | Same value as `defender_games_won`.                        |
| `player_game_points`          | Sum of settlement scores for own declarer games.           |
| `own_game_bonus_points`       | `own_games_won * 50 + own_games_lost * -50`.               |
| `opponent_loss_bonus_points`  | `other_players_lost_games * 40`.                           |
| `total_performance_points`    | Sum of game points and performance bonuses.                |

SkWO 6.3.1 orders standings by `total_performance_points` descending,
`own_games_won` descending, and `own_games_lost` ascending. A remaining tie is
resolved only by an externally supplied `lot_order`. `player_game_points`,
`opponent_loss_bonus_points`, player IDs, labels, and input order do not decide
rank. The `isko_list` rating-system identifier remains for compatibility.

Without a supplied lot result, tied rows receive standard competition ranks:
`1, 1, 3`, `1, 2, 2`, or `1, 1, 1`. The summary then uses
`ranking_status: "lot_required"`, lists the tied IDs in deterministic input
order, and leaves `applied_lot_order` as `null`. Input order determines only
serialization and does not imply an order within the tie, so these standings
are not final.

When no tie remains, the status is `final`, both lot fields are empty or
`null`, respectively. A valid external lot result also produces `final` status,
unique ranks for only the tied players, and echoes the supplied order in
`applied_lot_order`. The engine never executes a random lot.

This standings output is fixed to three players. It is not four-player support,
full tournament reporting, or an official federation report format.

## Analysis report

`analysis_report` contains one entry per legal card.

Immediate Analysis is local-action only. When the normalized input position does
not have `next_player = "me"`, or when the game has already ended,
`legal_cards` is `[]`, `analysis_report` is `[]`, and `recommendation.card` is
`null`.

For effective bounded Search, and for strict Search without a recommendation,
`analysis_report` is empty because it remains an Immediate one-trick report.
Search aggregates appear only in
`bounded_search_result.candidate_results`; they are never copied into Immediate
win-rate or point-swing fields. Auto fallback returns the unchanged Immediate
report and marks its rank-1 Immediate candidate normally.

Immediate win-rate and point-value fields are local-side based. For a local
declarer, `win_rate` means the declarer side wins the trick. For a local
defender, `win_rate` means either defender wins the trick. `average_points_won`,
`average_points_lost`, and `expected_point_swing` use the same local-side
perspective.

With declared Ouvert or continuation, every candidate uses the same exact public hand. Its owner
can play only those cards; played cards are removed and cannot reappear.
Candidate objectives and card-selection policies are otherwise unchanged.

For Null games, candidate ordering and `is_recommended` use the Null contract
objective instead of card-point swing. A local Null declarer prefers avoiding
declarer-won evaluated tricks. A local Null defender prefers making the concrete
declarer win an evaluated trick. The point fields above remain card-point
metrics and are not redefined as contract utility.

Immediate ordering is stable: exact objective ties retain legal-card order, and
exactly one row, the selected representative, has `is_recommended: true`. Review
ranks are one-based ordinal positions in this ordering, not shared quality ranks.
A later equal-best Card can therefore have rank 2, `decision_quality: "optimal"`,
zero missed objective value and `better_card_count: 0`. These fields are unchanged
by Issue #240; a singleton flag does not imply that equal-value alternatives are worse.

Example:

```json
{
  "card": "SA",
  "win_rate": 0.659,
  "average_trick_points": 12.737,
  "average_points_won": 8.304,
  "average_points_lost": 4.433,
  "expected_point_swing": 3.871,
  "is_recommended": true
}
```

## Recommendation

Issue #240 corrects newly generated Immediate `recommendation.reason` and
`strategic_summary` for exact top ties. All Cards exactly equal to the maximum
full-precision finite game/role objective are named in existing order. Suit/Grand
use expected point swing; Null uses the existing contract utility, with point
metrics remaining informational. Positive, zero and negative maxima are handled
alike. Tied lower rows and sole choices are not top ties. No epsilon, rounding or
statistical-equivalence criterion is introduced.

Fresh tie prose identifies the stable representative and equality under this
Immediate method, without claiming whole-game equivalence. A genuinely positive
gap that would print as `0.00` instead says `less than 0.01 expected points`;
the corresponding Null summary uses `less than 0.001` objective utility. This is
prose precision only: numerical gaps, quality thresholds, metrics and selection
remain exact. Other non-tied, sole-choice and unavailable prose is unchanged.

Existing shared callers propagate these text corrections through explicit fresh
execution, including Auto fallback, Match Position exports, Historical Immediate
Review, diagnostic Immediate baselines and composed copies. Fresh content-derived
Report/Teacher identities may consequently change, with text still included in
canonical hashing and provenance. Previously retained Results, Reports and Teacher
sources remain strict-loadable with their original strings and exact export bytes;
there is no migration, load-time rewrite or automatic re-execution.

Example:

```json
"recommendation": {
  "card": "SA",
  "reason": "This card has the highest estimated immediate expected point swing: 3.87."
}
```

For explicit methods, `recommendation.card` always belongs to the effective
method. A Search recommendation uses deterministic Search-specific reason and
strategic-summary text with status, stop reason, selected/completed worlds,
coverage, success rate, mean local settlement score, and Suit/Grand margin when
available. The text does not claim an optimal imperfect-information policy.

The strict method summary is:

```json
{
  "requested_method": "auto",
  "effective_method": "immediate_expected_value",
  "search_attempted": true,
  "fallback_used": true,
  "fallback_method": "immediate_expected_value",
  "analysis_report_method": "immediate_expected_value"
}
```

Effective methods are `immediate_expected_value`,
`compatible_world_minimax_v1`, and `none`. Report methods are
`immediate_expected_value` and `none`. Strict Search never sets fallback. Auto
sets fallback only when Immediate actually returns the top-level card; if both
methods produce no card, effective method is `none` and fallback remains false.

Explicit Immediate emits `bounded_search_result: null`. Search and auto serialize
the validated result through `build_serializable_bounded_search_result()`, using
the standalone strict schema by reference. Auto fallback marks that Search result
with `fallback_used: true`, `fallback_method: "immediate_expected_value"`, and a
null Search `recommended_card`; the top-level recommendation holds the Immediate
card. All Search status, budget, world-count, coverage, candidate, and claim data
remain unchanged.

With any explicit method, `settings` adds normalized
`recommendation_method` and `bounded_search_settings`. Explicit Immediate uses a
null Search settings value. Search settings include the public Search seed and
requested budget, but no derived child seed. The top-level Immediate seed remains
separate. Human-readable explicit Search output prints both the existing top-level
random seed and a separately labeled `Search random seed`.

No selected world, opponent hand, hypothetical Skat, exact state, coherent root,
world fingerprint, principal variation, future historical fact, or profile
weight is serialized.

For opponent-turn inputs, Immediate Analysis does not create a local card
recommendation. The unavailable shape is:

```json
"recommendation": {
  "card": null,
  "reason": "Immediate analysis is unavailable because the local player is not next."
}
```

## Post-game review summary

`post_game_review_summary` compares the actual played card with the recommended card.
It requires an available local Immediate Analysis report.

For explicit `bounded_search` or `auto` flat post-game review, the engine runs a
separate Immediate baseline after Search. The ordinary
`post_game_review_summary` is built from that Immediate report and remains
independent of the Search recommendation. The top-level recommendation remains
the configured Search workflow result. The additional strict
`bounded_search_post_game_review_summary` contains:

| Field | Meaning |
| --- | --- |
| `schema_version` | Always `1`. |
| `analysis_method` | Always `bounded_search_with_immediate_baseline`. |
| `game_type` | The aligned Suit, Grand, or Null contract used to enforce margin semantics. |
| `search_actual_card_comparison` | Actual card and Search rank/metrics, best/equivalent flags, completed-world basis, and recommendation-minus-actual gaps. |
| `search_vs_immediate_comparison` | Both cards and reciprocal ranks, card agreement, aggregate relation, and Search-minus-Immediate aggregate advantages. |

Comparison basis is `all_compatible_worlds`, `sampled_compatible_worlds`, or
`completed_common_prefix`. Aggregate relation is `search_better`,
`aggregate_equivalent`, or `not_available`; equal metrics remain equivalent even
when canonical tie-breaking selects different cards. Suit and Grand include
card-point margins. Null margin metrics and gaps are null. Explicit unavailable
reasons cover zero completed worlds, a stopped Search with no recommendation,
and missing aligned candidates. Candidate aggregates without a Search
recommendation do not enter the Search-versus-Immediate quality denominator.

Flat declared-Ouvert and continuation review use the same public information state. When the local
actor owns the public hand, `actual_card_played` must belong to it; other local
cards retain ordinary hand and follow-suit validation. Continuation alone never
adds a final result or settlement to the review.

If `actual_card_played` was not provided, the summary is still present but marked as unavailable.
If Immediate Analysis is unavailable, the summary is also unavailable and uses
`reason: "immediate_analysis_unavailable"`.

Example without `actual_card_played`:

```json
"post_game_review_summary": {
  "is_available": false,
  "reason": "actual_card_played_not_provided",
  "actual_card_played": null,
  "recommended_card": "SA",
  "actual_expected_point_swing": null,
  "recommended_expected_point_swing": 6.0,
  "expected_point_swing_difference": null,
  "decision_quality": "not_available",
  "decision_factors": ["actual_card_played_not_provided"],
  "decision_explanation": "No post-game review decision quality is available because actual_card_played was not provided.",
  "actual_card_rank": null,
  "recommended_card_rank": 1,
  "candidate_count": 3,
  "better_card_count": null
}
```

Example with `actual_card_played`:

```json
"post_game_review_summary": {
  "is_available": true,
  "reason": "actual_card_played_provided",
  "actual_card_played": "S9",
  "recommended_card": "SA",
  "actual_expected_point_swing": -4.0,
  "recommended_expected_point_swing": 6.0,
  "expected_point_swing_difference": 10.0,
  "decision_quality": "mistake",
  "decision_factors": [
    "lower_expected_point_swing_than_recommendation",
    "large_expected_point_swing_gap"
  ],
  "decision_explanation": "The actual card has a much lower expected point swing than the recommended card. Missed expected point swing: 10.00.",
  "actual_card_rank": 3,
  "recommended_card_rank": 1,
  "candidate_count": 3,
  "better_card_count": 2
}
```

Fields:

| Field                              | Meaning                                                                                   |
| ---------------------------------- | ----------------------------------------------------------------------------------------- |
| `is_available`                     | Whether actual-card review is available.                                                  |
| `reason`                           | Availability reason.                                                                      |
| `actual_card_played`               | Actual card from input, or `null`.                                                        |
| `recommended_card`                 | Recommended card from analysis.                                                           |
| `actual_expected_point_swing`      | Expected point swing of the actual card, or `null`.                                       |
| `recommended_expected_point_swing` | Expected point swing of the recommended card.                                             |
| `expected_point_swing_difference`  | Recommended swing minus actual swing, or `null`.                                          |
| `decision_quality`                 | `not_available`, `optimal`, `acceptable`, `suboptimal`, or `mistake`.                     |
| `decision_factors`                 | Machine-readable explanation factors.                                                     |
| `decision_explanation`             | Human-readable explanation.                                                               |
| `actual_card_rank`                 | One-based ordinal position of the actual Card in stable objective order, or `null`.        |
| `recommended_card_rank`            | One-based ordinal position of the selected representative in stable objective order.        |
| `candidate_count`                  | Number of legal candidate cards in the analysis report.                                   |
| `better_card_count`                | Number of legal cards with a higher expected point swing than the actual card, or `null`. |

Decision quality thresholds are based on the missed expected point swing:

| Quality         | Meaning                                                   |
| --------------- | --------------------------------------------------------- |
| `not_available` | No actual card was provided.                              |
| `optimal`       | Actual card has no missed expected point swing.           |
| `acceptable`    | Actual card has only a small missed expected point swing. |
| `suboptimal`    | Actual card has a clearly lower expected point swing.     |
| `mistake`       | Actual card has a much lower expected point swing.        |

For Null games, post-game review uses the same Null contract objective as the
recommendation for ranks, better-card counts, and decision quality. The public
point fields keep their card-point meanings. Null-specific decision factors may
include `no_missed_null_objective`,
`lower_null_objective_than_recommendation`, `small_null_objective_gap`,
`medium_null_objective_gap`, and `large_null_objective_gap`.

Representative examples:

* `examples/grand_post_game_mistake_actual_card.json` shows a clear missed recommendation with a large expected-point-swing gap.
* `examples/grand_post_game_acceptable_actual_card.json` shows a small missed expected-point-swing gap classified as `acceptable`.
* `examples/null_post_game_objective_actual_card.json` shows a Null review where the actual card differs from the recommendation but has no missed Null contract-objective utility.
* `examples/spades_post_game_defender_actual_card.json` shows local defender-perspective review with a concrete declarer seat.

## Multi-step result

When a multi-step simulation is requested, the output can include `multi_step_result`.

`multi_step_result` contains the serialized multi-step simulation result, including:

| Field                            | Meaning                                                           |
| -------------------------------- | ----------------------------------------------------------------- |
| `card_selection_policy`          | Card-selection policy used for player decisions.                  |
| `requested_step_count`           | Number of requested simulation steps.                             |
| `steps_simulated`                | Number of steps that were actually simulated.                     |
| `stop_reason`                    | Reason why the simulation stopped.                                |
| `strict_context`                 | Whether strict simulation-context validation was active.          |
| `summary`                        | Multi-step score and context summary.                             |
| `context_summary`                | Summary of simulated opponent-card context.                       |
| `steps`                          | Serialized step-by-step simulation details.                       |
| `final_state`                    | Final serialized game state after the simulated steps.            |
| `opponent_policy_settings`       | Global opponent policy settings used as fallback.                 |
| `left_opponent_policy_settings`  | Left-opponent policy settings passed into multi-step simulation.  |
| `right_opponent_policy_settings` | Right-opponent policy settings passed into multi-step simulation. |
| `stopped_recommendation_decision` | Search diagnostics when no local card was executed, otherwise absent. |

Nested `steps[].prepared_state` is the state after any supported opponent-turn
preparation and before the local candidate card is simulated. This separates the
original top-level `position` from the internally advanced local-action state.

Nested `final_state` follows the same reusable-state invariant as input
positions: `declarer_points` and `defender_points` contain only explicit points
not already represented by `completed_tricks`. Points from simulated completed
tricks are contributed by the completed-trick cards and are reflected in the
summary totals.

For declared Ouvert or continuation, `context_summary.public_hand_constraints`
contains every remaining exact public hand. Each child path removes known cards
that were played and retains every unplayed public card with its original source.
Two supported disjoint public hands remain exact in the same path.

When root evidence supports inference, `multi_step_result.hidden_card_inference_summary`
matches the root model. A step can additionally contain
`steps[].hidden_card_inference_summary` for its prepared public decision state.
A later visible simulated failure to follow can increase later evidence, but it
does not mutate or resample the immutable compatible root.

`context_summary.hidden_world` and each `steps[].coherence_summary` expose the
privacy-safe coherent-path contract:

| Field | Meaning |
| --- | --- |
| `mode` | Always `coherent_path`. |
| `initial_left_hand_size`, `initial_right_hand_size` | Root opponent-hand counts. |
| `initial_hypothetical_skat_size` | Root hypothetical-skat count, without card identities. |
| `remaining_left_hand_size`, `remaining_right_hand_size` | Current opponent-hand counts after owner-aware plays. |
| `remaining_hypothetical_skat_size` | Current hypothetical-skat count; it remains equal to the initial count. |
| `root_sample_count`, `sampled_once`, `resampled_after_path_start` | One root was sampled and no later step resampled it. |
| `ownership_transition_count`, `opponent_cards_played` | Reconciled counts of cards removed from opponent owners. |
| `ownership_preserved`, `hand_sizes_reconciled`, `hypothetical_skat_fixed` | Successful path invariants. |
| `duplicate_card_detected`, `ownership_violation_detected` | Both remain `false` in successful output. |
| `hidden_cards_emitted` | Always `false`. |

These summaries never contain `left_hand`, `right_hand`, hypothetical-skat card
identities, or any hidden-world digest. Opponent-turn preparation and candidate-
trick completion use the same private path world. Local decision policies receive
only public decision-time information; `highest_expected_value` keeps separate
counterfactual Monte Carlo samples and does not expose the execution root.

Search-aware steps add `recommendation_decision` with the decision index,
requested and effective methods, Search-attempt flag, selected card and reason,
fallback metadata, and the externally schema-validated aggregate
`bounded_search_result`. It contains no Immediate report rows, private hands,
coherent world, ownership map, hypothetical Skat, future path, or child seed.
The decision card always equals `candidate_card`.

When Search and any allowed auto fallback both return no card, the path stops
with `local_policy_no_recommendation`. No step is added. The same decision shape
appears as `stopped_recommendation_decision` with a null card, and any opponent
actions already used to prepare that public decision remain in `final_state` and
the context/coherence counts.

Only Search-aware summaries add `requested_method`, `decisions_attempted`,
`decisions_executed`, `search_recommendations_used`,
`immediate_fallbacks_used`, and `no_recommendation_count`. Attempted decisions
equal executed decisions plus no-recommendation stops; executed decisions equal
Search recommendations plus Immediate fallbacks. Strict Search always reports
zero Immediate fallbacks. Legacy results omit all of these fields.

Nested `steps[].detailed_result` uses explicit ownership fields:

| Field                  | Meaning                                                            |
| ---------------------- | ------------------------------------------------------------------ |
| `did_win`              | Whether the local player's side won the completed trick.           |
| `local_side_won`       | Same local-side ownership value as `did_win`.                      |
| `candidate_card_won`   | Whether the candidate card itself won the completed trick.         |
| `completed_trick`      | Completed trick entry with winner side and, when known, winner player. |

Nested `summary.score_summary` includes both declarer-perspective and
local-perspective swing fields:

| Field                 | Meaning                                                            |
| --------------------- | ------------------------------------------------------------------ |
| `final_point_swing`   | `declarer_points_gained - defender_points_gained`.                 |
| `local_point_swing`   | Local-side swing. This matches `final_point_swing` for a local declarer and is `defender_points_gained - declarer_points_gained` for a local defender. |

The output schema defines the stable `multi_step_result` structure, including
serialized steps, `steps[].prepared_state`, candidate detailed results,
`final_state`, context summaries, stop reasons, and both `final_point_swing` and
`local_point_swing`. All nine concrete canonical phases are executable. The
existing `unsupported_turn_phase` reason remains only for an unresolved
non-concrete phase and does not describe any canonical table row. Existing-Trick
completion creates no step for an already played local Card; if the local hand is
then empty, zero serialized steps and `Player has no cards left.` are returned.

## Policy comparison result

When policy comparison is requested, `policy_comparison_result.policy_results`
contains one row per compared card-selection policy.

Each row includes `final_point_swing` for the declarer-perspective swing and
`local_point_swing` for the local player's side. Policy results and
`recommended_policy` are ranked by `local_point_swing`, then by the documented
tie-breakers.

Every comparison samples one shared private root world. Each compared policy
receives an equal independent immutable copy, together with the same resolved
public-hand constraints and sources. Policy paths may diverge after their local
actions, but one path cannot mutate another and differences cannot come from a
separately resampled initial world.

`policy_comparison_result.hidden_world` contains only:

| Field | Meaning |
| --- | --- |
| `mode` | Always `coherent_path`. |
| `shared_root_world` | Every policy began from the same root assignment. |
| `root_sample_count` | Always `1`. |
| `policy_path_count` | Number of independent policy paths. |
| `independent_path_worlds` | Equal immutable copies evolve independently. |
| `hidden_cards_emitted` | Always `false`. |

Each policy row's `context_summary.hidden_world` contains the privacy-safe
per-path counts and statuses documented above. No new point-swing, Null horizon,
or tie-break objective is introduced. When available,
`policy_comparison_result.hidden_card_inference_summary` describes the one shared
root inference model. Every policy receives an immutable copy of the same sampled
compatible root; later public evidence may diverge only after path play diverges.

The output schema defines the stable `policy_comparison_result` structure,
including requested settings, compared policies, per-policy result rows,
context summaries, shared-root hidden-world status, and `recommended_policy`.
See [Coherent hidden-world simulation](coherent_hidden_world_simulation.md).

Without Search configuration, comparison output remains the exact legacy four-
policy shape. With explicit `bounded_search` or `auto`, exactly that method is
appended last. Search-inclusive rows add `eligible_for_recommendation` and a
nullable `ineligible_reason`; a Search path stopped by
`local_policy_no_recommendation` remains visible but is ineligible, sorts after
eligible policies, and cannot be recommended. `recommended_policy` is null when
no row is eligible.

The Search row also includes the six-field `recommendation_summary` documented
above and ordered `search_decision_diagnostics`. Each compact diagnostic contains
only step index, effective method, Search status and stop reason, selected and
completed world counts, recommendation card, and fallback flag. Full per-world
or coherent-root data is never copied into comparison output.

## Historical opponent profile application

Profile-enabled historical review adds the root
`historical_opponent_profile_application_summary`. It preserves the statistics
file, game ID, original `played_at`, strict temporal rule, three participant
match rows, matched count, and unmatched IDs. Matched rows contain compact source
provenance and existing derivation metadata but not source percentage values.

Each historical review decision adds `opponent_profile_application` with the
acting, left, and right stable IDs plus independent side match, actionability,
precedence, applied preset, and effective lead/response policies. The review
summary adds bounded `opponent_profile_application_counts` by decision, side,
stable player ID, and actionable preset. These are application counts, not
policy-quality or improvement measurements.

Optional `played_at` is preserved in the historical record and summary;
`source_played_at` is preserved in decision and training provenance where the
source game is referenced. The focused contract is
[`schemas/historical_opponent_profile_application.schema.json`](../schemas/historical_opponent_profile_application.schema.json).
