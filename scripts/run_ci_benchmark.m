function run_ci_benchmark()
%RUN_CI_BENCHMARK Performance benchmark for CI with statistical analysis.
%   Runs multiple iterations across multiple dataset sizes to produce
%   mean, std, and RMS for each metric. Outputs results as JSON for
%   github-action-benchmark (customSmallerIsBetter format).
%
%   Metrics measured:
%     - Instantiation: FastSense() + addLine + addThreshold
%     - Render: render() + drawnow
%     - Zoom cycle: set XLim + drawnow (interactive responsiveness)
%     - Downsample: minmax_downsample kernel
%
%   Dataset sizes: 1M, 5M, 10M, 50M, 100M, 500M points
%   Iterations: scaled per size to keep CI runtime reasonable

    % Support both FastSense and FastSense directory names
    if exist(fullfile(pwd, 'libs', 'FastSense', 'private'), 'dir')
        addpath(fullfile(pwd, 'libs', 'FastSense', 'private'));
    else
        addpath(fullfile(pwd, 'libs', 'FastSense', 'private'));
    end

    % Load Dashboard classes (and all lib paths) if not already on path
    if ~exist('DashboardEngine', 'class')
        install();
    end

    % Global warmup — pay one-time costs (class loading, MEX dlopen, BLAS
    % thread pool spin-up, xvfb graphics backend init) before any timed work.
    warmup_();

    sizes  = [1e6, 5e6, 10e6, 50e6, 100e6, 500e6];
    labels = {'1M', '5M', '10M', '50M', '100M', '500M'};

    % Scale iterations down for larger sizes to keep CI runtime reasonable
    N_DS_base   = 20;   % downsample iterations (base for 1M)
    N_ZOOM      = 20;   % zoom cycles per run
    N_RUNS_base = 10;   % runs for zoom/downsample stats (base for 1M)
    N_INIT_base = 5;    % runs for instantiation/render (base for 1M)

    results = {};

    for s = 1:numel(sizes)
        n = sizes(s);
        lbl = labels{s};
        fprintf('\n========== %s points ==========\n', lbl);

        % Scale iterations for larger sizes to keep total runtime manageable
        % ~15 min budget for full suite on CI
        if n <= 1e6
            N_DS = N_DS_base; N_RUNS = N_RUNS_base; N_INIT = N_INIT_base;
        elseif n <= 10e6
            N_DS = 10; N_RUNS = 5; N_INIT = 3;
        elseif n <= 100e6
            N_DS = 5; N_RUNS = 3; N_INIT = 3;
        else
            N_DS = 3; N_RUNS = 3; N_INIT = 3;
        end

        fprintf('  Generating %s data points...\n', lbl);
        x = linspace(0, 100, n);
        y = sin(x * 2*pi / 10) + 0.5 * randn(1, n);
        fprintf('  Data ready (%.0f MB)\n', n * 16 / 1e6);

        % --- Downsample benchmark ---
        minmax_downsample(x, y, 2000);   % untimed warmup
        t_ds = zeros(1, N_RUNS);
        for r = 1:N_RUNS
            tic;
            for k = 1:N_DS
                minmax_downsample(x, y, 2000);
            end
            t_ds(r) = toc / N_DS;
        end
        results = add_result(results, sprintf('Downsample mean (%s)', lbl), 'ms', t_ds * 1000);

        % --- Instantiation benchmark ---
        % Untimed warmup
        fp = FastSense();
        fp.addLine(x, y, 'DisplayName', 'Sensor');
        fp.addThreshold(1.5, 'Direction', 'upper', 'ShowViolations', true);
        fp.addThreshold(-1.5, 'Direction', 'lower', 'ShowViolations', true);
        close all force;
        t_init = zeros(1, N_INIT);
        for r = 1:N_INIT
            tic;
            fp = FastSense();
            fp.addLine(x, y, 'DisplayName', 'Sensor');
            fp.addThreshold(1.5, 'Direction', 'upper', 'ShowViolations', true);
            fp.addThreshold(-1.5, 'Direction', 'lower', 'ShowViolations', true);
            t_init(r) = toc;
            close all force;
        end
        results = add_result(results, sprintf('Instantiation mean (%s)', lbl), 'ms', t_init * 1000);

        % --- Render benchmark ---
        % Untimed warmup
        fp = FastSense();
        fp.addLine(x, y, 'DisplayName', 'Sensor');
        fp.addThreshold(1.5, 'Direction', 'upper', 'ShowViolations', true);
        fp.addThreshold(-1.5, 'Direction', 'lower', 'ShowViolations', true);
        fp.render();
        drawnow;
        close all force;
        t_render = zeros(1, N_INIT);
        for r = 1:N_INIT
            fp = FastSense();
            fp.addLine(x, y, 'DisplayName', 'Sensor');
            fp.addThreshold(1.5, 'Direction', 'upper', 'ShowViolations', true);
            fp.addThreshold(-1.5, 'Direction', 'lower', 'ShowViolations', true);
            tic;
            fp.render();
            drawnow;
            t_render(r) = toc;
            close all force;
        end
        results = add_result(results, sprintf('Render mean (%s)', lbl), 'ms', t_render * 1000);

        % --- Zoom cycle benchmark ---
        fp = FastSense();
        fp.addLine(x, y, 'DisplayName', 'Sensor');
        fp.addThreshold(1.5, 'Direction', 'upper', 'ShowViolations', true);
        fp.addThreshold(-1.5, 'Direction', 'lower', 'ShowViolations', true);
        fp.render();
        drawnow;

        % Warmup
        for k = 1:5
            set(fp.hAxes, 'XLim', [20 80]);
            drawnow;
        end

        t_zoom = zeros(1, N_RUNS);
        for r = 1:N_RUNS
            centers = 10 + 80 * rand(1, N_ZOOM);
            widths  = 1 + 20 * rand(1, N_ZOOM);
            tic;
            for k = 1:N_ZOOM
                set(fp.hAxes, 'XLim', [centers(k)-widths(k)/2, centers(k)+widths(k)/2]);
                drawnow;
            end
            t_zoom(r) = toc / N_ZOOM;
        end
        close all force;

        results = add_result(results, sprintf('Zoom cycle mean (%s)', lbl), 'ms', t_zoom * 1000);

        % Free memory before next size (critical for 100M+ datasets)
        clear x y fp;
    end

    % --- Dashboard benchmarks ---
    fprintf('\n========== Dashboard benchmarks ==========\n');
    N_INIT = 3;

    % a. Dashboard creation + render
    % Untimed warmup
    [d_tmp, ~, ~] = build_bench_dashboard_();
    d_tmp.render();
    drawnow;
    close all force;
    clear d_tmp;
    t_dash = zeros(1, N_INIT);
    for r = 1:N_INIT
        [d_tmp, ~, ~] = build_bench_dashboard_();
        tic;
        d_tmp.render();
        drawnow;
        t_dash(r) = toc;
        close all force;
        clear d_tmp;
    end
    results = add_result(results, 'Dashboard create+render mean', 'ms', t_dash * 1000);

    % b. Live tick
    [d_live, ~, ~] = build_bench_dashboard_();
    d_live.render(); drawnow;
    for k = 1:2, d_live.onLiveTick(); end
    t_tick = zeros(1, N_INIT);
    for r = 1:N_INIT
        tic; d_live.onLiveTick(); t_tick(r) = toc;
    end
    results = add_result(results, 'Dashboard live tick mean', 'ms', t_tick * 1000);
    close all force; clear d_live;

    % c. Page switch
    [d_page, ~, ~] = build_bench_dashboard_();
    d_page.render(); drawnow;
    for k = 1:2, d_page.switchPage(2); d_page.switchPage(1); end
    t_sw = zeros(1, N_INIT);
    for r = 1:N_INIT
        tic; d_page.switchPage(2); d_page.switchPage(1); t_sw(r) = toc / 2;
    end
    results = add_result(results, 'Dashboard page switch mean', 'ms', t_sw * 1000);
    close all force; clear d_page;

    % d. Time slider broadcast
    [d_br, x100k, ~] = build_bench_dashboard_();
    d_br.render(); drawnow;
    tMax = x100k(end);
    for k = 1:2, d_br.broadcastTimeRange(0, tMax * 0.5); end
    t_br = zeros(1, N_INIT);
    for r = 1:N_INIT
        tStart = tMax * rand();
        tic; d_br.broadcastTimeRange(tStart, tStart + tMax * 0.1); t_br(r) = toc;
    end
    results = add_result(results, 'Dashboard broadcastTimeRange mean', 'ms', t_br * 1000);
    close all force; clear d_br;

    % --- Phase 1028: 1000-tag pipeline gate (D-06) ---
    % Emit tickMin + tickMedian for both NoIO (gated) and WithIO (diagnostic).
    % Direct struct append (NOT via add_result_) because each bench invocation
    % already does its own min-of-N internally; we report the bench's own stats
    % rather than re-running it for outer-loop variance.
    fprintf('\n========== Phase 1028: 1000-tag pipeline ==========\n');

    fprintf('Running bench_tag_pipeline_1k (NoIO, cache-on, gated)...\n');
    r1k = bench_tag_pipeline_1k();
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_noio_min_ms', ...
        'unit',  'ms', ...
        'value', r1k.tickMin * 1000); %#ok<AGROW>
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_noio_median_ms', ...
        'unit',  'ms', ...
        'value', r1k.tickMedian * 1000); %#ok<AGROW>

    % Phase 1028 plan 02d: record BOTH cache-on (production default) and
    % cache-off (Plan 02b WithIO baseline / regression check) so the
    % post-cache tBreakdown table in VERIFICATION.md has both numbers.
    fprintf('Running bench_tag_pipeline_1k (WithIO, cache-on, diagnostic — not gated, D-12)...\n');
    rIO = bench_tag_pipeline_1k('Mode', 'WithIO', '--cache-on');
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_withio_min_ms', ...
        'unit',  'ms', ...
        'value', rIO.tickMin * 1000); %#ok<AGROW>
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_withio_cache_on_min_ms', ...
        'unit',  'ms', ...
        'value', rIO.tickMin * 1000); %#ok<AGROW>

    fprintf('Running bench_tag_pipeline_1k (WithIO, cache-off, regression check)...\n');
    rIOOff = bench_tag_pipeline_1k('Mode', 'WithIO', '--cache-off');
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_withio_cache_off_min_ms', ...
        'unit',  'ms', ...
        'value', rIOOff.tickMin * 1000); %#ok<AGROW>

    % Phase 1028 plan 05: record WithIO coalesce-off as the A1+A2
    % regression check. coalesce-on is the production default already
    % captured above as rIO. The delta (coalesce-on - coalesce-off)
    % isolates the cost of Tag.invalidateBatch_(updatedSet) at end-of-tick.
    % Cache stays ON for both runs so the only difference is the listener
    % coalescing path. Production callers use cache-on + coalesce-on.
    fprintf('Running bench_tag_pipeline_1k (WithIO, cache-on, coalesce-off, plan 05 regression)...\n');
    rCoOff = bench_tag_pipeline_1k('Mode', 'WithIO', '--cache-on', '--coalesce-off');
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_withio_coalesce_on_min_ms', ...
        'unit',  'ms', ...
        'value', rIO.tickMin * 1000); %#ok<AGROW>
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_withio_coalesce_off_min_ms', ...
        'unit',  'ms', ...
        'value', rCoOff.tickMin * 1000); %#ok<AGROW>

    % Phase 1028 plan 06: record WithIO fs-coalesce-off as the fs-stat
    % coalescing regression check. fs-coalesce-on is the production default
    % already captured above as rIO. The delta isolates the cost of the
    % per-tag exist/dir/datenum syscalls inside processTag_. Cache stays
    % ON and listener-coalesce stays ON for both runs; only the fs-stat
    % path changes.
    fprintf('Running bench_tag_pipeline_1k (WithIO, cache-on, coalesce-on, fs-coalesce-off, plan 06 regression)...\n');
    rFsOff = bench_tag_pipeline_1k('Mode', 'WithIO', '--cache-on', '--coalesce-on', '--fs-coalesce-off');
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_withio_fs_coalesce_on_min_ms', ...
        'unit',  'ms', ...
        'value', rIO.tickMin * 1000); %#ok<AGROW>
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_withio_fs_coalesce_off_min_ms', ...
        'unit',  'ms', ...
        'value', rFsOff.tickMin * 1000); %#ok<AGROW>
    % Plan 06 syscall-count observability: record the actual number of
    % fs-stat syscalls in the FINAL tick of each run. Production (ON)
    % expects ~1 syscall (8 csvs share 1 parent dir in the bench);
    % regression (OFF) expects ~2000 (2 calls × 1000 tags).
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_withio_fs_coalesce_on_lastfsstat_count', ...
        'unit',  'count', ...
        'value', double(rIO.lastFsStatCount)); %#ok<AGROW>
    results{end+1} = struct( ...
        'name',  'tag_pipeline_1k_withio_fs_coalesce_off_lastfsstat_count', ...
        'unit',  'count', ...
        'value', double(rFsOff.lastFsStatCount)); %#ok<AGROW>

    % Phase 1028 Wave 1: tBreakdown profile run (informational — not gated).
    % Captures per-region wall time so kernel selection in waves 2/3 can be
    % data-driven against the actual hot region rather than RESEARCH's
    % H1-H10 ranking. Slower than the gated run because Octave's profile
    % adds per-call overhead; runs only ONCE at smoke scale to keep CI
    % wall budget bounded.
    %
    % Phase 1028 plan 02d: profile NoIO cache-on as the primary tBreakdown
    % (production-default behavior). Additional WithIO cache-on/off profile
    % runs below quantify the load() reduction at the bench scale.
    fprintf('\nRunning bench_tag_pipeline_1k (--profile, NoIO cache-on, Wave 1 tBreakdown)...\n');
    rProf = bench_tag_pipeline_1k('--smoke', '--profile', '--cache-on');
    nMeasTicks = max(1, numel(rProf.profileTopN.totalTime));  %#ok<NASGU> (smoke has 3 ticks)
    smokeTicksDivisor = 3;  % matches `nTicks=3` for smoke; sec/tick = total/3
    if isfield(rProf.tBreakdown, 'parse')
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_breakdown_parse_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProf.tBreakdown.parse * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_breakdown_mat_write_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProf.tBreakdown.mat_write * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_breakdown_select_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProf.tBreakdown.select * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_breakdown_other_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProf.tBreakdown.other * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_breakdown_monitor_recompute_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProf.tBreakdown.monitor_recompute * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_breakdown_composite_merge_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProf.tBreakdown.composite_merge * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_breakdown_aggregate_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProf.tBreakdown.aggregate * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_breakdown_listener_fanout_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProf.tBreakdown.listener_fanout * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_breakdown_total_profiled_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProf.tBreakdown.totalProfiled * 1000 / smokeTicksDivisor); %#ok<AGROW>
    end

    % Phase 1028 plan 02d: profile WithIO cache-on AND cache-off so the
    % post-cache table in VERIFICATION.md can show the load() reduction at
    % bench scale. Smoke (3 ticks) keeps CI wall under control.
    fprintf('\nRunning bench_tag_pipeline_1k (--profile, WithIO cache-on)...\n');
    rProfOn = bench_tag_pipeline_1k('--smoke', '--profile', 'Mode', 'WithIO', '--cache-on');
    if isfield(rProfOn.tBreakdown, 'mat_write')
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_withio_cache_on_breakdown_mat_write_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProfOn.tBreakdown.mat_write * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_withio_cache_on_breakdown_other_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProfOn.tBreakdown.other * 1000 / smokeTicksDivisor); %#ok<AGROW>
    end

    fprintf('\nRunning bench_tag_pipeline_1k (--profile, WithIO cache-off)...\n');
    rProfOff = bench_tag_pipeline_1k('--smoke', '--profile', 'Mode', 'WithIO', '--cache-off');
    if isfield(rProfOff.tBreakdown, 'mat_write')
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_withio_cache_off_breakdown_mat_write_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProfOff.tBreakdown.mat_write * 1000 / smokeTicksDivisor); %#ok<AGROW>
        results{end+1} = struct( ...
            'name',  'tag_pipeline_1k_withio_cache_off_breakdown_other_ms_per_tick', ...
            'unit',  'ms', ...
            'value', rProfOff.tBreakdown.other * 1000 / smokeTicksDivisor); %#ok<AGROW>
    end

    % --- Write JSON ---
    fid = fopen('benchmark-results.json', 'w');
    fprintf(fid, '[\n');
    for i = 1:numel(results)
        r = results{i};
        comma = ',';
        if i == numel(results), comma = ''; end
        fprintf(fid, '  {"name": "%s", "unit": "%s", "value": %.3f}%s\n', ...
            r.name, r.unit, r.value, comma);
    end
    fprintf(fid, ']\n');
    fclose(fid);

    fprintf('\n=== Benchmark complete — %d metrics written to benchmark-results.json ===\n', numel(results));
end

function [d, x100k, y100k] = build_bench_dashboard_()
%BUILD_BENCH_DASHBOARD_ Build a representative 20-widget, 2-page dashboard for CI benchmarking.
%   Returns [d, x100k, y100k] where d is a rendered-ready DashboardEngine,
%   x100k and y100k are the 100K-point sinusoidal dataset used by fastsense widgets.
    x100k = linspace(0, 10, 100000);
    y100k = sin(x100k * 2 * pi) + 0.1 * randn(1, 100000);

    d = DashboardEngine('CIBench');

    % 6x fastsense widgets — rows 1-3, 2 per row, 12 cols each
    for i = 1:6
        col = mod(i - 1, 2) * 12 + 1;
        row = ceil(i / 2);
        d.addWidget('fastsense', ...
            'Title', sprintf('Signal %d', i), ...
            'Position', [col, row, 12, 1], ...
            'XData', x100k, 'YData', y100k);
    end

    % 4x number widgets — row 4, 6 cols each
    for i = 1:4
        col = (i - 1) * 6 + 1;
        d.addWidget('number', ...
            'Title', sprintf('Count %d', i), ...
            'Position', [col, 4, 6, 1], ...
            'ValueFcn', @() rand());
    end

    % 4x status widgets — row 5, 6 cols each
    for i = 1:4
        col = (i - 1) * 6 + 1;
        d.addWidget('status', ...
            'Title', sprintf('Status %d', i), ...
            'Position', [col, 5, 6, 1], ...
            'ValueFcn', @() 'OK');
    end

    % 2x text widgets — row 6, 12 cols each
    d.addWidget('text', ...
        'Title', 'Info A', ...
        'Position', [1, 6, 12, 1], ...
        'Content', 'Dashboard CI benchmark — panel A');
    d.addWidget('text', ...
        'Title', 'Info B', ...
        'Position', [13, 6, 12, 1], ...
        'Content', 'Dashboard CI benchmark — panel B');

    % 1x barchart widget — row 7, full width
    d.addWidget('barchart', ...
        'Title', 'Metrics', ...
        'Position', [1, 7, 24, 1]);

    % Page 2 — one number widget for page switch benchmark
    d.addPage('Page2');
    d.switchPage(2);
    d.addWidget('number', ...
        'Title', 'Page2 Count', ...
        'Position', [1, 1, 6, 1], ...
        'ValueFcn', @() rand());

    % Reset to page 1 before caller calls render()
    d.switchPage(1);
end

function results = add_result(results, name, unit, samples)
%ADD_RESULT Compute stats and add to results list.
    % Use median as the tracked statistic — far more robust to single-iteration
    % outliers on shared GitHub runners than mean. Metric label keeps the
    % "mean" wording so github-action-benchmark history remains continuous.
    m   = median(samples);
    s   = std(samples);
    rms = sqrt(mean(samples.^2));

    fprintf('  %-30s  median=%.2f %s  std=%.2f %s  rms=%.2f %s  (n=%d)\n', ...
        name, m, unit, s, unit, rms, unit, numel(samples));

    % Report median (under historical "mean" label) as the tracked value
    results{end+1} = struct('name', name, 'unit', unit, 'value', m);
    % Also report std as a separate metric
    results{end+1} = struct('name', [name(1:end-5) ' std' name(end-3:end)], ...
        'unit', unit, 'value', s);
end

function warmup_()
%WARMUP_ One-time prewarm to absorb cold-start costs before any timed work.
%   Loads classes, prewarms MEX kernels, and forces graphics-backend init so
%   the first timed iteration of each benchmark block doesn't pay these costs.
    % Class loading (parses classdef and resolves dependencies)
    DashboardEngine('warmup_dashboard');
    close all force;

    % MEX dlopen + first-touch
    xw = linspace(0, 1, 1e5);
    yw = sin(xw);
    minmax_downsample(xw, yw, 1000);

    % Graphics backend (xvfb cold start can be 200-500 ms)
    f = figure('Visible', 'off');
    plot(xw, yw);
    drawnow;
    close(f);
end
