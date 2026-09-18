"""
Validation Resource for the Pulse SDK.

This module provides methods for validating simulation quality by comparing
simulated LOB data against historical data using distributional metrics,
impact response analysis, stylised facts, and the MIND/FID inception distances
on DeepLOB embeddings.

Workflow:
    1. Submit a validation job with run() -> returns job_id
    2. Poll status with get_job(job_id) or use run_pipeline() for blocking
    3. View results including distances and plots
    4. List past jobs with list_jobs()

For the inception distances alone, inception_distances() is a one-call
shortcut that returns just the MIND and FID scores.

Tri-state run flags
-------------------
``run_metrics`` / ``run_impact`` / ``run_stylised_facts`` / ``plot_data``
default to ``None``, meaning "use the default for my tier" — resolved
server-side. Demo turns everything on; other tiers get metrics and stylised
facts. Only flags you set explicitly are sent, so a demo key is not silently
opted out of the passes it is entitled to. Pass ``False`` to skip an expensive
pass, or ``True`` to force one on.

``run_inception_distances`` is the exception: it defaults to ``True``, so MIND
and FID are computed unless you opt out. It maps to the API's ``run_fid``
config field, which gates both metrics because they share one DeepLOB
embedding pass. As of pulse-api-pod 1.56.0 the scores are returned to every
validation tier; on older API deployments they reach the demo tier only.
"""

import base64
import json
import time
from pathlib import Path


RUN_PATH = "/validation/run"
UPLOAD_PATH = "/validation/run/upload"
JOBS_PATH = "/validation/jobs"

#: The API rejects more per job; checked client-side so a 26-file submission
#: fails before any bytes are uploaded.
MAX_SIM_FILES = 25

#: Flags the API resolves from the caller's tier when left unset.
_TRI_STATE_FLAGS = (
    "run_metrics",
    "run_impact",
    "run_stylised_facts",
    "plot_data",
)

#: Areas of checking selectable per job, as of pulse-check 1.10.0. Left unset
#: they take the server's default, so a job that names none behaves as before.
_AREA_FLAGS = ("statistical", "stylised_facts", "impact", "volume_correlation",
               "fid", "mind")

#: Everything else the 1.10.0 schema accepts. ``lob`` marks the frames as L2
#: snapshots, which switches off anything needing the message stream;
#: ``sample_period`` and ``match_generated_sample`` set the grid the book is
#: resampled onto; ``plots`` is False, True, or a list of plot ids;
#: ``historical_output`` is the demo-only gate that ``plot_data`` used to be.
_EXTRA_FIELDS = ("lob", "sample_period", "match_generated_sample", "plots",
                 "historical_output")

#: SDK name -> API config field. The API kept ``run_fid`` for compatibility;
#: the SDK spells out what it actually gates.
_INCEPTION_WIRE_FIELD = "run_fid"


def _frame_to_parquet(entry, index: int):
    """Normalise one simulated run to ``(filename, parquet bytes)``.

    Accepts a path, a ``(filename, bytes)`` pair, or a polars / pandas
    DataFrame, which is written to parquet in memory. The frame must be pulse
    format -- the same shape the engine writes to ``sim_data.parquet`` -- which
    the server validates; sending something else fails there, not here.
    """
    import io

    if isinstance(entry, tuple):
        return entry

    # Duck-typed rather than imported: neither polars nor pandas is a hard
    # dependency of the SDK, and importing one to test for the other would
    # make it one.
    writer = getattr(entry, "write_parquet", None)      # polars
    if writer is not None:
        buf = io.BytesIO()
        writer(buf)
        return f"sim_{index}.parquet", buf.getvalue()

    writer = getattr(entry, "to_parquet", None)          # pandas
    if writer is not None:
        buf = io.BytesIO()
        writer(buf, index=False)
        return f"sim_{index}.parquet", buf.getvalue()

    path = Path(entry)
    return path.name, path.read_bytes()


def _build_config(
    run_metrics,
    run_impact,
    run_inception_distances,
    run_stylised_facts,
    plot_data,
    n_levels,
    l2_only,
    **extra,
) -> dict:
    """The validation config object as the API expects it.

    Tri-state flags left as None are omitted rather than sent as null: the API
    reads absence as "use my tier's default", and an explicit null would not
    do that. The same rule covers the 1.10.0 area flags and everything in
    ``extra`` — naming nothing new leaves the job behaving exactly as before.
    """
    config = {
        "n_levels": n_levels,
        "l2_only": l2_only,
        _INCEPTION_WIRE_FIELD: run_inception_distances,
    }
    for flag, value in zip(
        _TRI_STATE_FLAGS,
        (run_metrics, run_impact, run_stylised_facts, plot_data),
    ):
        if value is not None:
            config[flag] = value

    for name in _AREA_FLAGS + _EXTRA_FIELDS:
        value = extra.get(name)
        if value is not None:
            config[name] = value

    unknown = set(extra) - set(_AREA_FLAGS) - set(_EXTRA_FIELDS)
    if unknown:
        raise ValueError(
            f"Unknown validation option(s): {sorted(unknown)}. "
            f"Valid: {sorted(_AREA_FLAGS + _EXTRA_FIELDS)}"
        )
    return config


class ValidationResource:
    def __init__(self, client):
        self._client = client

    def run(
        self,
        symbol: str,
        date: str,
        sim_ids: list[str],
        ticksize: float = 1.0,
        run_metrics: bool = None,
        run_impact: bool = None,
        run_inception_distances: bool = True,
        run_stylised_facts: bool = None,
        plot_data: bool = None,
        n_levels: int = 10,
        l2_only: bool = False,
        provider: str = None,
        exchange: str = None,
        statistical: bool = None,
        stylised_facts: bool = None,
        impact: bool = None,
        volume_correlation: bool = None,
        fid: bool = None,
        mind: bool = None,
        lob: bool = None,
        sample_period: str = None,
        match_generated_sample: bool = None,
        plots=None,
        historical_output: bool = None,
    ) -> dict:
        """Submit a validation job.

        Compares simulation output against historical market data using
        distributional distance metrics (L1, Wasserstein), impact response
        curves, Cont stylised facts, and the MIND/FID inception distances.

        Historical data is fetched automatically based on symbol and date.
        Simulation data is fetched from each sim_id's sim_data.parquet.

        Args:
            symbol: Trading symbol (e.g. "700.HK")
            date: Calibration date in YYYY-MM-DD format (e.g. "2025-09-01")
            sim_ids: List of simulation IDs to validate (max 25)
            ticksize: Tick size for the symbol
            run_metrics: Compute L1/Wasserstein distributional distances
                (None = tier default)
            run_impact: Compute Bouchaud impact response curves for each
                simulated run (None = tier default). Runs on every tier as of
                pulse 2.17.0 / pulse-api-pod 1.62.0; the historical curve is
                additionally included on demo (plot_data) jobs. Older API
                deployments only compute it when plot_data is on.
            run_inception_distances: Compute MIND *and* FID on DeepLOB
                embeddings (default True). One flag gates both — they share a
                single embedding pass. Sent as the API's ``run_fid`` field.
                Scores are returned to every validation tier (API >= 1.56.0;
                demo-only before that).
            run_stylised_facts: Compute the 11 Cont stylised facts
                (None = tier default)
            plot_data: Store the raw data behind every plot — distribution
                histograms, full stylised-fact payloads, impact curves.
                **Demo tier only**; an explicit True from any other tier is
                rejected with 403. When off, the job returns distances and the
                per-fact verdicts only.
            n_levels: Number of L2 book levels to use. The inception distances
                need all 10.
            l2_only: Restrict to metrics that need only bid/ask price+size.
                Disables the impact response.
            provider: Data provider (e.g. "omd"). Defaults to the prefix parsed
                from sim_ids[0].
            exchange: Exchange protocol (e.g. "hkex_securities"). Defaults to
                the prefix parsed from sim_ids[0].

        Returns:
            dict with job_id, status, message
        """
        config = _build_config(
            run_metrics, run_impact, run_inception_distances,
            run_stylised_facts, plot_data, n_levels, l2_only,
            statistical=statistical,
            stylised_facts=stylised_facts,
            impact=impact,
            volume_correlation=volume_correlation,
            fid=fid,
            mind=mind,
            lob=lob,
            sample_period=sample_period,
            match_generated_sample=match_generated_sample,
            plots=plots,
            historical_output=historical_output,
        )

        payload = {
            "symbol": symbol,
            "date": date,
            "sim_ids": sim_ids,
            "ticksize": ticksize,
            "config": config,
        }
        if provider is not None:
            payload["provider"] = provider
        if exchange is not None:
            payload["exchange"] = exchange

        return self._client._request("POST", RUN_PATH, json=payload)

    def run_upload(
        self,
        symbol: str,
        date: str,
        provider: str,
        exchange: str,
        sim_files: list,
        ticksize: float = 1.0,
        run_metrics: bool = None,
        run_impact: bool = None,
        run_inception_distances: bool = True,
        run_stylised_facts: bool = None,
        plot_data: bool = None,
        n_levels: int = 10,
        l2_only: bool = False,
        statistical: bool = None,
        stylised_facts: bool = None,
        impact: bool = None,
        volume_correlation: bool = None,
        fid: bool = None,
        mind: bool = None,
        lob: bool = None,
        sample_period: str = None,
        match_generated_sample: bool = None,
        plots=None,
        historical_output: bool = None,
    ) -> dict:
        """Submit a validation job from simulation files you hold yourself.

        Same scoring as run(), for output that is not stored in Pulse —
        parquets from your own systems, a local engine build, or a different
        generator entirely. The historical side is still fetched server-side,
        so only the simulated frames are uploaded.

        Args:
            symbol: Trading symbol (e.g. "700.HK")
            date: Calibration date in YYYY-MM-DD format
            provider: Data provider (e.g. "omd"). Required — with no sim_ids
                to parse it from, it is the only way to identify the
                historical day.
            exchange: Exchange protocol (e.g. "hkex_securities"). Required,
                same reason.
            sim_files: 1-25 simulated frames, each either a path to a parquet
                file or a ``(filename, bytes)`` pair for frames already in
                memory.
            ticksize: Tick size for the symbol.

        The run flags mean exactly what they mean on run().

        Returns:
            dict with job_id, status, message

        Raises:
            ValueError: before any request, if sim_files is empty or has more
                than 25 entries.
        """
        if not sim_files:
            raise ValueError("sim_files is empty — supply 1 to 25 files")
        if len(sim_files) > MAX_SIM_FILES:
            raise ValueError(
                f"{len(sim_files)} sim_files — the API accepts at most "
                f"{MAX_SIM_FILES} per validation job"
            )

        config = _build_config(
            run_metrics, run_impact, run_inception_distances,
            run_stylised_facts, plot_data, n_levels, l2_only,
            statistical=statistical,
            stylised_facts=stylised_facts,
            impact=impact,
            volume_correlation=volume_correlation,
            fid=fid,
            mind=mind,
            lob=lob,
            sample_period=sample_period,
            match_generated_sample=match_generated_sample,
            plots=plots,
            historical_output=historical_output,
        )

        files = []
        for index, entry in enumerate(sim_files):
            filename, content = _frame_to_parquet(entry, index)
            files.append(
                ("sim_files", (filename, content, "application/octet-stream"))
            )

        data = {
            "symbol": symbol,
            "date": date,
            "provider": provider,
            "exchange": exchange,
            "ticksize": str(ticksize),
            "config": json.dumps(config),
        }
        return self._client._request("POST", UPLOAD_PATH, files=files, data=data)

    def get_job(self, job_id: str) -> dict:
        """Get validation job status and results.

        Args:
            job_id: The job ID returned by run()

        Returns:
            dict with:
            - status: "pending", "running", "completed", or "failed"
            - distances: {metric: {l1: [...], w: [...]}} — every entitled tier
            - stylised_fact_verdicts: {fact: {historical: bool | None,
              simulated: [bool | None, ...]}} — every entitled tier
            - mind_scores: one Monge Inception Distance per sim run, in sim_ids
              order; None where a run could not be embedded. Every validation
              tier (API >= 1.56.0)
            - fid_scores: one Frechet Inception Distance per sim run, same
              ordering and tier rule. Since pulse-check 1.8.0 this is the
              embedding-space FID — not comparable with values stored by older
              jobs
            - impact_response: Bouchaud response curves — lags and events are
              the axes, and simulated holds one {ys, ci_low, ci_high} block
              per run, indexed [event][lag]. Every tier (pulse-api-pod >=
              1.62.0); the historical block appears on demo plot_data jobs only
            - impact_response_error: set when the impact pass was requested
              but failed, so a null impact_response can be told apart from one
              never asked for
            - distributions / stylised_facts: the full historical-derived
              payloads. Demo tier, plot_data jobs only
            - plots: {distributions: [...], distances: [...],
              impact_response: [...]} of {name, content_base64}
            - metadata: dict with run parameters
            - error: error message (when failed)

        Lower MIND/FID = closer to the historical day. Neither is meaningful as
        a bare number — see inception_distances() for how to read them.
        """
        return self._client._request("GET", f"{JOBS_PATH}/{job_id}")

    def list_jobs(self, limit: int = 50) -> dict:
        """List validation jobs for the current user.

        Args:
            limit: Max number of jobs to return (default 50, max 200)

        Returns:
            dict with jobs list and total count
        """
        return self._client._request("GET", JOBS_PATH, params={"limit": limit})

    def run_pipeline(
        self,
        symbol: str,
        date: str,
        sim_ids: list[str],
        ticksize: float = 1.0,
        run_metrics: bool = None,
        run_impact: bool = None,
        run_inception_distances: bool = True,
        run_stylised_facts: bool = None,
        plot_data: bool = None,
        n_levels: int = 10,
        l2_only: bool = False,
        provider: str = None,
        exchange: str = None,
        poll_interval: float = 3.0,
        timeout: float = 600.0,
        statistical: bool = None,
        stylised_facts: bool = None,
        impact: bool = None,
        volume_correlation: bool = None,
        fid: bool = None,
        mind: bool = None,
        lob: bool = None,
        sample_period: str = None,
        match_generated_sample: bool = None,
        plots=None,
        historical_output: bool = None,
    ) -> dict:
        """Submit a validation job and block until it completes.

        Combines run() + polling get_job() into a single call.
        Prints progress to stderr.

        Args:
            symbol: Trading symbol (e.g. "700.HK")
            date: Calibration date in YYYY-MM-DD format
            sim_ids: List of simulation IDs to validate (max 25)
            ticksize: Tick size for the symbol
            run_metrics: Compute L1/Wasserstein distances (None = tier default)
            run_impact: Compute impact response curves (None = tier default)
            run_inception_distances: Compute MIND *and* FID on DeepLOB
                embeddings (default True) — one flag gates both
            run_stylised_facts: Compute the Cont stylised facts
                (None = tier default)
            plot_data: Store the raw plottable data (demo tier only)
            n_levels: Number of L2 book levels to use
            l2_only: Restrict to L2-only metrics
            provider: Data provider; defaults to the sim_id prefix
            exchange: Exchange protocol; defaults to the sim_id prefix
            poll_interval: Seconds between status checks (default 3)
            timeout: Max seconds to wait (default 600)

        Returns:
            dict with full validation results — see get_job() for the fields

        Raises:
            RuntimeError: If the validation job fails
            TimeoutError: If the job doesn't complete within timeout
        """
        import sys

        job = self.run(
            symbol=symbol,
            date=date,
            sim_ids=sim_ids,
            ticksize=ticksize,
            run_metrics=run_metrics,
            run_impact=run_impact,
            run_inception_distances=run_inception_distances,
            run_stylised_facts=run_stylised_facts,
            plot_data=plot_data,
            n_levels=n_levels,
            l2_only=l2_only,
            provider=provider,
            exchange=exchange,
            statistical=statistical,
            stylised_facts=stylised_facts,
            impact=impact,
            volume_correlation=volume_correlation,
            fid=fid,
            mind=mind,
            lob=lob,
            sample_period=sample_period,
            match_generated_sample=match_generated_sample,
            plots=plots,
            historical_output=historical_output,
        )
        job_id = job["job_id"]
        print(f"Validation job submitted: {job_id}", file=sys.stderr)

        start = time.time()
        while True:
            result = self.get_job(job_id)
            status = result["status"]

            if status == "completed":
                elapsed = time.time() - start
                print(f"Completed in {elapsed:.1f}s", file=sys.stderr)
                return result
            elif status == "failed":
                raise RuntimeError(f"Validation failed: {result.get('error')}")

            if time.time() - start > timeout:
                raise TimeoutError(
                    f"Validation job {job_id} timed out after {timeout}s"
                )

            time.sleep(poll_interval)

    def inception_distances(
        self,
        symbol: str,
        date: str,
        sim_ids: list[str],
        ticksize: float = 1.0,
        n_levels: int = 10,
        provider: str = None,
        exchange: str = None,
        poll_interval: float = 3.0,
        timeout: float = 600.0,
    ) -> dict:
        """MIND and FID for each simulation, and nothing else.

        A focused shortcut over run_pipeline(): keeps the inception distances
        on and forces every other pass off, so the job does one DeepLOB embedding pass
        and skips the metric, impact and stylised-fact work.

        Both metrics are computed on 96-dim DeepLOB embeddings of 100-row L2
        windows and need 10 book levels in the data.

        Args:
            symbol: Trading symbol (e.g. "700.HK")
            date: Calibration date in YYYY-MM-DD format
            sim_ids: List of simulation IDs to score (max 25)
            ticksize: Tick size for the symbol
            n_levels: Number of L2 book levels (10 required for the embeddings)
            provider: Data provider; defaults to the sim_id prefix
            exchange: Exchange protocol; defaults to the sim_id prefix
            poll_interval: Seconds between status checks
            timeout: Max seconds to wait

        Returns:
            dict with:
            - mind: list of MIND scores, one per sim_id, None where a run could
              not be embedded
            - fid: list of FID scores, same ordering and convention
            - sim_ids: the ids, so scores can be zipped back to their runs
            - job_id: the underlying validation job

        Raises:
            RuntimeError: If the job fails, or if the scores come back empty —
                which means the pipeline skipped them (missing torch, fewer
                than 10 levels, unreachable checkpoint), or the API predates
                1.56.0 and the key is not demo tier; both are silent in the
                raw response.

        Interpreting the scores:
            Lower = closer to the historical day, but neither number means
            anything on its own — only relative to a noise floor. Score a
            real-vs-real control too (two slices of genuine market data) and
            read a generator as a multiple of that floor. ~1x means the metric
            cannot separate it from ordinary intraday variation.
        """
        result = self.run_pipeline(
            symbol=symbol,
            date=date,
            sim_ids=sim_ids,
            ticksize=ticksize,
            run_inception_distances=True,
            run_metrics=False,
            run_impact=False,
            run_stylised_facts=False,
            n_levels=n_levels,
            provider=provider,
            exchange=exchange,
            poll_interval=poll_interval,
            timeout=timeout,
        )

        mind = result.get("mind_scores")
        fid = result.get("fid_scores")
        if not mind and not fid:
            raise RuntimeError(
                "no inception distances in the response. Either the pipeline "
                "skipped them (torch missing, fewer than 10 book levels, or "
                "the DeepLOB checkpoint unreachable), or the API predates "
                "1.56.0 and this key is not demo tier."
            )

        return {
            "mind": mind,
            "fid": fid,
            "sim_ids": list(sim_ids),
            "job_id": result.get("job_id"),
        }

    def display_plots(self, result: dict) -> "PlotDisplay":
        """Return a PlotDisplay object for displaying validation plots.

        Usage:
            plots = client.validation.display_plots(result)
            plots.distributions()    # show distribution histograms
            plots.distances()        # show spider plots
            plots.impact_response()  # show impact response plots

        Args:
            result: The result dict from run_pipeline() or get_job()
        """
        return PlotDisplay(result)


class PlotDisplay:
    """Displays categorized validation plots inline in Jupyter notebooks."""

    def __init__(self, result: dict):
        plots = result.get("plots") or {}
        self._distributions = plots.get("distributions", [])
        self._distances = plots.get("distances", [])
        self._impact_response = plots.get("impact_response", [])

    def _show(self, plot_list, title):
        from IPython.display import display, Image

        if not plot_list:
            print(f"No {title} plots available")
            return

        for plot in plot_list:
            print(f"\n--- {plot['name']} ---")
            display(Image(data=base64.b64decode(plot["content_base64"])))

    def distributions(self):
        """Display distribution histogram plots."""
        self._show(self._distributions, "distribution")

    def distances(self):
        """Display spider plots (L1 and Wasserstein distances)."""
        self._show(self._distances, "distance")

    def impact_response(self):
        """Display impact response plots."""
        self._show(self._impact_response, "impact response")

    def all(self):
        """Display all plots."""
        self.distances()
        self.distributions()
        self.impact_response()
