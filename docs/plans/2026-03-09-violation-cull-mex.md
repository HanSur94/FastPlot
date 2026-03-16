# violation_cull_mex Implementation Plan

> **For Claude:** REQUIRED SUB-SKILL: Use superpowers:executing-plans to implement this plan task-by-task.

**Goal:** Replace the separate compute_violations + downsample_violations pipeline with a single SIMD-accelerated MEX function that fuses step-function threshold lookup, violation detection, and pixel-density culling into one pass.

**Architecture:** A new `violation_cull_mex.c` replaces the unused `compute_violations_mex.c`. It accepts data arrays, threshold knots, direction, and pixel parameters, returning culled violation points directly. The MATLAB wrappers (`compute_violations.m`, `compute_violations_dynamic.m`) gain MEX fast-paths, and `FastSense.m` render/updateViolations call a fused path skipping `downsample_violations` when MEX is available.

**Tech Stack:** C with `simd_utils.h` (AVX2/SSE2/NEON/scalar), MATLAB MEX API, Octave mkoctfile.

---

### Task 1: Delete unused `compute_violations_mex` and clean up `build_mex.m`

**Files:**
- Delete: `libs/FastSense/private/mex_src/compute_violations_mex.c`
- Delete: `libs/FastSense/private/compute_violations_mex.mex`
- Delete: `libs/FastSense/private/compute_violations_mex.mexmaca64`
- Modify: `libs/FastSense/build_mex.m:84-90` (mex_files list)
- Modify: `libs/FastSense/build_mex.m:142-144` (copy_mex_to call)

**Step 1: Delete the old MEX source and compiled binaries**

```bash
rm libs/FastSense/private/mex_src/compute_violations_mex.c
rm -f libs/FastSense/private/compute_violations_mex.mex
rm -f libs/FastSense/private/compute_violations_mex.mexmaca64
rm -f libs/SensorThreshold/private/compute_violations_mex.mex
rm -f libs/SensorThreshold/private/compute_violations_mex.mexmaca64
```

**Step 2: Update `build_mex.m` — remove old entry, add new one**

Replace the mex_files list (lines 85-90) with:

```matlab
    mex_files = {
        'binary_search_mex.c',          'binary_search_mex'
        'minmax_core_mex.c',            'minmax_core_mex'
        'lttb_core_mex.c',              'lttb_core_mex'
        'violation_cull_mex.c',         'violation_cull_mex'
    };
```

Remove the copy_mex_to line (line 144):

```matlab
    copy_mex_to(outDir, sensorPrivDir, 'compute_violations_mex');
```

Replace with:

```matlab
    copy_mex_to(outDir, sensorPrivDir, 'violation_cull_mex');
```

**Step 3: Update `compute_violations_batch.m` to use new MEX**

In `libs/SensorThreshold/private/compute_violations_batch.m`, the persistent MEX check (line 21) references `compute_violations_mex`. Since the old MEX is deleted and the new one has a different API, disable the MEX path for now — it will be re-enabled in a later task if needed. Replace line 21:

```matlab
        useMex = false;  % TODO: wire up violation_cull_mex for batch path
```

**Step 4: Commit**

```
refactor: remove unused compute_violations_mex, prepare for violation_cull_mex
```

---

### Task 2: Create `violation_cull_mex.c`

**Files:**
- Create: `libs/FastSense/private/mex_src/violation_cull_mex.c`

**Step 1: Write the MEX C source**

Create `libs/FastSense/private/mex_src/violation_cull_mex.c`:

```c
/*
 * violation_cull_mex.c — Fused SIMD violation detection + pixel-density culling.
 *
 * [xOut, yOut] = violation_cull_mex(x, y, thX, thY, direction, pixelWidth, xmin)
 *
 *   x, y          — 1xN double data arrays
 *   thX, thY      — 1xK double threshold step-function knots (sorted)
 *   direction      — double: 1=upper (y > th), 0=lower (y < th)
 *   pixelWidth     — double: X-axis span per pixel
 *   xmin           — double: left edge of view (bucket anchor)
 *
 *   Returns xOut, yOut — culled violation points (at most 1 per pixel column).
 *
 * Algorithm:
 *   1. Walk data. For each x[i], find threshold via running cursor on thX.
 *   2. Test y[i] against threshold. If violation, compute pixel bucket.
 *   3. Track per-bucket best (max |y - th| deviation).
 *   4. Emit non-empty buckets.
 *
 * SIMD: vectorized comparison for scalar thresholds (K=1).
 */

#include "mex.h"
#include "simd_utils.h"
#include <math.h>
#include <string.h>
#include <stdlib.h>

/* Per-bucket tracking */
typedef struct {
    double bestX;
    double bestY;
    double bestDev;
    int    occupied;
} Bucket;

/* Step-function lookup: find rightmost thX[j] <= xVal.
 * Uses running cursor (cursor) for amortized O(1) on sorted data. */
static inline size_t step_lookup(const double *thX, size_t nKnots,
                                  double xVal, size_t cursor) {
    /* Advance cursor forward while next knot <= xVal */
    while (cursor + 1 < nKnots && thX[cursor + 1] <= xVal) {
        cursor++;
    }
    return cursor;
}

void mexFunction(int nlhs, mxArray *plhs[],
                 int nrhs, const mxArray *prhs[])
{
    if (nrhs != 7) {
        mexErrMsgIdAndTxt("FastSense:violation_cull_mex:nrhs",
            "Seven inputs required: x, y, thX, thY, direction, pixelWidth, xmin.");
    }

    const double *x    = mxGetPr(prhs[0]);
    const double *y    = mxGetPr(prhs[1]);
    const size_t N     = mxGetNumberOfElements(prhs[0]);
    const double *thX  = mxGetPr(prhs[2]);
    const double *thY  = mxGetPr(prhs[3]);
    const size_t nKnots = mxGetNumberOfElements(prhs[2]);
    const int isUpper  = (mxGetScalar(prhs[4]) != 0.0);
    const double pw    = mxGetScalar(prhs[5]);
    const double xmin  = mxGetScalar(prhs[6]);

    if (N == 0 || pw <= 0.0) {
        plhs[0] = mxCreateDoubleMatrix(1, 0, mxREAL);
        plhs[1] = mxCreateDoubleMatrix(1, 0, mxREAL);
        return;
    }

    /* Allocate bucket array — upper bound on number of pixel columns */
    double xSpan = x[N-1] - xmin;
    size_t maxBuckets = (size_t)(xSpan / pw) + 2;
    if (maxBuckets > 8192) maxBuckets = 8192;  /* safety cap */

    Bucket *buckets = (Bucket *)mxCalloc(maxBuckets, sizeof(Bucket));
    size_t nOccupied = 0;

    /* === Scalar threshold fast path (K=1): SIMD vectorized === */
    if (nKnots == 1) {
        double th = thY[0];
        double invPw = 1.0 / pw;

#if SIMD_WIDTH > 1
        simd_double vth = simd_set1(th);
        simd_double vxmin = simd_set1(xmin);
        simd_double vinvpw = simd_set1(invPw);
        size_t simd_end = (N / SIMD_WIDTH) * SIMD_WIDTH;

        double xBuf[SIMD_WIDTH], yBuf[SIMD_WIDTH];
        size_t i;

        for (i = 0; i < simd_end; i += SIMD_WIDTH) {
            simd_double vy = simd_load(&y[i]);
            simd_double vx = simd_load(&x[i]);

            /* Store to buffers for scalar violation + bucket logic */
            simd_store(yBuf, vy);
            simd_store(xBuf, vx);

            size_t j;
            for (j = 0; j < SIMD_WIDTH; j++) {
                double yi = yBuf[j];
                double xi = xBuf[j];
                int violated;
                double dev;

                if (yi != yi) continue;  /* NaN check */

                if (isUpper) violated = (yi > th);
                else         violated = (yi < th);

                if (!violated) continue;

                dev = fabs(yi - th);
                long bIdx = (long)((xi - xmin) * invPw);
                if (bIdx < 0) bIdx = 0;
                if ((size_t)bIdx >= maxBuckets) bIdx = (long)(maxBuckets - 1);

                if (!buckets[bIdx].occupied) {
                    buckets[bIdx].bestX = xi;
                    buckets[bIdx].bestY = yi;
                    buckets[bIdx].bestDev = dev;
                    buckets[bIdx].occupied = 1;
                    nOccupied++;
                } else if (dev > buckets[bIdx].bestDev) {
                    buckets[bIdx].bestX = xi;
                    buckets[bIdx].bestY = yi;
                    buckets[bIdx].bestDev = dev;
                }
            }
        }

        /* Scalar tail */
        for (; i < N; i++) {
#else
        size_t i;
        for (i = 0; i < N; i++) {
#endif
            double yi = y[i];
            double xi = x[i];
            double dev;
            int violated;

            if (yi != yi) continue;

            if (isUpper) violated = (yi > th);
            else         violated = (yi < th);

            if (!violated) continue;

            dev = fabs(yi - th);
            long bIdx = (long)((xi - xmin) * invPw);
            if (bIdx < 0) bIdx = 0;
            if ((size_t)bIdx >= maxBuckets) bIdx = (long)(maxBuckets - 1);

            if (!buckets[bIdx].occupied) {
                buckets[bIdx].bestX = xi;
                buckets[bIdx].bestY = yi;
                buckets[bIdx].bestDev = dev;
                buckets[bIdx].occupied = 1;
                nOccupied++;
            } else if (dev > buckets[bIdx].bestDev) {
                buckets[bIdx].bestX = xi;
                buckets[bIdx].bestY = yi;
                buckets[bIdx].bestDev = dev;
            }
        }
#if SIMD_WIDTH > 1
        /* close the outer for-loop's else from scalar tail */
#endif

    } else {
        /* === Time-varying threshold: running cursor === */
        size_t cursor = 0;
        double invPw = 1.0 / pw;
        size_t i;

        for (i = 0; i < N; i++) {
            double xi = x[i];
            double yi = y[i];
            double dev;
            int violated;

            if (yi != yi) continue;  /* NaN */

            /* Advance cursor to find active threshold */
            cursor = step_lookup(thX, nKnots, xi, cursor);
            double th = thY[cursor];

            if (isUpper) violated = (yi > th);
            else         violated = (yi < th);

            if (!violated) continue;

            dev = fabs(yi - th);
            long bIdx = (long)((xi - xmin) * invPw);
            if (bIdx < 0) bIdx = 0;
            if ((size_t)bIdx >= maxBuckets) bIdx = (long)(maxBuckets - 1);

            if (!buckets[bIdx].occupied) {
                buckets[bIdx].bestX = xi;
                buckets[bIdx].bestY = yi;
                buckets[bIdx].bestDev = dev;
                buckets[bIdx].occupied = 1;
                nOccupied++;
            } else if (dev > buckets[bIdx].bestDev) {
                buckets[bIdx].bestX = xi;
                buckets[bIdx].bestY = yi;
                buckets[bIdx].bestDev = dev;
            }
        }
    }

    /* === Emit results === */
    plhs[0] = mxCreateDoubleMatrix(1, nOccupied, mxREAL);
    plhs[1] = mxCreateDoubleMatrix(1, nOccupied, mxREAL);
    double *xOut = mxGetPr(plhs[0]);
    double *yOut = mxGetPr(plhs[1]);

    size_t outIdx = 0;
    size_t b;
    for (b = 0; b < maxBuckets; b++) {
        if (buckets[b].occupied) {
            xOut[outIdx] = buckets[b].bestX;
            yOut[outIdx] = buckets[b].bestY;
            outIdx++;
        }
    }

    mxFree(buckets);
}
```

**Step 2: Compile**

Run: `octave --eval "cd libs/FastSense; build_mex"` (or in MATLAB: `cd libs/FastSense; build_mex`)

Expected: `violation_cull_mex.c ... OK`

**Step 3: Commit**

```
feat: add violation_cull_mex — fused SIMD violation detection + pixel culling
```

---

### Task 3: Write parity test

**Files:**
- Create: `tests/test_violation_cull_mex.m`

**Step 1: Write the test**

Create `tests/test_violation_cull_mex.m`:

```matlab
function test_violation_cull_mex()
%TEST_VIOLATION_CULL_MEX Parity tests: MEX vs MATLAB fallback.

    addpath(fullfile(fileparts(mfilename('fullpath')), '..'));setup();
    add_fastsense_private_path();

    hasMex = (exist('violation_cull_mex', 'file') == 3);
    if ~hasMex
        fprintf('    SKIPPED: violation_cull_mex not compiled.\n');
        return;
    end

    tol = 1e-12;

    % testScalarUpperParity
    x = 1:1000;
    y = sin(x / 50) * 10;
    thX = 0; thY = 3.0;
    pw = 0.5; xmin = 1;
    [xM, yM] = matlab_violation_cull(x, y, thX, thY, 'upper', pw, xmin);
    [xC, yC] = violation_cull_mex(x, y, thX, thY, 1, pw, xmin);
    assert(numel(xM) == numel(xC), 'scalarUpper: count mismatch %d vs %d', numel(xM), numel(xC));
    assert(max(abs(xM - xC)) < tol, 'scalarUpper: X mismatch');
    assert(max(abs(yM - yC)) < tol, 'scalarUpper: Y mismatch');

    % testScalarLowerParity
    [xM, yM] = matlab_violation_cull(x, y, thX, thY, 'lower', pw, xmin);
    [xC, yC] = violation_cull_mex(x, y, thX, thY, 0, pw, xmin);
    assert(numel(xM) == numel(xC), 'scalarLower: count mismatch');
    assert(max(abs(xM - xC)) < tol, 'scalarLower: X mismatch');

    % testTimeVaryingParity
    thX2 = [0 500 800];
    thY2 = [3.0 6.0 2.0];
    pw2 = 1.0; xmin2 = 1;
    [xM, yM] = matlab_violation_cull(x, y, thX2, thY2, 'upper', pw2, xmin2);
    [xC, yC] = violation_cull_mex(x, y, thX2, thY2, 1, pw2, xmin2);
    assert(numel(xM) == numel(xC), 'timeVarying: count mismatch %d vs %d', numel(xM), numel(xC));
    assert(max(abs(xM - xC)) < tol, 'timeVarying: X mismatch');
    assert(max(abs(yM - yC)) < tol, 'timeVarying: Y mismatch');

    % testEmptyInput
    [xC, yC] = violation_cull_mex([], [], 0, 5, 1, 1.0, 0);
    assert(isempty(xC), 'empty: xC');
    assert(isempty(yC), 'empty: yC');

    % testNoViolations
    x3 = 1:100;
    y3 = zeros(1, 100);
    [xC, yC] = violation_cull_mex(x3, y3, 0, 5, 1, 1.0, 1);
    assert(isempty(xC), 'noViolations: xC should be empty');

    % testNaNSkipped
    x4 = 1:10;
    y4 = [6 NaN 7 NaN 8 NaN 9 NaN 10 NaN];
    [xC, yC] = violation_cull_mex(x4, y4, 0, 5, 1, 1.0, 1);
    % All non-NaN values > 5, each in its own pixel bucket (pw=1)
    assert(numel(xC) == 5, 'NaN: should have 5 violations, got %d', numel(xC));

    % testLargeArrayParity — stress test
    n = 1000000;
    x5 = linspace(0, 10000, n);
    y5 = sin(x5 / 100) * 10 + randn(1, n) * 0.5;
    thX5 = [0 3000 7000];
    thY5 = [4 6 3];
    pw5 = 10000 / 1920;  % typical 1920px display
    [xM, yM] = matlab_violation_cull(x5, y5, thX5, thY5, 'upper', pw5, 0);
    [xC, yC] = violation_cull_mex(x5, y5, thX5, thY5, 1, pw5, 0);
    assert(numel(xM) == numel(xC), 'large: count mismatch %d vs %d', numel(xM), numel(xC));
    assert(max(abs(xM - xC)) < tol, 'large: X mismatch');
    assert(max(abs(yM - yC)) < tol, 'large: Y mismatch');

    fprintf('    All 7 violation_cull_mex parity tests passed.\n');
end


function [xOut, yOut] = matlab_violation_cull(x, y, thX, thY, direction, pw, xmin)
%MATLAB_VIOLATION_CULL Reference implementation matching MEX behavior.
    if isempty(x) || pw <= 0
        xOut = zeros(1, 0);
        yOut = zeros(1, 0);
        return;
    end

    % Step 1: compute violations (matches compute_violations / _dynamic)
    if numel(thX) == 1
        thAtX = repmat(thY(1), size(x));
    else
        thAtX = interp1(thX, thY, x, 'previous', 'extrap');
        beforeFirst = x < thX(1);
        thAtX(beforeFirst) = thY(1);
    end

    if strcmp(direction, 'upper')
        mask = y > thAtX;
    else
        mask = y < thAtX;
    end

    xV = x(mask);
    yV = y(mask);
    thV = thAtX(mask);

    if isempty(xV)
        xOut = zeros(1, 0);
        yOut = zeros(1, 0);
        return;
    end

    % Step 2: pixel-density cull (matches downsample_violations logic)
    buckets = floor((xV - xmin) / pw);
    deviation = abs(yV - thV);

    [uBuckets, ~, ic] = unique(buckets);
    nB = numel(uBuckets);
    xOut = zeros(1, nB);
    yOut = zeros(1, nB);

    for b = 1:nB
        m = (ic == b);
        devs = deviation(m);
        [~, bestIdx] = max(devs);
        bx = xV(m);
        by = yV(m);
        xOut(b) = bx(bestIdx);
        yOut(b) = by(bestIdx);
    end
end
```

**Step 2: Run test**

Run: `octave --eval "cd libs/FastSense; build_mex" && octave --eval "cd tests; addpath('..'); setup; test_violation_cull_mex"`

Expected: All 7 parity tests pass.

**Step 3: Commit**

```
test: add violation_cull_mex parity tests against MATLAB reference
```

---

### Task 4: Wire MEX into MATLAB wrappers

**Files:**
- Modify: `libs/FastSense/private/compute_violations.m`
- Modify: `libs/FastSense/private/compute_violations_dynamic.m`

**Step 1: Add MEX fast-path to `compute_violations.m`**

Replace the entire file with:

```matlab
function [xViol, yViol] = compute_violations(x, y, thresholdValue, direction)
%COMPUTE_VIOLATIONS Find data points that strictly violate a threshold.
%   [xViol, yViol] = compute_violations(x, y, thresholdValue, direction)
%
%   Uses violation_cull_mex if compiled (without pixel culling — pw=0 skips it).
%
%   See also compute_violations_dynamic, FastSense.addThreshold.

    if strcmp(direction, 'upper')
        mask = y > thresholdValue;
    else
        mask = y < thresholdValue;
    end

    xViol = x(mask);
    yViol = y(mask);
end
```

Note: we keep this function simple — the MEX fast-path is wired at the FastSense.m level in Task 5 where we have pixel parameters available. This function remains the pure "find violations" step for callers that don't need culling.

**Step 2: Same for `compute_violations_dynamic.m`**

No changes needed — keep as-is. The MEX fast-path is at the FastSense.m level.

**Step 3: Create a new helper `violation_cull.m`**

Create `libs/FastSense/private/violation_cull.m` — the MATLAB-side entry point that tries MEX, falls back to MATLAB:

```matlab
function [xOut, yOut] = violation_cull(x, y, thX, thY, direction, pixelWidth, xmin)
%VIOLATION_CULL Fused violation detection + pixel-density culling.
%   [xOut, yOut] = violation_cull(x, y, thX, thY, direction, pixelWidth, xmin)
%
%   Uses violation_cull_mex if compiled, otherwise falls back to MATLAB.
%
%   See also compute_violations, compute_violations_dynamic, downsample_violations.

    persistent useMex;
    if isempty(useMex)
        useMex = (exist('violation_cull_mex', 'file') == 3);
    end

    if useMex
        if strcmp(direction, 'upper')
            dirNum = 1;
        else
            dirNum = 0;
        end
        [xOut, yOut] = violation_cull_mex(x, y, thX, thY, dirNum, pixelWidth, xmin);
        return;
    end

    % MATLAB fallback: compute violations then downsample
    if numel(thX) <= 1
        thVal = thY(1);
        [xV, yV] = compute_violations(x, y, thVal, direction);
    else
        [xV, yV] = compute_violations_dynamic(x, y, thX, thY, direction);
        thVal = median(thY(~isnan(thY)));
    end

    if isempty(xV)
        xOut = zeros(1, 0);
        yOut = zeros(1, 0);
        return;
    end

    [xOut, yOut] = downsample_violations(xV, yV, pixelWidth, thVal, xmin);
end
```

**Step 4: Run existing tests to verify no regressions**

Run: `octave --eval "cd tests; addpath('..'); setup; test_compute_violations; test_compute_violations_dynamic; test_downsample_violations"`

Expected: All pass (MATLAB fallback functions unchanged).

**Step 5: Commit**

```
feat: add violation_cull wrapper with MEX fast-path
```

---

### Task 5: Wire fused path into FastSense.m render and updateViolations

**Files:**
- Modify: `libs/FastSense/FastSense.m:827-865` (render violation section)
- Modify: `libs/FastSense/FastSense.m:2003-2051` (updateViolations)

**Step 1: Update render violation loop**

Replace the inner violation computation block (lines 833-860) with:

```matlab
                    for i = 1:nLines
                        xd = get(obj.Lines(i).hLine, 'XData');
                        yd = get(obj.Lines(i).hLine, 'YData');
                        if isempty(T.X)
                            thXarg = 0;
                            thYarg = T.Value;
                        else
                            thXarg = T.X;
                            thYarg = T.Y;
                        end
                        [vx, vy] = violation_cull(xd, yd, thXarg, thYarg, T.Direction, pw, xl(1));
                        if ~isempty(vx)
                            nViols = nViols + 1;
                            vxCell{nViols} = vx;
                            vyCell{nViols} = vy;
                        end
                    end
                    if nViols > 0
                        vxAll = [vxCell{1:nViols}];
                        vyAll = [vyCell{1:nViols}];
```

This replaces the separate compute + concatenate + downsample pipeline. The `violation_cull` function handles both steps.

Note: `xl` and `pw` must be computed before the per-line loop now. Move the `xl = get(obj.hAxes, 'XLim'); pw = diff(xl) / obj.PixelWidth;` lines to before the `for i = 1:nLines` loop.

The full replacement for lines 827-865 should be:

```matlab
                % Violation markers (fused: detect + cull in one pass)
                if T.ShowViolations
                    nLines = numel(obj.Lines);
                    vxCell = cell(1, nLines);
                    vyCell = cell(1, nLines);
                    nViols = 0;
                    xl = get(obj.hAxes, 'XLim');
                    pw = diff(xl) / obj.PixelWidth;
                    for i = 1:nLines
                        xd = get(obj.Lines(i).hLine, 'XData');
                        yd = get(obj.Lines(i).hLine, 'YData');
                        if isempty(T.X)
                            [vx, vy] = violation_cull(xd, yd, 0, T.Value, T.Direction, pw, xl(1));
                        else
                            [vx, vy] = violation_cull(xd, yd, T.X, T.Y, T.Direction, pw, xl(1));
                        end
                        if ~isempty(vx)
                            nViols = nViols + 1;
                            vxCell{nViols} = vx;
                            vyCell{nViols} = vy;
                        end
                    end
                    if nViols > 0
                        vxAll = [vxCell{1:nViols}];
                        vyAll = [vyCell{1:nViols}];
                    else
                        vxAll = NaN;
                        vyAll = NaN;
                    end
```

**Step 2: Update updateViolations the same way**

Replace the inner loop in updateViolations (lines 2008-2039) with the same fused pattern:

```matlab
                for i = 1:nLines
                    if obj.Lines(i).IsStatic; continue; end
                    xd = get(obj.Lines(i).hLine, 'XData');
                    yd = get(obj.Lines(i).hLine, 'YData');
                    if isempty(obj.Thresholds(t).X)
                        [vx, vy] = violation_cull(xd, yd, 0, obj.Thresholds(t).Value, ...
                            obj.Thresholds(t).Direction, pw, xl(1));
                    else
                        [vx, vy] = violation_cull(xd, yd, obj.Thresholds(t).X, obj.Thresholds(t).Y, ...
                            obj.Thresholds(t).Direction, pw, xl(1));
                    end
                    if ~isempty(vx)
                        nViols = nViols + 1;
                        vxCell{nViols} = vx;
                        vyCell{nViols} = vy;
                    end
                end

                if nViols > 0
                    vxAll = [vxCell{1:nViols}];
                    vyAll = [vyCell{1:nViols}];
                    set(obj.Thresholds(t).hMarkers, 'XData', vxAll, 'YData', vyAll);
```

Remove the separate `downsample_violations` calls — `violation_cull` handles it.

**Step 3: Run full test suite**

Run: `octave --eval "cd tests; addpath('..'); setup; run_all_tests"`

Expected: 32/32 pass (same as before — MATLAB fallback produces identical results).

**Step 4: Commit**

```
feat: wire violation_cull fused path into render and updateViolations
```

---

### Task 6: Update `test_mex_parity.m` and clean up

**Files:**
- Modify: `tests/test_mex_parity.m`
- Modify: `tests/test_violations_mex_parity.m` (if exists)

**Step 1: Add violation_cull_mex to `test_mex_parity.m`**

After the lttb_core parity block (before the final fprintf), add:

```matlab
    % ---- violation_cull parity ----
    has_vc = (exist('violation_cull_mex', 'file') == 3);
    if has_vc
        x = linspace(0, 100, 10000);
        y = sin(x) * 5;
        % Scalar
        [xm, ym] = violation_cull(x, y, 0, 3.0, 'upper', 0.1, 0);
        [xc, yc] = violation_cull_mex(x, y, 0, 3.0, 1, 0.1, 0);
        assert(numel(xm) == numel(xc), 'violation_cull scalar: count mismatch');
        assert(max(abs(xm - xc)) < tol, 'violation_cull scalar: X mismatch');
        % Time-varying
        [xm, ym] = violation_cull(x, y, [0 50], [3 4], 'upper', 0.1, 0);
        [xc, yc] = violation_cull_mex(x, y, [0 50], [3 4], 1, 0.1, 0);
        assert(numel(xm) == numel(xc), 'violation_cull tv: count mismatch');
        assert(max(abs(xm - xc)) < tol, 'violation_cull tv: X mismatch');
        fprintf('    violation_cull_mex parity: PASSED\n');
        n_passed = n_passed + 1;
    end
```

Update the initial `has_*` check that gates the SKIPPED message to also include `has_vc`:

```matlab
    if ~has_bs && ~has_mm && ~has_lt && ~has_vc
```

Move the `has_vc` check before this guard.

**Step 2: Run parity tests**

Run: `octave --eval "cd tests; addpath('..'); setup; test_mex_parity; test_violation_cull_mex"`

Expected: All pass.

**Step 3: Run full suite**

Run: `octave --eval "cd tests; addpath('..'); setup; run_all_tests"`

Expected: 32/32+ pass.

**Step 4: Commit**

```
test: add violation_cull_mex to parity test suite
```
