# AGENTS.md

Instructions for AI coding agents working in this repository. Human contributors should read [CONTRIBUTING.md](CONTRIBUTING.md); everything here applies to you as well.

## What this project is

jAIgent is a CLI and Python library: an LLM agent that can search the web and manipulate local files. Users bring their own API key. The project's selling points are that it is **small enough to read**, **safe by default**, and **easy to extend**. Every change should protect those three properties.

## Setup

```bash
python -m venv .venv && source .venv/bin/activate
pip install -e ".[dev]"
```

## Checks — run these before you claim to be done

```bash
pytest                 # must pass, no skips introduced
ruff check .           # must be clean
ruff format .          # apply, don't just check
mypy                   # must be clean
```

All four are required. For anything touching the shell tool, the sandbox,
key handling or a dependency, also run:

```bash
bandit -r src/jaigent -ll     # must report zero issues
pip-audit                     # no known CVEs in dependencies
``` The test suite is offline and needs no API key; if a test of yours needs the network, it is the wrong test.

## Repository layout

```
src/jaigent/
├── __init__.py     # public API — update __all__ when you export something
├── agent.py        # the tool-calling loop
├── approval.py     # diff previews and the ask/auto/dry-run policy
├── branding.py     # the logo: glyphs, colours, responsive sizing
├── checkpoint.py   # content-addressed snapshots behind undo/rewind
├── cli.py          # argparse + rich rendering
├── config.py       # Settings, env vars, .env loader
├── updater.py      # release checking and self-upgrade
├── commands.py     # custom slash commands
├── failover.py     # retry classification and provider chaining
├── gateway.py      # the OpenAI-compatible server and its keys
├── input_lock.py   # keeps the chat input locked while a turn runs
├── models.py       # the curated model catalogue
├── paths.py        # where files live, per platform
├── picker.py       # the arrow-key option picker behind ask_user
├── router.py       # auto model selection
├── ui.py           # animations, phrases, glyph fallbacks
├── pricing.py      # token accounting and the price table
├── schedule.py     # timed tasks
├── session.py      # saving and resuming conversations
├── settings_store.py  # the project/user settings files
├── plugins.py      # local tool plugins
├── skills.py       # reusable instruction packs
├── prompts.py      # system prompt
├── errors.py       # exception hierarchy
├── llm/
│   ├── base.py     # LLMProvider ABC, AssistantMessage, ToolCall
│   ├── openai.py   # OpenAI-compatible chat completions
│   ├── anthropic.py
│   └── gemini.py   # Google's generateContent protocol
└── tools/
    ├── base.py     # Tool, ToolRegistry
    ├── sandbox.py  # workspace confinement — treat as security-critical
    ├── files.py
    ├── web.py
    └── shell.py    # opt-in, dangerous
tests/              # mirrors src/, one test module per source module
examples/           # runnable demos, including a mock LLM server
packaging/          # PyInstaller spec, frozen launcher, installers, icon
docs/               # long-form guides: architecture, terminal UI, CI, proposals
```

## Conventions

**Paths.** Never call `Path.home()` directly. Use `jaigent.paths.user_home()`,
`project_home()` or `scoped_dirs()` so Windows and XDG users get the right location and
every store agrees on one root.

**Terminal output.** Anything decorative goes through `ui.py`. New glyphs need an ASCII
fallback in `GLYPHS`, because Windows consoles raise `UnicodeEncodeError` rather than
degrading. Never animate unconditionally: check `console.is_terminal` and `no_color`,
which `Thinking` already does. Anything drawn in place — a status line, a redraw, a
cursor movement — must also fit the terminal it is drawn in; `Thinking.render` trims
itself, and overflowing means every frame leaves a stale row behind.

**Moving the cursor.** If you emit an escape sequence that repositions the cursor, test
it with a terminal emulator, not with string assertions. `tests/test_terminal_render.py`
feeds the output through `pyte` and asserts on the resulting screen. The first version
of the post-streaming markdown redraw passed every string-level test and still left
debris on screen; only the emulator caught it.

**Colour.** Never hard-code a colour. Import `ACCENT`, `ACCENT_DIM`, `INK` or `MUTED`
from `branding.py` so the palette stays consistent and themeable in one place.

**Approval.** Any new tool that changes the filesystem or the machine must be added to
`MUTATING_TOOLS` in `approval.py` and given a case in `preview()` so the user sees what
is about to happen. A tool that mutates without a preview is a bug.

**Prompts with brackets.** Rich parses `[y]` as markup. When a prompt or message
contains literal square brackets, pass a `rich.text.Text` instead of a markup string —
see `Approver._read_answer`.

**Branding.** The logo lives in `branding.py` as per-letter glyph blocks, never as flat
strings — that is what keeps the accent on the `AI` in j-**AI**-gent and lets the width be
computed. If you touch the glyphs, keep every letter rectangular and all letters the same
height; `tests/test_branding.py` asserts both, plus that the logo never overflows the
terminal at any width. Anything user-facing must degrade correctly under `--no-color`.

**Style.** Python 3.10+, 100-column lines, `from __future__ import annotations` at the top of every module, type hints on all public functions, imperative-mood docstrings on public APIs. Ruff enforces the rest; don't hand-format.

**Errors.** Everything raised on purpose inherits from `JaigentError`:

- `ConfigurationError` — bad or missing settings. The message must tell the user exactly which variable to set.
- `ProviderError` — the LLM call failed. Include the HTTP status and a hint when the cause is known.
- `ToolError` — a tool failed in a way the *model* should read and recover from.
- `SandboxViolation` — a path escaped the workspace.

Never let a tool crash a run: `ToolRegistry.call` converts every exception into an `ERROR: …` string that goes back to the model. Preserve that contract.

**Error messages are prompts.** A tool's error text is consumed by an LLM that will try again. Say what was wrong *and* what to do instead ("old_text appears 3 times; include more surrounding context, or pass count=-1"). Don't just say "invalid input".

## Security rules — non-negotiable

1. **Every filesystem path goes through `resolve_in_workspace()`.** No exceptions. If you add a tool that touches a path, it calls that function before doing anything else.
2. **Never widen the sandbox** to make a feature work. If a feature seems to need it, that is a design discussion, not a patch.
3. **New dangerous capabilities are opt-in**, gated behind a `Settings` flag and marked `dangerous=True` on the `Tool`, exactly like `run_command`.
4. **Never print, log or persist an API key.** Use `Settings.redacted()` for any output that includes configuration.
5. **Don't add a hard dependency lightly.** Runtime deps are `httpx` and `rich`, and that is close to the ceiling. Every new one is a supply-chain risk you are asking every user to accept.
6. **A destructive tool call must be reversible.** If you add a tool that modifies files, make sure `paths_for_tool()` in `checkpoint.py` knows which paths it touches, so `undo` keeps working. A tool whose effects cannot be snapshotted (like `run_command`) must return `[]` rather than a wrong guess.
7. **Never disable a security control to make a test pass.** Fix the test, or fix the design.

Changes to `tools/sandbox.py` require accompanying tests covering traversal, absolute paths and symlink escapes. Changes to `tools/shell.py` require tests for each blocklist pattern you add, including a case-and-spacing variant.

### Handling a vulnerability report

Fixes go to `main` first, then get backported to **every** affected minor — the
project supports all released versions (see `SECURITY.md`). Add a regression test
that fails before the fix, and never describe the vulnerability in a commit message
before the advisory is public.

## Adding a tool

1. Implement the function in the right `tools/` module, taking `workspace: Path` first if it touches files.
2. Add a `Tool(...)` descriptor in that module's `build_*_tools()` factory.
3. Write the description **for the model**: when to use it, not just what it does. Give every parameter a `description`, and state defaults in the text.
4. Register it in `build_default_registry()` if it should be on by default.
5. Test the happy path, each failure mode, and the sandbox boundary if applicable.

`tests/test_tools_base.py` asserts that every default tool has a non-empty description and that every parameter is documented — that test will fail if you skip step 3.

## Adding a setting

Add it to `Settings`, to `ALLOWED_KEYS` in `settings_store.py` (with its type), to the
`from_env` chain using the `pick*` helpers, and to `redacted()` if it is worth showing.
`tests/test_settings_store.py` asserts every allowed key exists on `Settings`, so a
mismatch fails the suite. Never add a secret to `ALLOWED_KEYS`.

If only some values are usable, say so in `validate_value()` — add the key to `CHOICES`,
to `POSITIVE_KEYS`, or give it its own check. A settings file is read at every startup,
so an unusable value written there breaks every later command, including the ones needed
to undo it.

## Skills and schedules

Skills are **prompt text, never code** — loading one must never execute anything. Keep
skill bodies out of the system prompt: only descriptions go in the catalogue, and the
body arrives through `load_skill`. `tests/test_skills.py` asserts this.

Scheduled runs are non-interactive. They must always force `Mode.AUTO`, because there is
no human to answer an approval prompt, and they must record failures on the task rather
than raising out of the loop.

## Adding a provider

Most providers speak the OpenAI chat-completions shape: for those, just add the entries
listed above and point `PROVIDERS` at `OpenAIProvider` — no new class needed. Only a
genuinely different wire format justifies one.

For that case: subclass `LLMProvider` in `src/jaigent/llm/`, implement `complete`, `format_assistant_message` and `format_tool_result`, register it in `PROVIDERS`, add its defaults to `DEFAULT_MODELS` / `DEFAULT_BASE_URLS` / `API_KEY_ENV_VARS` in `config.py`, and add it to `KNOWN_PROVIDERS`. Test it with mocked HTTP following the pattern in `tests/test_llm.py`; map at least 401/404/429 to actionable messages.

## Testing expectations

- One test module per source module, mirroring the layout.
- Never call a real network or a real API. Mock `httpx` (see `_patch_client` in `tests/test_tools_web.py`) or use the `FakeProvider` in `tests/conftest.py`.
- Use the `workspace` and `settings` fixtures instead of building `tmp_path` layouts by hand; use `clean_env` whenever a test reads configuration.
- Test names describe behaviour: `test_symlink_pointing_outside_is_rejected`, not `test_sandbox_2`.
- New code comes with tests. Coverage is ~89%; don't lower it.
- A bug fix starts with a test that reproduces the bug and fails. If you cannot write one, you do not yet understand the bug.
- Prefer many small, specific tests over one that asserts ten things. When it fails, the name should tell you what broke.
- Watch for a test that passes for the wrong reason. A failover test whose fallback chain is not pinned will quietly reach the real network; pin it.

## Documentation

If you change behaviour a user can observe, update the docs in the same change:

- new/changed CLI flag or command → README "Usage" and "Configuration"
- new model pricing → `DEFAULT_PRICES` in `pricing.py`
- new provider → `KNOWN_PROVIDERS`, `DEFAULT_MODELS`, `DEFAULT_BASE_URLS`,
  `API_KEY_ENV_VARS`, `PROVIDERS`, and the catalogue in `models.py`
- new persistable setting → `ALLOWED_KEYS` in `settings_store.py`
- new model → `models.py`, `pricing.py`, and `PREFERENCES` in `router.py`
- new tool → README "Tools" table
- new setting → README "Configuration" table **and** `.env.example`
- new slash command → `CHAT_COMMANDS` in `cli.py` **and** the README chat table
- new tool that writes files → `paths_for_tool()` in `checkpoint.py`
- anything notable → `CHANGELOG.md` under "Unreleased"
- a release → bump `pyproject.toml` *and* `jaigent.__version__` together, and give the
  version a changelog entry; `tests/test_packaging.py` asserts all three agree, and the
  release workflow refuses to publish a tag that disagrees with the source

Docs are written in English. Keep the README's tone: short sentences, real commands, no
marketing. The README stays the front door; when a topic outgrows it — a walkthrough, a
reference, a proposal — it moves to `docs/` as its own file, one topic per file, and the
README keeps a link. `docs/web-ui-proposal.md` shows the pattern for proposals: status
line up top, built nothing until the issue discussion happens.

## Releasing

1. Update `CHANGELOG.md`, `version` in `pyproject.toml` and `__version__` in `src/jaigent/__init__.py` — they must agree.
2. Add the new version to the table in `SECURITY.md`. Every version stays supported; do not mark one end-of-life.
3. Tag `vX.Y.Z` and push it. `.github/workflows/release.yml` builds the binaries for all five platform targets, verifies each one runs, publishes checksums and creates the release. The details — including PyPI authentication and republishing — are in `docs/ci-and-releases.md`.
4. Never hand-edit a published checksum, and never re-tag a released version.
5. The release smoke test must render the logo. Freezers miss `rich`'s unicode tables,
   which are resolved by name at runtime, and the failure only shows on a wide glyph.

## Git

Work on the branch you were given; never force-push a shared branch. Use [Conventional Commits](https://www.conventionalcommits.org/) — `feat:`, `fix:`, `docs:`, `test:`, `refactor:`, `chore:` — with a subject in the imperative mood under ~72 characters. Keep a commit to one logical change.

## Things not to do

- Don't commit secrets, `.env` files, or recorded API responses containing keys.
- Don't add telemetry, analytics, or any phone-home behaviour. Ever.
- Don't bundle a default API key or route requests through a proxy — users talk to their provider directly.
- Don't reformat files you didn't otherwise change; it buries the real diff.
- Don't add a web UI or an async rewrite without discussing it in an issue first. Small and readable is the point.
- Plugins are local Python in `.jaigent/plugins` only. Never fetch or execute plugin code from the network.
- Don't leave `print()` debugging in the source; the CLI renders through `rich`, and traces go to stderr behind `--verbose`.
