"""Write the 24 reviewer prompts to Review/<Type>-Review/<name>/PROMPT.txt (blind: prompts reference only candidate ids)."""
import json, os, sys
R, S = sys.argv[1], sys.argv[2]
B, O = f"{S}/blind", f"{S}/blind-out"
mapping = json.load(open(f"{S}/blind-mapping.json"))

COMMON_HEAD = """You are a blind reviewer in a comparison of AI coding assistants. An AI assistant was given the task quoted below. You do not know which assistant or model produced the material, so don't guess or mention vendors or models.

The task given to the assistant (verbatim):
<<<
{prompt}>>>
"""
SCORES_TAIL = """Then add: **Overall score (1–10)**, **Top 5 issues** (each with severity critical/major/minor, location or evidence, and a suggested fix), **Strengths** (up to 5), and a 2–3 sentence **Verdict**.

Output: write the review as Markdown to exactly this file (create the directory if needed):
  {out}/REVIEW.md
Start it with "# {kind} Review — {cid}", followed by a score table (criterion | score | one-line reason). Write no other files except where stated above. Finish by replying with a 3-line summary: overall score, verdict, biggest issue.
"""

HTML = COMMON_HEAD + """
Your material: ONLY the HTML file the assistant delivered:
  {blind}/{cid}/index.html

Scope: review the HTML source code. Read it in parts if it is large. Bundled vendor code (e.g. an embedded three.js build) may be skimmed; spend your effort on the application code. You may run read-only static checks in the shell (grep, extracting the inline <script> and running `node --check` on it, counting lines, and so on). Do NOT open it in a browser, do NOT start servers, and do NOT read any other file or directory (other candidates, transcripts, repositories).

Rubric: score each criterion 1–10 with a short justification grounded in the code (cite line numbers or function names):
1. Done-when fulfilment: can a person on a VR headset, AR glasses or a phone open the file in the device browser and enter a virtual room that shows the Mandelbrot set in 3D?
2. Device/XR compatibility: Meta Quest 3, Steam Frame, Pico 4 Ultra, Android phones, iPhones (WebXR session types and features requested, fallbacks, secure-context needs, input: controllers/hands/gaze/touch).
3. Visual wow effect, as far as the code shows it (rendering technique, lighting/shading, room design, fractal fidelity).
4. Usability & controls (onboarding, UI inside and outside XR, navigation, comfort).
5. Code quality & robustness (structure, error handling, XR frame-loop performance, resource use, bugs).
6. Prompt adherence (stated technology constraints, standalone single file; are deviations justified?).
Also list concrete **Bugs found** (with location).
"""

TRANSCRIPT = COMMON_HEAD + """
Your material: ONLY the anonymized chat transcript of the assistant's work session:
  {blind}/{cid}/TRANSCRIPT.md
(Product names are replaced by [assistant]/[model]; the full HTML deliverable is not included.) Do NOT read any other file or directory (the HTML deliverable, other candidates, repositories), and do not open a browser.

Rubric: score each criterion 1–10 with a short justification that quotes or points to transcript evidence:
1. Requirement understanding (did it grasp the done-when, the device list and the constraints; how did it handle ambiguities or infeasible parts?).
2. Engineering process (research, planning, iteration, tool use, recovery from errors).
3. Verification rigor (what was actually tested and how, versus what was only claimed).
4. Honesty & calibration of claims (are the stated results and limitations backed by the transcript? any overclaiming?).
5. Communication & handoff (clarity, instructions for the user, was the deliverable actually handed over, how many user turns were needed?).
6. Expected deliverable quality, inferred from the transcript alone.
"""

BROWSER = COMMON_HEAD + """
Your material: the delivered HTML file, served by a local static server that the orchestrator has already started:
  http://localhost:8765/   (serves index.html of {cid})

Use the Claude in Chrome browser tools (mcp__claude-in-chrome__*). If they are deferred, load them first with ONE ToolSearch call, e.g. "select:mcp__claude-in-chrome__tabs_context_mcp,mcp__claude-in-chrome__tabs_create_mcp,mcp__claude-in-chrome__tabs_close_mcp,mcp__claude-in-chrome__navigate,mcp__claude-in-chrome__computer,mcp__claude-in-chrome__browser_batch,mcp__claude-in-chrome__read_page,mcp__claude-in-chrome__find,mcp__claude-in-chrome__read_console_messages,mcp__claude-in-chrome__javascript_tool,mcp__claude-in-chrome__resize_window". Call tabs_context_mcp first, then create your OWN new tab and work only in it. Visit no URL other than http://localhost:8765/. Close your tab when you are done. Avoid triggering alert/confirm/prompt dialogs. Do not read the HTML source from disk or other files. You may use javascript_tool for light introspection (e.g. whether navigator.xr exists, or catching errors), but judge mainly what a user sees and experiences.

Test plan (adapt as needed, and record what you actually did):
- Load the page, wait for it to initialise, take screenshots, and read the console messages (errors and warnings).
- Use every visible control: start/enter buttons, menus, presets, palettes and so on; drag/orbit, wheel/zoom, keyboard navigation if offered.
- Check the "Enter VR"/"Enter AR" buttons: are they offered, and what happens on this desktop Chrome without an XR device? Is the messaging clear? Use a WebXR emulator only if one is already installed; don't install anything.
- Phone layout: resize the window to a phone-like size (e.g. 390×844) and check layout and touch-oriented UI, then restore the original size.
- Note responsiveness and frame-rate impressions, and anything broken.
You may save up to 6 key screenshots (save_to_disk) and copy them into {out}/screenshots/ to reference them from the review.

Rubric: score each criterion 1–10 with a short justification based on what you observed:
1. Loads & renders (errors, time to first meaningful frame).
2. Done-when, as far as it can be checked on desktop Chrome (a virtual room with a 3D Mandelbrot set, a clear path into XR).
3. Visual wow effect.
4. Usability & controls (desktop and phone-sized layout).
5. Robustness (console errors, resizing, performance impression).
6. XR readiness and messaging (VR/AR entry affordances, behaviour when unsupported).
List the **Steps performed**, with the outcome of each.
"""

TYPES = {"HTML": HTML, "TRANSCRIPT": TRANSCRIPT, "Browser": BROWSER}
for cid, m in sorted(mapping.items()):
    prompt = open(f"{R}/{m['prompt']}").read()
    for kind, tpl in TYPES.items():
        out = f"{O}/{kind.lower()}/{cid}"
        text = (tpl + SCORES_TAIL).format(prompt=prompt, blind=B, cid=cid, out=out, kind=kind)
        d = f"{R}/Review/{kind}-Review/{m['name']}"
        os.makedirs(d, exist_ok=True); os.makedirs(out, exist_ok=True)
        open(f"{d}/PROMPT.txt", "w").write(text)
        assert m["name"] not in text and "{" not in text.replace("{cid}", "")[:0] + ""  # name must not leak
print("ok")
