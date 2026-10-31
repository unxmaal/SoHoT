"""Which repos share a crowd with the people this project already relies on. #58.

The mechanism behind every "similar repositories" service: things starred by the
same people are probably about the same thing. We compute it here rather than
calling one, because the hosted versions rate-limit, gate results behind
starring them, and die -- one found in the same prior-art search is already
archived and marked end-of-service.

THE CROWD IS PEOPLE, NOT STARGAZERS, AND NOT BY CHOICE. `repos/<r>/stargazers`
returns 404 to an authenticated token and 401 to none, for every repo, so who
starred a thing cannot be read. What can be read is who WROTE it and who they
follow, which turns out to be the better seed anyway: contributors to mflux and
mlx-audio are a stronger signal than whoever bookmarked them.

NORMALISATION IS THE WHOLE JOB. Ranking by how many of the crowd starred
something just ranks by popularity and returns whatever huge repo everyone
stars. Dividing by the union fixes it, and `control()` proves that on real data
rather than assuming it, because a metric without a negative control is noise.
"""
from __future__ import annotations

import math
import time
from collections import Counter
from datetime import datetime, timezone
from dataclasses import dataclass, field

from harness import github

#: Repos this project actually runs. Their contributors are the starting crowd,
#: so the seed follows what is installed rather than a hand-kept list of people.
DEFAULT_SEEDS = ("ml-explore/mlx", "ml-explore/mlx-lm", "Blaizzy/mlx-audio",
                 "mflux-community/mflux")
#: Below this, a score rests on one or two people and means nothing.
MIN_SHARED = 3
#: How many people could plausibly have starred any of this. NOT a free
#: constant: it sets how much evidence counts against how much enrichment, and
#: the control only passes between 1e6 and 2e7. Measured, see control().
POPULATION = 5_000_000
#: Score halves after this long without a push. A live niche project beats a
#: dead one with the same overlap, because the question is what to try NOW.
HALF_LIFE_DAYS = 365.0
#: A repo this large is starred by everyone and tells us nothing. One in the
#: top means popularity has leaked back into the ranking. Structural rather
#: than a list of names, because the first hand-written list missed every repo
#: that actually leaked (openclaw, opencode, hermes-agent) and named repos this
#: crowd does not star.
POPULAR_STARS = 100_000
#: Pages of PER_PAGE stars read per crowd member, newest first; one page reads 13% of the crowd's stars (#764).
STAR_PAGES = 1


@dataclass
class Neighbor:
    repo: str
    score: float
    shared: int
    crowd: int
    stars: int = 0
    language: str = ""
    topics: list[str] = field(default_factory=list)
    archived: bool = False
    pushed: str = ""
    description: str = ""


def enrichment(shared: int, crowd_size: int, stars: int,
               population: float = POPULATION) -> float:
    """How much more this crowd stars a repo than the world does, times the
    evidence for saying so.

        shared * log( (shared / crowd) / (stars / population) )

    BOTH HALVES ARE NECESSARY AND THIS WAS MEASURED, not reasoned. Ranking on
    `shared` alone returns whatever giant everyone stars: five repos over
    100k stars led the first real run. Ranking on the ratio alone -- plain
    Jaccard, lift, or a Wilson bound, all three tried -- inverts the error and
    returns 33-star repos that four people happen to share, putting nothing
    this project runs in the top ten. Multiplying the log ratio by the count
    is the standard fix and the only one of six that passed both directions.

    `population` decides the balance. The control passes between 1e6 and 2e7
    and fails outside it, so the default sits in the middle of that window
    rather than at its edge.
    """
    if crowd_size <= 0 or stars <= 0 or shared <= 0:
        return 0.0
    shared = min(shared, crowd_size)
    ratio = (shared / crowd_size) / (stars / population)
    return shared * math.log(ratio) if ratio > 1 else 0.0


def recency(pushed: str, now: float | None = None,
            half_life: float = HALF_LIFE_DAYS) -> float:
    """Weight from how long ago the repo was last pushed, halving per half-life.

    Unknown or unparseable dates weigh 1.0 rather than 0: a missing field is
    not evidence of abandonment, and scoring it as such would silently drop
    every repo whose metadata came back thin.
    """
    if not pushed:
        return 1.0
    try:
        when = datetime.strptime(pushed[:10], "%Y-%m-%d").replace(
            tzinfo=timezone.utc).timestamp()
    except ValueError:
        return 1.0
    now = time.time() if now is None else now
    days = max(0.0, (now - when) / 86400.0)
    return 0.5 ** (days / half_life)


def cohort(seeds=DEFAULT_SEEDS, client: github.Client | None = None, *,
           per_repo: int = 12, follow: bool = True, hops: int = 2,
           limit: int = 250, min_degree: int = 2,
           per_hop: int | None = None) -> list[str]:
    """People to ask, grown from the repos this project runs.

    Contributors first, then who they follow. Each further hop reaches the
    people THEY read, which is where a technique appears before it reaches a
    subreddit.

    EXPANSION IS TOWARD CONSENSUS, NOT OUTWARD, and that is the whole design.
    A naive second hop is 250 people following a hundred each: up to 25,000
    candidates, almost all of them a random walk away from the subject. Hop one
    already drags in an unrelated neuroscience cluster because one contributor
    follows academics, and a second hop multiplies it.

    So every candidate carries an IN-DEGREE: how many people already in the
    crowd follow them. That separates someone the community reads from someone
    one person happens to follow. Hop one is ordered by it; every hop after
    REQUIRES it, so a distant person joins only on several existing members'
    agreement. Same idea as the repo ranking in #58, applied to people.

    Deterministic throughout, so two sweeps are comparable.

    TWO HOPS IS THE DEFAULT, AT THE SAME CROWD SIZE. Measured on 250 people:

      1 hop    45 core + 205 hop-one              separates, 5/6, 0 leaks
      2 hops   45 core + 102 hop-one + 102 hop-two  separates, 5/6, 0 leaks
                                                    and 12 repos one hop
                                                    never surfaced

    Size is held constant, so this compares hop DEPTH rather than crowd size.
    Depth is free; SIZE is what breaks the metric. A 450-person crowd fails its
    control at every POPULATION from 5e6 to 1e8, because doubling the crowd
    raises `shared` for popular repos faster than the enrichment term divides
    it out. The metric is not scale-invariant in crowd size, so widen by DEPTH,
    never by raising the cap. See issue #75.
    """
    client = client or github.Client()
    people: list[str] = []
    seen: set[str] = set()
    over = {"limit": 0, "per_repo": 0, "min_degree": 0}

    def add(login) -> bool:
        if login and login not in seen and not login.endswith("[bot]") and len(people) >= limit:
            over["limit"] += 1
        if (login and login not in seen and not login.endswith("[bot]")
                and len(people) < limit):
            seen.add(login)
            people.append(login)
            return True
        return False

    core: list[str] = []
    for repo in seeds:
        try:
            listed = client.contributors(repo)
        except github.GitHubError:
            continue
        found = listed[:per_repo]
        over["per_repo"] += len(listed) - len(found)
        for login in found:
            add(login)
            core.append(login)
    if not follow:
        _cohort_cuts(over, len(people), limit, per_repo, min_degree)
        return people[:limit]

    # EACH HOP GETS ITS OWN BUDGET, and without one `hops` is unreachable.
    # 45 contributors follow enough people to fill ANY cap tried -- 250 and 450
    # both came back 100% hop-one -- so a second hop can never start while hop
    # one is allowed to spend the whole allowance. Measured, not reasoned: the
    # first attempt at this ran three configurations and executed hop two in
    # none of them.
    hops = max(1, hops)
    budget = per_hop if per_hop else max(1, (limit - len(people)) // hops)
    frontier = list(dict.fromkeys(core))
    for hop in range(hops):
        degree: Counter = Counter()
        for login in frontier:
            try:
                for other in client.following(login):
                    if other not in seen:
                        degree[other] += 1
            except github.GitHubError:
                continue
        # Ties broken by name so the order does not depend on dict iteration.
        ranked = sorted(degree.items(), key=lambda kv: (-kv[1], kv[0]))
        floor = 1 if hop == 0 else min_degree
        added = []
        for name, d in ranked:
            if len(added) >= budget or len(people) >= limit:
                break
            over["min_degree"] += d < floor
            if d >= floor and add(name):
                added.append(name)
        if not added:
            break
        frontier = added
    else:
        if len(people) < limit:
            from harness import cuts
            cuts.cut("hops", "a crowd still growing at its last hop", value=hops, kept=len(people))
    _cohort_cuts(over, len(people), limit, per_repo, min_degree)
    return people[:limit]


def _cohort_cuts(over: dict, size: int, limit: int, per_repo: int, min_degree: int) -> None:
    """One cut per crowd for each of its caps that left someone out."""
    from harness import cuts
    if over["limit"]:
        cuts.cut("crowd_limit", "people left out of a full crowd", value=limit, kept=size, dropped=over["limit"])
    if over["per_repo"]:
        cuts.cut("per_repo", "contributors past the per-repo take", value=per_repo, dropped=over["per_repo"])
    if over["min_degree"]:
        cuts.cut("min_degree", "people too few of the crowd follow", value=min_degree, dropped=over["min_degree"])


def stars_of(client: github.Client, login: str, pages: int) -> tuple[list[str], bool, bool]:
    """(repos newest first over up to `pages` pages, the cap cut them short, a deeper page could not be read)."""
    out: list[str] = []
    for page in range(1, pages + 1):
        try:
            got = client.starred(login, pages=(page,))
        except github.GitHubError:
            if page == 1:
                raise
            # A deeper page lost to the budget or the network keeps what was read. #764.
            return out, False, True
        out += got
        if len(got) < github.PER_PAGE:
            return out, False, False
    return out, True, False


def crowd(people, client: github.Client | None = None, *, pages: int | None = None) -> tuple[Counter, int]:
    """What the crowd starred, and how many of them actually answered."""
    from harness import cuts
    client = client or github.Client()
    pages = STAR_PAGES if pages is None else pages
    counts: Counter = Counter()
    asked = short = 0
    for login in people:
        try:
            starred, capped, _ = stars_of(client, login, pages)
        except github.GitHubError:
            continue
        asked += 1
        short += capped
        counts.update(set(starred))
    if short:
        cuts.cut("crowd_star_pages", f"{short} of {asked} crowd members starred more than {pages} page(s); "
                 "their older stars were not read", value=pages, kept=asked - short, dropped=short)
    return counts, asked


def why(repo: str, people, client: github.Client, *, depths=(1, 2, 3, 5, 10),
        min_shared: int = MIN_SHARED) -> dict:
    """Where `repo` stands in the crowd at each page depth, by star position only, never by member. #764."""
    deepest = max(depths)
    asked = unread = 0
    positions = []
    for login in people:
        try:
            starred, _, lost = stars_of(client, login, deepest)
        except github.GitHubError:
            continue
        asked += 1
        unread += lost
        if repo in starred:
            positions.append(starred.index(repo) + 1)
    positions.sort()
    by_depth = {d: sum(p <= d * github.PER_PAGE for p in positions) for d in depths}
    reached = next((d for d in sorted(depths) if by_depth[d] >= min_shared), None)
    sweep = sum(p <= STAR_PAGES * github.PER_PAGE for p in positions)
    if sweep >= min_shared:
        verdict = f"the crowd reaches it at the sweep's {STAR_PAGES} page(s): {sweep} of {asked} starred it"
    elif reached is not None:
        verdict = (f"the crowd misses it at the sweep's {STAR_PAGES} page(s) ({sweep} of {asked}) "
                   f"and reaches it at {reached} pages ({by_depth[reached]} of {asked})")
    else:
        verdict = (f"falls out at the crowd: {by_depth[deepest]} of {asked} starred it within {deepest} pages, "
                   f"and a repo needs {min_shared}")
    return {"repo": repo, "crowd": asked, "positions": positions, "by_depth": by_depth,
            "unread": unread, "sweep_pages": STAR_PAGES, "sweep_count": sweep,
            "min_shared": min_shared, "reached_at": reached, "verdict": verdict}


def neighbors(people=None, client: github.Client | None = None, *,
              seeds=DEFAULT_SEEDS, min_shared: int = MIN_SHARED,
              top: int = 25, exclude=(), keep_archived: bool = False,
              pages: int | None = None) -> list[Neighbor]:
    """Repos concentrated in this crowd, best first."""
    client = client or github.Client()
    people = list(people) if people is not None else cohort(seeds, client)
    counts, asked = crowd(people, client, pages=pages)
    skip = set(exclude)
    out = []
    for n, (repo, shared) in enumerate(counts.most_common()):
        if shared < min_shared:
            from harness import cuts
            cuts.cut("min_shared", "repos too few of the crowd starred", value=min_shared, kept=n,
                     dropped=len(counts) - n)
            break
        if repo in skip:
            continue
        try:
            meta = client.repo(repo)
        except github.GitHubError:
            continue
        # An archived repo is finished by definition, so it cannot be a thing
        # to try next however well it scores. A 2020 physics course ranked
        # sixth on the first real run.
        if bool(meta.get("archived")) and not keep_archived:
            continue
        stars = int(meta.get("stargazers_count") or 0)
        pushed = (meta.get("pushed_at") or "")[:10]
        out.append(Neighbor(
            repo=repo, shared=shared, crowd=asked,
            score=enrichment(shared, asked, stars) * recency(pushed),
            stars=stars,
            language=meta.get("language") or "",
            topics=list(meta.get("topics") or []),
            archived=bool(meta.get("archived")),
            pushed=pushed,
            description=(meta.get("description") or "")[:200]))
    out.sort(key=lambda n: n.score, reverse=True)
    return out[:top]


def control(expect, people=None, client: github.Client | None = None, *,
            top: int = 10, popular: int = POPULAR_STARS, **kw) -> dict:
    """Rank a known crowd and report whether the ranking is real.

    Two directions, because either alone passes on a broken metric:

    POSITIVE -- things already known to belong here have to rank. The tools this
    project runs are the honest test set: they were chosen before the metric
    existed.
    NEGATIVE -- nothing enormous may rank, because a repo with 300k stars is
    starred by every crowd and carries no information about this one. Measured
    by size rather than by a list of names: the hand-written list passed a
    ranking whose top five were all repos over 100k stars, because it did not
    happen to name those five.

    `raw_top` is the ranking by shared count alone, kept so the difference
    between the two orderings is visible rather than asserted.

    ONE HONEST LIMIT: `POPULATION` was chosen by running this control, so a
    pass now confirms the metric has not regressed rather than proving it
    generalises. A fresh crowd is the real test.
    """
    client = client or github.Client()
    people = list(people) if people is not None else cohort(client=client)
    found = neighbors(people, client, top=top, **kw)
    counts, asked = crowd(people, client, pages=kw.get("pages"))
    names = [n.repo for n in found]
    hits = [e for e in expect if e in names]
    leaks = [(n.repo, n.stars) for n in found if n.stars > popular]
    return {"crowd": asked, "top": names, "expected_found": hits,
            "missing": [e for e in expect if e not in names],
            "popularity_leaks": leaks,
            "raw_top": [r for r, _ in counts.most_common(top)],
            "separates": bool(hits) and not leaks}
