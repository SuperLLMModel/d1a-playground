"""Outcomes for the PR and issue labeler's D1A decisions, posted to the model server's POST /v1/feedback.

    python3 scripts/pr_outcomes.py                       # once; mini.sh runs it every 15 minutes when LABEL_OUTCOMES=1
    python3 scripts/pr_outcomes.py --dry-run             # print what it would post

The CTO bot's labeling job asks D1A three choice questions on every open pull request in John's repositories (change
type, blast radius, severity P0-P4) and applies the answers as labels. It writes one line per D1A call to
/Users/Shared/d1a/labeler-decisions.jsonl: ts, repo, number, head_sha, decision_id, applied_labels. Two kinds of outcome
follow on GitHub:
- reviewer: the review bot (another model) re-decides type and blast radius on every head it reviews and sets its own
  labels. Its type/* and review:blast-* labels after its review of the decision's head are that decision's outcome. It
  decides P0-P4 the same way, in the same pass, for reviews from SEV_REVIEWED_SINCE (2026-10-11 04:49 JST); before that
  its reviews give severity no outcome.
- human: a person (any account that is not a bot) changing a type, blast-radius or severity label after the decision.
  d1a.learning.feedback ranks these above the reviewer's, whatever arrives last.
A decision's window closes at the next labeler call on the same pull request (a new head), so a later head's labels are
never counted against it. Nothing is written to GitHub. Posted outcomes are remembered in --state, so each is sent once.

The same job labels issues (type and severity), as hermes-prbot[bot] too. Those calls are not in the mirror: they are
the decisions in the model server's log (--log) whose state says `kind: github-issue`, and that state names the issue
only by title and author, so each is matched to the one issue with that exact title and author in the labeled
repositories' owners (an issue renamed since, or a title two issues share, is skipped). Issues get no review, so their
outcomes are the human ones, under the same rules, with the window closing at the next call on the same issue.

Polling backs off: a decision is checked on every run in its first day, on every 4th run (hourly) until its third, then
every 24th (6-hourly) until --days. A window that closed more than a day ago was read whole by the runs since, so it is
not polled for a person's labels any more.
"""
import argparse
import json
import os
import subprocess
import sys
import urllib.error
import urllib.parse
import urllib.request
import zlib
from datetime import datetime, timedelta, timezone
from pathlib import Path

FAMILIES = {"type": lambda l: l.startswith("type/"), "blast": lambda l: l.startswith("review:blast-"),
            "sev": lambda l: l in ("P0", "P1", "P2", "P3", "P4")}
REVIEWER_FAMILIES = ("type", "blast")
SEV_REVIEWED_SINCE = "2026-10-10T19:49:17Z"   # from this review on, the review bot also decides P0-P4 in the same pass
                                              # (its github-pr-review skill, changed 2026-10-11 04:49 JST); before it, a P
                                              # that stood through a review was only D1A's own, never the reviewer's answer
REVIEWER = "hermes-prbot[bot]"
SETTLE = timedelta(minutes=2)        # the review bot sets its labels within seconds of posting its review
REVIEW_LEAD = timedelta(minutes=10)  # ... or while writing it
CALL_LEAD = timedelta(seconds=20)    # the labeler writes its labels in the seconds before it logs the call
RUN = timedelta(minutes=15)          # mini.sh runs this every 15 minutes
BACKOFF = ((timedelta(days=1), 1), (timedelta(days=3), 4))   # (decision younger than, poll every Nth run); older: OLD_EVERY
OLD_EVERY = 24
CLOSED = timedelta(days=1)           # a window closed this long ago has been read whole: no person's label can land in it
ISSUE_KIND = "kind: github-issue"    # the issue labeler's state header line


def ts(s):
    return datetime.fromisoformat(s.replace("Z", "+00:00"))


def labels_at(events, when):
    """The pull request's labels at `when`, replayed from its labeled/unlabeled events."""
    labels = set()
    for e in sorted(events, key=lambda e: e["created_at"]):
        if ts(e["created_at"]) > when: break
        if e["event"] == "labeled": labels.add(e["label"])
        elif e["event"] == "unlabeled": labels.discard(e["label"])
    return labels


def family_labels(labels, families):
    """{question: label} for each family with exactly one label."""
    out = {}
    for q in families:
        hits = [l for l in labels if FAMILIES[q](l)]
        if len(hits) == 1: out[q] = hits[0]
    return out


def outcomes(decision, next_ts, events, reviews, call_times=()):
    """[(src, {question: label})] for one decision, given its pull request's label events ({event, label, actor,
    created_at}), reviews ({user, commit_id, submitted_at}) and the times of all labeler calls on it. Empty while the
    reviewer has not reviewed the decision's head and no person has touched its labels.

    The reviewer's answer for a question is the last label of that family it adds around its review of the head (from
    REVIEW_LEAD before to SETTLE after posting it); the labeler's own writes land in the CALL_LEAD before each of its
    logged calls and are not the reviewer's. GitHub records no event when a label that is already there is set again,
    so without an add the reviewer kept the label as it stood SETTLE after its review: D1A's (agreement) or its own
    from an earlier head."""
    t0 = ts(decision["ts"]); end = ts(next_ts) if next_ts else None
    calls = [ts(t) for t in call_times]
    out = []
    review = min((r for r in reviews if r["user"] == REVIEWER and r["commit_id"] == decision["head_sha"] and r.get("submitted_at")),
                 key=lambda r: r["submitted_at"], default=None)
    if review is not None:
        tr = ts(review["submitted_at"]); lo, hi = max(t0, tr - REVIEW_LEAD), tr + SETTLE
        families = REVIEWER_FAMILIES + (("sev",) if tr >= ts(SEV_REVIEWED_SINCE) else ())
        got, standing = {}, family_labels(labels_at(events, hi), families)
        for q in families:
            adds = [e for e in sorted(events, key=lambda e: e["created_at"]) if e["event"] == "labeled" and e["actor"] == REVIEWER
                    and FAMILIES[q](e["label"]) and lo <= ts(e["created_at"]) <= hi
                    and not any(c - CALL_LEAD <= ts(e["created_at"]) <= c + timedelta(seconds=2) for c in calls)]
            if adds: got[q] = adds[-1]["label"]
            elif q in standing: got[q] = standing[q]
        if got: out.append(("reviewer", got))
    human = [e for e in events if not e["actor"].endswith("[bot]") and t0 < ts(e["created_at"]) and (end is None or ts(e["created_at"]) < end)
             and any(f(e["label"]) for f in FAMILIES.values())]
    if human:
        touched = [q for q in FAMILIES if any(FAMILIES[q](e["label"]) for e in human)]
        last = max(ts(e["created_at"]) for e in human)
        got = family_labels(labels_at(events, last), touched)
        if got: out.append(("human", got))
    return out


def gh(path, jq=".[]"):
    r = subprocess.run(["gh", "api", "--paginate", path, "--jq", jq], capture_output=True, text=True, timeout=120)
    if r.returncode != 0: raise RuntimeError(f"gh api {path}: {r.stderr.strip()[:200]}")
    return [json.loads(l) for l in r.stdout.splitlines() if l.strip()]   # one item per line across all pages


def label_events(repo, number):
    return [{"event": e["event"], "label": e["label"]["name"], "actor": (e.get("actor") or {}).get("login", ""), "created_at": e["created_at"]}
            for e in gh(f"repos/{repo}/issues/{number}/events?per_page=100") if e["event"] in ("labeled", "unlabeled")]


def pr_history(repo, number):
    reviews = [{"user": (r.get("user") or {}).get("login", ""), "commit_id": r.get("commit_id"), "submitted_at": r.get("submitted_at")}
               for r in gh(f"repos/{repo}/pulls/{number}/reviews?per_page=100")]
    return label_events(repo, number), reviews


def issue_history(repo, number):
    return label_events(repo, number), []


def issue_calls(log_path):
    """The issue labeler's calls in the model server's decision log: [{ts, decision_id, title, author}]."""
    path = Path(log_path); out = []
    if not path.exists(): return out
    for line in path.read_text(encoding="utf-8").splitlines():
        if ISSUE_KIND not in line: continue                 # most of the log is the PR labeler's and the demos'
        e = json.loads(line); state = e.get("state")
        if e.get("kind") != "decision" or not isinstance(state, str): continue
        if e.get("replay_of"): continue                     # a replay (d1a#233) re-scores a call; it is never a call itself
        head = dict(l.split(": ", 1) for l in state.split("\nbody:", 1)[0].splitlines() if ": " in l)
        if head.get("kind") != ISSUE_KIND.split(": ")[1] or not head.get("title"): continue
        out.append({"ts": datetime.fromtimestamp(e["ts"], timezone.utc).isoformat(), "decision_id": e["id"], "head_sha": None,
                    "title": head["title"], "author": head.get("author", "")})
    return out


def find_issues(owners, since):
    """{(title, author): [(repo, number), ...]} for the issues in `owners`' repositories updated since `since` (a labeler
    call labels its issue, so every call since then is on one of them)."""
    found = {}
    for owner in owners:
        q = urllib.parse.quote(f"user:{owner} is:issue updated:>={since:%Y-%m-%d}")
        for it in gh(f"search/issues?q={q}&per_page=100", ".items[]"):
            found.setdefault((it["title"], (it.get("user") or {}).get("login", "")), []).append((it["repository_url"].split("/repos/", 1)[1], it["number"]))
    return found


def wanted(c, next_ts, done, now, srcs):
    """The sources decision `c` may still get an outcome from: the reviewer until it has one, a person while the window is
    open or closed less than CLOSED ago."""
    return [src for src in srcs if src not in done
            and not (src == "human" and next_ts is not None and now - ts(next_ts) > CLOSED)]


def due(c, now, key):
    """Whether this run polls decision `c` of pull request or issue `key` (BACKOFF by its age). Runs are counted in RUN
    slots of the clock, offset per `key` so the backed-off reads spread over the runs instead of landing on one."""
    age = now - ts(c["ts"])
    every = next((n for younger, n in BACKOFF if age < younger), OLD_EVERY)
    return (int(now.timestamp() // RUN.total_seconds()) + zlib.crc32(key.encode())) % every == 0


def post(url, decision_id, labels, src, group):
    """group: the outcome's unit for d1a.learning.feedback promote's clustered bootstrap, "<repo>#<number>", so a PR's
    re-labelled decisions count as one piece of evidence (d1a#148)."""
    body = json.dumps({"decision_id": decision_id, "labels": labels, "src": src, "group": group}).encode()
    req = urllib.request.Request(url, body, {"Content-Type": "application/json"})
    with urllib.request.urlopen(req, timeout=30) as r: return r.status


def outcomes_enabled(path):
    """outcomes.enabled from the self-learning settings: the last valid file d1a.learning.settings kept, else the file
    itself; a missing, unreadable or broken file leaves collection on, as it was before the settings existed."""
    if not path: return True
    for f in (Path(path).with_name(Path(path).name + ".last-valid.json"), Path(path)):
        try: return json.loads(f.read_text(encoding="utf-8")).get("outcomes", {}).get("enabled", True) is not False
        except (OSError, ValueError, AttributeError): continue
    return True


def summary(calls, posted, now):
    """How often D1A's labels were changed, per family, over the PR labeler's decisions (for the Learning page): decisions
    the reviewer graded and how many of those it changed, and how many a person changed, among decisions whose window is
    closed (the next call on the PR came over CLOSED ago). A rate with nobody looking says nothing, so the counts go with it."""
    by_pr = {}
    for c in sorted(calls, key=lambda c: c["ts"]): by_pr.setdefault((c["repo"], c["number"]), []).append(c)
    out = {q: {"closed": 0, "reviewed": 0, "reviewer_changed": 0, "person_changed": 0} for q in FAMILIES}
    for seq in by_pr.values():
        for i, c in enumerate(seq):
            if i + 1 >= len(seq) or now - ts(seq[i + 1]["ts"]) <= CLOSED or not c.get("decision_id"): continue
            mine = family_labels(set(c.get("applied_labels") or ()), FAMILIES)
            got = posted.get(c["decision_id"], {})
            for q in FAMILIES:
                if q not in mine: continue
                s = out[q]; s["closed"] += 1
                if q in got.get("reviewer", {}):
                    s["reviewed"] += 1; s["reviewer_changed"] += got["reviewer"][q] != mine[q]
                if q in got.get("human", {}) and got["human"][q] != mine[q]: s["person_changed"] += 1
    return out


def main(argv=None, now=None):
    ap = argparse.ArgumentParser(description=__doc__.split("\n")[0])
    ap.add_argument("--decisions", default="/Users/Shared/d1a/labeler-decisions.jsonl")
    ap.add_argument("--log", default=str(Path(__file__).resolve().parents[1] / ".demo/feedback/decisions.jsonl"),
                    help="the model server's decision log (D1A_FEEDBACK_LOG), for the issue labeler's calls")
    ap.add_argument("--feedback", default="http://127.0.0.1:8009/v1/feedback")
    ap.add_argument("--state", default=str(Path(__file__).resolve().parents[1] / ".demo/feedback/outcomes-posted.json"))
    ap.add_argument("--days", type=float, default=14, help="decisions older than this are no longer checked")
    ap.add_argument("--dry-run", action="store_true")
    ap.add_argument("--learning", default=os.environ.get("D1A_LEARNING"), help="the self-learning settings file (d1a.learning.settings); "
                    "outcomes.enabled false there stops this run")
    a = ap.parse_args(argv)
    if not outcomes_enabled(a.learning):
        print("outcomes.enabled is false in the self-learning settings: no outcomes collected"); return 0
    calls = [json.loads(l) for l in Path(a.decisions).read_text(encoding="utf-8").splitlines() if l.strip()]
    state_path = Path(a.state); posted = json.loads(state_path.read_text()) if state_path.exists() else {}
    now = now or datetime.now(timezone.utc); since = now - timedelta(days=a.days)
    items = {}   # (repo, number) -> (history, sources, calls oldest first)
    for c in sorted(calls, key=lambda c: c["ts"]): items.setdefault((c["repo"], c["number"]), (pr_history, ("reviewer", "human"), []))[2].append(c)
    asked = [c for c in issue_calls(a.log) if ts(c["ts"]) >= since]
    if asked:
        try: found = find_issues(sorted({c["repo"].split("/")[0] for c in calls}), since)
        except (RuntimeError, subprocess.TimeoutExpired, json.JSONDecodeError) as e:
            print(f"skip the issue labeler's calls: {e}", file=sys.stderr); found = {}
        for c in sorted(asked, key=lambda c: c["ts"]):
            hits = found.get((c["title"], c["author"]), [])
            if len(hits) == 1: items.setdefault(hits[0], (issue_history, ("human",), []))[2].append(c)
    sent = 0
    for (repo, number), (history, srcs, seq) in items.items():
        todo = [(c, seq[i + 1]["ts"] if i + 1 < len(seq) else None) for i, c in enumerate(seq)]
        todo = [(c, next_ts) for c, next_ts in todo if c.get("decision_id") and ts(c["ts"]) >= since
                and wanted(c, next_ts, posted.get(c["decision_id"], {}), now, srcs)]
        if not any(due(c, now, f"{repo}#{number}") for c, _ in todo): continue
        try: events, reviews = history(repo, number)
        except (RuntimeError, subprocess.TimeoutExpired, json.JSONDecodeError) as e:
            print(f"skip {repo}#{number}: {e}", file=sys.stderr); continue
        for c, next_ts in todo:
            done = posted.setdefault(c["decision_id"], {})
            for src, labels in outcomes(c, next_ts, events, reviews, [x["ts"] for x in seq]):
                if done.get(src) == labels: continue
                print(f"{repo}#{number} {(c['head_sha'] or 'issue')[:8]} {src}: {labels}")
                if not a.dry_run:
                    try: post(a.feedback, c["decision_id"], labels, src, f"{repo}#{number}")
                    except (urllib.error.URLError, OSError) as e:
                        print(f"feedback not reachable ({e}); stopping", file=sys.stderr); return 1
                    done[src] = labels; sent += 1
    if not a.dry_run:
        state_path.parent.mkdir(parents=True, exist_ok=True); state_path.write_text(json.dumps(posted, indent=1) + "\n")
        (state_path.parent / "outcomes-summary.json").write_text(json.dumps({"ts": now.isoformat(), "families": summary(calls, posted, now)}, indent=1) + "\n")
    print(f"{sent} outcomes posted")
    return 0


if __name__ == "__main__":
    sys.exit(main())
