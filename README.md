# Least-squares adjustment of an unfamiliar geodetic network

A harbor-format benchmark task, authored for the AfterQuery Experts programme as data
annotation for AI evaluation. Task slug `afterquery/geodetic-network-adjust` — **Science / Earth**.

An AI agent gets a container, this brief and nothing else. It works alone for
4 hours. Then a sealed verifier it never sees scores the result `0` or `1`.

## What it asks for

We run a small survey office. For years every job we adjusted looked the same: a handful of stations, distances only, measured round three times, held on two known points. The program we inherited handles those fine and we have never had reason to doubt it.

The full brief is in [`instruction.md`](instruction.md).

| | |
| --- | --- |
| **Deliverable** | `/app/solution` |
| **Agent budget** | 4 hours (14400s) |
| **Expert estimate** | 6 hours |
| **Machine** | 2 CPU, 4096 MB RAM, 0 GPU |
| **Verifier budget** | 3600s |
| **Tags** | `geodesy`, `least-squares`, `surveying`, `numerical-methods`, `statistics` |

## Why it is hard

A least squares network adjustment is undergraduate material and any competent engineer can write one. Forming the observation equations is calculus, and the three published jobs confirm the partials immediately. That is not where this task lives.

<details>
<summary>Full note</summary>

It lives in the difference between an adjustment that runs and an adjustment that is correct on a network it was not designed for, and that difference is four separate pieces of professional practice, none of which the published jobs exercise. First, the weight matrix. Azimuth precisions are quoted in arc seconds and the residual of an azimuth observation is an angle in radians, so a weight built without converting is out by a factor of two hundred thousand and the azimuths carry no influence at all. The published jobs are distance only, so nothing there catches it. Second, conditioning. Forming the normal equations and inverting them squares the condition number of the design matrix, which costs about half the available digits. On a braced five point figure that is invisible. On a fourteen leg traverse it puts the coordinates out by metres. Third, whether the observations determine the answer at all. A job held on one station with distances only does not fix orientation: the solution is a family and not a point. An adjustment that inverts anyway returns one arbitrary member of that family, with residuals that look perfectly reasonable. Recognising rank deficiency and saying so is the correct answer, and it requires understanding what the datum is for. Fourth, and the one that separates a statistician from a programmer, detecting gross errors. How much a network is able to check any given observation varies enormously, and the redundancy number quantifies it. On these jobs the ties to an outlying station carry redundancy numbers near one sixth, so five sixths of an error there is absorbed into that station's coordinates and never appears in its own residual. A test that compares each residual with its own standard deviation - the intuitive test, and the one almost everybody writes - sees a forty eight millimetre blunder as two sigma and passes it. Standardising by the redundancy number puts the same observation at five, where nothing legitimate in the network comes close. The degrees of freedom must also drop as observations are removed, or the variance factor reports the adjustment as better than it is. Measured on this bundle: a straightforward implementation, correct units, numpy's least squares, variance factor over observations minus unknowns, and a residual threshold for gross errors, reproduces all three published jobs exactly and gets six of the ten graded jobs right. Everything it is able to check says it is finished. The correct adjustment gets ten.

</details>

## How it is verified

The verifier runs in its own container. It never imports the submitted module: for each job it runs a small runner as an unprivileged account in a separate process, which loads the submission, adjusts one network and writes the answer to a file. Anything the submission does - exhausting memory, calling sys.exit, replacing library functions - is contained in that process and is recorded as that job having failed, rather than affecting how anything else is graded.

<details>
<summary>Full note</summary>

Each job has its own time limit. The graded jobs are baked into the verifier image and are not in the agent's container. Coordinates are checked against the survey the observations were generated from, so the answer comes from the data rather than from any implementation: every point must be within fifty millimetres, against a correct adjustment that lands within twenty and a straightforward one that is out by metres on the traverses. The variance factor is checked within twenty five per cent of what a correct adjustment produces; it is a scalar and does not depend on the choice of datum. The rejected observations must be exactly the ones that were actually perturbed. That last check is graded as an exact set, so it must not depend on where a solver draws its rejection line. It was verified by running the whole reject-and-adjust loop at critical values of 3.0, 3.29, 3.5, 3.89 and 4.5 on every job: each value rejects exactly the observations that are in error and nothing else. One job originally had a clean observation sitting at 3.29, which made the answer turn on the threshold; it was regenerated from another draw and the check is kept in the build so it cannot come back. Nothing is generated at grading time. The jobs are static files produced from a seeded generator, the reference is deterministic, and it was run repeatedly against the graded set to confirm it gives the same answer every time. Nine of the ten jobs must be correct.

</details>

<details>
<summary>Reference approach (spoiler)</summary>

Build the observation equations for distances and azimuths, scale every row by that observation's own standard deviation in the unit it is quoted in - arc seconds converted to radians for azimuths - and iterate Gauss Newton from the approximate coordinates to convergence. Solve by a QR factorisation of the scaled design matrix rather than by forming and inverting the normal equations. Before trusting a solution, test whether the scaled design matrix has full column rank. Where it does not, the observations do not determine the free points and the answer is that fact. Take redundancy numbers from the hat matrix of the scaled system: with the thin QR factor Q, the redundancy of observation i is one minus the sum of squares of row i of Q. Divide each scaled residual by the square root of its redundancy to standardise it, reject the largest that exceeds the critical value for the one in a thousand level, adjust again without it, and repeat. The variance factor is the sum of squares of the scaled residuals over the degrees of freedom, and the degrees of freedom are the observations still in use minus the unknowns. The reference implementation is about a hundred and sixty lines.

</details>

## Layout

```
instruction.md          the brief - the only thing the agent is told
task.toml               artifacts, timeouts, resources, metadata
environment/            Dockerfile and data for the agent's container
solution/solve.sh       reference solution; scores 1 by construction
tests/                  verifier image, grading logic and ground truth
cheat/                  a deliberate cheating attempt, never executed
```

## Running it

With [harbor](https://github.com/laude-institute/harbor) installed and Docker running:

```bash
uv tool install harbor

harbor run -p . -a oracle -e docker   # reference solution - must score 1
harbor run -p . -a nop    -e docker   # nothing happens    - must score 0
```

Those two runs are the calibration the bundle has to satisfy: the oracle run substitutes
`solution/solve.sh` for the agent and must score `1`, the nop run does nothing and must
score `0`. Anything in between means the verifier is measuring the wrong thing.

## Reading this

`tests/` and `solution/` hold the answers. To try the task honestly, read only
`instruction.md` and `environment/`.

---

Part of a set of 38 tasks indexed at
[afterquery-data-annotation](https://github.com/helexdev1004/afterquery-data-annotation).
