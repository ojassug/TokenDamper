#!/usr/bin/env node
import { readFileSync, writeFileSync, existsSync, statSync } from 'node:fs';
import { dirname, resolve } from 'node:path';
import { randomUUID } from 'node:crypto';
import { CLI_ADAPTER_NAME, CLI_ADAPTER_VERSION, format as formatCliOutput, parse } from '../adapters/cli';
import { createMultiItemRequest } from '../core/model/constructors';
import { escapeDelimiterLabel, ITEM_DELIMITER_PREFIX, ITEM_DELIMITER_SUFFIX } from '../core/render';
import { registerDeepBackends } from './deep-backends';
import { gitIgnoredAmong, ingestPaths, type IngestedFile } from './ingest';
import { loadConfig } from '../config';
import { declarableLanguages, normalizeLanguage } from '../core/model';
import type { ContextBundle } from '../core/model/types';
import { optimize } from '../core/engine';
import { runExecCommand } from '../gateway/exec';
import { renderTerminalDiff } from './diff-renderer';
import { generateHtmlReport } from './html-reporter';
import { loadBenchmarkFixtures, BenchmarkRunner } from '../bench';
import { renderBenchTable } from './bench-table-renderer';
import { startMcpServer } from '../adapters/mcp';
import type { BenchmarkRunnerConfig } from '../bench/types';
import type { ConfigOverrides } from '../config';
import type { EngineMode } from '../core/parser/mode';

/**
 * Runs the TokenDamper CLI with the provided arguments and IO streams.
 *
 * Returns `number` for every command except `exec`, which returns `Promise<number>` because its
 * exit code belongs to a child process that has not finished yet (audit OX-H1). The union is
 * deliberate: making the whole function `async` would turn a synchronous `number` into a promise
 * for `optimize`, `bench` and `mcp`, none of which need one, and every existing caller reads the
 * result directly. `await` handles both, so a caller that does not care which it got is correct
 * either way.
 */
export function runCli(
  argv: readonly string[],
  io: { readonly stdout: NodeJS.WritableStream; readonly stderr: NodeJS.WritableStream } = {
    stdout: process.stdout,
    stderr: process.stderr,
  },
  cwd: string = process.cwd(),
): number | Promise<number> {
  try {
    const parsed = parseArguments(argv, cwd);
    let engineMode: EngineMode = 'fast';

    if (parsed.command === 'optimize' || parsed.command === 'bench' || parsed.command === 'mcp') {
      // Resolved once, here, so a withdrawn key's notice is written once per run and the engine
      // is chosen by the precedence every other setting has: flag, environment, file, default
      // (DECISIONS §87). Each branch below still loads its own copy; this one decides the engine.
      const config = loadConfig({
        cwd,
        ...(parsed.configPath ? { configPath: parsed.configPath } : {}),
        ...(parsed.configOverrides ? { cliOverrides: parsed.configOverrides } : {}),
      });
      for (const notice of config.notices) io.stderr.write(`tokendamper: ${notice}\n`);
      engineMode = config.engineMode;
      // bench's runner reads no engine mode and the MCP server registers no backends, so running
      // either under a resolved `deep` would report a deep run that never happened (invariant 10).
      // `--mode` is already refused on both; this is the same refusal for the file and env doors.
      if (engineMode === 'deep' && parsed.command !== 'optimize') {
        throw new Error(
          `tokendamper: the engine resolves to deep (engine.mode or TOKENDAMPER_ENGINE_MODE), but ${parsed.command} runs the fast engine only. Set TOKENDAMPER_ENGINE_MODE=fast for this command, or remove engine.mode.`,
        );
      }
    }

    const resolved: ParsedArguments = engineMode === 'deep' ? { ...parsed, engineMode } : parsed;
    if (engineMode === 'deep') {
      // Registration is the one place async work is allowed (`ParserAdapter` is otherwise
      // sync), so it happens here, before the pipeline runs.
      return registerDeepBackends()
        .then(() => dispatch(resolved, io, cwd))
        .catch((err: unknown) => {
          io.stderr.write(`${err instanceof Error ? err.message : String(err)}\n`);
          return 1;
        });
    }

    return dispatch(resolved, io, cwd);
  } catch (error) {
    const message = error instanceof Error ? error.message : 'Unknown TokenDamper error';
    io.stderr.write(`${message}\n`);
    return 1;
  }
}

/**
 * The body of `runCli` after argument parsing — every command branch, moved here unchanged so
 * `runCli` can `await` backend registration before reaching it (Task 8). A pure extraction: the
 * `try`/`catch` stays in `runCli`, wrapping this call, so a thrown error from any branch below
 * is still caught in exactly one place.
 */
function dispatch(
  parsed: ParsedArguments,
  io: { readonly stdout: NodeJS.WritableStream; readonly stderr: NodeJS.WritableStream },
  cwd: string,
): number | Promise<number> {
    if (parsed.command === 'mcp') {
      const config = loadConfig({
        cwd,
        ...(parsed.configPath ? { configPath: parsed.configPath } : {}),
        ...(parsed.configOverrides ? { cliOverrides: parsed.configOverrides } : {}),
      });
      const server = startMcpServer({
        input: process.stdin,
        output: io.stdout as NodeJS.WritableStream,
        log: io.stderr as NodeJS.WritableStream,
        config,
      });

      // A signal must not cut the output stream short — audit OX-L8.
      //
      // `process.exit()` does not wait for writes already handed to a stream, so exiting the
      // instant `stop()` returns discards whatever is still buffered. This was recorded rather
      // than fixed for a stated reason — "delivering SIGINT is not something the suite can do
      // here", so the change would ship unverified — and the fix contemplated at the time,
      // dropping the forced exit and letting the loop drain, carried a real risk of `tokendamper
      // mcp` hanging on Ctrl+C instead.
      //
      // **Measured before writing, because the platform decides whether this bug exists at all.**
      // Node's stdout is synchronous for pipes on Windows and Linux and asynchronous on macOS,
      // and the buffer only overflows on a large frame. Spawning a child that writes one frame
      // and exits the way this handler does:
      //
      //   payload 1 MB, piped   | Windows: 1000046/1000046 complete
      //                         | Linux:    146176/1000046 TRUNCATED  <- 85% of the response lost
      //   payload 1 KB / 100 KB | both: complete (it fits the pipe buffer)
      //
      // So the defect is real, and it is worst exactly where it matters: a large MCP response is
      // the one a client cannot afford to lose half of.
      //
      // **The obvious fix does not work, and was measured too.** Awaiting `server.stop()` — the
      // shape this repository's other Lane A worktree reached for — delivers **146176 bytes, byte
      // for byte the same as no fix at all**: `stop()` is `(): void`, so the await yields one
      // microtask, and a microtask does not run the I/O loop that drains a pipe.
      //
      // What works is asking the stream itself. An empty `write` queues behind everything already
      // pending, so its callback is the stream saying "your bytes have reached the OS": measured
      // 1000046/1000046 complete on Linux. The timeout is what answers the original objection —
      // a consumer that never reads cannot wedge shutdown, because the exit happens anyway after
      // 2 s. `unref` keeps the timer itself from holding the loop open.
      let exiting = false;
      const exitNow = (): void => {
        if (exiting) return;
        exiting = true;
        process.exit(0);
      };
      const shutdown = () => {
        server.stop();
        process.removeListener('SIGINT', shutdown);
        process.removeListener('SIGTERM', shutdown);
        const cap = setTimeout(exitNow, 2000);
        cap.unref?.();
        io.stdout.write('', () => exitNow());
      };

      process.on('SIGINT', shutdown);
      process.on('SIGTERM', shutdown);

      return 0;
    }

    if (parsed.command === 'exec') {
      // Returned, not fired and forgotten. `runExecCommand` always resolved the child's real exit
      // code; this branch used to drop it on the floor and hand back a synchronous `0`, which
      // `main()` had assigned to `process.exitCode` long before the child finished (audit OX-H1).
      // `tokendamper exec -- some-tool && next-step` therefore ran `next-step` after a failure.
      return runExecCommand(parsed.execArgs, { io }).catch((err: Error) => {
        io.stderr.write(`Exec process error: ${err.message}\n`);
        // Reached only when the child could not be spawned at all. A command that simply does not
        // exist does not land here — `shell: true` means the shell starts, diagnoses it, and
        // exits with its own code (127 on sh, 1 on cmd.exe), which arrives through `close`.
        return 1;
      });
    }

    if (parsed.command === 'bench') {
      // No default path. It used to fall back to the literal `test/fixtures/bench`, which
      // exists only in a checkout of this repository — for an installed user that resolved to
      // nothing and `bench` threw before running a fixture (audit M10). Absent, the loader
      // uses the datasets bundled with the package, which is what the repo path resolved to
      // anyway.
      const rawDatasetPath = parsed.datasetPath || (parsed.inputPath !== '-' ? parsed.inputPath : undefined);
      let loadArg: string | undefined = rawDatasetPath;

      // Resolved against `cwd` rather than `process.cwd()`: `runCli` takes its working
      // directory as a parameter, and the loader's own directory check cannot see it.
      if (rawDatasetPath !== undefined) {
        const resolvedPath = resolve(cwd, rawDatasetPath);
        if (existsSync(resolvedPath) && statSync(resolvedPath).isDirectory()) {
          loadArg = undefined;
        }
      }

      const fixtures = loadBenchmarkFixtures(loadArg);
      const config = loadConfig({
        cwd,
        ...(parsed.configPath ? { configPath: parsed.configPath } : {}),
        ...(parsed.configOverrides ? { cliOverrides: parsed.configOverrides } : {}),
      });

      const runnerConfig: BenchmarkRunnerConfig = {
        baseConfig: config,
        sweeps: [
          {
            sweepId: 'cli-sweep',
            budget: config.budget,
          },
        ],
        // Absent unless `--evaluate-quality` was passed. The runner defaults it off (audit
        // OX-M15), so plain `bench` never reaches for an interpreter.
        ...(parsed.evaluateQuality ? { evaluateQuality: true } : {}),
      };

      const report = BenchmarkRunner.run(fixtures, runnerConfig);

      if (!parsed.quiet) {
        const tableOutput = renderBenchTable(report);
        io.stdout.write(`${tableOutput}\n`);
      }

      if (parsed.reportJsonPath) {
        const reportPath = resolve(cwd, parsed.reportJsonPath);
        writeFileSync(reportPath, JSON.stringify(report, null, 2), 'utf8');
      }

      return 0;
    }

    if (parsed.command !== 'optimize') {
      io.stderr.write(
        'Usage: tokendamper optimize <input-file|-> | tokendamper bench [dataset-path] | tokendamper exec -- <command> | tokendamper mcp\n',
      );
      return 1;
    }

    const isStdin = parsed.inputPath === '-';

    // Multi-file ingestion — the route that makes the 0/1 knapsack reachable (audit H5).
    //
    // Entered only when the caller named more than one path, or named a directory. A single
    // file and stdin fall through to the original code below **unchanged**: that route carries
    // the byte-identity guarantee of DECISIONS §35, and the cheapest way to keep it is not to
    // touch it.
    const extraPaths = parsed.extraInputPaths ?? [];
    const namesDirectory =
      !isStdin && existsSync(resolve(cwd, parsed.inputPath)) && statSync(resolve(cwd, parsed.inputPath)).isDirectory();

    if (!isStdin && (extraPaths.length > 0 || namesDirectory)) {
      if (parsed.language !== undefined) {
        // Refused rather than applied to every file (audit OX-M3). `--language` exists for input
        // with no filename to classify by; a directory walk and a list of paths both have one per
        // file, so a blanket declaration can only *overwrite* a correct answer with a single
        // wrong one — declaration outranks extension by design (`constructors.ts`).
        //
        // Measured on a three-file tree at `--language python`: `languageSupport` went from
        // "1 unsupported (json)" to "3 supported, 0 unsupported", `astCoverage` still read
        // `unchecked: 0` because the Python validator genuinely did look at the JSON, and the run
        // fell back entirely. So the cost is not merely a mislabel — it is a coverage report that
        // lies and a guaranteed 0% behind it.
        throw new Error(
          '--language applies to stdin or a single file; a directory or multiple paths are classified per file by extension. ' +
            'Declaring one language for all of them would override every file’s own type. Optimize the files individually to declare a language.',
        );
      }

      return runMultiFileOptimize(parsed, [parsed.inputPath, ...extraPaths], io, cwd);
    }

    const inputPath = isStdin ? undefined : resolve(cwd, parsed.inputPath);

    // Read bytes, decode second, and keep the bytes.
    //
    // This used to be `readFileSync(path, 'utf8')`, which is lossy before the pipeline starts:
    // any byte that is not valid UTF-8 becomes U+FFFD, and U+FFFD re-encodes to three bytes.
    // The fallback path returns `request.rawInput`, so "fail-open hands the caller their input
    // back" was true only for input that happened to be valid UTF-8. Measured on a frozen
    // corpus, `vimspell.sh` — Latin-1, containing "Fernández-Sanguino_Peña" — came back
    // 1,462 -> 1,466 bytes with `fallbackUsed: true`. That is invariant 3 failing quietly.
    const rawBuffer = inputPath ? readFileSync(inputPath) : readFileSync(0);
    const rawInput = rawBuffer.toString('utf8');
    // Round-trip, not a BOM or charset sniff: the only question that matters is whether these
    // exact bytes survive the string model the whole pipeline is built on.
    const inputSurvivesDecoding = Buffer.from(rawInput, 'utf8').equals(rawBuffer);
    const config = loadConfig({
      cwd,
      ...(parsed.configPath ? { configPath: parsed.configPath } : {}),
      ...(parsed.configOverrides ? { cliOverrides: parsed.configOverrides } : {}),
    });
    // `--input-name` is a declared name, not a location: it is never resolved against `cwd`
    // and never opened. Resolving it would put a fabricated absolute path on `item.path` and
    // into the `filepath:` marker, asserting that a file exists where none does.
    const declaredPath = inputPath ?? parsed.inputName;
    const request = parse(rawInput, config, {
      sourceKind: isStdin ? 'stdin' : 'file',
      ...(declaredPath ? { sourcePath: declaredPath } : {}),
      ...(parsed.language ? { language: parsed.language } : {}),
    });

    // Input the string model cannot represent forces a fallback rather than short-circuiting.
    //
    // Falling back is the honest outcome, not a conservative one: every stage, validator and
    // token estimate downstream operates on the decoded string, so for these bytes they would
    // all be reasoning about content the caller never sent, and a "reduction" measured against
    // corrupted input is worse than none. It goes through the engine so the run still produces
    // a trace — returning early here emitted no trace at all, which a consumer cannot tell
    // apart from a silent crash.
    const result = optimize(request, {
      ...(parsed.maxDebt !== undefined ? { maxDebtThreshold: parsed.maxDebt } : {}),
      ...(parsed.maxDrift !== undefined ? { maxDriftThreshold: parsed.maxDrift } : {}),
      ...(parsed.keepDocstrings ? { keepDocstrings: true } : {}),
      ...(parsed.engineMode ? { engineMode: parsed.engineMode } : {}),
      ...(inputSurvivesDecoding
        ? {}
        : {
            inputNotRepresentable: `Input is not valid UTF-8 (${rawBuffer.length} bytes); it cannot be represented losslessly as a string, so no stage output can be trusted against it. Emitted verbatim.`,
          }),
    });

    // On fallback, write the bytes that were read rather than the string that was decoded from
    // them. `resolveFallback` returns `request.rawInput`, so for valid UTF-8 this is the same
    // output byte for byte; for anything else it is the difference between the caller's file
    // and a lossy re-encoding of it. The guard above means this branch is currently reached
    // only by round-trippable input — it is here so the guarantee does not depend on that.
    if (result.fallbackUsed) {
      io.stdout.write(rawBuffer);
    } else {
      io.stdout.write(formatCliOutput(result));
    }

    if (parsed.diff) {
      const diffStr = renderTerminalDiff(request.bundle, result.finalBundle);
      io.stdout.write(`\n${diffStr}\n`);
    }

    if (parsed.diffHtmlPath) {
      const htmlPath = resolve(cwd, parsed.diffHtmlPath);
      generateHtmlReport(result, request.bundle, { outputPath: htmlPath });
    }

    io.stderr.write(`${JSON.stringify(result.trace, null, 2)}\n`);
    return 0;
}

/**
 * `optimize` over more than one file.
 *
 * This is the ingestion path audit H5 asked for. Until it existed, `createContextBundle` produced
 * exactly one item for every shipping entry point, so `applyCacheAwarePrefixLocking` pinned item
 * 0, `solve01Knapsack` always selected it, `itemsPruned` was always 0, and roughly a thousand
 * lines — the knapsack solver, cache-aware prefix locking, topology scoring, the dependency graph,
 * the git inspector — could not affect any output the product was able to produce. Measured on a
 * six-file bundle from this repository at `maxInputTokens: 5000`, the pruner now removes 3 items
 * and saves 897 tokens.
 *
 * Two properties are load-bearing, and are asserted in `test/integration/cli-multi-file.test.ts`:
 *
 *   - **Fail-open is per file.** Each file's original *bytes* are written back inside the
 *     envelope, not a re-encoding of the decoded string, so a file that is not valid UTF-8
 *     survives exactly as the single-file route guarantees (DECISIONS §35). What is *not*
 *     byte-identical is the stream as a whole, because the headers are TokenDamper's and were
 *     never in any input file.
 *   - **Order is deterministic.** `expandPath` sorts, because prefix locking pins the first
 *     ~1,024 tokens and therefore decides which files bypass the knapsack entirely
 *     (invariants 6 and 7).
 */
function runMultiFileOptimize(
  parsed: ParsedArguments,
  paths: readonly string[],
  io: { readonly stdout: NodeJS.WritableStream; readonly stderr: NodeJS.WritableStream },
  cwd: string,
): number {
  const files = ingestPaths(paths, cwd);
  if (files.length === 0) {
    io.stderr.write('No ingestible files found for the given path(s).\n');
    return 1;
  }

  const config = loadConfig({
    cwd,
    ...(parsed.configPath ? { configPath: parsed.configPath } : {}),
    ...(parsed.configOverrides ? { cliOverrides: parsed.configOverrides } : {}),
  });

  const request = createMultiItemRequest(
    files.map((file) => ({
      path: file.path,
      content: file.content,
      ...(parsed.language ? { language: parsed.language } : {}),
    })),
    config,
    {
      requestId: randomUUID(),
      adapterName: CLI_ADAPTER_NAME,
      adapterVersion: CLI_ADAPTER_VERSION,
      source: 'file',
    },
  );

  const unrepresentable = files.filter((file) => !file.representable);
  const result = optimize(request, {
    ...(parsed.maxDebt !== undefined ? { maxDebtThreshold: parsed.maxDebt } : {}),
    ...(parsed.maxDrift !== undefined ? { maxDriftThreshold: parsed.maxDrift } : {}),
    ...(parsed.keepDocstrings ? { keepDocstrings: true } : {}),
    ...(parsed.engineMode ? { engineMode: parsed.engineMode } : {}),
    ...(unrepresentable.length === 0
      ? {}
      : {
          inputNotRepresentable: `${unrepresentable.length} of ${files.length} input file(s) are not valid UTF-8 and cannot be represented losslessly as a string, so no stage output can be trusted against them. Emitted verbatim.`,
        }),
  });

  if (result.fallbackUsed) {
    // Original bytes per file, under the same headers `renderItemsOutput` produces. Writing
    // `result.emittedOutput` here would re-encode, which is exactly what DECISIONS §35
    // established loses the caller's data for input the string model cannot represent.
    io.stdout.write(renderFallbackBytes(files));
  } else {
    io.stdout.write(result.emittedOutput);
  }

  warnAboutIgnoredFiles(files, cwd, io.stderr);
  warnAboutDroppedFiles(request.bundle, result.finalBundle, io.stderr);

  if (parsed.diff) {
    // Rendered here too (audit OX-M2). This branch handled `--diff-html` and dropped `--diff`,
    // so a caller asking for a terminal diff over a directory paid for the flag and got nothing
    // — the accepted-then-ignored shape `SUPPORTED_FLAGS` exists to prevent. `renderTerminalDiff`
    // already takes a whole `ContextBundle`, so no per-file variant is needed.
    io.stdout.write(`\n${renderTerminalDiff(request.bundle, result.finalBundle)}\n`);
  }

  if (parsed.diffHtmlPath) {
    generateHtmlReport(result, request.bundle, { outputPath: resolve(cwd, parsed.diffHtmlPath) });
  }

  io.stderr.write(`${JSON.stringify(result.trace, null, 2)}\n`);
  return 0;
}

/**
 * Says out loud when the knapsack removed whole files from the output.
 *
 * `pruning:topology-pruner` drops entire items to meet the token budget, which is a different
 * operation from elision: elision leaves a marker saying what it took, and pruning leaves
 * nothing at all. On a directory run the file simply is not in stdout, and a caller piping that
 * to a model has no way to notice — the model will not report a file it was never shown, it
 * will infer an API and be confidently wrong about it.
 *
 * The trace already carried `itemsPruned`, so this is not new information; it is the same
 * information somewhere a person reading a terminal will actually see. Measured on a 7-file
 * project at `--target-reduction-ratio 0.3`, two modules were dropped silently.
 *
 * Derived by diffing the bundles rather than by reading the stage's metric, because the metric
 * is a count and the useful part is *which* files. The fallback path returns the original
 * bundle, so nothing is reported there — correctly, since nothing was dropped.
 */
/**
 * Names ingested files that git is being told to ignore (security review F-03).
 *
 * Written to stderr, so it cannot corrupt the optimized stream on stdout, and emitted even when
 * the run succeeds — the point is that the caller is about to send these bytes to a model and may
 * not know `secrets.yaml` was among them. See `gitIgnoredAmong` for why this reports rather than
 * filters, and for why no filename reaches a command line.
 */
function warnAboutIgnoredFiles(
  files: ReadonlyArray<IngestedFile>,
  cwd: string,
  stderr: NodeJS.WritableStream,
): void {
  // Run the query inside the tree being *read*, not the process's own. `optimize /other/repo`
  // resolves to absolute paths, and `git check-ignore` answers according to the repository it is
  // run in — asking this repository about another one's paths reports nothing at all, silently,
  // which is the shape of failure this warning exists to prevent. A bundle spanning two
  // repositories is checked against the first one's rules; that under-reports rather than
  // misreports, and no realistic invocation does it.
  const first = files[0];
  const root = first ? dirname(first.path) : cwd;
  const ignored = gitIgnoredAmong(
    files.map((f) => f.path),
    root,
  );
  if (ignored.length === 0) return;

  stderr.write(
    `Warning: ${ignored.length} of ${files.length} ingested file(s) are ignored by git, and their ` +
      `contents are in the output:\n` +
      ignored.map((name) => `  - ${name}\n`).join('') +
      `They were read because ingestion selects by extension and does not consult .gitignore. ` +
      `Name files individually, or point at a narrower directory, to exclude them.\n`,
  );
}

function warnAboutDroppedFiles(
  before: ContextBundle,
  after: ContextBundle,
  stderr: NodeJS.WritableStream,
): void {
  const survived = new Set(after.items.map((item) => item.id));
  const dropped = before.items.filter((item) => !survived.has(item.id));
  if (dropped.length === 0) {
    return;
  }

  const names = dropped.map((item) => item.path ?? item.origin ?? item.id);
  stderr.write(
    `Warning: ${dropped.length} of ${before.items.length} file(s) were removed entirely to meet the token budget, ` +
      `not elided — their contents are absent from the output with no marker:\n` +
      names.map((name) => `  - ${name}\n`).join('') +
      `Lower --target-reduction-ratio (e.g. 0.3 -> 0.1), raise --max-input-tokens, or optimize files individually to keep them.\n`,
  );
}

/**
 * The fallback stream: each file's original bytes, under the header the renderer emits.
 *
 * **The label goes through `escapeDelimiterLabel`, the same one `core/render` uses** (security
 * review S-02). It used to interpolate `file.path` raw, and a POSIX filename may contain a
 * newline — so a crafted name broke the header across lines here and planted a second,
 * well-formed `==> … <==` naming a file that does not exist, on the one route F-06's fix did not
 * reach. Reaching it is not exotic: fail-open is where this function is called, and an attacker
 * forces it with one file of their own that is not valid UTF-8.
 *
 * Only the header is escaped. `file.bytes` is written through untouched, because emitting the
 * caller's original bytes is the entire reason this path exists rather than `emittedOutput`
 * (DECISIONS §35).
 */
export function renderFallbackBytes(files: ReadonlyArray<IngestedFile>): Buffer {
  if (files.length === 1) {
    return files[0]!.bytes;
  }

  const parts: Buffer[] = [];
  files.forEach((file, index) => {
    if (index > 0) parts.push(Buffer.from('\n', 'utf8'));
    const label = escapeDelimiterLabel(file.path);
    parts.push(Buffer.from(`${ITEM_DELIMITER_PREFIX}${label}${ITEM_DELIMITER_SUFFIX}\n`, 'utf8'));
    parts.push(file.bytes);
  });
  return Buffer.concat(parts);
}

/**
 * Entry point used by the executable wrapper and compiled CLI binary.
 */
export function main(): void {
  const exitCode = runCli(process.argv.slice(2));

  if (typeof exitCode === 'number') {
    process.exitCode = exitCode;
    return;
  }

  // `exec` is the one command whose code is not known yet (audit OX-H1). Assigning it on
  // settlement is sufficient and does not need an explicit `process.exit`: the spawned child
  // inherits this process's stdio, so the event loop cannot drain while it is still running, and
  // forcing an exit here would risk truncating whatever the child last wrote.
  void exitCode.then((code) => {
    process.exitCode = code;
  });
}

export interface ParsedArguments {
  readonly command: 'optimize' | 'exec' | 'bench' | 'mcp' | 'unknown';
  readonly inputPath: string;
  /**
   * Additional positional paths for `optimize`. Empty for the single-file and stdin routes,
   * which stay byte-for-byte what they were (audit H5).
   */
  readonly extraInputPaths?: readonly string[];
  readonly datasetPath?: string;
  readonly reportJsonPath?: string;
  /**
   * `--evaluate-quality`: run the fixture-execution evaluator, which shells out to `python`.
   * Off unless asked for by name — audit OX-M15.
   */
  readonly evaluateQuality?: boolean;
  readonly quiet?: boolean;
  readonly execArgs: readonly string[];
  readonly configPath?: string;
  readonly configOverrides?: Partial<ConfigOverrides>;
  readonly diff?: boolean;
  readonly diffHtmlPath?: string;
  readonly maxDebt?: number;
  readonly maxDrift?: number;
  /** `--keep-docstrings`: keep leading docstrings outside elided regions (Python only). */
  readonly keepDocstrings?: boolean;
  /**
   * The resolved engine — `--mode`, then `TOKENDAMPER_ENGINE_MODE`, then `engine.mode`. Set by
   * `runCli` after config resolves, never by the parser, which carries the flag in
   * `configOverrides` like every other setting.
   */
  readonly engineMode?: EngineMode;
  /** `--language`: what the content is, declared by the caller. */
  readonly language?: string;
  /** `--input-name`: the filename stdin content would have had. Never opened. */
  readonly inputName?: string;
}

/**
 * The flags each command actually reads, keyed by what `runCli` consumes — not by what the
 * parse loop happens to recognize.
 *
 * The two used to be different, silently. Every flag below was accepted by the loop for every
 * command and then dropped by the command that had no field for it: `bench --diff`,
 * `optimize --report-json`, and worst of all `mcp --config`, which the MCP branch *reads*
 * (`parsed.configPath`) while the parser returned before ever setting it — so pointing the
 * server at a config file silently ran it on defaults. Each exited 0 and looked configured.
 *
 * That is the shape DECISIONS §29 rejects for `--language`, and it was never specific to
 * `--language`. An unsupported flag is now an error naming where it *is* supported.
 */
/**
 * Three flags are absent from this list on purpose, and their absence is the fix.
 *
 * `--max-output-tokens` and `--max-latency-ms` were parsed, range-validated, merged into the
 * budget — and then read by nothing at all, anywhere in the pipeline. `--risk-tolerance` was
 * read by exactly one thing, `bench-table-renderer.ts`, which prints it in a column; no stage,
 * validator or planner consults it, so setting it changed a label and nothing else.
 *
 * They are removed from the *surface*, not from `OptimizationBudget`, which `ARCHITECTURE.md`
 * pins as a frozen model. A field awaiting an implementation is a different thing from a
 * command-line dial that reports success and does nothing (audit H4).
 *
 * **`--trace-output` was withdrawn later, on the same grounds — audit OX-H5, DECISIONS §62.** It
 * survived the H4 sweep because it is not a budget field: it was parsed, validated and stored on
 * `ResolvedConfig`, where nothing read it. The trace goes out through a literal
 * `io.stderr.write(...)`, so `--trace-output stdout` reported success and changed nothing, and a
 * caller redirecting it to capture a trace in a pipe concluded the tool had ignored them. It had.
 * `--mode` lost its `explain` value in the same change, for the same reason. **2.0.0 withdrew
 * `optimize` and `bench` as well (DECISIONS §87)** — the identity and a duplicate of the
 * positional command — and gave the name to the engine, which `--engine-mode` had carried.
 *
 * `--target-reduction-ratio` was called out here as "nearly as inert — the planner reads it only
 * as `> 0`". **That has not been true since DECISIONS §48**, which resolved it against the input
 * into an absolute token ceiling that both `pruning:topology-pruner` and
 * `compression:token-hashing` respect. It is a real target now, adhered to partially rather than
 * exactly, and §50 narrowed the gap further with sub-region elision. It stays because it works.
 */
const COMMON_FLAGS = [
  '--config',
  '--planner-mode',
  '--minimum-confidence',
  '--log-level',
  '--max-input-tokens',
  '--target-reduction-ratio',
  '--preserve-kinds',
] as const;

export const SUPPORTED_FLAGS: Readonly<Record<'optimize' | 'bench' | 'mcp', ReadonlySet<string>>> = {
  optimize: new Set([
    ...COMMON_FLAGS,
    '--diff',
    '--diff-html',
    '--max-debt',
    '--max-drift',
    '--keep-docstrings',
    '--mode',
    '--language',
    '--input-name',
  ]),
  // `--mode` (the engine) is optimize-only. `src/bench/runner.ts` never reads an engine mode, and
  // the MCP server registers no backends, so accepting `--mode deep` on either would report a
  // deep run that never happened (invariant 10). Deep through bench or MCP is closed as not done
  // in DECISIONS §89.
  bench: new Set([...COMMON_FLAGS, '--report-json', '--quiet', '--evaluate-quality']),
  mcp: new Set(COMMON_FLAGS),
};

function rejectUnsupportedFlags(command: 'optimize' | 'bench' | 'mcp', seen: ReadonlySet<string>): void {
  const unsupported = [...seen].filter((flag) => !SUPPORTED_FLAGS[command].has(flag));
  if (unsupported.length === 0) {
    return;
  }

  const detail = unsupported
    .map((flag) => {
      const elsewhere = (Object.keys(SUPPORTED_FLAGS) as Array<keyof typeof SUPPORTED_FLAGS>)
        .filter((other) => SUPPORTED_FLAGS[other].has(flag))
        .join(', ');
      return elsewhere ? `${flag} (applies to: ${elsewhere})` : flag;
    })
    .join('; ');

  throw new Error(`Unsupported for \`tokendamper ${command}\`: ${detail}.`);
}

/**
 * Exported for `test/unit/cli/flag-support.test.ts`, which checks the flag table against the
 * parse loop it governs. A parser is testable directly; asserting on it through `runCli` would
 * mean starting an MCP server to find out whether `--config` was read.
 */
export function parseArguments(argv: readonly string[], cwd: string): ParsedArguments {
  void cwd;

  const args = [...argv];
  const command = args.shift();

  if (command === 'exec') {
    // Drop optional '--' separator if present. Everything after it belongs to the child
    // process, so `exec` is deliberately outside the flag table above — it forwards rather
    // than consumes.
    if (args[0] === '--') {
      args.shift();
    }
    return {
      command: 'exec',
      inputPath: '',
      execArgs: args,
    };
  }

  let inputPath = '';
  const extraInputPaths: string[] = [];
  let datasetPath: string | undefined;

  if (command === 'bench') {
    if (args.length > 0 && args[0] !== undefined && !args[0].startsWith('-')) {
      datasetPath = args.shift();
    }
  } else if (command === 'optimize') {
    if (args.length > 0 && args[0] !== undefined && (args[0] === '-' || !args[0].startsWith('-'))) {
      inputPath = args.shift()!;
    } else {
      throw new Error('Missing input file path.');
    }
    // Additional positional paths, so `optimize a.ts b.ts` and a shell glob both work. Collected
    // here rather than after flag parsing because a path is any non-flag token, and stopping at
    // the first flag keeps `optimize a.ts b.ts --target-reduction-ratio 0.3` unambiguous.
    while (args.length > 0 && args[0] !== undefined && !args[0].startsWith('-')) {
      extraInputPaths.push(args.shift()!);
    }
  } else if (command !== 'mcp') {
    return {
      command: 'unknown',
      inputPath: '',
      execArgs: [],
    };
  }

  let configPath: string | undefined;
  const configOverrides: Partial<ConfigOverrides> = {};
  let minimumConfidence: number | undefined;
  let budgetOverrides: NonNullable<Partial<ConfigOverrides>['budget']> | undefined;
  let diff = false;
  let diffHtmlPath: string | undefined;
  let maxDebt: number | undefined;
  let maxDrift: number | undefined;
  let keepDocstrings = false;
  let reportJsonPath: string | undefined;
  let evaluateQuality = false;
  let quiet = false;
  let language: string | undefined;
  let inputName: string | undefined;
  // Recorded as encountered, checked against the command once parsing is done, so a refusal
  // names every offending flag at once rather than the first one met.
  const seenFlags = new Set<string>();

  while (args.length > 0) {
    const flag = args.shift();
    if (flag !== undefined) {
      seenFlags.add(flag);
    }
    if (flag === '--config') {
      configPath = args.shift();
      if (!configPath) {
        throw new Error('Missing value for --config.');
      }
      continue;
    }

    if (flag === '--mode') {
      const value = args.shift();
      if (value === 'fast' || value === 'deep') {
        // Into the config layers rather than straight onto the result, so the flag outranks
        // `TOKENDAMPER_ENGINE_MODE` and `engine.mode` by the loader's one precedence rule.
        configOverrides.engineMode = value;
        continue;
      }
      if (value === 'optimize' || value === 'bench') {
        // 2.0.0 (DECISIONS §87): `optimize` was the identity and `bench` duplicated the positional
        // command, so the name was freed for the engine. A parse error naming the replacement,
        // never a silent reinterpretation — a script passing `--mode bench` must not start
        // optimizing instead.
        throw new Error(
          `--mode ${value} was withdrawn in 2.0.0; run \`tokendamper ${value} …\` instead. --mode now selects the engine: fast (default) or deep.`,
        );
      }
      throw new Error('Invalid value for --mode. Accepted values: fast, deep.');
    }

    if (flag === '--engine-mode') {
      throw new Error('--engine-mode was withdrawn in 2.0.0; use --mode fast|deep.');
    }

    if (flag === '--report-json') {
      const value = args.shift();
      if (!value) {
        throw new Error('Missing value for --report-json.');
      }
      reportJsonPath = value;
      continue;
    }

    if (flag === '--quiet') {
      quiet = true;
      continue;
    }

    if (flag === '--evaluate-quality') {
      evaluateQuality = true;
      continue;
    }

    if (flag === '--planner-mode') {
      const value = args.shift();
      if (value === 'pass_through') {
        configOverrides.plannerMode = value;
        continue;
      }
      throw new Error('Invalid value for --planner-mode.');
    }

    if (flag === '--minimum-confidence') {
      const value = args.shift();
      if (!value) {
        throw new Error('Missing value for --minimum-confidence.');
      }
      minimumConfidence = Number(value);
      if (!Number.isFinite(minimumConfidence)) {
        throw new Error('Invalid value for --minimum-confidence.');
      }
      continue;
    }

    if (flag === '--log-level') {
      const value = args.shift();
      if (value === 'silent' || value === 'error' || value === 'warn' || value === 'info' || value === 'debug') {
        configOverrides.logLevel = value;
        continue;
      }
      throw new Error('Invalid value for --log-level.');
    }

    if (flag === '--max-input-tokens') {
      const value = args.shift();
      const parsedValue = parseBudgetNumber(value, '--max-input-tokens');
      budgetOverrides = {
        ...(budgetOverrides ?? {}),
        maxInputTokens: parsedValue,
      };
      continue;
    }

    if (flag === '--target-reduction-ratio') {
      const value = args.shift();
      const parsedValue = parseBudgetRatio(value);
      budgetOverrides = {
        ...(budgetOverrides ?? {}),
        targetReductionRatio: parsedValue,
      };
      continue;
    }

    if (flag === '--preserve-kinds') {
      const value = args.shift();
      if (!value) {
        throw new Error('Missing value for --preserve-kinds.');
      }
      const preserveKinds = value
        .split(',')
        .map((entry) => entry.trim())
        .filter((entry): entry is 'prompt' | 'file' | 'diff' | 'conversation' | 'note' =>
          entry === 'prompt' ||
          entry === 'file' ||
          entry === 'diff' ||
          entry === 'conversation' ||
          entry === 'note',
        );
      if (preserveKinds.length === 0) {
        throw new Error('Invalid value for --preserve-kinds.');
      }
      budgetOverrides = {
        ...(budgetOverrides ?? {}),
        preserveKinds,
      };
      continue;
    }

    if (flag === '--diff') {
      diff = true;
      continue;
    }

    if (flag === '--keep-docstrings') {
      keepDocstrings = true;
      continue;
    }

    if (flag === '--diff-html') {
      const value = args.shift();
      if (!value) {
        throw new Error('Missing value for --diff-html.');
      }
      diffHtmlPath = value;
      continue;
    }

    if (flag === '--max-debt') {
      const value = args.shift();
      if (!value) {
        throw new Error('Missing value for --max-debt.');
      }
      const parsedVal = Number(value);
      if (!Number.isFinite(parsedVal) || parsedVal < 0 || parsedVal > 100) {
        throw new Error('Invalid value for --max-debt.');
      }
      maxDebt = parsedVal;
      continue;
    }

    if (flag === '--max-drift') {
      const value = args.shift();
      if (!value) {
        throw new Error('Missing value for --max-drift.');
      }
      const parsedVal = Number(value);
      if (!Number.isFinite(parsedVal) || parsedVal < 0 || parsedVal > 1) {
        throw new Error('Invalid value for --max-drift.');
      }
      maxDrift = parsedVal;
      continue;
    }

    if (flag === '--language') {
      const value = args.shift();
      if (!value) {
        throw new Error('Missing value for --language.');
      }
      // Rejected here rather than dropped in the model. An unrecognized declaration that
      // silently does nothing produces a run that looks declared, validates nothing, and
      // reports a clean trace — invariant 10's shape.
      if (!normalizeLanguage(value)) {
        throw new Error(
          `Invalid value for --language: ${value}. Accepted: ${declarableLanguages().join(', ')}.`,
        );
      }
      language = value;
      continue;
    }

    if (flag === '--input-name') {
      const value = args.shift();
      if (!value) {
        throw new Error('Missing value for --input-name.');
      }
      inputName = value;
      continue;
    }

    throw new Error(`Unknown argument: ${flag ?? ''}`);
  }

  const resolvedOverrides: Partial<ConfigOverrides> =
    minimumConfidence === undefined && budgetOverrides === undefined
      ? configOverrides
      : {
          ...configOverrides,
          ...(minimumConfidence === undefined ? {} : { minimumConfidence }),
          ...(budgetOverrides === undefined ? {} : { budget: budgetOverrides }),
        };

  if (command === 'mcp') {
    rejectUnsupportedFlags('mcp', seenFlags);
    return {
      command: 'mcp',
      inputPath: '',
      execArgs: [],
      // Populated, at last. The MCP branch of `runCli` has always read these two; the parser
      // returned before the loop that sets them, so `mcp --config custom.json` ran on defaults.
      ...(configPath ? { configPath } : {}),
      configOverrides: resolvedOverrides,
    };
  }

  if (command === 'bench') {
    rejectUnsupportedFlags('bench', seenFlags);
    return {
      command: 'bench',
      inputPath: inputPath || datasetPath || '',
      ...(datasetPath || inputPath ? { datasetPath: datasetPath || inputPath } : {}),
      ...(reportJsonPath ? { reportJsonPath } : {}),
      ...(evaluateQuality ? { evaluateQuality } : {}),
      ...(quiet ? { quiet } : {}),
      execArgs: [],
      ...(configPath ? { configPath } : {}),
      configOverrides: resolvedOverrides,
    };
  }

  rejectUnsupportedFlags('optimize', seenFlags);

  if (inputName !== undefined && inputPath !== '-') {
    // Not merged, and not silently ignored: with a real file argument there are two
    // candidate names for one item, and picking either leaves the other as a lie in the
    // trace. The caller has to say which one they meant.
    throw new Error('--input-name applies to stdin input only; pass `-` as the input file.');
  }

  return {
    command: 'optimize',
    inputPath,
    ...(extraInputPaths.length > 0 ? { extraInputPaths: Object.freeze([...extraInputPaths]) } : {}),
    execArgs: [],
    ...(language ? { language } : {}),
    ...(inputName ? { inputName } : {}),
    ...(configPath ? { configPath } : {}),
    ...(diff ? { diff } : {}),
    ...(diffHtmlPath ? { diffHtmlPath } : {}),
    ...(maxDebt !== undefined ? { maxDebt } : {}),
    ...(maxDrift !== undefined ? { maxDrift } : {}),
    ...(keepDocstrings ? { keepDocstrings } : {}),
    configOverrides: resolvedOverrides,
  };
}

function parseBudgetNumber(value: string | undefined, flagName: string): number {
  if (!value) {
    throw new Error(`Missing value for ${flagName}.`);
  }

  const parsed = Number(value);
  if (!Number.isInteger(parsed) || parsed < 0) {
    throw new Error(`Invalid value for ${flagName}.`);
  }

  return parsed;
}

function parseBudgetRatio(value: string | undefined): number {
  if (!value) {
    throw new Error('Missing value for --target-reduction-ratio.');
  }

  const parsed = Number(value);
  if (!Number.isFinite(parsed) || parsed < 0 || parsed > 1) {
    throw new Error('Invalid value for --target-reduction-ratio.');
  }

  return parsed;
}


// Delegates rather than repeating `main()`'s body. This block *is* the shipped entry point —
// `package.json`'s `bin` points at `dist/src/cli/main.js`, so this is what runs, and `main()` is
// what tests and the wrapper call. They had drifted into two copies of the same logic, and the
// copy here carried a `typeof exitCode === 'number'` guard that was dead while `runCli` always
// returned a number. Once `exec` started returning a promise (audit OX-H1) that guard would have
// silently dropped it on the floor, leaving the shipped binary exiting 0 with a full green suite
// behind it — the fix tested through `main()`, the product running this.
if (require.main === module) {
  main();
}