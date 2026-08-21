# Voigt Fitting Algorithm Documentation (modules/spectra)

**Author:** Claude Code
**Original analysis date:** 2025-12-21 (v2.2.0) · **Last reviewed:** 2026-08-12 (v2.9.0)
**Purpose:** Comprehensive documentation of the Voigt peak fitting algorithm — fundamental theory, workflow, and the history of issues found and fixed against it.

This document originally proposed a set of fixes against v2.2.0. Most were implemented in v2.2.1 (see [§8 Implementation History](#8-implementation-history)); each item in §5 and §6 below is now marked with its current status rather than living in a separate changelog file.

---

## Table of Contents

1. [Fundamental Theory](#1-fundamental-theory)
2. [Current Implementation Workflow](#2-current-implementation-workflow)
3. [Algorithm Deep Dive](#3-algorithm-deep-dive)
4. [Code Structure and Comments](#4-code-structure-and-comments)
5. [Known Issues and Limitations](#5-known-issues-and-limitations)
6. [Proposed Solutions and Optimizations](#6-proposed-solutions-and-optimizations)
7. [Quality Improvement Roadmap](#7-quality-improvement-roadmap)
8. [Implementation History](#8-implementation-history)

---

## 1. Fundamental Theory

### 1.1 Voigt Profile Mathematics

The **Voigt profile** is a convolution of Gaussian and Lorentzian line shapes, commonly used in spectroscopy to model peak shapes affected by both:
- **Gaussian broadening**: Instrumental resolution, Doppler broadening
- **Lorentzian broadening**: Natural lifetime, pressure broadening

**Mathematical Definition:**
```
V(x; center, σ, γ) = ∫_{-∞}^{∞} G(x'; center, σ) · L(x - x'; γ) dx'
```

Where:
- **G(x; center, σ)**: Gaussian component with standard deviation σ
- **L(x; γ)**: Lorentzian component with half-width-at-half-maximum γ
- **center**: Peak position
- **amplitude**: Integrated intensity (area under curve)

**Parameter Relationships:**
- Gaussian FWHM: `FWHM_G = 2.355 × σ`
- Lorentzian FWHM: `FWHM_L = 2 × γ`
- **Voigt FWHM** (approximate): `FWHM_V ≈ 0.5346·FWHM_L + √(0.2166·FWHM_L² + FWHM_G²)`

### 1.2 lmfit VoigtModel Implementation

**lmfit** uses the Faddeeva function for efficient Voigt calculation:
```python
from lmfit.models import VoigtModel

# VoigtModel parameters:
# - center: peak position (cm⁻¹ or nm)
# - amplitude: height × width (NOT peak height!)
# - sigma: Gaussian width parameter
# - gamma: Lorentzian width parameter
```

**Critical Detail**: `amplitude` in lmfit is **NOT** the peak height, but rather:
```
amplitude ≈ peak_height × effective_width
```

This is a common source of confusion and can lead to poor initial guesses.

---

## 2. Current Implementation Workflow

### 2.1 High-Level Workflow

```
User Input: Baseline-corrected spectrum (X, Y) + Peak guesses
    ↓
[Auto-Find Peaks] (Optional)
    ↓ (Uses scipy.signal.find_peaks)
    ↓
Peak Table: List[PeakDefinition]
    ↓ (center, amplitude, width_fwhm, bounds)
    ↓
[Voigt Fitting] fit_voigt_peaks()
    ↓
    ├─→ Validation (1-10 peaks, array lengths)
    ├─→ Auto-bounds calculation (mode-dependent)
    ├─→ Build composite model (sum of Voigt models)
    ├─→ Initialize parameters with bounds
    ├─→ Levenberg-Marquardt optimization
    ├─→ Extract fitted parameters
    ├─→ Calculate quality metrics (χ², R²)
    ↓
FitResult: success, fitted_peaks, total_fit_curve, R², χ²
```

### 2.2 Step-by-Step Fitting Process

**Step 1: Validation** ([fitting.py:79-87](src/processing/fitting.py#L79-L87))
```python
if len(peak_table) == 0:
    raise ValueError("peak_table must have at least 1 peak")
if len(peak_table) > 10:
    raise ValueError(f"peak_table must have <= 10 peaks (got {len(peak_table)})")
if len(x) != len(y):
    raise ValueError(f"x and y must have same length")
```

**Step 2: Auto-bounds Calculation** ([fitting.py:89-95](src/processing/fitting.py#L89-L95))
```python
x_range = (x.min(), x.max())
y_max = y.max()
spectral_resolution = np.median(np.abs(np.diff(x)))

for peak in peak_table:
    peak.calculate_auto_bounds(mode, x_range, y_max, spectral_resolution)
```

**Auto-bounds logic** ([peak.py:76-127](src/models/peak.py#L76-L127)):
- **Raman mode**: center ± 5 cm⁻¹
- **PL mode**: center ± 30 nm
- **width_min**: 2.5 × spectral_resolution
- **width_max**: 50% of X range
- **amplitude_max**: 5 × max(Y) (raised from 2× in v2.2.1, §6.4)

**Step 3: Build Composite Model** ([fitting.py:97-124](src/processing/fitting.py#L97-L124))
```python
composite_model = None
params = Parameters()

for i, peak in enumerate(peak_table):
    prefix = f"p{i}_"
    voigt = VoigtModel(prefix=prefix)

    if composite_model is None:
        composite_model = voigt
    else:
        composite_model += voigt  # Sum of Voigt models

    # Convert FWHM to sigma/gamma
    sigma_guess = peak.width_fwhm / (2 * 2.355)  # FWHM_G = 2.355 × σ
    gamma_guess = peak.width_fwhm / 4.0          # FWHM_L = 2 × γ

    # Add parameters with bounds
    params.add(f"{prefix}center", value=peak.center,
               min=peak.center_min, max=peak.center_max)
    params.add(f"{prefix}amplitude", value=peak.amplitude,
               min=0, max=peak.amplitude_max)
    params.add(f"{prefix}sigma", value=sigma_guess,
               min=peak.width_min / (2 * 2.355), max=peak.width_max / (2 * 2.355))
    params.add(f"{prefix}gamma", value=gamma_guess,
               min=peak.width_min / 4.0, max=peak.width_max / 4.0)
```

**Step 4: Levenberg-Marquardt Optimization** ([fitting.py:126-166](src/processing/fitting.py#L126-L166))
```python
result = composite_model.fit(
    y, params, x=x,
    method='leastsq',       # Levenberg-Marquardt
    max_nfev=2000,          # Max function evaluations
    fit_kws={'ftol': 1e-6, 'xtol': 1e-6}  # Convergence tolerances
)
```

**Step 5: Extract Fitted Parameters** ([fitting.py:168-238](src/processing/fitting.py#L168-L238))
```python
for i, peak in enumerate(peak_table):
    prefix = f"p{i}_"

    # Extract values with defensive coding
    center_fit = get_param_value(result.params[f"{prefix}center"])
    amplitude_fit = get_param_value(result.params[f"{prefix}amplitude"])
    sigma_fit = get_param_value(result.params[f"{prefix}sigma"])
    gamma_fit = get_param_value(result.params[f"{prefix}gamma"])

    # Convert back to FWHM
    width_fwhm_fit = 2.355 * sigma_fit

    # Calculate shape parameter (Lorentzian fraction)
    shape_fit = gamma_fit / (gamma_fit + sigma_fit)

    # Evaluate component curve
    component_curve = voigt_component.eval(x=x, **{...})
```

**Step 6: Quality Metrics** ([fitting.py:240-247](src/processing/fitting.py#L240-L247))
```python
residuals = result.residual
chi_squared = result.chisqr

# R-squared (coefficient of determination)
ss_res = np.sum(residuals**2)
ss_tot = np.sum((y - np.mean(y))**2)
r_squared = 1.0 - (ss_res / ss_tot) if ss_tot > 0 else 0.0
```

---

## 3. Algorithm Deep Dive

### 3.1 Levenberg-Marquardt Optimization

The **Levenberg-Marquardt (LM)** algorithm is a hybrid optimization method combining:
- **Gradient Descent**: Fast far from minimum
- **Gauss-Newton**: Fast near minimum (quadratic convergence)

**Algorithm (simplified):**
```
1. Initialize parameters θ₀ (center, amplitude, sigma, gamma for each peak)
2. Set damping parameter λ = 0.001
3. While not converged:
   a. Compute residuals: r = Y_data - Y_model(θ)
   b. Compute Jacobian: J = ∂Y_model/∂θ
   c. Solve: (J^T J + λI) Δθ = -J^T r
   d. If error decreases: θ ← θ + Δθ, λ ← λ/10 (more Gauss-Newton)
   e. Else: λ ← λ×10 (more gradient descent), retry
4. Return optimized parameters
```

**Convergence Criteria:**
- **ftol** (1e-6): Relative error in sum of squares
- **xtol** (1e-6): Relative error in parameter values
- **max_nfev** (2000): Maximum function evaluations

### 3.2 Parameter Initialization Strategy

**Current approach** ([fitting.py:113-114](src/processing/fitting.py#L113-L114)):
```python
sigma_guess = peak.width_fwhm / (2 * 2.355)  # Assume equal Gaussian/Lorentzian
gamma_guess = peak.width_fwhm / 4.0          # contribution
```

**Assumption**: Equal contribution from Gaussian and Lorentzian components.

**Problem**: This assumption may not hold for:
- **Raman spectra**: Often more Lorentzian (lifetime-dominated)
- **PL spectra**: Often more Gaussian (instrumental broadening)

**Impact on amplitude**: Since `amplitude ≈ height × width`, if the width guess is wrong, the amplitude will be wrong by a proportional factor.

### 3.3 Auto-Find Peaks Algorithm

**Implementation** ([fitting.py:261-377](src/processing/fitting.py#L261-L377)):

```python
def auto_find_peaks(x, y, mode="Raman", min_peaks=2, max_peaks=5, prominence_threshold=0.05):
    # 1. Calculate prominence threshold
    y_max = y.max()
    min_prominence = prominence_threshold * y_max

    # 2. Find peaks using scipy.signal
    peak_indices, properties = signal.find_peaks(
        y,
        prominence=min_prominence,
        width=2  # Minimum width in data points
    )

    # 3. Sort by prominence (descending)
    prominences = properties['prominences']
    sorted_indices = np.argsort(prominences)[::-1]

    # 4. Take top N peaks
    n_peaks = min(max(len(sorted_indices), min_peaks), max_peaks)
    top_indices = sorted_indices[:n_peaks]

    # 5. Estimate FWHM from widths
    if 'widths' in properties:
        width_points = properties['widths'][idx]
        dx = np.median(np.abs(np.diff(x)))
        width_fwhm = width_points * dx
    else:
        width_fwhm = 10 * np.median(np.abs(np.diff(x)))  # Fallback

    # 6. Create PeakDefinition objects
    peak_table.append(PeakDefinition(
        center=center,
        amplitude=amplitude,  # Uses peak height (NOT lmfit amplitude!)
        width_fwhm=width_fwhm,
        shape=0.5  # Equal Gaussian/Lorentzian
    ))
```

**Key issue**: `amplitude` is set to peak height, but lmfit expects `amplitude = height × width`.

---

## 4. Code Structure and Comments

### 4.1 File Organization

```
src/processing/fitting.py (412 lines)
├── fit_voigt_peaks()           # Main fitting function
├── auto_find_peaks()           # Peak detection
└── estimate_peak_bounds()      # Convenience wrapper

src/models/peak.py (293 lines)
├── PeakDefinition              # User-defined peak guess
│   ├── __post_init__()         # Validation
│   ├── calculate_auto_bounds() # Mode-dependent bounds
│   ├── to_dict()               # Serialization
│   └── from_dict()             # Deserialization
├── FittedPeak                  # Fitted parameters + errors
└── FitResult                   # Complete fit result with metrics
```

### 4.2 Critical Code Sections with Explanations

**Section 1: Amplitude Initialization** ([fitting.py:119-120](src/processing/fitting.py#L119-L120))

```python
params.add(f"{prefix}amplitude", value=peak.amplitude,
           min=0, max=peak.amplitude_max)
```

**Comment**: `peak.amplitude` comes from user guess (or auto-find), which is often the **peak height**. However, lmfit's VoigtModel expects `amplitude = ∫V(x)dx ≈ height × effective_width`. This mismatch can cause:
- **Over-estimation** if amplitude is too large → optimizer struggles
- **Under-estimation** if amplitude is too small → fit doesn't reach true peak height

**Section 2: Width Parameter Conversion** ([fitting.py:113-114](src/processing/fitting.py#L113-L114))

```python
sigma_guess = peak.width_fwhm / (2 * 2.355)  # Gaussian FWHM = 2.355 × sigma
gamma_guess = peak.width_fwhm / 4.0          # Lorentzian FWHM = 2 × gamma
```

**Comment**: This assumes equal Gaussian and Lorentzian contributions. For a pure Gaussian (γ=0), FWHM = 2.355σ. For a pure Lorentzian (σ=0), FWHM = 2γ. The current approach uses:
```
sigma = FWHM / (2 × 2.355) ≈ FWHM / 4.71
gamma = FWHM / 4
```

This means we're biasing towards more Lorentzian character. **Better approach**: Use shape parameter to distribute FWHM:
```python
if peak.shape < 0.5:  # More Gaussian
    sigma_guess = peak.width_fwhm / 2.355
    gamma_guess = peak.width_fwhm * peak.shape / 2
else:  # More Lorentzian
    sigma_guess = peak.width_fwhm * (1 - peak.shape) / 2.355
    gamma_guess = peak.width_fwhm / 2
```

**Section 3: Convergence Tolerance Handling** ([fitting.py:138-153](src/processing/fitting.py#L138-L153))

```python
# Accept fit even if error bars couldn't be estimated (common with tight fits)
if not result.success and "Tolerance seems to be too small" not in str(result.message):
    return FitResult(
        success=False,
        fitted_peaks=[],
        total_fit_curve=np.zeros_like(y),
        residuals=y.copy(),
        chi_squared=np.sum(y**2),
        r_squared=0.0,
        convergence_time=convergence_time,
        error_message=(...)
    )
```

**Comment**: This is a workaround for a common lmfit behavior where the fit converges but uncertainties cannot be calculated. The fit is still valid, but we accept it with `stderr=0.0`. **Better approach**: Check `result.errorbars` flag instead of string matching.

**Section 4: Parameter Extraction Defensive Coding** ([fitting.py:172-205](src/processing/fitting.py#L172-L205))

```python
def get_param_value(param):
    """Extract value from Parameter object or float."""
    return param.value if hasattr(param, 'value') else float(param)

def get_param_stderr(param):
    """Extract stderr from Parameter object (returns 0.0 if unavailable)."""
    if hasattr(param, 'stderr'):
        return param.stderr or 0.0
    return 0.0
```

**Comment**: This defensive coding was added to handle cases where lmfit returns raw floats instead of Parameter objects (rare edge case). **Better approach**: Always expect Parameter objects; if we get floats, there's a deeper issue.

---

## 5. Known Issues and Limitations

The subsections below are numbered as originally analyzed (v2.2.0); each is
now tagged with its resolution status. See §6 for the fix that resolved it.

### 5.1 Amplitude Mismatch Issue — ✅ RESOLVED (v2.2.1, §6.1)

**Problem**: User-provided `amplitude` is often peak height, but lmfit expects integrated intensity.

**Symptoms**:
- Fitted peaks have wrong heights
- Optimizer takes many iterations to converge
- Poor fits for sharp peaks (underestimation) or broad peaks (overestimation)

**Example**:
```
User input:
  - center = 1350 cm⁻¹
  - amplitude = 5000 (thinking this is peak height)
  - width_fwhm = 50 cm⁻¹

lmfit expects:
  - amplitude ≈ 5000 × 50 = 250,000 (integrated intensity)

Current behavior:
  - Initializes with amplitude=5000
  - Optimizer has to scale it up by 50×
  - May hit amplitude_max bound or converge slowly
```

### 5.2 Width Initialization Bias — ✅ RESOLVED (v2.2.1, §6.2)

**Problem**: Assumes equal Gaussian/Lorentzian contributions, which may not be true.

**Symptoms**:
- Fitted peaks have wrong shapes (too narrow or too broad)
- Poor fit quality (low R²) even with correct peak positions

**Example**:
```
Raman spectrum (naturally Lorentzian-dominated):
  - True: σ_small, γ_large
  - Current guess: σ ≈ γ (equal contribution)
  - Result: Optimizer tries to fit Gaussian-like profile to Lorentzian peak
```

### 5.3 Auto-Find FWHM Estimation — ✅ RESOLVED (v2.2.1, §6.3)

**Problem**: Falls back to `10 × spectral_resolution` if `scipy.signal.find_peaks` doesn't return widths.

**Symptoms**:
- Auto-found peaks have wildly wrong width guesses
- Poor initial fit quality
- May not converge if widths are way off

**Code** ([fitting.py:346-353](src/processing/fitting.py#L346-L353)):
```python
if 'widths' in properties:
    width_points = properties['widths'][idx]
    dx = np.median(np.abs(np.diff(x)))
    width_fwhm = width_points * dx
else:
    # Fallback: use spectral resolution × 10
    width_fwhm = 10 * np.median(np.abs(np.diff(x)))
```

**Issue**: `10 × spectral_resolution` is arbitrary. For a spectrum with 1 cm⁻¹ resolution, this gives 10 cm⁻¹ FWHM, which may be too narrow for broad peaks.

### 5.4 Bounds May Be Too Tight — ✅ RESOLVED (v2.2.1, §6.4)

**Problem**: Auto-bounds may constrain parameters too tightly, preventing convergence to true minimum.

**Example** ([peak.py:107-115](src/models/peak.py#L107-L115)):
```python
if mode == "Raman":
    center_tolerance = 5.0  # cm⁻¹
else:  # PL
    center_tolerance = 30.0  # nm
```

**Issue**: If the initial center guess is off by >5 cm⁻¹ (Raman), the optimizer cannot correct it.

### 5.5 No Multi-Stage Fitting — ⬜ STILL OPEN (see §6.5)

**Problem**: Single-stage fitting tries to optimize all parameters simultaneously, which is prone to local minima.

**Symptoms**:
- Optimizer converges to poor local minimum
- Peaks "stick together" (two nearby peaks collapse into one)
- R² is low even though fit appears reasonable

**Better approach**: Multi-stage fitting:
1. **Stage 1**: Fix widths and shapes, optimize centers and amplitudes only
2. **Stage 2**: Fix centers, optimize widths, shapes, and amplitudes
3. **Stage 3**: Optimize all parameters together (fine-tuning)

### 5.6 No Peak Overlap Detection — ✅ RESOLVED (v2.2.1, §6.7)

**Problem**: Auto-find may detect overlapping peaks that are better fit as a single peak, or miss closely-spaced peaks.

**Symptoms**:
- Auto-find detects 3 peaks, but true spectrum has 2 overlapping peaks
- Poor fit quality due to over/under-parameterization

**Better approach**: Use prominence ratio and distance metrics to merge or split peaks.

---

## 6. Proposed Solutions and Optimizations

### 6.1 Fix Amplitude Initialization — ✅ IMPLEMENTED (v2.2.1)

**Solution**: Convert user-provided height to lmfit amplitude.

**Implementation** (as proposed and originally shipped in v2.2.1):
```python
# In fit_voigt_peaks(), before adding parameters:

# Estimate effective FWHM for amplitude calculation
fwhm_eff = peak.width_fwhm  # Could refine with shape parameter

# Convert height to integrated intensity
# For Voigt profile: amplitude ≈ height × FWHM × sqrt(π/ln(2)) ≈ height × FWHM × 1.064
amplitude_lmfit = peak.amplitude * fwhm_eff * 1.064

params.add(f"{prefix}amplitude", value=amplitude_lmfit,
           min=0, max=peak.amplitude_max * fwhm_eff * 1.064)
```

**Refined further since**: the current code (`src/processing/fitting.py`) no longer
seeds the amplitude from `peak.amplitude` at all — it auto-estimates the initial
height directly from the data at `peak.center` (`height_guess = max(float(y[idx]), 1e-6)`),
since amplitude depends on measurement conditions while position/FWHM come from
the material preset. `peak.amplitude` itself is now a required-but-unused
placeholder field, kept only for backward-compatible (de)serialization
(see `PeakDefinition.amplitude` in `src/models/peak.py`).

**Impact**: Better initial guesses → faster convergence, fewer local minima.

### 6.2 Shape-Aware Width Initialization — ✅ IMPLEMENTED (v2.2.1)

**Solution**: Use `peak.shape` parameter to distribute FWHM between σ and γ.

**Implementation**:
```python
# Shape parameter: 0 = pure Gaussian, 1 = pure Lorentzian
shape = peak.shape  # 0.0 to 1.0

if shape < 0.5:
    # More Gaussian-like
    frac_gaussian = 1.0 - shape
    frac_lorentzian = shape
else:
    # More Lorentzian-like
    frac_gaussian = 1.0 - shape
    frac_lorentzian = shape

# Distribute FWHM according to shape
# For Voigt: FWHM ≈ 0.5346*FWHM_L + sqrt(0.2166*FWHM_L² + FWHM_G²)
# Simplified: allocate FWHM proportionally
sigma_guess = (peak.width_fwhm * frac_gaussian) / 2.355  # Gaussian component
gamma_guess = (peak.width_fwhm * frac_lorentzian) / 2.0  # Lorentzian component

# Ensure non-zero values
sigma_guess = max(sigma_guess, peak.width_min / (2 * 2.355))
gamma_guess = max(gamma_guess, peak.width_min / 4.0)
```

**Impact**: Better shape guesses → better fit quality for mixed profiles.

### 6.3 Improved Auto-Find FWHM Estimation — ✅ IMPLEMENTED (v2.2.1)

**Solution**: Always use `width_half_height` from `find_peaks`, and provide a smarter fallback.

**Implementation**:
```python
# In auto_find_peaks():

peak_indices, properties = signal.find_peaks(
    y,
    prominence=min_prominence,
    width=2,
    rel_height=0.5  # Measure width at half-maximum
)

# Extract widths_half_height
if 'widths' in properties and len(properties['widths']) > idx:
    width_points = properties['widths'][idx]
    dx = np.median(np.abs(np.diff(x)))
    width_fwhm = width_points * dx
else:
    # Smarter fallback: estimate from peak curvature
    # Use 2nd derivative at peak to estimate width
    peak_idx = peak_indices[idx]
    if peak_idx > 1 and peak_idx < len(y) - 2:
        # Approximate curvature: y''(x) ≈ (y[i-1] - 2*y[i] + y[i+1]) / dx²
        d2y = (y[peak_idx-1] - 2*y[peak_idx] + y[peak_idx+1]) / (dx**2)
        if d2y < 0:  # Concave down (valid peak)
            # For Gaussian: y''(peak) = -height / σ²
            # σ ≈ sqrt(height / |y''|)
            sigma_est = np.sqrt(y[peak_idx] / abs(d2y))
            width_fwhm = 2.355 * sigma_est
        else:
            width_fwhm = 10 * dx  # Fallback to old method
    else:
        width_fwhm = 10 * dx
```

**Impact**: Better width estimates → better initial fits.

### 6.4 Adaptive Bounds — ✅ IMPLEMENTED (v2.2.1)

**Solution**: Make bounds relative to data range and peak properties.

**Implementation**:
```python
# In PeakDefinition.calculate_auto_bounds():

# Center bounds: wider tolerance for uncertain peaks
if mode == "Raman":
    center_tolerance = max(5.0, 0.02 * self.width_fwhm)  # At least 2% of FWHM
else:  # PL
    center_tolerance = max(30.0, 0.05 * self.width_fwhm)

# Width bounds: allow 0.5× to 3× initial guess
if self.width_min is None:
    self.width_min = max(2.5 * spectral_resolution, 0.5 * self.width_fwhm)

if self.width_max is None:
    self.width_max = min(0.5 * (x_range[1] - x_range[0]), 3.0 * self.width_fwhm)

# Amplitude bounds: wider range for uncertain peaks
if self.amplitude_max is None:
    self.amplitude_max = 5.0 * y_max  # Allow up to 5× max intensity
```

**Impact**: Optimizer has more freedom → less likely to hit bounds, better convergence.

### 6.5 Multi-Stage Fitting — ⬜ NOT IMPLEMENTED

**Solution**: Implement 3-stage fitting strategy.

**Implementation**:
```python
def fit_voigt_peaks_multistage(x, y, peak_table, mode="Raman"):
    # ... [validation and auto-bounds as before] ...

    # STAGE 1: Fix widths and shapes, optimize centers and amplitudes
    for i, peak in enumerate(peak_table):
        prefix = f"p{i}_"
        params.add(f"{prefix}sigma", value=sigma_guess, vary=False)
        params.add(f"{prefix}gamma", value=gamma_guess, vary=False)

    result_stage1 = composite_model.fit(y, params, x=x, method='leastsq', max_nfev=500)

    # STAGE 2: Fix centers, optimize widths and amplitudes
    for i, peak in enumerate(peak_table):
        prefix = f"p{i}_"
        result_stage1.params[f"{prefix}center"].vary = False
        result_stage1.params[f"{prefix}sigma"].vary = True
        result_stage1.params[f"{prefix}gamma"].vary = True

    result_stage2 = composite_model.fit(y, result_stage1.params, x=x, method='leastsq', max_nfev=500)

    # STAGE 3: Optimize all parameters (fine-tuning)
    for i, peak in enumerate(peak_table):
        prefix = f"p{i}_"
        result_stage2.params[f"{prefix}center"].vary = True

    result_final = composite_model.fit(y, result_stage2.params, x=x, method='leastsq', max_nfev=1000)

    # ... [extract parameters from result_final as before] ...
```

**Impact**: Much better convergence, avoids local minima, higher fit quality.

### 6.6 Robust Error Handling — ⬜ NOT IMPLEMENTED

**Solution**: Replace string matching with proper flag checking.

**Implementation**:
```python
# After fitting:
if result.success:
    # Fit converged
    if result.errorbars:
        # Uncertainties calculated successfully
        pass
    else:
        # Fit converged but no error bars (tight tolerance)
        st.warning("Fit succeeded but uncertainties unavailable (tight tolerance)")
else:
    # Fit failed
    return FitResult(success=False, error_message=result.message, ...)
```

**Impact**: Cleaner code, more reliable error detection.

### 6.7 Peak Overlap Detection — ✅ IMPLEMENTED (v2.2.1), UI removed (v2.9.0)

**Solution**: Check for peaks closer than 2× FWHM and suggest merging.
`detect_overlapping_peaks()` (and `auto_find_peaks()`, §3.3/§6.3) are still
defined and tested in `src/processing/fitting.py`, but as of v2.9.0 have no
call site anywhere in the app: the manual peak-fitting UI that called them
(`src/ui/control_panel/peak_fit.py`) was removed in favor of preset-driven
processing, and `execute_auto_workflow()` builds the peak table directly
from the preset's `peak_templates` rather than auto-detecting or
overlap-checking them. See [CHANGELOG.md](CHANGELOG.md) v2.9.0.

**Implementation**:
```python
def detect_overlapping_peaks(peak_table, merge_threshold=2.0):
    """
    Detect peaks that are too close and suggest merging.

    Parameters
    ----------
    peak_table : List[PeakDefinition]
        List of peaks sorted by center position.
    merge_threshold : float
        Merge if centers are closer than this × average FWHM.

    Returns
    -------
    warnings : list[str]
        List of warning messages.
    """
    warnings = []
    for i in range(len(peak_table) - 1):
        p1 = peak_table[i]
        p2 = peak_table[i + 1]

        distance = abs(p2.center - p1.center)
        avg_fwhm = (p1.width_fwhm + p2.width_fwhm) / 2

        if distance < merge_threshold * avg_fwhm:
            warnings.append(
                f"Peaks '{p1.label}' and '{p2.label}' are very close "
                f"({distance:.1f} < {merge_threshold}×FWHM={merge_threshold*avg_fwhm:.1f}). "
                f"Consider merging into a single peak or refining guesses."
            )

    return warnings
```

**Impact**: Warns user about likely fitting issues before running fit.

---

## 7. Quality Improvement Roadmap

### 7.1 Immediate Fixes (High Priority) — ✅ ALL DONE (v2.2.1)

1. **Fix amplitude initialization** (Section 6.1) — done
2. **Implement adaptive bounds** (Section 6.4) — done
3. **Improve auto-find FWHM** (Section 6.3) — done

### 7.2 Medium-Term Improvements (Medium Priority)

4. **Shape-aware width initialization** (Section 6.2) — ✅ done (v2.2.1)
5. **Robust error handling** (Section 6.6) — ⬜ still open (still string-matches `result.message`)
6. **Peak overlap detection** (Section 6.7) — ✅ done (v2.2.1)

### 7.3 Long-Term Enhancements (Low Priority) — still open

7. **Multi-stage fitting** (Section 6.5)
   - **Effort**: 3-4 hours
   - **Impact**: High (best fit quality, but complex)
   - **Files**: `fitting.py` (new function or refactor existing)

8. **Alternative optimization methods**
   - **Effort**: 4-6 hours
   - **Impact**: Medium (some edge cases)
   - **Options**: Differential Evolution, Basin Hopping, MCMC
   - **Files**: `fitting.py` (add method parameter)

9. **Bayesian uncertainty estimation**
   - **Effort**: 6-8 hours
   - **Impact**: Low (research use case)
   - **Tools**: emcee, pymc3
   - **Files**: New module `fitting_bayesian.py`

### 7.4 Testing and Validation — ✅ DONE (v2.8.0)

A pytest suite now exists at `tests/unit/test_fitting.py`, covering
`fit_voigt_peaks()` (synthetic single- and two-peak spectra, convergence and
R² thresholds), `auto_find_peaks()` (including a regression test for the
§ min_peaks clarity fix — see [CHANGELOG.md](CHANGELOG.md) v2.8.0), and
`detect_overlapping_peaks()`. Items 11-12 below (UI-workflow integration
tests and a real-spectra benchmark suite) remain open.

11. **Integration tests for UI workflow** — still open
12. **Benchmark test suite** (real Raman/PL spectra with ground truth) — still open

---

## Summary

### Current Implementation Strengths:
- ✅ Uses industry-standard lmfit library
- ✅ Robust Voigt profile model (handles Gaussian + Lorentzian)
- ✅ Levenberg-Marquardt optimization (well-tested, reliable)
- ✅ Auto-bounds calculation (mode-aware)
- ✅ Quality metrics (R², χ²)
- ✅ Defensive parameter extraction
- ✅ Error handling with actionable messages
- ✅ Unit-tested (`tests/unit/test_fitting.py`, v2.8.0)

### Remaining Open Issues:
1. ⚠️ **Single-stage fitting** (§6.5) → still prone to local minima with many peaks
2. ⚠️ **String-matched error detection** (§6.6) → works, but fragile against lmfit message wording changes

All other issues originally identified in this document (amplitude mismatch,
width initialization bias, tight bounds, missing overlap detection) were
resolved in v2.2.1 — see §8 below.

### Recommended Action Plan:
1. **Long-term**: Consider multi-stage fitting (§6.5) if quality issues resurface on real-world spectra.
2. **Code quality**: Replace the `result.message` string match (§6.6) with `result.errorbars`/`result.success` flag checks.
3. **Testing**: Extend coverage to UI-workflow integration tests and a real-spectra benchmark suite (§7.4).

---

## 8. Implementation History

### v2.2.1 (2025-12-23) — Fitting quality fixes

Implemented the five high/medium-priority items from §6 (6.1-6.4, 6.7) in a
single pass. Two items were explicitly deferred: multi-stage fitting (§6.5,
high effort/complexity) and the string-matching→flag-based error handling
cleanup (§6.6, low impact).

**Files touched:** `src/processing/fitting.py`, `src/models/peak.py`,
`src/ui/control_panel.py` (peak-fitting section — moved to
`src/ui/control_panel/peak_fit.py` in the v2.8.0 package refactor, then
removed entirely in v2.9.0 — see below).

**Reported quality impact** (author's estimate at the time, not independently
re-measured):

| Metric | Before (v2.2.0) | After (v2.2.1) |
|---|---|---|
| R² (well-behaved spectra) | 0.85–0.92 | 0.95–0.99 |
| Convergence rate | 60–70% | 90–95% |
| Bound-hitting issues | Common | Rare |
| Auto-find quality | Poor | Good |

**Suggested validation** (for anyone re-verifying these numbers): fit a
synthetic multi-peak spectrum with known ground-truth parameters and check
R² > 0.99; fit a real Raman spectrum with 3-5 peaks and confirm auto-find
gives reasonable initial guesses; construct two peaks 1.5×FWHM apart and
confirm the overlap warning fires before fitting.

### v2.8.0 (2026-08-11) — Test coverage + amplitude refinement

- Added `tests/unit/test_fitting.py` (see §7.4).
- `fit_voigt_peaks()`'s amplitude initialization (§6.1) was refined further:
  it no longer seeds from `peak.amplitude` at all, instead auto-estimating
  the initial height directly from the data at each peak's center (see the
  note under §6.1).
- `auto_find_peaks()`'s peak-count formula was simplified for clarity (its
  behavior was already correct — see CHANGELOG.md).
- `src/ui/control_panel.py` (referenced throughout §6-§7 above) was split
  into a package; the peak-fitting section referenced in §6.7/§8 moved to
  `src/ui/control_panel/peak_fit.py`.

### v2.9.0 (2026-08-12) — Manual peak-fitting UI removed

`src/ui/control_panel/peak_fit.py` (referenced above) no longer exists.
Processing is now exclusively preset-driven
(`execute_auto_workflow()` in `src/processing/auto_workflow.py`, triggered
from `src/ui/sidebar.py`); the peak table comes directly from the preset's
`peak_templates` instead of manual entry or `auto_find_peaks()`. This
doesn't change any theory or algorithm described above — `fit_voigt_peaks()`
is called exactly the same way, just from `auto_workflow.py` instead of a
UI button handler. `auto_find_peaks()` and `detect_overlapping_peaks()`
(§3.3, §6.3, §6.7) remain in `src/processing/fitting.py`, still tested, but
currently have no caller anywhere in the app.

---

**End of Document**
