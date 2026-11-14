# Configuration

vigent reads one file: `~/.config/vigent/config.toml` (or `$XDG_CONFIG_HOME/vigent/config.toml`). Everything in it is optional. Without the file, vigent uses Neovim's default look and the keys listed under [Built-in keys](#built-in-keys).

```bash
vigent config init     # write a commented starter file
vigent config check    # validate it: bad keys, unknown actions, missing themes
```

`vigent add <name>` adds a template, keymap or engine from the [registry](registry.md) to this file, beside what's there, after showing it to you.

A mistake in the file never stops vigent from starting. It shows as a warning on the command line, and `vigent config check` lists every problem, with a suggestion when a name looks like a typo.

## A complete example

```toml
# ~/.config/vigent/config.toml

theme = "tokyonight"            # built-in, imported (vigent theme import), or your own
model = "claude-sonnet-4-5"     # model for new agents
leader = "<Space>"              # what <leader> means below (vim's default is "\")

[ui]
sidebar = true
sidebar_width = 32
sidebar_position = "left"       # or "right"
number = true                   # session numbers in the sidebar
tilde = true                    # ~ on empty sidebar rows
icons = "unicode"               # or "ascii"
timeoutlen = 500                # ms to wait for the rest of a multi-key mapping

[highlights]                    # on top of whichever theme is active
Normal = { bg = "NONE" }        # transparent background
Comment = "gui=NONE"            # no italic comments
CursorLine = "guibg=#2a2f3a"

[worktree]
enabled = true
dir = "../{repo}-worktrees"
branch = "{type}/{name}"        # "fix flaky test" -> fix/flaky-test

[keys.normal]
"<leader>n" = ":new "           # opens ":new " so you can type a name
"<leader>x" = ":kill<CR>"
"<leader>t" = "theme.picker"
"<leader>h" = "app.help"
"<leader>d" = ":colorscheme default<CR>"
"<Tab>" = "session.next"
"<S-Tab>" = "session.prev"
"J" = "scroll.half_down"
"K" = "scroll.half_up"
"<C-j>" = ["fold.open_all", "scroll.bottom"]
"H" = "gg"                      # H does what gg does
"q" = false                     # unbind a built-in key

[keys.insert]
"jk" = "<Esc>"
"<C-s>" = "edit.submit"

[keys.command]
"<C-k>" = "edit.clear"
```

## `:settings`: change it all without editing this file

`:settings` (or `<Space>s`) opens every option in one float, and changes apply immediately:

| Section | What you can change |
|---|---|
| Look | theme (Enter opens the picker), transparent background, icons, 24-bit color |
| Layout | sidebar, its width and side, session numbers, `~` rows |
| Agents | the engine for new agents, a worktree per agent, worktree storage (riftri or git) |
| Keys | the leader, and every NORMAL-mode key: Enter, type the new keys, Enter again |

Move with `j`/`k`, change with `Enter`/`Space` (or step with `h`/`l`), and press `w` to write the changes to this file. Saving changes only those values: a setting you had commented out is replaced in place, and your comments and other settings stay. A key you move is saved as the new mapping plus `false` for the old key.

## Top-level settings

| Key | Default | Meaning |
|---|---|---|
| `theme` | `"default"` | Colorscheme at startup. `colorscheme` is accepted as an alias. See [themes.md](themes.md). |
| `model` | pi's own default | Model for new pi agents, as `provider/model` (anything `pi --model` takes). `--model` on the command line wins. |
| `engine` | `"auto"` | What runs new agents: `"pi"`, `"claude"`, `"codex"`, `"opencode"`, [one of your own](#your-own-engines), or `"auto"` (the first signed-in CLI, else pi if it has an API key; with neither, starting an agent says how to connect one). `--engine` on the command line wins; `:new <task> --engine <id>` picks one per agent. See [`[engines]`](#engines). |
| `leader` | `"<Space>"` | The key `<leader>` stands for in `[keys]`, like vim's `mapleader` (vim's own default is `"\"`). `mapleader` is accepted as an alias. |

## `[ui]`

Each option can also be changed while vigent runs, with vim's `:set` syntax: `:set nonumber`, `:set number!`, `:set sidebar_width=40`, `:set tm=300`. `:set` alone lists them all.

| Option | Default | Meaning |
|---|---|---|
| `sidebar` | `true` | show the session sidebar (hidden anyway on narrow terminals) |
| `sidebar_width` | `30` | sidebar width in columns, 16–80 |
| `sidebar_position` | `"left"` | `"right"` puts the sidebar on the right; the window keys follow it (`<C-l>` goes to it, `<C-h>` back). Alias `sbp` |
| `number` | `true` | session numbers in the sidebar (they match the `<leader>1`–`9` keys) |
| `tilde` | `true` | `~` on empty sidebar rows |
| `icons` | `"unicode"` | `"ascii"` swaps every glyph for plain ASCII |
| `timeoutlen` | `1000` | ms to wait for the next key of a mapping (vim's `'timeoutlen'`, alias `tm`) |
| `termguicolors` | `true` (`false` in macOS Terminal.app) | 24-bit color, as in vim. Turn it off on terminals without it, and every color is mapped to the nearest of the 256 standard ones (alias `tgc`) |
| `notify` | `"auto"` | when an agent finishes, fails or needs you while you're looking at another one (or another window): `"auto"` rings the bell and, in terminals that show one (iTerm2, WezTerm, Ghostty, kitty; also inside tmux), sends a desktop notification. `"bell"`, `"desktop"` or `"off"` choose. The agent gets a mark in the sidebar until you open it |
| `whichkey` | `true` | after `<leader>` (or any key that starts mappings), pause and a panel lists what each next key does, like which-key.nvim. `Esc` closes it (alias `wk`) |
| `transparent` | `"auto"` | draw on the terminal's own background, so its blur, opacity or wallpaper shows through. `"auto"` does what the theme says (`lazyvim` is transparent); `true` or `false` forces it for every theme. Live: `:set transparent`, `:set notransparent`, `:set transparent!`, and `:set transparent&` back to `"auto"` |

## `[statusline]` and `[winbar]`

What the statusline (the bottom bar) and the winbar (the line over the transcript) show, in order, like lualine's sections. Each takes a `left` and a `right` list; leave one out to keep its default.

```toml
[statusline]                         # the defaults
left = ["mode", "agent", "branch"]
right = ["model", "usage", "agents"]

[winbar]
left = ["agent", "model", "status"]
right = []
```

| Part | Shows | In |
|---|---|---|
| `mode` | the mode badge (`NORMAL`, `INSERT`…) | statusline |
| `agent` | the focused agent's name | both |
| `branch` | its worktree branch (on the statusline with `+added -removed`) | both |
| `engine` | its engine, like `Claude Code` | both |
| `model` | its model (on the winbar with the engine and effort, like `Claude Code · sonnet · high`) | both |
| `effort` | its reasoning effort | both |
| `usage` | tokens and cost, like `74.8k tok · $0.50` | both |
| `agents` | running / all agents, with a spinner while any run | statusline |
| `path` | where it works: its worktree, or `this checkout` | both |
| `clock` | the time, `HH:MM` | statusline |
| `status` | `paused`, `setting up`, queued prompts, pi extension status | winbar |

A part with nothing to show (no effort set, no worktree) is left out. On the winbar, the right side gives way first when the line is too narrow.

## `[style]`

How vigent is laid out, over the theme's own style: the sidebar (`tree`, `cards`, `compact`), messages (`plain`, `labeled`, `bubbles`), a lualine-style statusline (`separators = "round"`, with `icons = "nerd"`), tool-call icons and any glyph. See [Styles in themes.md](themes.md#styles-layout-and-icons).

```toml
[style]
sidebar = "compact"
messages = "labeled"
tool_icons = "unicode"
[style.icons]
prompt = "λ "
```

## `[highlights]`

Overrides for any highlight group, applied on top of whichever theme is active, including after `:colorscheme`. A value can be a table, a vim `:hi` string, or the name of a group to link to:

```toml
[highlights]
Normal = { fg = "#c0caf5", bg = "NONE", bold = false }
Comment = "guifg=#565f89 gui=italic"
VigentSidebar = "NormalFloat"
```

The full list of groups, and how to write whole themes, is in [themes.md](themes.md).

## `[worktree]`

Each agent works in its own git worktree, on its own branch, so agents never touch your checkout or each other's files. `:new fix flaky checkout test` creates the branch `fix/flaky-checkout-test` from the branch you have checked out, in `../<repo>-worktrees/fix-flaky-checkout-test`, and starts the agent there.

| Option | Default | Meaning |
|---|---|---|
| `enabled` | `true` | give each new agent a worktree (`:new!` skips it for one agent) |
| `dir` | `"../{repo}-worktrees"` | where worktrees go, relative to the repo root; `{repo}` is the repo's folder name. A folder inside the repo is added to `.git/info/exclude` so `git status` stays clean |
| `branch` | `"{type}/{name}"` | branch name pattern; must contain `{name}` |
| `base` | the checked-out branch | branch to start new worktrees from |
| `backend` | `"auto"` | how worktrees are made. `"auto"`: with [riftri](https://riftri.dev) when it's installed and can make copy-on-write worktrees here, else plain `git worktree`. `"riftri"`: always riftri (an error if it can't). `"git"`: never riftri |

**riftri** (installed with vigent, or found on your PATH, or set with `$RIFTRI_BINARY`; on a platform riftri has no binary for, worktrees are plain git ones) makes each agent's worktree a real git linked worktree whose unchanged files share copy-on-write storage with the others. It uses APFS clones, Btrfs/XFS reflinks, OverlayFS or ReFS block clones. With `"auto"`, vigent falls back to git only when riftri declines with a receipt saying nothing was changed. Any other riftri failure stops `:new` with riftri's message and its suggested command. `:checkhealth` shows whether riftri is ready for your worktrees folder, what's blocking it, and how much disk the worktrees use. riftri refuses to run while `GIT_CONFIG_PARAMETERS`, or a `GIT_CONFIG_COUNT` with anything beyond network settings (`credential.*`, `http.*`, `url.<base>.insteadOf`), is set, because those inject git config into its internal git commands. Hosted agent sandboxes, which set only network settings, work from riftri 0.6.7. `:checkhealth` reports the reason when riftri declines.

**Branch names** are built from the task you type:

| You type | Branch |
|---|---|
| `fix flaky checkout test` | `fix/flaky-checkout-test` |
| `auth-refactor` | `refactor/auth` |
| `docs: refresh README flags` | `docs/refresh-readme-flags` |
| `add dark mode` | `feat/add-dark-mode` |
| `release/v2 notes` | `release/v2-notes` (a name with `/` is used as written) |

A first or last word of `feat`, `fix` (also `bugfix`, `hotfix`, `bug`), `docs`, `refactor`, `test`, `chore`, `perf`, `ci`, `build` or `style` becomes the type. Otherwise the type is `feat`. Names are lowercase ASCII with hyphens, at most 48 characters. Reusing a name gives `-2`, `-3`, … instead of failing. Other patterns: `"agent/{name}"`, or `"yourname/{type}/{name}"`.

**Removing** always goes through git's safety checks. `git worktree remove` (or `riftri worktree remove` for riftri's worktrees, followed by `riftri gc` to free unused storage) refuses a worktree with uncommitted changes, and the branch is deleted only if it's merged. Otherwise it's kept, so finished work is never lost by accident:

```vim
:kill                       " stop the agent, keep its worktree and branch
:kill!                      " stop it and remove the worktree (refused if it has uncommitted changes)
:worktree remove <branch>   " remove a worktree no agent is using (:worktree remove! forces it)
:worktrees                  " list them; ● marks the ones an agent is working in
:diff                       " everything the focused agent changed, new files included (]c / [c between hunks)
:diff split                 " side by side (s switches layouts in the diff window)
:attach <branch>            " reopen an agent in a worktree that's kept (after :kill, or made elsewhere)
:merge                      " squash-merge the agent's branch into its base, in your checkout
:merge --no-squash          " a regular merge commit instead
:pr                         " push the branch and open a pull request
```

**Restarting:** vigent saves each agent's name, model and conversation inside git's own record of its worktree (`.git/worktrees/<name>/vigent/`). riftri worktrees are inspected first, and an OverlayFS view that lost its mount in a reboot is repaired before its agent reopens. When you start vigent again in the repo, every agent you didn't `:kill` comes back where it left off. `:kill` keeps the worktree but doesn't reopen it; `:attach <branch>` does. Removing the worktree removes the record too.

`:merge` and `:pr` first commit anything the agent left uncommitted, using a message built from the branch (`fix/flaky-checkout-test` → `fix: flaky checkout test`). `:merge` only runs when your checkout is on the base branch with no uncommitted changes, and a conflict is rolled back so your checkout is left as it was. A squash merge makes a new commit, so git doesn't count the branch as merged. vigent checks the content instead, so `:kill!` afterwards deletes the branch too. `:pr` uses `gh` when it's installed and signed in; otherwise it pushes and prints the GitHub compare URL.

From the shell: `vigent worktree list` (with each worktree's backend), `vigent worktree remove <branch> [--force]`, `vigent worktree prune`, `vigent worktree gc` (free riftri storage that no worktree uses).

## `[engines]`

Claude Code, Codex, OpenCode, Gemini CLI, Cursor CLI and pi run as installed, each with its own login; vigent never reads their credentials. `:checkhealth` (or `:engines`) shows which are installed and signed in, and the command to connect the rest. One table per CLI:

```toml
[engines.claude]
args = ["--permission-mode", "acceptEdits"]   # the default
model = "opus"                                # default: Claude Code's own
allow = ["Bash(gh:*)", "Bash(cargo:*)"]       # commands it may run without asking
ask = true                                    # off unless set: ask when it's refused a tool

[engines.codex]
args = ["-c", 'sandbox_mode="workspace-write"']  # the default
# model = "gpt-5"

[engines.opencode]
model = "anthropic/claude-sonnet-4-5"         # provider/model

[engines.gemini]
args = ["--approval-mode", "auto_edit"]       # the default (headless Gemini CLI can't ask)
model = "pro"                                 # or flash, flash-lite, a full model name

[engines.cursor]
args = ["--force"]                            # the default: edits and commands in its worktree
```

| Option | Meaning |
|---|---|
| `args` | Extra arguments for every run of that CLI. They **replace** the defaults above, so keep a permission or sandbox setting in them. vigent always adds its own JSON-output and resume flags, and the prompt last. |
| `model` | Model for new agents on that engine. Without it, the CLI uses its own default. `:new <task> --engine claude --model sonnet` overrides it for one agent. |
| `effort` | Reasoning effort for new agents on that engine: `low` to `max` for Claude Code, `minimal` to `xhigh` for Codex, `minimal` to `max` for OpenCode, `off` to `xhigh` for pi (its thinking level). Without it, the engine decides. |

| `allow` | Claude Code only. Permission rules every run may use, passed as `--allowedTools`: `"Bash(gh:*)"` allows `gh` with any arguments, `"WebFetch"` a whole tool. Same syntax as Claude Code's own `permissions.allow`. |
| `ask` | Claude Code only, **off unless you set it**. See below. |

`:permissions` changes these without editing the file: Claude Code's mode, `ask` and `allow`, Codex's sandbox and network, Gemini's approval mode and Cursor's `--force`, live, and saves each change here as you make it ([guide](guide.md#engines)).

### When Claude Code is refused a tool

vigent runs Claude Code with `-p`, where it can't stop and ask you. So a command its permission settings don't allow (say `gh pr view` or `cargo test` under `acceptEdits`) is refused, and the agent carries on without it. vigent shows what was refused in the transcript, along with the `allow` line that would permit it.

With `ask = true`, vigent asks you instead, in a picker that names the agent and what was blocked:

- **allow once:** runs the agent again (same conversation) with those rules, for that run only.
- **always allow:** the same, and adds the rules to `allow` in config.toml, so every Claude Code agent may use them from then on.
- **no** (or Esc): leaves it blocked.

The rule is the program for a command (`gh pr view 12` → `Bash(gh:*)`) or the tool's name for anything else. If an agent you aren't looking at asks, the bell rings.

It only asks when a rule would change something:

- It asks only about rules that aren't in `allow` yet. When everything refused is allowed already, Claude Code wanted approval for that command whatever the rules say, so vigent says that instead of asking again.
- In `bypassPermissions` it never asks: every rule already applies. What Claude Code still refuses there (it always asks before writing in `.git` or `.claude`, for one) is shown in the transcript.
- `AskUserQuestion` and `ExitPlanMode` wait for you to answer, which `-p` can't do. vigent shows the question, or says the plan is ready, and you answer with your next prompt. Codex doesn't need this, because it runs in a workspace-write sandbox. pi doesn't either: it has no permission gate unless an extension adds one (see [pi in the guide](guide.md#pi-extensions-skills-and-prompt-templates)).

`[engines.pi]` takes `model` (as `provider/model`, e.g. `openai/gpt-5`, or any pattern `pi --model` takes), `effort` (pi's thinking level) and `args`: extra arguments for `pi --mode rpc`, such as `["--no-extensions"]` or `["-e", "./my-extension.ts"]`. pi is your own install (`npm install -g @mariozechner/pi-coding-agent`); vigent keeps one `pi --mode rpc` running per agent and saves its conversation in the worktree.

### Your own engines

Any agent CLI that takes a prompt on its command line can be an engine. Give a table a `command` and it becomes one, listed in the sidebar, `:engine`, `:checkhealth`, `:model`, templates and `--engine` like the built-in ones (a table with a built-in's name and a `command` replaces that one):

```toml
engine = "aider"                   # new agents use it

[engines.aider]
name = "Aider"                     # how vigent shows it (default: the table's name)
command = ["aider", "--yes-always", "--message", "{prompt}"]
output = "text"                    # the default
model_args = ["--model", "{model}"]   # added when an agent has a model
models = ["sonnet", "gpt-5"]          # offered by :model

[engines.my-agent]                 # a wrapper that prints Claude Code's stream-json
command = ["my-agent", "--json"]
output = "claude"
resume_args = ["--resume", "{id}"]
```

| Option | Meaning |
|---|---|
| `command` | The program and its arguments, as a list. `{prompt}` is replaced by the prompt; without it, the prompt goes last. The program must be on your `PATH`. |
| `output` | How vigent reads what it prints. `"text"`: everything it prints is the reply. `"claude"`, `"codex"`, `"opencode"`, `"gemini"` or `"cursor"`: it prints the same JSON events as that CLI (`claude -p --output-format stream-json` and friends, or a wrapper around them), so vigent also shows its tool calls, tokens and cost. |
| `model_args` | Arguments added when the agent has a model, with `{model}` replaced by it. |
| `models` | Models `:model` offers for this engine, besides its own default. |
| `resume_args` | With a JSON `output`: arguments that continue the CLI's conversation, with `{id}` replaced by the id it reported (`["--resume", "{id}"]` for Claude Code's format). Follow-ups and a restarted vigent then pick the conversation up. |

Ready to copy (check each CLI's own help for the flags your version takes):

```toml
[engines.amp]                      # Amp: its --stream-json follows Claude Code's format
name = "Amp"
command = ["amp", "--execute", "{prompt}", "--stream-json"]
output = "claude"

[engines.copilot]                  # GitHub Copilot CLI, programmatic mode
name = "Copilot CLI"
command = ["copilot", "-p", "{prompt}", "--allow-all"]
model_args = ["--model", "{model}"]

[engines.goose]
name = "Goose"
command = ["goose", "run", "-t", "{prompt}"]

[engines.qwen]                     # Qwen Code
name = "Qwen Code"
command = ["qwen", "--yolo", "-p", "{prompt}"]
model_args = ["-m", "{model}"]
```

Each prompt runs the command once, in the agent's worktree, with your environment. Without `resume_args` each prompt starts a fresh conversation, unless the CLI keeps its own history. vigent can't tell whether a custom CLI is signed in, so it counts as ready when its program is on your `PATH`.

In a project's `.vigent.toml`, a `command` is a program to run, so it waits for `:trust` like hooks do.

### Choosing a model and effort while vigent runs

`:model` (`<Space>M`) opens one plain list: each model's name and version, like `Claude Fable 5.1` or `GPT-5.5 Codex`, with its id next to it. It lists the models of every engine that's ready (`:checkhealth`), the focused agent's own first:
- Claude Code's: Claude Fable 5.1, Opus 5.5, Sonnet 5.5 and Haiku 5.5.
- Codex's own catalog, from `codex debug models` (the GPT models your account has).
- everything `opencode models` lists.
- pi's: what `pi --list-models` lists (the providers you have a key or login for, and your `models.json`).

An open agent keeps its engine, because its conversation lives there. So a model from another engine is used by new agents instead, and `:new <task>` starts one. `:model codex:gpt-5.5` does this without the picker.

The one exception is a pi agent when pi is no longer installed: at the next start it moves to your default engine. It starts a new conversation in the same worktree, and the pi one stays on disk.

Press `/` to filter by name or id. Enter on text that matches nothing uses the typed name as-is.

`:effort` (`<Space>R`) picks the reasoning effort the same way.

Both apply from the agent's next prompt, show in the winbar (`claude-fable-5 · high`), and are saved with the agent, so they survive a restart. With no agent open, they set the model and effort for new agents. Those are also in `:settings`. `:model <name>` and `:effort <level>` skip the picker.

`claude -p` can't stop and ask before a tool runs, so with the default `acceptEdits` Claude Code may edit files in the worktree, and other tools follow the permission rules in your Claude Code settings. Use `"--permission-mode", "bypassPermissions"` only where the agent is sandboxed.

## `[templates]`

A template is a prompt you start agents with often. `:new -t <name> <task>` starts an agent on the template's engine, model and effort, and sends it the prompt with `{task}` replaced by your task. A prompt without `{task}` gets the task added after it. `:templates` (`Space T`, or `T` on the start screen) opens a picker. Pick a template there and type the task on the command line.

```toml
[templates.migrate]
description = "a database migration, with a rollback"   # shown in the picker
prompt = "Write a migration that {task}. Include the rollback, and test both."
engine = "claude"     # optional: pi, claude, codex, opencode (default: the usual engine)
model = "opus"        # optional
effort = "high"       # optional; checked against the engine's levels
worktree = true       # optional; false runs it in your checkout
```

Four are built in. A template of yours with the same name replaces it.

| Template | What the agent is told |
|---|---|
| `fix` | find and fix the bug: reproduce it with a failing test first, make the smallest change, run the suite |
| `test` | write tests in the project's style, run them, and report bugs instead of changing the code |
| `review` | review this branch's work for bugs, missing tests and unclear code, without changing files; the task (optional) is what to focus on |
| `explain` | explain how something works and where it lives, without changing files |

What you type wins: `:new -t migrate --engine codex <task>` runs on Codex, without the template's model and effort.

## `[commands]`

Your own ex commands, like vim's `:command`. Each runs ex commands, shell commands, or a list of them:

```toml
[commands]
Review = "new -t review {args}"     # :Review the cart → :new -t review the cart
Test = "!npm test {args}"           # a shell command in the agent's worktree
Land = ["!npm test", "pr"]          # one after another
```

- Names start with a capital letter, as in vim, so a command of yours never hides a built-in one.
- `{args}` (or vim's `<args>`) is whatever you type after the name.
- An ex command is anything you'd type after `:`; the leading `:` is optional.
- A step that starts with `!` runs in a shell, in the focused agent's worktree (with no agent, in the repository). Like hooks, it sees `VIGENT_AGENT`, `VIGENT_BRANCH`, `VIGENT_WORKTREE`, `VIGENT_REPO` and `VIGENT_ENGINE`. What it prints goes into the agent's transcript, and its last line shows on the command line. A shell step that fails stops the steps after it, so `Land` opens a pull request only when the tests pass.
- Map a key to one like any ex command: `"<leader>T" = ":Test<CR>"` under `[keys.normal]`.

While vigent runs:

- `:command` lists your commands.
- `:command Name` shows one.
- `:command Name {cmd}` defines one for this run. Steps are separated by `|`; from the first shell step on, the rest of the line belongs to the shell, so pipes work. `:command!` replaces an existing one.
- `:delcommand Name` forgets one.
- `:!{cmd}` runs a shell command once, the same way.

In a project's `.vigent.toml`, a command with a shell step waits for `:trust`. Commands made only of ex commands don't.

## A project's own config: `.vigent.toml`

A `.vigent.toml` at the root of a repository is read on top of your `~/.config/vigent/config.toml`, so a team can commit its theme, templates, engine, worktree layout, keys and hooks once. Where both set something, the project wins; tables merge key by key (setting `model` under `[engines.claude]` keeps your `effort`).

The parts that run programs only count once you trust the file: `[hooks]`, `args` under `[engines.*]`, the `command` of [your own engines](#your-own-engines), [commands](#commands) with a shell step, and Claude Code's `allow` rules. Until then vigent says what's waiting (`.vigent.toml wants to run commands (hooks.worktree_created): :trust allows them`) and uses the rest. Trust it with **`:trust`** in vigent or **`vigent trust`** in the project. Trust is for the file as it is: when it changes, vigent asks again. Your own config.toml is always trusted.

## `[hooks]`

Shell commands vigent runs at points in an agent's life, in the agent's worktree:

```toml
[hooks]
worktree_created = "npm ci"     # in each new worktree; the agent's first prompt waits for it
before_merge = "npm test"       # before :merge and :pr; if it fails, nothing is merged or pushed
agent_finished = "say done"     # whenever an agent stops: finished, failed or needs you
```

| Hook | When | If it fails |
|---|---|---|
| `worktree_created` | right after a new agent's worktree is made; prompts wait in its queue (the winbar says "setting up") | the output goes in the transcript and the agent starts anyway |
| `before_merge` | before `:merge` and `:pr` | nothing is merged or pushed; the output goes in the transcript |
| `agent_finished` | when an agent stops running | a warning in the message line |

Each hook sees `VIGENT_HOOK`, `VIGENT_AGENT`, `VIGENT_BRANCH`, `VIGENT_WORKTREE`, `VIGENT_REPO` and `VIGENT_ENGINE`, and `agent_finished` also gets `VIGENT_STATE` (`finished`, `failed` or `needs-you`). `worktree_created` and `before_merge` may run for 15 minutes, `agent_finished` for one.

## `[keys]`

One table per mode: `[keys.normal]`, `[keys.insert]`, `[keys.visual]` and `[keys.command]` (the `:`, `/` and `?` command line). Entries placed directly under `[keys]` count as normal mode.

Each entry maps a key sequence (left) to what it does (right). Your mappings replace built-in ones with the same keys and leave every other built-in key alone.

### Writing keys

Keys use vim's notation, so mappings can be copied from a vimrc:

| Write | Key |
|---|---|
| `j`, `G`, `]s`, `gg` | the characters themselves; sequences are typed in order |
| `<C-d>` | Ctrl-d (case doesn't matter: `<c-D>` is the same) |
| `<M-x>` or `<A-x>` | Alt-x |
| `<S-Tab>`, `<C-S-p>` | with Shift (`<S-a>` is just `A`) |
| `<CR>` `<Esc>` `<Tab>` `<BS>` `<Space>` `<Del>` | Enter, Escape, Tab, Backspace, Space, Delete |
| `<Up>` `<Down>` `<Left>` `<Right>` `<Home>` `<End>` `<PageUp>` `<PageDown>` | movement keys |
| `<F1>` … `<F12>` | function keys |
| `<leader>` | the `leader` setting |
| `<lt>`, `<Bar>`, `<Bslash>` | `<`, `\|`, `\` |

### What a key can do

| Right-hand side | Example | Effect |
|---|---|---|
| an action | `"session.next"`, `"session.goto 3"` | runs a built-in action (list below) |
| an ex command ending in `<CR>` | `":colorscheme nord<CR>"` | runs the command |
| an ex command without `<CR>` | `":new "` | opens the command line with that text, so you can finish typing |
| `<Cmd>…<CR>` | `"<Cmd>kill<CR>"` | runs the command (Neovim style) |
| other keys | `"gg"`, `"<Esc>"`, `"ihello"` | presses those keys with their **built-in** meaning |
| a list | `["fold.open_all", "G"]` | each in order |
| `false` or `"<Nop>"` | `q = false` | the key does nothing |

When the right-hand side is other keys, they always get their built-in meaning, the way vim's `noremap` works. That makes swaps like `j = "k"` and `k = "j"` safe: neither one loops back to your own mappings.

### Multi-key mappings and `timeoutlen`

When a key could start a longer mapping, vigent waits `timeoutlen` ms for the next one, exactly as vim does. What you've typed so far shows near the bottom right, like vim's `showcmd`.
- `jk` in insert mode: typing `j` waits briefly. `k` finishes the mapping. Any other key, or the timeout, types the `j` normally.
- If you map both `g` and the built-in `gg` exists, `gg` still works. A lone `g` fires after the timeout, or as soon as you press a key that isn't `g`.

Pasted text always goes in as text, never as keys, so pasting `jk` into a prompt doesn't leave insert mode.

### Changing keys while vigent runs

The same mappings work as commands, with vim's names:

```vim
:nmap <leader>t theme.picker        " normal mode (also :map, :noremap, :nnoremap)
:imap jk <Esc>                       " insert mode (also :inoremap)
:xmap Y visual.yank                  " VISUAL mode (also :vmap, :xnoremap)
:cmap <C-k> edit.clear               " command line (also :cnoremap)
:nunmap q                            " remove a mapping (:unmap, :iunmap, :cunmap)
:nmap J                              " show what J does
:map                                 " list your mappings
:let mapleader = ","                 " change the leader for mappings made after this
:help                                " every active key, yours marked with *
```

Like vim, every mapping is non-recursive, so `:nmap` behaves like `:nnoremap`. Changes made with these commands last until you quit. Put them in `config.toml` to keep them.

### Actions

| Action | Does |
|---|---|
| `mode.normal` | back to NORMAL mode |
| `mode.insert` | write a prompt to the focused agent (INSERT); the cursor is where you left it |
| `mode.insert_start`, `mode.append_end` | write the prompt from its start / its end (`I` / `A`) |
| `mode.command` | open the `:` command line |
| `mode.search` | search the transcript |
| `mode.search_back` | search the transcript backward (`n` then goes up) |
| `mode.visual` | select transcript lines (VISUAL LINE mode) |
| `cursor.down`, `cursor.up` | move the VISUAL cursor one line |
| `cursor.half_down`, `cursor.half_up` | move the VISUAL cursor half a page |
| `cursor.top`, `cursor.bottom` | move the VISUAL cursor to the top / bottom |
| `visual.yank` | copy the selected lines to the clipboard |
| `visual.inner_block` | select the code block under the VISUAL cursor |
| `visual.swap` | jump to the other end of the selection |
| `visual.reselect` | select the last VISUAL selection again (`gv`) |
| `view.center`, `view.top`, `view.bottom` | put the VISUAL cursor's line, or the search match, in the middle / at the top / at the bottom of the window (`zz` / `zt` / `zb`) |
| `jump.back`, `jump.forward` | back to where you were before a jump, and forward again (`<C-o>` / `<Tab>`). `G`, `gg`, `{N}G`, `n`, `N`, `{`, `}`, a search and a mark are jumps |
| `app.position` | the agent's name, how long its transcript is and how far down you are (`<C-g>`) |
| `message.next`, `message.prev` | jump to the next / previous message |
| `yank.reply` | copy the agent's last reply |
| `yank.block` | copy the code block nearest the bottom of the screen |
| `scroll.down`, `scroll.up` | scroll one line |
| `scroll.half_down`, `scroll.half_up` | scroll half a page |
| `scroll.page_down`, `scroll.page_up` | scroll a page |
| `scroll.top`, `scroll.bottom` | jump to the top / bottom of the transcript |
| `session.next`, `session.prev` | next / previous session |
| `session.tab` | next session, or session N with a count (`3gt`) |
| `session.alternate` | the session you were on before |
| `session.goto N` | session N, e.g. `"session.goto 3"` |
| `session.new` | spawn a new agent |
| `session.kill` | kill the focused agent, after asking (`:kill` doesn't ask) |
| `session.abort` | stop the focused agent's current run |
| `session.pause` | stop the run and hold queued prompts (`:pause`) |
| `session.resume` | continue a paused agent (`:resume`) |
| `session.tree` | the conversation tree: go back to an earlier point and branch (`:tree`) |
| `fold.toggle` | fold / unfold tool output |
| `fold.open_all`, `fold.close_all` | unfold / fold all tool output |
| `search.next`, `search.prev` | next / previous match |
| `search.clear` | clear search highlighting |
| `edit.submit` | send the prompt, or run the command line |
| `edit.backspace` | delete the character before the cursor |
| `edit.delete_word` | delete the word before the cursor |
| `edit.clear` | delete everything before the cursor (all of it when the cursor is at the end) |
| `edit.delete` | delete the character under the cursor |
| `edit.left`, `edit.right` | move the cursor one character |
| `edit.word_left`, `edit.word_right` | move the cursor one word |
| `edit.home`, `edit.end` | move the cursor to the start / end of the line |
| `edit.history_prev`, `edit.history_next` | the older / newer line from history that starts with what's typed. In INSERT that's the agent's own earlier prompts; on the command line, the commands or searches you ran since vigent started |
| `edit.paste` | put in what the line's NORMAL mode last deleted or yanked |
| `edit.normal` | edit the line in NORMAL mode (see below) |
| `edit.complete`, `edit.complete_prev` | complete a command, an agent (`:b`, `:vsplit`) or a theme (`:colorscheme`) and go through what fits, shown over the statusline; past the last one is what you typed |
| `theme.picker` | pick a colorscheme (live preview) |
| `app.help` | show every key |
| `app.dashboard` | all agents at a glance (`:dash`) |
| `app.redraw` | redraw the screen |
| `window.left` | the window to the left (like `<C-w>h`): the sessions sidebar, or the transcript when the sidebar is on the right |
| `window.right` | the window to the right (like `<C-w>l`): back to the transcript, or the sidebar when it's on the right; with nowhere to go, redraw the screen |
| `window.down` / `window.up` | the window below / above |
| `window.vsplit` / `window.split` | split the window side by side / one above the other |
| `window.close` / `window.quit` / `window.only` | close this window / close it or quit if it's the last / close the others |
| `window.next` / `window.prev` / `window.last` | next window (the sidebar counts as one) / previous / the one you were in last |
| `window.top` / `window.bottom` | the first / last window |
| `window.equal` | make all windows the same size |
| `window.wider` / `window.narrower` / `window.taller` / `window.shorter` | resize by one column or row |
| `window.max_width` / `window.max_height` | as wide / as tall as it can be |
| `window.exchange` / `window.rotate` | swap what two windows show / swap the two halves of a split |
| `cursor.page_down` / `cursor.page_up` | move the VISUAL cursor by a page |
| `cursor.screen_top` / `cursor.screen_middle` / `cursor.screen_bottom` | move the VISUAL cursor within the window |
| `app.quit` | quit vigent; refuses while agents are running, like vim's `:q` |
| `app.quit_force` | quit even with agents running (`:q!`) |
| `app.quit_hint` | explain how to quit |
| `noop` | do nothing |

### Built-in keys

**Normal mode**

| Keys | Action |
|---|---|
| `i` `a` `o` | `mode.insert` |
| `:` | `mode.command` |
| `/` / `?` | `mode.search` / `mode.search_back` |
| `v` `V` | `mode.visual` |
| `j` `<Down>` / `k` `<Up>` | `scroll.down` / `scroll.up` |
| `<C-d>` / `<C-u>` | `scroll.half_down` / `scroll.half_up` |
| `<C-f>` `<PageDown>` / `<C-b>` `<PageUp>` | `scroll.page_down` / `scroll.page_up` |
| `gg` / `G` | `scroll.top` / `scroll.bottom` |
| `]s` / `[s` | `session.next` / `session.prev` |
| `<C-^>` | `session.alternate` |
| `<leader>1` `<leader>2` `<leader>3` `<leader>4` `<leader>5` `<leader>6` `<leader>7` `<leader>8` `<leader>9` | `session.goto 1` … `session.goto 9` |
| `za` / `zR` / `zM` | `fold.toggle` / `fold.open_all` / `fold.close_all` |
| `n` / `N` | `search.next` / `search.prev` |
| `{` / `}` | `message.prev` / `message.next` |
| `yy` / `yib` | `yank.reply` / `yank.block` |
| `dd` | `session.kill` (asks first) |
| `<Esc>` | `search.clear` (also `:noh`) |
| `<C-c>` | `session.abort` |
| `<C-l>` | `window.right` (from the sidebar back to the transcript; in the transcript, redraw. With `sidebar_position = "right"`, the two swap) |
| `<C-h>` `<BS>` | `window.left` (most terminals send `<C-h>` as Backspace) |
| `<C-w>h` `<C-w><C-h>` | `window.left` |
| `<C-w>l` `<C-w><C-l>` | `window.right` |
| `<C-w>j` `<C-w><C-j>` `<C-j>` | `window.down` |
| `<C-w>k` `<C-w><C-k>` `<C-k>` | `window.up` |
| `<C-w>w` `<C-w><C-w>` | `window.next` (with one window, toggles the sidebar) |
| `<C-w>W` | `window.prev` |
| `<C-w>p` `<C-w><C-p>` | `window.last` |
| `<C-w>t` / `<C-w>b` | `window.top` / `window.bottom` |
| `<C-w>v` `<C-w><C-v>` | `window.vsplit` |
| `<C-w>s` `<C-w>S` `<C-w><C-s>` `<leader>-` | `window.split` |
| `<C-w>c` | `window.close` |
| `<C-w>q` `<C-w><C-q>` | `window.quit` |
| `<C-w>o` `<C-w><C-o>` | `window.only` |
| `<C-w>=` | `window.equal` |
| `<C-w>>` / `<C-w><lt>` | `window.wider` / `window.narrower` |
| `<C-w>+` / `<C-w>-` | `window.taller` / `window.shorter` |
| `<C-w>_` | `window.max_height` |
| `<C-w>x` `<C-w><C-x>` | `window.exchange` |
| `<C-w>r` `<C-w><C-r>` | `window.rotate` |
| `<C-e>` `<C-n>` / `<C-y>` `<C-p>` | `scroll.down` / `scroll.up` |
| `gt` / `gT` | `session.tab` / `session.prev` |
| `zr` / `zm` | `fold.open_all` / `fold.close_all` |
| `I` / `A` | `mode.insert_start` / `mode.append_end` |
| `zz` / `zt` / `zb` | `view.center` / `view.top` / `view.bottom` (the current search match) |
| `gv` | `visual.reselect` |
| `<C-o>` / `<Tab>` | `jump.back` / `jump.forward` (`<Tab>` is what terminals send for `<C-i>`) |
| `<C-g>` | `app.position` |
| `ZZ` / `ZQ` | `app.quit` / `app.quit_force` |
| `q` | `app.quit_hint` |
| `<leader>n` | `:new ` (type the task) |
| `<leader>d` | `:diff` |
| `<leader>m` | `:merge` |
| `<leader>p` | `:pr` |
| `<leader>q` | `:queue ` (type a follow-up) |
| `<leader>t` | `theme.picker` |
| `<leader>D` | `:dash` |
| `<leader>u` | `session.tree` (like an undo tree, for the conversation) |
| `<leader>s` | `:settings<CR>` (theme, look, engine, worktrees and keys in one float) |
| `<leader>r` | `:review<CR>` (keep or drop the agent's changes hunk by hunk) |
| `<leader>T` | `:templates<CR>` (start an agent from a template) |
| `<leader>M` | `:model<CR>` (pick the focused agent's model) |
| `<leader>e` | `sidebar.focus` (move the cursor into the sessions sidebar: `j`/`k` pick an agent, `a` new agent, `dd` kill it, Enter or Esc go back) |
| `<leader>R` | `:effort<CR>` (pick its reasoning effort) |
| `<leader>E` | `:engine<CR>` (pick the engine new agents run on) |

Also: `<C-w>|` is `window.max_width`, and `<leader>|` is `window.vsplit` (`<leader>-` is `window.split`).

Marks work like vim's, per agent: `m{a-z}` marks the line at the top of the window (in VISUAL, the cursor's line), `'{a-z}` or `` `{a-z} `` goes back to it, and `''` goes back to where you were before the last jump. `:marks` and `:jumps` list them. A mapping of your own on `m`, `'` or `` ` `` wins.

**VISUAL mode** (`v` or `V`: whole lines, like vim's `V`)

| Keys | Action |
|---|---|
| `j` `<Down>` / `k` `<Up>` | `cursor.down` / `cursor.up` |
| `<C-d>` / `<C-u>` | `cursor.half_down` / `cursor.half_up` |
| `<C-f>` `<PageDown>` / `<C-b>` `<PageUp>` | `cursor.page_down` / `cursor.page_up` |
| `H` / `M` / `L` | `cursor.screen_top` / `cursor.screen_middle` / `cursor.screen_bottom` |
| `gg` / `G` | `cursor.top` / `cursor.bottom` |
| `y` | `visual.yank` |
| `ib` | `visual.inner_block` |
| `o` | `visual.swap` |
| `zz` / `zt` / `zb` | `view.center` / `view.top` / `view.bottom` |
| `<Esc>` `<C-c>` `v` `V` | `mode.normal` |

**Insert mode and the command line**

| Keys | Action |
|---|---|
| `<Esc>` `<C-c>` | `mode.normal` (in INSERT, the prompt you were typing is kept) |
| `<CR>` | `edit.submit` |
| `<BS>` `<C-h>` | `edit.backspace` (on an empty command line, leaves it) |
| `<C-w>` | `edit.delete_word` |
| `<C-u>` | `edit.clear` |
| `<Left>` / `<Right>` | `edit.left` / `edit.right` |
| `<C-Left>` `<S-Left>` / `<C-Right>` `<S-Right>` | `edit.word_left` / `edit.word_right` |
| `<Home>` / `<End>` | `edit.home` / `edit.end` (on the command line, `<C-b>` / `<C-e>` too) |
| `<Del>` | `edit.delete` |
| `<Up>` / `<Down>` | `edit.history_prev` / `edit.history_next` (on the command line, `<C-p>` / `<C-n>` too) |
| `<C-r>"` | `edit.paste` |
| `<C-f>` | `edit.normal` |
| `<Tab>` / `<S-Tab>` | `edit.complete` / `edit.complete_prev` (command line) |
| `@` | in INSERT, at the start of a word: pick a file to attach (`Esc` keeps a plain `@`) |

`<C-f>` on the prompt or the command line edits it in vim's NORMAL mode, like the command-line window: `h` `l` `w` `b` `e` `W` `B` `E` `ge` `0` `^` `$` `f` `t` `F` `T` `;` `,`, `x` `X` `s` `S` `r` `~` `D` `C` `Y` `p` `P`, the operators `d` `c` `y` with any of those motions or the text objects `iw` `aw` `iW` `aW` `i"` `a"` `i'` `i(` `a(` `ib` `i[` `i{` `iB` `i<`, counts, `u` `<C-r>` and `.`. The statusline says NORMAL. `i` `a` `I` `A`, `c` and `Esc` go back to typing, `Enter` sends the prompt or runs the command, and `j` / `k` step through history.
