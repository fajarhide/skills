---
name: ui-receipts
description: Use when asked to audit, review, critique, QA or improve the UI or UX of a web app, site, page or flow, or before claiming a UI change is finished, even if the request is casual ("cek halaman ini", "why does this screen feel off", "is this usable", "make it look better", "looks AI generated", "review my dashboard", "how would you redesign this"). Covers usability, accessibility, responsive layout, visual polish and interaction states, on a live URL or a local project.
---

# UI Receipts

Audit what the page does, not what the code suggests. Reading source finds plenty, and most of it is guesses about behaviour nobody watched. A finding here carries a receipt: something a reader can check without trusting you.

## Set up

1. **Get it running.** A URL, or start the project from its own docs and scripts. Use synthetic data and a throwaway instance when you can, since screenshots travel.
2. **On production or anyone's real data, look and do not write:** no submits, deletes or sends. Say which checks that ruled out.
3. **Fix the frame in one line each:** who is using this and in what hurry (default: a distracted first-timer on a phone), the page type, and the one job each page exists for. Project conventions and any design system outrank your taste.
4. **Behind a login with no test account:** audit what you can reach and report the rest as not tested.

## Measure

```sh
python scripts/probe.py OUT_DIR URL [URL ...] [--cookie name=value] [--label before]
```

It saves a mobile and a desktop screenshot of each page, and reports console errors, failed requests, contrast, tap targets, unnamed controls, unlabeled inputs, broken images, dead links, clipped text, page overflow and leaked text such as `undefined`. Look at the screenshots yourself. A number is a lead until you have seen it in context. A login page in the screenshot or 401s in `failedRequests` mean the session did not take, so nothing was measured. Requires Playwright (`pip install playwright && playwright install chromium`).

## Walk it

Before opening the source, drive the primary path in a real browser and write down each action and what changed. Then force what a happy path never shows, on each primary action. Start each forced case from a fresh page load, because a timer or request left over from the last attempt will land in this one and put a false cause in your receipt. Read the result again after 5 s, since a slow response looks exactly like no response.

| Force | Look for |
| --- | --- |
| Act, then read the page at 0.5 s and 5 s, then reload | Feedback at once, a real state change, and that it stuck |
| Double-click submit | A duplicate in the result |
| Make it fail: bad input, or route the request to a 500 | Input kept, the error names the fix and stays, retry works |
| Slow the network | Loading state, disabled control, no layout jump |
| Filter to nothing, delete the last row, new account | A real empty state with a next step |
| 200 character string, emoji, 1 and 1000 rows | Wrapping, pluralising, layout holding |
| Destroy something | Confirm naming the object, or undo |
| Refresh, back button, open a deep link | State and filters survive, 404 is handled |
| Tab through the page, then Escape in any dialog | Order, visible focus, focus returns |

Every row ends up either performed or named under Not tested with its reason. Capture console errors after interactions too, since `probe.py` only sees page load. Read the source only afterwards, to find the line to change.

## Judge per page type

- **Landing:** in five seconds, what is it, who for, why. One primary action, and it goes somewhere. Proof is real or absent.
- **Dashboard:** the one decision this screen serves, and whether hierarchy serves it. Deciding columns first, numbers right-aligned, status distinguishable, periods stated.
- **Form:** persistent labels, correct input types and autocomplete, error beside its field, input survives failure, submit label states the outcome.
- **Store:** full price before the last step, stock and variant states, payment failure recovery, no manufactured urgency.
- **Docs:** search, where am I, copyable code, working anchors, readable line length.

Judge in this order: can the job be done, is it understood, is the hierarchy right, then does it look good. Polish worth raising names its fix: tokens over raw colours, one light source for shadows, inner radius equal to outer minus padding, spacing on a scale, a hover state you can actually see.

**The generic AI look** is one judgment, made after the job works. Ask whether the page could belong to any other product if the logo were swapped. Signs: purple or blue gradients and glow on everything, frosted glass on every surface, the hero, three icon cards, testimonials and FAQ sequence whatever the content, numbers and quotes with nothing behind them, copy that never says what the product does. Report them as one finding tagged `judgment`, name what the page's own content should replace them with, and rank it below anything that stops the job.

A plain page that says what it does is not this, and neither is a bold look that plainly comes from the product. Use the swap test on both before reporting.

## Not findings

Disabled controls and `aria-hidden` decoration are exempt from contrast rules. A code block or wide table scrolling inside its own container is fine, only the page overflowing is a defect. A target under 44 px passes if it is at least 24 px and not crowded. Drop these rather than reporting them with a caveat, because a list padded with near-misses buries what matters.

## Report

Write exactly this:

```
# UI receipts: <what was audited>
Tested: <pages, viewports, actions performed>. Frame: <who, job>.

## Findings
1. [Blocker] <what the user hits, in one line>
   Receipt: <observed | measured | judgment>: <the action and result, the number, or the screenshot path>
   Fix: <smallest change, with file:line when you have source>
...

## Works, do not break
<a few things that held up under the forcing>

## Not tested
<what you could not check, and why>
```

Severity: **Blocker**, the job cannot be done or data is lost or duplicated. **Major**, the user is misled, takes a wrong path, or hits an accessibility failure, the test being "would they contact support". **Minor**, it works with extra effort. **Polish**, no effect on the job.

Rank by what it costs the user, not by what is easiest to spot. If most findings came out Major, re-rank, because a list where everything is Major tells the reader nothing about what to do first. State only what you tested: "the data is gone" needs the reload that shows it. Merge repeats of one cause into one finding with a count. Stop at 10 and put a count of what you left out at the end. Tag a finding `observed` only if you performed the action in this session, `measured` only with a number from a tool, and `judgment` otherwise, and let `judgment` be the minority. A finding that could be pasted into a report about any other app gets cut. No overall score, since a number implies precision the audit does not have.

## When a redesign is asked for

If the request asks how to redesign, rethink or go further, finish the report above first, then read `references/redesign.md` and add its section. Keep the two apart: thinking about redesign during the audit costs findings.

## When building

Before calling a UI change done, run `probe.py` on the changed pages, force the rows that apply to what changed, and take before and after screenshots from the same view. Capture the before first, since it is gone once the change lands: run the probe with `--label before`, then `--label after` to the same folder, so neither overwrites the other and their numbers can be compared. For a state behind an interaction, run the same steps on the same data on both versions. Report in the same receipt form, with the pair side by side in a table.

For visual improvement, change the hierarchy and spacing before adding decoration, keep to the project's existing look, and re-run the probe, because a prettier page can still lose contrast or break on a phone. Measurements prove nothing broke. Whether it looks better is the owner's call, so show both screenshots.
