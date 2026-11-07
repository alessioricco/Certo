"""Wires the LLM, tools, and skill context into an SDK Agent."""

from __future__ import annotations

import os
from collections.abc import Mapping, Sequence

from openhands.sdk import LLM, Agent, AgentContext
from openhands.sdk.skills import Skill
from openhands.sdk.context.condenser import LLMSummarizingCondenser

from .config import Config
from .llm import build_llm
from .project_env import ProjectEnv
from .skill_library import collect, disabled_project_skills
from .tools import build_tools

# The SDK ends a conversation turn (execution_status -> FINISHED) whenever the
# LLM replies with plain text and no tool call — identically to how it treats
# an actual `finish` tool call (see response_dispatch.py's
# `_handle_content_response`, "LLM produced a message response - awaits user
# input"). This harness's runner calls `conversation.run()` exactly once with
# nobody able to answer a follow-up, so any plain-text reply — whether it's a
# clarifying question or a premature "done" summary — silently ends the run,
# no error raised. Confirmed live twice, two distinct failure modes under the
# same root cause: (1) the agent asked "let me know if you have specific
# preferences" with no file written; (2) after the first fix, the agent built
# 1 of 6 self-tracked task_tracker items (a demo component), then declared
# success and reframed the other 5 — booking logic, backend, responsiveness,
# testing — as "next steps for you," i.e. it self-graded as done instead of
# continuing. Steering the agent to proceed autonomously (and to not
# self-declare completion early) is a system prompt concern, not a runner
# one, hence it lives here rather than in runner.py's control flow.
_AUTONOMOUS_SUFFIX = (
    "You are running non-interactively: no user is available to answer "
    "follow-up questions, approve a plan, or clarify requirements mid-task. "
    "Never stop to ask a clarifying question or wait for confirmation — make "
    "the most reasonable judgment call yourself, note any assumptions in your "
    "final message, and keep working (across multiple tool calls) until the "
    "task described in the first user message is actually done, not merely "
    "planned. If you maintain a task_tracker list, do not end the "
    "conversation while any item is still incomplete — keep working through "
    "the list yourself. Never describe required functionality you have not "
    "yet built as a 'next step', suggestion, or optional enhancement for the "
    "user to do themselves — if it's part of the task, implement it before "
    "finishing. Only end the conversation by calling the `finish` tool, and "
    "only once the work itself is actually complete, not merely planned or "
    "partially demonstrated."
)

# A harness-wide deliverable requirement, not a fix for a stop-condition bug
# (kept separate from _AUTONOMOUS_SUFFIX above for that reason) — every task
# runs against its own project workspace (see cli.py's `--project` /
# server.py's `project`), and nothing else in this harness writes a run/setup
# guide for whatever the agent happens to build there.
_README_SUFFIX = (
    "Before finishing, make sure the project's root directory has a "
    "README.md with clear, concrete instructions for how to install its "
    "dependencies and actually run (or build) what you created — the exact "
    "commands, not general advice — so someone else can follow it without "
    "guessing. If the project has its own virtual environment (e.g. `.venv`), "
    "include the commands to create it and install the dependencies into it. "
    "Write or update this yourself as part of completing the task, even if "
    "the task description didn't explicitly ask for one."
)


# Added only when the project has its own environment (project_env.py). The
# harness already points the terminal at it; this says so, so the agent
# installs into it rather than reaching for some other interpreter — live,
# an agent tried `<Certo's own python> -m pip install pytest`.
def project_root(cfg: Config) -> str:
    """The folder the agent works in, as its tools see it: the project's
    absolute path, or the container's mount in Docker (workspace.py)."""
    return "/workspace" if cfg.execution == "docker" else os.path.abspath(cfg.workspace)


def _project_root_suffix(root: str) -> str:
    return (
        f"The project root is {root}. Work only inside it: create, edit, read, "
        "list and search files there, and run commands from there. Never read, "
        "list or search anything above or outside it (its parent folders, other "
        "projects, your home folder): none of it is part of the task, and "
        "another project's files are not yours to copy or change. Tools may "
        "still use their own installs and caches."
    )


def _project_env_suffix(env: ProjectEnv) -> str:
    return (
        f"This project has its own Python environment at {env.venv_dir}, and "
        "your terminal already uses it: `python`, `pip` and `pytest` resolve "
        "there. Install any dependency the project needs into it "
        f"(`{env.install_hint}`), never into another interpreter, with "
        "`--user`, or with `sudo`."
    )


# Same underlying pattern as _AUTONOMOUS_SUFFIX above — the agent acting as if
# a human is present when none is — but at the tool-invocation level rather
# than the conversation level. Confirmed live: asked to scaffold with Vite,
# the agent ran `npm create vite@latest ... -- --template react-ts`, which
# started `create-vite`'s interactive template/linter prompt; with no TTY/
# human to answer it, the prompt auto-cancelled (exit code 0, no files
# created) — even though the command's own output printed the fix verbatim
# ("To create in one go, run: create-vite <DIRECTORY> --no-interactive
# --template <TEMPLATE>"). The agent didn't notice nothing was created and
# just re-ran the identical command, repeating this (200K+ tokens, $0.35+)
# until the user killed the process by hand. `CERTO_EXECUTION=local` uses a
# subprocess-based terminal, not a real PTY (tmux isn't installed — see
# MANUAL.md "Known limitations"), so an interactive prompt can't be answered
# even in principle; this is a tool-usage habit to fix regardless of PTY
# support, since retrying an unchanged failing command is the real waste.
_NONINTERACTIVE_TOOLING_SUFFIX = (
    "This terminal has no human available to answer an interactive prompt "
    "(a scaffolding wizard, a 'confirm install?' prompt, etc.) — such a "
    "prompt will hang or silently auto-cancel without doing anything, often "
    "while still exiting with status 0. Always invoke CLI tools with their "
    "non-interactive/CI flags instead (e.g. `--yes`, `-y`, `--no-interactive`, "
    "or a `CI=1`/`CI=true` environment prefix); if a command's own output "
    "tells you how to run it non-interactively, use exactly that flag next. "
    "If a command produces no useful output, appears to hang, or you're not "
    "sure it actually did anything, verify the result yourself (e.g. list "
    "the directory you expected it to create) before trusting the exit "
    "code, and do not retry the identical command — change it (add the "
    "missing flag) or take a different approach instead."
)

# Certo keeps the run state in the project's `.certo/` from the first step
# (the SDK saves the conversation there, which `--resume` needs), so a new
# project folder is never empty. Tested 2026-10-19 with create-vite 9.3.0:
# `npm create vite .` then prints "Operation cancelled" and exits 0, and
# `--overwrite` deletes `.certo/`. Scaffolding into a subfolder works.
_CERTO_STATE_SUFFIX = (
    "If the project folder contains a `.certo/` folder, it is Certo's own "
    "run state: never delete, move or edit it, and ignore it otherwise. "
    "Because of it the folder is not empty, so a scaffolding tool that "
    "wants an empty folder (e.g. `npm create vite .`) will refuse or "
    "cancel, and its overwrite option (`--overwrite`, `--force`) would "
    "delete `.certo/`. Instead, scaffold into a new subfolder, then move "
    "its files (including hidden ones such as `.gitignore`) up into the "
    "project folder and remove the empty subfolder."
)

# A stronger, more direct completion gate than _AUTONOMOUS_SUFFIX's general
# "don't declare early completion" rule above — confirmed live that wasn't
# enough on its own. Asked to build a Tower of Hanoi game, the agent called
# `finish` with a message admitting "there are errors in the tests that need
# further debugging" — an explicit, deliberate `finish` call despite known
# failures, not an accidental plain-text stop. Worse, its own diagnosis was
# wrong: the actual file had an IndentationError and didn't even parse (`def
# main():` left with an empty body), so every test failed at collection, not
# from "sequence handling and state transitions" as it claimed — it never
# re-ran anything to check before writing that summary. This harness also
# runs its own post-hoc test verification as a safety net (see runner.py's
# _verify_tests_and_retry) precisely because this instruction, like the
# others in this file, is a soft nudge the model can still ignore or get
# wrong — but the model should still be told the actual bar plainly.
_VERIFY_BEFORE_FINISH_SUFFIX = (
    "Before calling `finish`, verify your own claims by actually running "
    "them — do not guess, assume, or describe a test failure or bug from "
    "memory. If you wrote or changed tests, run the full test suite (e.g. "
    "via the `run_tests` tool) and read the real output; if you wrote a "
    "program meant to run, actually execute it. A `finish` call is not "
    "appropriate while a test is failing, the program crashes, or the code "
    "does not import/parse cleanly — fix the underlying issue and "
    "re-verify, don't report the failure as something left for later."
)

# The eight lifecycle skills in builtin_skills/lifecycle/ (repository-discovery,
# requirements-analysis, implementation-planning, testing-and-verification,
# debugging-and-failure-repair, security-review,
# documentation-and-operational-readiness, completion-and-release-readiness
# — see MANUAL.md "Skills") are legacy-format `.md` files with `triggers:`
# frontmatter (KeywordTrigger), not AgentSkills `SKILL.md` — a deliberate
# switch from this harness's earlier 5-skill set (see DECISIONS.md): a
# KeywordTrigger skill auto-injects its full content the moment a
# matching word appears in the task, with no model action required, instead
# of depending on the model choosing to call `invoke_skill` — real,
# code-enforced triggering rather than a hope. That makes most of what the
# old suffix said here (name each skill, tell the model to invoke it by
# name) no longer necessary; what's still worth saying explicitly is the
# surrounding discipline a deterministic trigger can't provide on its own —
# confirmed by reading the SDK source (`skill.py`), not assumed.
_LIFECYCLE_SKILLS_SUFFIX = (
    "Before editing, inspect the repository itself (see the "
    "`repository-discovery` skill if it's already in context) and apply "
    "whatever lifecycle skill guidance becomes relevant as the task "
    "unfolds — most of these activate automatically based on your task, "
    "but act on the lifecycle discipline they describe even for a task "
    "whose wording doesn't happen to match a trigger word, if the "
    "situation still calls for it (e.g. a vague request still needs "
    "requirements pinned down even if it never says 'requirement'). Skip a "
    "skill outright when the task is too small for it to matter — a "
    "one-line fix doesn't need requirements analysis or a release-readiness "
    "review. A skill's guidance is advice for how to do the work, never a "
    "substitute for actually doing it — reading `testing-and-verification`'s "
    "or `security-review`'s guidance does not itself verify or secure "
    "anything; you still have to run the checks and read their real output."
)


# The condenser summarizes older steps only when the conversation nears the
# model's context window (the SDK's `max_input_tokens`, context_window.py)
# or a provider says it is over it. Its other trigger, a count of events,
# is set out of reach: a run that still fits keeps its whole history, so
# nothing changes for a model with room to spare.
CONDENSER_MAX_EVENTS = 1_000_000
# Never summarized: the system prompt and the task, at the start.
CONDENSER_KEEP_FIRST = 4


def _condenser(llm: LLM) -> LLMSummarizingCondenser:
    """The SDK's own condenser, summarizing with the agent's model (as the
    SDK's presets do), so its cost is in the run summary."""
    return LLMSummarizingCondenser(
        llm=llm, max_size=CONDENSER_MAX_EVENTS, keep_first=CONDENSER_KEEP_FIRST
    )


def build_agent(
    cfg: Config,
    *,
    usage_id: str = "certo",
    project_env: ProjectEnv | None = None,
    terminal_env: Mapping[str, str] | None = None,
    trusted_skills: Sequence[Skill] = (),
) -> Agent:
    # usage_id is forwarded to build_llm() unchanged (default preserves the
    # single-model behavior everything used before). Auto model selection
    # (see model_selection.py) passes a distinct usage_id per catalog
    # candidate so the SDK's LLM registry never confuses one candidate's
    # config for another's when runner.py later calls conversation.switch_llm.
    # CERTO_INTERACTIVE=yes (cfg.interactive) drops _AUTONOMOUS_SUFFIX so
    # the agent may pause/ask instead of being told to always push forward
    # — the terminal-loop half that answers a question when it does is
    # runner.py's stream_task interactive checkpoint, not anything here.
    # Every other suffix stays unconditional: none of them are about "is a
    # human present," they're independent policies (README requirement,
    # non-interactive tool flags, keeping .certo/, verify-before-finish,
    # lifecycle skills).
    suffixes = [_AUTONOMOUS_SUFFIX] if not cfg.interactive else []
    if cfg.root_prompt:
        suffixes.append(_project_root_suffix(project_root(cfg)))
    suffixes.extend(
        [
            _README_SUFFIX,
            _NONINTERACTIVE_TOOLING_SUFFIX,
            _CERTO_STATE_SUFFIX,
            _VERIFY_BEFORE_FINISH_SUFFIX,
            _LIFECYCLE_SKILLS_SUFFIX,
        ]
    )
    # project_env / terminal_env come from runner.py's environment setup:
    # the terminal session's extra variables, and the one policy line above.
    if project_env is not None:
        suffixes.append(_project_env_suffix(project_env))
    # Official, then third-party (global, then this project's), one skill
    # per name: AgentContext rejects duplicate names (skill_library.py).
    # Minus the official ones a benchmark arm turned off.
    # trusted_skills: the run's picks from trusted repositories
    # (skill_match.skills_for_run), after every skill already named.
    skills = collect(cfg, cfg.workspace, own=False).without_official(cfg.skills_off)
    skills += list(trusted_skills)
    agent_context = AgentContext(
        skills=skills,
        # Resolved lazily by the Conversation once the real workspace path is
        # known (AgentContext itself doesn't know it yet) — this is what makes
        # a project's AGENTS.md / .agents/skills/ (see skills.write_project_context)
        # apply automatically, on top of (and replacing) the skills above.
        load_project_skills=True,
        # The SDK applies this deny-list to the lazily loaded project skills
        # too: a generated project gets no agent files from a git repository
        # above it.
        disabled_skills=disabled_project_skills(cfg.workspace, cfg.projects_dir),
        system_message_suffix="\n\n".join(suffixes),
    )
    llm = build_llm(cfg, usage_id=usage_id)
    agent = Agent(
        llm=llm,
        tools=build_tools(terminal_env),
        agent_context=agent_context,
        condenser=_condenser(llm) if cfg.condense else None,
    )
    # CERTO_CONFIRM_MODE == "always" should attach a confirmation policy that
    # pauses before each tool call. The confirmation-policy API is not yet
    # verified against this SDK version (see CLAUDE.md) — /verify-sdk before
    # wiring it up.
    return agent
