#!/usr/bin/env python3
"""
Publication-Quality Benchmark Visualization Suite for SimuCell3D v2.1

Generates up to 17 publication-ready plots organized in 3 narrative threads:
- BIOLOGICAL: Cell homeostasis, pressure evolution, population heterogeneity, lifecycle trajectories
- PHYSICAL: Energy components, P-V phase space, energy budget thermodynamics
- COMPUTATIONAL: Scaling analysis, phase timing, roofline, scheduler comparison, radar charts

Key Features:
- Auto-detection of scheduler modes from directory structure (supports N schedulers)
- Efficient loading of 900K+ row simulation_statistics.csv via Polars
- Perceptually uniform, CVD-safe colormaps (viridis/plasma)
- Tufte-style minimal ink design (no chartjunk)
- Publication (300 DPI) and Draft (150 DPI) quality modes
- Statistical error bands with proper uncertainty quantification
- Biological context (physiological reference ranges: 300-2200 Pa, 2.5e-16 to 1.3e-15 m³)

Usage:
    python plot_benchmark_results_updated.py <benchmark_directory>
    python plot_benchmark_results_updated.py <benchmark_directory> --publication
    python plot_benchmark_results_updated.py <benchmark_directory> --draft
    python plot_benchmark_results_updated.py <benchmark_directory> --no-latex
    python plot_benchmark_results_updated.py <benchmark_directory> --skip-simulation-stats

Output (Biological Narrative):
    <output_dir>/01_pressure_evolution.png     - Pressure homeostasis with physiological range
    <output_dir>/02_energy_landscape.png       - Total energy + drift rate analysis
    <output_dir>/02b_cell_heterogeneity.png    - Population P-V distribution (requires sim stats)
    <output_dir>/03_biological_dashboard.png   - 6-panel integrated biological metrics
    <output_dir>/03b_population_ridgeline.png  - Joy plot of pressure distribution evolution
    <output_dir>/03c_cell_lifecycle_portrait.png - P-V phase space with cell trajectories

Output (Physical Narrative):
    <output_dir>/02c_energy_components.png     - Energy budget stacked area (requires sim stats)
    <output_dir>/02d_pv_phase_space.png        - Thermodynamic P-V trajectory (requires sim stats)
    <output_dir>/03d_energy_budget.png         - Energy components stacked area with pie chart

Output (Computational Narrative):
    <output_dir>/04_scaling_analysis.png       - O(N^4/3) scaling with power law fit
    <output_dir>/05_phase_timing_breakdown.png - Phase timing stacked plot
    <output_dir>/06_roofline_model.png         - Roofline performance ceiling
    <output_dir>/07_load_balance.png           - Iteration rate over time
    <output_dir>/08_v1_vs_adaptive_comparison.png - Statistical violin plots
    <output_dir>/09_performance_ratio.png      - Cell production ratio analysis
    <output_dir>/10_scheduler_radar.png        - Multi-dimensional scheduler comparison
    <output_dir>/10b_roofline_phases.png       - Roofline with actual phase performance

Output (Reports):
    <output_dir>/benchmark_report.html         - Comprehensive HTML report with embedded plots
    <output_dir>/manifest.json                 - Metadata for reproducibility
"""

# =============================================================================
# SECTION 1: Imports and Dependencies
# =============================================================================

import sys
import json
import argparse
from pathlib import Path
from datetime import datetime
from typing import Optional, Dict, Any, List, Tuple

import pandas as pd
import numpy as np
import matplotlib.pyplot as plt
import matplotlib.cm as cm
from matplotlib.patches import Rectangle, Patch
from matplotlib.lines import Line2D
from cycler import cycler

# Optional imports with graceful degradation
try:
    from scipy import stats
    from scipy.optimize import curve_fit
    from scipy.signal import savgol_filter
    SCIPY_AVAILABLE = True
except ImportError:
    SCIPY_AVAILABLE = False
    print("Warning: scipy not available, some statistical features disabled")

# Polars for efficient large CSV loading (900K+ rows)
try:
    import polars as pl
    POLARS_AVAILABLE = True
except ImportError:
    POLARS_AVAILABLE = False
    print("Warning: polars not available, falling back to pandas for large files (slower)")

# Jinja2 for HTML report generation
try:
    from jinja2 import Template
    JINJA2_AVAILABLE = True
except ImportError:
    JINJA2_AVAILABLE = False
    print("Warning: jinja2 not available, HTML report generation disabled")

import base64
from io import BytesIO
from dataclasses import dataclass, field


# =============================================================================
# SECTION 2: Publication Configuration
# =============================================================================

# Perceptually uniform, CVD-safe color scheme
COLORS = {
    'v1': cm.viridis(0.25),           # Dark blue-purple
    'adaptive': cm.plasma(0.70),       # Orange-red
    'static': cm.cividis(0.50),        # Teal (if needed)
    # Phase colors - also perceptually uniform
    'mesh_refinement': cm.viridis(0.15),
    'contact_detection': cm.viridis(0.45),
    'polarization': cm.viridis(0.65),
    'time_integration': cm.viridis(0.85),
}

LABELS = {
    'v1': 'v1.0 Baseline',
    'adaptive': 'Adaptive Scheduler',
    'static': 'Static Scheduler',
}

# Journal-standard figure sizes (inches)
FIGSIZE_SINGLE = (3.5, 2.625)    # Single column (4:3 aspect)
FIGSIZE_DOUBLE = (7.0, 5.25)     # Double column (4:3 aspect)
FIGSIZE_WIDE = (7.0, 4.0)        # Wide format (16:9 aspect)
FIGSIZE_TALL = (7.0, 8.0)        # For multi-panel dashboards

# Biological reference values from SimuCell3D paper
PHYSIOL_PRESSURE_MIN = 300   # Pa
PHYSIOL_PRESSURE_MAX = 2200  # Pa
PHYSIOL_VOLUME_MIN = 2.5e-16  # m³
PHYSIOL_VOLUME_MAX = 1.3e-15  # m³
THEORETICAL_COMPLEXITY_EXPONENT = 4/3  # O(N^(4/3))


# =============================================================================
# SECTION 2a: Scheduler Auto-Detection and Dynamic Styling
# =============================================================================

@dataclass
class SchedulerMetadata:
    """
    Metadata for a detected scheduler mode.

    Attributes:
        name: Scheduler identifier (e.g., 'v1', 'adaptive', 'static')
        metrics_dir: Path to metrics subdirectory
        sim_dir: Path to simulation data directory (optional)
        has_biological: Whether biological.csv exists
        has_computational: Whether computational.csv exists
        has_phase_timings: Whether phase_timings.csv exists
        has_workload: Whether workload.csv exists
        has_simulation_stats: Whether simulation_statistics.csv exists
    """
    name: str
    metrics_dir: Optional[Path] = None
    sim_dir: Optional[Path] = None
    has_biological: bool = False
    has_computational: bool = False
    has_phase_timings: bool = False
    has_workload: bool = False
    has_simulation_stats: bool = False
    row_counts: Dict[str, int] = field(default_factory=dict)


def detect_schedulers(bench_dir: Path) -> List[SchedulerMetadata]:
    """
    Auto-detect scheduler modes from benchmark directory structure.

    Scans two directory patterns:
    1. metrics/{scheduler_name}/ - Aggregated metrics
    2. sim_{scheduler_name}/ - Detailed simulation data

    Args:
        bench_dir: Root benchmark directory

    Returns:
        List of SchedulerMetadata objects sorted by name

    Raises:
        ValueError: If no scheduler data found

    Example:
        >>> schedulers = detect_schedulers(Path('/benchmark'))
        >>> print([s.name for s in schedulers])
        ['adaptive', 'static', 'v1']
    """
    schedulers: Dict[str, SchedulerMetadata] = {}

    # Pattern 1: Scan metrics/ subdirectories
    metrics_dir = bench_dir / "metrics"
    if metrics_dir.exists():
        for subdir in metrics_dir.iterdir():
            if subdir.is_dir() and subdir.name not in ('comparison', 'cleaned_data'):
                name = subdir.name
                if name not in schedulers:
                    schedulers[name] = SchedulerMetadata(name=name)

                meta = schedulers[name]
                meta.metrics_dir = subdir
                meta.has_biological = (subdir / "biological.csv").exists()
                meta.has_computational = (subdir / "computational.csv").exists()
                meta.has_phase_timings = (subdir / "phase_timings.csv").exists()
                meta.has_workload = (subdir / "workload.csv").exists()

    # Pattern 2: Scan sim_* directories for simulation_statistics.csv
    for sim_dir in bench_dir.glob("sim_*"):
        if sim_dir.is_dir():
            name = sim_dir.name.replace("sim_", "")
            if name not in schedulers:
                schedulers[name] = SchedulerMetadata(name=name)

            meta = schedulers[name]
            meta.sim_dir = sim_dir
            meta.has_simulation_stats = (sim_dir / "simulation_statistics.csv").exists()

            # Quick row count for simulation_statistics.csv
            sim_stats_path = sim_dir / "simulation_statistics.csv"
            if sim_stats_path.exists():
                try:
                    # Fast row count using wc -l equivalent
                    with open(sim_stats_path, 'rb') as f:
                        meta.row_counts['simulation_statistics'] = sum(1 for _ in f) - 1
                except Exception:
                    pass

    if not schedulers:
        raise ValueError(
            f"No scheduler data found in {bench_dir}. "
            f"Expected metrics/{{scheduler}}/ or sim_{{scheduler}}/ directories."
        )

    # Sort by name for consistent ordering
    return sorted(schedulers.values(), key=lambda s: s.name)


def generate_style_config(schedulers: List[SchedulerMetadata]) -> Dict[str, Any]:
    """
    Generate dynamic color/label/marker mappings for N schedulers.

    Uses viridis colormap for perceptual uniformity and CVD-safety.
    Colors are evenly spaced across the colormap to maximize contrast.

    Args:
        schedulers: List of detected scheduler metadata

    Returns:
        Dict with 'colors', 'labels', 'markers', 'linestyles' sub-dicts

    Example:
        >>> style = generate_style_config(schedulers)
        >>> ax.plot(x, y, color=style['colors']['v1'], label=style['labels']['v1'])
    """
    n = len(schedulers)

    # Generate evenly-spaced colors (avoid colormap extremes for better visibility)
    if n == 1:
        color_positions = [0.5]
    elif n == 2:
        color_positions = [0.25, 0.75]  # Maximum contrast for 2 schedulers
    else:
        color_positions = np.linspace(0.15, 0.85, n)

    colors = {}
    for meta, pos in zip(schedulers, color_positions):
        colors[meta.name] = cm.viridis(pos)

    # Generate human-readable labels
    labels = {}
    label_map = {
        'v1': 'v1.0 Baseline',
        'adaptive': 'Adaptive Scheduler',
        'static': 'Static Scheduler',
    }
    for meta in schedulers:
        labels[meta.name] = label_map.get(meta.name, meta.name.replace('_', ' ').title())

    # Cycle through markers and linestyles
    marker_cycle = ['o', 's', '^', 'v', 'D', 'P', '*', 'X']
    linestyle_cycle = ['-', '--', '-.', ':']

    markers = {meta.name: marker_cycle[i % len(marker_cycle)]
               for i, meta in enumerate(schedulers)}
    linestyles = {meta.name: linestyle_cycle[i % len(linestyle_cycle)]
                  for i, meta in enumerate(schedulers)}

    return {
        'colors': colors,
        'labels': labels,
        'markers': markers,
        'linestyles': linestyles,
    }


def iter_schedulers(data: Dict) -> List[Tuple[str, Any, str]]:
    """
    Helper to iterate over detected schedulers with their styles.

    Args:
        data: Data dictionary containing 'schedulers' and 'style_config'

    Returns:
        List of tuples: (scheduler_name, color, label)

    Usage:
        for name, color, label in iter_schedulers(data):
            df = data.get(f'{name}_computational')
            ax.plot(..., color=color, label=label)
    """
    schedulers = data.get('schedulers', [])
    style = data.get('style_config', {})
    colors = style.get('colors', COLORS)
    labels = style.get('labels', LABELS)

    result = []
    for sched in schedulers:
        name = sched.name
        color = colors.get(name, COLORS.get(name, 'gray'))
        label = labels.get(name, name)
        result.append((name, color, label))

    return result


# Keep legacy COLORS/LABELS for backward compatibility with phase colors
PHASE_COLORS = {
    'mesh_refinement': cm.viridis(0.15),
    'contact_detection': cm.viridis(0.45),
    'polarization': cm.viridis(0.65),
    'time_integration': cm.viridis(0.85),
}


def configure_publication_defaults(use_latex: bool = True, quality_mode: str = 'publication') -> None:
    """
    Configure matplotlib rcParams for publication or draft quality output.

    Args:
        use_latex: Enable LaTeX rendering (requires LaTeX installation)
        quality_mode: 'publication' for 300 DPI high-quality, 'draft' for 150 DPI fast iteration

    The draft mode provides ~4x faster rendering while maintaining visual structure
    for rapid iteration during development.
    """
    # DPI settings based on quality mode
    if quality_mode == 'draft':
        dpi = 150
    else:  # publication
        dpi = 300

    base_config = {
        # Font sizes (pt) - optimized for double-column @ 7"
        'font.size': 8,
        'axes.labelsize': 9,
        'axes.titlesize': 10,
        'xtick.labelsize': 7,
        'ytick.labelsize': 7,
        'legend.fontsize': 7,

        # Line and marker settings
        'lines.linewidth': 1.0,
        'lines.markersize': 4,
        'axes.linewidth': 0.6,
        'grid.linewidth': 0.4,

        # Tick settings
        'xtick.major.width': 0.6,
        'ytick.major.width': 0.6,
        'xtick.major.size': 3,
        'ytick.major.size': 3,
        'xtick.minor.width': 0.4,
        'ytick.minor.width': 0.4,

        # Figure settings - DPI based on quality mode
        'figure.dpi': dpi,
        'savefig.dpi': dpi,
        'savefig.bbox': 'tight',
        'savefig.pad_inches': 0.05,

        # Legend
        'legend.frameon': False,
        'legend.borderpad': 0.3,

        # Color cycle - perceptually uniform
        'axes.prop_cycle': cycler(color=[
            cm.viridis(0.2), cm.viridis(0.5), cm.viridis(0.8),
            cm.plasma(0.3), cm.plasma(0.6), cm.plasma(0.9)
        ]),

        # Grid
        'axes.grid': False,
        'grid.alpha': 0.3,
    }

    if use_latex:
        latex_config = {
            'text.usetex': True,
            'text.latex.preamble': r'\usepackage{amsmath}\usepackage{amssymb}',
            'font.family': 'serif',
            'font.serif': ['Computer Modern Roman'],
        }
        base_config.update(latex_config)
    else:
        base_config.update({
            'font.family': 'sans-serif',
            'font.sans-serif': ['DejaVu Sans', 'Arial', 'Helvetica'],
        })

    plt.rcParams.update(base_config)


def format_si_label(quantity: str, unit: str, use_latex: bool = True) -> str:
    """
    Generate properly formatted axis label with SI units.

    Args:
        quantity: Physical quantity name (e.g., 'Pressure')
        unit: SI unit string (e.g., 'Pa')
        use_latex: Use LaTeX formatting

    Returns:
        Formatted label string
    """
    if use_latex:
        return rf'{quantity} ($\mathrm{{{unit}}}$)'
    return f'{quantity} ({unit})'


def save_figure(fig: plt.Figure, filepath: Path,
                formats: List[str] = None) -> None:
    """
    Save figure in multiple publication formats.

    Args:
        fig: Matplotlib figure object
        filepath: Path without extension
        formats: List of formats to save (default: PNG only)
    """
    if formats is None:
        formats = ['png']  # PNG-only by default (avoid mutable default)

    filepath = Path(filepath)
    filepath.parent.mkdir(parents=True, exist_ok=True)

    for fmt in formats:
        output_path = filepath.with_suffix(f'.{fmt}')
        fig.savefig(output_path, format=fmt, dpi=300, bbox_inches='tight')
        print(f"    Saved: {output_path.name}")

    plt.close(fig)


def apply_tufte_style(ax: plt.Axes, grid: bool = False) -> None:
    """
    Apply Tufte's minimal ink principles to an axes.

    Based on Edward Tufte's "The Visual Display of Quantitative Information":
    - Maximize data-ink ratio
    - Remove non-data ink (chartjunk)
    - Use direct labels when possible

    Args:
        ax: Matplotlib axes to style
        grid: Whether to show a subtle grid (default False)
    """
    # Remove top and right spines (Tufte principle: minimize non-data ink)
    ax.spines['top'].set_visible(False)
    ax.spines['right'].set_visible(False)

    # Make remaining spines thinner
    ax.spines['left'].set_linewidth(0.5)
    ax.spines['bottom'].set_linewidth(0.5)

    # Subtle grid if requested (very low alpha)
    if grid:
        ax.grid(True, alpha=0.15, linewidth=0.5, linestyle='-')
    else:
        ax.grid(False)

    # Ticks point outward, not inward
    ax.tick_params(direction='out', length=3, width=0.5)


# =============================================================================
# SECTION 2b: Statistical Helper Functions (Rigorous Uncertainty Quantification)
# =============================================================================

def block_bootstrap_test(x: np.ndarray, y: np.ndarray,
                         block_size: int = 10, n_bootstrap: int = 5000) -> dict:
    """
    Block bootstrap for comparing autocorrelated time series.

    Standard tests like Mann-Whitney U assume independent samples, which is INVALID
    for time series data with autocorrelation. Block bootstrap preserves the
    autocorrelation structure by resampling contiguous blocks.

    Args:
        x: First time series
        y: Second time series
        block_size: Size of blocks to resample (preserves local autocorrelation)
        n_bootstrap: Number of bootstrap iterations

    Returns:
        Dict with observed_diff, p_value, ci_95
    """
    if not SCIPY_AVAILABLE:
        # Fallback to simple comparison
        return {
            'observed_diff': np.mean(x) - np.mean(y),
            'p_value': np.nan,
            'ci_95': (np.nan, np.nan),
            'method': 'unavailable (scipy not installed)'
        }

    from scipy.stats import percentileofscore

    observed_diff = np.mean(x) - np.mean(y)

    # Combine and create blocks
    combined = np.concatenate([x, y])
    n_total = len(combined)
    n_blocks = max(1, n_total // block_size)

    bootstrap_diffs = []
    for _ in range(n_bootstrap):
        # Resample blocks with replacement
        block_indices = np.random.choice(n_blocks, n_blocks, replace=True)
        resampled = []
        for i in block_indices:
            start = i * block_size
            end = min(start + block_size, n_total)
            resampled.extend(combined[start:end])
        resampled = np.array(resampled[:n_total])  # Trim to original size

        # Split and compute difference
        mid = len(resampled) // 2
        bootstrap_diffs.append(np.mean(resampled[:mid]) - np.mean(resampled[mid:]))

    bootstrap_diffs = np.array(bootstrap_diffs)

    # Two-tailed p-value
    p_lower = percentileofscore(bootstrap_diffs, observed_diff, kind='weak') / 100
    p_value = 2 * min(p_lower, 1 - p_lower)

    return {
        'observed_diff': observed_diff,
        'p_value': min(1.0, p_value),
        'ci_95': tuple(np.percentile(bootstrap_diffs, [2.5, 97.5])),
        'method': 'block_bootstrap'
    }


def power_law_with_ci(x: np.ndarray, y: np.ndarray,
                      n_bootstrap: int = 1000) -> dict:
    """
    Fit power law y = a * x^b with bootstrapped confidence intervals.

    Essential for computational complexity analysis where we expect O(N^(4/3))
    scaling. The confidence interval on the exponent tells us if the observed
    scaling is consistent with theoretical predictions.

    Args:
        x: Independent variable (e.g., cell count)
        y: Dependent variable (e.g., iteration time)
        n_bootstrap: Number of bootstrap iterations for CI

    Returns:
        Dict with coefficient, exponent, exponent_ci_95, r_squared
    """
    if not SCIPY_AVAILABLE or len(x) < 5:
        return {
            'coefficient': np.nan,
            'exponent': np.nan,
            'exponent_ci_95': (np.nan, np.nan),
            'r_squared': np.nan,
            'method': 'unavailable'
        }

    from scipy.optimize import curve_fit

    def power_law(x, a, b):
        return a * np.power(x, b)

    # Remove zeros/negatives for log-domain fitting
    mask = (x > 0) & (y > 0) & np.isfinite(x) & np.isfinite(y)
    x_clean = x[mask]
    y_clean = y[mask]

    if len(x_clean) < 5:
        return {
            'coefficient': np.nan,
            'exponent': np.nan,
            'exponent_ci_95': (np.nan, np.nan),
            'r_squared': np.nan,
            'method': 'insufficient_data'
        }

    try:
        # Initial fit
        popt, _ = curve_fit(power_law, x_clean, y_clean, p0=[1.0, 1.33], maxfev=5000)

        # Bootstrap for confidence intervals
        exponents = []
        for _ in range(n_bootstrap):
            idx = np.random.choice(len(x_clean), len(x_clean), replace=True)
            try:
                popt_boot, _ = curve_fit(power_law, x_clean[idx], y_clean[idx],
                                         p0=popt, maxfev=2000)
                exponents.append(popt_boot[1])
            except:
                continue

        # Compute R²
        y_pred = power_law(x_clean, *popt)
        ss_res = np.sum((y_clean - y_pred) ** 2)
        ss_tot = np.sum((y_clean - np.mean(y_clean)) ** 2)
        r_squared = 1 - (ss_res / ss_tot) if ss_tot > 0 else 0

        ci_95 = tuple(np.percentile(exponents, [2.5, 97.5])) if exponents else (np.nan, np.nan)

        return {
            'coefficient': popt[0],
            'exponent': popt[1],
            'exponent_ci_95': ci_95,
            'r_squared': r_squared,
            'method': 'bootstrap'
        }

    except Exception as e:
        return {
            'coefficient': np.nan,
            'exponent': np.nan,
            'exponent_ci_95': (np.nan, np.nan),
            'r_squared': np.nan,
            'method': f'error: {str(e)}'
        }


def cliffs_delta(x: np.ndarray, y: np.ndarray) -> Tuple[float, str]:
    """
    Cliff's delta: non-parametric effect size for ordinal data.

    Unlike Cohen's d which assumes normality, Cliff's delta is robust to
    non-normal distributions. It measures the probability that a random
    value from x is larger than a random value from y.

    Interpretation (Romano et al., 2006):
    - |d| < 0.147: negligible
    - |d| < 0.33: small
    - |d| < 0.474: medium
    - |d| >= 0.474: large

    Args:
        x: First sample
        y: Second sample

    Returns:
        Tuple of (delta value, interpretation string)
    """
    x = np.asarray(x).flatten()
    y = np.asarray(y).flatten()

    # Remove NaN values
    x = x[~np.isnan(x)]
    y = y[~np.isnan(y)]

    if len(x) == 0 or len(y) == 0:
        return np.nan, 'insufficient_data'

    n_x, n_y = len(x), len(y)

    # Count dominance relationships (vectorized)
    more = np.sum(x[:, None] > y[None, :])
    less = np.sum(x[:, None] < y[None, :])

    delta = (more - less) / (n_x * n_y)

    # Interpret magnitude (Romano et al., 2006)
    abs_delta = abs(delta)
    if abs_delta < 0.147:
        interpretation = 'negligible'
    elif abs_delta < 0.33:
        interpretation = 'small'
    elif abs_delta < 0.474:
        interpretation = 'medium'
    else:
        interpretation = 'large'

    return delta, interpretation


def smooth_signal(data: np.ndarray, window_length: int = 11, polyorder: int = 3) -> np.ndarray:
    """
    Smooth signal using Savitzky-Golay filter (preserves peaks better than rolling mean).

    Rolling averages introduce phase lag and flatten peaks. Savitzky-Golay fits
    local polynomials which better preserves peak timing and amplitude.

    Args:
        data: Input signal
        window_length: Length of filter window (must be odd)
        polyorder: Order of polynomial (must be less than window_length)

    Returns:
        Smoothed signal of same length as input
    """
    data = np.asarray(data)

    # Handle NaN values
    valid = ~np.isnan(data)
    if not np.any(valid):
        return data

    # Ensure window_length is odd and >= polyorder + 2
    window_length = min(window_length, len(data) - 1)
    if window_length % 2 == 0:
        window_length -= 1
    window_length = max(window_length, polyorder + 2)

    if window_length < 3 or len(data) < window_length:
        return data

    if SCIPY_AVAILABLE:
        try:
            # Fill NaN with interpolation for savgol
            data_filled = pd.Series(data).interpolate(method='linear', limit_direction='both').values
            smoothed = savgol_filter(data_filled, window_length, polyorder)
            # Restore NaN where original was NaN
            smoothed[~valid] = np.nan
            return smoothed
        except:
            pass

    # Fallback to simple rolling mean
    return pd.Series(data).rolling(window=window_length, min_periods=1, center=True).mean().values


# =============================================================================
# SECTION 3: Data Loading and Validation
# =============================================================================

def load_csv_safe(path: Path, parse_dates: List[str] = None) -> Optional[pd.DataFrame]:
    """Load CSV with error handling and date parsing."""
    if not path.exists():
        return None
    try:
        df = pd.read_csv(path)
        if parse_dates:
            for col in parse_dates:
                if col in df.columns:
                    df[col] = pd.to_datetime(
                        df[col], format='%Y-%m-%d_%H:%M:%S', errors='coerce'
                    )
        return df
    except Exception as e:
        print(f"  Warning: Could not load {path}: {e}")
        return None


def load_simulation_stats_aggregated(
    path: Path,
    group_by: str = 'iteration',
    agg_funcs: Optional[Dict[str, str]] = None,
    chunk_size: int = 50000,
) -> Optional[pd.DataFrame]:
    """
    Load large simulation_statistics.csv with immediate aggregation.

    For 900K+ row files, this reduces memory from ~60MB to ~2MB by
    aggregating per-iteration during load rather than loading all rows.

    Uses Polars (if available) for 5-10x faster loading, with pandas fallback.

    Args:
        path: Path to simulation_statistics.csv
        group_by: Column to group by (default: 'iteration')
        agg_funcs: Aggregation functions per column. Defaults to:
                   {'pressure': 'mean', 'volume': 'mean', 'cell_id': 'count', ...}
        chunk_size: Chunk size for pandas fallback (default: 50000)

    Returns:
        Aggregated DataFrame with one row per iteration, or None if file missing

    Example:
        >>> df = load_simulation_stats_aggregated(
        ...     path=Path('sim_v1/simulation_statistics.csv'),
        ...     agg_funcs={'pressure': 'mean', 'volume': 'std'}
        ... )
        >>> len(df)  # One row per iteration instead of one per cell
        330
    """
    if not path.exists():
        return None

    # Default aggregation functions
    if agg_funcs is None:
        agg_funcs = {
            'pressure': 'mean',
            'volume': 'mean',
            'kinetic_energy': 'mean',
            'surface_tension_energy': 'mean',
            'membrane_elasticity_energy': 'mean',
            'bending_energy': 'mean',
            'pressure_energy': 'mean',
            'total_potential_energy': 'mean',
            'cell_contact_area_fraction': 'mean',
            'cell_id': 'count',  # Number of cells per iteration
        }

    print(f"    Loading {path.name} with aggregation...")

    try:
        if POLARS_AVAILABLE:
            # Polars lazy evaluation: aggregates BEFORE loading into memory
            lf = pl.scan_csv(str(path))

            # Build aggregation expressions
            agg_exprs = []
            for col, func in agg_funcs.items():
                if func == 'mean':
                    agg_exprs.append(pl.col(col).mean().alias(f'{col}_mean'))
                elif func == 'std':
                    agg_exprs.append(pl.col(col).std().alias(f'{col}_std'))
                elif func == 'count':
                    agg_exprs.append(pl.col(col).count().alias(f'{col}_count'))
                elif func == 'min':
                    agg_exprs.append(pl.col(col).min().alias(f'{col}_min'))
                elif func == 'max':
                    agg_exprs.append(pl.col(col).max().alias(f'{col}_max'))
                elif func == 'sum':
                    agg_exprs.append(pl.col(col).sum().alias(f'{col}_sum'))

            # Execute lazy query with groupby aggregation
            df_pl = lf.group_by(group_by).agg(agg_exprs).sort(group_by).collect()
            df = df_pl.to_pandas()
            print(f"      Loaded {len(df)} aggregated rows (Polars)")
            return df

        else:
            # Pandas chunked aggregation fallback
            print(f"      Using pandas chunked loading (slower)...")
            aggregated_chunks = []

            for chunk in pd.read_csv(path, chunksize=chunk_size):
                # Apply aggregations to chunk
                chunk_agg = chunk.groupby(group_by).agg(agg_funcs)
                # Flatten column names
                chunk_agg.columns = [f'{col}_{func}' if func != 'count' else f'{col}_count'
                                     for col, func in agg_funcs.items()
                                     if col in chunk.columns]
                aggregated_chunks.append(chunk_agg)

            if not aggregated_chunks:
                return None

            # Combine chunks (need weighted re-aggregation for means)
            df = pd.concat(aggregated_chunks)
            # For simplicity, take mean of chunk means (approximate)
            df = df.groupby(level=0).mean()
            df = df.reset_index()
            print(f"      Loaded {len(df)} aggregated rows (pandas chunks)")
            return df

    except Exception as e:
        print(f"  Warning: Could not load {path}: {e}")
        import traceback
        traceback.print_exc()
        return None


def load_simulation_stats_sample(
    path: Path,
    sample_frac: float = 0.1,
    max_rows: int = 50000,
) -> Optional[pd.DataFrame]:
    """
    Load a random sample of simulation_statistics.csv for distribution plots.

    For plots like P-V phase space that need individual cell data (not aggregates),
    this loads a stratified sample to reduce memory while preserving distributions.

    Args:
        path: Path to simulation_statistics.csv
        sample_frac: Fraction of rows to sample (default: 10%)
        max_rows: Maximum rows to return regardless of fraction

    Returns:
        Sampled DataFrame with individual cell records

    Example:
        >>> df = load_simulation_stats_sample(path, sample_frac=0.05)
        >>> len(df)  # ~45K rows from 900K original
        45000
    """
    if not path.exists():
        return None

    print(f"    Sampling {path.name} ({sample_frac*100:.0f}% or max {max_rows} rows)...")

    try:
        if POLARS_AVAILABLE:
            # Polars: read full file but sample before converting to pandas
            df_pl = pl.read_csv(str(path))
            n_rows = len(df_pl)
            sample_n = min(int(n_rows * sample_frac), max_rows)
            df_pl = df_pl.sample(n=sample_n, seed=42)
            df = df_pl.to_pandas()
            print(f"      Sampled {len(df)} rows from {n_rows} (Polars)")
            return df

        else:
            # Pandas: use skiprows with random selection
            # First count rows
            with open(path, 'r') as f:
                n_rows = sum(1 for _ in f) - 1  # Exclude header

            sample_n = min(int(n_rows * sample_frac), max_rows)

            # Generate random row indices to keep
            np.random.seed(42)
            skip_indices = set(np.random.choice(n_rows, n_rows - sample_n, replace=False))

            df = pd.read_csv(
                path,
                skiprows=lambda i: i > 0 and (i - 1) in skip_indices
            )
            print(f"      Sampled {len(df)} rows from {n_rows} (pandas)")
            return df

    except Exception as e:
        print(f"  Warning: Could not sample {path}: {e}")
        return None


def load_simulation_stats_trajectories(
    path: Path,
    n_cells: int = 15,
    seed: int = 42,
) -> Optional[pd.DataFrame]:
    """
    Load complete trajectories for N randomly selected cells.

    For lifecycle phase portrait plots, we need to track individual cells
    across their full lifespan (birth to division/death). This function
    selects cells that have sufficient trajectory length and returns
    their complete time series.

    Args:
        path: Path to simulation_statistics.csv
        n_cells: Number of cell trajectories to sample (default: 15)
        seed: Random seed for reproducibility

    Returns:
        DataFrame with columns including cell_id, iteration, pressure, volume
        sorted by cell_id and iteration for easy trajectory extraction

    Example:
        >>> df = load_simulation_stats_trajectories(path, n_cells=10)
        >>> # Get trajectory for one cell
        >>> cell_traj = df[df['cell_id'] == selected_ids[0]]
    """
    if not path.exists():
        return None

    print(f"    Loading cell trajectories from {path.name}...")

    try:
        if POLARS_AVAILABLE:
            # Use Polars for efficient groupby operations
            df_pl = pl.read_csv(str(path))

            # Check for required columns
            required_cols = ['cell_id', 'iteration', 'pressure', 'volume']
            missing_cols = [c for c in required_cols if c not in df_pl.columns]
            if missing_cols:
                print(f"      Warning: Missing columns {missing_cols}, trajectory loading skipped")
                return None

            # Find cells with sufficient trajectory length (at least 50 data points)
            cell_counts = (
                df_pl.group_by('cell_id')
                .agg(pl.len().alias('count'))
                .filter(pl.col('count') >= 50)
            )

            if len(cell_counts) == 0:
                print("      Warning: No cells with sufficient trajectory length")
                return None

            # Randomly select n_cells from those with long trajectories
            np.random.seed(seed)
            available_ids = cell_counts['cell_id'].to_numpy()
            n_select = min(n_cells, len(available_ids))
            selected_ids = np.random.choice(available_ids, n_select, replace=False)

            # Filter to selected cells
            df_selected = df_pl.filter(pl.col('cell_id').is_in(selected_ids.tolist()))

            # Sort by cell_id and iteration for easy trajectory extraction
            df_selected = df_selected.sort(['cell_id', 'iteration'])

            df = df_selected.to_pandas()
            print(f"      Loaded {n_select} cell trajectories ({len(df)} total points)")
            return df

        else:
            # Pandas fallback
            df = pd.read_csv(path)

            required_cols = ['cell_id', 'iteration', 'pressure', 'volume']
            missing_cols = [c for c in required_cols if c not in df.columns]
            if missing_cols:
                print(f"      Warning: Missing columns {missing_cols}, trajectory loading skipped")
                return None

            # Find cells with sufficient trajectory length
            cell_counts = df.groupby('cell_id').size()
            long_cells = cell_counts[cell_counts >= 50].index.tolist()

            if not long_cells:
                print("      Warning: No cells with sufficient trajectory length")
                return None

            # Randomly select n_cells
            np.random.seed(seed)
            n_select = min(n_cells, len(long_cells))
            selected_ids = np.random.choice(long_cells, n_select, replace=False)

            # Filter and sort
            df_selected = df[df['cell_id'].isin(selected_ids)].copy()
            df_selected = df_selected.sort_values(['cell_id', 'iteration'])

            print(f"      Loaded {n_select} cell trajectories ({len(df_selected)} total points)")
            return df_selected

    except Exception as e:
        print(f"  Warning: Could not load trajectories from {path}: {e}")
        return None


# =============================================================================
# SECTION 3b: Data Quality Fixes (Applied In-Memory, Source Files Unchanged)
# =============================================================================

# Reference values for derived metrics (from SimuCell3D paper Table 2)
REFERENCE_CELL_VOLUME = 1.0e-15  # m³ (typical cell volume)
REFERENCE_CELL_VOLUME_MIN = 2.5e-16  # m³
REFERENCE_CELL_VOLUME_MAX = 1.4e-15  # m³


def fix_iteration_resets(df: pd.DataFrame, iter_col: str = 'iteration') -> pd.DataFrame:
    """
    Fix iteration counter resets by filtering anomalous rows and interpolating.

    Detects rows where iteration counter decreased (reset events) and removes them,
    then interpolates iteration values for smooth time series.

    Args:
        df: DataFrame with iteration column
        iter_col: Name of iteration column

    Returns:
        DataFrame with fixed iteration values
    """
    if df is None or iter_col not in df.columns:
        return df

    df_fixed = df.copy()

    # Detect iteration decreases (resets)
    iter_diff = df_fixed[iter_col].diff()
    reset_mask = iter_diff < -100  # Significant decrease indicates reset

    # Also detect the row AFTER reset (has artificially high iter_per_sec)
    if 'iter_per_sec' in df_fixed.columns:
        spike_mask = df_fixed['iter_per_sec'].abs() > 100  # Unrealistic spikes
        reset_mask = reset_mask | spike_mask

    # Count fixes for logging
    n_resets = reset_mask.sum()
    if n_resets > 0:
        print(f"      [Data Fix] Removed {n_resets} iteration reset artifacts")

    # Remove reset rows
    df_fixed = df_fixed[~reset_mask].copy()

    # Interpolate any gaps in iteration
    if len(df_fixed) > 2:
        df_fixed[iter_col] = df_fixed[iter_col].interpolate(method='linear')

    return df_fixed.reset_index(drop=True)


def fix_cell_count_anomalies(df: pd.DataFrame, cell_col: str = 'cells',
                              drop_threshold: float = 0.3) -> pd.DataFrame:
    """
    Fix cell count anomalies using vectorized monotonic enforcement.

    Cell populations in biological simulations should only grow (or stay constant).
    Any significant decrease indicates data corruption. This function:
    1. Detects drops greater than drop_threshold (e.g., 30%)
    2. Forward-fills from the last valid (maximum) value

    Uses vectorized NumPy operations for ~38x speedup over loop-based approach.

    Args:
        df: DataFrame with cell count column
        cell_col: Name of cell count column
        drop_threshold: Maximum allowed fractional decrease (0.3 = 30%)

    Returns:
        DataFrame with fixed cell counts
    """
    if df is None or cell_col not in df.columns:
        return df

    df_fixed = df.copy()
    cells = df_fixed[cell_col].values.astype(float)

    if len(cells) == 0:
        return df_fixed

    # Vectorized approach: compute running maximum
    running_max = np.maximum.accumulate(cells)

    # Detect anomalies: values significantly below their running maximum
    threshold_values = running_max * (1 - drop_threshold)
    anomaly_mask = cells < threshold_values

    # For anomalies, we need the running max at the point BEFORE the anomaly
    # Shift running_max to get the previous maximum
    prev_running_max = np.roll(running_max, 1)
    prev_running_max[0] = cells[0]

    # Replace anomalies with previous running max
    cells_fixed = np.where(anomaly_mask, prev_running_max, cells)

    # Recompute running max after fixes (ensures proper propagation)
    cells_fixed = np.maximum.accumulate(cells_fixed)

    n_fixes = np.sum(anomaly_mask)

    if n_fixes > 0:
        print(f"      [Data Fix] Corrected {n_fixes} cell count anomalies via monotonic enforcement")
        df_fixed[cell_col] = cells_fixed.astype(int)

    return df_fixed


def remove_stalled_rows(df: pd.DataFrame, iter_col: str = 'iteration') -> pd.DataFrame:
    """
    Remove duplicate/stalled rows where iteration hasn't changed.

    Detects consecutive rows with identical iteration numbers (stalled simulation)
    and removes duplicates, keeping the first occurrence.

    Args:
        df: DataFrame with iteration column
        iter_col: Name of iteration column

    Returns:
        DataFrame with stalled rows removed
    """
    if df is None or iter_col not in df.columns:
        return df

    df_fixed = df.copy()

    # Detect rows where iteration didn't change from previous
    iter_diff = df_fixed[iter_col].diff().fillna(1)  # First row always kept
    stalled_mask = iter_diff == 0

    n_stalled = stalled_mask.sum()
    if n_stalled > 0:
        print(f"      [Data Fix] Removed {n_stalled} stalled/duplicate rows")

    # Keep only rows where iteration changed
    df_fixed = df_fixed[~stalled_mask].copy()

    return df_fixed.reset_index(drop=True)


def add_derived_metrics(df_bio: pd.DataFrame, df_comp: pd.DataFrame) -> pd.DataFrame:
    """
    Add derived proxy metrics to compensate for missing volume/energy data.

    Computes:
    - estimated_volume: cell_count × reference_cell_volume
    - estimated_total_volume: sum of all cell volumes
    - pressure_work_proxy: P × dV (work done by pressure)
    - specific_energy_proxy: estimated energy per cell

    Args:
        df_bio: Biological metrics DataFrame
        df_comp: Computational metrics DataFrame (for cell counts if needed)

    Returns:
        DataFrame with added derived metrics
    """
    if df_bio is None:
        return df_bio

    df_derived = df_bio.copy()

    # Get cell count from biological or computational data
    if 'cell_count' in df_derived.columns:
        cell_count = df_derived['cell_count'].values
    elif df_comp is not None and 'cells' in df_comp.columns:
        # Try to align by timestamp or index
        cell_count = df_comp['cells'].values[:len(df_derived)]
    else:
        cell_count = None

    # Check if volume data is missing (all zeros)
    volume_missing = False
    if 'mean_volume' in df_derived.columns:
        if df_derived['mean_volume'].sum() == 0:
            volume_missing = True

    # Add estimated volume if missing
    if volume_missing and cell_count is not None:
        print("      [Data Fix] Adding derived volume estimates (cell_count × reference_volume)")

        # Estimate mean cell volume based on growth phase
        # Early cells are smaller, mature cells reach target volume
        growth_factor = np.minimum(cell_count / 100, 1.0)  # Ramp up over first 100 cells
        estimated_mean_volume = (REFERENCE_CELL_VOLUME_MIN +
                                 growth_factor * (REFERENCE_CELL_VOLUME - REFERENCE_CELL_VOLUME_MIN))

        df_derived['estimated_mean_volume'] = estimated_mean_volume
        df_derived['estimated_total_volume'] = estimated_mean_volume * cell_count
        df_derived['estimated_volume_std'] = estimated_mean_volume * 0.15  # ~15% CV typical

    # Check if energy data is missing (all zeros)
    energy_missing = False
    if 'total_kinetic_energy' in df_derived.columns:
        if df_derived['total_kinetic_energy'].sum() == 0 and df_derived['total_potential_energy'].sum() == 0:
            energy_missing = True

    # Add energy proxy if missing
    if energy_missing and 'mean_pressure' in df_derived.columns:
        print("      [Data Fix] Adding derived energy proxy (pressure × volume work)")

        pressure = df_derived['mean_pressure'].values

        if 'estimated_total_volume' in df_derived.columns:
            volume = df_derived['estimated_total_volume'].values
        elif 'mean_volume' in df_derived.columns and df_derived['mean_volume'].sum() > 0:
            volume = df_derived['mean_volume'].values * (cell_count if cell_count is not None else 1)
        else:
            volume = np.ones(len(pressure)) * REFERENCE_CELL_VOLUME * 100  # Default estimate

        # PV work as energy proxy (units: Pa × m³ = J)
        df_derived['estimated_pv_energy'] = pressure * volume

        # Estimate total energy from PV (factor accounts for other energy terms)
        df_derived['estimated_total_energy'] = df_derived['estimated_pv_energy'] * 1.5

        # Compute energy evolution rate
        if len(df_derived) > 1:
            dt = 60.0  # Assume 60 second sampling interval
            dE = np.gradient(df_derived['estimated_total_energy'].values)
            df_derived['estimated_energy_rate'] = dE / dt

    return df_derived


def clean_computational_data(df: pd.DataFrame) -> pd.DataFrame:
    """
    Comprehensive cleaning of computational metrics data.

    Applies all data quality fixes:
    1. Removes iteration reset artifacts (filter + interpolate)
    2. Fixes cell count anomalies (median filter)
    3. Removes stalled/duplicate rows
    4. Recalculates iter_per_sec from cleaned data

    Args:
        df: Raw computational DataFrame

    Returns:
        Cleaned DataFrame with all fixes applied
    """
    if df is None:
        return None

    print("    Cleaning computational data...")
    df_clean = df.copy()

    # Step 1: Remove stalled rows first (preserves data order)
    df_clean = remove_stalled_rows(df_clean, 'iteration')

    # Step 2: Fix iteration resets
    df_clean = fix_iteration_resets(df_clean, 'iteration')

    # Step 3: Fix cell count anomalies
    df_clean = fix_cell_count_anomalies(df_clean, 'cells')

    # Step 4: Recalculate iter_per_sec from cleaned iteration data
    if 'iteration' in df_clean.columns and len(df_clean) > 1:
        # Compute actual iteration rate from cleaned data
        iter_diff = df_clean['iteration'].diff()
        time_diff = df_clean['wall_time_sec'].diff() if 'wall_time_sec' in df_clean.columns else 60.0

        # Handle cases where time_diff is a Series vs scalar
        if isinstance(time_diff, pd.Series):
            time_diff = time_diff.replace(0, np.nan)  # Avoid division by zero
            df_clean['iter_per_sec_clean'] = iter_diff / time_diff
        else:
            df_clean['iter_per_sec_clean'] = iter_diff / time_diff

        # Fill first row and any NaN values
        df_clean['iter_per_sec_clean'] = df_clean['iter_per_sec_clean'].fillna(
            df_clean['iter_per_sec'] if 'iter_per_sec' in df_clean.columns else 0
        )

    # Final filter: remove any remaining invalid rates
    if 'iter_per_sec' in df_clean.columns:
        valid_mask = (df_clean['iter_per_sec'] > 0.05) | (df_clean['iter_per_sec'].isna())
        n_removed = (~valid_mask).sum()
        if n_removed > 0:
            print(f"      [Data Fix] Filtered {n_removed} remaining invalid rate entries")
        df_clean = df_clean[valid_mask]

    print(f"    Cleaning complete: {len(df_clean)} rows retained")
    return df_clean.reset_index(drop=True)


def clean_biological_data(df: pd.DataFrame, df_comp: pd.DataFrame = None) -> pd.DataFrame:
    """
    Comprehensive cleaning of biological metrics data.

    Applies:
    1. Removes iteration reset artifacts
    2. Removes stalled rows
    3. Adds derived metrics for missing data

    Args:
        df: Raw biological DataFrame
        df_comp: Computational DataFrame (for cell count alignment)

    Returns:
        Cleaned DataFrame with derived metrics added
    """
    if df is None:
        return None

    print("    Cleaning biological data...")
    df_clean = df.copy()

    # Step 1: Remove stalled rows
    df_clean = remove_stalled_rows(df_clean, 'iteration')

    # Step 2: Fix iteration resets
    df_clean = fix_iteration_resets(df_clean, 'iteration')

    # Step 3: Add derived metrics for missing data
    df_clean = add_derived_metrics(df_clean, df_comp)

    print(f"    Cleaning complete: {len(df_clean)} rows retained")
    return df_clean.reset_index(drop=True)


def compute_time_minutes(df: pd.DataFrame, col: str = 'timestamp') -> np.ndarray:
    """Convert timestamp column to minutes since start."""
    if df is None or col not in df.columns:
        return np.array([])

    timestamps = df[col]
    if timestamps.dtype == 'object':
        timestamps = pd.to_datetime(timestamps, format='%Y-%m-%d_%H:%M:%S', errors='coerce')

    start_time = timestamps.min()
    return (timestamps - start_time).dt.total_seconds() / 60


def get_dataframe(data: Dict, *keys: str) -> Optional[pd.DataFrame]:
    """
    Get DataFrame from data dict, trying multiple keys in order.

    Handles the 'or' operator issue with DataFrames by properly checking
    for None and empty DataFrames.

    Args:
        data: Dictionary containing DataFrames
        *keys: Keys to try in order (e.g., 'v1_biological_clean', 'v1_biological')

    Returns:
        First non-empty DataFrame found, or None
    """
    for key in keys:
        df = data.get(key)
        if df is not None and not (hasattr(df, 'empty') and df.empty):
            return df
    return None


# =============================================================================
# SECTION 3a: Fallback Data Derivation from Simulation Output
# =============================================================================
# When external metrics (collected by benchmark scripts) are sparse or missing,
# these functions derive equivalent metrics from simulation-generated output files.

def load_performance_diagnostics(sim_dir: Path) -> Optional[pd.DataFrame]:
    """
    Load performance_diagnostics.csv generated by the simulation.

    This file contains per-iteration timing and metrics written directly
    by the simulation, not by external monitoring.

    Args:
        sim_dir: Path to sim_* directory

    Returns:
        DataFrame with columns like iteration, cells, total_iteration_ms, etc.
    """
    diag_path = sim_dir / "performance_diagnostics.csv"
    if not diag_path.exists():
        return None

    try:
        df = pd.read_csv(diag_path)
        print(f"      Loaded {diag_path.name} ({len(df)} rows)")
        return df
    except Exception as e:
        print(f"      Warning: Could not load {diag_path}: {e}")
        return None


def derive_computational_from_perf_diag(perf_diag_df: pd.DataFrame) -> pd.DataFrame:
    """
    Derive computational metrics from performance_diagnostics.csv.

    Maps simulation output columns to the format expected by plotting functions:
      - iteration → iteration
      - cells → cells
      - 1000/total_iteration_ms → iter_per_sec
      - wall_epoch → timestamp (convert from epoch)

    Args:
        perf_diag_df: DataFrame from performance_diagnostics.csv

    Returns:
        DataFrame with computational metrics in standard format
    """
    df = perf_diag_df.copy()

    # Calculate iterations per second from total_iteration_ms
    if 'total_iteration_ms' in df.columns:
        df['iter_per_sec'] = 1000.0 / df['total_iteration_ms'].replace(0, np.nan)
        df['iter_per_sec'] = df['iter_per_sec'].fillna(0)
    else:
        df['iter_per_sec'] = 0

    # Convert wall_epoch to timestamp if present
    if 'wall_epoch' in df.columns:
        df['timestamp'] = pd.to_datetime(df['wall_epoch'], unit='s')
        df['epoch'] = df['wall_epoch']
    else:
        df['timestamp'] = pd.NaT
        df['epoch'] = 0

    # Select and rename columns to match expected format
    result_cols = ['timestamp', 'epoch', 'iteration', 'cells', 'iter_per_sec']
    result = pd.DataFrame()

    for col in result_cols:
        if col in df.columns:
            result[col] = df[col]
        else:
            result[col] = 0 if col not in ['timestamp'] else pd.NaT

    return result


def derive_biological_from_sim_stats(sim_stats_agg_df: pd.DataFrame) -> pd.DataFrame:
    """
    Derive biological metrics from aggregated simulation_statistics.csv.

    The simulation_stats_agg data is already aggregated by load_simulation_stats_aggregated(),
    this function maps columns to the format expected by biological plots.

    Args:
        sim_stats_agg_df: Aggregated DataFrame from simulation_statistics.csv

    Returns:
        DataFrame with biological metrics in standard format
    """
    df = sim_stats_agg_df.copy()

    # Map aggregated column names to expected biological format
    column_mapping = {
        'pressure_mean': 'mean_pressure',
        'volume_mean': 'mean_volume',
        'cell_id_count': 'cell_count',
        'kinetic_energy_mean': 'mean_kinetic_energy',
        'total_potential_energy_mean': 'mean_potential_energy',
    }

    result = pd.DataFrame()
    result['iteration'] = df['iteration'] if 'iteration' in df.columns else 0

    for src, dst in column_mapping.items():
        if src in df.columns:
            result[dst] = df[src]
        elif dst in df.columns:
            result[dst] = df[dst]

    return result


def load_all_data(bench_dir: Path, load_simulation_stats: bool = True) -> Dict[str, Any]:
    """
    Master data loader with auto-detection and graceful degradation.

    Automatically detects available schedulers from directory structure and
    loads all available data for each. Optionally loads per-cell simulation
    statistics for heterogeneity analysis.

    Args:
        bench_dir: Root benchmark directory
        load_simulation_stats: Whether to load simulation_statistics.csv (slower but enables
                               cell heterogeneity, energy component, and P-V phase plots)

    Returns:
        Dictionary containing:
        - 'schedulers': List of SchedulerMetadata
        - 'style_config': Dynamic colors/labels/markers for N schedulers
        - '{scheduler}_computational': Computational metrics DataFrame
        - '{scheduler}_biological': Biological metrics DataFrame
        - '{scheduler}_phase': Phase timings DataFrame (if available)
        - '{scheduler}_workload': Workload metrics DataFrame (if available)
        - '{scheduler}_simulation_stats_agg': Aggregated per-cell data (if available)
        - '{scheduler}_simulation_stats_sample': Sampled per-cell data for distribution plots
        - '{scheduler}_simulation_stats_trajectories': Full trajectories for N selected cells
        - 'comparison': Cross-scheduler comparison DataFrame
    """
    data = {}
    metrics_dir = bench_dir / "metrics"

    # Step 1: Auto-detect schedulers
    print("\n  Auto-detecting schedulers...")
    try:
        schedulers = detect_schedulers(bench_dir)
        data['schedulers'] = schedulers
        print(f"    Found {len(schedulers)} scheduler(s): {[s.name for s in schedulers]}")
    except ValueError as e:
        print(f"    Warning: {e}")
        # Fall back to hardcoded for backward compatibility
        schedulers = [
            SchedulerMetadata(name='v1', metrics_dir=metrics_dir / 'v1'),
            SchedulerMetadata(name='adaptive', metrics_dir=metrics_dir / 'adaptive'),
        ]
        data['schedulers'] = schedulers

    # Generate dynamic style config
    data['style_config'] = generate_style_config(schedulers)

    print("\n  Loading raw data files...")

    # Load data for each detected scheduler
    for sched in schedulers:
        name = sched.name

        # Load from metrics directory
        if sched.metrics_dir and sched.metrics_dir.exists():
            data[f'{name}_computational'] = load_csv_safe(
                sched.metrics_dir / "computational.csv",
                parse_dates=['timestamp']
            )
            data[f'{name}_biological'] = load_csv_safe(
                sched.metrics_dir / "biological.csv",
                parse_dates=['timestamp']
            )
            data[f'{name}_phase'] = load_csv_safe(
                sched.metrics_dir / "phase_timings.csv",
                parse_dates=['timestamp']
            )
            data[f'{name}_workload'] = load_csv_safe(
                sched.metrics_dir / "workload.csv",
                parse_dates=['timestamp']
            )

        # Load simulation statistics if requested and available
        if load_simulation_stats and sched.sim_dir and sched.has_simulation_stats:
            sim_stats_path = sched.sim_dir / "simulation_statistics.csv"

            # Load aggregated version (for time series plots)
            data[f'{name}_simulation_stats_agg'] = load_simulation_stats_aggregated(
                sim_stats_path
            )

            # Load sampled version (for distribution/phase space plots)
            data[f'{name}_simulation_stats_sample'] = load_simulation_stats_sample(
                sim_stats_path, sample_frac=0.05, max_rows=50000
            )

            # Load cell trajectories (for lifecycle phase portrait)
            data[f'{name}_simulation_stats_trajectories'] = load_simulation_stats_trajectories(
                sim_stats_path, n_cells=15, seed=42
            )

        # Load performance_diagnostics.csv (simulation-generated)
        if sched.sim_dir and sched.sim_dir.exists():
            data[f'{name}_perf_diag'] = load_performance_diagnostics(sched.sim_dir)

    # Load comparison data (cross-scheduler)
    data['comparison'] = load_csv_safe(
        metrics_dir / "comparison.csv",
        parse_dates=['timestamp']
    )

    print("\n  Applying fallbacks for sparse/missing data...")

    # Fallback: derive computational/biological data from simulation output
    # when external metrics are sparse (< 10 rows)
    SPARSE_THRESHOLD = 10

    for sched in schedulers:
        name = sched.name

        # Check if computational data is sparse/missing
        comp_df = data.get(f'{name}_computational')
        comp_rows = len(comp_df) if comp_df is not None else 0

        if comp_rows < SPARSE_THRESHOLD:
            perf_diag = data.get(f'{name}_perf_diag')
            if perf_diag is not None and len(perf_diag) > 0:
                data[f'{name}_computational'] = derive_computational_from_perf_diag(perf_diag)
                print(f"    {name}: Derived computational from performance_diagnostics.csv "
                      f"({len(data[f'{name}_computational'])} rows)")

        # Check if biological data is sparse/missing
        bio_df = data.get(f'{name}_biological')
        bio_rows = len(bio_df) if bio_df is not None else 0

        if bio_rows < SPARSE_THRESHOLD:
            sim_stats_agg = data.get(f'{name}_simulation_stats_agg')
            if sim_stats_agg is not None and len(sim_stats_agg) > 0:
                data[f'{name}_biological'] = derive_biological_from_sim_stats(sim_stats_agg)
                print(f"    {name}: Derived biological from simulation_statistics.csv "
                      f"({len(data[f'{name}_biological'])} rows)")

    print("\n  Applying data quality fixes (in-memory, source files unchanged)...")

    # Clean data for each scheduler
    for sched in schedulers:
        name = sched.name

        # Clean computational data
        raw_comp = data.get(f'{name}_computational')
        if raw_comp is not None:
            data[f'{name}_computational_clean'] = clean_computational_data(raw_comp)

        # Clean biological data (with derived metrics)
        raw_bio = data.get(f'{name}_biological')
        clean_comp = data.get(f'{name}_computational_clean')
        if raw_bio is not None:
            data[f'{name}_biological_clean'] = clean_biological_data(raw_bio, clean_comp)

    return data


def export_cleaned_data(data: Dict[str, Any], output_dir: Path) -> None:
    """
    Export cleaned data copies to the output directory.

    Saves cleaned DataFrames as CSV files for reproducibility and further analysis.
    Original source files are NOT modified.

    Args:
        data: Dictionary containing cleaned DataFrames
        output_dir: Output directory (plots-updated/)
    """
    cleaned_dir = output_dir / "cleaned_data"
    cleaned_dir.mkdir(exist_ok=True)

    print("\n  Exporting cleaned data copies...")

    # List of datasets to export
    datasets_to_export = [
        ('v1_computational_clean', 'v1_computational_cleaned.csv'),
        ('v1_biological_clean', 'v1_biological_cleaned.csv'),
        ('adaptive_computational_clean', 'adaptive_computational_cleaned.csv'),
        ('adaptive_biological_clean', 'adaptive_biological_cleaned.csv'),
    ]

    exported_files = []
    for key, filename in datasets_to_export:
        df = data.get(key)
        if df is not None and len(df) > 0:
            output_path = cleaned_dir / filename
            # Convert timestamps to string format for CSV
            df_export = df.copy()
            for col in df_export.columns:
                if pd.api.types.is_datetime64_any_dtype(df_export[col]):
                    df_export[col] = df_export[col].dt.strftime('%Y-%m-%d_%H:%M:%S')
            df_export.to_csv(output_path, index=False)
            exported_files.append(filename)
            print(f"    Saved: {output_path.name} ({len(df)} rows)")

    # Create a README explaining the cleaned data
    readme_content = f"""# Cleaned Benchmark Data

Generated: {datetime.now().isoformat()}

## Data Quality Fixes Applied

These cleaned data files have the following fixes applied (source files unchanged):

1. **Iteration Reset Artifacts Removed**: Rows with counter resets filtered, values interpolated
2. **Cell Count Outliers Corrected**: Median filter applied to detect/replace anomalous values
3. **Stalled/Duplicate Rows Removed**: Consecutive rows with same iteration number removed
4. **Derived Metrics Added**: Estimated volume and energy proxies computed where data missing

## Files

{chr(10).join(f'- {f}' for f in exported_files)}

## Derived Metrics Added

For biological data where volume/energy values were zero:

- `estimated_mean_volume`: Computed from cell_count × reference_cell_volume
- `estimated_total_volume`: Sum of all cell volumes
- `estimated_volume_std`: Estimated standard deviation (~15% CV)
- `estimated_pv_energy`: Pressure × Volume work proxy
- `estimated_total_energy`: Total energy estimate (PV × 1.5 factor)
- `estimated_energy_rate`: Energy rate of change (J/s)

## Reference Values Used

- Reference cell volume: {REFERENCE_CELL_VOLUME:.2e} m³
- Min cell volume: {REFERENCE_CELL_VOLUME_MIN:.2e} m³
- Max cell volume: {REFERENCE_CELL_VOLUME_MAX:.2e} m³

## Usage

These cleaned files can be used for:
- Further custom analysis
- Validation of visualization results
- Comparison with future benchmark runs
"""
    readme_path = cleaned_dir / "README.md"
    readme_path.write_text(readme_content)
    print(f"    Saved: README.md")

    print(f"\n  Cleaned data exported to: {cleaned_dir}")


# =============================================================================
# SECTION 4: Plotting Utilities
# =============================================================================

def add_error_band(ax: plt.Axes, x: np.ndarray, y_mean: np.ndarray,
                   y_std: np.ndarray, color, alpha: float = 0.25,
                   label: str = None) -> None:
    """
    Add ±1σ error band to time series plot.

    Args:
        ax: Matplotlib axes
        x: X-axis data (time)
        y_mean: Mean values
        y_std: Standard deviation
        color: Band color
        alpha: Transparency
        label: Optional label for legend
    """
    ax.fill_between(
        x, y_mean - y_std, y_mean + y_std,
        color=color, alpha=alpha, linewidth=0,
        label=f'{label} ±1σ' if label else None
    )


def add_stats_annotation(ax: plt.Axes, data: np.ndarray,
                         position: str = 'upper right',
                         use_latex: bool = True) -> None:
    """
    Add statistical summary box to plot.

    Args:
        ax: Matplotlib axes
        data: 1D array of values
        position: Box position
        use_latex: Use LaTeX formatting
    """
    data = np.array(data)
    data = data[~np.isnan(data)]

    if len(data) == 0:
        return

    mean = np.mean(data)
    std = np.std(data)
    cv = std / mean if mean != 0 else 0

    if use_latex:
        text = f"$n = {len(data)}$\n"
        text += f"$\\mu = {mean:.2e}$\n"
        text += f"$\\sigma = {std:.2e}$\n"
        text += f"$CV = {cv:.3f}$"
    else:
        text = f"n = {len(data)}\n"
        text += f"μ = {mean:.2e}\n"
        text += f"σ = {std:.2e}\n"
        text += f"CV = {cv:.3f}"

    # Position mapping
    positions = {
        'upper right': (0.95, 0.95, 'top', 'right'),
        'upper left': (0.05, 0.95, 'top', 'left'),
        'lower right': (0.95, 0.05, 'bottom', 'right'),
        'lower left': (0.05, 0.05, 'bottom', 'left'),
    }
    x, y, va, ha = positions.get(position, (0.95, 0.95, 'top', 'right'))

    props = dict(boxstyle='round', facecolor='white', alpha=0.8, edgecolor='gray')
    ax.text(x, y, text, transform=ax.transAxes, fontsize=6,
            verticalalignment=va, horizontalalignment=ha, bbox=props)


def get_significance_stars(p_value: float) -> str:
    """Convert p-value to significance stars."""
    if p_value < 0.001:
        return '***'
    elif p_value < 0.01:
        return '**'
    elif p_value < 0.05:
        return '*'
    return 'n.s.'


# =============================================================================
# SECTION 5: Biological Metrics Plots
# =============================================================================

def plot_pressure_evolution(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Plot pressure evolution with ±1σ error bands and physiological reference.

    Features:
    - Time series with error bands
    - Physiological range annotation (300-2200 Pa)
    - Statistical annotations
    - Auto-detects available schedulers
    """
    print("  Plotting: pressure_evolution")

    fig, ax = plt.subplots(figsize=FIGSIZE_DOUBLE)

    # Get detected schedulers and style config
    schedulers = data.get('schedulers', [])
    style = data.get('style_config', {})
    colors = style.get('colors', COLORS)
    labels = style.get('labels', LABELS)

    first_sched_with_data = None
    for sched in schedulers:
        mode = sched.name
        color = colors.get(mode, COLORS.get(mode, 'gray'))
        label = labels.get(mode, mode)

        df = data.get(f'{mode}_biological')
        if df is None or 'mean_pressure' not in df.columns:
            continue

        t = compute_time_minutes(df)
        if len(t) == 0:
            continue

        if first_sched_with_data is None:
            first_sched_with_data = mode

        mean_p = df['mean_pressure'].values
        std_p = df['pressure_std'].values if 'pressure_std' in df.columns else np.zeros_like(mean_p)

        # Plot line
        ax.plot(t, mean_p, color=color, label=label, linewidth=1.2)

        # Add error band
        add_error_band(ax, t, mean_p, std_p, color, alpha=0.2)

    # Add physiological reference range
    ax.axhspan(PHYSIOL_PRESSURE_MIN, PHYSIOL_PRESSURE_MAX,
               alpha=0.1, color='gray', label='Physiological range')
    ax.axhline(PHYSIOL_PRESSURE_MIN, color='gray', linestyle='--', linewidth=0.5)
    ax.axhline(PHYSIOL_PRESSURE_MAX, color='gray', linestyle='--', linewidth=0.5)

    # Labels
    ax.set_xlabel(format_si_label('Time', 'min', use_latex))
    ax.set_ylabel(format_si_label('Mean Cell Pressure', 'Pa', use_latex))
    ax.legend(loc='upper left', frameon=False)
    ax.set_xlim(left=0)
    ax.set_ylim(0, 500)  # Fixed physiological range (user-requested)
    apply_tufte_style(ax, grid=True)

    # Add statistics annotation for first scheduler with data
    if first_sched_with_data:
        bio_df = data.get(f'{first_sched_with_data}_biological')
        if bio_df is not None and 'mean_pressure' in bio_df.columns:
            add_stats_annotation(ax, bio_df['mean_pressure'].values, 'upper right', use_latex)

    save_figure(fig, output_dir / '01_pressure_evolution')


def plot_volume_homeostasis(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Plot volume regulation analysis with target reference.

    Features:
    - Volume evolution over time (actual or estimated)
    - Target volume reference
    - Error quantification
    - Auto-detects available schedulers
    """
    print("  Plotting: volume_homeostasis")

    fig, ax = plt.subplots(figsize=FIGSIZE_DOUBLE)

    # Get detected schedulers and style config
    schedulers = data.get('schedulers', [])
    style = data.get('style_config', {})
    colors = style.get('colors', COLORS)
    labels = style.get('labels', LABELS)

    has_data = False
    using_estimates = False

    for sched in schedulers:
        mode = sched.name
        color = colors.get(mode, COLORS.get(mode, 'gray'))

        # Try cleaned data first, then raw
        df = data.get(f'{mode}_biological_clean')
        if df is None or (hasattr(df, 'empty') and df.empty):
            df = data.get(f'{mode}_biological')
        if df is None or (hasattr(df, 'empty') and df.empty):
            continue

        t = compute_time_minutes(df)
        if len(t) == 0:
            continue

        # Check for actual volume data
        if 'mean_volume' in df.columns and not np.all(df['mean_volume'].values == 0):
            mean_v = df['mean_volume'].values
            std_v = df['volume_std'].values if 'volume_std' in df.columns else np.zeros_like(mean_v)
            has_data = True
        # Fall back to estimated volume
        elif 'estimated_mean_volume' in df.columns:
            mean_v = df['estimated_mean_volume'].values
            std_v = df['estimated_volume_std'].values if 'estimated_volume_std' in df.columns else mean_v * 0.15
            has_data = True
            using_estimates = True
        else:
            continue

        sched_label = labels.get(mode, mode)
        label = f'{sched_label}' + (' (est.)' if using_estimates else '')
        ax.plot(t, mean_v, color=color, label=label, linewidth=1.2,
                linestyle='--' if using_estimates else '-')
        add_error_band(ax, t, mean_v, std_v, color, alpha=0.2)

    if not has_data:
        # Create placeholder plot with message
        ax.text(0.5, 0.5, 'Volume data not available\nin current benchmark',
                ha='center', va='center', transform=ax.transAxes,
                fontsize=10, color='gray')
    else:
        # Add physiological reference
        ax.axhspan(PHYSIOL_VOLUME_MIN, PHYSIOL_VOLUME_MAX,
                   alpha=0.1, color='gray', label='Physiological range')
        ax.legend(loc='upper left', frameon=False)

        if using_estimates:
            ax.text(0.98, 0.02, 'Dashed lines = estimated from cell count',
                    transform=ax.transAxes, fontsize=6, ha='right', va='bottom',
                    style='italic', color='gray')

    ax.set_xlabel(format_si_label('Time', 'min', use_latex))
    ax.set_ylabel(format_si_label('Mean Cell Volume', 'm^3', use_latex))
    ax.set_xlim(left=0)
    apply_tufte_style(ax, grid=True)

    save_figure(fig, output_dir / '02_volume_homeostasis')


def plot_energy_landscape(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Plot energy evolution with drift quantification.

    Features:
    - Total energy time series (actual or estimated)
    - Energy rate of change
    - Drift rate annotation
    - Auto-detects available schedulers
    """
    print("  Plotting: energy_landscape")

    fig, axes = plt.subplots(2, 1, figsize=FIGSIZE_DOUBLE, gridspec_kw={'height_ratios': [2, 1]}, sharex=True)
    ax1, ax2 = axes

    # Get detected schedulers and style config
    schedulers = data.get('schedulers', [])
    style = data.get('style_config', {})
    colors = style.get('colors', COLORS)
    labels = style.get('labels', LABELS)

    has_data = False
    using_estimates = False
    all_energy_maxes = []  # Track max energy for auto-scaling

    for sched in schedulers:
        mode = sched.name
        color = colors.get(mode, COLORS.get(mode, 'gray'))
        sched_label = labels.get(mode, mode)

        # Try cleaned data first, then raw
        df = data.get(f'{mode}_biological_clean')
        if df is None or (hasattr(df, 'empty') and df.empty):
            df = data.get(f'{mode}_biological')
        if df is None or (hasattr(df, 'empty') and df.empty):
            continue

        t = compute_time_minutes(df)
        if len(t) == 0:
            continue

        # Get energy data - check for actual data first
        E_kinetic = df.get('total_kinetic_energy', pd.Series(np.zeros(len(df)))).values
        E_potential = df.get('total_potential_energy', pd.Series(np.zeros(len(df)))).values
        E_total = E_kinetic + E_potential

        # If actual energy is all zeros, try estimated energy
        if np.all(E_total == 0) and 'estimated_total_energy' in df.columns:
            E_total = df['estimated_total_energy'].values
            using_estimates = True

        # Skip if still no data
        if np.all(E_total == 0) or np.all(np.isnan(E_total)):
            continue

        has_data = True
        all_energy_maxes.append(np.nanmax(E_total))

        # Panel 1: Total energy
        label = f'{sched_label}' + (' (PV proxy)' if using_estimates else '')
        ax1.plot(t, E_total, color=color, label=label, linewidth=1.2,
                 linestyle='--' if using_estimates else '-')

        # Panel 2: Energy rate (derivative or pre-computed)
        if 'estimated_energy_rate' in df.columns and using_estimates:
            drift_rate = df['estimated_energy_rate'].values
            ax2.plot(t, drift_rate, color=color, linewidth=0.8, alpha=0.7)
        elif len(t) > 1:
            dt = np.diff(t) * 60  # Convert to seconds
            dt[dt == 0] = 1  # Avoid division by zero
            dE = np.diff(E_total)
            drift_rate = dE / dt
            ax2.plot(t[1:], drift_rate, color=color, linewidth=0.8, alpha=0.7)

    if not has_data:
        ax1.text(0.5, 0.5, 'Energy data not available\nin current benchmark',
                 ha='center', va='center', transform=ax1.transAxes,
                 fontsize=10, color='gray')
    elif using_estimates:
        ax1.text(0.98, 0.02, 'Dashed = PV work proxy (P×V×1.5)',
                 transform=ax1.transAxes, fontsize=6, ha='right', va='bottom',
                 style='italic', color='gray')

    ax1.set_ylabel(format_si_label('Total Energy', 'J', use_latex))
    ax1.legend(loc='upper right', frameon=False)
    # Auto-scale Y-axis to prevent data clipping (user-requested)
    if all_energy_maxes:
        max_energy = max(all_energy_maxes)
        if max_energy > 0:
            ax1.set_ylim(0, max_energy * 1.1)
    apply_tufte_style(ax1, grid=True)

    ax2.set_xlabel(format_si_label('Time', 'min', use_latex))
    ax2.set_ylabel(format_si_label('Energy Drift Rate', 'J/s', use_latex))
    ax2.axhline(0, color='gray', linestyle='--', linewidth=0.5)
    apply_tufte_style(ax2, grid=True)

    plt.tight_layout()
    save_figure(fig, output_dir / '02_energy_landscape')


def plot_cell_heterogeneity(data: Dict, output_dir: Path, use_latex: bool = True,
                            style_config: Optional[Dict] = None) -> None:
    """
    Plot cell population heterogeneity as 2D histogram (pressure vs volume).

    Uses per-cell data from simulation_statistics.csv to show the spread
    of mechanical states across the cell population. The physiological
    corridor (pressure: 300-2200 Pa, volume: 2.5e-16 to 1.3e-15 m³) is overlaid.

    Features:
    - 2D hexbin density plot with log color scale
    - Physiological corridor as rectangular overlay
    - Marginal histograms for pressure and volume distributions
    - Per-scheduler comparison if multiple available
    """
    print("  Plotting: cell_heterogeneity")

    # Check for simulation statistics data
    has_data = False
    for key in data.keys():
        if 'simulation_stats' in key:
            has_data = True
            break

    if not has_data:
        print("    Skipped: No simulation_statistics data available")
        return

    # Get style config or use defaults
    colors = style_config.get('colors', COLORS) if style_config else COLORS
    labels = style_config.get('labels', LABELS) if style_config else LABELS

    # Determine schedulers with simulation stats data
    schedulers_with_data = []
    for key in sorted(data.keys()):
        if 'simulation_stats_sample' in key:
            sched = key.replace('_simulation_stats_sample', '')
            schedulers_with_data.append(sched)

    if not schedulers_with_data:
        print("    Skipped: No sampled simulation statistics")
        return

    n_schedulers = len(schedulers_with_data)
    fig, axes = plt.subplots(1, n_schedulers, figsize=(4.5 * n_schedulers, 4.5),
                              squeeze=False)

    for idx, sched in enumerate(schedulers_with_data):
        ax = axes[0, idx]
        df = data.get(f'{sched}_simulation_stats_sample')

        if df is None or 'pressure' not in df.columns or 'volume' not in df.columns:
            ax.text(0.5, 0.5, 'Data not available', ha='center', va='center',
                    transform=ax.transAxes, fontsize=10, color='gray')
            ax.set_title(labels.get(sched, sched))
            continue

        # Extract pressure and volume, filter valid values
        pressure = df['pressure'].values
        volume = df['volume'].values

        valid = (pressure > 0) & (volume > 0) & np.isfinite(pressure) & np.isfinite(volume)
        pressure = pressure[valid]
        volume = volume[valid]

        if len(pressure) < 100:
            ax.text(0.5, 0.5, 'Insufficient data', ha='center', va='center',
                    transform=ax.transAxes, fontsize=10, color='gray')
            continue

        # 2D hexbin plot with log color scale
        hb = ax.hexbin(volume * 1e15, pressure, gridsize=40, cmap='viridis',
                       mincnt=1, xscale='log', yscale='linear',
                       norm=plt.matplotlib.colors.LogNorm())

        # Add colorbar
        cb = plt.colorbar(hb, ax=ax, label='Cell count')
        cb.ax.tick_params(labelsize=6)

        # Overlay physiological corridor
        from matplotlib.patches import Rectangle
        physiol_rect = Rectangle(
            (PHYSIOL_VOLUME_MIN * 1e15, PHYSIOL_PRESSURE_MIN),
            (PHYSIOL_VOLUME_MAX - PHYSIOL_VOLUME_MIN) * 1e15,
            PHYSIOL_PRESSURE_MAX - PHYSIOL_PRESSURE_MIN,
            linewidth=2, edgecolor='red', facecolor='none',
            linestyle='--', label='Physiological range'
        )
        ax.add_patch(physiol_rect)

        ax.set_xlabel(format_si_label('Volume', 'fL', use_latex))
        ax.set_ylabel(format_si_label('Pressure', 'Pa', use_latex))
        ax.set_title(f'{labels.get(sched, sched)}: Cell State Distribution')
        ax.legend(loc='upper right', fontsize=6)
        apply_tufte_style(ax, grid=False)

    plt.tight_layout()
    save_figure(fig, output_dir / '02b_cell_heterogeneity')


def plot_energy_components(data: Dict, output_dir: Path, use_latex: bool = True,
                           style_config: Optional[Dict] = None) -> None:
    """
    Plot energy component breakdown as stacked area chart.

    Shows how total potential energy is partitioned among 4 components:
    - Surface tension energy (cortical tension)
    - Membrane elasticity energy (area elasticity)
    - Bending energy (membrane curvature)
    - Pressure energy (volumetric compression)

    This reveals the dominant mechanical storage mechanism over time.
    """
    print("  Plotting: energy_components")

    # Check for aggregated simulation statistics with energy components
    has_data = False
    energy_cols = ['surface_tension_energy_mean', 'membrane_elasticity_energy_mean',
                   'bending_energy_mean', 'pressure_energy_mean']

    for key in data.keys():
        if 'simulation_stats_agg' in key:
            df = data[key]
            if df is not None and all(col in df.columns for col in energy_cols):
                has_data = True
                break

    if not has_data:
        print("    Skipped: No energy component data available")
        return

    # Get style config
    colors = style_config.get('colors', COLORS) if style_config else COLORS
    labels = style_config.get('labels', LABELS) if style_config else LABELS

    # Collect schedulers with energy data
    schedulers_with_data = []
    for key in sorted(data.keys()):
        if 'simulation_stats_agg' in key:
            df = data[key]
            if df is not None and all(col in df.columns for col in energy_cols):
                sched = key.replace('_simulation_stats_agg', '')
                schedulers_with_data.append(sched)

    if not schedulers_with_data:
        print("    Skipped: No energy component columns found")
        return

    n_schedulers = len(schedulers_with_data)
    fig, axes = plt.subplots(1, n_schedulers, figsize=(5 * n_schedulers, 4),
                              squeeze=False)

    # Energy component colors (perceptually distinct)
    component_colors = {
        'surface_tension': cm.viridis(0.2),
        'membrane_elasticity': cm.viridis(0.4),
        'bending': cm.viridis(0.6),
        'pressure': cm.viridis(0.8),
    }

    component_labels = {
        'surface_tension_energy_mean': 'Surface Tension',
        'membrane_elasticity_energy_mean': 'Membrane Elasticity',
        'bending_energy_mean': 'Bending',
        'pressure_energy_mean': 'Pressure (PV)',
    }

    for idx, sched in enumerate(schedulers_with_data):
        ax = axes[0, idx]
        df = data.get(f'{sched}_simulation_stats_agg')

        if df is None:
            continue

        # Get iteration as x-axis
        if 'iteration' in df.columns:
            x = df['iteration'].values
        else:
            x = np.arange(len(df))

        # Stack energy components
        y_components = []
        component_names = []
        for col in energy_cols:
            if col in df.columns:
                values = df[col].values
                # Convert to femtojoules for readability
                values_fj = np.abs(values) * 1e15
                y_components.append(values_fj)
                component_names.append(component_labels.get(col, col))

        if not y_components:
            continue

        # Stacked area plot
        y_stack = np.vstack(y_components)
        colors_list = [cm.viridis(0.2 + 0.2 * i) for i in range(len(y_components))]

        ax.stackplot(x, y_stack, labels=component_names, colors=colors_list, alpha=0.8)

        ax.set_xlabel('Iteration')
        ax.set_ylabel(format_si_label('Energy', 'fJ', use_latex))
        ax.set_title(f'{labels.get(sched, sched)}: Energy Budget')
        ax.legend(loc='upper left', fontsize=6)
        ax.set_xlim(left=0)
        ax.set_ylim(bottom=0)
        apply_tufte_style(ax, grid=True)

    plt.tight_layout()
    save_figure(fig, output_dir / '02c_energy_components')


def plot_pv_phase_space(data: Dict, output_dir: Path, use_latex: bool = True,
                        style_config: Optional[Dict] = None) -> None:
    """
    Plot pressure-volume phase space with physiological corridor.

    Shows cell population trajectories in P-V space, analogous to
    thermodynamic state diagrams. The physiological corridor represents
    the viable region for healthy cells.

    Features:
    - Scatter/density plot of individual cells in P-V space
    - Physiological corridor overlay (300-2200 Pa × 2.5e-16 to 1.3e-15 m³)
    - Optional ideal gas isotherms for comparison
    - Time evolution shown via color gradient
    """
    print("  Plotting: pv_phase_space")

    # Check for sampled simulation statistics
    has_data = False
    for key in data.keys():
        if 'simulation_stats_sample' in key:
            has_data = True
            break

    if not has_data:
        print("    Skipped: No simulation statistics sample available")
        return

    # Get style config
    colors = style_config.get('colors', COLORS) if style_config else COLORS
    labels = style_config.get('labels', LABELS) if style_config else LABELS

    # Collect schedulers with data
    schedulers_with_data = []
    for key in sorted(data.keys()):
        if 'simulation_stats_sample' in key:
            sched = key.replace('_simulation_stats_sample', '')
            schedulers_with_data.append(sched)

    if not schedulers_with_data:
        return

    n_schedulers = len(schedulers_with_data)
    fig, axes = plt.subplots(1, n_schedulers, figsize=(5 * n_schedulers, 4.5),
                              squeeze=False)

    for idx, sched in enumerate(schedulers_with_data):
        ax = axes[0, idx]
        df = data.get(f'{sched}_simulation_stats_sample')

        if df is None or 'pressure' not in df.columns or 'volume' not in df.columns:
            ax.text(0.5, 0.5, 'Data not available', ha='center', va='center',
                    transform=ax.transAxes)
            continue

        pressure = df['pressure'].values
        volume = df['volume'].values

        # Color by iteration if available (shows time evolution)
        if 'iteration' in df.columns:
            iteration = df['iteration'].values
            # Normalize for colormap
            iter_norm = (iteration - iteration.min()) / (iteration.max() - iteration.min() + 1)
            color_values = iter_norm
            cmap = 'viridis'
        else:
            color_values = colors.get(sched, 'blue')
            cmap = None

        # Filter valid data
        valid = (pressure > 0) & (volume > 0) & np.isfinite(pressure) & np.isfinite(volume)
        pressure = pressure[valid]
        volume = volume[valid]
        if 'iteration' in df.columns:
            color_values = color_values[valid]

        if len(pressure) < 100:
            ax.text(0.5, 0.5, 'Insufficient data', ha='center', va='center',
                    transform=ax.transAxes)
            continue

        # Convert volume to femtoliters for readability
        volume_fl = volume * 1e15

        # Scatter plot with time coloring
        scatter = ax.scatter(volume_fl, pressure, c=color_values, cmap=cmap,
                            s=3, alpha=0.3, rasterized=True)

        if 'iteration' in df.columns:
            cb = plt.colorbar(scatter, ax=ax, label='Time (normalized)')
            cb.ax.tick_params(labelsize=6)

        # Overlay physiological corridor
        ax.axhspan(PHYSIOL_PRESSURE_MIN, PHYSIOL_PRESSURE_MAX,
                   alpha=0.1, color='green', label='Physiological P')
        ax.axvspan(PHYSIOL_VOLUME_MIN * 1e15, PHYSIOL_VOLUME_MAX * 1e15,
                   alpha=0.1, color='blue', label='Physiological V')

        # Add ideal gas isotherms for reference (PV = nRT = const)
        # Use median values as reference
        pv_median = np.median(pressure * volume)
        v_range = np.logspace(np.log10(volume_fl.min()), np.log10(volume_fl.max()), 50)
        p_isotherm = (pv_median / (v_range / 1e15))
        ax.plot(v_range, p_isotherm, 'k--', linewidth=0.5, alpha=0.5, label='PV=const')

        ax.set_xlabel(format_si_label('Volume', 'fL', use_latex))
        ax.set_ylabel(format_si_label('Pressure', 'Pa', use_latex))
        ax.set_title(f'{labels.get(sched, sched)}: P-V Phase Space')
        ax.set_xscale('log')
        ax.legend(loc='upper right', fontsize=5)
        apply_tufte_style(ax, grid=True)

    plt.tight_layout()
    save_figure(fig, output_dir / '02d_pv_phase_space')


def plot_biological_dashboard(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Create 6-panel biological metrics dashboard.

    Panels:
    1. Pressure evolution
    2. Cell count growth
    3. Volume evolution (if available)
    4. Pressure distribution
    5. Energy evolution
    6. Cell growth rate
    """
    print("  Plotting: biological_dashboard")

    fig = plt.figure(figsize=(10.5, 6.0))  # Wider layout for 3 columns
    gs = fig.add_gridspec(2, 3, hspace=0.35, wspace=0.3)

    # Panel A: Pressure evolution (use cleaned data) - dynamic scheduler iteration
    style = data.get('style_config', {})
    colors = style.get('colors', COLORS)
    labels = style.get('labels', LABELS)
    ax_pressure = fig.add_subplot(gs[0, 0])
    for mode, color, label in iter_schedulers(data):
        df = get_dataframe(data, f'{mode}_biological_clean', f'{mode}_biological')
        if df is None or 'mean_pressure' not in df.columns:
            continue
        t = compute_time_minutes(df)
        if len(t) > 0:
            ax_pressure.plot(t, df['mean_pressure'], color=color, label=label, linewidth=1.0)
            if 'pressure_std' in df.columns:
                add_error_band(ax_pressure, t, df['mean_pressure'].values,
                              df['pressure_std'].values, color, alpha=0.15)

    ax_pressure.axhspan(PHYSIOL_PRESSURE_MIN, PHYSIOL_PRESSURE_MAX, alpha=0.1, color='gray')
    ax_pressure.set_ylabel(format_si_label('Pressure', 'Pa', use_latex))
    ax_pressure.set_title('A. Pressure Evolution', fontsize=9, fontweight='bold', loc='left')
    ax_pressure.legend(fontsize=6, loc='upper left')
    ax_pressure.set_ylim(0, 500)  # Fixed physiological range (synced with Plot 1)
    apply_tufte_style(ax_pressure, grid=True)

    # Panel B: Cell count growth (use cleaned data)
    ax_cells = fig.add_subplot(gs[0, 1])
    for mode, color, label in iter_schedulers(data):
        df = get_dataframe(data, f'{mode}_computational_clean', f'{mode}_computational')
        if df is None or 'cells' not in df.columns:
            continue
        t = compute_time_minutes(df)
        if len(t) > 0:
            ax_cells.plot(t, df['cells'], color=color, label=label, linewidth=1.0)

    ax_cells.set_ylabel('Cell Count')
    ax_cells.set_title('B. Population Growth', fontsize=9, fontweight='bold', loc='left')
    ax_cells.legend(fontsize=6, loc='upper left')
    apply_tufte_style(ax_cells, grid=True)

    # Panel C: Volume evolution (use cleaned data with estimates)
    ax_volume = fig.add_subplot(gs[0, 2])
    has_volume = False
    for mode, color, label in iter_schedulers(data):
        df = get_dataframe(data, f'{mode}_biological_clean', f'{mode}_biological')
        if df is None:
            continue
        t = compute_time_minutes(df)
        # Try actual volume first, then estimated
        if 'mean_volume' in df.columns and not np.all(df['mean_volume'].values == 0):
            mean_v = df['mean_volume'].values
        elif 'estimated_mean_volume' in df.columns:
            mean_v = df['estimated_mean_volume'].values
        else:
            continue
        if len(t) > 0 and not np.all(mean_v == 0):
            has_volume = True
            ax_volume.plot(t, mean_v, color=color, label=label, linewidth=1.0)

    if not has_volume:
        ax_volume.text(0.5, 0.5, 'Data not available', ha='center', va='center',
                       transform=ax_volume.transAxes, fontsize=8, color='gray')

    ax_volume.set_ylabel(format_si_label('Volume', 'm^3', use_latex))
    ax_volume.set_title('C. Volume Homeostasis', fontsize=9, fontweight='bold', loc='left')
    apply_tufte_style(ax_volume, grid=True)

    # Panel D: Pressure distribution (use cleaned data) - dynamic scheduler iteration
    ax_dist = fig.add_subplot(gs[1, 0])
    box_data = []
    box_labels = []
    box_colors = []

    for mode, color, label in iter_schedulers(data):
        bio_df = get_dataframe(data, f'{mode}_biological_clean', f'{mode}_biological')
        if bio_df is not None and 'mean_pressure' in bio_df.columns:
            box_data.append(bio_df['mean_pressure'].dropna().values)
            box_labels.append(label)
            box_colors.append(color)

    if box_data:
        bp = ax_dist.boxplot(box_data, labels=box_labels, patch_artist=True)
        for patch, color in zip(bp['boxes'], box_colors):
            patch.set_facecolor(color)
            patch.set_alpha(0.6)

    ax_dist.set_ylabel(format_si_label('Pressure', 'Pa', use_latex))
    ax_dist.set_title('D. Pressure Distribution', fontsize=9, fontweight='bold', loc='left')
    apply_tufte_style(ax_dist, grid=True)

    # Panel E: Energy evolution (use cleaned data with estimates)
    ax_energy = fig.add_subplot(gs[1, 1])
    has_energy = False
    energy_maxes = []
    for mode, color, label in iter_schedulers(data):
        df = get_dataframe(data, f'{mode}_biological_clean', f'{mode}_biological')
        if df is None:
            continue
        t = compute_time_minutes(df)
        E_total = (df.get('total_kinetic_energy', pd.Series([0]*len(df))).values +
                   df.get('total_potential_energy', pd.Series([0]*len(df))).values)
        # Try estimated energy if actual is zero
        if np.all(E_total == 0) and 'estimated_total_energy' in df.columns:
            E_total = df['estimated_total_energy'].values
        if len(t) > 0 and not np.all(E_total == 0):
            has_energy = True
            energy_maxes.append(np.nanmax(E_total))
            ax_energy.plot(t, E_total, color=color, label=label, linewidth=1.0)

    if not has_energy:
        ax_energy.text(0.5, 0.5, 'Data not available', ha='center', va='center',
                       transform=ax_energy.transAxes, fontsize=8, color='gray')

    ax_energy.set_xlabel(format_si_label('Time', 'min', use_latex))
    ax_energy.set_ylabel(format_si_label('Energy', 'J', use_latex))
    ax_energy.set_title('E. Energy Evolution', fontsize=9, fontweight='bold', loc='left')
    # Auto-scale Y-axis to prevent clipping (synced with Plot 3)
    if energy_maxes:
        max_e = max(energy_maxes)
        if max_e > 0:
            ax_energy.set_ylim(0, max_e * 1.1)
    apply_tufte_style(ax_energy, grid=True)

    # Panel F: Growth rate (use cleaned data to avoid anomalies)
    ax_growth = fig.add_subplot(gs[1, 2])
    for mode, color, label in iter_schedulers(data):
        df = get_dataframe(data, f'{mode}_computational_clean', f'{mode}_computational')
        if df is None or 'cells' not in df.columns:
            continue
        t = compute_time_minutes(df)
        cells = df['cells'].values
        if len(t) > 1:
            # Compute growth rate (cells/hour)
            dt_hours = np.diff(t) / 60
            dcells = np.diff(cells)
            growth_rate = dcells / dt_hours
            # Smooth with Savitzky-Golay filter (preserves peaks better than rolling mean)
            growth_rate_smooth = smooth_signal(growth_rate, window_length=11, polyorder=3)
            ax_growth.plot(t[1:], growth_rate_smooth, color=color, label=label, linewidth=1.0)

    ax_growth.set_xlabel(format_si_label('Time', 'min', use_latex))
    ax_growth.set_ylabel('Growth Rate (cells/hour)')
    ax_growth.set_title('F. Cell Growth Rate', fontsize=9, fontweight='bold', loc='left')
    ax_growth.legend(fontsize=6, loc='upper right')
    apply_tufte_style(ax_growth, grid=True)

    save_figure(fig, output_dir / '03_biological_dashboard')


def plot_population_ridgeline(data: Dict, output_dir: Path, use_latex: bool = True,
                               style_config: Optional[Dict] = None) -> None:
    """
    Plot population ridgeline (joy plot) showing pressure distribution evolution.

    Narrative: Biological - "How does population heterogeneity evolve?"

    Creates a ridgeline/joy plot showing how the pressure distribution across
    the cell population changes over time. Each horizontal ridge represents
    a time window, with later times stacked above earlier times.

    Features:
    - Joy plot with 20-30 time windows
    - Plasma colormap gradient (early=purple, late=yellow)
    - Physiological range overlay (300-2200 Pa)
    - KDE-smoothed distributions for each time window
    """
    print("  Plotting: population_ridgeline")

    # Check for sampled simulation statistics
    has_data = False
    for key in data.keys():
        if 'simulation_stats_sample' in key:
            df = data[key]
            if df is not None and 'pressure' in df.columns and 'iteration' in df.columns:
                has_data = True
                break

    if not has_data:
        print("    Skipped: No simulation statistics sample available")
        return

    # Get style config
    labels = style_config.get('labels', LABELS) if style_config else LABELS

    # Collect schedulers with data
    schedulers_with_data = []
    for key in sorted(data.keys()):
        if 'simulation_stats_sample' in key:
            df = data[key]
            if df is not None and 'pressure' in df.columns and 'iteration' in df.columns:
                sched = key.replace('_simulation_stats_sample', '')
                schedulers_with_data.append(sched)

    if not schedulers_with_data:
        return

    n_schedulers = len(schedulers_with_data)
    fig, axes = plt.subplots(1, n_schedulers, figsize=(6 * n_schedulers, 7), squeeze=False)

    n_bins = 25  # Number of time windows

    for idx, sched in enumerate(schedulers_with_data):
        ax = axes[0, idx]
        df = data.get(f'{sched}_simulation_stats_sample')

        if df is None or 'pressure' not in df.columns:
            ax.text(0.5, 0.5, 'Data not available', ha='center', va='center',
                    transform=ax.transAxes)
            continue

        pressure = df['pressure'].values
        iteration = df['iteration'].values

        # Filter valid data
        valid = (pressure > 0) & (pressure < 5000) & np.isfinite(pressure)
        pressure = pressure[valid]
        iteration = iteration[valid]

        if len(pressure) < 500:
            ax.text(0.5, 0.5, 'Insufficient data', ha='center', va='center',
                    transform=ax.transAxes)
            continue

        # Bin data into time windows
        iter_min, iter_max = iteration.min(), iteration.max()
        bin_edges = np.linspace(iter_min, iter_max, n_bins + 1)

        # Pressure range for KDE
        p_range = np.linspace(0, min(pressure.max() * 1.1, 3000), 200)

        # Create ridgeline plot
        offset = 0
        ridge_height = 0.03  # Height multiplier for ridges

        for i in range(n_bins):
            mask = (iteration >= bin_edges[i]) & (iteration < bin_edges[i + 1])
            p_window = pressure[mask]

            if len(p_window) < 20:
                continue

            # Compute KDE for this time window
            if SCIPY_AVAILABLE:
                try:
                    from scipy.stats import gaussian_kde
                    kde = gaussian_kde(p_window, bw_method=0.2)
                    density = kde(p_range)
                except Exception:
                    # Fallback to histogram-based density
                    hist, edges = np.histogram(p_window, bins=50, range=(p_range[0], p_range[-1]), density=True)
                    density = np.interp(p_range, (edges[:-1] + edges[1:]) / 2, hist)
            else:
                hist, edges = np.histogram(p_window, bins=50, range=(p_range[0], p_range[-1]), density=True)
                density = np.interp(p_range, (edges[:-1] + edges[1:]) / 2, hist)

            # Normalize density
            density = density / density.max() if density.max() > 0 else density

            # Color based on time (plasma colormap: early=purple, late=yellow)
            color = cm.plasma(i / n_bins)

            # Plot ridge with offset
            y_offset = offset + density * ridge_height
            ax.fill_between(p_range, offset, y_offset, color=color, alpha=0.7, linewidth=0)
            ax.plot(p_range, y_offset, color='white', linewidth=0.3, alpha=0.8)

            offset += 0.015  # Vertical offset between ridges

        # Add physiological range indicators
        ax.axvline(PHYSIOL_PRESSURE_MIN, color='gray', linestyle='--', linewidth=1, alpha=0.7)
        ax.axvline(PHYSIOL_PRESSURE_MAX, color='gray', linestyle='--', linewidth=1, alpha=0.7)

        # Add text annotations for physiological bounds
        ax.text(PHYSIOL_PRESSURE_MIN, offset * 0.95, f'{PHYSIOL_PRESSURE_MIN} Pa',
                fontsize=6, ha='center', color='gray')
        ax.text(PHYSIOL_PRESSURE_MAX, offset * 0.95, f'{PHYSIOL_PRESSURE_MAX} Pa',
                fontsize=6, ha='center', color='gray')

        ax.set_xlabel(format_si_label('Pressure', 'Pa', use_latex))
        ax.set_ylabel('Time (early → late)')
        ax.set_title(f'{labels.get(sched, sched)}: Pressure Distribution Evolution')
        ax.set_xlim(0, min(pressure.max() * 1.1, 3000))
        ax.set_ylim(0, offset * 1.1)
        ax.set_yticks([])  # Hide y-axis ticks (ordinal time)

        # Add colorbar for time
        sm = plt.cm.ScalarMappable(cmap='plasma', norm=plt.Normalize(0, 1))
        sm.set_array([])
        cbar = plt.colorbar(sm, ax=ax, orientation='vertical', fraction=0.03, pad=0.02)
        cbar.set_label('Time (normalized)', fontsize=7)
        cbar.ax.tick_params(labelsize=6)

        apply_tufte_style(ax, grid=False)

    plt.tight_layout()
    save_figure(fig, output_dir / '03b_population_ridgeline')


def plot_cell_lifecycle_portrait(data: Dict, output_dir: Path, use_latex: bool = True,
                                  style_config: Optional[Dict] = None) -> None:
    """
    Plot cell lifecycle phase portrait in P-V space.

    Narrative: Biological/Physical - "What mechanical trajectory do cells follow?"

    Creates a 2D phase space plot (pressure vs normalized volume V/V_target)
    showing individual cell trajectories. Background shows population density
    via hexbin, foreground shows 10-15 representative trajectories with
    directional arrows.

    Features:
    - Background hexbin density of all cell states
    - Foreground: 10-15 representative cell trajectories with arrows
    - Iso-energy contours (PV = const)
    - Division threshold line (if available)
    """
    print("  Plotting: cell_lifecycle_portrait")

    # Check for trajectory data
    has_data = False
    for key in data.keys():
        if 'simulation_stats_trajectories' in key:
            df = data[key]
            if df is not None and 'pressure' in df.columns and 'volume' in df.columns:
                has_data = True
                break

    if not has_data:
        # Fall back to sample data
        for key in data.keys():
            if 'simulation_stats_sample' in key:
                df = data[key]
                if df is not None and 'pressure' in df.columns and 'volume' in df.columns:
                    has_data = True
                    break

    if not has_data:
        print("    Skipped: No simulation statistics data available")
        return

    # Get style config
    labels = style_config.get('labels', LABELS) if style_config else LABELS

    # Collect schedulers with data
    schedulers_with_data = []
    for key in sorted(data.keys()):
        if 'simulation_stats_trajectories' in key or 'simulation_stats_sample' in key:
            sched = key.replace('_simulation_stats_trajectories', '').replace('_simulation_stats_sample', '')
            if sched not in schedulers_with_data:
                schedulers_with_data.append(sched)

    if not schedulers_with_data:
        return

    n_schedulers = len(schedulers_with_data)
    fig, axes = plt.subplots(1, n_schedulers, figsize=(6 * n_schedulers, 5.5), squeeze=False)

    for idx, sched in enumerate(schedulers_with_data):
        ax = axes[0, idx]

        # Get trajectory data (preferred) or sample data (fallback)
        df_traj = data.get(f'{sched}_simulation_stats_trajectories')
        df_sample = data.get(f'{sched}_simulation_stats_sample')

        # Determine target volume from data (use target_volume column if available)
        V_target = None
        if df_sample is not None and 'target_volume' in df_sample.columns:
            V_target = df_sample['target_volume'].median()
        elif df_traj is not None and 'target_volume' in df_traj.columns:
            V_target = df_traj['target_volume'].median()

        # Fallback: estimate from volume data
        if V_target is None or V_target <= 0:
            if df_sample is not None and 'volume' in df_sample.columns:
                V_target = df_sample['volume'].median()
            else:
                V_target = 1.0e-14  # Reasonable default for cells

        # Use sample for background density
        if df_sample is not None and 'pressure' in df_sample.columns and 'volume' in df_sample.columns:
            p_all = df_sample['pressure'].values
            v_all = df_sample['volume'].values

            # Filter valid data
            valid = (p_all > 0) & (v_all > 0) & np.isfinite(p_all) & np.isfinite(v_all)
            p_all = p_all[valid]
            v_all = v_all[valid]

            # Normalize volume by target
            v_norm_all = v_all / V_target

            if len(p_all) > 100:
                # Background hexbin density
                hb = ax.hexbin(v_norm_all, p_all, gridsize=35, cmap='Greys',
                               mincnt=1, alpha=0.6, linewidths=0.2)

        # Overlay trajectories if available
        if df_traj is not None and 'cell_id' in df_traj.columns:
            cell_ids = df_traj['cell_id'].unique()

            # Use a distinct colormap for trajectories
            traj_colors = cm.plasma(np.linspace(0.2, 0.9, len(cell_ids)))

            for i, cell_id in enumerate(cell_ids[:15]):  # Max 15 trajectories
                cell_data = df_traj[df_traj['cell_id'] == cell_id].copy()
                cell_data = cell_data.sort_values('iteration')

                if len(cell_data) < 10:
                    continue

                p = cell_data['pressure'].values
                v = cell_data['volume'].values

                # Filter valid data
                valid = (p > 0) & (v > 0) & np.isfinite(p) & np.isfinite(v)
                if valid.sum() < 10:
                    continue

                p = p[valid]
                v = v[valid]
                v_norm = v / V_target

                # Plot trajectory line
                ax.plot(v_norm, p, color=traj_colors[i], linewidth=1.2, alpha=0.8)

                # Add directional arrows (quiver) at regular intervals
                n_arrows = min(5, len(p) // 10)
                if n_arrows >= 2:
                    arrow_indices = np.linspace(len(p) // 4, 3 * len(p) // 4, n_arrows, dtype=int)
                    for ai in arrow_indices:
                        if ai < len(p) - 1:
                            dx = v_norm[ai + 1] - v_norm[ai]
                            dy = p[ai + 1] - p[ai]
                            # Normalize arrow length for visibility
                            mag = np.sqrt(dx**2 + dy**2)
                            if mag > 0:
                                ax.annotate('', xy=(v_norm[ai] + dx * 0.3, p[ai] + dy * 0.3),
                                           xytext=(v_norm[ai], p[ai]),
                                           arrowprops=dict(arrowstyle='->', color=traj_colors[i],
                                                          lw=0.8, mutation_scale=8))

                # Mark start and end points
                ax.scatter(v_norm[0], p[0], s=25, color=traj_colors[i], marker='o', zorder=5)
                ax.scatter(v_norm[-1], p[-1], s=25, color=traj_colors[i], marker='s', zorder=5)

        # Compute axis limits from data
        v_norm_min, v_norm_max = 0.5, 1.5  # Default range
        p_max = 500  # Default pressure max
        if df_sample is not None and 'pressure' in df_sample.columns and 'volume' in df_sample.columns:
            valid = (df_sample['pressure'] > 0) & (df_sample['volume'] > 0)
            if valid.sum() > 0:
                v_norm_data = df_sample.loc[valid, 'volume'].values / V_target
                v_norm_min = max(0, np.percentile(v_norm_data, 1) * 0.9)
                v_norm_max = np.percentile(v_norm_data, 99) * 1.1
                p_max = df_sample.loc[valid, 'pressure'].quantile(0.99) * 1.2

        # Add physiological pressure corridor
        ax.axhspan(PHYSIOL_PRESSURE_MIN, PHYSIOL_PRESSURE_MAX,
                   alpha=0.1, color='green', label='Physiological P range')

        # Add target volume reference line (V/V_target = 1)
        ax.axvline(1.0, color='blue', linestyle='--', linewidth=1, alpha=0.5, label='V = V_target')

        # Add iso-energy contour (PV = constant) using median PV from data
        v_range = np.linspace(max(0.1, v_norm_min), v_norm_max, 100)
        if df_sample is not None and 'pressure' in df_sample.columns:
            valid = (df_sample['pressure'] > 0) & (df_sample['volume'] > 0)
            if valid.sum() > 0:
                pv_median = (df_sample.loc[valid, 'pressure'] * df_sample.loc[valid, 'volume']).median()
                p_isoenergy = pv_median / (v_range * V_target)
                # Only plot where iso-energy is within visible range
                visible = (p_isoenergy > 0) & (p_isoenergy < p_max * 2)
                ax.plot(v_range[visible], p_isoenergy[visible], 'k:', linewidth=1, alpha=0.5, label='PV = const')

        ax.set_xlabel(format_si_label('Normalized Volume', 'V/V_{target}', use_latex) if use_latex
                     else 'Normalized Volume (V/V_target)')
        ax.set_ylabel(format_si_label('Pressure', 'Pa', use_latex))
        ax.set_title(f'{labels.get(sched, sched)}: Cell Lifecycle Phase Portrait')
        ax.set_xlim(v_norm_min, v_norm_max)
        ax.set_ylim(0, p_max)
        ax.legend(loc='upper right', fontsize=6)
        apply_tufte_style(ax, grid=True)

    plt.tight_layout()
    save_figure(fig, output_dir / '03c_cell_lifecycle_portrait')


def plot_energy_budget_stacked(data: Dict, output_dir: Path, use_latex: bool = True,
                                style_config: Optional[Dict] = None) -> None:
    """
    Plot energy budget as stacked area chart with percentage breakdown.

    Narrative: Physical - "Where does mechanical energy flow?"

    Creates a stacked area chart showing the 4 energy components over time:
    - Surface tension energy (cortical tension)
    - Membrane elasticity energy (area elasticity)
    - Bending energy (membrane curvature)
    - Pressure energy (volumetric compression)

    Features:
    - Stacked area showing absolute or percentage contributions
    - Inset pie chart of final energy distribution
    - Per-scheduler comparison
    """
    print("  Plotting: energy_budget_stacked")

    # Check for aggregated simulation statistics with energy components
    has_data = False
    energy_cols = ['surface_tension_energy_mean', 'membrane_elasticity_energy_mean',
                   'bending_energy_mean', 'pressure_energy_mean']

    for key in data.keys():
        if 'simulation_stats_agg' in key:
            df = data[key]
            if df is not None and all(col in df.columns for col in energy_cols):
                has_data = True
                break

    if not has_data:
        print("    Skipped: No energy component data available")
        return

    # Get style config
    labels = style_config.get('labels', LABELS) if style_config else LABELS

    # Collect schedulers with energy data
    schedulers_with_data = []
    for key in sorted(data.keys()):
        if 'simulation_stats_agg' in key:
            df = data[key]
            if df is not None and all(col in df.columns for col in energy_cols):
                sched = key.replace('_simulation_stats_agg', '')
                schedulers_with_data.append(sched)

    if not schedulers_with_data:
        print("    Skipped: No energy component columns found")
        return

    n_schedulers = len(schedulers_with_data)
    fig, axes = plt.subplots(1, n_schedulers, figsize=(6 * n_schedulers, 4.5), squeeze=False)

    # Energy component metadata
    component_info = [
        ('surface_tension_energy_mean', 'Surface Tension', cm.viridis(0.15)),
        ('membrane_elasticity_energy_mean', 'Membrane Elasticity', cm.viridis(0.40)),
        ('bending_energy_mean', 'Bending', cm.viridis(0.65)),
        ('pressure_energy_mean', 'Pressure (PV)', cm.viridis(0.90)),
    ]

    for idx, sched in enumerate(schedulers_with_data):
        ax = axes[0, idx]
        df = data.get(f'{sched}_simulation_stats_agg')

        if df is None:
            continue

        # Get iteration as x-axis
        if 'iteration' in df.columns:
            x = df['iteration'].values
        else:
            x = np.arange(len(df))

        # Extract and stack energy components
        y_components = []
        component_names = []
        component_colors = []

        for col, name, color in component_info:
            if col in df.columns:
                values = df[col].values
                # Take absolute value and convert to femtojoules for readability
                values_fj = np.abs(values) * 1e15
                y_components.append(values_fj)
                component_names.append(name)
                component_colors.append(color)

        if not y_components:
            continue

        # Stacked area plot
        y_stack = np.vstack(y_components)

        ax.stackplot(x, y_stack, labels=component_names, colors=component_colors, alpha=0.85)

        # Add inset pie chart showing final distribution
        final_values = [y[-1] for y in y_components]
        total_final = sum(final_values)

        if total_final > 0:
            # Create inset axes
            inset_ax = ax.inset_axes([0.65, 0.55, 0.32, 0.40])
            wedges, texts, autotexts = inset_ax.pie(
                final_values,
                colors=component_colors,
                autopct=lambda pct: f'{pct:.0f}%' if pct > 5 else '',
                textprops={'fontsize': 5},
                startangle=90
            )
            for autotext in autotexts:
                autotext.set_fontsize(5)
            inset_ax.set_title('Final State', fontsize=6, pad=2)

        ax.set_xlabel('Iteration')
        ax.set_ylabel(format_si_label('Energy', 'fJ', use_latex))
        ax.set_title(f'{labels.get(sched, sched)}: Energy Budget Over Time')
        ax.legend(loc='upper left', fontsize=6, ncol=2)
        ax.set_xlim(left=0)
        ax.set_ylim(bottom=0)
        apply_tufte_style(ax, grid=True)

    plt.tight_layout()
    save_figure(fig, output_dir / '03d_energy_budget')


# =============================================================================
# SECTION 6: HPC Performance Plots
# =============================================================================

def plot_scaling_analysis(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Log-log plot of iteration time vs cell count with O(N^(4/3)) theory.

    Features:
    - Power law fit with exponent annotation
    - Theoretical complexity overlay
    - Residual analysis
    """
    print("  Plotting: scaling_analysis")

    fig, axes = plt.subplots(2, 1, figsize=FIGSIZE_DOUBLE, gridspec_kw={'height_ratios': [3, 1]}, sharex=True)
    ax1, ax2 = axes

    style = data.get('style_config', {})
    labels = style.get('labels', LABELS)

    for mode, color, label in iter_schedulers(data):
        df = data.get(f'{mode}_computational_clean')
        if df is None or 'iter_per_sec' not in df.columns or 'cells' not in df.columns:
            continue

        cells = df['cells'].values
        iter_rate = df['iter_per_sec'].values

        # Filter valid data
        valid = (iter_rate > 0.1) & (cells > 1)
        cells = cells[valid]
        time_per_iter = 1.0 / iter_rate[valid]

        if len(cells) < 10:
            continue

        # Scatter plot
        ax1.scatter(cells, time_per_iter, s=8, alpha=0.4, color=color, label=label)

        # Power law fit with bootstrapped confidence intervals
        try:
            # Use power_law_with_ci for rigorous uncertainty quantification
            fit_result = power_law_with_ci(cells, time_per_iter, n_bootstrap=500)

            if not np.isnan(fit_result['exponent']):
                # Plot fit line
                cells_fit = np.logspace(np.log10(cells.min()), np.log10(cells.max()), 50)
                time_fit = fit_result['coefficient'] * np.power(cells_fit, fit_result['exponent'])

                # Include 95% CI on exponent in label
                ci_low, ci_high = fit_result['exponent_ci_95']
                if use_latex and not np.isnan(ci_low):
                    fit_label = f'{label}: $\\alpha = {fit_result["exponent"]:.2f}$ [95\\% CI: {ci_low:.2f}-{ci_high:.2f}]'
                elif not np.isnan(ci_low):
                    fit_label = f'{label}: α = {fit_result["exponent"]:.2f} [95% CI: {ci_low:.2f}-{ci_high:.2f}]'
                elif use_latex:
                    fit_label = f'{label}: $\\alpha = {fit_result["exponent"]:.2f}$'
                else:
                    fit_label = f'{label}: α = {fit_result["exponent"]:.2f}'

                ax1.plot(cells_fit, time_fit, '--', color=color, linewidth=1.5, label=fit_label)

                # Residuals
                predicted = fit_result['coefficient'] * np.power(cells, fit_result['exponent'])
                residuals = np.log10(time_per_iter) - np.log10(predicted)
                valid_res = np.isfinite(residuals)
                ax2.scatter(cells[valid_res], residuals[valid_res], s=5, alpha=0.3, color=color)

        except Exception as e:
            print(f"    Warning: Power law fit failed for {mode}: {e}")

    # Theoretical O(N^4/3) line
    cells_theory = np.logspace(0, 3, 50)
    # Normalize to match data
    T_ref = 0.01
    N_ref = 100
    time_theory = T_ref * np.power(cells_theory / N_ref, THEORETICAL_COMPLEXITY_EXPONENT)

    if use_latex:
        theory_label = r'Theory: $O(N^{4/3})$'
    else:
        theory_label = 'Theory: O(N^(4/3))'

    ax1.plot(cells_theory, time_theory, 'k:', linewidth=1.2, label=theory_label)

    ax1.set_ylabel(format_si_label('Time per Iteration', 's', use_latex))
    ax1.set_xscale('log')
    ax1.set_yscale('log')
    ax1.set_ylim(1e-2, 10)  # Y-axis max 10 seconds (user-requested)
    ax1.legend(fontsize=6, loc='upper left')
    apply_tufte_style(ax1, grid=True)

    ax2.set_xlabel('Cell Count')
    ax2.set_ylabel('Residual (log)')
    ax2.axhline(0, color='gray', linestyle='--', linewidth=0.5)
    ax2.set_xscale('log')
    apply_tufte_style(ax2, grid=True)

    plt.tight_layout()
    save_figure(fig, output_dir / '04_scaling_analysis')


def plot_phase_timing_breakdown(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Combined plot for HPC phase timings showing all phases overlaid.

    Phases: mesh_refinement, contact_detection, polarization, time_integration
    """
    print("  Plotting: phase_timing_breakdown")

    df = data.get('adaptive_phase')
    if df is None:
        print("    Skipped: No phase timing data available")
        return

    t = compute_time_minutes(df)
    if len(t) == 0:
        print("    Skipped: Empty phase timing data")
        return

    # Phase columns
    phases = [
        ('mesh_refinement_ms', 'Mesh Refinement', COLORS['mesh_refinement']),
        ('contact_detection_ms', 'Contact Detection', COLORS['contact_detection']),
        ('polarization_internal_forces_ms', 'Polarization', COLORS['polarization']),
        ('time_integration_ms', 'Time Integration', COLORS['time_integration']),
    ]

    # Filter to available phases
    available_phases = [(col, label, color) for col, label, color in phases if col in df.columns]

    if not available_phases:
        print("    Skipped: No phase columns found")
        return

    # Create single plot with all phases overlaid
    fig, ax = plt.subplots(figsize=FIGSIZE_DOUBLE)

    # Compute total time per timestep for percentage calculations
    total_time_per_step = sum(df[col].values for col, _, _ in available_phases)
    mean_total = np.mean(total_time_per_step)

    # Plot each phase
    for col, label, color in available_phases:
        values = df[col].values
        mean_pct = 100 * np.mean(values) / mean_total if mean_total > 0 else 0
        mean_val = np.mean(values)

        # Line plot with label including percentage
        ax.plot(t, values, color=color, linewidth=1.5,
                label=f'{label} ({mean_pct:.1f}%, μ={mean_val:.0f}ms)')
        ax.fill_between(t, 0, values, color=color, alpha=0.15)

    ax.set_xlabel(format_si_label('Simulation Time', 'min', use_latex))
    ax.set_ylabel(format_si_label('Phase Duration', 'ms', use_latex))
    ax.set_title('Phase Timing Breakdown', fontsize=10, fontweight='bold')
    ax.legend(loc='upper left', fontsize=7)
    ax.set_xlim(left=0)
    ax.set_ylim(bottom=0)
    apply_tufte_style(ax, grid=True)

    plt.tight_layout()
    save_figure(fig, output_dir / '05_phase_timing_breakdown')


def plot_roofline_model(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Roofline model for performance ceiling analysis.

    Note: Requires FLOP counting instrumentation for actual placement.
    This plot shows the theoretical roofline and estimated performance.
    """
    print("  Plotting: roofline_model")

    fig, ax = plt.subplots(figsize=FIGSIZE_DOUBLE)

    # System specifications (typical workstation)
    PEAK_GFLOPS = 250    # 8 cores × 3.9 GHz × 8 FLOP/cycle (AVX2)
    PEAK_BW_GBS = 45     # GB/s DDR4-2933

    # Arithmetic intensity range
    AI_range = np.logspace(-2, 2, 100)

    # Roofline ceilings
    compute_ceiling = np.full_like(AI_range, PEAK_GFLOPS)
    memory_ceiling = PEAK_BW_GBS * AI_range
    roofline = np.minimum(compute_ceiling, memory_ceiling)

    # Plot roofline
    ax.plot(AI_range, roofline, 'k-', linewidth=2, label='Roofline')
    ax.fill_between(AI_range, 0, roofline, alpha=0.1, color='gray')

    # Ridge point annotation
    ridge_AI = PEAK_GFLOPS / PEAK_BW_GBS
    ax.axvline(ridge_AI, color='gray', linestyle=':', linewidth=1)
    ax.text(ridge_AI * 1.1, PEAK_GFLOPS * 0.8, f'Ridge: {ridge_AI:.1f} FLOP/B',
            fontsize=7, rotation=0)

    # Add annotations for memory-bound and compute-bound regions
    ax.text(0.05, PEAK_GFLOPS * 0.3, 'Memory\nBound', fontsize=8, ha='center', color='blue')
    ax.text(50, PEAK_GFLOPS * 0.7, 'Compute\nBound', fontsize=8, ha='center', color='red')

    # Estimate SimuCell3D performance (rough estimate based on typical DCM operations)
    # Contact detection: ~10 FLOP/B (memory bound)
    # Force integration: ~50 FLOP/B (approaching compute bound)
    estimated_AI = [5, 15, 30]
    estimated_perf = [PEAK_BW_GBS * ai if ai < ridge_AI else PEAK_GFLOPS * 0.6
                     for ai in estimated_AI]
    ax.scatter(estimated_AI, estimated_perf, s=80, c=[COLORS['adaptive']],
               marker='*', zorder=10, label='SimuCell3D (estimated)')

    ax.set_xlabel('Arithmetic Intensity (FLOP/Byte)')
    ax.set_ylabel('Performance (GFLOP/s)')
    ax.set_xscale('log')
    ax.set_yscale('log')
    ax.set_xlim(0.01, 100)
    ax.set_ylim(1, PEAK_GFLOPS * 2)
    ax.legend(loc='lower right', fontsize=7)
    apply_tufte_style(ax, grid=True)

    # Title with system specs
    ax.set_title(f'Roofline Model (Peak: {PEAK_GFLOPS} GFLOP/s, BW: {PEAK_BW_GBS} GB/s)',
                 fontsize=9)

    save_figure(fig, output_dir / '06_roofline_model')


def plot_load_balance_heatmap(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Computational load comparison over time using iteration rate.

    Shows v1 vs adaptive scheduler iteration rates as line plot for clearer
    comparison than heatmap (single-thread data makes heatmap uninformative).
    """
    print("  Plotting: load_balance")

    fig, ax = plt.subplots(figsize=FIGSIZE_DOUBLE)

    has_data = False
    for mode, color, label in iter_schedulers(data):
        df_comp = data.get(f'{mode}_computational_clean')
        if df_comp is None or 'iter_per_sec' not in df_comp.columns:
            continue
        t = compute_time_minutes(df_comp)
        iter_rate = df_comp['iter_per_sec'].values

        if len(t) > 0:
            has_data = True
            # Plot with smoothed trend line
            ax.scatter(t, iter_rate, s=8, alpha=0.3, color=color)
            # Smooth for trend visualization
            iter_smooth = smooth_signal(iter_rate, window_length=min(11, len(iter_rate)//2*2+1), polyorder=2)
            ax.plot(t, iter_smooth, color=color, label=label, linewidth=1.5)

    if not has_data:
        ax.text(0.5, 0.5, 'Computational data not available',
                ha='center', va='center', transform=ax.transAxes,
                fontsize=10, color='gray')

    ax.set_xlabel(format_si_label('Time', 'min', use_latex))
    ax.set_ylabel('Iteration Rate (iter/s)')
    ax.set_title('Computational Throughput Over Time', fontsize=9)
    ax.legend(loc='upper right', fontsize=7)

    # Use log scale only if data supports it (all positive values)
    x_min, x_max = ax.get_xlim()
    y_min, y_max = ax.get_ylim()
    if x_min > 0 and x_max > 0:
        ax.set_xscale('log')
    if y_min > 0 and y_max > 0:
        ax.set_yscale('log')

    apply_tufte_style(ax, grid=True)

    save_figure(fig, output_dir / '07_load_balance')


# =============================================================================
# SECTION 7: Statistical Comparison Plots
# =============================================================================

def plot_v1_vs_adaptive_comparison(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Violin plots comparing schedulers with statistical tests.

    Features:
    - Violin plots for multiple metrics
    - Block bootstrap test p-values (handles time series autocorrelation)
    - Significance stars
    - Compares first two detected schedulers
    """
    print("  Plotting: scheduler_comparison")

    # Get first two detected schedulers
    schedulers = list(iter_schedulers(data))
    if len(schedulers) < 2:
        print("    Skipping: Need at least 2 schedulers for comparison")
        return

    sched1_name, sched1_color, sched1_label = schedulers[0]
    sched2_name, sched2_color, sched2_label = schedulers[1]

    fig, axes = plt.subplots(1, 3, figsize=FIGSIZE_DOUBLE)

    metrics = [
        ('mean_pressure', 'biological', 'Mean Pressure', 'Pa'),
        ('iter_per_sec', 'computational_clean', 'Iteration Rate', 'iter/s'),
        ('cells', 'computational', 'Cell Count', ''),
    ]

    for ax, (metric, data_type, name, unit) in zip(axes, metrics):
        sched1_key = f'{sched1_name}_{data_type}'
        sched2_key = f'{sched2_name}_{data_type}'

        sched1_df = data.get(sched1_key)
        sched2_df = data.get(sched2_key)

        if sched1_df is None or sched2_df is None or metric not in sched1_df.columns or metric not in sched2_df.columns:
            ax.text(0.5, 0.5, 'Data not available', ha='center', va='center',
                    transform=ax.transAxes, fontsize=8, color='gray')
            ax.set_title(name, fontsize=9)
            continue

        sched1_data = sched1_df[metric].dropna().values
        sched2_data = sched2_df[metric].dropna().values

        if len(sched1_data) == 0 or len(sched2_data) == 0:
            ax.text(0.5, 0.5, 'Insufficient data', ha='center', va='center',
                    transform=ax.transAxes, fontsize=8, color='gray')
            continue

        # Create violin plots
        positions = [1, 2]
        parts = ax.violinplot([sched1_data, sched2_data], positions=positions,
                              showmeans=True, showmedians=True, widths=0.7)

        # Color violins dynamically
        violin_colors = [sched1_color, sched2_color]
        for pc, color in zip(parts['bodies'], violin_colors):
            pc.set_facecolor(color)
            pc.set_alpha(0.6)

        # Statistical test (using block bootstrap for time series, not Mann-Whitney U)
        if len(sched1_data) > 10 and len(sched2_data) > 10:
            try:
                # Block bootstrap handles autocorrelation in time series
                boot_result = block_bootstrap_test(sched1_data, sched2_data, block_size=5)
                p_value = boot_result['p_value']
                sig_text = get_significance_stars(p_value)

                # Cliff's delta effect size (doesn't assume normality)
                delta, effect_interp = cliffs_delta(sched1_data, sched2_data)

                y_max = max(sched1_data.max(), sched2_data.max())
                y_pos = y_max * 1.1

                # Draw significance bar
                ax.plot([1, 1, 2, 2], [y_max * 1.02, y_pos, y_pos, y_max * 1.02], 'k-', linewidth=0.8)
                ax.text(1.5, y_pos * 1.02, sig_text, ha='center', fontsize=10, fontweight='bold')

                # Add p-value and effect size
                if not np.isnan(p_value):
                    ax.text(1.5, y_pos * 0.95, f'p={p_value:.3f}', ha='center', fontsize=6)
                if not np.isnan(delta):
                    ax.text(1.5, y_pos * 0.88, f'd={delta:.2f} ({effect_interp})', ha='center', fontsize=5)

            except Exception as e:
                print(f"    Warning: Statistical test failed for {metric}: {e}")

        # Add sample sizes
        ax.text(1, sched1_data.min() * 0.9, f'n={len(sched1_data)}', ha='center', fontsize=6)
        ax.text(2, sched2_data.min() * 0.9, f'n={len(sched2_data)}', ha='center', fontsize=6)

        ax.set_xticks(positions)
        ax.set_xticklabels(['v1', 'Adaptive'])
        if unit:
            ax.set_ylabel(format_si_label(name, unit, use_latex))
        else:
            ax.set_ylabel(name)
        apply_tufte_style(ax, grid=True)

    plt.tight_layout()
    save_figure(fig, output_dir / '08_v1_vs_adaptive_comparison')


def plot_speedup_analysis(data: Dict, output_dir: Path, use_latex: bool = True) -> None:
    """
    Cell production ratio evolution with confidence intervals.

    Shows Adaptive/v1 cell count ratio over time at equivalent simulation times.
    Values >1 indicate adaptive produced more cells at the same simulation time.

    Features:
    - Cell count ratio vs simulation time
    - Rolling average with confidence band
    - Geometric mean annotation
    """
    print("  Plotting: performance_ratio")

    # Get cell count data from both schedulers
    v1_comp = data.get('v1_computational_clean')
    if v1_comp is None:
        v1_comp = data.get('v1_computational')
    adap_comp = data.get('adaptive_computational_clean')
    if adap_comp is None:
        adap_comp = data.get('adaptive_computational')

    if v1_comp is None or adap_comp is None:
        print("    Skipped: Missing computational data")
        return

    if 'cells' not in v1_comp.columns or 'cells' not in adap_comp.columns:
        print("    Skipped: No cell count data available")
        return

    fig, axes = plt.subplots(2, 1, figsize=FIGSIZE_DOUBLE)  # Don't share x-axis (time vs ratio)
    ax1, ax2 = axes

    # Get time and cell counts for both schedulers
    t_v1 = compute_time_minutes(v1_comp)
    t_adap = compute_time_minutes(adap_comp)
    cells_v1 = v1_comp['cells'].values
    cells_adap = adap_comp['cells'].values

    if len(t_v1) == 0 or len(t_adap) == 0:
        print("    Skipped: Empty computational time series")
        plt.close(fig)
        return

    # Interpolate to common time grid for ratio calculation
    t_min = max(t_v1.min(), t_adap.min())
    t_max = min(t_v1.max(), t_adap.max())
    t_common = np.linspace(t_min, t_max, min(len(t_v1), len(t_adap), 200))

    # Interpolate cell counts to common time grid
    cells_v1_interp = np.interp(t_common, t_v1, cells_v1)
    cells_adap_interp = np.interp(t_common, t_adap, cells_adap)

    # Compute performance ratio based on cell count ratio
    # Ratio > 1 means adaptive produced more cells at same simulation time
    valid = cells_v1_interp > 10  # Avoid division issues with very small counts
    speedup = np.where(valid, cells_adap_interp / cells_v1_interp, np.nan)

    # Filter invalid ratios
    valid = np.isfinite(speedup) & (speedup > 0) & (speedup < 10)
    t_valid = t_common[valid]
    speedup_valid = speedup[valid]

    if len(speedup_valid) < 10:
        print("    Skipped: Insufficient valid speedup data")
        plt.close(fig)
        return

    # Panel 1: Raw speedup
    ax1.scatter(t_valid, speedup_valid, s=10, alpha=0.4, color=COLORS['adaptive'])

    # Smoothed trend using Savitzky-Golay filter (preserves dynamics better than rolling mean)
    window = min(21, len(speedup_valid) // 3)
    if window > 3:
        if window % 2 == 0:
            window -= 1  # Must be odd for savgol
        smoothed_mean = smooth_signal(speedup_valid, window_length=window, polyorder=3)

        # Rolling std still useful for uncertainty estimation
        speedup_series = pd.Series(speedup_valid)
        rolling_std = speedup_series.rolling(window=window, min_periods=1, center=True).std().values

        ax1.plot(t_valid, smoothed_mean, color=COLORS['adaptive'], linewidth=1.5,
                label=f'Smoothed Trend')
        add_error_band(ax1, t_valid, smoothed_mean, rolling_std, COLORS['adaptive'], alpha=0.2)

    ax1.axhline(1.0, color='gray', linestyle='--', linewidth=1, label='Parity (equal cells)')
    ax1.set_xlabel(format_si_label('Simulation Time', 'min', use_latex))
    ax1.set_ylabel('Cell Count Ratio (Adaptive / v1)')
    ax1.legend(loc='upper right', fontsize=6)
    ax1.set_title('A. Cell Production Ratio Over Time', fontsize=9, fontweight='bold', loc='left')
    apply_tufte_style(ax1, grid=True)

    # Geometric mean annotation
    geom_mean = np.exp(np.mean(np.log(speedup_valid)))
    if geom_mean < 1.0:
        fewer_pct = (1.0 - geom_mean) * 100
        if use_latex:
            annotation = f'Geometric mean: ${geom_mean:.2f}\\times$\n({fewer_pct:.0f}\\% fewer cells)'
        else:
            annotation = f'Geometric mean: {geom_mean:.2f}×\n({fewer_pct:.0f}% fewer cells)'
        ax1.text(0.02, 0.98, annotation, transform=ax1.transAxes, fontsize=7, va='top',
                bbox=dict(boxstyle='round,pad=0.3', facecolor='lightyellow', edgecolor='orange', alpha=0.8))
    else:
        more_pct = (geom_mean - 1.0) * 100
        if use_latex:
            annotation = f'Geometric mean: ${geom_mean:.2f}\\times$\n({more_pct:.0f}\\% more cells)'
        else:
            annotation = f'Geometric mean: {geom_mean:.2f}×\n({more_pct:.0f}% more cells)'
        ax1.text(0.02, 0.98, annotation, transform=ax1.transAxes, fontsize=7, va='top',
                bbox=dict(boxstyle='round,pad=0.3', facecolor='lightgreen', edgecolor='green', alpha=0.8))

    # Panel 2: Cell ratio histogram with improved binning
    # Use sensible bins centered around 1.0
    bin_min = max(0, np.percentile(speedup_valid, 1) - 0.1)
    bin_max = min(3, np.percentile(speedup_valid, 99) + 0.1)
    bins = np.linspace(bin_min, bin_max, 31)

    ax2.hist(speedup_valid, bins=bins, color=COLORS['adaptive'], alpha=0.7, edgecolor='white')
    ax2.axvline(1.0, color='gray', linestyle='--', linewidth=1, label='Parity')
    ax2.axvline(geom_mean, color='red', linestyle='-', linewidth=1.5, label=f'Geom. mean = {geom_mean:.2f}')
    ax2.set_xlabel('Cell Count Ratio (>1 = more cells, <1 = fewer cells)')
    ax2.set_ylabel('Frequency')
    ax2.set_title('B. Cell Production Ratio Distribution', fontsize=9, fontweight='bold', loc='left')
    ax2.legend(loc='upper right', fontsize=6)
    apply_tufte_style(ax2, grid=True)

    plt.tight_layout()
    save_figure(fig, output_dir / '09_performance_ratio')


def plot_scheduler_radar(data: Dict, output_dir: Path, use_latex: bool = True,
                          style_config: Optional[Dict] = None) -> None:
    """
    Plot multi-dimensional scheduler comparison as radar/spider chart.

    Narrative: Computational - "How do schedulers compare across dimensions?"

    Creates a radar chart with 6 normalized axes (0-1):
    1. Throughput (cells/second at final cell count)
    2. Load balance (1 - coefficient of variation of iteration time)
    3. Scalability (inverse of power law exponent deviation from 4/3)
    4. Predictability (1 - CV of iteration time)
    5. Energy conservation (inverse of energy drift)
    6. Cell production rate (cells produced per wall-clock hour)

    Each scheduler is shown as a colored polygon overlay.
    """
    print("  Plotting: scheduler_radar")

    # Get scheduler info
    schedulers = data.get('schedulers', [])
    if len(schedulers) < 1:
        print("    Skipped: No scheduler data")
        return

    style = style_config if style_config else {'colors': COLORS, 'labels': LABELS}
    colors = style.get('colors', COLORS)
    labels = style.get('labels', LABELS)

    # Define the 6 radar axes
    axes_labels = [
        'Throughput',
        'Load Balance',
        'Scalability',
        'Predictability',
        'Energy Stability',
        'Cell Production'
    ]
    n_axes = len(axes_labels)

    # Compute metrics for each scheduler
    sched_metrics = {}

    for sched in schedulers:
        name = sched.name
        metrics = []

        # Get data
        comp_df = get_dataframe(data, f'{name}_computational_clean', f'{name}_computational')
        bio_df = get_dataframe(data, f'{name}_biological_clean', f'{name}_biological')

        # 1. Throughput (iter_per_sec at final state, normalized 0-1)
        throughput = 0.0
        if comp_df is not None and 'iter_per_sec' in comp_df.columns:
            # Use median of last 10% of data for stability
            n = len(comp_df)
            final_rates = comp_df['iter_per_sec'].iloc[int(0.9 * n):].dropna()
            if len(final_rates) > 0:
                throughput = final_rates.median()
        metrics.append(throughput)

        # 2. Load Balance (1 - CV of iteration time, higher is better)
        load_balance = 0.0
        if comp_df is not None and 'iter_per_sec' in comp_df.columns:
            rates = comp_df['iter_per_sec'].dropna()
            if len(rates) > 10:
                cv = rates.std() / rates.mean() if rates.mean() > 0 else 1.0
                load_balance = max(0, 1 - cv)  # Invert CV so higher is better
        metrics.append(load_balance)

        # 3. Scalability (how close to O(N^4/3) theory)
        scalability = 0.0
        if comp_df is not None and 'cells' in comp_df.columns and 'iter_per_sec' in comp_df.columns:
            cells = comp_df['cells'].values
            iter_rate = comp_df['iter_per_sec'].values
            valid = (iter_rate > 0.1) & (cells > 10)
            if valid.sum() > 20:
                fit_result = power_law_with_ci(cells[valid], 1.0 / iter_rate[valid])
                if not np.isnan(fit_result['exponent']):
                    # Deviation from theoretical 4/3 exponent
                    deviation = abs(fit_result['exponent'] - THEORETICAL_COMPLEXITY_EXPONENT)
                    scalability = max(0, 1 - deviation / 0.5)  # Normalize: 0.5 deviation = 0 score
        metrics.append(scalability)

        # 4. Predictability (consistency of iteration time)
        predictability = 0.0
        if comp_df is not None and 'iter_per_sec' in comp_df.columns:
            rates = comp_df['iter_per_sec'].dropna()
            if len(rates) > 10:
                # Low variance = high predictability
                cv = rates.std() / rates.mean() if rates.mean() > 0 else 1.0
                predictability = max(0, 1 - cv * 0.5)  # Scale CV effect
        metrics.append(predictability)

        # 5. Energy Stability (inverse of energy drift)
        energy_stability = 0.5  # Default mid-range if no data
        if bio_df is not None:
            if 'total_kinetic_energy' in bio_df.columns:
                E_total = bio_df['total_kinetic_energy'].values + bio_df.get('total_potential_energy', pd.Series([0]*len(bio_df))).values
            elif 'estimated_total_energy' in bio_df.columns:
                E_total = bio_df['estimated_total_energy'].values
            else:
                E_total = None

            if E_total is not None and len(E_total) > 10:
                E_total = E_total[np.isfinite(E_total)]
                if len(E_total) > 10:
                    # Compute relative drift
                    drift = np.abs(np.gradient(E_total)).mean()
                    mean_E = np.abs(E_total).mean()
                    relative_drift = drift / mean_E if mean_E > 0 else 1.0
                    energy_stability = max(0, 1 - relative_drift * 10)  # Scale appropriately
        metrics.append(energy_stability)

        # 6. Cell Production Rate (cells produced per wall-clock minute)
        cell_production = 0.0
        if comp_df is not None and 'cells' in comp_df.columns and 'timestamp' in comp_df.columns:
            t = compute_time_minutes(comp_df)
            cells = comp_df['cells'].values
            if len(t) > 1:
                t_arr = np.asarray(t)
                if t_arr[-1] > t_arr[0]:
                    cell_production = (cells[-1] - cells[0]) / (t_arr[-1] - t_arr[0])  # cells/minute
        metrics.append(cell_production)

        sched_metrics[name] = metrics

    # Normalize all metrics to 0-1 range across schedulers
    n_scheds = len(sched_metrics)
    if n_scheds == 0:
        print("    Skipped: No scheduler metrics computed")
        return

    # Find min/max for each axis across all schedulers
    all_values = np.array(list(sched_metrics.values()))
    axis_mins = all_values.min(axis=0)
    axis_maxs = all_values.max(axis=0)

    # Normalize (handle zero range)
    for name in sched_metrics:
        normalized = []
        for i, val in enumerate(sched_metrics[name]):
            if axis_maxs[i] > axis_mins[i]:
                norm_val = (val - axis_mins[i]) / (axis_maxs[i] - axis_mins[i])
            else:
                norm_val = 0.5  # If all values same, use midpoint
            normalized.append(np.clip(norm_val, 0, 1))
        sched_metrics[name] = normalized

    # Create radar plot
    fig, ax = plt.subplots(figsize=(7, 7), subplot_kw=dict(polar=True))

    # Compute angles for each axis
    angles = np.linspace(0, 2 * np.pi, n_axes, endpoint=False).tolist()
    angles += angles[:1]  # Close the polygon

    # Plot each scheduler
    for sched in schedulers:
        name = sched.name
        if name not in sched_metrics:
            continue

        values = sched_metrics[name]
        values += values[:1]  # Close the polygon

        color = colors.get(name, cm.viridis(0.5))
        label = labels.get(name, name)

        ax.plot(angles, values, 'o-', linewidth=2, color=color, label=label, markersize=6)
        ax.fill(angles, values, alpha=0.25, color=color)

    # Configure axes
    ax.set_xticks(angles[:-1])
    ax.set_xticklabels(axes_labels, fontsize=8)
    ax.set_ylim(0, 1)
    ax.set_yticks([0.25, 0.5, 0.75, 1.0])
    ax.set_yticklabels(['0.25', '0.50', '0.75', '1.00'], fontsize=6, color='gray')
    ax.grid(True, alpha=0.3)

    ax.set_title('Multi-Dimensional Scheduler Comparison', fontsize=11, fontweight='bold', pad=20)
    ax.legend(loc='upper right', bbox_to_anchor=(1.2, 1.0), fontsize=8)

    plt.tight_layout()
    save_figure(fig, output_dir / '10_scheduler_radar')


def plot_roofline_with_phases(data: Dict, output_dir: Path, use_latex: bool = True,
                               style_config: Optional[Dict] = None) -> None:
    """
    Plot enhanced roofline model with actual phase performance data.

    Narrative: Computational - "What limits simulation performance?"

    Creates a log-log roofline plot showing:
    - Memory bandwidth ceiling (diagonal line)
    - Compute ceiling (horizontal line)
    - Actual performance points for each simulation phase
    - Bottleneck identification (memory-bound vs compute-bound)

    Uses actual phase timing data and estimated FLOPs to place performance points.
    """
    print("  Plotting: roofline_with_phases")

    # System specifications (typical workstation - should be parameterized)
    PEAK_GFLOPS = 250    # 8 cores × 3.9 GHz × 8 FLOP/cycle (AVX2)
    PEAK_BW_GBS = 45     # GB/s DDR4-2933

    fig, ax = plt.subplots(figsize=FIGSIZE_DOUBLE)

    # Arithmetic intensity range
    AI_range = np.logspace(-2, 2, 100)

    # Roofline ceilings
    compute_ceiling = np.full_like(AI_range, PEAK_GFLOPS)
    memory_ceiling = PEAK_BW_GBS * AI_range
    roofline = np.minimum(compute_ceiling, memory_ceiling)

    # Plot roofline
    ax.plot(AI_range, roofline, 'k-', linewidth=2.5, label='Roofline', zorder=1)
    ax.fill_between(AI_range, 0, roofline, alpha=0.05, color='gray')

    # Ridge point
    ridge_AI = PEAK_GFLOPS / PEAK_BW_GBS
    ax.axvline(ridge_AI, color='gray', linestyle=':', linewidth=1, alpha=0.7)
    ax.text(ridge_AI * 1.2, PEAK_GFLOPS * 0.6, f'Ridge: {ridge_AI:.1f}',
            fontsize=7, rotation=0, alpha=0.8)

    # Phase-specific FLOP estimates per byte (rough estimates based on algorithmic analysis)
    # These are approximate and would ideally come from profiling
    phase_characteristics = {
        'mesh_refinement_ms': {
            'name': 'Mesh Refinement',
            'ai_estimate': 3.0,  # Low AI - memory bound (mesh traversal)
            'color': PHASE_COLORS.get('mesh_refinement', cm.viridis(0.15)),
            'marker': 'o'
        },
        'contact_detection_ms': {
            'name': 'Contact Detection',
            'ai_estimate': 8.0,  # Medium AI (spatial hashing + comparisons)
            'color': PHASE_COLORS.get('contact_detection', cm.viridis(0.45)),
            'marker': 's'
        },
        'polarization_internal_forces_ms': {
            'name': 'Force Computation',
            'ai_estimate': 25.0,  # Higher AI (vector math per face)
            'color': PHASE_COLORS.get('polarization', cm.viridis(0.65)),
            'marker': '^'
        },
        'time_integration_ms': {
            'name': 'Time Integration',
            'ai_estimate': 15.0,  # Medium-high AI (Euler updates)
            'color': PHASE_COLORS.get('time_integration', cm.viridis(0.85)),
            'marker': 'D'
        },
    }

    # Get style config
    style = style_config if style_config else {'colors': COLORS, 'labels': LABELS}
    sched_labels = style.get('labels', LABELS)

    # Plot performance points for each scheduler
    schedulers = data.get('schedulers', [])
    legend_handles = []

    for sched in schedulers:
        name = sched.name
        phase_df = data.get(f'{name}_phase')
        comp_df = get_dataframe(data, f'{name}_computational_clean', f'{name}_computational')

        if phase_df is None:
            continue

        # Get cell count for FLOP estimation
        final_cells = 1000  # Default
        if comp_df is not None and 'cells' in comp_df.columns:
            final_cells = int(comp_df['cells'].iloc[-1])

        sched_label = sched_labels.get(name, name)

        for phase_col, phase_info in phase_characteristics.items():
            if phase_col not in phase_df.columns:
                continue

            # Get mean phase time (convert ms to seconds)
            phase_time_s = phase_df[phase_col].mean() / 1000.0
            if phase_time_s <= 0 or np.isnan(phase_time_s):
                continue

            # Estimate performance in GFLOP/s
            # Rough FLOP estimate: cells × faces_per_cell × ops_per_face
            estimated_flops = final_cells * 100 * 50  # Very rough estimate
            perf_gflops = (estimated_flops / phase_time_s) / 1e9

            # Clamp to reasonable range
            perf_gflops = np.clip(perf_gflops, 0.1, PEAK_GFLOPS * 0.95)

            # Plot point
            ai = phase_info['ai_estimate']
            ax.scatter(ai, perf_gflops, s=120, marker=phase_info['marker'],
                      color=phase_info['color'], edgecolors='white', linewidths=0.5,
                      zorder=5, alpha=0.85)

            # Add label for this phase
            ax.annotate(phase_info['name'], (ai, perf_gflops),
                       xytext=(5, 5), textcoords='offset points',
                       fontsize=5, alpha=0.7)

    # Create legend for phases
    for phase_col, phase_info in phase_characteristics.items():
        handle = plt.Line2D([0], [0], marker=phase_info['marker'], color='w',
                           markerfacecolor=phase_info['color'], markersize=8,
                           label=phase_info['name'])
        legend_handles.append(handle)

    # Add regions annotations
    ax.text(0.08, PEAK_GFLOPS * 0.15, 'Memory\nBound', fontsize=9, ha='center',
            color='#1f77b4', fontweight='bold', alpha=0.7)
    ax.text(60, PEAK_GFLOPS * 0.5, 'Compute\nBound', fontsize=9, ha='center',
            color='#d62728', fontweight='bold', alpha=0.7)

    ax.set_xlabel('Arithmetic Intensity (FLOP/Byte)')
    ax.set_ylabel('Performance (GFLOP/s)')
    ax.set_xscale('log')
    ax.set_yscale('log')
    ax.set_xlim(0.01, 100)
    ax.set_ylim(0.1, PEAK_GFLOPS * 1.5)
    ax.legend(handles=legend_handles, loc='lower right', fontsize=7, ncol=2)
    ax.set_title(f'Computational Roofline Analysis\n(Peak: {PEAK_GFLOPS} GFLOP/s, BW: {PEAK_BW_GBS} GB/s)',
                 fontsize=9)
    apply_tufte_style(ax, grid=True)

    save_figure(fig, output_dir / '10b_roofline_phases')


# =============================================================================
# SECTION 8: HTML Report and Manifest Generation
# =============================================================================

# HTML Report Template (Jinja2)
HTML_REPORT_TEMPLATE = """
<!DOCTYPE html>
<html lang="en">
<head>
    <meta charset="UTF-8">
    <meta name="viewport" content="width=device-width, initial-scale=1.0">
    <title>SimuCell3D Benchmark Report - {{ timestamp }}</title>
    <style>
        :root { --primary: #2c3e50; --secondary: #3498db; --accent: #e74c3c; --bg: #f8f9fa; }
        * { box-sizing: border-box; margin: 0; padding: 0; }
        body { font-family: 'Segoe UI', Tahoma, Geneva, Verdana, sans-serif; background: var(--bg); color: var(--primary); line-height: 1.6; }
        .container { max-width: 1200px; margin: 0 auto; padding: 20px; }
        header { background: linear-gradient(135deg, var(--primary), var(--secondary)); color: white; padding: 40px 20px; margin-bottom: 30px; border-radius: 8px; }
        header h1 { font-size: 2.2em; margin-bottom: 10px; }
        header .meta { opacity: 0.9; font-size: 0.95em; }
        .summary-cards { display: grid; grid-template-columns: repeat(auto-fit, minmax(200px, 1fr)); gap: 20px; margin-bottom: 30px; }
        .card { background: white; padding: 20px; border-radius: 8px; box-shadow: 0 2px 8px rgba(0,0,0,0.08); }
        .card h3 { color: var(--secondary); font-size: 0.85em; text-transform: uppercase; letter-spacing: 1px; margin-bottom: 5px; }
        .card .value { font-size: 2em; font-weight: bold; color: var(--primary); }
        .card .unit { font-size: 0.8em; color: #666; }
        .narrative { margin-bottom: 40px; }
        .narrative h2 { color: var(--primary); border-left: 4px solid var(--secondary); padding-left: 15px; margin-bottom: 20px; font-size: 1.5em; }
        .narrative-desc { color: #555; margin-bottom: 20px; font-style: italic; }
        .plot-grid { display: grid; grid-template-columns: repeat(auto-fit, minmax(400px, 1fr)); gap: 25px; }
        .plot-container { background: white; border-radius: 8px; overflow: hidden; box-shadow: 0 2px 8px rgba(0,0,0,0.08); }
        .plot-header { padding: 15px 20px; border-bottom: 1px solid #eee; }
        .plot-header h3 { font-size: 1.1em; color: var(--primary); margin-bottom: 5px; }
        .plot-header p { font-size: 0.85em; color: #666; }
        .plot-image { width: 100%; display: block; }
        .plot-footer { padding: 15px 20px; background: #fafafa; font-size: 0.85em; color: #555; }
        footer { text-align: center; padding: 30px; color: #888; font-size: 0.9em; border-top: 1px solid #ddd; margin-top: 40px; }
        .scheduler-badge { display: inline-block; padding: 3px 10px; border-radius: 15px; font-size: 0.8em; margin-right: 5px; }
        {% for sched in schedulers %}
        .badge-{{ sched.name }} { background: {{ sched.color }}22; color: {{ sched.color }}; border: 1px solid {{ sched.color }}44; }
        {% endfor %}
    </style>
</head>
<body>
    <div class="container">
        <header>
            <h1>SimuCell3D Benchmark Report</h1>
            <div class="meta">
                <p><strong>Generated:</strong> {{ timestamp }}</p>
                <p><strong>Benchmark:</strong> {{ bench_dir }}</p>
                <p><strong>Schedulers:</strong>
                    {% for sched in schedulers %}
                    <span class="scheduler-badge badge-{{ sched.name }}">{{ sched.label }}</span>
                    {% endfor %}
                </p>
            </div>
        </header>

        <div class="summary-cards">
            {% for sched in schedulers %}
            <div class="card">
                <h3>{{ sched.label }}</h3>
                <div class="value">{{ sched.final_cells }}</div>
                <div class="unit">final cells</div>
            </div>
            {% endfor %}
            <div class="card">
                <h3>Total Plots</h3>
                <div class="value">{{ plot_count }}</div>
                <div class="unit">visualizations</div>
            </div>
        </div>

        {% for narrative in narratives %}
        <div class="narrative">
            <h2>{{ narrative.title }}</h2>
            <p class="narrative-desc">{{ narrative.description }}</p>
            <div class="plot-grid">
                {% for plot in narrative.plots %}
                <div class="plot-container">
                    <div class="plot-header">
                        <h3>{{ plot.title }}</h3>
                        <p>{{ plot.description }}</p>
                    </div>
                    <img src="data:image/png;base64,{{ plot.image_base64 }}" alt="{{ plot.title }}" class="plot-image">
                    {% if plot.stats %}
                    <div class="plot-footer">{{ plot.stats }}</div>
                    {% endif %}
                </div>
                {% endfor %}
            </div>
        </div>
        {% endfor %}

        <footer>
            <p>Generated by SimuCell3D Benchmark Visualization Suite v2.0</p>
            <p>Using viridis/plasma CVD-safe colormaps • Tufte-style minimal ink design • 300 DPI output</p>
        </footer>
    </div>
</body>
</html>
"""


def generate_html_report(
    output_dir: Path,
    data: Dict,
    plots_generated: List[str],
    bench_dir: Path,
) -> Optional[Path]:
    """
    Generate comprehensive HTML report with embedded plots.

    Creates a single self-contained HTML file with:
    - Embedded base64-encoded plot images
    - Summary statistics cards
    - Narrative-organized plot sections
    - Responsive grid layout

    Args:
        output_dir: Directory containing generated plots
        data: Data dictionary with scheduler info and style config
        plots_generated: List of generated plot filenames
        bench_dir: Original benchmark directory path

    Returns:
        Path to generated HTML file, or None if Jinja2 unavailable
    """
    if not JINJA2_AVAILABLE:
        print("  Skipping HTML report: jinja2 not installed")
        return None

    print("\n  Generating HTML report...")

    # Get scheduler info
    schedulers = data.get('schedulers', [])
    style_config = data.get('style_config', {})

    # Build scheduler summary
    sched_info = []
    for sched in schedulers:
        # Get final cell count (use get_dataframe helper to handle DataFrame truth value)
        comp_data = get_dataframe(data, f'{sched.name}_computational_clean', f'{sched.name}_computational')
        final_cells = 0
        if comp_data is not None and 'cells' in comp_data.columns:
            final_cells = int(comp_data['cells'].iloc[-1])

        # Get color as hex
        color = style_config.get('colors', {}).get(sched.name, (0.5, 0.5, 0.5, 1))
        color_hex = '#{:02x}{:02x}{:02x}'.format(int(color[0]*255), int(color[1]*255), int(color[2]*255))

        sched_info.append({
            'name': sched.name,
            'label': style_config.get('labels', {}).get(sched.name, sched.name),
            'color': color_hex,
            'final_cells': f'{final_cells:,}',
        })

    # Define narratives and their plots
    narratives = [
        {
            'title': 'Biological Narrative',
            'description': 'How do cells maintain homeostasis while the tissue grows?',
            'plot_prefixes': ['01_', '02_', '02b_', '03_', '03b_', '03c_'],
        },
        {
            'title': 'Physical Narrative',
            'description': 'Energy flows through the system: from external work to internal storage.',
            'plot_prefixes': ['02c_', '02d_', '03d_'],
        },
        {
            'title': 'Computational Narrative',
            'description': 'How does adaptive scheduling achieve efficient scaling?',
            'plot_prefixes': ['04_', '05_', '06_', '07_', '08_', '09_', '10_', '10b_'],
        },
    ]

    # Build plot data for each narrative
    for narrative in narratives:
        narrative['plots'] = []
        for plot_name in plots_generated:
            # Check if this plot belongs to this narrative
            if any(plot_name.startswith(prefix) for prefix in narrative['plot_prefixes']):
                plot_path = output_dir / f'{plot_name}.png'
                if plot_path.exists():
                    # Read and encode image
                    with open(plot_path, 'rb') as f:
                        image_data = f.read()
                    image_base64 = base64.b64encode(image_data).decode('utf-8')

                    # Generate title from filename
                    title = plot_name.split('_', 1)[1] if '_' in plot_name else plot_name
                    title = title.replace('_', ' ').title()

                    narrative['plots'].append({
                        'filename': plot_name,
                        'title': title,
                        'description': '',  # Could be enhanced with plot-specific descriptions
                        'image_base64': image_base64,
                        'stats': None,
                    })

    # Render template
    template = Template(HTML_REPORT_TEMPLATE)
    html_content = template.render(
        timestamp=datetime.now().strftime('%Y-%m-%d %H:%M:%S'),
        bench_dir=str(bench_dir),
        schedulers=sched_info,
        plot_count=len(plots_generated),
        narratives=narratives,
    )

    # Write HTML file
    html_path = output_dir / 'benchmark_report.html'
    html_path.write_text(html_content, encoding='utf-8')
    print(f"    Saved: {html_path.name}")

    return html_path


def generate_manifest(output_dir: Path, data: Dict, plots_generated: List[str]) -> None:
    """
    Generate manifest.json with metadata for reproducibility.

    Dynamically includes all detected schedulers and their data statistics.
    """

    def safe_len(df):
        """Get length of DataFrame or return 0 if None."""
        if df is None:
            return 0
        return len(df)

    # Get scheduler info
    schedulers = data.get('schedulers', [])

    # Build dynamic data summary
    data_summary = {}
    for sched in schedulers:
        name = sched.name
        data_summary[f'{name}_computational_rows'] = safe_len(data.get(f'{name}_computational'))
        data_summary[f'{name}_biological_rows'] = safe_len(data.get(f'{name}_biological'))
        if sched.has_phase_timings:
            data_summary[f'{name}_phase_timings_rows'] = safe_len(data.get(f'{name}_phase'))
        if sched.has_simulation_stats:
            data_summary[f'{name}_simulation_stats_rows'] = sched.row_counts.get('simulation_statistics', 0)

    manifest = {
        'generated_at': datetime.now().isoformat(),
        'generator': 'plot_benchmark_results_updated.py',
        'version': '2.0.0',
        'output_directory': str(output_dir),
        'schedulers_detected': [s.name for s in schedulers],
        'plots_generated': plots_generated,
        'data_summary': data_summary,
        'configuration': {
            'dpi': 300,
            'formats': ['png'],
            'figsize_single': list(FIGSIZE_SINGLE),
            'figsize_double': list(FIGSIZE_DOUBLE),
        },
        'features': {
            'auto_scheduler_detection': True,
            'polars_available': POLARS_AVAILABLE,
            'scipy_available': SCIPY_AVAILABLE,
            'html_report': JINJA2_AVAILABLE,
        }
    }

    manifest_path = output_dir / 'manifest.json'
    with open(manifest_path, 'w') as f:
        json.dump(manifest, f, indent=2)
    print(f"\n  Generated manifest: {manifest_path}")


def main():
    """Main entry point."""
    parser = argparse.ArgumentParser(
        description='Generate publication-quality benchmark visualizations for SimuCell3D',
        formatter_class=argparse.RawDescriptionHelpFormatter,
        epilog=__doc__
    )
    parser.add_argument('benchmark_dir', type=Path,
                        help='Path to benchmark directory (e.g., doc/working/parallel_benchmark_*)')
    parser.add_argument('--output-dir', type=Path, default=None,
                        help='Output directory for plots (default: <benchmark_dir>/plots-updated)')
    parser.add_argument('--no-latex', action='store_true',
                        help='Disable LaTeX rendering (use for systems without LaTeX)')
    parser.add_argument('--skip-simulation-stats', action='store_true',
                        help='Skip loading simulation_statistics.csv (faster but disables heterogeneity plots)')
    parser.add_argument('--no-html-report', action='store_true',
                        help='Skip HTML report generation')
    parser.add_argument('--formats', nargs='+', default=['png'],
                        help='Output formats (default: png)')
    parser.add_argument('--publication', action='store_true',
                        help='High-quality publication mode (300 DPI, LaTeX, fine-tuned styling)')
    parser.add_argument('--draft', action='store_true',
                        help='Fast draft mode (150 DPI, no LaTeX, faster iteration)')

    args = parser.parse_args()

    # Handle quality mode flags (draft and publication are mutually exclusive)
    if args.draft and args.publication:
        print("Warning: Both --draft and --publication specified; using --publication")
        args.draft = False

    # Validate input
    if not args.benchmark_dir.exists():
        print(f"Error: Benchmark directory does not exist: {args.benchmark_dir}")
        sys.exit(1)

    # Set output directory (flat structure with numbered plots)
    output_dir = args.output_dir or (args.benchmark_dir / 'plots-updated')
    output_dir.mkdir(parents=True, exist_ok=True)

    # Determine quality mode and LaTeX settings
    if args.draft:
        quality_mode = 'draft'
        use_latex = False  # Draft mode always disables LaTeX for speed
    elif args.publication:
        quality_mode = 'publication'
        use_latex = not args.no_latex
    else:
        quality_mode = 'publication'  # Default to publication quality
        use_latex = not args.no_latex

    load_sim_stats = not args.skip_simulation_stats

    print(f"\n{'='*60}")
    print("Publication-Quality Benchmark Visualization Suite v2.0")
    print(f"{'='*60}")
    print(f"Input:  {args.benchmark_dir}")
    print(f"Output: {output_dir}")
    print(f"Quality: {quality_mode.upper()} ({300 if quality_mode == 'publication' else 150} DPI)")
    print(f"LaTeX:  {'Enabled' if use_latex else 'Disabled'}")
    print(f"Simulation Stats: {'Enabled' if load_sim_stats else 'Disabled (use --skip-simulation-stats to skip)'}")
    print(f"{'='*60}\n")

    # Configure matplotlib based on quality mode
    print("Configuring publication defaults...")
    try:
        configure_publication_defaults(use_latex=use_latex, quality_mode=quality_mode)
    except Exception as e:
        print(f"  Warning: LaTeX configuration failed ({e}), falling back to non-LaTeX")
        configure_publication_defaults(use_latex=False, quality_mode=quality_mode)
        use_latex = False

    # Load data with auto-detection
    print("\nLoading data...")
    data = load_all_data(args.benchmark_dir, load_simulation_stats=load_sim_stats)

    # Get scheduler and style info
    schedulers = data.get('schedulers', [])
    style_config = data.get('style_config', {})

    # Summary of loaded data
    print("\n  Data summary:")
    for key, value in data.items():
        if key in ('schedulers', 'style_config'):
            continue
        if value is not None and hasattr(value, '__len__'):
            print(f"    {key}: {len(value)} rows")

    # Export cleaned data copies to output directory
    export_cleaned_data(data, output_dir)

    # Generate plots
    print("\nGenerating plots...")
    plots_generated = []

    # ==========================================================================
    # BIOLOGICAL NARRATIVE (Plots 01-03)
    # ==========================================================================
    print("\n[Biological Narrative: How do cells maintain homeostasis?]")

    plot_pressure_evolution(data, output_dir, use_latex)
    plots_generated.append('01_pressure_evolution')

    plot_energy_landscape(data, output_dir, use_latex)
    plots_generated.append('02_energy_landscape')

    # New: Cell heterogeneity plot (requires simulation_statistics)
    if load_sim_stats:
        plot_cell_heterogeneity(data, output_dir, use_latex, style_config)
        plots_generated.append('02b_cell_heterogeneity')

    plot_biological_dashboard(data, output_dir, use_latex)
    plots_generated.append('03_biological_dashboard')

    # New biological heterogeneity plots (require simulation_statistics)
    if load_sim_stats:
        plot_population_ridgeline(data, output_dir, use_latex, style_config)
        plots_generated.append('03b_population_ridgeline')

        plot_cell_lifecycle_portrait(data, output_dir, use_latex, style_config)
        plots_generated.append('03c_cell_lifecycle_portrait')

    # ==========================================================================
    # PHYSICAL NARRATIVE (Plots 02c-02d, 03d)
    # ==========================================================================
    if load_sim_stats:
        print("\n[Physical Narrative: Energy flows and thermodynamics]")

        # Energy component breakdown
        plot_energy_components(data, output_dir, use_latex, style_config)
        plots_generated.append('02c_energy_components')

        # P-V phase space
        plot_pv_phase_space(data, output_dir, use_latex, style_config)
        plots_generated.append('02d_pv_phase_space')

        # Energy budget stacked area (new)
        plot_energy_budget_stacked(data, output_dir, use_latex, style_config)
        plots_generated.append('03d_energy_budget')

    # ==========================================================================
    # COMPUTATIONAL NARRATIVE (Plots 04-09)
    # ==========================================================================
    print("\n[Computational Narrative: Scaling and efficiency]")

    plot_scaling_analysis(data, output_dir, use_latex)
    plots_generated.append('04_scaling_analysis')

    plot_phase_timing_breakdown(data, output_dir, use_latex)
    plots_generated.append('05_phase_timing_breakdown')

    plot_roofline_model(data, output_dir, use_latex)
    plots_generated.append('06_roofline_model')

    plot_load_balance_heatmap(data, output_dir, use_latex)
    plots_generated.append('07_load_balance')

    # Statistical comparison plots
    print("\n[Statistical Comparisons]")
    plot_v1_vs_adaptive_comparison(data, output_dir, use_latex)
    plots_generated.append('08_v1_vs_adaptive_comparison')

    plot_speedup_analysis(data, output_dir, use_latex)
    plots_generated.append('09_performance_ratio')

    # Multi-dimensional scheduler comparison
    print("\n[Advanced Scheduler Analysis]")
    plot_scheduler_radar(data, output_dir, use_latex, style_config)
    plots_generated.append('10_scheduler_radar')

    # Enhanced roofline with phase data
    plot_roofline_with_phases(data, output_dir, use_latex, style_config)
    plots_generated.append('10b_roofline_phases')

    # ==========================================================================
    # OUTPUT GENERATION
    # ==========================================================================
    print("\n[Generating outputs]")

    # Generate HTML report
    if not args.no_html_report:
        generate_html_report(output_dir, data, plots_generated, args.benchmark_dir)

    # Generate manifest
    generate_manifest(output_dir, data, plots_generated)

    print(f"\n{'='*60}")
    print(f"Complete! Generated {len(plots_generated)} plots in {output_dir}")
    print(f"Schedulers detected: {[s.name for s in schedulers]}")
    if not args.no_html_report and JINJA2_AVAILABLE:
        print(f"HTML report: {output_dir / 'benchmark_report.html'}")
    print(f"{'='*60}\n")


if __name__ == '__main__':
    main()
