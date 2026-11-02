"""store.py — SQLite persistence for the live prediction track record.

Snapshots each fixture's core-market predictions, then reconciles them against
actual results once matches are played. A pick is RECORDED whenever it is
computed — before kickoff or after — and the track record counts every recorded
pick, one per fixture, the earliest recorded one (`_counted_picks`). Whether a
pick was made before its own kickoff is DERIVED per read from the pick's two
timestamps (`_made_before_kickoff`), never read from a stored flag and never
stored itself, and it is published beside the headline as `pre_kickoff` rather
than used to exclude the pick.

Recording the pick as it stood is the only way to honestly measure "how good
are the predictions really" going forward — a model re-evaluated after the fact
against its own current (possibly retrained) state would just be grading itself
on data it may have since trained on — and keeping the late picks in, labelled,
is what makes the difference between the two figures visible rather than
arguable.

Markets tracked: the same core set already in `FixtureSummary` — 1X2, total
goals O/U 2.5, and BTTS. Corners/cards/player markets aren't tracked here
(no live line to compare against for most of them anyway — see
`odds/value_bets.py`).
"""

from __future__ import annotations

import json
import sqlite3
from datetime import datetime, timezone

import pandas as pd

from ..config import TRACKING_DB_PATH
from ..models import scoreline

# (market, outcome_name, source probability column on the value-bet table)
MARKET_SPEC = [
    ("1x2", "home_win", "home_win_prob"),
    ("1x2", "draw", "draw_prob"),
    ("1x2", "away_win", "away_win_prob"),
    ("totals_2_5", "over", "over_2_5_prob"),
    ("totals_2_5", "under", "under_2_5_prob"),
    ("btts", "yes", "btts_yes_prob"),
]

_RESULT_TO_1X2 = {"H": "home_win", "D": "draw", "A": "away_win"}

PLAYER_REVIEW_GOAL_THRESHOLD = 0.35
PLAYER_REVIEW_ASSIST_THRESHOLD = 0.25
PLAYER_REVIEW_CONTRIBUTION_THRESHOLD = 0.30


def _naive(ts) -> pd.Timestamp:
    """Strip timezone info so every timestamp in this module compares
    cleanly against `data/football_data.py`'s naive `date` column — sources
    mix tz-aware (Odds API, UTC) and naive (FPL fallback) kickoff times."""
    ts = pd.Timestamp(ts)
    return ts.tz_localize(None) if ts.tzinfo is not None else ts


def _utc_instant(value) -> pd.Timestamp | None:
    """An ISO-8601 timestamp as a NAIVE UTC instant, or None if unreadable.

    **The offset is converted, not stripped, and that is the whole point.**
    `_naive()` above strips an offset without converting, which is right for
    matching a source's own wall-clock column and wrong for every comparison in
    the track-record path: 13:30 at UTC-5 is 18:30 UTC, four and a half hours
    AFTER a 14:00 UTC kickoff, and stripping the offset compares 13:30 with
    14:00 and calls it pre-kickoff.

    So every comparison between a pick's timestamp and a fixture's kickoff goes
    through here first, and is between two instants — never between two strings.
    A naive value is read as UTC, which is how both columns are written
    everywhere in this repo.
    """
    if value is None:
        return None
    try:
        ts = pd.Timestamp(value)
    except (TypeError, ValueError):
        return None
    if pd.isna(ts):
        return None
    if ts.tzinfo is not None:
        ts = ts.tz_convert("UTC").tz_localize(None)
    return ts


def _made_before_kickoff(snapshotted_at, commence_time) -> bool:
    """Whether this pick was made before this fixture's kickoff, from its own two
    timestamps. DERIVED, never read from a stored flag.

    `predictions.backfilled` exists and is `0` for a pick captured live, `1` for
    one computed after the fact. It is not consulted here, and there is no
    `made_before_kickoff` column to add: the question is when the pick was made
    relative to the match, and `record_predictions` takes `backfilled=` as an
    argument, so a flag is only as honest as whatever set it.

    **Fails closed.** An unreadable timestamp on either side, or a missing
    kickoff, gives False: "cannot prove it was made before kickoff" is the only
    honest answer, and it is never a `true` the timestamps do not support. Note
    what that withholds now — the LABEL, not the pick. Under the pre-2026-10-01
    rule this function's answer decided whether a pick counted at all; it no
    longer does (see `get_track_record`), so an unreadable timestamp costs a
    pick its place in the secondary figure and nothing else.

    A pick stamped exactly at kickoff is not before it: it had no chance to be
    made on the night.
    """
    picked, kickoff = _utc_instant(snapshotted_at), _utc_instant(commence_time)
    if picked is None or kickoff is None:
        return False
    return picked < kickoff


def _made_before_kickoff_row(row: pd.Series) -> bool:
    """`_made_before_kickoff` over one row, for a frame filter."""
    return _made_before_kickoff(row.get("snapshotted_at"), row.get("commence_time"))


def _instants(frame: pd.DataFrame) -> pd.Series:
    """The frame's `snapshotted_at` column as UTC instants, NaT where unreadable.

    A column the frame does not carry yields an all-NaT series rather than
    raising, so `_counted_picks` and `_counted_player_picks` can share one
    ordering even where the provenance differs — the player snapshot table has
    no `snapshotted_at` at all (see `_counted_player_picks`).
    """
    if "snapshotted_at" not in frame.columns:
        return pd.Series(pd.NaT, index=frame.index, dtype="datetime64[ns]")
    return frame["snapshotted_at"].map(_utc_instant).astype("datetime64[ns]")


def _counted_picks(fixtures: pd.DataFrame) -> pd.DataFrame:
    """The fixture rows that count: one per fixture, the EARLIEST recorded.

    **The counting key is the fixture's `event_id`** — the same key, and only
    the key, every other sport uses: NFL `drop_duplicates(subset=["game_id"])`,
    CFB `_earliest_recorded(labelled, ("game_id", ...))`, NBA grouping by
    `game_id`. PL used to re-derive identity from
    `(team_home, team_away, _utc_instant(commence_time).date())`; that is gone,
    and `_fixture_hit_table` says at length what it cost.

    All four graded markets (match result, exact score, O/U 2.5, BTTS) live as
    COLUMNS on one row of `_fixture_market_hit_table`, so `(fixture, market)`
    reduces to the fixture and the four markets are read off that single counted
    row. This function must therefore NOT collapse the row to one market — a
    `drop_duplicates` over a column-per-market shape would delete three of the
    four, and the by_market block would report the right keys with silently
    wrong n.

    So on today's data this function is a no-op (`_fixture_market_hit_table`
    already yields one row per `event_id`, and `predictions` is
    `UNIQUE(event_id, market, outcome_name)`), and it is written anyway for
    the same reason NFL's is: a rule enforced only by an upstream
    `drop_duplicates` (or by that `UNIQUE`) stops being enforced the moment the
    key changes, and the failure when it does is invisible — the accuracy simply
    improves and a rerun of the model gets to grade a second time.

    "Earliest" is by UTC instant, so which row wins does not depend on how its
    timestamp is spelled. An unreadable timestamp cannot be proven earliest, so
    it sorts LAST and never displaces a row carrying a real instant; where no
    row in a group has one, the first row encountered stands and
    `_made_before_kickoff` fails closed on it.

    Rows that lose here are NOT deleted. They stay in the table — rule 1,
    recorded stays recorded — and they are deliberately absent from `per_pick`
    too, so the list a reader tallies is the list that produced the headline.
    A non-counted rerun is in the table, in no figure, and in no list: that is
    what history is.
    """
    if fixtures.empty:
        return fixtures
    ordered = fixtures.assign(_instant=_instants(fixtures))
    ordered = ordered.sort_values("_instant", na_position="last", kind="stable", ignore_index=True)
    return ordered.drop_duplicates(subset=["event_id"], keep="first").drop(columns=["_instant"])


def _connect() -> sqlite3.Connection:
    # Fixture views and the five-minute tracking task run concurrently in
    # FastAPI worker threads. A tiny default SQLite timeout turns an ordinary
    # short write into a user-visible 500/blank page; WAL lets readers keep
    # serving while a snapshot is written and busy_timeout serialises the
    # occasional competing write safely.
    conn = sqlite3.connect(str(TRACKING_DB_PATH), timeout=15)
    conn.execute("PRAGMA busy_timeout = 15000")
    try:
        conn.execute("PRAGMA journal_mode = WAL")
    except sqlite3.OperationalError:
        # A pre-existing external connection can temporarily block the mode
        # switch. The busy timeout above still protects normal operations.
        pass
    conn.execute(
        """
        CREATE TABLE IF NOT EXISTS predictions (
            id INTEGER PRIMARY KEY AUTOINCREMENT,
            event_id TEXT NOT NULL,
            team_home TEXT NOT NULL,
            team_away TEXT NOT NULL,
            market TEXT NOT NULL,
            outcome_name TEXT NOT NULL,
            predicted_prob REAL NOT NULL,
            commence_time TEXT NOT NULL,
            snapshotted_at TEXT NOT NULL,
            model_trained_at TEXT,
            resolved INTEGER NOT NULL DEFAULT 0,
            actual_outcome INTEGER,
            resolved_at TEXT,
            UNIQUE(event_id, market, outcome_name)
        )
        """
    )
    # Migration: actual_goals_home/away didn't exist in the original schema
    # — added so recent-results views can show the real scoreline next to
    # the predicted probabilities, not just per-market hit/miss booleans.
    existing_cols = {row[1] for row in conn.execute("PRAGMA table_info(predictions)")}
    for col in ("actual_goals_home", "actual_goals_away"):
        if col not in existing_cols:
            conn.execute(f"ALTER TABLE predictions ADD COLUMN {col} INTEGER")
    # backfilled: 0 for a prediction actually captured live before kickoff,
    # 1 for one computed after the fact by backfill_missing_predictions (see
    # its docstring for why this distinction stays visible rather than
    # blurring the two).
    if "backfilled" not in existing_cols:
        conn.execute("ALTER TABLE predictions ADD COLUMN backfilled INTEGER NOT NULL DEFAULT 0")
    # gameweek: only football-data.org's `matchday` carries this (football-
    # data.co.uk's CSVs have no equivalent column), so it's written in at
    # reconcile time rather than snapshot time, and stays NULL for anything
    # resolved via the football-data.co.uk fallback path. predicted_scoreline
    # is the model's single most-likely scoreline at prediction time (already
    # computed by odds/value_bets.py::build_value_bet_table's "top_scoreline"
    # for live predictions, and by backfill_missing_predictions's own
    # scoreline.predict_fixture call for backfilled ones) — stored so the
    # Recent Results view can show it next to the actual score without
    # recomputing anything.
    for col, col_type in (("gameweek", "INTEGER"), ("predicted_scoreline", "TEXT")):
        if col not in existing_cols:
            conn.execute(f"ALTER TABLE predictions ADD COLUMN {col} {col_type}")
    conn.execute(
        """
        CREATE TABLE IF NOT EXISTS fixture_market_predictions (
            event_id TEXT NOT NULL,
            team_home TEXT NOT NULL,
            team_away TEXT NOT NULL,
            commence_time TEXT NOT NULL,
            market TEXT NOT NULL,
            lambda_value REAL NOT NULL,
            line REAL NOT NULL,
            over_probability REAL NOT NULL,
            under_probability REAL NOT NULL,
            provenance TEXT NOT NULL,
            actual_total REAL,
            resolved INTEGER NOT NULL DEFAULT 0,
            PRIMARY KEY (event_id, market)
        )
        """
    )
    conn.execute(
        """
        CREATE TABLE IF NOT EXISTS fixture_forecast_snapshots (
            event_id TEXT NOT NULL,
            stage TEXT NOT NULL,
            commence_time TEXT NOT NULL,
            snapshotted_at TEXT NOT NULL,
            home_win REAL NOT NULL,
            draw REAL NOT NULL,
            away_win REAL NOT NULL,
            over_2_5 REAL NOT NULL,
            lineup_snapshot TEXT,
            PRIMARY KEY (event_id, stage)
        )
        """
    )
    conn.execute(
        """
        CREATE TABLE IF NOT EXISTS odds_timing_snapshots (
            event_id TEXT NOT NULL,
            stage TEXT NOT NULL,
            commence_time TEXT NOT NULL,
            snapshotted_at TEXT NOT NULL,
            quote_snapshot TEXT NOT NULL,
            PRIMARY KEY (event_id, stage)
        )
        """
    )
    conn.execute(
        """
        CREATE TABLE IF NOT EXISTS player_prediction_snapshots (
            event_id TEXT NOT NULL,
            player_id INTEGER NOT NULL,
            name TEXT NOT NULL,
            team TEXT NOT NULL,
            goal_probability REAL NOT NULL,
            assist_probability REAL NOT NULL,
            contribution_probability REAL NOT NULL,
            confirmed_starter INTEGER NOT NULL,
            qualifies_call INTEGER NOT NULL,
            is_recommended INTEGER NOT NULL DEFAULT 0,
            provenance TEXT NOT NULL,
            actual_goals INTEGER,
            actual_assists INTEGER,
            resolved INTEGER NOT NULL DEFAULT 0,
            PRIMARY KEY (event_id, player_id)
        )
        """
    )
    conn.execute(
        """
        CREATE TABLE IF NOT EXISTS fixture_player_outcomes (
            event_id TEXT NOT NULL,
            player_id INTEGER NOT NULL,
            side TEXT NOT NULL,
            goals INTEGER NOT NULL,
            assists INTEGER NOT NULL,
            PRIMARY KEY (event_id, player_id)
        )
        """
    )
    player_columns = {row[1] for row in conn.execute("PRAGMA table_info(player_prediction_snapshots)")}
    if "is_recommended" not in player_columns:
        conn.execute("ALTER TABLE player_prediction_snapshots ADD COLUMN is_recommended INTEGER NOT NULL DEFAULT 0")
        conn.execute(
            """
            UPDATE player_prediction_snapshots
            SET is_recommended = 1
            WHERE rowid IN (
                SELECT rowid FROM (
                    SELECT rowid, ROW_NUMBER() OVER (
                        PARTITION BY event_id ORDER BY contribution_probability DESC
                    ) AS rank
                    FROM player_prediction_snapshots
                    WHERE confirmed_starter = 1
                ) WHERE rank <= 3
            )
            """
        )
    conn.execute(
        """
        UPDATE player_prediction_snapshots
        SET qualifies_call = CASE
            WHEN goal_probability >= 0.20
              OR assist_probability >= 0.20
              OR contribution_probability >= 0.20 THEN 1
            ELSE 0
        END
        """
    )
    return conn


def record_fixture_forecast_snapshots(table: pd.DataFrame, stage: str, lineups: dict | None = None) -> int:
    """Persist early and confirmed-XI forecasts independently.

    The current outcome model has no unvalidated lineup coefficient, so the
    confirmed stage records the honest baseline alongside the actual XI. It
    creates the leakage-safe prospective dataset needed to test a future
    late-model adjustment rather than pretending a historical reconstruction
    was available before kickoff.
    """
    if table.empty:
        return 0
    now = datetime.now(timezone.utc).isoformat()
    rows = []
    for _, fixture in table.iterrows():
        event_id = str(fixture["event_id"])
        rows.append((
            event_id, stage, _naive(fixture["commence_time"]).isoformat(), now,
            float(fixture["home_win_prob"]), float(fixture["draw_prob"]),
            float(fixture["away_win_prob"]), float(fixture["over_2_5_prob"]),
            json.dumps((lineups or {}).get(event_id)) if lineups and event_id in lineups else None,
        ))
    with _connect() as conn:
        result = conn.executemany(
            """INSERT OR IGNORE INTO fixture_forecast_snapshots
               (event_id, stage, commence_time, snapshotted_at, home_win, draw, away_win, over_2_5, lineup_snapshot)
               VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?)""",
            rows,
        )
        return result.rowcount


def confirmed_xi_experiment_status() -> dict:
    with _connect() as conn:
        rows = conn.execute(
            "SELECT stage, COUNT(*) FROM fixture_forecast_snapshots GROUP BY stage"
        ).fetchall()
    counts = {stage: count for stage, count in rows}
    return {
        "early_snapshots": counts.get("early", 0),
        "confirmed_xi_snapshots": counts.get("confirmed_xi_baseline", 0),
        "minimum_fixtures_for_decision": 60,
        "status": "collecting_prospectively",
        "note": "Confirmed-XI forecasts remain the independent baseline until a leakage-safe late-model experiment clears validation.",
    }


def capture_due_odds_snapshots(table: pd.DataFrame, now: pd.Timestamp | None = None) -> int:
    """Save free live quotes only in tightly defined 24h/1h windows.

    Closing prices in the historical CSV are deliberately excluded here:
    they would be known after the scheduled decision point and create a
    train/serve timing mismatch.
    """
    if table.empty:
        return 0
    now = _naive(now if now is not None else pd.Timestamp.now(tz="UTC"))
    rows = []
    quote_cols = [c for c in table.columns if c.endswith(("_price", "_implied", "_edge")) or c in {"odds_fetched_at", "odds_source"}]
    for _, fixture in table.iterrows():
        kickoff = _naive(fixture["commence_time"])
        remaining_hours = (kickoff - now).total_seconds() / 3600
        stage = "t24" if 23.0 <= remaining_hours <= 25.0 else "t1" if 0.5 <= remaining_hours <= 1.5 else None
        if stage is None:
            continue
        quote = {col: (None if pd.isna(fixture.get(col)) else fixture.get(col)) for col in quote_cols}
        rows.append((str(fixture["event_id"]), stage, kickoff.isoformat(), datetime.now(timezone.utc).isoformat(), json.dumps(quote, default=str)))
    if not rows:
        return 0
    with _connect() as conn:
        result = conn.executemany(
            "INSERT OR IGNORE INTO odds_timing_snapshots (event_id, stage, commence_time, snapshotted_at, quote_snapshot) VALUES (?, ?, ?, ?, ?)",
            rows,
        )
        return result.rowcount


def odds_snapshot_status() -> dict:
    with _connect() as conn:
        rows = conn.execute("SELECT stage, COUNT(*) FROM odds_timing_snapshots GROUP BY stage").fetchall()
    counts = {stage: count for stage, count in rows}
    return {
        "t24_snapshots": counts.get("t24", 0),
        "t1_snapshots": counts.get("t1", 0),
        "status": "collecting_prospectively",
        "historical_closing_odds": "research-only benchmark; never used in a deployable or value-bet model",
    }


def record_predictions(table: pd.DataFrame, model_trained_at: str | None = None, backfilled: bool = False) -> int:
    """Snapshot current predictions for every fixture in `table` (the
    value-bet table already built by `odds/value_bets.py`, or the
    equivalent shape `backfill_missing_predictions` builds). Already-logged
    (event_id, market, outcome_name) rows are left untouched — this is safe
    to call on every fixtures request."""
    if table.empty:
        return 0

    now = datetime.now(timezone.utc).isoformat()
    rows = []
    for _, fixture in table.iterrows():
        predicted_scoreline = fixture.get("top_scoreline")
        for market, outcome_name, prob_col in MARKET_SPEC:
            rows.append(
                (
                    str(fixture["event_id"]),
                    fixture["team_home"],
                    fixture["team_away"],
                    market,
                    outcome_name,
                    float(fixture[prob_col]),
                    _naive(fixture["commence_time"]).isoformat(),
                    now,
                    model_trained_at,
                    int(backfilled),
                    predicted_scoreline,
                )
            )

    with _connect() as conn:
        cur = conn.executemany(
            """
            INSERT OR IGNORE INTO predictions
                (event_id, team_home, team_away, market, outcome_name, predicted_prob,
                 commence_time, snapshotted_at, model_trained_at, backfilled, predicted_scoreline)
            VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?)
            """,
            rows,
        )
        return cur.rowcount


def _actual_outcome(market: str, outcome_name: str, match: pd.Series) -> int:
    total_goals = match["goals_home"] + match["goals_away"]
    if market == "1x2":
        return int(_RESULT_TO_1X2[match["ftr"]] == outcome_name)
    if market == "totals_2_5":
        is_over = total_goals > 2.5
        return int(is_over if outcome_name == "over" else not is_over)
    if market == "btts":
        both_scored = match["goals_home"] > 0 and match["goals_away"] > 0
        return int(both_scored if outcome_name == "yes" else not both_scored)
    raise ValueError(f"Unknown market: {market}")


def reconcile_predictions(matches_df: pd.DataFrame, lookback_days: int = 3) -> int:
    """For every unresolved prediction whose kickoff has passed, look up the
    actual result in `matches_df` (matched on team names, within a few days
    of the predicted kickoff to absorb date/timezone slop) and fill in
    `actual_outcome`. Returns how many rows were resolved this call.

    `matches_df` carrying a `matchday` column (currently only
    football-data.org's `fetch_matches` provides one — football-data.co.uk
    has no equivalent) also fills in `gameweek` on resolve; without it,
    `gameweek` is left NULL rather than guessed."""
    has_matchday = "matchday" in matches_df.columns
    now = _naive(pd.Timestamp.now(tz="UTC"))

    # `commence_time` in the predictions table is always stored naive (see
    # record_predictions), but football-data.org's own `date`/`commence_time`
    # column is tz-aware (UTC) — comparing the two raises "Cannot compare
    # tz-naive and tz-aware datetime-like objects", which this function's
    # only caller (_run_tracking_bookkeeping) swallows silently, so a
    # football-data.org-sourced finished match could never actually
    # reconcile. Normalize to naive here rather than relying on every
    # caller to pre-strip tz info.
    if isinstance(matches_df["date"].dtype, pd.DatetimeTZDtype):
        matches_df = matches_df.copy()
        matches_df["date"] = matches_df["date"].dt.tz_localize(None)

    with _connect() as conn:
        unresolved = pd.read_sql(
            "SELECT * FROM predictions WHERE resolved = 0", conn, parse_dates=["commence_time"]
        )
        if unresolved.empty:
            return 0

        due = unresolved[unresolved["commence_time"] < now]
        if due.empty:
            return 0

        resolved_count = 0
        for _, pred in due.iterrows():
            window_start = pred["commence_time"] - pd.Timedelta(days=lookback_days)
            window_end = pred["commence_time"] + pd.Timedelta(days=lookback_days)
            candidates = matches_df[
                (matches_df["team_home"] == pred["team_home"])
                & (matches_df["team_away"] == pred["team_away"])
                & (matches_df["date"] >= window_start)
                & (matches_df["date"] <= window_end)
            ]
            if candidates.empty:
                continue

            match = candidates.iloc[0]
            actual = _actual_outcome(pred["market"], pred["outcome_name"], match)
            gameweek = int(match["matchday"]) if has_matchday and pd.notna(match["matchday"]) else None
            conn.execute(
                """
                UPDATE predictions
                SET resolved = 1, actual_outcome = ?, resolved_at = ?,
                    actual_goals_home = ?, actual_goals_away = ?, gameweek = ?
                WHERE id = ?
                """,
                (
                    actual,
                    datetime.now(timezone.utc).isoformat(),
                    int(match["goals_home"]),
                    int(match["goals_away"]),
                    gameweek,
                    int(pred["id"]),
                ),
            )
            resolved_count += 1

        return resolved_count


def backfill_missing_gameweeks(matches_df: pd.DataFrame, lookback_days: int = 3) -> int:
    """Fill in `gameweek` for already-resolved rows that were left NULL
    because they resolved via the football-data.co.uk fallback (no
    `matchday` column) before football-data.org's own reconciliation got a
    chance to run first -- see `reconcile_predictions`'s docstring: once a
    row is `resolved`, that function's `WHERE resolved = 0` filter never
    revisits it, so a fixture that raced its way to a NULL gameweek stays
    NULL forever without this. Requires a `matchday`-carrying source
    (football-data.org); a no-op otherwise. Returns how many rows were
    backfilled."""
    if "matchday" not in matches_df.columns:
        return 0

    with _connect() as conn:
        missing = pd.read_sql(
            "SELECT * FROM predictions WHERE resolved = 1 AND gameweek IS NULL",
            conn,
            parse_dates=["commence_time"],
        )
        if missing.empty:
            return 0

        matches = matches_df
        if isinstance(matches["date"].dtype, pd.DatetimeTZDtype):
            matches = matches.copy()
            matches["date"] = matches["date"].dt.tz_localize(None)

        backfilled_count = 0
        for _, pred in missing.iterrows():
            window_start = pred["commence_time"] - pd.Timedelta(days=lookback_days)
            window_end = pred["commence_time"] + pd.Timedelta(days=lookback_days)
            candidates = matches[
                (matches["team_home"] == pred["team_home"])
                & (matches["team_away"] == pred["team_away"])
                & (matches["date"] >= window_start)
                & (matches["date"] <= window_end)
                & matches["matchday"].notna()
            ]
            if candidates.empty:
                continue

            gameweek = int(candidates.iloc[0]["matchday"])
            conn.execute("UPDATE predictions SET gameweek = ? WHERE id = ?", (gameweek, int(pred["id"])))
            backfilled_count += 1

        return backfilled_count


def _finished_matches_lookup(finished_matches: pd.DataFrame) -> set[tuple]:
    return {(r["team_home"], r["team_away"], _naive(r["date"]).date()) for _, r in finished_matches.iterrows()}


def has_unlogged_finished_matches(finished_matches: pd.DataFrame) -> bool:
    """Cheap pre-check for `backfill_missing_predictions`: same team+date
    matching it uses, but stops at the first gap instead of computing
    predictions. `finished_matches` needs `team_home`, `team_away`, `date`
    columns — pass whichever source has the freshest results (see
    `backfill_missing_predictions`'s docstring)."""
    if finished_matches.empty:
        return False

    with _connect() as conn:
        existing = pd.read_sql(
            "SELECT DISTINCT team_home, team_away, commence_time FROM predictions", conn, parse_dates=["commence_time"]
        )
    already_logged = {(r["team_home"], r["team_away"], _naive(r["commence_time"]).date()) for _, r in existing.iterrows()}

    return any(key not in already_logged for key in _finished_matches_lookup(finished_matches))


def backfill_missing_predictions(
    finished_matches: pd.DataFrame, model, model_trained_at: str | None = None, market_overrides: dict | None = None
) -> int:
    """One-time (and self-healing) catch-up for matches that finished
    before this app was polling `/api/fixtures` to snapshot them live —
    e.g. the handful of matches already played when prediction tracking
    first started this season, or any result that lands while the app is
    down. `finished_matches` needs `team_home`, `team_away`, `date`,
    `goals_home`, `goals_away`, `ftr` — pass whichever source has the
    freshest results (typically football-data.org, which tends to reflect
    a finished match faster than football-data.co.uk's own scrape).

    Computes what the model would have predicted via its ordinary
    live-serving `.predict(home, away)` path (the same one genuine
    upcoming fixtures use) rather than a point-in-time historical row —
    that's what makes this leakage-safe *specifically* for a match still
    missing from the backfill: the whole reason it needs backfilling is
    that football-data.co.uk (which the model's live context is built
    from) doesn't have this match yet, so "current state" at the moment
    this runs genuinely reflects "as of just before this match," the same
    as it would for any other fixture that hasn't been played yet. Once
    football-data.co.uk does catch up and the match's own stats flow into
    a future context rebuild, that's fine — this function has already
    logged the prediction it needs to for reconciliation, and later
    rebuilds don't retroactively change what was recorded here. Always
    marked `backfilled=True` so the Recent Results view can keep these
    visually distinct from rows the live path wrote — but that flag is
    provenance ("this row came from the backfill job"), NOT proof of timing.
    This docstring used to go further and call a live-captured prediction
    one that "proves no hindsight was even possible in principle", which was
    simply false: the five-minute tracking tick writes `backfilled=False`
    whenever it happens to run, so a pick written an hour after its own
    kickoff is labelled live-captured. The question "was this pick made
    before the match?" is answered by comparing `snapshotted_at` to
    `commence_time` (`_made_before_kickoff`), on every read, and never by this
    flag."""
    if finished_matches.empty:
        return 0

    with _connect() as conn:
        existing = pd.read_sql(
            "SELECT DISTINCT team_home, team_away, commence_time FROM predictions", conn, parse_dates=["commence_time"]
        )
    already_logged = {(r["team_home"], r["team_away"], _naive(r["commence_time"]).date()) for _, r in existing.iterrows()}

    prediction_rows, match_rows = [], []
    for _, row in finished_matches.iterrows():
        key = (row["team_home"], row["team_away"], _naive(row["date"]).date())
        if key in already_logged:
            continue
        pred = scoreline.predict_fixture(model, row["team_home"], row["team_away"], market_overrides=market_overrides)
        event_id = f"backfill-{row['team_home']}-{row['team_away']}-{key[2]}"
        top = pred["top_scorelines"][0]
        prediction_rows.append(
            {
                "event_id": event_id,
                "team_home": row["team_home"],
                "team_away": row["team_away"],
                "commence_time": row["date"],
                "home_win_prob": pred["home_win"],
                "draw_prob": pred["draw"],
                "away_win_prob": pred["away_win"],
                "over_2_5_prob": pred["over_2_5"],
                "under_2_5_prob": pred["under_2_5"],
                "btts_yes_prob": pred["btts_yes"],
                "top_scoreline": f"{top['home']}-{top['away']}",
            }
        )
        match_row = {
            "team_home": row["team_home"],
            "team_away": row["team_away"],
            # reconcile_predictions compares this directly against a
            # naive window (it reads commence_time back from SQLite,
            # which record_predictions always stores naive) — a
            # tz-aware "date" here (e.g. from football-data.org) would
            # raise "Invalid comparison between dtype=datetime64[us,
            # UTC] and Timestamp".
            "date": _naive(row["date"]),
            "goals_home": row["goals_home"],
            "goals_away": row["goals_away"],
            "ftr": row["ftr"],
        }
        if "matchday" in row.index:
            match_row["matchday"] = row["matchday"]
        match_rows.append(match_row)

    if not prediction_rows:
        return 0

    n = record_predictions(pd.DataFrame(prediction_rows), model_trained_at=model_trained_at, backfilled=True)
    reconcile_predictions(pd.DataFrame(match_rows), lookback_days=0)
    return n


def _fixture_hit_table() -> pd.DataFrame:
    """One row per resolved fixture (not per market row): team_home/away,
    commence_time, resolved_at, gameweek, predicted_scoreline, actual score,
    predicted H/D/A probabilities, actual_outcome (side name), hit (whether
    the model's highest-probability side matches what happened), backfilled.
    Shared by `get_track_record`/`get_results_by_gameweek`/
    `get_biggest_upsets` so "correct" is defined exactly once. Only fixtures
    with all three 1x2 rows resolved are included (matches the old
    `get_recent_results`'s behavior).

    Groups by (team_home, team_away, commence_time) to deduplicate the same
    fixture recorded under multiple event_ids (e.g. numeric FPL id and opaque
    Odds API id). Fixtures with unreadable commence_time are NOT grouped
    together (fail closed — they stay as separate rows keyed by event_id).
    """
    with _connect() as conn:
        resolved = pd.read_sql(
            "SELECT * FROM predictions WHERE resolved = 1 AND market = '1x2'",
            conn,
            parse_dates=["commence_time", "resolved_at"],
        )
    if resolved.empty:
        return pd.DataFrame()

    # History: fixture identity was (teams, kickoff DATE) until 2026-10-01, when
    # that was removed after measuring zero duplicates and finding two bugs -- a
    # kickoff straddling UTC midnight under two ids graded twice, and distinct
    # fixtures sharing a team pair with unreadable dates collapsed into one.
    # Duplicates are real now (PL#69: 20 fixtures in data/tracking_picks.jsonl sit
    # under both an FPL numeric id and an Odds-API opaque id), so we group again,
    # but on the EXACT commence_time, not the date: the same fixture carries the
    # identical timestamp under both ids, so there is no midnight straddle to
    # misjudge, and an unreadable (NaT) time is never grouped -- it falls back to
    # event_id. Pinned by the *_under_two_ids / straddle / unreadable tests.
    # Split into readable and unreadable commence_time. Unreadable ones
    # (NaT) must NOT be grouped together — each event_id stays separate.
    readable = resolved[resolved["commence_time"].notna()].copy()
    unreadable = resolved[resolved["commence_time"].isna()].copy()

    rows = []

    def _process_event_id_group(group: pd.DataFrame) -> dict | None:
        """Process a single event_id's 1x2 rows into one fixture row."""
        probs = {r["outcome_name"]: float(r["predicted_prob"]) for _, r in group.iterrows()}
        if set(probs) != {"home_win", "draw", "away_win"}:
            return None
        first = group.iloc[0]  # all rows in this group have same event_id, so same metadata
        hit_row = group[group["actual_outcome"] == 1]
        actual_side = hit_row.iloc[0]["outcome_name"] if not hit_row.empty else None
        predicted_side = max(probs, key=probs.get)
        return {
            "event_id": first["event_id"],
            "team_home": first["team_home"],
            "team_away": first["team_away"],
            "commence_time": first["commence_time"],
            "resolved_at": first["resolved_at"],
            "snapshotted_at": pd.to_datetime(group["snapshotted_at"]).min(),
            "gameweek": _none_if_nan_int(first["gameweek"]),
            "predicted_scoreline": first["predicted_scoreline"],
            "actual_goals_home": _none_if_nan_int(first["actual_goals_home"]),
            "actual_goals_away": _none_if_nan_int(first["actual_goals_away"]),
            "predicted_home_win": probs["home_win"],
            "predicted_draw": probs["draw"],
            "predicted_away_win": probs["away_win"],
            "predicted_prob_actual": probs.get(actual_side) if actual_side else None,
            "actual_outcome": actual_side,
            "hit": bool(actual_side is not None and predicted_side == actual_side),
            "backfilled": bool(first["backfilled"]),
        }

    # Group readable fixtures by (team_home, team_away, commence_time, event_id)
    # to get each event_id's complete 1x2 set, then pick the earliest event_id's set.
    if not readable.empty:
        for _, group in readable.groupby(["team_home", "team_away", "commence_time"]):
            # Within this (home, away, commence_time), pick the earliest event_id's complete set
            event_id_groups = [g for _, g in group.groupby("event_id")]
            event_id_rows = [_process_event_id_group(g) for g in event_id_groups]
            event_id_rows = [r for r in event_id_rows if r is not None]
            if event_id_rows:
                # Pick the one with earliest snapshotted_at
                earliest = min(event_id_rows, key=lambda r: r["snapshotted_at"])
                rows.append(earliest)

    # Unreadable commence_time: fall back to event_id grouping (fail closed)
    if not unreadable.empty:
        for _, group in unreadable.groupby("event_id"):
            row = _process_event_id_group(group)
            if row:
                rows.append(row)

    table = pd.DataFrame(rows)
    if not table.empty:
        table = table.reset_index(drop=True)
    return table


def _fixture_market_hit_table() -> pd.DataFrame:
    """`_fixture_hit_table()` extended with three more columns -- whether
    the exact scoreline, the Over/Under 2.5 goals call, and the BTTS call
    were correct -- so accuracy can be compared across every market the
    model calls, not just match result (see `get_fixture_post_match`'s
    per-fixture verdicts, which this generalises across a whole season).
    Same fixture universe as `_fixture_hit_table` (only where all three 1x2
    rows are resolved); a market column is None for a fixture whose
    totals_2_5/btts rows were never recorded (an early backfilled result,
    say) rather than dropping the fixture from every other column."""
    base = _fixture_hit_table()
    if base.empty:
        return base

    with _connect() as conn:
        markets = pd.read_sql(
            "SELECT event_id, market, outcome_name, predicted_prob FROM predictions "
            "WHERE resolved = 1 AND market IN ('totals_2_5', 'btts')",
            conn,
        )

    def _favoured_outcome(event_id, market: str, outcome_a: str, outcome_b: str) -> str | None:
        rows = markets[(markets["event_id"] == event_id) & (markets["market"] == market)]
        probs = {r["outcome_name"]: float(r["predicted_prob"]) for _, r in rows.iterrows()}
        if outcome_a not in probs or outcome_b not in probs:
            return None
        return outcome_a if probs[outcome_a] >= probs[outcome_b] else outcome_b

    def _btts_pick(event_id) -> str | None:
        # Unlike totals_2_5, only a single "yes" probability row is ever
        # stored for btts (see get_fixture_post_match's identical 0.5
        # threshold) -- there is no "no" row to look up.
        rows = markets[
            (markets["event_id"] == event_id) & (markets["market"] == "btts") & (markets["outcome_name"] == "yes")
        ]
        if rows.empty:
            return None
        return "yes" if float(rows.iloc[0]["predicted_prob"]) >= 0.5 else "no"

    def _row_market_hits(row) -> pd.Series:
        home, away, scoreline = row["actual_goals_home"], row["actual_goals_away"], row["predicted_scoreline"]
        exact_score_hit = None if home is None or away is None or scoreline is None else scoreline == f"{home}-{away}"

        over_under_pick = _favoured_outcome(row["event_id"], "totals_2_5", "over", "under")
        over_under_hit = None if over_under_pick is None or home is None or away is None else (
            (over_under_pick == "over") == ((home + away) > 2.5)
        )

        btts_pick = _btts_pick(row["event_id"])
        btts_hit = None if btts_pick is None or home is None or away is None else (
            (btts_pick == "yes") == bool(home and away)
        )

        return pd.Series({"exact_score_hit": exact_score_hit, "over_under_hit": over_under_hit, "btts_hit": btts_hit})

    return pd.concat([base, base.apply(_row_market_hits, axis=1)], axis=1)


def _market_reliability(fixtures: pd.DataFrame, column: str) -> dict:
    resolved = fixtures[column].dropna()
    return {
        "pct_correct": float(resolved.mean()) if not resolved.empty else None,
        "n_resolved": int(len(resolved)),
    }


def _iso(value) -> str | None:
    """A timestamp as an ISO string, or None when it is not one.

    A NaT is a timestamp nobody can read, and `pd.NaT.isoformat()` returns "NaT"
    — a string that looks like a timestamp to whatever consumes it and is not
    one. None is the honest answer, and it is also the one that makes
    `_made_before_kickoff` fail closed if the row is ever re-read.
    """
    if value is None:
        return None
    if isinstance(value, str):
        return value
    isoformat = getattr(value, "isoformat", None)
    if isoformat is None:
        return str(value)
    text = isoformat()
    return None if text == "NaT" else text


def _per_pick_rows(fixtures: pd.DataFrame) -> list[dict]:
    """One row per COUNTED pick, each labelled with when it was made.

    This is what makes the headline auditable rather than merely asserted, and it
    is what the 2026-10-01 reversal asks for: honesty moves from exclusion to
    disclosure. Every row carries `made_before_kickoff` beside its own
    `snapshotted_at`, so a reader can CHECK the label rather than take it — a row
    that says only "hit: true" cannot be checked against the claim that the
    headline counts picks made after the start.

    The label is DERIVED from the row's own two timestamps compared as UTC
    instants (`_made_before_kickoff`), never read from `backfilled` and never
    stored, so there is nothing to be stale and nothing to backfill.

    `rebuilt` is RETAINED under its published name as the exact negation,
    because a site may read it. It no longer means "not counted" — under the
    reversal a rebuilt pick IS counted — so `made_before_kickoff` is the field
    for anything a reader is meant to understand, and the two cannot disagree
    because one is computed from the other.

    Counted picks only, so a reader tallying this list arrives at the headline. A
    non-counted rerun is in the table as history and in neither figure nor list.
    """
    if fixtures.empty:
        return []
    rows = []
    for _, r in fixtures.iterrows():
        ct = r.get("commence_time")
        snap = r.get("snapshotted_at")
        made_before_kickoff = _made_before_kickoff(snap, ct)
        rows.append({
            "event_id": r.get("event_id"),
            "team_home": r.get("team_home"),
            "team_away": r.get("team_away"),
            "commence_time": _iso(ct),
            "gameweek": int(r["gameweek"]) if pd.notna(r.get("gameweek")) else None,
            "hit": bool(r["hit"]) if pd.notna(r.get("hit")) else None,
            # The disclosure, derived and never stored.
            "made_before_kickoff": made_before_kickoff,
            # The time the pick was made, so the label above can be checked.
            # None when it is unreadable, never the string "NaT".
            "snapshotted_at": _iso(snap),
            # Retained name, now meaning "made at or after kickoff" and nothing
            # more: this pick is still counted.
            "rebuilt": not made_before_kickoff,
        })
    return rows


def _all_picks_record(fixtures: pd.DataFrame) -> dict:
    """The same rates over EVERY COUNTED pick.

    **Kept under its published name, and it still means what it always meant:
    every pick.** Before the 2026-10-01 reversal the headline excluded picks
    recorded after their own kickoff, so this was the wider figure beside it. The
    reversal makes the HEADLINE the wider figure instead, and this key is what a
    site that already reads it gets. It is kept rather than renamed so no consumer
    breaks, and kept rather than deleted so a consumer reading `all_picks` is not
    silently pointed at a subset it believes is the whole record.

    Its `n_resolved` therefore now equals the headline's rather than exceeding it.
    The pre-kickoff figure a reader wants is `pre_kickoff`.
    """
    if fixtures.empty:
        return {"n_resolved": 0, "pct_correct": None, "by_market": {
            "exact_score": {"pct_correct": None, "n_resolved": 0},
            "match_result": {"pct_correct": None, "n_resolved": 0},
            "over_under_2_5": {"pct_correct": None, "n_resolved": 0},
            "btts": {"pct_correct": None, "n_resolved": 0},
        }}
    return {
        "n_resolved": int(len(fixtures)),
        "pct_correct": float(fixtures["hit"].mean()),
        "by_market": {
            "exact_score": _market_reliability(fixtures, "exact_score_hit"),
            "match_result": _market_reliability(fixtures, "hit"),
            "over_under_2_5": _market_reliability(fixtures, "over_under_hit"),
            "btts": _market_reliability(fixtures, "btts_hit"),
        },
    }


def _summarize_fixtures(fixtures: pd.DataFrame) -> dict:
    """The rate block over exactly the rows handed in: n, the headline rate, and
    the four per-market breakouts.

    Split out so the headline and `pre_kickoff` are the SAME summariser over two
    frames rather than two blocks of arithmetic that can drift apart. The
    secondary figure's `n` is then equal to the count of counted picks whose own
    timestamps prove they were made before kickoff, by construction rather than
    by agreement.
    """
    empty = {
        "exact_score": {"pct_correct": None, "n_resolved": 0},
        "match_result": {"pct_correct": None, "n_resolved": 0},
        "over_under_2_5": {"pct_correct": None, "n_resolved": 0},
        "btts": {"pct_correct": None, "n_resolved": 0},
    }
    if fixtures.empty:
        return {"n_resolved_fixtures": 0, "pct_correct_overall": None, "by_market": empty}
    return {
        "n_resolved_fixtures": int(len(fixtures)),
        "pct_correct_overall": float(fixtures["hit"].mean()),
        "by_market": {
            "exact_score": _market_reliability(fixtures, "exact_score_hit"),
            "match_result": _market_reliability(fixtures, "hit"),
            "over_under_2_5": _market_reliability(fixtures, "over_under_hit"),
            "btts": _market_reliability(fixtures, "btts_hit"),
        },
    }


def get_track_record() -> dict:
    """The track record: every COUNTED pick in the headline, the made-before-
    kickoff subset beside it.

    **This reverses the pre-2026-10-01 rule, under which the headline was the
    pre-kickoff record and a pick recorded after its own kickoff never counted
    toward it.** Kevin's reason, and it is the right one: the models are re-run
    constantly, so under the old rule a re-run on an already-played game stopped
    counting and the record emptied out on every model change. PL's shipped
    headline was empty for exactly that reason — `n_resolved_fixtures: 0,
    n_rebuilt_fixtures: 50, pct_correct_overall: null` — while 50 graded picks
    sat in the same payload under `all_picks`.

    Three consequences, stated so a reader is never misled about what the
    headline is:

    - **A recorded pick is never re-scored.** One counted pick per fixture
      (`_counted_picks`), the EARLIEST recorded one. A later rerun is kept in
      the table as history; it neither displaces the counted pick nor counts a
      second time, because re-running until the model is right would otherwise
      be free.
    - **`pre_kickoff` is the honest read of live performance**, and it is the
      figure to quote for what the model would have done on the night. It is the
      same summariser (`_summarize_fixtures`) over the counted picks whose own
      timestamps prove they were made before kickoff, so its `n` is the exact
      size of that subset rather than a figure reconciled by hand.
    - **Counting a late pick is a known, accepted cost.** A model fitted on data
      that includes the result can look better than it would have on the night.
      That is why both figures are published together, and why
      `n_rebuilt_fixtures` is still reported: the difference between the headline
      and `pre_kickoff` is exactly the size of the inflation.

    `n_rebuilt_fixtures` is RETAINED and now counts counted picks made at or
    after their own kickoff. It used to mean "excluded from the headline"; it no
    longer does, and `n_resolved_fixtures == pre_kickoff.n_resolved_fixtures +
    n_rebuilt_fixtures` holds.

    `all_picks` is RETAINED under its published name and still means every
    counted pick, which is now the same population as the headline. It is not
    renamed to `pre_kickoff` and not deleted, so no consumer breaks and none is
    silently pointed at a subset it believes is the whole record.

    **The counting key is per record type, not one key.** Fixture-level markets
    (result, exact score, O/U 2.5, BTTS) are keyed `(fixture, market)`, which
    reduces to the fixture's `event_id` because all four live as columns on one
    row. Player picks are keyed `(event_id, player_id)` — many players share a
    fixture, so collapsing a pick to game level deletes the player record — and
    they are graded by a separate entry point, `get_scorer_accuracy`, which
    applies that dedupe for real. See `_counted_picks` and
    `_counted_player_picks`.
    """
    resolved = _fixture_market_hit_table()

    # One counted pick per fixture, the earliest recorded; losers stay in the
    # table as history.
    counted = _counted_picks(resolved)
    # The secondary figure: of the counted picks, the ones whose own timestamps
    # prove they were made before their fixture's kickoff. Its n is therefore
    # exactly the size of that subset.
    pre = counted[counted.apply(_made_before_kickoff_row, axis=1)] if not counted.empty else counted
    n_rebuilt = int(len(counted) - len(pre))

    summary = _summarize_fixtures(counted)

    # current_gameweek is a navigation anchor (routes._resolve_current_gameweek,
    # public_snapshot's default view), not a rate: it follows every counted
    # fixture, whenever it was made.
    with_gw = counted[counted["gameweek"].notna()] if not counted.empty else counted
    current_gameweek = int(with_gw["gameweek"].max()) if not with_gw.empty else None
    this_gw = with_gw[with_gw["gameweek"] == current_gameweek] if current_gameweek is not None else with_gw.iloc[0:0]
    if not this_gw.empty:
        pct_correct_current_gameweek = float(this_gw["hit"].mean())
        n_fixtures_current_gameweek = int(len(this_gw))
    else:
        pct_correct_current_gameweek = None
        n_fixtures_current_gameweek = 0

    gameweek_trend = []
    if not with_gw.empty:
        grouped = with_gw.groupby("gameweek")["hit"].agg(["mean", "size"]).reset_index()
        gameweek_trend = [
            {"gameweek": int(r["gameweek"]), "pct_correct": float(r["mean"]), "n_fixtures": int(r["size"])}
            for _, r in grouped.sort_values("gameweek").iterrows()
        ]

    return {
        **summary,
        "n_rebuilt_fixtures": n_rebuilt,
        "current_gameweek": current_gameweek,
        "pct_correct_current_gameweek": pct_correct_current_gameweek,
        "n_fixtures_current_gameweek": n_fixtures_current_gameweek,
        "gameweek_trend": gameweek_trend,
        "pre_kickoff": {**_summarize_fixtures(pre), "n_rebuilt_fixtures": 0},
        "all_picks": _all_picks_record(counted),
        "per_pick": _per_pick_rows(counted),
    }



def get_calibration() -> dict:
    """Per-market confidence buckets (50-60/60-70/70%+) over resolved picks.

    Each bucket reports how many picks the model made at that confidence level
    and how many were right, so a reader can check whether 70% really means
    70%. One entry per market that has resolved picks; empty list otherwise.
    """
    import sqlite3
    from collections import defaultdict

    conn = _connect()
    try:
        result = {}

        # match_result (1x2)
        rows = conn.execute(
            "SELECT event_id, outcome_name, predicted_prob, actual_outcome "
            "FROM predictions WHERE resolved = 1 AND market = '1x2'"
        ).fetchall()
        fixtures = defaultdict(dict)
        for eid, outcome, prob, actual in rows:
            fixtures[eid][outcome] = (prob, actual)
        buckets = {"50-60%": [0, 0], "60-70%": [0, 0], "70%+": [0, 0]}
        for eid, outcomes in fixtures.items():
            if set(outcomes.keys()) != {"home_win", "draw", "away_win"}:
                continue
            probs = {k: v[0] for k, v in outcomes.items()}
            conf = max(probs.values())
            pick = max(probs, key=probs.get)
            hit = outcomes[pick][1] == 1
            if conf < 0.5:
                continue
            if conf < 0.6:
                b = "50-60%"
            elif conf < 0.7:
                b = "60-70%"
            else:
                b = "70%+"
            buckets[b][0] += 1
            if hit:
                buckets[b][1] += 1
        result["match_result"] = [{"bucket": k, "n": v[0], "correct": v[1]} for k, v in buckets.items() if v[0] > 0]

        # over_under_2_5
        rows = conn.execute(
            "SELECT event_id, outcome_name, predicted_prob, actual_outcome "
            "FROM predictions WHERE resolved = 1 AND market = 'totals_2_5'"
        ).fetchall()
        fixtures = defaultdict(dict)
        for eid, outcome, prob, actual in rows:
            fixtures[eid][outcome] = (prob, actual)
        buckets = {"50-60%": [0, 0], "60-70%": [0, 0], "70%+": [0, 0]}
        for eid, outcomes in fixtures.items():
            if set(outcomes.keys()) != {"over", "under"}:
                continue
            probs = {k: v[0] for k, v in outcomes.items()}
            conf = max(probs.values())
            pick = max(probs, key=probs.get)
            hit = outcomes[pick][1] == 1
            if conf < 0.5:
                continue
            if conf < 0.6:
                b = "50-60%"
            elif conf < 0.7:
                b = "60-70%"
            else:
                b = "70%+"
            buckets[b][0] += 1
            if hit:
                buckets[b][1] += 1
        result["over_under_2_5"] = [{"bucket": k, "n": v[0], "correct": v[1]} for k, v in buckets.items() if v[0] > 0]

        # btts (only yes outcome stored; confidence = max(yes, 1-yes))
        rows = conn.execute(
            "SELECT event_id, predicted_prob, actual_outcome, actual_goals_home, actual_goals_away "
            "FROM predictions WHERE resolved = 1 AND market = 'btts' AND outcome_name = 'yes'"
        ).fetchall()
        buckets = {"50-60%": [0, 0], "60-70%": [0, 0], "70%+": [0, 0]}
        for eid, prob, actual, gh, ga in rows:
            conf = max(prob, 1 - prob)
            pick_yes = prob >= 0.5
            actual_btts = gh is not None and ga is not None and gh > 0 and ga > 0
            hit = pick_yes == actual_btts
            if conf < 0.5:
                continue
            if conf < 0.6:
                b = "50-60%"
            elif conf < 0.7:
                b = "60-70%"
            else:
                b = "70%+"
            buckets[b][0] += 1
            if hit:
                buckets[b][1] += 1
        result["btts"] = [{"bucket": k, "n": v[0], "correct": v[1]} for k, v in buckets.items() if v[0] > 0]

        return result
    finally:
        conn.close()


def get_validation_calibration() -> dict:
    """RPS/Brier/ignorance of the recorded 1X2 probabilities, for the public
    /calibration surface (see routes.get_calibration's PUBLIC_MODE branch).

    The population is the counted one -- fixtures whose pick was recorded
    before kickoff (`_made_before_kickoff`, derived from the row's own
    timestamps, so backfilled after-the-fact rows exclude themselves) with a
    complete home/draw/away triple. That is deliberately NOT the live path's
    holdout-season validation frame: computing that frame on the public
    host is what PUBLIC_MODE exists to prevent, and the snapshot build's
    one attempt to bake it hung the build. These numbers answer a slightly
    different, still honest question -- how well calibrated are the picks
    this site actually published -- over the same fixtures the track
    record counts.

    `bookmaker` is None: no bookmaker probability is stored alongside a
    recorded pick, so there is nothing honest to report here (the
    bookmaker comparison lives in evaluate/calibration.py's live path,
    where closing odds exist). `naive` is the same fixed 46/25/29 split
    the live path uses, scored on the same fixtures.
    """
    from collections import defaultdict

    import numpy as np
    import penaltyblog as pb

    conn = _connect()
    try:
        rows = conn.execute(
            "SELECT event_id, outcome_name, predicted_prob, actual_outcome, snapshotted_at, commence_time "
            "FROM predictions WHERE resolved = 1 AND market = '1x2'"
        ).fetchall()
    finally:
        conn.close()

    order = ["home_win", "draw", "away_win"]
    fixtures: dict[str, dict] = defaultdict(dict)
    timing: dict[str, tuple] = {}
    for event_id, outcome, prob, actual, snapshotted_at, commence_time in rows:
        fixtures[event_id][outcome] = (prob, actual)
        timing[event_id] = (snapshotted_at, commence_time)

    probs, outcomes = [], []
    for event_id, by_outcome in fixtures.items():
        if set(by_outcome) != set(order):
            continue
        if not _made_before_kickoff(*timing[event_id]):
            continue
        probs.append([by_outcome[name][0] for name in order])
        outcomes.append(next(i for i, name in enumerate(order) if by_outcome[name][1] == 1))

    if not probs:
        return {
            "model": {"rps": None, "brier": None, "ignorance": None, "n_matches": 0},
            "bookmaker": None,
            "naive": {"rps": None, "brier": None, "n_matches": 0},
        }

    probs_arr = np.array(probs)
    outcomes_arr = np.array(outcomes)
    naive_arr = np.tile([0.46, 0.25, 0.29], (len(probs), 1))
    return {
        "model": {
            "rps": float(pb.metrics.rps_average(probs_arr, outcomes_arr)),
            "brier": float(pb.metrics.multiclass_brier_score(probs_arr, outcomes_arr)),
            "ignorance": float(pb.metrics.ignorance_score(probs_arr, outcomes_arr)),
            "n_matches": len(probs),
        },
        "bookmaker": None,
        "naive": {
            "rps": float(pb.metrics.rps_average(naive_arr, outcomes_arr)),
            "brier": float(pb.metrics.multiclass_brier_score(naive_arr, outcomes_arr)),
            "n_matches": len(probs),
        },
    }


def get_biggest_upsets(limit: int = 5) -> list[dict]:
    """Genuine 1x2 upsets only — the side that actually happened, ranked by
    how unlikely the model said it was. Deliberately not "biggest squared
    error across all markets": that would resurface confident-but-wrong
    goals/BTTS misses, which aren't what "upset" means and aren't tracked by
    this view anymore."""
    fixtures = _fixture_hit_table()
    # Upsets are ranked over every resolved pick, rebuilt or not, matching
    # the track record's score-everything rule.
    fixtures = fixtures[fixtures["actual_outcome"].notna()] if not fixtures.empty else fixtures
    if fixtures.empty:
        return []

    worst = fixtures.sort_values("predicted_prob_actual", ascending=True).head(limit)
    return [
        {
            "team_home": r["team_home"],
            "team_away": r["team_away"],
            "commence_time": r["commence_time"].isoformat(),
            "gameweek": r["gameweek"],
            "actual_goals_home": r["actual_goals_home"],
            "actual_goals_away": r["actual_goals_away"],
            "actual_outcome": r["actual_outcome"],
            "predicted_prob": float(r["predicted_prob_actual"]),
        }
        for _, r in worst.iterrows()
    ]


def get_results_by_gameweek() -> list[dict]:
    """Resolved fixtures grouped by gameweek, most recent gameweek first
    (fixtures with no gameweek data — resolved via the football-data.co.uk
    fallback, which has no matchday column — bucketed last under `gameweek:
    null`). Each group also carries its own `pct_correct`/`n_fixtures` so the
    frontend can render a per-gameweek header without a second aggregation.
    `pct_correct_by_market` breaks that same header out per market, so the
    per-gameweek list doubles as a reliability trend for each of the 4
    markets without a separate chart (see `_fixture_market_hit_table`)."""
    fixtures = _fixture_market_hit_table()
    if fixtures.empty:
        return []

    fixtures = fixtures.sort_values("commence_time", ascending=False)
    groups = []
    for gameweek, group in fixtures.groupby(fixtures["gameweek"].fillna(-1)):
        gw_value = None if gameweek == -1 else int(gameweek)
        # Every resolved pick in the group counts, rebuilt or not; `n_rebuilt` is
        # the informational split, and it is the SAME derivation the track
        # record reports as `n_rebuilt_fixtures` — each fixture's own two
        # timestamps compared as UTC instants, never the stored `backfilled`
        # flag. It used to be `group["backfilled"].sum()`, which is a different
        # population: `record_predictions` takes `backfilled=` as an argument,
        # so a group could report `n_rebuilt` that disagrees with the headline
        # it sits beside. `made_before_kickoff` on each fixture row is the same
        # derivation again, so a reader can check the count instead of taking
        # it. `n_rebuilt + n_made_before_kickoff == n_fixtures` holds.
        made_pre = group.apply(_made_before_kickoff_row, axis=1)
        n_made_pre = int(made_pre.sum())
        n_rebuilt_group = int(len(group)) - n_made_pre
        groups.append(
            {
                "gameweek": gw_value,
                "pct_correct": float(group["hit"].mean()),
                "n_fixtures": int(len(group)),
                "n_rebuilt": n_rebuilt_group,
                "n_made_before_kickoff": n_made_pre,
                "pct_correct_by_market": {
                    "exact_score": _market_reliability(group, "exact_score_hit")["pct_correct"],
                    "match_result": float(group["hit"].mean()),
                    "over_under_2_5": _market_reliability(group, "over_under_hit")["pct_correct"],
                    "btts": _market_reliability(group, "btts_hit")["pct_correct"],
                },
                "fixtures": [
                    {
                        "event_id": r["event_id"],
                        "team_home": r["team_home"],
                        "team_away": r["team_away"],
                        "commence_time": _iso(r["commence_time"]),
                        "predicted_scoreline": r["predicted_scoreline"],
                        "actual_goals_home": r["actual_goals_home"],
                        "actual_goals_away": r["actual_goals_away"],
                        "predicted_home_win": r["predicted_home_win"],
                        "predicted_draw": r["predicted_draw"],
                        "predicted_away_win": r["predicted_away_win"],
                        "actual_outcome": r["actual_outcome"],
                        "hit": r["hit"],
                        # The derivation, on every read, failing closed to False.
                        # `backfilled` is kept below for the fixtures that were
                        # reconstructed; nothing reads it to decide timing.
                        "made_before_kickoff": bool(pre),
                        # Carried so the label above can be checked rather
                        # than taken. `_iso` because a string column reaches
                        # this path from a cached frame and `pd.NaT` must not
                        # be published as the literal string "NaT".
                        "snapshotted_at": _iso(r["snapshotted_at"]),
                        "backfilled": r["backfilled"],
                    }
                    for (_, r), pre in zip(group.iterrows(), made_pre)
                ],
            }
        )

    groups.sort(key=lambda g: (g["gameweek"] is None, -(g["gameweek"] or 0)))
    return groups


def get_fixture_prediction(event_id: str) -> dict | None:
    """All markets' honestly pre-match-recorded probabilities for one
    fixture, by event_id. Used to show a finished fixture's prediction
    (e.g. reached via the gameweek view) without recomputing it live —
    for an already-played match, live recomputation risks that match's
    own result having fed back into "current model state," which would
    make the "prediction" shown partly hindsight. None if this event_id
    was never logged.

    Carries `made_before_kickoff`, DERIVED from the fixture's earliest recorded
    `snapshotted_at` against its kickoff, so `/facts` can label the pick's
    timing without ever reading the stored `backfilled` flag. Fails closed to
    `False` when either timestamp is unreadable — and `False` is what a reader
    must act on, so it withholds the "pre-kickoff" claim rather than inventing
    one. It is derived on this read and never stored."""
    with _connect() as conn:
        rows = pd.read_sql(
            "SELECT * FROM predictions WHERE event_id = ?", conn, params=(event_id,), parse_dates=["commence_time"]
        )
    if rows.empty:
        return None

    probs = {r["outcome_name"]: float(r["predicted_prob"]) for _, r in rows.iterrows()}
    first = rows.iloc[0]
    # One event_id is one fixture and one counted pick, so the timing label
    # reads the EARLIEST row's stamp — the same rule `_counted_picks` applies.
    stamps = rows["snapshotted_at"].map(_utc_instant).dropna()
    earliest = stamps.min() if not stamps.empty else None
    return {
        "event_id": event_id,
        "team_home": first["team_home"],
        "team_away": first["team_away"],
        "commence_time": first["commence_time"].isoformat(),
        "home_win": probs.get("home_win", 0.0),
        "draw": probs.get("draw", 0.0),
        "away_win": probs.get("away_win", 0.0),
        "over_2_5": probs.get("over", 0.0),
        "under_2_5": probs.get("under", 0.0),
        "btts_yes": probs.get("yes", 0.0),
        "predicted_scoreline": first["predicted_scoreline"],
        "made_before_kickoff": _made_before_kickoff(earliest, first["commence_time"]),
    }


def _none_if_nan_int(value) -> int | None:
    return None if pd.isna(value) else int(value)


def record_fixture_market_predictions(
    event_id: str,
    team_home: str,
    team_away: str,
    commence_time,
    predictions: dict[str, dict],
    provenance: str = "snapshot",
) -> int:
    """Persist corners/cards O/U probabilities without altering core markets.

    The first row always wins. A genuine pre-kickoff snapshot must never be
    overwritten by a later reconstructed view of the same fixture.
    """
    rows = [
        (
            str(event_id), team_home, team_away, _naive(commence_time).isoformat(), market,
            float(prediction["lambda"]), float(prediction["line"]), float(prediction["over"]),
            float(prediction["under"]), provenance,
        )
        for market, prediction in predictions.items()
    ]
    if not rows:
        return 0
    with _connect() as conn:
        cursor = conn.executemany(
            """
            INSERT OR IGNORE INTO fixture_market_predictions
            (event_id, team_home, team_away, commence_time, market, lambda_value, line,
             over_probability, under_probability, provenance)
            VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?, ?)
            """,
            rows,
        )
        return cursor.rowcount


def reconcile_fixture_market_predictions(matches_df: pd.DataFrame, lookback_days: int = 3) -> int:
    """Attach final corner/card totals to unresolved saved market snapshots."""
    required = {"date", "team_home", "team_away"}
    if matches_df.empty or not required.issubset(matches_df.columns):
        return 0
    source = matches_df.copy()
    source["date"] = pd.to_datetime(source["date"]).map(_naive)
    with _connect() as conn:
        unresolved = pd.read_sql(
            "SELECT * FROM fixture_market_predictions WHERE resolved = 0", conn, parse_dates=["commence_time"]
        )
        updated = 0
        for _, prediction in unresolved.iterrows():
            date = _naive(prediction["commence_time"])
            candidates = source[
                (source["team_home"] == prediction["team_home"])
                & (source["team_away"] == prediction["team_away"])
                & (source["date"] >= date - pd.Timedelta(days=lookback_days))
                & (source["date"] <= date + pd.Timedelta(days=lookback_days))
            ]
            if candidates.empty:
                continue
            match = candidates.iloc[0]
            columns = ("hc", "ac") if prediction["market"] == "corners" else ("hy", "ay", "hr", "ar")
            if not all(column in match.index and pd.notna(match[column]) for column in columns[:2]):
                continue
            if prediction["market"] == "corners":
                actual_total = float(match["hc"] + match["ac"])
            else:
                actual_total = float(match["hy"] + match["ay"] + (match.get("hr", 0) or 0) + (match.get("ar", 0) or 0))
            conn.execute(
                "UPDATE fixture_market_predictions SET actual_total = ?, resolved = 1 WHERE event_id = ? AND market = ?",
                (actual_total, prediction["event_id"], prediction["market"]),
            )
            updated += 1
        return updated


def record_player_prediction_snapshots(event_id: str, players: list[dict], provenance: str = "snapshot") -> int:
    """Store confirmed starters; a call needs a 20%+ goal, assist, or G+A signal."""
    confirmed = [player for player in players if player.get("confirmed_starter")]
    recommended_ids = {
        int(player["player_id"])
        for player in sorted(confirmed, key=lambda player: float(player["anytime_goal_contribution_prob"]), reverse=True)[:3]
    }
    rows = [
        (
            str(event_id), int(player["player_id"]), player["name"], player["team"],
            float(player["anytime_goal_prob"]), float(player["anytime_assist_prob"]),
            float(player["anytime_goal_contribution_prob"]), int(bool(player["confirmed_starter"])),
            int(
                bool(player["confirmed_starter"])
                and (
                    float(player["anytime_goal_prob"]) >= 0.20
                    or float(player["anytime_assist_prob"]) >= 0.20
                    or float(player["anytime_goal_contribution_prob"]) >= 0.20
                )
            ),
            int(int(player["player_id"]) in recommended_ids), provenance,
        )
        for player in confirmed
    ]
    if not rows:
        return 0
    with _connect() as conn:
        cursor = conn.executemany(
            """
            INSERT OR IGNORE INTO player_prediction_snapshots
            (event_id, player_id, name, team, goal_probability, assist_probability,
             contribution_probability, confirmed_starter, qualifies_call, is_recommended, provenance)
            VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?)
            """,
            rows,
        )
        return cursor.rowcount


def has_player_prediction_snapshots(event_id: str) -> bool:
    with _connect() as conn:
        row = conn.execute(
            "SELECT 1 FROM player_prediction_snapshots WHERE event_id = ? LIMIT 1", (str(event_id),)
        ).fetchone()
    return row is not None


def record_fixture_player_outcomes(event_id: str, outcomes: dict[int, dict]) -> int:
    rows = [
        (str(event_id), int(player_id), "home" if outcome.get("was_home") else "away", int(outcome.get("goals", 0)), int(outcome.get("assists", 0)))
        for player_id, outcome in outcomes.items()
        if outcome.get("was_home") is not None
    ]
    if not rows:
        return 0
    with _connect() as conn:
        cursor = conn.executemany(
            "INSERT OR IGNORE INTO fixture_player_outcomes (event_id, player_id, side, goals, assists) VALUES (?, ?, ?, ?, ?)",
            rows,
        )
        return cursor.rowcount


def has_fixture_player_outcomes(event_id: str) -> bool:
    with _connect() as conn:
        return conn.execute(
            "SELECT 1 FROM fixture_player_outcomes WHERE event_id = ? LIMIT 1", (str(event_id),)
        ).fetchone() is not None


def get_fixture_player_events(event_id: str, bootstrap: dict) -> dict:
    with _connect() as conn:
        rows = pd.read_sql(
            "SELECT * FROM fixture_player_outcomes WHERE event_id = ? AND (goals > 0 OR assists > 0)",
            conn,
            params=(str(event_id),),
        )
    names = {int(element["id"]): element["web_name"] for element in bootstrap.get("elements", [])}
    result = {"home": [], "away": []}
    for _, row in rows.iterrows():
        result[row["side"]].append({
            "name": names.get(int(row["player_id"]), f"Player {int(row['player_id'])}"),
            "goals": int(row["goals"]),
            "assists": int(row["assists"]),
        })
    for side in result:
        result[side].sort(key=lambda player: (-player["goals"], -player["assists"], player["name"]))
    return result


def resolved_fixtures_missing_player_snapshots(gameweek: int | None = None) -> list[dict]:
    where = "WHERE resolved = 1"
    params: tuple = ()
    if gameweek is not None:
        where += " AND gameweek = ?"
        params = (int(gameweek),)
    with _connect() as conn:
        rows = pd.read_sql(
            f"""
            SELECT event_id, team_home, team_away, commence_time, gameweek
            FROM predictions
            {where}
            GROUP BY event_id, team_home, team_away, commence_time, gameweek
            HAVING COUNT(*) = SUM(resolved)
               AND (
                   NOT EXISTS (
                       SELECT 1 FROM player_prediction_snapshots player
                       WHERE player.event_id = predictions.event_id
                   )
                   OR NOT EXISTS (
                       SELECT 1 FROM fixture_player_outcomes outcome
                       WHERE outcome.event_id = predictions.event_id
                   )
               )
            ORDER BY commence_time
            """,
            conn,
            params=params,
        )
    return rows.to_dict("records")


def reconcile_player_prediction_snapshots(event_id: str, outcomes: dict[int, dict]) -> int:
    """Resolve saved player probabilities against FPL's confirmed outcomes."""
    if not outcomes:
        return 0
    with _connect() as conn:
        rows = pd.read_sql(
            "SELECT player_id FROM player_prediction_snapshots WHERE event_id = ? AND resolved = 0",
            conn,
            params=(str(event_id),),
        )
        updated = 0
        for player_id in rows["player_id"]:
            outcome = outcomes.get(int(player_id))
            if outcome is None:
                continue
            conn.execute(
                """UPDATE player_prediction_snapshots
                   SET actual_goals = ?, actual_assists = ?, resolved = 1
                   WHERE event_id = ? AND player_id = ?""",
                (int(outcome.get("goals", 0)), int(outcome.get("assists", 0)), str(event_id), int(player_id)),
            )
            updated += 1
        return updated


def get_fixture_post_match(event_id: str) -> dict | None:
    """Return a compact, presentation-ready review for a completed fixture."""
    core = get_fixture_prediction(event_id)
    if core is None:
        return None
    with _connect() as conn:
        core_rows = pd.read_sql("SELECT * FROM predictions WHERE event_id = ?", conn, params=(str(event_id),))
        markets = pd.read_sql("SELECT * FROM fixture_market_predictions WHERE event_id = ?", conn, params=(str(event_id),))
        players = pd.read_sql("SELECT * FROM player_prediction_snapshots WHERE event_id = ?", conn, params=(str(event_id),))
    if core_rows.empty or not core_rows["resolved"].all():
        return None
    first = core_rows.iloc[0]
    home_goals, away_goals = int(first["actual_goals_home"]), int(first["actual_goals_away"])
    total_goals = home_goals + away_goals
    outcome = "home_win" if home_goals > away_goals else "away_win" if away_goals > home_goals else "draw"
    result_probs = {row["outcome_name"]: float(row["predicted_prob"]) for _, row in core_rows[core_rows["market"] == "1x2"].iterrows()}
    goals_probs = {row["outcome_name"]: float(row["predicted_prob"]) for _, row in core_rows[core_rows["market"] == "totals_2_5"].iterrows()}
    btts_prob = float(core_rows[(core_rows["market"] == "btts") & (core_rows["outcome_name"] == "yes")].iloc[0]["predicted_prob"])

    # Plain marginal argmax -- matches `_fixture_hit_table()` exactly, so a
    # fixture's "correct?" verdict here always agrees with the season-wide
    # accuracy stats that use the same fixture. A prior version of this
    # function credited a "hit" whenever the top scoreline was a draw, on
    # the theory that draws are structurally suppressed in the marginal
    # probabilities (they are -- see outcomes.py) and deserved a second
    # look. A walk-forward backtest across 5 seasons (1,900 fixtures)
    # disproved that: even gated behind a real draw-probability floor, the
    # rule was net-negative for accuracy at every threshold with meaningful
    # volume (a "1-1" top scoreline is weak evidence of an actual draw --
    # often just the least-bad single grid cell, not a real signal the
    # match levels). See `outcomes.predicted_result`, which is used for
    # informational pre-match display (`api/schemas.py`'s `draw_signal`)
    # but deliberately NOT for this hit/accuracy determination.
    marginal_pick = max(result_probs, key=result_probs.get)
    match_result_hit, match_result_prediction = marginal_pick == outcome, marginal_pick

    verdicts = [
        {"label": "Exact score", "prediction": core["predicted_scoreline"], "actual": f"{home_goals}-{away_goals}", "hit": core["predicted_scoreline"] == f"{home_goals}-{away_goals}"},
        {"label": "Match result", "prediction": match_result_prediction, "actual": outcome, "hit": match_result_hit},
        {"label": "Goals O/U 2.5", "prediction": "over" if goals_probs.get("over", 0) >= goals_probs.get("under", 0) else "under", "actual": "over" if total_goals > 2.5 else "under", "hit": (goals_probs.get("over", 0) >= goals_probs.get("under", 0)) == (total_goals > 2.5)},
        {"label": "BTTS", "prediction": "yes" if btts_prob >= 0.5 else "no", "actual": "yes" if home_goals and away_goals else "no", "hit": (btts_prob >= 0.5) == bool(home_goals and away_goals)},
    ]
    for _, market in markets.iterrows():
        if not bool(market["resolved"]):
            continue
        predicted_over = float(market["over_probability"]) >= float(market["under_probability"])
        actual_over = float(market["actual_total"]) > float(market["line"])
        verdicts.append({"label": f"{market['market'].title()} O/U {market['line']:g}", "prediction": "over" if predicted_over else "under", "actual": f"{market['actual_total']:g}", "hit": predicted_over == actual_over})
    player_calls = []
    if not players.empty:
        # Same no-dedupe decision as `get_fixture_player_review`, and the same
        # reason: `player_prediction_snapshots` is keyed
        # `PRIMARY KEY (event_id, player_id)` and written only by
        # `INSERT OR IGNORE`, so this loop sees at most one row per player. It
        # does agree with the counting path by construction — the filter below
        # is `qualifies_call AND (goals > 0 OR assists > 0)`, which is exactly
        # `_scorer_accuracy_group`'s `call_hits` population, so these rows and
        # the counted hits are the same rows rather than two derivations that
        # happen to match. Read that function's docstring before adding a
        # dedupe here; it explains why one would discard a row arbitrarily.
        for _, player in players.iterrows():
            if not bool(player["resolved"]):
                continue
            goals, assists = int(player["actual_goals"]), int(player["actual_assists"])
            goal_called = float(player["goal_probability"]) >= 0.20
            assist_called = float(player["assist_probability"]) >= 0.20
            contribution_called = bool(player["qualifies_call"])
            is_recommended = bool(player["is_recommended"])
            if not (contribution_called and (goals > 0 or assists > 0)):
                continue
            player_calls.append({
                "name": player["name"], "team": player["team"], "goal_probability": float(player["goal_probability"]),
                "assist_probability": float(player["assist_probability"]), "contribution_probability": float(player["contribution_probability"]),
                "goals": goals, "assists": assists, "goal_hit": goals > 0, "assist_hit": assists > 0,
                "goal_called": goal_called, "assist_called": assist_called, "contribution_called": contribution_called,
                "is_recommended": is_recommended,
                "contribution_hit": goals > 0 or assists > 0, "provenance": player["provenance"],
            })
    provenance = "snapshot" if not markets.empty and (markets["provenance"] == "snapshot").any() else "reconstructed"
    return {"final_score": f"{home_goals}-{away_goals}", "provenance": provenance, "verdicts": verdicts, "player_calls": player_calls}


def get_fixture_player_review(event_id: str) -> dict | None:
    """Resolved confirmed-starter calls, plus resolved scorers who did not
    qualify, for one fixture.

    Both populations, not just the qualifying calls: the `elif hit` arm below
    labels a player who scored while clearing no threshold as
    `"Overperformer"`, and those land in the `overperformed` bucket rather than
    being dropped. Anyone reading only the qualifying threshold would
    under-count what this returns, and would conclude the view is filtered to
    calls when a third of its output is not.

    **No dedupe here, and that is a measured decision, not an oversight.** #44
    flagged this view and `get_fixture_post_match` as the two readers still
    taking every player row without `_counted_player_picks`' dedupe, on the
    theory that a detail view showing a player's scored picks is part of that
    player's record and would render one player's run twice. Traced, that
    theory does not hold: a duplicate `(event_id, player_id)` row is
    UNREACHABLE, so a dedupe here could never fire.

    What holds the key is structural, not incidental:

    - the table is `PRIMARY KEY (event_id, player_id)` and has carried it since
      it was introduced; its only migrations are `ALTER TABLE ADD COLUMN`,
      which cannot drop a PK;
    - its only writer is `INSERT OR IGNORE`, so a rerun can neither append a
      second row nor overwrite the first. Measured: five identical writes, a
      rerun carrying changed probabilities, and snapshot-then-reconstructed all
      leave exactly one row. The refresh workflow reruns every 20 minutes on
      matchdays, so that rerun is routine, not hypothetical;
    - #46 is a `frontend/src/predictor-ui/` re-vendor and writes no row at all.

    Worth being precise about why the COUNTING path dedupes anyway when the
    same PK holds there too: the two defend against different failures. This
    view is bounded by the PK, so a re-key degrades it VISIBLY — a player
    listed twice is obvious on screen. The counting path's answer is a bare
    accuracy number, so a re-key there inflates it invisibly and nothing
    downstream can catch it. That asymmetry is the whole argument for
    `_counted_player_picks`, and it is the one thing that does not transfer.

    **So do not "fix" this by calling `_counted_player_picks` here.** On this
    table it could not pick the EARLIEST row even if a duplicate existed: the
    table carries no timestamp column at all, which is why `_instants` yields
    all-NaT for it and `_counted_player_picks`' own docstring says "earliest"
    cannot order anything here. Such a dedupe would discard one of two rows on
    an arbitrary storage-order basis while appearing to apply the standing
    earliest-recorded rule — strictly worse than showing both.
    `test_detail_views_and_counting_path_share_one_key` is the real guard: it
    reads the key out of the live schema, so a re-key fails a test instead of
    quietly changing what this renders.
    """
    with _connect() as conn:
        players = pd.read_sql(
            "SELECT * FROM player_prediction_snapshots WHERE event_id = ? AND resolved = 1",
            conn,
            params=(str(event_id),),
        )
    if players.empty:
        return None
    calls = []
    for _, player in players.iterrows():
        goals, assists = int(player["actual_goals"]), int(player["actual_assists"])
        goal_probability = float(player["goal_probability"])
        assist_probability = float(player["assist_probability"])
        contribution_probability = float(player["contribution_probability"])
        hit = goals > 0 or assists > 0
        is_recommended = bool(player["is_recommended"])
        if hit and goals > 0 and goal_probability >= PLAYER_REVIEW_GOAL_THRESHOLD:
            label, probability, market = "Goal call", goal_probability, "Goal"
        elif hit and assists > 0 and assist_probability >= PLAYER_REVIEW_ASSIST_THRESHOLD:
            label, probability, market = "Assist call", assist_probability, "Assist"
        elif hit and is_recommended:
            label, probability, market = "Recommended player", contribution_probability, "G+A"
        elif hit and contribution_probability >= PLAYER_REVIEW_CONTRIBUTION_THRESHOLD:
            label, probability, market = "G+A call", contribution_probability, "G+A"
        elif hit:
            label, probability, market = "Overperformer", contribution_probability, "G+A"
        elif goal_probability >= PLAYER_REVIEW_GOAL_THRESHOLD:
            label, probability, market = "Goal call", goal_probability, "Goal"
        elif assist_probability >= PLAYER_REVIEW_ASSIST_THRESHOLD:
            label, probability, market = "Assist call", assist_probability, "Assist"
        elif is_recommended:
            label, probability, market = "Recommended player", contribution_probability, "G+A"
        elif contribution_probability >= PLAYER_REVIEW_CONTRIBUTION_THRESHOLD:
            label, probability, market = "G+A call", contribution_probability, "G+A"
        else:
            continue
        calls.append({
            "name": player["name"], "team": player["team"],
            "goal_probability": goal_probability,
            "assist_probability": assist_probability,
            "contribution_probability": contribution_probability,
            "goals": goals, "assists": assists,
            "hit": hit,
            "is_recommended": is_recommended,
            "review_label": label,
            "review_probability": probability,
            "review_market": market,
        })
    calls.sort(key=lambda player: (-player["review_probability"], player["name"]))
    provenance = "snapshot" if (players["provenance"] == "snapshot").any() else "reconstructed"
    return {
        "provenance": provenance,
        "correct": [player for player in calls if player["hit"] and player["review_label"] != "Overperformer"],
        "missed": [player for player in calls if not player["hit"]],
        "overperformed": [player for player in calls if player["hit"] and player["review_label"] == "Overperformer"],
    }


def _counted_player_picks(resolved: pd.DataFrame) -> pd.DataFrame:
    """The player rows that count: one per `(event_id, player_id)`, the EARLIEST
    recorded.

    **This is a DIFFERENT counting key from `_counted_picks`, and the difference
    is not cosmetic.** Keying a player pick on the game alone keeps one player
    per fixture and DELETES the rest of the player record outright — not
    mis-measures it, removes it. So player picks are counted here, in their own
    function, rather than sharing the fixture frame's key.

    **The key is `(event_id, player_id)` and NOT `(event_id, player_id,
    market)`.** The docstring used to claim the latter, and it was false in a way
    that crashed: `player_prediction_snapshots` has PRIMARY KEY
    `(event_id, player_id)` and carries all three player markets (goal, assist,
    G+A) as COLUMNS — there is no `market` column to key on, and
    `drop_duplicates(subset=[..., "market"])` raised
    `KeyError: Index(['market'])` on every real `SELECT *` this table returns.
    As with fixtures, the market reduces to the row, so the row must not be
    collapsed to one market: keying on the market column would have deleted the
    assist column off every player row.

    `player_prediction_snapshots` has no `snapshotted_at` column — provenance is
    recorded as `snapshot` vs `reconstructed` instead — so "earliest" cannot
    order anything today and the stable sort keeps the first row encountered.
    It is written anyway because a rule enforced only by a primary key stops
    being enforced the moment the key changes, and a re-keyed or restored
    history is exactly the case where a player pick would be graded twice.

    **Called from `get_scorer_accuracy`**, the serving path. It used to be
    reachable only from tests, which is how a `KeyError` on real data could sit
    in a module that ships: a rule asserted in a test and enforced nowhere.
    """
    if resolved.empty:
        return resolved
    ordered = resolved.assign(_instant=_instants(resolved))
    ordered = ordered.sort_values("_instant", na_position="last", kind="stable", ignore_index=True)
    return ordered.drop_duplicates(
        subset=["event_id", "player_id"], keep="first"
    ).drop(columns=["_instant"])


def get_scorer_accuracy() -> dict:
    """Accuracy and calibration for confirmed-starter scorer probabilities.

    **Counted on its own key, `(event_id, player_id)`** — see
    `_counted_player_picks`, which this function calls. The fixture grader's key
    would keep one player per fixture and delete the rest of the record, so the
    two must not share a key. The dedupe used to be dead code reachable only
    from tests; it runs here, before the snapshot/reconstructed split, so the
    COUNTED pick for a (fixture, player) pair is the one graded and its own
    provenance is the one that labels it.

    Deliberately NOT relaxed the way the track record was: the `snapshot` vs
    `reconstructed` split here is a statement about how the probability was
    produced, and this is a calibration view the scorer list reads, not the track
    record headline. The track-record reversal is a change to what the RECORD
    counts; carrying it here would be a second change wearing its clothes.
    """
    with _connect() as conn:
        rows = pd.read_sql("SELECT * FROM player_prediction_snapshots WHERE resolved = 1", conn)
    counted = _counted_player_picks(rows)
    result = {"snapshot": _scorer_accuracy_group(counted[counted["provenance"] == "snapshot"]), "reconstructed": _scorer_accuracy_group(counted[counted["provenance"] == "reconstructed"])} if not counted.empty else {"snapshot": _scorer_accuracy_group(counted), "reconstructed": _scorer_accuracy_group(counted)}
    return result


def _scorer_accuracy_group(rows: pd.DataFrame) -> dict:
    if rows.empty:
        return {"calls": 0, "call_hits": 0, "call_hit_rate": None, "goal_brier": None, "calibration": []}
    calls = rows[rows["qualifies_call"] == 1]
    goal_actual = (rows["actual_goals"] > 0).astype(float)
    probability = rows["goal_probability"].astype(float)
    calibration = []
    for lower in range(0, 100, 20):
        upper = lower + 20
        bucket = rows[(probability >= lower / 100) & (probability < upper / 100)]
        if bucket.empty:
            continue
        calibration.append({"range": f"{lower}-{upper}%", "n": int(len(bucket)), "predicted": float(bucket["goal_probability"].mean()), "actual": float((bucket["actual_goals"] > 0).mean())})
    return {
        "calls": int(len(calls)), "call_hits": int(((calls["actual_goals"] > 0) | (calls["actual_assists"] > 0)).sum()),
        "call_hit_rate": float(((calls["actual_goals"] > 0) | (calls["actual_assists"] > 0)).mean()) if not calls.empty else None,
        "goal_brier": float(((probability - goal_actual) ** 2).mean()), "calibration": calibration,
    }
