# Drafters on the engine's own token stream

The capture case's 8192-token prompt and the 1024 tokens a real engine run
produced from it -- `lever84-20261020/auto12`. Every earlier drafter comparison
used this repository's source files as a stand-in.

| drafter | width | accepted | rounds | TPOT ms |
|---|---|---|---|---|
| lookup | 12 | 4.900 | 209 | 10.98 |
| automaton | 12 | 5.565 | 184 | 9.67 |
| tree | 12 | 6.059 | 169 | 8.88 |
| lookup | 24 | 5.418 | 189 | 11.39 |
| automaton | 24 | 6.564 | 156 | 9.40 |
| tree | 24 | 7.585 | 135 | 8.14 |
| lookup | 32 | 5.689 | 180 | 11.78 |
| automaton | 32 | 6.872 | 149 | 9.75 |
| tree | 32 | 8.258 | 124 | 8.11 |

TPOT from the round model's measured terms, 45.88 ms plus 0.66 a unit of
captured width.

## Three things this settles

**The offline figure is conservative but ordered.** `lookup` at width 12 gives
4.900 accepted here against the engine's measured 5.441, so this corpus
understates acceptance by about ten percent -- the stream is the engine's own
output, but the drafter sees it without the engine's warm context. The ordering
is what matters and it is stable across widths.

**The automaton is worth 13 to 21 percent over lookup**, which is the drafter
the project's best result actually used. At width 12 that projects 9.3794 ms to
about 8.3.

**The tree beats the automaton on the real stream**, by 9 percent at width 12
and 20 at width 32. This overturns today's conclusion from the repository
corpus, where the two matched to within half a percent at equal budget. Source
files are not the workload: an agentic coding model's output repeats its input
with edits, and a tree's branches cover the edit where a single path does not.

## And the optimum width

24 to 32 on this stream, TPOT 8.14 and 8.11 -- flat between them, and matching
the repository corpus's optimum near 24 despite disagreeing about the drafters.
The engine's own sweep chose 12, which was right for `lookup`: its acceptance
saturates at 5.4 where the tree's is still climbing at 8.3.
