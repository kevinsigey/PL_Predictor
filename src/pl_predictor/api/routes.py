from __future__ import annotations

import os, pickle
_DISK_CACHE_DIR = os.path.expanduser("~/.cache/pl_predictor")
os.makedirs(_DISK_CACHE_DIR, exist_ok=True)
def _disk_cache(name):
    def decorator(func):
        def wrapper(*args, **kwargs):
            p = os.path.join(_DISK_CACHE_DIR, f"{name}.pkl")
            if os.path.exists(p):
                with open(p, "rb") as f:
                    return pickle.load(f)
            res = func(*args, **kwargs)
            with open(p, "wb") as f:
                pickle.dump(res, f)
            return res
        return wrapper
    return decorator

"""routes.py — thin JSON-serialization layer over the existing `pl_predictor`
package. No business logic lives here; every endpoint just calls the same
functions the notebooks/tests already use and reshapes the result for the
frontend.
"""


import json
import logging
import time
from datetime import datetime, timezone
from threading import Lock, Thread

import pandas as pd
from fastapi import APIRouter, Body, Depends, HTTPException

import requests

from ..config import (
    GITHUB_ACTIONS_REPO,
    GITHUB_ACTIONS_TOKEN,
    PUBLIC_MODE,
    PUBLIC_REFRESH_COOLDOWN_SECONDS,
    PUBLIC_SNAPSHOT_PATH,
    PUBLIC_SNAPSHOT_REFRESH_URL,
    SPORTSBOOK_CACHE_TTL_SECONDS,
)
from ..data import fixtures as fixtures_mod
from ..data import espn, fpl_api, fpl_history, understat, understat_shots
from ..data.team_names import to_canonical
from ..data import football_data
from ..data import football_data_org
from ..outcomes import predicted_result
from ..data.football_data_org import FootballDataOrgKeyMissing
from ..data.sportsbook_api import SportsbookAPIKeyMissing, fetch_epl_odds as fetch_sportsbook_odds
from ..evaluate import backtest as backtest_lib
from ..evaluate import betting_validation
from ..evaluate import calibration as calibration_lib
from ..evaluate import odds_benchmark
from ..evaluate import scoreline_selection
from ..features import head_to_head, opponent_defence, player_form, ratings as ratings_mod, rolling_form, squad_change
from ..features.build import build_features_for_fixtures, build_training_frame
from ..models import manifest as manifest_lib
from ..models import fpl as fpl_model, player_goals, power_rankings as power_rankings_mod, projected_table, scoreline
from ..models.manifest import chronological_split
from ..odds import value_bets
from ..tracking import store as tracking_store
from ..tracking import value_bet_ledger
from .schemas import (
    FixtureDetail,
    FixtureActualStats,
    FixturePlayers,
    FixtureSummary,
    FixtureTeamContext,
    H2HMeeting,
    MarketEdge,
    OverUnderPrediction,
    PlayerPrediction,
    SingleBetRecommendation,
    FPLManualSquadRequest,
    FPLTransferRequest,
)
from . import hub_analytics

router = APIRouter(prefix="/api")


def _admin_only() -> None:
    """Dependency for the four state-changing endpoints (retrain/refresh/
    backtest) — 404s them unconditionally on the public deployment.
    Pretending the route doesn't exist, rather than 403, avoids
    advertising an admin surface to a public visitor at all."""
    if PUBLIC_MODE:
        raise HTTPException(status_code=404)


_public_snapshot_cache: dict | None = None
_public_snapshot_etag: str | None = None


def _public_snapshot() -> dict:
    """The precomputed data public_snapshot.py generates. Cold-start value
    is whatever was baked into this image at build time; a running process
    then keeps it current via `refresh_public_snapshot_from_remote` below,
    polled on a timer (see api/main.py's lifespan) rather than by waiting
    for the next redeploy. Empty dict if none has been generated yet (a
    public deploy before its first snapshot exists), so every PUBLIC_MODE
    branch degrades to empty results instead of a 500."""
    global _public_snapshot_cache
    if _public_snapshot_cache is None:
        _public_snapshot_cache = (
            json.loads(PUBLIC_SNAPSHOT_PATH.read_text()) if PUBLIC_SNAPSHOT_PATH.exists() else {}
        )
    return _public_snapshot_cache


def refresh_public_snapshot_from_remote() -> bool:
    """Re-fetch the precomputed public snapshot from its GitHub raw URL and
    swap it in — lets a data-only commit (the GitHub Actions snapshot
    refresh, several times a day) reach the running process without a
    Docker rebuild+container swap, the same way the private/full app's own
    background loops keep it current without a restart. `ETag`-conditional
    so an unchanged snapshot costs one small request, not a re-download of
    the whole multi-MB file. Any fetch/parse failure is swallowed and
    leaves the previous snapshot serving — a transient network hiccup here
    must never blank an already-working public site."""
    global _public_snapshot_cache, _public_snapshot_etag
    try:
        headers = {"If-None-Match": _public_snapshot_etag} if _public_snapshot_etag else {}
        resp = requests.get(PUBLIC_SNAPSHOT_REFRESH_URL, headers=headers, timeout=30)
        if resp.status_code == 304:
            return False
        resp.raise_for_status()
        snapshot = resp.json()
    except Exception as exc:  # noqa: BLE001 - keep serving the last-known-good snapshot
        print(f"[public_snapshot] remote refresh skipped: {exc}")
        return False
    _public_snapshot_cache = snapshot
    _public_snapshot_etag = resp.headers.get("ETag")
    return True


_CACHE_TTL_SECONDS = 1800
# Fixtures/results/live-serving state get a much shorter TTL than everything
# else: on a live matchday, results and "which fixtures are still upcoming"
# genuinely change within minutes, and a stale 30-minute cache reads as "the
# app doesn't know a match already happened." `load_models(matches_df=...)`
# (the expensive part of this refreshing) benchmarks at ~0.4s on top of the
# ~7.5s data reload — trivial to redo this often for a personal app.
_LIVE_CACHE_TTL_SECONDS = 300
_LIVE_RESULTS_CACHE_TTL_SECONDS = 60
_cache: dict[str, tuple[float, object]] = {}
_cache_locks: dict[str, Lock] = {}
_player_outcome_backfill_lock = Lock()
_warmup_status = {"state": "not_started", "started_at": None, "completed_at": None, "failures": []}


def _cached(key: str, build_fn, ttl: float = _CACHE_TTL_SECONDS, force: bool = False):
    hit = _cache.get(key)
    if not force and hit and (time.time() - hit[0]) < ttl:
        return hit[1]

    lock = _cache_locks.setdefault(key, Lock())
    with lock:
        hit = _cache.get(key)
        if not force and hit and (time.time() - hit[0]) < ttl:
            return hit[1]
        value = build_fn()
        _cache[key] = (time.time(), value)
        return value


def _clear_cache(*keys: str):
    for k in keys:
        _cache.pop(k, None)


def _clear_cache_prefix(prefix: str) -> None:
    for key in list(_cache):
        if key.startswith(prefix):
            _cache.pop(key, None)


@router.get("/health")
def get_health():
    """Small readiness probe for the local UI and deployment checks.

    The server accepts requests while the expensive local caches warm in the
    background.  Exposing that state lets the frontend explain a temporarily
    slow first request instead of presenting it as a mysterious fetch error.
    """
    return {"status": "ok", "cache_warmup": dict(_warmup_status)}


def _refresh_player_outcomes_in_background(gameweek: int) -> None:
    """Refresh missing player events without making fixture cards wait."""
    if not _player_outcome_backfill_lock.acquire(blocking=False):
        return

    def run() -> None:
        try:
            backfill_completed_player_reviews(gameweek)
        finally:
            _player_outcome_backfill_lock.release()

    Thread(target=run, name="player-outcome-backfill", daemon=True).start()


def _get_matches_df() -> pd.DataFrame:
    def build():
        df = football_data.load_training_data()
        current = football_data.fetch_current_season_partial()
        if current is not None and not current.empty:
            df = pd.concat([df, current], ignore_index=True)
        return df.sort_values("date").reset_index(drop=True)

    return _cached("matches_df", build, ttl=_LIVE_CACHE_TTL_SECONDS)


def _get_live_current_results_df() -> pd.DataFrame:
    """Official FPL results, shared with the fixture fallback.

    This is deliberately separate from the rich current-season training
    frame: FPL final scores are timely enough for the live table but do not
    carry the shots/cards/referee inputs needed for a safe scoreline retrain.
    """
    return _cached("live_current_results", fpl_api.fetch_current_season_results, ttl=_LIVE_RESULTS_CACHE_TTL_SECONDS)


def _get_models() -> dict:
    if not manifest_lib.MANIFEST_PATH.exists():
        raise HTTPException(status_code=409, detail="No trained models yet — call POST /api/retrain first.")
    # matches_df is only actually used when the chosen scoreline model is
    # ml_scoreline (see manifest.load_models's docstring) — always passed
    # since it's cheap here (already cached separately) and keeps this
    # simple regardless of which model is currently chosen.
    return _cached("models", lambda: manifest_lib.load_models(matches_df=_get_matches_df()), ttl=_LIVE_CACHE_TTL_SECONDS)


def _get_fixtures_df(force: bool = False) -> pd.DataFrame:
    # fixtures_mod.get_upcoming_fixtures already tries the Sportsbook API
    # first and falls back to FPL fixtures (no odds) on any failure -- see
    # its own docstring. This used to duplicate that fallback here a second
    # time, on top of the old Odds-API-primary source; that whole path was
    # actually dead code (the inner call already swallowed every failure
    # before it could reach this wrapper) and, on top of that, mapped
    # Sportsbook participant *keys* through `to_canonical` instead of their
    # names, which would have produced garbage team names had it ever run.
    return _cached("fixtures_df", lambda: fixtures_mod.get_upcoming_fixtures(force_refresh=force), ttl=_LIVE_CACHE_TTL_SECONDS, force=force)


def _get_remaining_fixtures_df() -> pd.DataFrame:
    """The full current-season fixture list, not-yet-played only. Prefers
    football-data.org (one call, always current — see
    data/football_data_org.py's module docstring for why this replaced the
    FPL-API-based source, which needed two blocking calls and was never
    called cached before this) and falls back to the FPL API if
    FOOTBALL_DATA_KEY isn't configured, so the app still works before
    that's set up."""

    def build():
        try:
            matches = football_data_org.fetch_matches()
        except FootballDataOrgKeyMissing:
            return fixtures_mod.get_all_remaining_fixtures()
        except requests.RequestException as exc:
            # Same DNS/network-blip resilience as _get_fd_org_matches below
            # -- a missing key isn't the only way this fails, and this
            # call site had no fallback to the FPL-based fixture list at
            # all before this, unlike the sibling functions here.
            print(f"[football_data_org] fetch failed, falling back to FPL fixtures: {exc}")
            return fixtures_mod.get_all_remaining_fixtures()
        if matches.empty:
            return matches
        remaining = matches[~matches["finished"]].drop(columns=["status", "finished", "goals_home", "goals_away", "ftr"])
        remaining["has_odds"] = False
        return remaining.reset_index(drop=True)

    return _cached("remaining_fixtures_df", build, ttl=_LIVE_CACHE_TTL_SECONDS)


def _get_fd_org_standings() -> pd.DataFrame:
    """Live current-season standings, already computed by football-data.org
    — see data/football_data_org.py::fetch_standings. Empty DataFrame (not
    an exception) if the key isn't configured, so callers can fall back to
    `models/projected_table.py::compute_standings` the same way they
    already handle "no data yet"."""

    def build():
        try:
            return football_data_org.fetch_standings()
        except FootballDataOrgKeyMissing:
            return pd.DataFrame()
        except requests.RequestException as exc:
            # Real incident: a DNS resolution failure here took down
            # /api/projected-table with an unhandled ConnectionError --
            # same fallback as a missing key, since callers
            # (_get_live_current_standings) already handle an empty
            # frame by falling back to the FPL-derived standings.
            print(f"[football_data_org] standings fetch failed, falling back: {exc}")
            return pd.DataFrame()

    return _cached("fd_org_standings", build, ttl=_LIVE_RESULTS_CACHE_TTL_SECONDS)


def _get_live_current_standings(current_season: str) -> tuple[pd.DataFrame, str]:
    """Prefer the licensed live table; fall back to the same FPL results
    feed that drives the fixture surface when no football-data.org key exists."""
    standings = _get_fd_org_standings()
    if not standings.empty:
        return standings, "football_data_org"
    results = _get_live_current_results_df().copy()
    if results.empty:
        return pd.DataFrame(columns=["team", "played", "points", "goals_for", "goals_against", "goal_diff"]), "official_fpl"
    results["season"] = current_season
    return projected_table.compute_standings(results), "official_fpl"


def _get_fd_org_matches() -> pd.DataFrame:
    """Full current-season fixture list including already-played results —
    unlike `_get_remaining_fixtures_df`, this keeps finished matches too,
    for reconciliation and the auto-retrain freshness check. Empty
    DataFrame if the key isn't configured."""

    def build():
        try:
            return football_data_org.fetch_matches()
        except FootballDataOrgKeyMissing:
            return pd.DataFrame()
        except requests.RequestException as exc:
            # A missing key isn't the only way this fails -- confirmed live:
            # a transient DNS/network blip took down the *entire* Fixtures
            # endpoint with an unhandled 500 (this was the only fetch in
            # current_gameweek_fixtures's call chain without the same
            # graceful-degradation _get_odds_df already has). Degrade to
            # "no football-data.org data this cycle" instead.
            print(f"[football_data_org] fetch failed, serving without it: {exc}")
            return pd.DataFrame()

    return _cached("fd_org_matches", build, ttl=_LIVE_CACHE_TTL_SECONDS)


def _get_position_priors() -> dict:
    def build():
        df = fpl_history.load_player_gw_history()
        return player_form.position_rate_priors(df)

    return _cached("position_priors", build, ttl=24 * 3600)


def _get_understat_fpl_crosswalk() -> dict:
    def build():
        from pl_predictor.data import understat as understat_mod
        current_year = int(understat_mod.CURRENT_SEASON_START_YEAR)
        seasons = [str(current_year), str(current_year - 1)]

        history = understat_shots.load_player_shot_history(seasons=seasons)
        if history.empty:
            shot_players = pd.DataFrame(columns=["player", "player_id"])
        else:
            shot_players = (
                history.drop_duplicates(subset=["player_id"])[["player", "player_id"]]
                .reset_index(drop=True)
            )

        return understat_shots.build_understat_fpl_crosswalk(
            shot_players, _get_bootstrap()
        )

    return _cached("understat_fpl_crosswalk", build, ttl=24 * 3600)

def _get_player_shots_by_element() -> dict[int, pd.DataFrame]:
    """FPL element id -> that player's own {date, shots, shots_on_target}
    rows, for 's live-serving merge."""
    def build():
        from pl_predictor.data import understat as understat_mod
        current_year = int(understat_mod.CURRENT_SEASON_START_YEAR)
        seasons_to_load = [str(current_year), str(current_year - 1)]

        shots = understat_shots.load_player_shot_history(seasons=seasons_to_load)
        if shots.empty:
            return {}

        crosswalk = _get_understat_fpl_crosswalk()
        shots = shots.copy()
        shots["element"] = shots["player_id"].map(crosswalk)
        shots = shots.dropna(subset=["element"])
        shots["element"] = shots["element"].astype(int)

        return {
            element: group[["date", "shots", "shots_on_target"]]
            for element, group in shots.groupby("element")
        }

    return _cached("player_shots_by_element", build, ttl=24 * 3600)

def _get_player_reliability_coeffs() -> dict:
    """Small linear-regression coefficients (goals ~ [rate, threat],
    assists ~ [rate, creativity]) — see `player_goals.fit_reliability_
    coefficients`'s docstring for why these two specifically. Cheap to
    refit (sub-second), so this is refreshed on the same day-scale cadence
    as `_get_position_priors` (both read the same historical FPL archive)
    rather than persisted anywhere — this data source is decoupled from the
    match model's own (currently stalled-on-football-data.co.uk) retrain
    cycle entirely, by design."""
    return _cached("player_reliability_coeffs", player_goals.fit_reliability_coefficients, ttl=24 * 3600)


@_disk_cache("lineup_model")
def _get_lineup_model():
    return _cached("lineup_model", player_goals.fit_lineup_model, ttl=24 * 3600)


@_disk_cache("pos_rates")
def _get_position_rate_models() -> dict:
    return _cached("position_rate_models", player_goals.fit_position_rate_models, ttl=24 * 3600)


def _get_goal_contribution_model() -> dict:
    return _cached("goal_contribution_model", player_goals.fit_goal_contribution_model, ttl=24 * 3600)


@_disk_cache("contrib_model")
def _get_ready_goal_contribution_model() -> dict | None:
    """Return the direct G+A model only after startup warming has finished.

    Training it from historical player data takes around 20 seconds. Player
    requests use the already-valid Poisson-union baseline until this cached
    model is ready, rather than making the first fixture modal wait for it.
    """
    hit = _cache.get("goal_contribution_model")
    if hit and (time.time() - hit[0]) < 24 * 3600:
        return hit[1]
    return None


def _get_bootstrap() -> dict:
    return _cached("bootstrap", fpl_api.fetch_bootstrap, ttl=3600)


def _get_odds_df(force: bool = False) -> pd.DataFrame:
    def build():
        try:
            return fetch_sportsbook_odds(_get_fixtures_df(), force_refresh=force)
        except SportsbookAPIKeyMissing:
            return pd.DataFrame()
        except requests.RequestException as exc:
            # A missing key isn't the only way this fails: a real rate limit
            # (this provider caps at 150 requests/day -- see
            # data/sportsbook_api.py's module docstring) or a transient
            # outage should degrade to "no live odds" the same way, not
            # take down /fixtures, /refresh-odds, and the value-bet table
            # with an unhandled 500.
            print(f"[sportsbook_api] fetch failed, serving without live odds: {exc}")
            return pd.DataFrame()

    return _cached("odds_df", build, ttl=SPORTSBOOK_CACHE_TTL_SECONDS, force=force)


def refresh_sportsbook_odds_in_background() -> None:
    """Proactively rebuilds the odds/value-bet caches on the Sportsbook API's
    own cadence (see SPORTSBOOK_CACHE_TTL_SECONDS), so value bets stay
    current without waiting for some request to happen to land after the
    cache goes stale. Call periodically from a background loop (see
    main.py's `_odds_refresh_loop`) -- mirrors `refresh_lineups_near_kickoff`'s
    role for the player-predictions cache."""
    _get_odds_df(force=True)
    _clear_cache("fixtures_df", "value_bet_table")

logger = logging.getLogger(__name__)


# The short-TTL (`_LIVE_CACHE_TTL_SECONDS`, 5 minutes) live-serving caches --
# shared between `warm_caches` (startup) and `refresh_live_caches_in_
# background` (periodic, see api/main.py's `_live_cache_refresh_loop`). Split
# in two, as functions rather than module-level constants (the referenced
# route handlers are defined later in this file, so building these lists at
# import time would hit a NameError), only so `warm_caches` can slot
# `bootstrap` (1h TTL, no need to redo every 5 minutes) into the same
# relative position it always had, ahead of odds/fixtures/rankings but
# after the dashboard's own critical path.
def _live_cache_warmers_before_bootstrap() -> list:
    return [
        ("matches_df", _get_matches_df),
        ("models", _get_models),
        ("calibration", get_calibration),
        ("fixtures_df", _get_fixtures_df),
        ("remaining_fixtures_df", _get_remaining_fixtures_df),
    ]


def _live_cache_warmers_after_bootstrap() -> list:
    return [
        ("odds_df", _get_odds_df),
        # The actual page the frontend loads first (see FixturesPage.tsx) --
        # not just its inputs above. Confirmed live: every input here was
        # already warmed except the assembly itself (`_value_bet_table`,
        # ~11s cold: it batch-predicts every remaining fixture's scoreline)
        # plus `current_gameweek_fixtures`'s own tracking reconciliation
        # pass -- so opening the Fixtures page shortly after startup still
        # paid that full cost on the first real request and blew past the
        # frontend's 20s timeout ("The API is still preparing data").
        ("current_gameweek_fixtures", current_gameweek_fixtures),
        ("power_rankings", get_power_rankings),
        ("projected_table", get_projected_table),
    ]


def _run_warmers(warmers: list) -> list[str]:
    failures: list[str] = []
    for name, fn in warmers:
        try:
            fn()
        except Exception as exc:  # noqa: BLE001 - warming is best-effort, never fatal
            failures.append(name)
            print(f"[warm_caches] {name} skipped: {exc}")
    return failures


def warm_caches() -> None:
    """Pre-populates every cache that would otherwise be paid for by
    whichever real request happens to be first — called once at server
    startup (see api/main.py's lifespan handler) so opening the very first
    fixture in the UI doesn't eat a multi-second bootstrap cost that every
    later fixture skips. `_get_bootstrap()` (a live FPL API call) is the
    one long-TTL entry that makes "first click slow, everything after
    fast" — everything else here has the shorter 5-minute live TTL and
    would eventually need re-warming anyway (see
    `refresh_live_caches_in_background` for that), but warming it here too
    means a server that's just started is fast immediately rather than on
    whatever request happens to land first."""
    global _warmup_status
    _warmup_status = {
        "state": "warming",
        "started_at": datetime.now(timezone.utc).isoformat(),
        "completed_at": None,
        "failures": [],
    }
    # The first interactive dashboard calls Calibration and the projected
    # table.  Warm their shared dependencies and Calibration first, before
    # lower-priority fixture/odds payloads, so a cold start cannot make the
    # user wait behind work unrelated to the page they opened.
    failures = _run_warmers([
        *_live_cache_warmers_before_bootstrap(),
        ("bootstrap", _get_bootstrap),
        *_live_cache_warmers_after_bootstrap(),
    ])
    _warmup_status = {
        "state": "ready" if not failures else "degraded",
        "started_at": _warmup_status["started_at"],
        "completed_at": datetime.now(timezone.utc).isoformat(),
        "failures": failures,
    }


def refresh_live_caches_in_background() -> None:
    """Re-warms the same short-TTL caches `warm_caches` does at startup, on
    a repeating timer (see api/main.py's `_live_cache_refresh_loop`) --
    without this, `warm_caches` only ever prevents the *first* request
    after startup from paying the cold-build cost; every 5 minutes after
    that (`_LIVE_CACHE_TTL_SECONDS`), the cache goes stale again and
    whichever real request happens to land first pays the same ~50-65s
    cost warm_caches was built to avoid (confirmed live: this is why "The
    API is still preparing data" kept recurring well after startup, not
    just on the very first request)."""
    _run_warmers([*_live_cache_warmers_before_bootstrap(), *_live_cache_warmers_after_bootstrap()])


def maybe_auto_retrain() -> None:
    """Retrains only if the current season has produced more played matches
    than the last training run saw — this is what makes "a team's result
    changes its power ranking" happen without a manual click. Compares
    against `n_current_season_matches` in the existing manifest.json rather
    than tracking state separately. Called on a repeating timer from api/
    main.py's lifespan handler (see `_AUTO_RETRAIN_INTERVAL_SECONDS`), so a
    new result shows up within one interval, not instantly — full retrains
    (fitting Dixon-Coles/Bivariate-Poisson/XGBoost from scratch) take real
    time (~10-30s), so this deliberately doesn't run on every request.

    `football_data.fetch_current_season_partial()` (called below) now falls
    back to `data/pulselive.py` when football-data.co.uk has no rows yet for
    the in-progress season — confirmed this can otherwise stall for a long
    time (zero rows even after a full gameweek). This function needed no
    changes for that: it only ever looks at the row *count*, agnostic to
    which source produced it."""
    if not manifest_lib.MANIFEST_PATH.exists():
        return
    try:
        current = football_data.fetch_current_season_partial()
        n_current = 0 if current is None or current.empty else len(current)
        manifest = manifest_lib.load_manifest()
        if n_current <= manifest.get("n_current_season_matches", 0):
            return  # nothing new since the last training run
        print(f"[auto_retrain] {n_current} current-season matches now available (was {manifest.get('n_current_season_matches', 0)}) — retraining...")
        manifest_lib.train_all()
        _clear_cache("models", "value_bet_table")
        print("[auto_retrain] done")
    except Exception as exc:  # noqa: BLE001 - never take the server down over this
        print(f"[auto_retrain] skipped: {exc}")


def _none_if_nan(value):
    return None if value is None or (isinstance(value, float) and pd.isna(value)) else value


def _row_to_summary(row: pd.Series) -> FixtureSummary:
    def edge(side: str) -> MarketEdge:
        return MarketEdge(
            prob=row[f"{side}_prob"],
            implied=_none_if_nan(row.get(f"{side}_implied")),
            edge=_none_if_nan(row.get(f"{side}_edge")),
        )

    recommended_market = _none_if_nan(row.get("recommended_market"))
    recommendation = (
        SingleBetRecommendation(
            market=str(recommended_market),
            probability=float(row["recommended_prob"]),
            implied_probability=float(row["recommended_implied"]),
            edge=float(row["recommended_edge"]),
            price=float(row["recommended_price"]),
            bookmaker=str(row["recommended_bookmaker"]),
        )
        if recommended_market is not None
        else None
    )

    return FixtureSummary(
        event_id=str(row["event_id"]),
        commence_time=row["commence_time"],
        team_home=row["team_home"],
        team_away=row["team_away"],
        home_win=edge("home_win"),
        draw=edge("draw"),
        away_win=edge("away_win"),
        over_2_5=edge("over_2_5"),
        under_2_5=edge("under_2_5"),
        btts_yes_prob=row["btts_yes_prob"],
        top_scoreline=row["top_scoreline"],
        is_fallback_prediction=bool(row["is_fallback_prediction"]),
        data_confidence=row.get("data_confidence"),
        predicted_total_goals=row["home_goal_expectation"] + row["away_goal_expectation"],
        predicted_margin=row["home_goal_expectation"] - row["away_goal_expectation"],
        home_2plus_prob=row["home_2plus_prob"],
        away_2plus_prob=row["away_2plus_prob"],
        value_bet_flags=row["value_bet_flags"],
        has_live_odds=row.get("home_win_implied") is not None and not pd.isna(row.get("home_win_implied")),
        odds_fetched_at=_none_if_nan(row.get("odds_fetched_at")),
        odds_is_stale=bool(row.get("odds_is_stale", False)),
        recommended_bet=recommendation,
    )


def _value_bet_table() -> pd.DataFrame:
    """Cached: this rebuilds every remaining fixture's scoreline prediction
    (a `predict_fixtures_batch` + full feature-row build per fixture), and
    is called from several call chains per single fixture lookup (e.g.
    `_resolve_fixture_kickoff`, hit twice per `/fixtures/{id}/players`
    request) — confirmed via profiling this was the dominant cost of
    `public_snapshot.py`'s per-fixture loop, recomputing the whole table
    from scratch on every call rather than reusing it across a run whose
    fixtures/odds/models don't change mid-flight."""

    def build() -> pd.DataFrame:
        fixtures_df = _get_fixtures_df()
        if fixtures_df.empty:
            return fixtures_df
        models = _get_models()
        odds_df = _get_odds_df()
        return value_bets.build_value_bet_table(fixtures_df, odds_df, models)

    return _cached("value_bet_table", build, ttl=_LIVE_CACHE_TTL_SECONDS)


def _capture_fixture_market_predictions(table: pd.DataFrame) -> None:
    """Save corners/cards predictions before kickoff, outside UI requests."""
    if table.empty:
        return
    models = _get_models()
    matches_df = _get_matches_df()
    feature_rows = build_features_for_fixtures(
        table[["team_home", "team_away", "commence_time"]].copy(), matches_df=matches_df, context=models.get("context")
    )
    for (_, fixture), (_, feature_row) in zip(table.iterrows(), feature_rows.iterrows()):
        predictions = value_bets.predict_market_models_for_fixture(models, feature_row)
        # Only the O/U-shaped markets -- see fixture_detail's identical note.
        tracking_store.record_fixture_market_predictions(
            fixture["event_id"], fixture["team_home"], fixture["team_away"], fixture["commence_time"],
            {"corners": predictions["corners"], "cards": predictions["cards"]},
        )


def _run_tracking_bookkeeping(table: pd.DataFrame) -> None:
    """Snapshot/reconcile/backfill the prediction track record. Originally
    piggybacked only on `/api/fixtures` being polled during normal use;
    also called from `/api/fixtures/gameweek` now that the Fixtures page's
    default view no longer fetches the flat `/api/fixtures` list at all —
    without a second call site, tracking would silently stop updating.
    Never let a tracking hiccup break the caller's main response."""
    try:
        # football-data.org first, deliberately: it's the only source with
        # a `matchday` column (see reconcile_predictions's docstring), and
        # reconcile_predictions only ever touches still-unresolved rows — if
        # football-data.co.uk's fallback below resolved a fixture first
        # (which it eventually can too, once its own scrape catches up a few
        # days later), this call would find nothing left to do for it and
        # that fixture's gameweek would be permanently NULL. Reconciling
        # football-data.org first avoids that race regardless of which
        # source is faster on any given day.
        # football-data.org's fetch is cached (_LIVE_CACHE_TTL_SECONDS), so
        # reusing it below for the backfill check costs nothing extra.
        fd_org_matches = _get_fd_org_matches()
        fd_org_finished = (
            fd_org_matches[fd_org_matches["finished"]].rename(columns={"commence_time": "date"})
            if not fd_org_matches.empty
            else fd_org_matches
        )
        if not fd_org_finished.empty:
            tracking_store.reconcile_predictions(fd_org_finished)
            value_bet_ledger.reconcile_value_bets(fd_org_finished, result_source="football-data.org")
            # Repairs rows stuck with gameweek=NULL from a past run where
            # football-data.org wasn't available yet (see
            # backfill_missing_gameweeks's docstring) -- self-heals once
            # this source is available again, rather than staying NULL
            # forever.
            tracking_store.backfill_missing_gameweeks(fd_org_finished)
        # Fallback/mop-up: anything football-data.org didn't have yet (e.g.
        # its own scrape running behind) still gets resolved here, just
        # without a gameweek number.
        tracking_store.reconcile_predictions(_get_matches_df())
        value_bet_ledger.reconcile_value_bets(_get_matches_df(), result_source="football-data.co.uk")
        trained_at = manifest_lib.load_manifest().get("trained_at") if manifest_lib.MANIFEST_PATH.exists() else None
        tracking_store.record_predictions(table, model_trained_at=trained_at)
        tracking_store.record_fixture_forecast_snapshots(table, "early")
        tracking_store.capture_due_odds_snapshots(table)
        _capture_fixture_market_predictions(table)
        tracking_store.reconcile_fixture_market_predictions(_get_matches_df())
        value_bet_ledger.record_value_bets(
            table,
            model_trained_at=trained_at,
            model_manifest_hash=manifest_lib.manifest_fingerprint(),
        )
        value_bet_ledger.update_closing_lines(table)

        # Catch up on any match that finished before this app was ever
        # polling for tracking to snapshot it live (e.g. the handful of
        # matches already played when tracking first started this season,
        # or any result that lands while the app is down). Prefers
        # football-data.org — it tends to reflect a finished match faster
        # than football-data.co.uk's own scrape, which is exactly why
        # backfill_missing_predictions uses the model's live-serving
        # predict path rather than a historical training-frame row (see
        # its docstring). Falls back to football-data.co.uk's own
        # current-season results once that's all that's available.
        if not fd_org_finished.empty:
            finished_matches = fd_org_finished
        else:
            current_season = _current_season_label()
            matches_df = _get_matches_df()
            finished_matches = matches_df[(matches_df["season"] == current_season) & matches_df["goals_home"].notna()]
        if tracking_store.has_unlogged_finished_matches(finished_matches):
            models = _get_models()
            tracking_store.backfill_missing_predictions(
                finished_matches,
                models["scoreline"],
                model_trained_at=trained_at,
                market_overrides=models.get("scoreline_market_overrides"),
            )
    except Exception as exc:  # noqa: BLE001
        print(f"[tracking] skipped: {exc}")


@router.get("/fixtures", response_model=list[FixtureSummary])
def list_fixtures():
    if PUBLIC_MODE:
        # No snapshot equivalent for this flat list exists (public_snapshot.py
        # only precomputes fixtures_by_gameweek -- see its own scoping
        # comment) and nothing in the frontend calls this endpoint anymore
        # (superseded by /fixtures/gameweek, see _run_tracking_bookkeeping's
        # docstring). Degrade to empty rather than run the full live
        # value-bet pipeline Render's free tier OOMs on.
        return []
    table = _value_bet_table()
    _run_tracking_bookkeeping(table)
    return [_row_to_summary(row) for _, row in table.iterrows()]


def _resolve_current_gameweek(current_gameweek: int | None, fd_org_matches: pd.DataFrame, now: pd.Timestamp | None = None) -> int | None:
    """`current_gameweek` (from `tracking_store.get_track_record()`, or the
    lowest-unfinished-matchday fallback) still points at a gameweek once
    every one of its matches is resolved, until the *next* gameweek produces
    its own first resolved match — which can be days later (e.g. a Sunday
    finish, Friday restart). Advances to the next gameweek on the calendar
    day before it kicks off, not the moment kickoff is within a rolling 24
    hours — a rolling window can sit as much as several hours into "the day
    before" still refusing to advance (confirmed live: a 14:00 UTC kickoff
    tomorrow left this on the fully-finished gameweek all morning, since
    "tomorrow 14:00" is >24h from "today 09:00"), which reads as stuck to
    anyone checking earlier in the day than the previous kickoff's own time
    of day. `now` is injectable for tests; real callers always use the
    default (actual current time)."""
    if current_gameweek is None or fd_org_matches.empty:
        return current_gameweek

    this_gw_matches = fd_org_matches[fd_org_matches["matchday"] == current_gameweek]
    this_gw_fully_finished = not this_gw_matches.empty and bool(this_gw_matches["finished"].all())
    if not this_gw_fully_finished:
        return current_gameweek

    next_gw_matches = fd_org_matches[fd_org_matches["matchday"] == current_gameweek + 1]
    if next_gw_matches.empty:
        return current_gameweek

    now = now if now is not None else pd.Timestamp.now(tz="UTC")
    next_kickoff = pd.to_datetime(next_gw_matches["commence_time"], utc=True).min()
    if next_kickoff.normalize() <= now.normalize() + pd.Timedelta(days=1):
        return current_gameweek + 1
    return current_gameweek


@router.get("/fixtures/gameweek")
def current_gameweek_fixtures(gameweek: int | None = None):
    """Every match in one gameweek, finished and upcoming together — the
    whole gameweek at a glance, not just "what's next." Defaults to the
    current gameweek when `gameweek` is omitted; pass an explicit number to
    browse another one (prev/next navigation in the frontend). "Current
    gameweek" uses the same definition `tracking_store.get_track_record()`
    already establishes for the Track Record tab (the highest gameweek
    number among resolved matches) for consistency between the two views;
    falls back to the lowest not-yet-finished matchday from football-data.org
    when nothing's resolved yet at all (e.g. brand new season, gameweek 1
    hasn't kicked off) — then `_resolve_current_gameweek` advances that a
    day early once it's fully finished, rather than waiting on the next
    gameweek's own first result. Finished fixtures reuse `tracking_store`'s
    already-recorded pre-match predictions (honest — never recomputed live,
    which for an already-finished match could leak that match's own result
    into what's "predicted"); upcoming fixtures get a fresh live prediction
    the same way `/fixtures` does, joined against the odds-windowed
    value-bet table by team pair when a live market covers that fixture (so
    the same market-edge/value-bet-flag data `/fixtures` shows is available
    here too, not just a bare model prediction) — falls back to a
    model-only prediction for fixtures further out than the odds window.
    `event_id` is included on every fixture (the Odds API's id when a
    live-odds match was found, football-data.org's id otherwise for
    upcoming ones, and the id `fixture_detail` already knows how to resolve
    for finished ones) so each card can open the same fixture-detail view
    `/fixtures` does."""
    if PUBLIC_MODE:
        snapshot = _public_snapshot()
        gw = gameweek if gameweek is not None else snapshot.get("current_gameweek")
        return snapshot.get("fixtures_by_gameweek", {}).get(
            str(gw), {"gameweek": gw, "fixtures": [], "is_current": False, "min_gameweek": None, "max_gameweek": None}
        )

    value_bet_table = _value_bet_table()
    _run_tracking_bookkeeping(value_bet_table)

    fd_org_matches = _get_fd_org_matches()

    track_summary = tracking_store.get_track_record()
    current_gameweek = track_summary["current_gameweek"]

    # football-data.org is optional. When its key/feed is unavailable, FPL's
    # cached full fixture list is enough to retain the future gameweek view.
    # Without this branch, the app could still compute a value-bet table yet
    # show an empty Fixtures tab after a completed round.
    fallback_remaining = pd.DataFrame()
    if fd_org_matches.empty:
        try:
            # The gameweek view must retain live matches.  Unlike projected
            # table calculations, it is not a future-only schedule: FPL's
            # per-fixture ``finished`` flag is the authoritative boundary
            # while a current gameweek is in progress.
            fallback_remaining = fixtures_mod._fixtures_from_fpl_api()
        except Exception:  # noqa: BLE001 - retain completed tracking rows
            fallback_remaining = pd.DataFrame()

    if current_gameweek is None and not fd_org_matches.empty:
        unfinished = fd_org_matches[~fd_org_matches["finished"]]
        current_gameweek = int(unfinished["matchday"].min()) if not unfinished.empty else None

    current_gameweek = _resolve_current_gameweek(current_gameweek, fd_org_matches)
    if current_gameweek is None and not fallback_remaining.empty and fallback_remaining["gameweek"].notna().any():
        # With no tracked result yet (for example, before GW1), the next
        # scheduled round is necessarily the current view. Once tracking has
        # established a current gameweek, do not jump the user into a future
        # round merely because the fallback only contains unplayed fixtures.
        current_gameweek = int(pd.to_numeric(fallback_remaining["gameweek"], errors="coerce").dropna().min())

    target_gameweek = gameweek if gameweek is not None else current_gameweek
    if target_gameweek is None:
        return {"gameweek": None, "fixtures": [], "is_current": True, "min_gameweek": None, "max_gameweek": None}

    # Keep previously completed rounds reachable even when the live fixture
    # provider only has the remaining schedule (the FPL fallback starts at
    # the next unplayed gameweek).  Those rows have the original pre-match
    # snapshot and post-match detail in the tracking store.
    groups = tracking_store.get_results_by_gameweek()
    tracked_gameweeks = [
        int(group["gameweek"])
        for group in groups
        if group.get("gameweek") is not None
    ]

    has_matchday = not fd_org_matches.empty and fd_org_matches["matchday"].notna().any()
    if has_matchday:
        min_gameweek = int(fd_org_matches["matchday"].min())
        max_gameweek = int(fd_org_matches["matchday"].max())
    elif not fallback_remaining.empty and fallback_remaining["gameweek"].notna().any():
        remaining_gw = pd.to_numeric(fallback_remaining["gameweek"], errors="coerce").dropna()
        min_gameweek, max_gameweek = int(remaining_gw.min()), int(remaining_gw.max())
        if tracked_gameweeks:
            min_gameweek = min(min_gameweek, min(tracked_gameweeks))
            max_gameweek = max(max_gameweek, max(tracked_gameweeks))
    else:
        min_gameweek, max_gameweek = (
            (min(tracked_gameweeks), max(tracked_gameweeks))
            if tracked_gameweeks
            else (1, 38)
        )

    fixtures = []
    completed_team_pairs: set[tuple[str, str]] = set()

    completed_group = next((g for g in groups if g["gameweek"] == target_gameweek), None)
    if completed_group:
        completed_team_pairs = {(r["team_home"], r["team_away"]) for r in completed_group["fixtures"]}
        pending_event_ids = {
            str(row["event_id"])
            for row in completed_group["fixtures"]
            if not tracking_store.has_fixture_player_outcomes(str(row["event_id"]))
        }
        if pending_event_ids:
            _refresh_player_outcomes_in_background(target_gameweek)
        try:
            bootstrap = _get_bootstrap()
        except Exception:  # noqa: BLE001 - scores still render during an FPL outage
            bootstrap = {"elements": []}
        for r in completed_group["fixtures"]:
            player_events_pending = str(r["event_id"]) in pending_event_ids
            player_events = tracking_store.get_fixture_player_events(str(r["event_id"]), bootstrap)
            fixtures.append(
                {
                    "event_id": str(r["event_id"]),
                    "team_home": r["team_home"],
                    "team_away": r["team_away"],
                    "commence_time": r["commence_time"],
                    "finished": True,
                    "actual_goals_home": r["actual_goals_home"],
                    "actual_goals_away": r["actual_goals_away"],
                    "predicted_home_win": r["predicted_home_win"],
                    "predicted_draw": r["predicted_draw"],
                    "predicted_away_win": r["predicted_away_win"],
                    "predicted_scoreline": r["predicted_scoreline"],
                    "draw_signal": predicted_result(
                        r["predicted_scoreline"], r["predicted_home_win"], r["predicted_draw"], r["predicted_away_win"]
                    ) == "draw",
                    "hit": r["hit"],
                    "backfilled": r["backfilled"],
                    # Derived per read from this pick's own timestamps, never
                    # from `backfilled`. The gameweek tally reads it, so it has
                    # to travel with the card. `.get` so a group row lacking it
                    # -- an older cached snapshot, a stub -- reads False, which
                    # is the fail-closed direction: the pick is listed and not
                    # claimed as pre-kickoff.
                    "made_before_kickoff": bool(r.get("made_before_kickoff")),
                    "has_live_odds": False,
                    "value_bet_flags": [],
                    "home_player_events": player_events["home"],
                    "away_player_events": player_events["away"],
                    "player_events_pending": player_events_pending,
                }
            )

    if not fd_org_matches.empty:
        upcoming_rows = fd_org_matches[(fd_org_matches["matchday"] == target_gameweek) & (~fd_org_matches["finished"])]
    elif not fallback_remaining.empty:
        upcoming_rows = fallback_remaining[
            pd.to_numeric(fallback_remaining["gameweek"], errors="coerce") == target_gameweek
        ]
    else:
        upcoming_rows = pd.DataFrame()

    if not upcoming_rows.empty and completed_team_pairs:
        # Our own tracking store can resolve a match as finished slightly
        # before an optional fixture feed catches up. Apply this to either
        # source so a completed fixture never renders twice.
        upcoming_rows = upcoming_rows[
            ~upcoming_rows.apply(lambda row: (row["team_home"], row["team_away"]) in completed_team_pairs, axis=1)
        ]

    if not upcoming_rows.empty:
            models = _get_models()
            # When this batch is computed — the only moment that can place a
            # freshly-built prediction relative to its own kickoff.
            captured_at = pd.Timestamp.now(tz="UTC")
            preds = scoreline.predict_fixtures_batch(
                models["scoreline"], upcoming_rows, market_overrides=models.get("scoreline_market_overrides")
            )
            # The Odds API only covers a rolling ~1-2 gameweek window, so
            # not every upcoming fixture here will have a live-odds match —
            # prefer it (real event_id, model prob, value-bet flags) when
            # one exists for this exact team pair, same model-only
            # prediction otherwise (has_live_odds=False, same as
            # `_team_fixture_to_summary`'s fallback for team-lookup
            # fixtures further out than the odds window).
            for (_, row), pred in zip(upcoming_rows.iterrows(), preds):
                vb_match = (
                    value_bet_table[
                        (value_bet_table["team_home"] == row["team_home"])
                        & (value_bet_table["team_away"] == row["team_away"])
                    ]
                    if not value_bet_table.empty
                    else value_bet_table
                )
                if not vb_match.empty:
                    vb_row = vb_match.iloc[0]
                    fixtures.append(
                        {
                            "event_id": str(vb_row["event_id"]),
                            "team_home": row["team_home"],
                            "team_away": row["team_away"],
                            "commence_time": row["commence_time"].isoformat(),
                            "finished": False,
                            "actual_goals_home": None,
                            "actual_goals_away": None,
                            "predicted_home_win": float(vb_row["home_win_prob"]),
                            "predicted_draw": float(vb_row["draw_prob"]),
                            "predicted_away_win": float(vb_row["away_win_prob"]),
                            "predicted_scoreline": vb_row["top_scoreline"],
                            "draw_signal": predicted_result(
                                vb_row["top_scoreline"], float(vb_row["home_win_prob"]), float(vb_row["draw_prob"]), float(vb_row["away_win_prob"])
                            ) == "draw",
                            "hit": None,
                            "backfilled": False,
                            # Derived, never stated. This pick came out of the
                            # cached value-bet table, whose own `odds_fetched_at`
                            # is when its inputs were captured; comparing that to
                            # the kickoff is the only timestamp here that can
                            # actually place the prediction in time. Notably NOT
                            # "is the fixture live now": a cached row captured
                            # before kickoff stays a pre-kickoff prediction
                            # after the match starts, which is the whole point of
                            # caching it (CodeRabbit, #44).
                            "made_before_kickoff": tracking_store._made_before_kickoff(
                                vb_row.get("odds_fetched_at"), row["commence_time"]
                            ),
                            "has_live_odds": bool(vb_row["home_win_implied"] is not None and not pd.isna(vb_row["home_win_implied"])),
                            "value_bet_flags": list(vb_row["value_bet_flags"]),
                        }
                    )
                    continue

                top = pred["top_scorelines"][0]
                fixtures.append(
                    {
                        "event_id": str(row["event_id"]),
                        "team_home": row["team_home"],
                        "team_away": row["team_away"],
                        "commence_time": row["commence_time"].isoformat(),
                        "finished": False,
                        "actual_goals_home": None,
                        "actual_goals_away": None,
                        "predicted_home_win": pred["home_win"],
                        "predicted_draw": pred["draw"],
                        "predicted_away_win": pred["away_win"],
                        "predicted_scoreline": f"{top['home']}-{top['away']}",
                        "draw_signal": predicted_result(
                            f"{top['home']}-{top['away']}", pred["home_win"], pred["draw"], pred["away_win"]
                        ) == "draw",
                        "hit": None,
                        "backfilled": False,
                        # Derived from the clock, because this pick was computed
                        # on this very request (`predict_fixtures_batch` above).
                        # `upcoming_rows` filters on the feed's `finished` flag,
                        # which can lag a kickoff that has already happened, so
                        # "not finished" is not "not started". Comparing the
                        # moment of computation to the kickoff is what actually
                        # places it, and it fails closed: after kickoff this is
                        # False and `/facts` will not judge the pick (CodeRabbit,
                        # #44).
                        "made_before_kickoff": tracking_store._made_before_kickoff(
                            captured_at, row["commence_time"]
                        ),
                        "has_live_odds": False,
                        "value_bet_flags": [],
                    }
                )

    fixtures.sort(key=lambda f: f["commence_time"])
    return {
        "gameweek": target_gameweek,
        "fixtures": fixtures,
        "is_current": target_gameweek == current_gameweek,
        "min_gameweek": min_gameweek,
        "max_gameweek": max_gameweek,
    }


def _build_fixture_detail(summary: FixtureSummary, home: str, away: str, read_only: bool = False) -> FixtureDetail:
    """`read_only=True` (used by public_snapshot.py) skips the two tracking-
    store writes below — `reconcile_fixture_market_predictions` in
    particular re-scans the *entire* matches_df against every unresolved
    prediction on every call. Confirmed live: ~250ms per call, unconditionally,
    on every single fixture-detail request regardless of whether anything
    actually changed (measured with 476 unresolved rows, zero updates on two
    back-to-back calls) — this was the dominant cost of opening a fixture,
    repeated on every click rather than amortized. Throttled via the same
    `_cached` TTL wrapper every other expensive live lookup in this file
    already uses, so it actually reconciles at most once per TTL window
    instead of once per click. Neither write is needed for a static export:
    they exist to build up this project's own live prediction-tracking
    history, which the public deployment doesn't have (or need) a copy of."""
    models = _get_models()
    matches_df = _get_matches_df()

    pred = scoreline.predict_fixture(
        models["scoreline"], home, away, max_goals=6, market_overrides=models.get("scoreline_market_overrides")
    )
    feature_row = build_features_for_fixtures(
        pd.DataFrame([{"team_home": home, "team_away": away, "commence_time": summary.commence_time}]),
        matches_df=matches_df,
        context=models.get("context"),
    ).iloc[0]
    market_preds = value_bets.predict_market_models_for_fixture(models, feature_row)
    if not read_only:
        fixture_time = pd.Timestamp(summary.commence_time)
        if fixture_time.tzinfo is not None:
            fixture_time = fixture_time.tz_localize(None)
        provenance = "snapshot" if fixture_time > pd.Timestamp.now(tz="UTC").tz_localize(None) else "reconstructed"
        # Only the O/U-shaped markets -- record_fixture_market_predictions'
        # table has NOT NULL line/over/under columns, which home_shots/
        # away_shots (plain expected values, no O/U line) don't have.
        tracking_store.record_fixture_market_predictions(
            summary.event_id, home, away, summary.commence_time,
            {"corners": market_preds["corners"], "cards": market_preds["cards"]}, provenance=provenance,
        )
        _cached(
            "reconcile_fixture_market_predictions",
            lambda: tracking_store.reconcile_fixture_market_predictions(matches_df),
            ttl=_LIVE_CACHE_TTL_SECONDS,
        )
    post_match = tracking_store.get_fixture_post_match(summary.event_id)
    actual_stats = _fixture_actual_stats(matches_df, home, away, summary.commence_time)
    # The live odds table stops carrying a fixture after kickoff.  The
    # ledger is therefore the only honest source for a completed fixture's
    # value-bet call: it preserves the first displayed price and edge rather
    # than silently recalculating (or forgetting) it afterwards.
    pre_match_value_bets = value_bet_ledger.get_fixture_value_bets(summary.event_id)

    return FixtureDetail(
        **summary.model_dump(),
        score_grid=[list(r) for r in pred["grid"][:6, :6]],
        top_scorelines=pred["top_scorelines"],
        corners=OverUnderPrediction(
            lambda_=market_preds["corners"]["lambda"],
            line=market_preds["corners"]["line"],
            over=market_preds["corners"]["over"],
            under=market_preds["corners"]["under"],
        ),
        home_shots=market_preds["home_shots"],
        away_shots=market_preds["away_shots"],
        home_shots_on_target=market_preds["home_shots_on_target"],
        away_shots_on_target=market_preds["away_shots_on_target"],
        cards=OverUnderPrediction(
            lambda_=market_preds["cards"]["lambda"],
            line=market_preds["cards"]["line"],
            over=market_preds["cards"]["over"],
            under=market_preds["cards"]["under"],
        ),
        head_to_head=[H2HMeeting(**m) for m in head_to_head.recent_meetings(matches_df, home, away)],
        home_recent_form=rolling_form.recent_form(matches_df[matches_df["season"] == _current_season_label()], home),
        away_recent_form=rolling_form.recent_form(matches_df[matches_df["season"] == _current_season_label()], away),
        home_context=FixtureTeamContext(
            rest_days=_none_if_nan(feature_row.get("rest_days_home")),
            xg_for_last_5=_none_if_nan(feature_row.get("home_xg_for_last_5")),
            xg_against_last_5=_none_if_nan(feature_row.get("home_xg_against_last_5")),
            corners_last_5=_none_if_nan(feature_row.get("home_last_5_corners_for")),
            cards_last_5=_none_if_nan(feature_row.get("home_last_5_cards_for")),
            set_piece_xg_share_last_5=_none_if_nan(feature_row.get("home_set_piece_xg_share_last_5")),
        ),
        away_context=FixtureTeamContext(
            rest_days=_none_if_nan(feature_row.get("rest_days_away")),
            xg_for_last_5=_none_if_nan(feature_row.get("away_xg_for_last_5")),
            xg_against_last_5=_none_if_nan(feature_row.get("away_xg_against_last_5")),
            corners_last_5=_none_if_nan(feature_row.get("away_last_5_corners_for")),
            cards_last_5=_none_if_nan(feature_row.get("away_last_5_cards_for")),
            set_piece_xg_share_last_5=_none_if_nan(feature_row.get("away_set_piece_xg_share_last_5")),
        ),
        post_match=post_match,
        actual_stats=actual_stats,
        pre_match_value_bets=pre_match_value_bets,
    )


def _fixture_actual_stats(matches_df: pd.DataFrame, home: str, away: str, kickoff) -> FixtureActualStats | None:
    """Confirmed team totals for a finished fixture; no live-context leakage."""
    if matches_df.empty:
        return None
    fixture_time = pd.Timestamp(kickoff)
    if fixture_time.tzinfo is not None:
        fixture_time = fixture_time.tz_localize(None)
    candidates = matches_df[(matches_df["team_home"] == home) & (matches_df["team_away"] == away)].copy()
    if candidates.empty:
        return None
    candidates["date"] = pd.to_datetime(candidates["date"]).map(lambda value: value.tz_localize(None) if value.tzinfo is not None else value)
    candidates = candidates[(candidates["date"] - fixture_time).abs() <= pd.Timedelta(days=3)]
    if candidates.empty:
        return None
    match = candidates.sort_values("date").iloc[-1]
    if pd.isna(match.get("goals_home")) or pd.isna(match.get("goals_away")):
        return None

    def number(value):
        return None if value is None or pd.isna(value) else float(value)

    pairs = [
        ("Goals", "goals_home", "goals_away"), ("Shots", "hs", "as"),
        ("On target", "hst", "ast"), ("Possession %", "hp", "ap"),
        ("Corners", "hc", "ac"), ("Fouls", "hf", "af"),
        ("Yellow cards", "hy", "ay"), ("Red cards", "hr", "ar"),
    ]
    home_stats, away_stats = {}, {}
    for label, home_column, away_column in pairs:
        home_value, away_value = number(match.get(home_column)), number(match.get(away_column))
        if home_value is not None or away_value is not None:
            home_stats[label], away_stats[label] = home_value, away_value
    return FixtureActualStats(home=home_stats, away=away_stats)


@router.get("/fixtures/{event_id}", response_model=FixtureDetail)
def fixture_detail(event_id: str, read_only: bool = False):
    """`read_only=True` is for public_snapshot.py's own bulk export use
    only (skips tracking-store writes — see `_build_fixture_detail`'s
    docstring); the frontend never sets it."""
    if PUBLIC_MODE:
        cached = _public_snapshot().get("fixture_detail_by_event_id", {}).get(event_id)
        if cached is None:
            raise HTTPException(status_code=404, detail=f"No fixture with event_id={event_id}")
        return cached

    table = _value_bet_table()
    matches = table[table["event_id"].astype(str) == event_id] if not table.empty else table
    if not matches.empty:
        row = matches.iloc[0]
        return _build_fixture_detail(_row_to_summary(row), row["team_home"], row["team_away"], read_only=read_only)

    # Not in the odds-windowed value-bet table — might be a further-out
    # fixture reached via team lookup (GET /api/teams/{team}/fixtures uses
    # FPL fixture ids, a different id space than the Odds API's event_id).
    all_remaining = _get_remaining_fixtures_df()
    remaining_match = (
        all_remaining[all_remaining["event_id"].astype(str) == event_id] if not all_remaining.empty else all_remaining
    )
    if not remaining_match.empty:
        fixture = remaining_match.iloc[0]
        home, away = fixture["team_home"], fixture["team_away"]
        models = _get_models()
        pred = scoreline.predict_fixture(
            models["scoreline"], home, away, market_overrides=models.get("scoreline_market_overrides")
        )
        return _build_fixture_detail(_team_fixture_to_summary(fixture, pred), home, away, read_only=read_only)

    # A live FPL fixture has started, so it is deliberately absent from the
    # future-only schedule above, but still needs a detail view.
    current_fpl_match = _current_fpl_fixture(event_id)
    if current_fpl_match is not None:
        home, away = current_fpl_match["team_home"], current_fpl_match["team_away"]
        models = _get_models()
        pred = scoreline.predict_fixture(
            models["scoreline"], home, away, market_overrides=models.get("scoreline_market_overrides")
        )
        return _build_fixture_detail(
            _team_fixture_to_summary(current_fpl_match, pred), home, away, read_only=read_only
        )

    # Neither odds-windowed nor still-upcoming — likely a finished fixture
    # reached via the gameweek view. Pull its honestly pre-match-recorded
    # prediction from tracking_store instead of recomputing live (which for
    # an already-played match risks that match's own result leaking into
    # "current model state"); the score grid/h2h/corners/cards/recent-form
    # sections below still come from a live recompute either way, same as
    # every other path through this function — those are descriptive
    # current-model context, not "the prediction" itself.
    recorded = tracking_store.get_fixture_prediction(event_id)
    if recorded is not None:
        return _build_fixture_detail(
            _recorded_fixture_to_summary(recorded), recorded["team_home"], recorded["team_away"], read_only=read_only
        )

    raise HTTPException(status_code=404, detail=f"No fixture with event_id={event_id}")


def _resolve_fixture_teams(event_id: str) -> tuple[str, str] | None:
    """Same three-tier lookup as `fixture_detail` (odds-windowed table,
    then still-upcoming fixtures, then a finished fixture's recorded
    prediction), reduced to just the team names — shared so player
    predictions work for any fixture reachable via the gameweek view, not
    only the odds-windowed ones."""
    table = _value_bet_table()
    matches = table[table["event_id"].astype(str) == event_id] if not table.empty else table
    if not matches.empty:
        row = matches.iloc[0]
        return row["team_home"], row["team_away"]

    all_remaining = _get_remaining_fixtures_df()
    remaining_match = (
        all_remaining[all_remaining["event_id"].astype(str) == event_id] if not all_remaining.empty else all_remaining
    )
    if not remaining_match.empty:
        fixture = remaining_match.iloc[0]
        return fixture["team_home"], fixture["team_away"]

    current_fpl_match = _current_fpl_fixture(event_id)
    if current_fpl_match is not None:
        return current_fpl_match["team_home"], current_fpl_match["team_away"]

    recorded = tracking_store.get_fixture_prediction(event_id)
    if recorded is not None:
        return recorded["team_home"], recorded["team_away"]

    return None


def _current_fpl_fixture(event_id: str) -> pd.Series | None:
    """Return an uncompleted FPL fixture, including one already in progress."""
    try:
        fixtures = fixtures_mod._fixtures_from_fpl_api()
    except Exception:  # noqa: BLE001 - retain the existing lookup fallbacks
        return None
    matches = fixtures[fixtures["event_id"].astype(str) == event_id] if not fixtures.empty else fixtures
    return matches.iloc[0] if not matches.empty else None


def _resolve_fixture_kickoff(event_id: str):
    table = _value_bet_table()
    matches = table[table["event_id"].astype(str) == event_id] if not table.empty else table
    if not matches.empty:
        return pd.to_datetime(matches.iloc[0]["commence_time"])
    all_remaining = _get_remaining_fixtures_df()
    matches = all_remaining[all_remaining["event_id"].astype(str) == event_id] if not all_remaining.empty else all_remaining
    if not matches.empty:
        return pd.to_datetime(matches.iloc[0]["commence_time"])
    current_fpl_match = _current_fpl_fixture(event_id)
    if current_fpl_match is not None:
        return pd.to_datetime(current_fpl_match["commence_time"])
    recorded = tracking_store.get_fixture_prediction(event_id)
    return pd.to_datetime(recorded["commence_time"]) if recorded is not None else None


def _opponent_defence_for_fixture(home: str, away: str, kickoff) -> dict[str, dict[str, float]]:
    """Rate each club's defence as it stands *before* this fixture kicks off.

    Returns `{team: {feature: value}}` — the rating of the defence that team's
    players are about to face, since the G+A model is now fitted on
    `opponent_defence_last*` (EXP-2026-25). Both sides come from a single call so
    the two clubs are rated from an identical frame.

    Grouped by season on both the fitting and serving side, deliberately: a
    gameweek-1 fixture has an unrated opponent on both, and that is what the
    fitted model was calibrated against. Grouping by club alone would give the
    first weeks of a season a rating carried in from the previous one — a small,
    plausible, entirely invisible train/serve skew. The season is taken from the
    fixture's own kickoff date for the same reason.

    Any failure yields `{}`, which serves the league-average prior (0.0). A
    feature that is worth ~0.0008 log loss must not be able to take down player
    predictions, so this is a deliberate guard rather than a swallowed error.
    """
    if kickoff is None:
        return {}
    try:
        team_matches = opponent_defence.team_matches_from_matches_df(_get_matches_df())
        if team_matches.empty:
            return {}
        # The season comes from the *kickoff date*, not from the newest season
        # present in the data. Both coincide in production, but deriving it from
        # the data would rate a fixture for a season that has not started yet out
        # of the previous season's matches -- the precise skew this grouping
        # exists to prevent, and invisible because the number is plausible.
        kickoff_at = pd.to_datetime(kickoff)
        season = football_data.season_str(kickoff_at.year if kickoff_at.month >= 7 else kickoff_at.year - 1)
        # `season_str` is the single producer of season labels: `fetch_season` does
        # `df["season"] = season` from `default_completed_seasons()`, and
        # `fetch_current_season_partial` uses the same helper. The manifest confirms
        # it -- `seasons` is uniformly long form ("2018-2019" ... "2026-2027").
        fixtures = pd.DataFrame({
            "season": [season, season],
            # The defence `home` faces is `away`'s, and vice versa.
            "opponent": [away, home],
            "date": [pd.to_datetime(kickoff), pd.to_datetime(kickoff)],
        })
        rated = opponent_defence.rate_opponents(team_matches, fixtures)
    except Exception:
        # Logged, not swallowed. This guard is right -- a feature worth ~0.0008 log
        # loss must not take down a fixture's player list -- but silently returning
        # `{}` means a column rename upstream, or a duplicate key, degrades the
        # feature to the league prior on *every* fixture indefinitely with nothing
        # in any log to say so.
        logger.exception("opponent_defence unavailable; serving the league-average prior")
        return {}

    return {
        home: rated.iloc[0].dropna().to_dict(),
        away: rated.iloc[1].dropna().to_dict(),
    }


def _rank_fixture_players(
    event_id: str,
    home: str,
    away: str,
    confirmed_lineups: dict[str, list[str]] | None = None,
    confirmed_starter_ids: set[int] | None = None,
) -> FixturePlayers:
    models = _get_models()
    pred = scoreline.predict_fixture(
        models["scoreline"], home, away, market_overrides=models.get("scoreline_market_overrides")
    )

    bootstrap = _get_bootstrap()
    current_event = fpl_api.get_current_event(bootstrap)
    position_priors = _get_position_priors()
    reliability_coeffs = _get_player_reliability_coeffs()
    kickoff = _resolve_fixture_kickoff(event_id)
    confirmed_lineups = confirmed_lineups if confirmed_lineups is not None else espn.fetch_confirmed_lineups(home, away, kickoff)
    opponent_defence_by_team = _opponent_defence_for_fixture(home, away, kickoff)

    lineup_model = _get_lineup_model()
    position_rate_models = _get_position_rate_models()
    contribution_model = _get_ready_goal_contribution_model()
    player_shots_by_element = _get_player_shots_by_element()

    def rank(team: str, team_goal_expectation: float, is_home: bool) -> list[PlayerPrediction]:
        ranked = player_goals.rank_team_players(
            team, team_goal_expectation, bootstrap, current_event, position_priors,
            reliability_coeffs=reliability_coeffs, lineup_model=lineup_model,
            position_rate_models=position_rate_models, contribution_model=contribution_model,
            is_home=is_home, confirmed_starters=confirmed_lineups.get(team),
            confirmed_starter_ids=confirmed_starter_ids,
            player_shots_by_element=player_shots_by_element,
            # `context` is what `predict_player` reads its `shots_scale` from.
            # Omitting it left shots_scale at 1.0 on every live call, so
            # expected_shots / expected_shots_on_target were never scaled by
            # how much this team's own attack actually generates.
            context=models.get("context"),
            # EXP-2026-25: the defence this team is about to face.
            opponent_defence=opponent_defence_by_team.get(team),
        )
        return [PlayerPrediction(**{k: p[k] for k in PlayerPrediction.model_fields}) for p in ranked]

    return FixturePlayers(
        home_players=rank(home, pred["home_goal_expectation"], True),
        away_players=rank(away, pred["away_goal_expectation"], False),
    )


def _get_cached_fixture_players(event_id: str, home: str, away: str) -> FixturePlayers:
    """Reuse the background-built player payload when a fixture modal opens."""
    return _cached(
        f"fixture_players:{event_id}",
        lambda: _rank_fixture_players(event_id, home, away),
        ttl=_LIVE_CACHE_TTL_SECONDS,
    )


# Confirmed lineups are typically posted ~60 minutes before kickoff --
# checking at both 90 and 30 minutes out means whichever side of that a
# given match's news drops on, the next check after it happens catches it.
_LINEUP_CHECK_OFFSETS_MINUTES = (90, 30)
_lineup_checks_done: set[tuple[str, int]] = set()


def _lineup_refresh_checkpoint(
    minutes_to_kickoff: float, event_id: str, offsets: tuple[int, ...], already_checked: set[tuple[str, int]]
) -> int | None:
    """Returns the offset (minutes-before-kickoff) that should trigger a
    lineup-aware refresh right now, or None if none applies. Fires on
    *crossing* a threshold (minutes_to_kickoff <= offset), not on landing
    exactly on it -- robust to this loop's own polling cadence/jitter,
    unlike a narrow exact-window match would be. Each (event_id, offset)
    pair fires at most once: this function both decides AND records the
    firing in `already_checked` (mutated in place), so a caller can't
    double-fire by forgetting to update it separately."""
    for offset in sorted(offsets, reverse=True):
        key = (event_id, offset)
        if key in already_checked:
            continue
        if minutes_to_kickoff <= offset:
            already_checked.add(key)
            return offset
    return None


def refresh_lineups_near_kickoff() -> None:
    """Proactively rebuilds the player-predictions cache for any fixture
    crossing a lineup-release checkpoint, so a fixture modal opened right
    after lineups drop shows the confirmed-XI-boosted predictions
    immediately -- rather than waiting for fixture_players's own 5-minute
    TTL to lapse AND a fresh request to happen to arrive after it does
    (confirmed: with nobody re-opening a given fixture, a stale cache
    entry could otherwise sit unchanged all the way to kickoff). Call
    periodically from a background loop (see main.py)."""
    view = current_gameweek_fixtures()
    now = pd.Timestamp.now(tz="UTC")
    for fixture in view.get("fixtures", []):
        event_id = fixture.get("event_id")
        commence = fixture.get("commence_time")
        if fixture.get("finished") or not event_id or not commence:
            continue
        minutes_to_kickoff = (pd.to_datetime(commence, utc=True) - now).total_seconds() / 60
        if minutes_to_kickoff < 0:
            continue
        checkpoint = _lineup_refresh_checkpoint(minutes_to_kickoff, event_id, _LINEUP_CHECK_OFFSETS_MINUTES, _lineup_checks_done)
        if checkpoint is None:
            continue
        try:
            _cached(
                f"fixture_players:{event_id}",
                lambda eid=event_id, h=fixture["team_home"], a=fixture["team_away"]: _rank_fixture_players(eid, h, a),
                ttl=_LIVE_CACHE_TTL_SECONDS,
                force=True,
            )
        except Exception as exc:  # noqa: BLE001 - one fixture's refresh must not block the rest
            print(f"[lineup_refresh] {event_id} ({checkpoint}min checkpoint) skipped: {exc}")


def prewarm_current_gameweek_player_details() -> None:
    """Build current completed-fixture player payloads outside modal requests."""
    current_gameweek = tracking_store.get_track_record().get("current_gameweek")
    if current_gameweek is None:
        return
    group = next(
        (item for item in tracking_store.get_results_by_gameweek() if item["gameweek"] == current_gameweek),
        None,
    )
    if group is None:
        return
    for fixture in group["fixtures"]:
        try:
            _get_cached_fixture_players(fixture["event_id"], fixture["team_home"], fixture["team_away"])
        except Exception as exc:  # noqa: BLE001 - one cache warm must not delay the rest
            print(f"[player_prewarm] {fixture['event_id']} skipped: {exc}")


def _fetch_and_record_fixture_player_outcomes(event_id: str, home: str, away: str, kickoff) -> dict[int, dict]:
    """Fetch official FPL outcomes before any expensive player-model work."""
    post_match = tracking_store.get_fixture_post_match(event_id)
    expected_score = tuple(map(int, post_match["final_score"].split("-"))) if post_match is not None else None
    outcomes: dict[int, dict] = {}
    try:
        outcomes = fpl_api.fixture_player_outcomes(home, away, kickoff, _get_bootstrap(), expected_score=expected_score)
    except Exception as exc:  # noqa: BLE001 - the cache fallback below may still resolve it
        print(f"[player_tracking] direct FPL outcomes skipped: {exc}")
    if not outcomes:
        try:
            outcomes = fpl_api.fixture_player_outcomes(
                home, away, kickoff, {"teams": [], "elements": []}, expected_score=expected_score
            )
        except Exception as exc:  # noqa: BLE001 - a missing outcome must not block scores/cards
            print(f"[player_tracking] cached FPL outcomes skipped: {exc}")
    if outcomes:
        tracking_store.record_fixture_player_outcomes(event_id, outcomes)
    return outcomes


def _snapshot_or_reconcile_player_predictions(
    event_id: str,
    home: str,
    away: str,
    players: FixturePlayers,
    outcomes: dict[int, dict] | None = None,
) -> None:
    kickoff = _resolve_fixture_kickoff(event_id)
    if kickoff is None:
        return
    fixture_time = pd.Timestamp(kickoff)
    if fixture_time.tzinfo is not None:
        fixture_time = fixture_time.tz_localize(None)
    now = pd.Timestamp.now(tz="UTC").tz_localize(None)
    combined = [dict(player.model_dump(), team=home) for player in players.home_players] + [dict(player.model_dump(), team=away) for player in players.away_players]
    post_match = tracking_store.get_fixture_post_match(event_id)
    if fixture_time > now and post_match is None:
        tracking_store.record_player_prediction_snapshots(event_id, combined)
        return
    outcomes = outcomes or _fetch_and_record_fixture_player_outcomes(event_id, home, away, kickoff)
    if not outcomes:
        return
    for player in combined:
        player["confirmed_starter"] = bool(outcomes.get(int(player["player_id"]), {}).get("started"))
    tracking_store.record_player_prediction_snapshots(event_id, combined, provenance="reconstructed")
    tracking_store.reconcile_player_prediction_snapshots(event_id, outcomes)


def _ensure_completed_player_review(
    event_id: str,
    home: str,
    away: str,
    outcomes: dict[int, dict] | None = None,
) -> None:
    if (
        tracking_store.has_player_prediction_snapshots(event_id)
        and tracking_store.has_fixture_player_outcomes(event_id)
    ):
        return
    players = _get_cached_fixture_players(event_id, home, away)
    _snapshot_or_reconcile_player_predictions(event_id, home, away, players, outcomes=outcomes)


def backfill_completed_player_reviews(gameweek: int | None = None) -> dict:
    fixtures = tracking_store.resolved_fixtures_missing_player_snapshots(gameweek)
    outcomes_by_event: dict[str, dict[int, dict]] = {}
    for fixture in fixtures:
        try:
            outcomes = _fetch_and_record_fixture_player_outcomes(
                fixture["event_id"], fixture["team_home"], fixture["team_away"], fixture["commence_time"]
            )
            if outcomes:
                outcomes_by_event[str(fixture["event_id"])] = outcomes
        except Exception as exc:  # noqa: BLE001 - one FPL fixture must not stop the rest
            print(f"[player_outcomes] {fixture['event_id']} skipped: {exc}")

    completed, unresolved = 0, 0
    for fixture in fixtures:
        try:
            outcomes = outcomes_by_event.get(str(fixture["event_id"]))
            if outcomes:
                _ensure_completed_player_review(
                    fixture["event_id"], fixture["team_home"], fixture["team_away"], outcomes=outcomes
                )
            if (
                tracking_store.has_player_prediction_snapshots(fixture["event_id"])
                and tracking_store.has_fixture_player_outcomes(fixture["event_id"])
            ):
                completed += 1
            else:
                unresolved += 1
        except Exception as exc:  # noqa: BLE001 - one fixture must not stop the remaining archive
            unresolved += 1
            print(f"[player_backfill] {fixture['event_id']} skipped: {exc}")
    return {
        "attempted": len(fixtures),
        "events_saved": len(outcomes_by_event),
        "completed": completed,
        "unresolved": unresolved,
    }


@router.get("/fixtures/{event_id}/players", response_model=FixturePlayers)
def fixture_players(event_id: str, read_only: bool = False):
    """`read_only=True` is for public_snapshot.py's own bulk export use
    only — skips the tracking-store snapshot/reconcile write below (for a
    finished match, that write can itself trigger a live outcomes fetch),
    same idea as `fixture_detail`'s own `read_only` param. The frontend
    never sets it."""
    if PUBLIC_MODE:
        cached = _public_snapshot().get("fixture_players_by_event_id", {}).get(event_id)
        if cached is None:
            raise HTTPException(status_code=404, detail=f"No fixture with event_id={event_id}")
        return cached

    resolved = _resolve_fixture_teams(event_id)
    if resolved is None:
        raise HTTPException(status_code=404, detail=f"No fixture with event_id={event_id}")
    home, away = resolved
    players = _get_cached_fixture_players(event_id, home, away)
    if not read_only:
        _snapshot_or_reconcile_player_predictions(event_id, home, away, players)
    return players


@router.get("/fixtures/{event_id}/player-review")
def fixture_player_review(event_id: str):
    if PUBLIC_MODE:
        # The live public deployment never accumulates tracking history
        # itself (background tracking is skipped entirely in PUBLIC_MODE —
        # see main.py's lifespan), but public_snapshot.py runs this same
        # route locally at build time, where real tracking history *does*
        # exist, and bakes the result in — same pattern as fixture_detail's
        # own post_match field, which is exactly what makes the frontend
        # call this route in the first place. None (not 404) when a
        # fixture's review genuinely isn't available yet, matching what
        # this returns locally in that case.
        return _public_snapshot().get("player_review_by_event_id", {}).get(event_id)

    resolved = _resolve_fixture_teams(event_id)
    if resolved is None:
        raise HTTPException(status_code=404, detail=f"No fixture with event_id={event_id}")
    home, away = resolved
    if not (
        tracking_store.has_player_prediction_snapshots(event_id)
        and tracking_store.has_fixture_player_outcomes(event_id)
    ):
        kickoff = _resolve_fixture_kickoff(event_id)
        if kickoff is not None:
            outcomes = _fetch_and_record_fixture_player_outcomes(event_id, home, away, kickoff)
            if outcomes:
                _ensure_completed_player_review(event_id, home, away, outcomes=outcomes)
    return tracking_store.get_fixture_player_review(event_id)


def background_tracking_tick() -> None:
    """Capture routine markets and confirmed-XI calls without a UI request."""
    try:
        table = _value_bet_table()
        _run_tracking_bookkeeping(table)
        backfill_completed_player_reviews()
        if table.empty:
            return
        now = pd.Timestamp.now(tz="UTC").tz_localize(None)
        for _, fixture in table.iterrows():
            kickoff = pd.Timestamp(fixture["commence_time"])
            if kickoff.tzinfo is not None:
                kickoff = kickoff.tz_localize(None)
            if not (now <= kickoff <= now + pd.Timedelta(hours=4)):
                continue
            confirmed = espn.fetch_confirmed_lineups(fixture["team_home"], fixture["team_away"], fixture["commence_time"])
            if fixture["team_home"] not in confirmed or fixture["team_away"] not in confirmed:
                continue
            tracking_store.record_fixture_forecast_snapshots(
                table.loc[[fixture.name]],
                "confirmed_xi_baseline",
                {str(fixture["event_id"]): confirmed},
            )
            players = _rank_fixture_players(str(fixture["event_id"]), fixture["team_home"], fixture["team_away"], confirmed)
            _snapshot_or_reconcile_player_predictions(str(fixture["event_id"]), fixture["team_home"], fixture["team_away"], players)
    except Exception as exc:  # noqa: BLE001 - periodic tracking is best effort
        print(f"[background_tracking] skipped: {exc}")


def _team_fixture_to_summary(fixture: pd.Series, pred: dict) -> FixtureSummary:
    """Same shape as `_row_to_summary`, for a fixture pulled from
    `get_all_remaining_fixtures()` rather than the odds-windowed value-bet
    table — those use the FPL API's own fixture ids, which don't line up
    with the Odds API's `event_id`s, so there's no reliable way to join a
    live market onto them here. Always model-only (`has_live_odds=False`),
    same graceful no-odds path already proven in `odds/value_bets.py`."""

    def edge(prob_key: str) -> MarketEdge:
        return MarketEdge(prob=pred[prob_key], implied=None, edge=None)

    return FixtureSummary(
        event_id=str(fixture["event_id"]),
        commence_time=fixture["commence_time"],
        team_home=fixture["team_home"],
        team_away=fixture["team_away"],
        home_win=edge("home_win"),
        draw=edge("draw"),
        away_win=edge("away_win"),
        over_2_5=edge("over_2_5"),
        under_2_5=edge("under_2_5"),
        btts_yes_prob=pred["btts_yes"],
        top_scoreline=f"{pred['top_scorelines'][0]['home']}-{pred['top_scorelines'][0]['away']}",
        is_fallback_prediction=pred["fallback"],
        data_confidence=pred["data_confidence"],
        predicted_total_goals=pred["home_goal_expectation"] + pred["away_goal_expectation"],
        predicted_margin=pred["home_goal_expectation"] - pred["away_goal_expectation"],
        home_2plus_prob=pred["home_2plus_prob"],
        away_2plus_prob=pred["away_2plus_prob"],
        value_bet_flags=[],
        has_live_odds=False,
    )


def _recorded_fixture_to_summary(rec: dict) -> FixtureSummary:
    """Same shape as `_row_to_summary`/`_team_fixture_to_summary`, for an
    already-finished fixture reached via the gameweek view — uses the
    honestly pre-match-recorded probabilities from `tracking_store` instead
    of recomputing live. No live odds/edge to show (this isn't the
    odds-windowed table), same graceful no-odds shape as
    `_team_fixture_to_summary`."""

    def edge(prob_key: str) -> MarketEdge:
        return MarketEdge(prob=rec[prob_key], implied=None, edge=None)

    return FixtureSummary(
        event_id=rec["event_id"],
        commence_time=rec["commence_time"],
        team_home=rec["team_home"],
        team_away=rec["team_away"],
        home_win=edge("home_win"),
        draw=edge("draw"),
        away_win=edge("away_win"),
        over_2_5=edge("over_2_5"),
        under_2_5=edge("under_2_5"),
        btts_yes_prob=rec["btts_yes"],
        top_scoreline=rec["predicted_scoreline"] or "?",
        is_fallback_prediction=False,
        data_confidence=None,
        value_bet_flags=[],
        has_live_odds=False,
    )


@router.get("/teams")
def list_teams():
    all_remaining = _get_remaining_fixtures_df()
    if all_remaining.empty:
        return {"teams": []}
    return {"teams": sorted(set(all_remaining["team_home"]) | set(all_remaining["team_away"]))}


@router.get("/teams/{team}/fixtures", response_model=list[FixtureSummary])
def team_fixtures(team: str, limit: int = 5):
    """A team's next `limit` remaining fixtures with predictions —
    always finds one regardless of how far out it is, unlike the main
    `/api/fixtures` list which is limited to whatever window The Odds API
    currently has pre-match lines for (typically 1-2 gameweeks)."""
    if PUBLIC_MODE:
        # Not called by the frontend anywhere, but was reachable unguarded
        # -- _get_models() runs the same live pipeline PUBLIC_MODE exists
        # to keep off this host (see get_calibration). No snapshot
        # equivalent exists (out of public_snapshot.py's deliberate scope).
        return []
    all_remaining = _get_remaining_fixtures_df()
    if all_remaining.empty:
        return []
    team_df = (
        all_remaining[(all_remaining["team_home"] == team) | (all_remaining["team_away"] == team)]
        .sort_values("commence_time")
        .head(limit)
    )
    if team_df.empty:
        return []

    models = _get_models()
    return [
        _team_fixture_to_summary(
            fixture,
            scoreline.predict_fixture(
                models["scoreline"],
                fixture["team_home"],
                fixture["team_away"],
                market_overrides=models.get("scoreline_market_overrides"),
            ),
        )
        for _, fixture in team_df.iterrows()
    ]


@router.get("/manifest")
def get_manifest():
    if not manifest_lib.MANIFEST_PATH.exists():
        raise HTTPException(status_code=409, detail="No trained models yet — call POST /api/retrain first.")
    manifest = manifest_lib.load_manifest().copy()
    if PUBLIC_MODE:
        # live_current_season_matches is a live-results probe, not a model
        # fact -- skip it here rather than fetching FPL results live on
        # every request to this deployment (see PUBLIC_MODE's contract of
        # never running the live pipeline, api/main.py's lifespan docstring).
        manifest["live_results_source"] = "unavailable"
        return manifest
    try:
        manifest["live_current_season_matches"] = int(len(_get_live_current_results_df()))
        manifest["live_results_source"] = "official_fpl"
    except Exception:  # noqa: BLE001 - a metadata probe must not hide the trained model
        manifest["live_results_source"] = "unavailable"
    return manifest


@router.get("/manifest/history")
def get_manifest_history():
    return {"history": manifest_lib.score_change_history(manifest_lib.load_manifest_history())}


@router.get("/snapshot-meta")
def get_snapshot_meta():
    """Snapshot freshness for cross-service consumers (the hub's
    stale-while-revalidate cache gates refetching on this, as it does for
    every other sport). Same shape as the other sports' snapshot-meta:
    `generated_at` + `source`, plus PL's model fingerprint."""
    if PUBLIC_MODE:
        snapshot = _public_snapshot()
        return {
            "generated_at": snapshot.get("generated_at"),
            "source": "public_snapshot",
            "model_fingerprint": snapshot.get("model_fingerprint"),
        }
    manifest = manifest_lib.load_manifest() if manifest_lib.MANIFEST_PATH.exists() else {}
    return {"generated_at": manifest.get("trained_at"), "source": "manifest"}


@router.get("/calibration")
def get_calibration():
    if PUBLIC_MODE:
        # Confirmed live: this endpoint's live path (build_training_frame +
        # a chronological split + fitting calibration curves) is exactly
        # the heavy live-serving computation PUBLIC_MODE exists to avoid --
        # it was reachable unguarded here and firing on every Model-tab
        # visit, the same football-data.co.uk scrape the snapshot system
        # was built to keep off this host. Baking THAT computation into
        # public_snapshot.py was tried and reverted -- confirmed live it
        # made the snapshot build hang indefinitely partway through
        # (build_training_frame appears to stall on GitHub's runners in a
        # way it never did locally) twice in a row, which is worse than an
        # empty Model tab.
        #
        # What the snapshot bakes instead (public_snapshot.py) is computed
        # from the tracking store's counted recorded picks -- data the
        # build already has locally, no training frame involved. The
        # question it answers is how well calibrated the picks this site
        # actually published are; the holdout-season question stays with
        # the live path. The bookmaker series there is scored from the
        # prices stored with each recorded pick since 2026-11, so it
        # stays null until enough recorded picks carry odds — it is never
        # reconstructed for picks recorded without them.
        return _public_snapshot().get(
            "calibration", {"model": [], "bookmaker": [], "naive": [], "season": None}
        )
    trained_at = manifest_lib.load_manifest().get("trained_at", "untrained") if manifest_lib.MANIFEST_PATH.exists() else "untrained"

    def build():
        models = _get_models()
        df, _ = build_training_frame()
        _, val_df = chronological_split(df)
        return {
            "model": calibration_lib.model_calibration(models["scoreline"], val_df),
            "bookmaker": calibration_lib.bookmaker_calibration(val_df),
            "naive": calibration_lib.naive_favourite_baseline(val_df),
            "season": str(val_df["season"].iloc[0]) if not val_df.empty else None,
        }

    return _cached(f"calibration_{trained_at}", build, ttl=_LIVE_CACHE_TTL_SECONDS)


@router.get("/squad-continuity")
def get_squad_continuity():
    """Per-team squad continuity for the current season (EXP-2026-18, see
    docs/AI_CONTINUITY.md and features/squad_change.py) — the fraction of
    last season's playing-time minutes retained by players still
    registered this season, lowest first (biggest off-season turnover).
    Feeds `ml_scoreline`'s feature set directly (see features/build.py);
    this endpoint just exposes the raw per-team numbers for display,
    independent of which scoreline model happens to be `chosen_model`."""
    season = football_data.season_str(football_data.CURRENT_SEASON_START_YEAR)
    if PUBLIC_MODE:
        # Not called by the frontend anywhere, but was reachable unguarded
        # -- team_season_continuity_table() builds the same live training
        # frame PUBLIC_MODE exists to keep off this host (see get_calibration).
        return {"season": season, "teams": []}

    def build():
        try:
            table = squad_change.team_season_continuity_table([season])
        except RuntimeError:
            return []
        return table.sort_values("squad_continuity")[["team", "squad_continuity"]].to_dict("records")

    return {"season": season, "teams": _cached("squad_continuity", build, ttl=24 * 3600)}


@router.post("/backtest", dependencies=[Depends(_admin_only)])
def run_backtest(edge_threshold: float = 0.05, staking: str = "kelly", drawdown_trials: int = 0):
    models = _get_models()
    df, _ = build_training_frame()
    _, val_df = chronological_split(df)
    start, end = str(val_df["date"].min().date()), str(val_df["date"].max().date())
    selections: list[dict] = []
    bt = backtest_lib.build_value_bet_backtest(
        val_df,
        models["scoreline"],
        start,
        end,
        edge_threshold=edge_threshold,
        staking=staking,
        selections=selections,
        market_overrides=models.get("scoreline_market_overrides"),
    )
    response = {
        "results": bt.results(),
        "bankroll_curve": bt.account.tracker,
        "staking": staking,
        "season": str(val_df["season"].iloc[0]) if not val_df.empty else None,
        "selections": selections,
    }
    # Opt-in (0 = skip): the single `bankroll_curve` above is one realized
    # path through which flagged bets happened to win or lose -- this reruns
    # staking `drawdown_trials` times with each selection's outcome
    # redrawn from the model's own probability, to put the realized
    # drawdown/ROI in context instead of taking one path as "the" result.
    if drawdown_trials > 0:
        response["drawdown_distribution"] = backtest_lib.bootstrap_drawdown_distribution(
            selections, staking=staking, n_trials=drawdown_trials
        )
    return response


@router.get("/value-bets/walk-forward")
def get_walk_forward_value_bet_validation():
    """Periodic multi-season validation for the live single-bet rule."""
    if PUBLIC_MODE:
        # Retrains ml_scoreline per walk-forward fold (see
        # evaluate/betting_validation.py::run_walk_forward_value_bet_validation)
        # -- as memory-heavy as /backtest, which is already admin-only for
        # the same reason. Unlike /backtest this is a real user-facing
        # button (WalkForwardBettingPanel), so degrade with an honest
        # "disabled here" message instead of a 404 or an OOM crash.
        raise HTTPException(
            status_code=503,
            detail="Walk-forward validation is disabled on this public deployment (too memory-intensive for this host).",
        )
    return _cached(
        "value_bet_walk_forward",
        betting_validation.run_walk_forward_value_bet_validation,
        ttl=24 * 3600,
    )


@router.get("/value-bets/track-record")
def get_value_bet_track_record(staking: str = "kelly"):
    """Live counterpart to /backtest: not a synthetic held-out-season
    replay, but the real fixtures the app actually flagged as "Value bet"
    (via /api/fixtures and /api/fixtures/gameweek's shared bookkeeping),
    tracked from the moment each was first flagged and reconciled once the
    match finishes. Answers "have the value-bet recommendations actually
    shown to the user been worth following," not "is this a good strategy
    in principle." """
    if not PUBLIC_MODE:
        # Background tracking is skipped entirely in PUBLIC_MODE (see
        # fixture_player_review's PUBLIC_MODE branch above), so this write
        # path has nothing to reconcile there -- and _value_bet_table()
        # alone is the full live pipeline Render's free tier OOMs on.
        _run_tracking_bookkeeping(_value_bet_table())
    return value_bet_ledger.get_value_bet_track_record(staking=staking)


@router.post("/retrain", dependencies=[Depends(_admin_only)])
def retrain(include_selection: bool = False):
    """Refit every model.

    `include_selection=true` additionally recomputes the scoreline-selection
    diagnostics, which is what puts a `walk_forward_mean_rps` headline into
    `manifest.json`. It is opt-in because it is a full four-candidate walk-forward
    -- minutes on top of an already-slow retrain -- and because the diagnostics
    change rarely: they describe the *decision procedure's* selection bias, not
    this week's data.

    It runs **before** `train_all` because the manifest is written by `train_all`
    and reads the cache while doing so. Running it afterwards would leave the
    manifest reporting `not_computed` for a retrain that had just produced the
    numbers.

    Without the flag the manifest reports `walk_forward_status: "not_computed"`
    and omits `headline_rps`. That is the honest default -- a stale headline is
    worse than an absent one -- but it does mean the published walk-forward mean
    only appears once this has been run at least once per data window.
    """
    if include_selection:
        seasons = manifest_lib.default_scoreline_seasons()
        result = scoreline_selection.run(seasons=seasons)
        scoreline_selection.write_cache(result, seasons=result.get("seasons"))
    manifest = manifest_lib.train_all()
    _clear_cache("models", "value_bet_table")
    return manifest


@router.post("/refresh-odds", dependencies=[Depends(_admin_only)])
def refresh_odds():
    refresh_sportsbook_odds_in_background()
    return {"status": "ok"}


_last_public_refresh_trigger = 0.0
_public_refresh_lock = Lock()


@router.post("/refresh-odds/public")
def refresh_odds_public():
    """Any visitor's "Refresh odds" button -- deliberately NOT behind
    `_admin_only`. On the public deployment this must never run the real
    odds-fetch/value-bet pipeline itself (see PUBLIC_SNAPSHOT_PATH's
    comment: that's the exact compute the free-tier host OOMs on) -- it
    only asks GitHub Actions to run refresh-public-snapshot.yml sooner
    than its next scheduled slot. The already-running background poll
    (refresh_public_snapshot_from_remote, api/main.py's lifespan loop)
    picks the new snapshot up once that workflow finishes and pushes,
    same as any of its scheduled runs -- this endpoint only requests an
    earlier run, it never serves fresher data itself.

    Off the public deployment (local/private use) there's no OOM risk, so
    this runs the real refresh directly, identical to the admin endpoint
    above -- just without needing to be logged in as -- admin, since
    there's no login gate there either."""
    global _last_public_refresh_trigger
    with _public_refresh_lock:
        elapsed = time.time() - _last_public_refresh_trigger
        if elapsed < PUBLIC_REFRESH_COOLDOWN_SECONDS:
            wait = int(PUBLIC_REFRESH_COOLDOWN_SECONDS - elapsed)
            raise HTTPException(status_code=429, detail=f"Already refreshing -- try again in {wait}s")
        _last_public_refresh_trigger = time.time()

    if not PUBLIC_MODE:
        refresh_sportsbook_odds_in_background()
        return {"status": "ok"}

    if not GITHUB_ACTIONS_TOKEN:
        raise HTTPException(
            status_code=503,
            detail="Odds refresh isn't configured on this deployment yet -- GITHUB_ACTIONS_TOKEN is unset.",
        )
    try:
        resp = requests.post(
            f"https://api.github.com/repos/{GITHUB_ACTIONS_REPO}/actions/workflows/refresh-public-snapshot.yml/dispatches",
            headers={
                "Authorization": f"Bearer {GITHUB_ACTIONS_TOKEN}",
                "Accept": "application/vnd.github+json",
            },
            json={"ref": "main"},
            timeout=15,
        )
        resp.raise_for_status()
    except requests.RequestException as exc:
        raise HTTPException(status_code=502, detail=f"Couldn't reach GitHub Actions: {exc}") from exc
    return {"status": "requested", "note": "Refreshing odds and value bets -- this can take a few minutes to appear."}


@router.post("/refresh-fixtures", dependencies=[Depends(_admin_only)])
def refresh_fixtures():
    _clear_cache("fixtures_df", "value_bet_table", "live_current_results", "fd_org_standings")
    _clear_cache_prefix("projected_table_")
    _clear_cache_prefix("team_hub_")
    _get_fixtures_df(force=True)
    return {"status": "ok"}


def _current_season_label() -> str:
    """The real in-progress season (e.g. '2026-2027'), not just whichever
    season happens to be latest in the loaded training window — those are
    different once the new season has started but football-data.co.uk
    hasn't published any results for it yet (or, as now, before a single
    ball's been kicked): `matches_df["season"].max()` would silently pick
    the *previous*, fully-completed season instead."""
    return football_data.season_str(football_data.CURRENT_SEASON_START_YEAR)


def _fpl_projections(gameweek: int | None = None) -> dict:
    """Build the FPL view from the official live pool and the independent
    scoreline model.  It is cached separately from fixtures because an FPL
    page should not trigger one element-summary request per player."""
    bootstrap = _get_bootstrap()
    event_id = gameweek or fpl_api.get_current_event(bootstrap)
    if event_id is None:
        raise HTTPException(status_code=409, detail="FPL has not published a current or next gameweek yet.")

    def build():
        fixtures = fpl_api.fetch_fixtures()
        models = _get_models()
        teams = {int(team["id"]): team["name"] for team in bootstrap.get("teams", [])}
        event_fixtures = [item for item in fixtures if item.get("event") == int(event_id) and not item.get("finished")]
        batch_input = pd.DataFrame([
            {
                "team_home": to_canonical(teams.get(int(item["team_h"]), str(item["team_h"])), source="fpl"),
                "team_away": to_canonical(teams.get(int(item["team_a"]), str(item["team_a"])), source="fpl"),
                "commence_time": item.get("kickoff_time"),
            }
            for item in event_fixtures
        ])
        batch_predictions = scoreline.predict_fixtures_batch(
            models["scoreline"], batch_input, market_overrides=models.get("scoreline_market_overrides")
        ) if not batch_input.empty else []
        prediction_by_pair = {
            (row.team_home, row.team_away): {**prediction, "model_source": "independent_scoreline"}
            for row, prediction in zip(batch_input.itertuples(index=False), batch_predictions)
        }

        def predict(home: str, away: str) -> dict:
            return prediction_by_pair.get(
                (to_canonical(home, source="fpl"), to_canonical(away, source="fpl")),
                {"home_goal_expectation": 1.35, "away_goal_expectation": 1.15, "model_source": "fpl_fallback"},
            )

        return fpl_model.build_projections(bootstrap, fixtures, int(event_id), predict)

    return _cached(f"fpl_projections_{event_id}", build, ttl=_LIVE_CACHE_TTL_SECONDS)


@router.get("/fpl/projections")
def fpl_projections(gameweek: int | None = None):
    if PUBLIC_MODE:
        return _public_snapshot().get("fpl", {}).get("projections", {"gameweek": gameweek, "players": []})
    return _fpl_projections(gameweek)


@router.get("/fpl/optimal-xi")
def fpl_optimal_xi(gameweek: int | None = None, formation: str | None = None):
    if PUBLIC_MODE:
        return _public_snapshot().get("fpl", {}).get("optimal_xi", {})
    data = _fpl_projections(gameweek)
    try:
        recommendation = fpl_model.optimal_xi(data["players"], formation=formation)
    except ValueError as exc:
        raise HTTPException(status_code=422, detail=str(exc)) from exc
    return {"gameweek": data["gameweek"], "model_source": data["model_source"], **recommendation}


@router.get("/fpl/squad")
def fpl_squad(gameweek: int | None = None, budget: float = 100.0):
    if not 80.0 <= budget <= 120.0:
        raise HTTPException(status_code=422, detail="Budget must be between £80m and £120m.")
    if PUBLIC_MODE:
        return _public_snapshot().get("fpl", {}).get("squad", {})
    data = _fpl_projections(gameweek)
    try:
        recommendation = fpl_model.build_squad(data["players"], budget)
    except ValueError as exc:
        raise HTTPException(status_code=409, detail=str(exc)) from exc
    return {"gameweek": data["gameweek"], "model_source": data["model_source"], **recommendation}


@router.post("/fpl/transfers/manual")
def fpl_manual_transfers(request: FPLManualSquadRequest = Body(...), gameweek: int | None = None):
    if len(set(request.player_ids)) != 15:
        raise HTTPException(status_code=422, detail="A manual FPL squad must contain exactly 15 distinct player ids.")
    data = _fpl_projections(gameweek)
    try:
        result = fpl_model.transfer_recommendations(data["players"], request.player_ids, request.bank, request.free_transfers)
    except ValueError as exc:
        raise HTTPException(status_code=422, detail=str(exc)) from exc
    current_squad = [player for player in data["players"] if player["player_id"] in set(request.player_ids)]
    return {
        "gameweek": data["gameweek"],
        "source": "manual",
        "current_lineup": fpl_model.squad_lineup(current_squad),
        **result,
    }


@router.get("/fpl/entry/{entry_id}/transfers")
def fpl_entry_transfers(entry_id: int, gameweek: int | None = None, free_transfers: int = 1):
    """Public-entry convenience endpoint.  The ID is only used for this
    request; no entry or squad is written to our tracking database.

    This is reachable in PUBLIC_MODE (a random visitor entering their own
    public entry ID is exactly the intended use) with no admin surface or
    write involved, so it isn't gated like `_admin_only` routes — but
    unlike every other FPL endpoint here, it makes a fresh outbound FPL
    request on every call with no cache at all, which an anonymous public
    deployment has no rate limit in front of. A given entry's picks for an
    already-reached gameweek never change, so caching by
    (entry_id, gameweek) removes the repeat-request cost/abuse surface
    without changing the result."""
    data = _fpl_projections(gameweek)
    try:
        picks, source_gameweek = _cached(
            f"fpl_entry_picks_{entry_id}_{data['gameweek']}",
            lambda: fpl_api.fetch_latest_entry_picks(entry_id, data["gameweek"], _get_bootstrap()),
            ttl=_LIVE_CACHE_TTL_SECONDS,
        )
    except Exception as exc:  # noqa: BLE001 - FPL uses several failure shapes
        raise HTTPException(status_code=502, detail="FPL could not load that public entry for this gameweek.") from exc
    player_ids = [int(item["element"]) for item in picks.get("picks", [])]
    bank = float(picks.get("entry_history", {}).get("bank", 0) or 0) / 10.0
    try:
        result = fpl_model.transfer_recommendations(data["players"], player_ids, bank, free_transfers)
    except ValueError as exc:
        raise HTTPException(status_code=422, detail=str(exc)) from exc
    current_squad = [player for player in data["players"] if player["player_id"] in set(player_ids)]
    return {
        "gameweek": data["gameweek"],
        "source_gameweek": source_gameweek,
        "source": "public_entry",
        "entry_id": entry_id,
        "current_lineup": fpl_model.squad_lineup(current_squad),
        **result,
    }


@router.get("/hub/rankings")
def get_power_rankings():
    if PUBLIC_MODE:
        return _public_snapshot().get("hub", {}).get("rankings", {"rankings": [], "ratings_history": {}, "season": None})
    matches_df = _get_matches_df()
    current_season = _current_season_label()
    season_matches = matches_df[matches_df["season"] == current_season]

    if not season_matches.empty:
        current_teams = set(season_matches["team_home"]) | set(season_matches["team_away"])
    else:
        remaining_df = _get_remaining_fixtures_df()
        current_teams = (set(remaining_df["team_home"]) | set(remaining_df["team_away"])) if not remaining_df.empty else None
    prior_matches = matches_df[matches_df["season"] != current_season]
    prior_model = _cached(
        f"rankings_preseason_prior_{current_season}", lambda: scoreline.fit_dixon_coles(prior_matches), ttl=24 * 3600
    )
    games_played = (
        pd.concat([season_matches["team_home"], season_matches["team_away"]]).value_counts().to_dict()
        if not season_matches.empty
        else {}
    )
    # A display-only ranking can update after each result without changing
    # scoreline probabilities or value-bet decisions. The fixed 75% online
    # Elo/Pi form blend won the offline ranking comparison; its remaining 25%
    # pre-season prior stops an isolated result from completely erasing the
    # history-seeded baseline.
    rankings = _cached(
        f"rankings_live_form_{current_season}_{len(season_matches)}",
        lambda: power_rankings_mod.blended_form_power_rankings(
            prior_model,
            ratings_mod.fit_elo(matches_df),
            ratings_mod.fit_pi_ratings(matches_df),
            current_teams=current_teams or set(),
            form_weight=0.75,
            games_played=games_played,
        ),
        ttl=_LIVE_CACHE_TTL_SECONDS,
    )

    history = ratings_mod.team_rating_timeseries(season_matches, fd_org_matches=_get_fd_org_matches())
    if history.empty:
        ratings_history = {}
    else:
        history["date"] = history["date"].dt.date.astype(str)
        history["gameweek"] = history["gameweek"].apply(lambda v: int(v) if pd.notna(v) else None)
        ratings_history = {
            team: group[["date", "elo", "pi", "gameweek"]].to_dict("records") for team, group in history.groupby("team")
        }

    return {"rankings": rankings, "ratings_history": ratings_history, "season": current_season}


@router.get("/hub/table")
def get_projected_table():
    if PUBLIC_MODE:
        return _public_snapshot().get("hub", {}).get("table", {"table": [], "season": None})
    matches_df = _get_matches_df()
    current_season = _current_season_label()
    live_results = _get_live_current_results_df()
    live_result_signature = tuple(
        live_results[["event_id", "goals_home", "goals_away"]].itertuples(index=False, name=None)
    ) if not live_results.empty else ()
    trained_at = manifest_lib.load_manifest().get("trained_at", "untrained") if manifest_lib.MANIFEST_PATH.exists() else "untrained"

    def build():
        models = _get_models()
        standings, _ = _get_live_current_standings(current_season)
        if standings.empty:
            standings = projected_table.compute_standings(matches_df[matches_df["season"] == current_season])
        remaining_fixtures = _get_remaining_fixtures_df()
        table = projected_table.project_table(models["scoreline"], remaining_fixtures, standings)
        return {"table": table, "season": current_season}

    return _cached(
        f"projected_table_{current_season}_{live_result_signature}_{trained_at}", build, ttl=_LIVE_CACHE_TTL_SECONDS
    )


@router.get("/hub/track-record")
def get_hub_track_record():
    if PUBLIC_MODE:
        return _public_snapshot().get("hub", {}).get(
            "track_record", {"summary": {}, "biggest_upsets": [], "gameweeks": [], "value_bets": None}
        )
    summary = tracking_store.get_track_record()
    summary["calibration"] = tracking_store.get_calibration()
    return {
        "summary": summary,
        "biggest_upsets": tracking_store.get_biggest_upsets(),
        "gameweeks": tracking_store.get_results_by_gameweek(),
        # The against-the-odds block: the value-bet ledger's own graded
        # record (see tracking/value_bet_ledger.py::get_value_bet_summary).
        "value_bets": value_bet_ledger.get_value_bet_summary(),
    }


@router.get("/hub/teams")
def get_team_hub():
    if PUBLIC_MODE:
        return _public_snapshot().get("hub", {}).get("teams", {})
    matches_df = _get_matches_df()
    season = _current_season_label()
    live_results = _get_live_current_results_df()
    live_result_signature = tuple(
        live_results[["event_id", "goals_home", "goals_away"]].itertuples(index=False, name=None)
    ) if not live_results.empty else ()
    return _cached(
        f"team_hub_{season}_{live_result_signature}",
        lambda: hub_analytics.build_team_hub(matches_df, season, bootstrap=_get_bootstrap(), live_results=live_results),
        ttl=_LIVE_CACHE_TTL_SECONDS,
    )


@router.get("/hub/players")
def get_player_hub():
    if PUBLIC_MODE:
        return _public_snapshot().get("hub", {}).get("players", {})
    return _cached("player_hub", lambda: hub_analytics.build_player_hub(_get_bootstrap()), ttl=300)


@router.get("/scorer-track-record")
def get_scorer_track_record():
    """Keep player-model evaluation with the calibration surfaces, not discovery."""
    if PUBLIC_MODE:
        # Background tracking is skipped entirely in PUBLIC_MODE (see
        # main.py's lifespan), so tracking_store is never populated here.
        # Baking this into public_snapshot.json alongside get_calibration
        # was tried and reverted -- see get_calibration's comment.
        return {"snapshot": {}, "reconstructed": {}}
    return tracking_store.get_scorer_accuracy()


@router.get("/research/confirmed-xi")
def get_confirmed_xi_experiment():
    if PUBLIC_MODE:
        return {}
    return tracking_store.confirmed_xi_experiment_status()


@router.get("/research/odds-snapshots")
def get_odds_snapshot_experiment():
    if PUBLIC_MODE:
        return {}
    return tracking_store.odds_snapshot_status()


@router.get("/research/historical-closing-odds")
def get_historical_closing_odds_benchmark():
    if PUBLIC_MODE:
        # Not called by the frontend anywhere, but was reachable unguarded
        # -- _get_matches_df() runs the same live pipeline PUBLIC_MODE
        # exists to keep off this host (see get_calibration).
        return {}
    return _cached(
        "historical_closing_odds_benchmark",
        lambda: odds_benchmark.closing_odds_benchmark(_get_matches_df()),
        ttl=24 * 3600,
    )
