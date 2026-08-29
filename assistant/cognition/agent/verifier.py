"""
P.E.P.P.E.R. - Agent Verifier

Created: August 9, 2026
Last Edited: August 10, 2026
Author: Max Maehara

Purpose:
    Provides Phase 7 execution verification, failure recovery,
    dynamic continuation planning, and final goal verification.

Capabilities:
    - deterministic Phase 6 result verification
    - stdout / stderr inspection
    - exact tool-signature awareness
    - failed-step recovery
    - dynamic continuation after successful investigative steps
    - Phase 8 browser-result preservation
    - Phase 8 research continuation
    - final goal completion verification
    - final result synthesis from verified task evidence

Important:
    This module NEVER executes tools.

    It only interprets real execution results and determines
    what the agent should do next.

Architecture:
    Phase 7 remains the reasoning / orchestration layer.

    Every real computer action continues through the existing
    Phase 6 executor, registry, permission system, and deterministic
    verification layer.

Most Recent Change:
    Final Phase 13 hardening:
    - preserves search_filesystem discovery evidence
    - consumes exact discovered paths
    - prevents repeated zero-result filesystem search loops
    - preserves verified Phase 13 success evidence
    - prevents redundant VS Code/window/browser continuation loops
"""

import inspect
import json

from dotenv import load_dotenv
from openai import OpenAI

from pydantic import (
    BaseModel,
    Field,
)

from assistant.capabilities.tools.registry import (
    list_tools,
    load_default_tools,
)

from assistant.capabilities.tools.verifier import (
    verify_tool_result as
    verify_phase6_tool_result,
)

from .models import (
    AgentStep,
    AgentTask,
)


# ---------------------------------------------------------------------------
# Environment
# ---------------------------------------------------------------------------

load_dotenv()

client = OpenAI()


# ---------------------------------------------------------------------------
# Structured Models
# ---------------------------------------------------------------------------

class PlannedAgentStep(BaseModel):
    description: str

    tool_name: str

    arguments_json: str = "{}"


class RecoveryDecision(BaseModel):
    action: str

    reason: str = ""

    next_steps: list[
        PlannedAgentStep
    ] = Field(
        default_factory=list
    )


class ContinuationDecision(BaseModel):
    complete: bool

    reason: str = ""

    next_steps: list[
        PlannedAgentStep
    ] = Field(
        default_factory=list
    )


class CompletionDecision(BaseModel):
    complete: bool

    confidence: int = Field(
        default=0,
        ge=0,
        le=100,
    )

    summary: str = ""

    missing: list[str] = Field(
        default_factory=list
    )


# ---------------------------------------------------------------------------
# Registered Tool Contracts
# ---------------------------------------------------------------------------

def describe_agent_tools():
    """
    Gives recovery and continuation reasoning access to the exact
    currently registered Phase 6 tool signatures.
    """

    load_default_tools()

    blocks = []


    for tool in list_tools():

        try:

            signature = inspect.signature(
                tool.function
            )

            if tool.name == "computer_control":
                parameters = [
                    parameter
                    for name, parameter in signature.parameters.items()
                    if name != "approved"
                ]
                signature = signature.replace(parameters=parameters)

        except (
            TypeError,
            ValueError,
        ):

            signature = (
                "(signature unavailable)"
            )


        blocks.append(
            (
                f"Tool: {tool.name}\n"
                f"Category: {tool.category}\n"
                f"Risk: {tool.risk}\n"
                f"Signature: "
                f"{tool.name}{signature}\n"
                f"Description: "
                f"{tool.description}"
            )
        )


    return "\n\n".join(
        blocks
    )


# ---------------------------------------------------------------------------
# Registered Tool Names
# ---------------------------------------------------------------------------

def get_registered_tool_names():
    load_default_tools()

    return {
        tool.name
        for tool
        in list_tools()
    }


# ---------------------------------------------------------------------------
# Deterministic Phase 6 Verification
# ---------------------------------------------------------------------------

def verify_step_result(
    execution,
):
    """
    Uses the existing Phase 6 deterministic verifier.
    """

    return (
        verify_phase6_tool_result(
            execution
        )
    )


# ---------------------------------------------------------------------------
# Compact Browser Search Results
# ---------------------------------------------------------------------------

def compact_browser_results(
    results,
    limit: int = 15,
):
    """
    Preserves structured browser-search results without allowing a
    very large result list to flood Phase 7 reasoning context.

    Search titles and canonical URLs remain unchanged.
    """

    if not isinstance(
        results,
        list,
    ):

        return results


    compacted = []


    for item in results[
        :limit
    ]:

        if isinstance(
            item,
            dict,
        ):

            compacted.append(
                {
                    "title":
                        item.get(
                            "title"
                        ),

                    "url":
                        item.get(
                            "url"
                        ),
                }
            )

        else:

            compacted.append(
                item
            )


    return compacted


# ---------------------------------------------------------------------------
# Compact Browser Links
# ---------------------------------------------------------------------------

def compact_browser_links(
    links,
    limit: int = 40,
):
    """
    Preserves useful page links while bounding agent context.
    """

    if not isinstance(
        links,
        list,
    ):

        return links


    compacted = []


    for item in links[
        :limit
    ]:

        if isinstance(
            item,
            dict,
        ):

            compacted.append(
                {
                    "text":
                        item.get(
                            "text"
                        ),

                    "url":
                        (
                            item.get(
                                "url"
                            )
                            or item.get(
                                "href"
                            )
                        ),
                }
            )

        else:

            compacted.append(
                item
            )


    return compacted


# ---------------------------------------------------------------------------
# Compact Browser Tabs
# ---------------------------------------------------------------------------

def compact_browser_tabs(
    tabs,
    limit: int = 25,
):
    """
    Preserves managed-browser tab state for Phase 7 reasoning.
    """

    if not isinstance(
        tabs,
        list,
    ):

        return tabs


    compacted = []


    for item in tabs[
        :limit
    ]:

        if isinstance(
            item,
            dict,
        ):

            compacted.append(
                {
                    "index":
                        item.get(
                            "index"
                        ),

                    "active":
                        item.get(
                            "active"
                        ),

                    "title":
                        item.get(
                            "title"
                        ),

                    "url":
                        item.get(
                            "url"
                        ),
                }
            )

        else:

            compacted.append(
                item
            )


    return compacted


# ---------------------------------------------------------------------------
# Compact Browser Text
# ---------------------------------------------------------------------------

def compact_browser_text(
    text,
    limit: int = 30000,
):
    """
    Preserves enough retrieved source text for meaningful research
    reasoning while bounding continuation / verifier prompt size.
    """

    if not isinstance(
        text,
        str,
    ):

        return text


    if len(text) <= limit:

        return text


    return (
        text[
            :limit
        ]
        + "\n\n"
        + (
            "[Browser text truncated "
            "for agent reasoning]"
        )
    )


# ---------------------------------------------------------------------------
# Compact Tool Results
# ---------------------------------------------------------------------------

def extract_execution_details(
    execution,
):
    """
    Preserves the execution information most useful for Phase 7
    reasoning.

    Existing Phase 6 / Phase 7 fields remain available.

    Phase 8 browser fields are also preserved so continuation and
    completion reasoning can consume real search results, URLs,
    page text, links, tabs, and navigation state rather than trying
    to rediscover them.

    Raw AgentStep.result remains unchanged elsewhere. This function
    only creates a compact LLM-facing representation.
    """

    if not isinstance(
        execution,
        dict,
    ):

        return execution


    details = {
        "success":
            execution.get(
                "success"
            ),

        "executed":
            execution.get(
                "executed"
            ),

        "tool":
            execution.get(
                "tool"
            ),

        "risk":
            execution.get(
                "risk"
            ),

        "requires_approval":
            execution.get(
                "requires_approval"
            ),

        "error":
            execution.get(
                "error"
            ),

        "reason":
            execution.get(
                "reason"
            ),
    }


    result = execution.get(
        "result"
    )


    # -----------------------------------------------------------------------
    # Phase 9 / 10 Integration Evidence
    # -----------------------------------------------------------------------
    #
    # integration_execute already returns bounded structured evidence.
    # Preserve it intact so Phase 7 continuation and final verification
    # can synthesize results across Weather, GitHub, Schwab, Google,
    # Notion, Spotify, and future providers.
    # -----------------------------------------------------------------------

    if (
        execution.get(
            "tool"
        )
        == "integration_execute"
        and isinstance(
            result,
            dict,
        )
    ):

        details[
            "result"
        ] = result

        return details

    # -----------------------------------------------------------------------
    # Phase 13 Computer-Control Evidence
    # -----------------------------------------------------------------------
    #
    # computer_control returns structured method selection, fallback trace,
    # verification state, and backend-specific evidence. Preserve that
    # evidence intact for continuation/recovery/final verification.
    # -----------------------------------------------------------------------

    if (
        execution.get(
            "tool"
        )
        == "computer_control"
        and isinstance(
            result,
            dict,
        )
    ):

        details[
            "result"
        ] = result

        return details
    


    # -----------------------------------------------------------------------
    # Phase 13 Filesystem-Discovery Evidence
    # -----------------------------------------------------------------------
    #
    # search_filesystem returns exact real filesystem discovery evidence.
    # Preserve the result intact so continuation/recovery can consume:
    #
    #     result.matches[].path
    #     result.count
    #     result.query
    #     result.roots
    #     result.truncated
    #
    # Without this special case, the generic compactor drops those fields,
    # causing Phase 7 to forget successful discoveries and search again.
    # -----------------------------------------------------------------------

    if (
        execution.get(
            "tool"
        )
        == "search_filesystem"
        and isinstance(
            result,
            dict,
        )
    ):

        details[
            "result"
        ] = result

        return details


    if isinstance(
        result,
        dict,
    ):

        details["result"] = {
            # ---------------------------------------------------------------
            # Existing Workspace / Terminal Evidence
            # ---------------------------------------------------------------

            "workspace":
                result.get(
                    "workspace"
                ),

            "cwd":
                result.get(
                    "cwd"
                ),

            "command":
                result.get(
                    "command"
                ),

            "command_text":
                result.get(
                    "command_text"
                ),

            "exit_code":
                result.get(
                    "exit_code"
                ),

            "stdout":
                result.get(
                    "stdout"
                ),

            "stderr":
                result.get(
                    "stderr"
                ),

            "timed_out":
                result.get(
                    "timed_out"
                ),

            # ---------------------------------------------------------------
            # Existing Filesystem Evidence
            # ---------------------------------------------------------------

            "file":
                result.get(
                    "file"
                ),

            "directory":
                result.get(
                    "directory"
                ),

            "entries":
                result.get(
                    "entries"
                ),

            "content":
                result.get(
                    "content"
                ),

            # ---------------------------------------------------------------
            # Existing Application / VS Code Evidence
            # ---------------------------------------------------------------

            "opened":
                result.get(
                    "opened"
                ),

            "new_window":
                result.get(
                    "new_window"
                ),

            "focused":
                result.get(
                    "focused"
                ),

            "window_title":
                result.get(
                    "window_title"
                ),

            "pid":
                result.get(
                    "pid"
                ),

            # ---------------------------------------------------------------
            # Phase 8 Browser Lifecycle / Navigation
            # ---------------------------------------------------------------

            "connected":
                result.get(
                    "connected"
                ),

            "closed":
                result.get(
                    "closed"
                ),

            "remaining_tabs":
                result.get(
                    "remaining_tabs"
                ),

            "status":
                result.get(
                    "status"
                ),

            "url":
                result.get(
                    "url"
                ),

            "title":
                result.get(
                    "title"
                ),

            # ---------------------------------------------------------------
            # Phase 8 Browser State
            # ---------------------------------------------------------------

            "tab_count":
                result.get(
                    "tab_count"
                ),

            "active_tab":
                result.get(
                    "active_tab"
                ),

            "active_title":
                result.get(
                    "active_title"
                ),

            "active_url":
                result.get(
                    "active_url"
                ),

            "tabs":
                compact_browser_tabs(
                    result.get(
                        "tabs"
                    )
                ),

            # ---------------------------------------------------------------
            # Phase 8 Search Evidence
            # ---------------------------------------------------------------

            "query":
                result.get(
                    "query"
                ),

            "provider":
                result.get(
                    "provider"
                ),

            "search_url":
                result.get(
                    "search_url"
                ),

            "results":
                compact_browser_results(
                    result.get(
                        "results"
                    )
                ),

            "attempts":
                result.get(
                    "attempts"
                ),

            # ---------------------------------------------------------------
            # Phase 8 Page Intelligence
            # ---------------------------------------------------------------

            "text":
                compact_browser_text(
                    result.get(
                        "text"
                    )
                ),

            "visible_text":
                compact_browser_text(
                    result.get(
                        "visible_text"
                    )
                ),

            "links":
                compact_browser_links(
                    result.get(
                        "links"
                    )
                ),

            "buttons":
                result.get(
                    "buttons"
                ),

            "inputs":
                result.get(
                    "inputs"
                ),

            # ---------------------------------------------------------------
            # Phase 8 Interaction Evidence
            # ---------------------------------------------------------------

            "filled":
                result.get(
                    "filled"
                ),
        }

    else:

        details["result"] = (
            result
        )


    return details


# ---------------------------------------------------------------------------
# Task History
# ---------------------------------------------------------------------------

def build_history(
    task: AgentTask,
):
    """
    Converts the entire current task into compact reasoning context.
    """

    history = []


    for step in task.steps:

        history.append(
            {
                "step_number":
                    step.step_number,

                "description":
                    step.description,

                "tool_name":
                    step.tool_name,

                "arguments":
                    step.arguments,

                "status":
                    step.status,

                "attempts":
                    step.attempts,

                "result":
                    extract_execution_details(
                        step.result
                    ),

                "error":
                    step.error,
            }
        )


    return history


# ---------------------------------------------------------------------------
# Parse Tool Arguments
# ---------------------------------------------------------------------------

def parse_arguments(
    arguments_json: str,
):
    if not arguments_json:

        return {}


    try:

        arguments = json.loads(
            arguments_json
        )

    except json.JSONDecodeError:

        return {}


    if not isinstance(
        arguments,
        dict,
    ):

        return {}


    return arguments


# ---------------------------------------------------------------------------
# Convert Planned Steps
# ---------------------------------------------------------------------------

def convert_planned_steps(
    planned_steps,
    starting_number: int,
):
    """
    Converts model-generated next steps into AgentStep objects.

    Invalid / hallucinated tool names are discarded.
    """

    registered = (
        get_registered_tool_names()
    )

    converted = []


    for planned in planned_steps:

        tool_name = (
            planned.tool_name
            .strip()
            .lower()
        )


        if tool_name not in registered:

            continue


        converted.append(
            AgentStep(
                step_number=(
                    starting_number
                    + len(
                        converted
                    )
                ),

                description=
                    planned.description,

                tool_name=
                    tool_name,

                arguments=
                    parse_arguments(
                        planned.arguments_json
                    ),
            )
        )


    return converted


# ---------------------------------------------------------------------------
# Failure Recovery
# ---------------------------------------------------------------------------

def decide_recovery(
    task: AgentTask,
    failed_step: AgentStep,
):
    """
    Determines what to do after a real failed action.
    """

    payload = {
        "goal":
            task.goal,

        "failed_step": {
            "step_number":
                failed_step.step_number,

            "description":
                failed_step.description,

            "tool_name":
                failed_step.tool_name,

            "arguments":
                failed_step.arguments,

            "attempts":
                failed_step.attempts,

            "error":
                failed_step.error,

            "execution":
                extract_execution_details(
                    failed_step.result
                ),
        },

        "task_history":
            build_history(
                task
            ),

        "available_tools":
            describe_agent_tools(),
    }


    response = (
        client.responses.parse(
            model="gpt-5.5",

            instructions="""
You are P.E.P.P.E.R.'s Phase 7 failure recovery controller.

A REAL computer action failed.

You have:
- the original user goal
- the exact failed tool
- the exact arguments used
- actual stdout
- actual stderr
- actual exit code
- the full task history
- exact registered tool signatures

Determine the safest useful next action.


VALID ACTIONS:

retry

    Retry the failed step unchanged.

    Use only for genuinely temporary failures.


replace

    Replace the failed step and remaining work with a corrected
    sequence of tool actions.


continue

    Skip the failed step only when it is genuinely optional to
    the user's original goal.


fail

    Stop only when the goal cannot reasonably or safely continue.


RULES:

1. Read actual stdout and stderr.

2. A non-zero exit code does NOT automatically mean the task
   should stop.

3. Programming errors are normally recoverable.

4. File-not-found errors are normally recoverable if the requested
   file can be located using available tools.

5. Incorrect tool arguments are normally recoverable.

6. When a source-code problem must be fixed:

       inspect the relevant source when necessary
       modify it with write_file
       rerun the program or test

7. write_file and other modifying tools will still pass through
   Phase 6 permissions. Do not avoid them merely because approval
   will be required.

8. Use the exact registered tool signatures.

9. Never invent argument names.

10. Never invent file paths.

11. Never repeat the same known-bad action indefinitely.

12. Return the smallest corrective sequence.

13. Return at most four next steps.

14. If an action discovers information needed for later work,
    include the action that actually uses that information when
    possible.

15. Browser failures follow the same evidence rules.

16. If browser_search_web already produced structured search
    results in task history, those exact returned URLs are real
    observed evidence.

17. Never invent a browser research URL when an unused real search
    result is available.

18. If one research source fails but other relevant real search
    results are available, using another returned result may be
    appropriate.

PHASE 13 COMPUTER CONTROL:

19. For desktop, Windows, application, UI, browser-DOM, or visual
    computer actions, prefer the registered computer_control tool.

20. Do NOT replace a failed structured Phase 13 action with:
        run_command
        PowerShell
        WScript.Shell
        SendKeys
        pyautogui
        arbitrary mouse coordinates

21. If a structured UI operation failed because the target application
    is not running, recover by using:

        computer_control(
            action="application.launch",
            target=<application>
        )

    and then retry the original structured computer_control action.

22. Let Phase 13 choose native/UIA/DOM/vision fallback internally.

23. Never manually lower a failed structured action to vision or
    coordinate clicking.

24. A Phase 13 BLOCKED result is a safety boundary, not a reason to
    try a weaker control mechanism.
25. Use only canonical computer_control actions in the registered contract.
26. Never include or invent approved.
27. A FAILED result is not permission to lower to vision.
28. If an action is unsupported, choose another REGISTERED canonical action.
29. If a requested monitor does not exist, report that evidence instead of pretending placement succeeded.
30. Treat computer_control verified=true as real post-action evidence.
31. Prefer filesystem.exists/inspect for file verification instead of inferring success from a prior write.

DIRECTORY / PROJECT DISCOVERY:

32. filesystem.inspect describes ONE already-known filesystem path.
    It does NOT enumerate or search that directory's children.

33. When the location of a requested project, workspace, directory, or file is
    unknown, prefer the registered read-only tool:

        search_filesystem

34. Do NOT replace search_filesystem with:
        run_python
        PowerShell
        os.walk
        pathlib traversal
        Get-ChildItem recursion
        custom filesystem crawling code

35. Never use filesystem.inspect on a parent directory and claim that it will
    locate a child project.

36. A successful search_filesystem result is real filesystem evidence.

37. When search_filesystem returns one strong exact-name directory match,
    immediately consume the exact:

        result.matches[0].path

    value in the next dependent action.

38. Never invent, shorten, reconstruct, or guess a discovered path.

39. If multiple plausible matches are returned, do not guess between them.
    Use other real evidence when available; otherwise stop safely so the user
    can disambiguate.

40. Read-only filesystem discovery must remain read-only.

FILESYSTEM SEARCH ANTI-LOOP:

41. A search_filesystem result with:

        count = 0
        matches = []

    is REAL evidence that the query was not found in the roots/depth actually
    searched.

42. Do not repeatedly issue increasingly vague filesystem searches forever.

43. For one unknown requested path, normally allow at most TWO materially
    different search_filesystem attempts.

44. A second attempt is justified only when it materially expands real search
    coverage, such as broader roots or greater max_depth.

45. After two searches return zero useful matches, do NOT spend more recovery
    or continuation cycles searching arbitrary fragments of the same name.

46. If the requested path still cannot be identified safely after the bounded
    searches, stop and report that the project/file location could not be
    found from the searched user folders.

47. Never claim a project was found when matches=[].

48. Once a valid match has been found, NEVER search for the same path again
    unless later real evidence proves that observed path is invalid.

RECOVERY ANTI-LOOP / SUCCESS-EVIDENCE RULES:

49. Never recover from one failed action by repeating an earlier action that
    task history already proves succeeded unless newer evidence invalidates
    that success.

50. Do not reopen the same workspace repeatedly merely to identify or retarget
    a window.

51. Prefer process id, window handle, workspace path, window title, browser tab,
    monitor, and other concrete evidence already observed in successful task
    history.

52. Do not repeat the same failed target-resolution strategy indefinitely.

53. If a corrected action has already succeeded, continue toward the next
    unfinished part of the original goal rather than redoing that action.

54. If a successful VS Code action reports opened=True and new_window=True,
    treat the requested new-window launch as complete.

55. If a successful computer_control result contains verified=True, treat the
    requested structured computer effect as real evidence unless later evidence
    contradicts it.

VS CODE TARGET RECOVERY:

56. If the generic target "Visual Studio Code" affected the wrong VS Code
    window, do not repeat that generic target.

57. For a project-specific VS Code request, prefer an observed project name
    appearing in the real visible window title, for example:

        FinalCollegePortfolio

58. Do not turn an application-launch process id into a string target such as:

        pid:<number>

    unless the registered Phase 13 action contract explicitly supports that
    target form.

59. A process id returned by application.launch is not automatically the
    process id of the intended top-level window. Applications such as VS Code
    may reuse or forward work into an existing process.

60. If task history contains a verified window.place whose real nested window
    title contains the requested project/workspace name and whose monitor
    matches the user's requested monitor, treat that placement as complete.

Example:

Goal:
Run typewriter.py and debug it until successful.

Failure:
typewriter.py was not found.

A search then needs to locate the file.

A useful corrected sequence could be:

1. search/list to locate the requested file
2. run the discovered path

If the exact discovered path is not known yet, it is acceptable
for the corrective sequence to contain only the search step.
The continuation controller will use the real search result afterward.


Example:

Failure:
run_python returned:

SyntaxError: expected ':'

Good recovery:

1. read_file the source
2. write_file corrected source
3. run_python again


Example:

Failure:
run_python() got unexpected keyword argument 'path'

Registered signature:

run_python(arguments=None, cwd=".", workspace_path=None, timeout=60)

Correct action:

replace

Next step:

run_python(
    arguments=["actual_script.py"]
)
""".strip(),

            input=json.dumps(
                payload,
                ensure_ascii=False,
                default=str,
            ),

            text_format=
                RecoveryDecision,
        )
    )


    return (
        response.output_parsed
    )


# ---------------------------------------------------------------------------
# Continuation Planning
# ---------------------------------------------------------------------------

def decide_continuation(
    task: AgentTask,
):
    """
    Runs when every CURRENTLY PLANNED step has completed.

    This prevents investigative actions from incorrectly ending the
    entire task.

    Phase 8:
        Structured browser_search_web results are preserved in history
        and should be consumed directly rather than rediscovered through
        redundant search-page inspection.
    """

    payload = {
        "goal":
            task.goal,

        "task_history":
            build_history(
                task
            ),

        "available_tools":
            describe_agent_tools(),
    }


    response = (
        client.responses.parse(
            model="gpt-5.5",

            instructions="""
You are P.E.P.P.E.R.'s Phase 7 continuation controller.

Every CURRENTLY PLANNED action has finished.

Your job is to determine whether the ORIGINAL USER GOAL is actually
finished.

This is different from asking whether the current plan ended.

A successful investigative action may reveal information that must
be used in another action.


GENERAL EXAMPLE:

Goal:

Run typewriter.py and fix errors until successful.

History:

1. run_python("typewriter.py")
   failed because the file was not found.

2. workspace search
   succeeded and found:
   TypewriterTest/typewriter.py

The task is NOT complete.

Correct next action:

run_python(
    arguments=[
        "TypewriterTest/typewriter.py"
    ]
)


ANOTHER GENERAL EXAMPLE:

Goal:

Debug script until successful.

History:

1. run_python
   SyntaxError

2. read_file
   source was successfully read

The task is NOT complete.

Correct next actions may be:

1. write_file corrected source
2. run_python again


PHASE 9 / 10 CONNECTED-SERVICE EVIDENCE

integration_execute results in task history are REAL connected-service
evidence.

They may contain structured evidence from:
    weather
    github
    google
    schwab
    spotify
    notion
    other registered providers

When multiple integration_execute steps succeeded:

- use the actual structured result from each step
- do not repeat a successful read merely because the current plan ended
- do not invent missing provider data
- if all requested independent reads succeeded, the information-gathering
  portion of the goal is normally complete
- allow final completion verification to synthesize those real results
  into one user-facing response

PHASE 8 STRUCTURED BROWSER EVIDENCE

browser_search_web returns structured, real search evidence.

A successful result may contain:

{
    "query": "...",
    "provider": "bing",
    "results": [
        {
            "title": "...",
            "url": "https://..."
        }
    ]
}

These URLs were observed by the real Phase 8 browser-search tool.

They are stronger evidence than model memory, guesses, or assumptions.


WHEN SEARCH RESULTS EXIST:

- consume the returned result objects directly
- use the exact returned URLs
- never invent a source URL
- do not repeat browser_search_web with the same query merely because
  the current plan ended
- do not repeatedly inspect the search-results page merely to
  rediscover URLs already present in structured results
- do not call browser_get_state merely to rediscover the same search
  page
- do not call browser_get_page_context merely to rediscover search
  result links already returned by browser_search_web
- do not browser_read_page the search-results page merely to rediscover
  those same URLs

If the original goal requires opening and reading sources, the normal
next action after a successful search is:

    browser_navigate(
        url=<exact returned result URL>
    )

followed by:

    browser_read_page


RESEARCH WORKFLOW

For a goal such as:

    Research X.
    Search the web.
    Open and read at least three useful sources.
    Compare them.
    Give me a concise summary.

A useful adaptive pattern is:

    browser_search_web
        ↓
    consume real results[]
        ↓
    browser_navigate(source 1)
        ↓
    browser_read_page
        ↓
    browser_navigate(source 2)
        ↓
    browser_read_page
        ↓
    browser_navigate(source 3)
        ↓
    browser_read_page
        ↓
    completion verification / synthesis

Do not perform redundant Bing/search-page inspections between source
reads.


SOURCE SELECTION

1. Select sources from the real browser_search_web results.

2. Prefer relevant and authoritative results when appropriate.

3. Prefer primary sources where they directly answer the user's
   question.

4. Never invent URLs.

5. Avoid reopening a URL already successfully read unless there is
   a real reason to revisit it.

6. Respect the requested number of sources.

7. If the user requested at least three sources, three distinct
   successfully read relevant sources normally satisfy the source
   count.

8. Search again only when:
       existing results are insufficient
       existing results are irrelevant
       existing results are unusable
       another query is genuinely needed


SOURCE READING

Successful browser_navigate proves navigation occurred.

It does NOT prove the source was actually read.

If the original goal requires understanding, comparing, or
summarizing a source, follow navigation with:

    browser_read_page

Use the returned real page text as research evidence.


RULES:

1. Judge the ORIGINAL GOAL, not merely the current plan.

2. Use actual execution results only.

3. Never invent discovered paths.

4. Never invent stdout or stderr.

5. Never invent browser URLs.

6. Use exact registered tool signatures.

7. If history reveals a file path needed for the next action,
   use that real path.

8. If browser_search_web reveals result URLs needed for subsequent
   work, use those exact returned URLs.

9. If the user requested:
       debug until successful
       fix errors
       keep trying
       rerun until it works
       verify the result

   then keep working until evidence supports completion.

10. If the user requested research from multiple sources, continue
    until the requested source-reading requirement is supported by
    real history.

11. Never bypass permissions.

12. Do not add unnecessary steps.

13. Do not repeatedly rediscover information that is already present
    in structured tool output.

14. Return at most four next steps.

15. Preserve adaptive execution. Do not hard-code imaginary future
    facts.

16. If future decisions depend on reading the next source, returning:

        browser_navigate
        browser_read_page

    and then reconsidering afterward is appropriate.

17. If several unused real source URLs are already known and opening
    them does not depend on an intermediate result, multiple
    navigate/read steps may be returned up to the four-step limit.

18. If the original goal is already supported by real history:

        complete = true
        next_steps = []

19. If more work remains:

        complete = false
        next_steps = concrete actions

PHASE 13 COMPUTER CONTROL:

20. For additional desktop/application actions, prefer the registered
    computer_control tool.

21. If task history proves an application was launched successfully,
    use that evidence when planning the next UI action.

22. If a computer_control result contains verified=true, treat that as
    real post-action evidence.

23. Do not redo successful Phase 13 actions using run_command,
    PowerShell, SendKeys, pyautogui, or coordinate clicking.

24. If the next requested computer action is supported by Phase 13,
    continue with another computer_control step.

25. Preserve the user's requested sequence while allowing Phase 13 to
    choose the physical backend.
26. Use only canonical computer_control actions in the registered contract.
27. Never include or invent approved.
28. Never replace structured Phase 13 control with PowerShell, SendKeys, pyautogui, or blind coordinate clicking.
29. A BLOCKED result is a safety boundary.
30. A FAILED result is not permission to lower to vision.
31. If an action is unsupported, choose another REGISTERED canonical action.
32. If a requested monitor does not exist, report that evidence instead of pretending placement succeeded.
33. Prefer filesystem.exists/inspect for verification instead of inferring success from a prior write.
34. filesystem.inspect is for ONE already-known path.
    It is not a directory search.

35. When a real project/file/workspace path is unknown, prefer:

        search_filesystem

36. Do NOT generate run_python, PowerShell, os.walk, pathlib traversal,
    Get-ChildItem recursion, or custom filesystem search code when
    search_filesystem is available.

37. search_filesystem returns real structured evidence. Consume the exact:

        result.matches[].path

    value.

38. Never guess that a project name is relative to the P.E.P.P.E.R. repository.

39. When search_filesystem returns exactly one strong matching project
    directory, use its exact absolute path in the NEXT dependent action.

40. Once the path has been discovered successfully, do not search for it again
    unless later real evidence shows that path is invalid.

41. If multiple plausible search matches exist and no real evidence identifies
    the intended one, do not guess.

FILESYSTEM SEARCH ANTI-LOOP:

42. A completed search_filesystem step with:
        count = 0
        matches = []
    is real negative search evidence.

43. Do not repeatedly broaden the same project-name search through arbitrary
    fragments merely to keep the task alive.

44. Normally allow no more than TWO materially different search_filesystem
    attempts for one unknown requested path.

45. A second attempt should materially expand real coverage, such as using
    broader roots or greater max_depth.

46. After two zero-result searches, do not consume more continuation cycles
    searching arbitrary fragments of the same project name.

47. Never claim the project was found unless task history contains a real
    search result with a matching path.

48. If two materially different searches return zero useful matches and the
    missing path blocks the remaining goal, stop continuation and allow final
    verification to report the missing project location accurately.

PHASE 13 ANTI-LOOP / SUCCESS-EVIDENCE RULES:

49. Do not repeat a successful computer action merely because the wording of
    the action description differs from the original user wording.

50. If task history already contains a successful verified window.place for
    the requested target and monitor, treat that placement as complete.

51. Do not repeatedly:
        focus the same window
        place the same window
        reopen the same workspace
        relaunch the same application
        reopen the same browser page
    unless new REAL evidence shows the previous action did not achieve the
    requested state.

52. If a VS Code result proves opened=True and new_window=True and identifies
    a workspace, process, or window, consume that evidence instead of opening
    the same workspace again.

53. If a successful Phase 13 result exposes a concrete process id, window
    handle, title, monitor, or other target identity, prefer that observed
    identity for subsequent targeting instead of rediscovering it.

54. After a requested browser tab/page action succeeds, move on to the next
    unfinished part of the original goal. Do not redo already-completed VS Code
    or window-placement work.

55. Before returning continuation steps, compare each proposed step against
    successful task history. Remove any step whose requested effect is already
    supported by real verified evidence.

56. If all requested real-world effects are already supported by real task
    history:
        complete = true
        next_steps = []

57. Do not consume continuation budget merely to re-verify actions whose
    successful structured results already contain verified=true or equivalent
    direct evidence.

58. When a later action depends on information discovered by the most recent
    successful step, use the exact observed value in the next action. Never
    substitute the original guessed value.

59. Preserve the original user ordering while skipping effects already proven
    complete.

VS CODE WINDOW TARGETING:

60. When a specific VS Code workspace/project is requested, do not use the
    generic target:

        Visual Studio Code

    if multiple VS Code windows may exist.

61. Prefer a project/workspace-specific target from real evidence, such as:

        FinalCollegePortfolio

    when that text appears in the observed visible window title.

62. A verified window.place only satisfies a project-specific placement request
    when the real nested result.window.title corresponds to that requested
    project/workspace.

63. Do not generate targets such as:

        pid:83848

    unless the registered computer_control/window contract explicitly supports
    PID-form targets.

64. An application-launch pid is not necessarily a stable top-level window id.
    VS Code may reuse an existing process.

65. If task history already contains a verified project-specific window.place
    on the requested monitor, do not focus, place, or reopen that workspace
    again.

66. Prefer, in order:

        observed project-specific window title
        observed supported native window identity
        requested project/workspace name appearing in the actual title

    over a generic application title.
""".strip(),

            input=json.dumps(
                payload,
                ensure_ascii=False,
                default=str,
            ),

            text_format=
                ContinuationDecision,
        )
    )


    return (
        response.output_parsed
    )


# ---------------------------------------------------------------------------
# Final Goal Verification
# ---------------------------------------------------------------------------

def verify_goal_completion(
    task: AgentTask,
):
    """
    Performs final strict verification of the original user goal.

    Important lifecycle rule:

        completion.summary becomes task.final_summary in runner.py.

        runner.py then places task.final_summary into AgentResult.message.

        format_agent_result() subsequently delivers that message to the
        user.

    Therefore the verifier must NOT require evidence that its own final
    natural-language response was already delivered before declaring
    the underlying task complete.
    """

    payload = {
        "goal":
            task.goal,

        "task_history":
            build_history(
                task
            ),
    }


    response = (
        client.responses.parse(
            model="gpt-5.5",

            instructions="""
You are P.E.P.P.E.R.'s final Phase 7 completion verifier AND final
task-summary generator.

Determine whether the ORIGINAL USER GOAL is actually complete.

Judge from REAL execution evidence.


CRITICAL ARCHITECTURE RULE

Your `summary` field becomes the final AgentResult message returned by
runner.py.

runner.py delivers that message to the user AFTER this verification.

Therefore:

DO NOT require evidence that the final natural-language summary has
already been delivered to the user.

That would create a circular requirement.

Instead:

1. verify whether all underlying requested work is complete

2. if the work is complete, generate the requested final user-facing
   answer in `summary`

3. set:

       complete = true

4. assign confidence based on the real evidence

The runner will deliver your summary afterward.


USE ONLY REAL EXECUTION EVIDENCE.

Useful evidence includes:

- exit codes
- stdout
- stderr
- filesystem results
- file contents
- Git output
- VS Code open results
- new_window metadata
- application focus results
- managed-browser state
- browser navigation results
- browser search results
- browser page titles
- browser URLs
- browser page text
- browser links
- other deterministic tool results


GENERAL RULES:

1. Never assume a planned action happened.

2. Never mark success merely because all currently planned steps
   finished.

3. Never invent missing evidence.

4. Judge whether the UNDERLYING WORK requested by the original user
   goal has been completed.

5. The final natural-language answer does NOT need to appear earlier
   in task history.

6. YOUR `summary` field is the final natural-language answer that
   runner.py will deliver.

7. If the underlying work is complete:

       complete = true

   and write the appropriate final response in:

       summary

8. If important underlying work is still missing:

       complete = false

   and describe what remains in:

       missing


PROGRAMMING TASKS:

9. For programming tasks:

       exit code 0 is evidence that the program executed successfully.

       expected stdout is evidence that the program produced the
       requested result.

10. For debugging tasks:

        the final successful run must occur AFTER the relevant
        correction.

11. If the user explicitly requested a new VS Code window:

        new_window=True

    in the actual VS Code tool result is sufficient evidence that the
    new-window launch was requested successfully.


PHASE 9 / 10 CONNECTED-SERVICE EVIDENCE:

12. Successful integration_execute results are real external-service
    evidence.

13. When the goal requested multiple connected-service reads, require
    successful evidence for each requested read.

14. Use the actual structured integration results when generating the
    final summary.

15. Do not replace live integration evidence with remembered or assumed
    values.

16. If all requested integration reads succeeded, synthesize them into
    one concise user-facing answer.

PHASE 8 BROWSER EVIDENCE:

12. A successful browser_search_web result proves that a live search
    occurred and that its returned result URLs were observed.

13. Search results alone do NOT prove those sources were read.

14. Successful browser_navigate proves navigation to that page occurred.

15. Successful browser_read_page proves the page content was actually
    retrieved and available for reasoning.

16. If the user requested at least N sources, require evidence that at
    least N distinct relevant sources were actually read.

17. Do not count repeatedly reading a search-results page as multiple
    sources.

18. Do not count repeated reads of the same URL as independent sources
    unless the original user specifically requested revisiting it.

19. If the goal requires comparing sources, require evidence from
    multiple distinct relevant source reads.

20. Never treat model knowledge or remembered webpages as if they were
    retrieved in the current task.

21. Use actual URLs, titles, search results, and retrieved page text
    preserved in task history.


RESEARCH SUMMARY GENERATION:

22. When the evidence proves the requested research work is complete,
    synthesize the findings into `summary`.

23. The summary must answer the original research question rather than
    merely saying:

        "Research completed successfully."

24. Use actual retrieved source text from task history.

25. Compare the sources when comparison was requested.

26. Explain meaningful agreement, differences, and complementary
    information when supported by the evidence.

27. Do not invent claims absent from retrieved evidence.

28. Do not claim that a source was read unless task history contains
    successful browser-read evidence for it.

29. Keep the answer concise when the user requested a concise summary.

30. Include useful source names or URLs when they are supported by the
    real task history.

31. If the user requested research but did NOT ask to modify anything,
    the absence of file mutations is normal and does not make the task
    incomplete.

PHASE 13 DESKTOP / FILESYSTEM COMPLETION:

32. A successful search_filesystem result with one matching path is real
    discovery evidence.

33. A search_filesystem result with count=0 is real evidence that no matching
    path was found in the roots/depth actually searched.

34. Never claim a project/workspace/file was found when matches=[].

35. A successful VS Code result with opened=True and new_window=True is real
    evidence that the requested new VS Code window was launched.

36. A successful computer_control result with verified=True is real
    post-action evidence for the specific requested effect represented by that
    result.

37. A verified window.place on the requested monitor is sufficient evidence of
    that window-placement request unless later evidence contradicts it.

38. Successful browser tab/navigation results are sufficient evidence that the
    corresponding requested pages were opened.

39. Do not require redundant focus/place/reopen actions when task history
    already contains direct structured evidence of completion.

40. If an essential requested project path could not be found after bounded
    real filesystem searches, the overall task is NOT fully complete. Set:
        complete = false
    and accurately describe the missing project location/action in `missing`.
    Do not pretend later dependent actions succeeded.


EXAMPLE

Original goal:

    Research Playwright's current Python browser automation
    capabilities.

    Search the web, open and read at least three useful sources,
    compare navigation, page interaction, and locators, and give me
    a concise research summary.

History proves:

    browser_search_web succeeded

    source 1:
        browser_navigate succeeded
        browser_read_page succeeded

    source 2:
        browser_navigate succeeded
        browser_read_page succeeded

    source 3:
        browser_navigate succeeded
        browser_read_page succeeded


CORRECT:

    complete = true

    confidence = high

    summary = a concise synthesis of what the three retrieved sources
              say about navigation, interaction, and locators


INCORRECT:

    complete = false

    reason:
        "The research summary has not already been delivered."


Why incorrect:

YOUR summary is what runner.py delivers after this verification.


FINAL DECISION

If all required real-world actions and evidence gathering are complete,
mark the task complete and generate the requested final answer.

Only mark the task incomplete when an underlying action, evidence,
source count, verification requirement, or requested real-world
operation is actually missing.
""".strip(),

            input=json.dumps(
                payload,
                ensure_ascii=False,
                default=str,
            ),

            text_format=
                CompletionDecision,
        )
    )


    return (
        response.output_parsed
    )


# ---------------------------------------------------------------------------
# Standalone Test
# ---------------------------------------------------------------------------

if __name__ == "__main__":

    print(
        "P.E.P.P.E.R. Agent Verifier"
    )

    print(
        "------------------------"
    )


    print()


    print(
        "Phase 7 deterministic verification test:"
    )


    sample = {
        "success":
            False,

        "executed":
            True,

        "tool":
            "run_python",

        "risk":
            "low",

        "result": {
            "exit_code":
                1,

            "stdout":
                "",

            "stderr":
                (
                    "SyntaxError: "
                    "expected ':'"
                ),

            "timed_out":
                False,
        },
    }


    print(
        verify_step_result(
            sample
        )
    )


    print()


    print(
        "Phase 8 browser result preservation test:"
    )


    browser_sample = {
        "success":
            True,

        "executed":
            True,

        "tool":
            "browser_search_web",

        "risk":
            "low",

        "result": {
            "query":
                (
                    "Playwright Python "
                    "browser automation"
                ),

            "provider":
                "bing",

            "search_url":
                (
                    "https://www.bing.com/"
                    "search?q=Playwright"
                ),

            "results": [
                {
                    "title":
                        (
                            "Playwright Python "
                            "Official Documentation"
                        ),

                    "url":
                        (
                            "https://"
                            "playwright.dev/python/"
                        ),
                },

                {
                    "title":
                        (
                            "Getting started - "
                            "Library"
                        ),

                    "url":
                        (
                            "https://playwright.dev/"
                            "python/docs/library"
                        ),
                },
            ],
        },
    }


    print(
        json.dumps(
            extract_execution_details(
                browser_sample
            ),
            indent=2,
            ensure_ascii=False,
        )
    )