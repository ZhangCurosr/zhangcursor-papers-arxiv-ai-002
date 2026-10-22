# Solving Go under Positional Superko: Sound Proof Transfer and New Board Values

Sami Kharma   
Zuse Institute Berlin   
Berlin, Germany   
kharma@zib.de   
Florian Schintke   
Zuse Institute Berlin   
Berlin, Germany   
schintke@zib.de

## Abstract

Positional superko (PSK) forbids recreating any earlier whole-board position. It is part of the Chinese rules as written and of the rules used in computer Go. Yet almost all solved Go boards were computed under a simpler basic-ko rule set. PSK makes solving hard: legality depends on the whole game history, and this breaks the three tools that make solving tractable, namely transposition tables (the graph-history interaction problem), static lifeand-death recognition, and safe move pruning. We present Sanko, a parallel depth-first proof-number solver that restores all three soundly. Its core is a cheap proof-transfer theorem: a stored proof stays valid on a new path unless a board that the proof’s winner must create has already occurred. Sanko proves 5×5 Go in 16 minutes with six threads, where the previous state of the art needed 5.25 hours with six processes, and in about a minute and a half on one 192-thread machine. It also establishes the first PSK values of twenty-three further boards, eleven of which were unsolved under any rules. Superko changes game-theoretic values: 4×7, a full-board win under basic ko, is worth only 12 points under PSK, and we pinpoint the move at which the previously published optimal line fails. Unlike earlier solutions of empty Go boards, we release the solver source together with the command line and outcome of every run behind our values and measurements, so that all reported values can be reproduced.

## 1 Introduction

Solving games exactly is a long-standing benchmark for search algorithms. Checkers has been solved [Schaeffer et al., 2007], and so have Hex on small boards [Henderson et al., 2009] and many smaller games. For Go, computer proofs exist for many boards up to 30 intersections [van der Werf et al., 2003; van der Werf and Winands, 2009]. However, these classic Go results were computed under a specialpurpose rule set designed to make a position’s value independent of how it was reached. Specifically, they use the basic ko rule, let a pass lift a ko ban, end a game at a repeated position and score the cycle by its passes [van der Werf, 2004; van der Werf and Winands, 2009].

Superko, the rule that forbids recreating earlier wholeboard positions, is part of everyday play. The Chinese rules forbid recreating any earlier whole-board position [Chinese Weiqi Association, 1988], the American and New Zealand rules forbid it only with the same player to move (situational superko) [AGA Rules Committee, 1991; New Zealand Go Society, 2017], and computer Go commonly uses the Chinese form, for example in the Tromp–Taylor rules [Tromp, 1995]. Solving under superko is hard, however, and it has received far less attention than basic ko. We approach solving Go under said positional superko (PSK), which forbids recreating any earlier whole-board position. Legality of a move therefore depends on the entire history of the game. This rule breaks three pillars of game solving:

• Transposition tables. Reusing the result of a position reached along another path becomes unsound. This is the graph-history interaction (GHI) problem [Campbell, 1985; Kishimoto and Muller, 2004¨ ].

• Static knowledge. Benson-style life and territory recognition [Benson, 1976] assumes that the owner can always capture intruders. Under PSK those captures may be illegal.

• Pruning. Moves that never help under basic ko, such as filling one’s own eye, can become decisive tempo moves [van der Werf, 2004].

The cost of losing these advantages is very large. Even with situational superko, the MIGOS solver needed 1.1 hours for 4×4, against 3.3 seconds with basic ko [van der Werf et al., 2003]. Now, Sanko solves 4×4 so fast that it no longer suits for performance comparisons. The first PSK solution of 5×5, by Expected Work Search (EWS), took 5.25 hours with six processes [Randall et al., 2024], a board we solve in minutes. Beyond 5×5, no board with at least two rows had been solved under PSK. It was also open whether the basic-ko values carry over.

This paper shows that PSK solving can be both sound and fast. Our contributions are:

• A proof-transfer theorem for PSK (Section 3). Using the observation that only boards created by a proof’s winner can invalidate it, five small attributes per stored proof allow for soundness-preserving proof reuse under PSK. Proof-transfer under this theorem cuts search effort by a factor of about 6,000 compared to reusing results only in the identical superko game.

![](images/f8b59bfffb7ccdaf82288a706e6054e6e8a74a30caf73f95048f4bb7241a08f8.jpg)  
Figure 1: Values under positional superko of all boards with four to 30 points and at most 18 columns. The value is Black’s winning margin with optimal play. Besides $2 \times 2 ,$ , whose superko value was known [van der Werf et $a l .$ , 2003], 4×7 (framed) is the one board whose value differs from its basic-ko value. The smaller boards agree with earlier results. Linear boards from 1×19 to 1×30 remain open.

• Static knowledge that is sound under PSK (Section 4). We introduce pure-eye analysis, a variant of Benson’s algorithm that is sound under PSK play-out, prove the two conditions it needs beyond Benson’s classic analysis, and give acyclic local region games.

• Sanko, a parallel solver (Section 5). It runs df-pn on shared lock-free tables, and checks proof identity on 128 bits. We show that the probability of a hash collision is magnitudes below that of hardware errors, even on our largest runs. We also verify against an oracle with no static knowledge.

• New results (Section 6). 5×5 takes 16 minutes on six threads, 20× faster than EWS. We give the first PSK values of 4×5, 3×7, 3×8, 3×9, 4×6, 4×7, 5×6, 3×10, $2 \times 1 0 { - } 2 { \times } 1 5$ and 1×10–1×18. Of these, $3 { \times } 1 0 , 2 { \times } 1 2 { - }$ 2×15 and $1 { \times } 1 3 { - } 1 { \times } 1 8$ were unsolved under any rules. A quick overview shows Figure 1.

• A rule-dependent value (Section 7). 4×7 is a fullboard win under basic ko (value 28), but is worth only 12 points under PSK. We locate the move at which the published optimal line [van der Werf and Winands, 2009] fails.

• An open, reproducible artifact (Section 9). Earlier solutions of empty Go boards were published without their solvers, so none of them can be reproduced independently. We release the solver source and the exact command line and outcome of every solver run behind our values and measurements.<sup>1</sup>

## 2 Background

We use the Chinese rules as written [Chinese Weiqi Association, 1988], whose repetition ban is the positional superko of EWS [Randall et al., 2024]. Black moves first on an $R { \times } C$ board. A move is a pass or the placement of a stone. Opponent chains without liberties are captured, and suicide is illegal. The ban on repeating a whole-board position is $p o -$ sitional superko: a stone move may not recreate any board that occurred earlier in the game. Passes are always legal. Two consecutive passes end the game, which is scored by area: each player counts their stones plus the empty regions bordered only by their stones. Where human players agree on dead stones, we play the game out, so stones that remain on the board count as alive. Under area scoring, playing in ones own territory costs neither side anything, so this does not change any value. The komi k (a half-integer) is added to White’s score. The value v of a board is Black’s margin under optimal play. We establish it with two proofs: a Black win at komi $\begin{array} { r } { v { \mathrm { ~ - ~ } } \frac { 1 } { 2 } } \end{array}$ and a White win at $\begin{array} { r } { v + \frac { 1 } { 2 } . } \end{array}$ . A full-board win $( v = R \cdot C )$ needs only the first.

MIGOS [van der Werf et al., 2003; van der Werf and Winands, 2009; van der Werf, 2004] formalizes the Chinese rules, but replaces their ban on repeated positions by a basic ko rule and special conventions for cycles, passes and dead stones.

A node is a position together with the history that leads to it. Under PSK, two nodes with the same position but different histories may have different values. Proof-number search [Allis et al., 1994] treats the game as an AND/OR graph of nodes. Each node carries a proof number ϕ and a disproof number δ, which estimate the effort to prove or disprove it. Depth-first proof-number search (df-pn) [Nagai, 2002] explores the graph with thresholds, with the $1 + \varepsilon { \mathrm { ~ r e } } -$ finement of [Pawlewicz and Lew, 2007]. A transposition table (TT) stores proven and unproven nodes, and its hit rate is what makes large proofs feasible. An expansion is one call of df-pn’s recursive procedure on a node. The call generates the legal moves and classifies each child as terminal, static leaf, stored proof, or unproven with initial proof numbers. It stops early at a child that already proves the node, and then repeatedly descends into the most promising child until the node’s thresholds are exceeded. Each call counts once, including later calls on a node that was already expanded. We measure search effort in expansions. The revisit factor of a search is the number of expansions divided by the number of distinct nodes expanded. EWS reports the number of nodes in its best-first search tree, and MIGOS counts every node visit of its iterative-deepening search [van der Werf and Winands, 2009], so the three counts are related but not identical.

Superko has three effects.

• Transpositions are unsound. Two paths to the same board can have different sets of earlier boards. A ko recapture, or any capture that recreates an earlier board, is legal on one path and illegal on the other, so the two nodes can have different values. Storing ‘won’ for one path and reusing it on the other is unsound: this is the GHI problem [Campbell, 1985; Breuker et al., 2001; Kishimoto and Muller, 2004 ¨ ]. The safe alternative, keying the table on the position and the set of earlier boards, almost eliminates reuse (Section 6.3). This is why superko slowed MIGOS down by more than 1,000× on 4×4 [van der Werf et al., 2003; Kishimoto and Muller,¨ 2004].

• Static knowledge from basic ko is unsound. Benson’s unconditional life [Benson, 1976] certifies groups that the opponent can never capture. Claiming their territory however, means the owner must actually capture intruders. Section 4 shows that superko can forbid those captures. In addition, a static verdict taken just after the owner’s own pass is wrong, because the opponent can pass and end the game immediately at the current position.

• Pruning becomes incomplete. Under PSK, any boardchanging move can make a later capture legal, even filling one’s own eye (a move that is never useful under basic ko). Section 4 gives an example where this is the only winning move.

## 3 Sound Proof Transfer under Superko

Kishimoto and Muller¨ [Kishimoto and Muller, 2004; Kishi-¨ moto and Muller, 2005¨ ] solve GHI in general: they re-check, or simulate [Kawano, 1996], a stored proof on the new path, at a cost that grows with the proof. We instead give a sufficient condition for reuse under PSK that can be checked in time linear in the path length, independent of the proof’s size.

A history H is the sequence of positions from the empty board to the current node N. We also write H for its set of boards. A proof T that player w wins from N is a finite tree. At w-nodes it picks one move, and at opponent nodes it contains every legal move. Its leaves are terminal wins for w or certified static wins (Section 4). We say line for a sequence of consecutive moves from a given position, so a path in the game tree.

## Definition 1. For a proof T of a win for w:

$B _ { w } ( T )$ is the set of boards created by w’s stone moves $i n T$

$X ( T )$ is the set of boards $b \in H$ that made some opponent move in T illegal (exclusion targets).

• terr(T) is the union of the territories certified at $T ' _ { s }$ static leaves.

$\mathrm { c a p } _ { w } ( H )$ is the set of points at which a w stone was captured along H.

Theorem 1 (Transfer). Let T prove that w winsfrom N under history H. Then T also proves that w wins from N under any history H<sup>′</sup> that satisfies

(i) $B _ { w } ( T ) \cap H ^ { \prime } = \varnothing ,$

(ii) $\begin{array} { r } { X ( T ) \subseteq H ^ { \prime } , } \end{array}$

(iii) $\mathrm { c a p } _ { w } ( H ^ { \prime } ) \cap \mathrm { t e r r } ( T ) = \emptyset .$

Proofsketch. Induction over $T$ (full proof in Appendix A). The line inside $T$ is the same under H and $H ^ { \dot { \prime } } .$ Only the prefix differs.

• A stone move of w creates a board $b \in B _ { w } ( T )$ . That board was not in H or on the line, because the move was legal. By (i) it is not in $H ^ { \prime }$ either, so the move stays legal.

![](images/dd40e2c261a5bc07aa899104915eb14e75ef7ceed73a136f8bab9af6a5004711.jpg)  
Figure 2: A proof T stored at N along history H and reused along $H ^ { \top }$ . Both histories start at the empty board ∅. A board that occurs both on $H ^ { \prime }$ and in T (dashed) makes T invalid only if the winner creates it in T, because that winner move becomes illegal. If the loser creates it, the loser merely loses an option.

• An opponent move that is legal under $H ^ { \prime }$ but was illegal under H must recreate a board of $H \backslash H ^ { \prime }$ . Such a board would lie in X(T), which (ii) rules out. So the opponent gains no new options. Opponent moves that become illegal only remove options.

• Terminal scores do not depend on the history. Static leaves need their own history condition (Lemma 1), and (iii) supplies it on the new prefix.

The theorem is asymmetric, in that only the winner’s boards matter. If the loser would recreate a board of $H ^ { \prime }$ , that merely removes a losing option, and the proof survives (Figure 2). Proofs are stored in negamax form, each for its own winner, so the theorem covers wins of both players.

The exact sets are too large to store. Each proof entry instead carries conservative summaries that compose bottomup. A won node takes its winning child’s attributes plus the board its winning move creates, and a lost node takes the join of all children:

• a 64-bit Bloom filter [Bloom, 1970] of the canonical hashes of $B _ { w } ( T )$

• the stones common to all boards of $B _ { w } ( T )$ , and their minimum stone count,

• the territory bitboard,

• a flag that marks proofs with an exclusion target.

A strict ancestor board $a \in H ^ { \prime }$ can lie in $B _ { w } ( T )$ only if it hits the Bloom filter, contains the common stones, and has at least the minimum number of stones. If any of these fails, (i) holds for a (Algorithm 1). Condition (iii) is checked exactly against the capture bitboard of the current path. Condition (ii) holds because every proof with an exclusion target is stored path-specifically and is never transferred, so a transferred proof has $X ( T ) = \emptyset$ . Path-specific proofs live under a twin key, the position key combined with a non-linear hash of the set of earlier boards, and are reused only on the identical board with an identical set, which the solver recognizes by two independent such hashes. Note that an XOR of Zobrist keys [Zobrist, 1990] is not a sound set identifier. Base entries are written once, and a proof without an exclusion target that finds its base slot taken by another path’s proof goes to one of two alternate slots, where any path can reuse it through Algorithm 1. Canonical hashing makes the test invariant under the board’s symmetries. Sibling moves are merged only under symmetries that map every board on the path onto itself.

Algorithm 1 Accepting a stored proof at node N on path $H ^ { \prime }$   
Require: entry e: winner $w ,$ Bloom filter $\beta ,$ common stones   
$C ,$ , minimum stone count m, territory τ, path-specific flag   
(set whenever X(T) ̸= ∅)   
1: if e is path-specific then   
2: return false {condition (ii)}   
3: end if   
4: if $\mathrm { c a p } _ { w } ( H ^ { \prime } ) \cap \tau \neq \emptyset$ then   
5: return false {condition (iii)}   
6: end if   
7: for each strict ancestor board a on $H ^ { \prime }$ do   
8: if $C \subseteq a$ and $| a | \geq m$ and hash $\mathbf { \boldsymbol { \mathbf { \rho } } } _ { \mathrm { \lambda } } ( a ) \in \beta$ then   
9: return false {condition (i)}   
10: end if   
11: end for   
12: return true {(i) to (iii) hold}

## 4 Static Knowledge under Superko

Leaves that end the search before the game ends are essential: on 5×5, kill-all proofs would otherwise run through every mop-up capture. Under PSK and play-out scoring they need two corrections.

Let w be a player and o the opponent. A region is a maximal connected set of non-w points. A region E is a pure eye of a w-chain K if every point of $E ,$ empty or occupied by $^ { O , }$ is adjacent to $K$ . Let ${ \bar { X } } ^ { * }$ be the largest set of w-chains in which each chain has two pure eyes bordered only by chains of $X ^ { * }$ . Let $T ^ { * }$ be the union of the regions bordered only by $X ^ { * }$ in which every point is adjacent to $X ^ { \ast }$ . We call $X ^ { * }$ and $T ^ { * }$ the pure-eye analysis. It follows Benson’s fixpoint [Benson, 1976] but replaces ‘vital’ by ‘pure’, and together with the conditions of Lemma 1 it is sound under PSK play-out.

Lemma 1 (Static leaves under PSK). Suppose (C1) no w stone was ever captured on a point of T<sup>∗</sup> during the history, and (C2) the last move was not a pass by w with o to move. Then w can enforce a final area of at least $\left| X ^ { * } \right| + \left| T ^ { * } \right|$ |.

Proofsketch. The winner follows the strategy σ: if an o stone lies in $T ^ { * }$ , play on a liberty of an o-chain there, and otherwise pass. Every chain containing $X ^ { * }$ stones keeps two pure eyes, each with an empty point, and so is never captured. Pureness guarantees that the points freed by a capture still touch the chain. Every σ stone joins such a chain, so w’s stones in $T ^ { * }$ are permanent. Hence a σ move cannot repeat a board of the continuation. It could repeat an earlier board only if a w stone had stood on that point and been captured, which (C1) forbids. (C2) prevents o from ending the game by passing before w has moved. □

Both conditions go beyond Benson’s original analysis.

• Condition (C2) cannot be dropped. In Figure 3a, Black has just passed, White is to move, and the komi is 4.5.

![](images/44ff8ba7ad3465a2b0fb5e261b66505bf2b29356a2fda86c86a7a0fc5075d81b.jpg)  
(a)

![](images/30a26a10d91f0d7f4b463255589cc76d5034737957971b0c37b527f48b649860.jpg)  
(b)

![](images/4cee1af6d171f05f853c9fcf83e143f0b959d52aa7cffc49b1e2bc0d8de3f80d.jpg)  
(c)  
Figure 3: (a) Condition (C2): Black has just passed and White passes back. (b) A region that is vital in Benson’s classic sense, since its empty points all touch the Black chain, but no pure eye, since the White stones do not. (c) The same region after Black captures the intruders: point a touches no Black stone.

Benson’s analysis gives Black all nine points, yet White passes, the area count is 3–3, and the komi decides for White.

• The pure eye condition strengthens Benson’s classic one, which only requires every empty point to be adjacent to the chain. The top-left region of Figure 3b passes the classic test but is not a pure eye. Capturing the intruders frees point a (Figure 3c), which touches no Black stone. The region is then not even vital: White can reenter at a with two liberties, and the argument above fails. In a pure eye every freed point still touches the chain.

When Black’s $X ^ { * }$ chains enclose every remaining region and no region has more than 14 points, the solver evaluates each region as a local game. White moves first and may pass. Black plays either anchored moves (adjacent to the walls or to earlier anchored stones), or interior moves in regions of at most eight points. In the local game, any White capture of a Black stone counts as a White win. Black’s stones therefore only accumulate, so the local game is acyclic, independent of the history, and memoizable. Composing the local strategies yields a whole-board win under the conditions of Lemma 1. Superko only removes White options. Black’s new stones are permanent, so they cannot repeat a board of the local game, and the possibility of a black move in the local game repeating a board in the history is ruled out by (C1).

A proof for w stays valid if w’s own options are removed. We therefore optionally skip the moves of the side being proven that fill its own single-point eyes or play inside its own certified territory. In all our runs the first such move at each node is kept as a tempo move, which is still sound, because a result against that side is reported as unknown. We effectively prune the search tree by removing moves that are extremely unlikely to help the side being proven, but sacrifice completeness of the proof.

Under PSK this pruning is sound but not complete. On $1 \times 1 2$ at komi 1.5, neither pruned search proves its side, and only the unpruned search proves Black’s win. Black’s move 31 in one such proof fills its own eye, and White captures three stones next move:

![](images/de912d21220c1747579343393e319819c5727a1f473c19975f2ea1e29efc6417.jpg)

The sacrifice changes which boards can recur later, and Black’s win needs it. We therefore fall back to unpruned runs when both pruned runs fail.

![](images/40169cd87bd8b229a53289b670cc60a0121dbaaa578b7fcfc87066118e0dc0d0.jpg)  
Figure 4: Expansions per benchmark position with the learned prior against a prior based on the opponent’s eye space (112 positions, serial, node limit 10<sup>8</sup>). Points below the diagonal favour the learned prior, which needs 2.8× fewer expansions in the geometric mean.

## 5 The Solver and Its Validation

Sanko is negamax df-pn with the 1+ε rule (ε = 0.3), 64-bit proof numbers, a pass shortcut, and canonical keys under the board’s symmetries.

New nodes get their initial proof and disproof numbers from a logistic model of the probability p that the side to move wins. Its 14 features are a constant, the side to move, the komi, and cheap bitboard counts: stones, eye points, chains in atari, chains with two liberties and liberties of each side, and White’s points that touch no Black stone. Point counts are divided by the number of points and chain counts by four. The numbers are $1 + S ( - \ln p )$ and $1 + S ( - \ln ( 1 - p ) )$ with $S \ : = \ : 6 4$ , so a likely win starts with a small proof number. The model learns from the solver itself: a solve can write a sample of the proofs it stores, each a position labelled with its winner, and Newton’s method fits the weights. The builtin weights come from solves of 3×3, 4×4, 3×7, 3×8, 4×5, 1×10, 1×11, 2×10 and 2×11 near their values. A model fitted to the other boards predicts each of them with a log loss of 0.13 on average, against 0.70 for a constant model. The prior only orders the search. The initial numbers lie in $[ 1 , 2 ^ { 4 0 } ]$ and are never 0 or infinite. Nodes are decided only by proofs, so any weights give the same values. Against a prior based on White’s eye space, it cuts expansions by a factor of 2.8 and time by 1.9 on our benchmark positions. Of the benchmark suites, only the 4×5 suite comes from a training board. Without it, the factor over the eye-space prior is 2.6 instead of 2.8, and 2.9 instead of 3.2 on the ablation suites (Table 3). We visualize the effect of the learned prior in Figure 4.

As in [Kaneko, 2010], all threads run df-pn from the root over one shared table, which in Sanko is lock-free. A busy counter per node, kept in a shared array indexed by the node’s key, acts as a virtual loss, like Kaneko’s virtual proof numbers, and spreads the threads apart. A thread accepts a proof only through its own classification, which re-applies Algorithm 1 or, for a path-specific proof, the twin identity test, or through its own recursive search. Values read from other threads only steer the search. Parallel soundness therefore reduces to serial soundness.

On boards of up to 30 points the position key is exact, because its Zobrist keys for the points, the side to move and the pass state are linearly independent over GF(2). Each alternate slot XORs the position key with a fixed constant. Neither the constant, nor the resulting XOR, is an XOR combination of the Zobrist keys, so the base and alternate keys of different positions must be distinct. A proof is reused outside its own superko game only through Algorithm 1, which uses exact board keys, stone sets and capture sets, so no such reuse depends on a hash being collision-free. We mitigate the risk that path-specific keys add a non-linear path signature and can collide, and concurrent writes can mix two entries in one slot: Proof entries match on an independent second 64-bit hash, sealed with a non-linear hash of the entry’s other words. Therefore, a mixed entry fails the check and counts as a miss. For a path-specific entry the second hash is also combined with a second, independent path signature, so the entry is reused only if both signatures agree. Section 8.1 bounds the probability that hashing ever produces a wrong result at many magnitudes below the probability of hardware errors.

We validate the solver with several types of checks, each targeting a different failure mode:

• a differential selftest solves random positions, with real superko histories and random komi, both with the full solver and with an oracle that reuses results only in the identical superko game and, on the large boards and in two of the three small-board modes, uses no static knowledge.

• threshold probes set the komi exactly at the point where a static rule declares a winner, then compare with the oracle.

• large-board selftests use long random prefixes on the precise boards and table layouts of our claims (4×7, $5 \times 6 , 3 { \times } 1 0 , 2 { \times } 1 4 , . . . )$

• independent re-solves split a proof into its branches and solve each in a fresh process.

• a brute-force check solves all prefixes of random games on one shared table and compares them with a minimax search whose memo is keyed on the exact game state, including the set of earlier boards.

• fault injection makes the solver accept wrong proofs on purpose and counts how often that changes a result (Section 8.1).

Sanko passes 10,808 small-board selftests, 31,622 threshold probes, 28,033 large-board selftests and 7,538 brute-force comparisons without a single mismatch (Table 11).

## 6 Experiments

All runs use one machine with two AMD EPYC 9475F CPUs (192 threads, 1.5 TB, tables of up to 0.97 TB) and a profileguided build of the released solver, which runs the same search as the plain build. Times are wall-clock and include table setup. Effort is given in expansions (Section 2).

<table><tr><td>Solver CPU, parallelism Time</td></tr><tr><td>Nodes 5×5, komi 24.5 (Black wins)</td></tr><tr><td>EWS i7-10510U, 6 proc. 5.25 h 2.61 B</td></tr><tr><td>Sanko EPYC 9475F, 6 threads 15.7 min 1.38 B</td></tr><tr><td>Sanko EPYC 9475F, 14 threads 7.4 min 1.54B</td></tr><tr><td>Sanko EPYC 9475F, 192 threads 1.3–1.6 min 2.0–2.5 B</td></tr><tr><td>4×4, komi 1.5 (Black wins), one thread</td></tr><tr><td>EWS i7-10510U 13.6s 0.50M Sanko EPYC 9475F 0.23 s 0.086M</td></tr></table>

Table 1: Comparison with EWS [Randall et al., 2024], the previous PSK state of the art. Nodes are expansions for Sanko and bestfirst tree nodes for EWS. EWS split 5×5 into six processes, one per White reply to C3. We solve the position after C3 in a single search.

![](images/5b3793b72e12c4df6f013e706845fa485c96e3820355a34d841c19d6504d6c30.jpg)  
Figure 5: 3×10 has value 8. (a) Black’s D2 (1) and the next 21 moves of the principal variation of Black’s proof at komi 7.5. It continues 23 K3 (capturing 8 and 10), 24 J2, 25 F1 (capturing 2 and 6). (b) The position after move 25, where the static analysis proves Black’s win. Whenever it is White’s turn, we follow the reply whose refutation took the most work, so it shows how Black wins rather than the optimal margin. White wins at komi 8.5 against every first move of Black.

## 6.1 Speed on 5×5

Table 1 compares Sanko with EWS on its own benchmark. With six threads, 5×5 takes 16 minutes, against 5.25 hours for EWS with six processes, a factor of 20.1. Measured in thread-hours, it is 1.6 against 31.5. Part of this is hardware: our six threads each have a server core, while EWS ran six processes on the four cores of a laptop i7-10510U. The gap is far larger than the hardware difference, though: on one thread, Sanko solves 4×4 58 times faster (0.23 against 13.6 seconds). On one 192-thread machine the proof takes about a minute and a half (1.3, 1.5, 1.6 and 1.6 minutes in four runs), of which about 10 seconds are table setup. MIGOS solves 5×5 in 14 minutes, but under basic ko [van der Werf and Winands, 2009]. Under full situational superko, MIGOS was more than 1,000× slower already on 4×4 [van der Werf et al., 2003].

## 6.2 New Values

Table 2 lists the boards we solved. Every value except that of 5×5 is new under PSK. On the boards that MIGOS also solved, the PSK value equals the basic-ko value, except on 2×2, whose superko value MIGOS already reported [van der Werf et al., 2003], and on 4×7 (Section 7). Each of our proofs takes seconds to hours on a single machine, where MIGOS needed hours to days of single-CPU time: 1.86 days for 3×8, 4.3 days for 3×9, and 10.6 days for 4×7 [van der Werf and Winands, 2009]. 2×12–2×15 and 1×13–1×18 had no published value under any rules, since MIGOS stopped at 2×11 and 1×12 [van der Werf and Winands, 2009]. The linear values from 1×9 to 1×15 repeat 0, 1, 2, 2 with period four, but 1×16 is worth 1, not 2 (Table 9). 5×6, the largest board MI-GOS solved, has the PSK value 4, as under basic ko. 3×10, for which MIGOS proved only the lower bound 6 and two months of search found no upper bound [van der Werf and Winands, 2009], has the PSK value 8, reached by Black’s first move D2 (Figure 5). White wins at komi 8.5 against every first move of Black (Table 7).

<table><tr><td rowspan="3">Board PSK</td><td rowspan="3"></td><td>Basic ko</td><td colspan="3">Black proof</td><td colspan="3">White proof</td></tr><tr><td></td><td>komi</td><td>exp.</td><td>time</td><td>komi</td><td>exp.</td><td>time</td></tr><tr><td>1×10</td><td>1</td><td>1</td><td>0.5</td><td>25k</td><td>10s</td><td>1.5</td><td>0.12M</td><td>10s</td></tr><tr><td> $1 \times 1 1$ </td><td>2</td><td>2</td><td>1.5</td><td>35k</td><td>10s</td><td>2.5</td><td>0.34M</td><td>10s</td></tr><tr><td> $1 \times 1 2$ </td><td>2</td><td>2</td><td>1.5</td><td>1.5 B</td><td>30s</td><td>2.5</td><td>26M</td><td>10s</td></tr><tr><td> $1 \times 1 3$ </td><td>0</td><td>一</td><td>-0.5</td><td>0.41 M</td><td>10s</td><td>0.5</td><td>88M</td><td>11 s</td></tr><tr><td> $1 \times 1 4$ </td><td>1</td><td>一</td><td>0.5</td><td>4.1M</td><td>10s</td><td>1.5</td><td>0.57B</td><td>17 s</td></tr><tr><td> $1 \times 1 5$ </td><td>2</td><td></td><td>1.5</td><td>0.28 B</td><td>14s</td><td>2.5</td><td>4.4B</td><td>66s</td></tr><tr><td> $1 \times 1 6$ </td><td>1</td><td></td><td>0.5</td><td>0.79 B</td><td>22s</td><td>1.5</td><td>475 B</td><td>1.7h</td></tr><tr><td> $1 \times 1 7$ </td><td>0</td><td>一</td><td>-0.5</td><td>7.0B</td><td>102s</td><td></td><td>0.5 4,757 B</td><td>17.4h</td></tr><tr><td> $1 \times 1 8$ </td><td>1</td><td>一</td><td>0.5</td><td>108 B</td><td>25 min</td><td></td><td>1.5 7,748 B</td><td>28.3 h</td></tr><tr><td> $2 \times 1 0$ </td><td>4</td><td>4</td><td>3.5</td><td>48M</td><td>11 s</td><td>4.5</td><td>19M</td><td>11 s</td></tr><tr><td> $2 \times 1 1$ </td><td>6</td><td>6</td><td>5.5</td><td>0.40 B</td><td>20s</td><td>6.5</td><td>54M</td><td>11 s</td></tr><tr><td> $2 \times 1 2$ </td><td>4</td><td>一</td><td>3.5</td><td>1.9B</td><td>64s</td><td>4.5</td><td>1.8 B</td><td>63 s</td></tr><tr><td> $2 \times 1 3$ </td><td>6</td><td>一</td><td>5.5</td><td>13 B</td><td>7min</td><td>6.5</td><td>6.0 B</td><td>4 min</td></tr><tr><td> $2 \times 1 4$ </td><td>4</td><td>一</td><td>3.5</td><td>126B</td><td>1.4h</td><td>4.5</td><td>146 B</td><td>1.5 h</td></tr><tr><td> $2 \times 1 5$ </td><td>6</td><td>一</td><td>5.5</td><td>1,223 B</td><td>14.3 h</td><td>6.5</td><td>468 B</td><td>5.6h</td></tr><tr><td>3×7</td><td>21</td><td>21</td><td>20.5</td><td>0.11 B</td><td>13s</td><td></td><td>(full board)</td><td></td></tr><tr><td>3×8</td><td>24</td><td>24</td><td>23.5</td><td>1.8B</td><td>58s</td><td></td><td>(full board)</td><td></td></tr><tr><td>3×9</td><td>5</td><td>5</td><td>4.5</td><td>9.7B</td><td>6 min</td><td>5.5</td><td>5.2 B</td><td>3 min</td></tr><tr><td>3×10</td><td>8</td><td>≥6</td><td>7.5</td><td>243 B</td><td>2.7h</td><td>8.5</td><td>97B</td><td>1.2h*</td></tr><tr><td>4×5</td><td>20</td><td>20</td><td>19.5</td><td>42M</td><td>11 s</td><td></td><td>(full board)</td><td></td></tr><tr><td>4×6</td><td>8</td><td>8</td><td>7.5</td><td>1.6B</td><td>61 s</td><td>8.5</td><td>0.52 B</td><td>26 s</td></tr><tr><td> $4 \times 7 ^ { \dagger }$ </td><td>12</td><td>28</td><td>11.5</td><td>66 B</td><td>44 min</td><td>12.5</td><td>16B</td><td>11 min</td></tr><tr><td>5×5</td><td>25</td><td></td><td></td><td>2.0B</td><td></td><td></td><td></td><td></td></tr><tr><td>5×6</td><td>4</td><td>25 4</td><td>24.5 3.5</td><td>316B</td><td>77 s 3.9h</td><td></td><td>(full board) 4.51,235 B14.8 h*</td><td></td></tr></table>

Table 2: PSK values established in this work, with the basic-ko values of MIGOS [van der Werf and Winands, 2009]. Each proof is given by its komi, expansions and time on one 192-thread machine (1×n: unpruned, <sup>†</sup>White proof unpruned). The Black proofs of 5×5 and 5×6 start after Black’s C3, that of 3×10 after Black’s D2. <sup>∗</sup>One part per symmetry-unique first move of Black, each in a fresh process (times added, Tables 6 and 7 in Appendix B). A full-board value needs no White proof: Black owns every point, and no result can exceed the board size. Bold values are new under PSK. A dash marks boards that were unsolved under any rules. Rows with ≥ or ≤ give the bound proved so far. Smaller boards (1×4–1×9, 3×3, 4×4) are consistent with the literature [Weninger and Hayward, 2017; Randall et al., 2024; van der Werf et al., 2003].

Figure 6 plots proof sizes against board area. On boards with at least two rows, effort grows by roughly a factor of ten for every two to three additional points. Linear boards are far more expensive per point: 1×12 needs almost as many expansions as 2×12. Their play is dominated by capture– recapture sequences, so almost every proof is path-specific. On the unpruned 1×12 proof the revisit factor is about 9,400: 1.53 billion expansions of only 163,000 distinct nodes.

![](images/e6253f0245601fe359397240136823240f3324f35dd08efaeabeef03a7f3a11b.jpg)

Figure 6: Proof sizes in expansions versus board area. <sup>†</sup>At 30 points, the 3×n and 5×n marks include one White-pruned subproblem per symmetry-unique first stone move of Black. The 1×n proofs are unpruned.
<table><tr><td>Variant (problem)</td><td>Effect</td></tr><tr><td>No proof transfer (3×7)</td><td>5,952×</td></tr><tr><td>No region solver</td><td> $2 . 3 3 \times ( 1 . 0 2 – 4 . 6 1 )$ </td></tr><tr><td>No interior region moves</td><td>1.70× (1.00–2.60)</td></tr><tr><td>Eye-space prior instead of the learned prior 3.19× (2.15–4.43) No prior (uniform initial numbers)</td><td></td></tr><tr><td>1 thread vs. 192 threads (3×9)</td><td>4.72× (3.40–6.02)</td></tr><tr><td></td><td>42× time</td></tr><tr><td>No virtual loss, 192 threads (3×9)</td><td>55× time</td></tr></table>

Table 3: Ablations. Each component is removed from the full solver. Effects are expansion ratios, except for the thread rows, which compare time. The four knowledge rows give the geometric mean over the 64 positions of five suites (4×5, two 5×5 suites after C3, and 4×6 for each side), with the range of the suite means in parentheses. Suites are seeded sets of random positions (12–16 positions, serial, deterministic, node limit 10<sup>8</sup>). The transfer row compares two 192- thread solves of 3×7.

## 6.3 Ablations

Table 3 measures each component and shows that proof transfer dominates. Without it, results are reused only in the identical superko game, the only safe option under PSK without Theorem 1. 3×7 then needs 664 billion expansions instead of 112 million, and the value is unchanged. On these five suites the learned prior saves a factor of 4.7 over uniform initial numbers and 3.2 over the eye-space prior. The region solver contributes a factor of 2.3, most of it on the full-board problems 4×5 and 5×5, where Black must kill every White group. Parallel search gains a factor of 42 on 192 threads. The serial 3×9 upper-bound proof has 2.1 B expansions and takes 2.3 h, against 5.2 B expansions and 200 s on 192 threads, so the threads search 2.4 times as many nodes. Without virtual loss the threads crowd into the same subtrees. Then, the 192- thread run takes 3.0 h, longer than the serial one, and expands 42 times as many nodes.

## 7 The Value of 4×7 under Superko

Under MIGOS’s rules 4×7 is a full-board win. Black captures everything, giving 28–0. Under PSK its value is 12. A Black proof at komi 11.5 (first move D3) and a White proof at komi 12.5. To show why, we replay the optimal line that MIGOS published under PSK (Figures 4a and 4b of [van der Werf and Winands, 2009], 31 moves). Every move is legal, and the final position is still a Black full-board win. We then solve the line backwards. The full board is still won after move 26, but not after move 25. After Black’s 25th move (Figure 7a), White refutes the line with G2 (or C1) instead of MIGOS’s A2. Every other White move still loses all 28 points.

After G2 the exact PSK value is +3, again established by two proofs. Black’s natural attack (Figure 7b) runs into a hanging ko. White’s capture at A1 cannot be answered, because under PSK the recapture at B1 recreates an earlier board, and every Black move that would change the board puts Black’s own group into atari (the state of having only one liberty remaining). Black has to pass, White passes, and the game ends with White alive. This is the “moonshine life” that MIGOS’s authors mention for 3×7 under superko [van der Werf and Winands, 2009]. Under MIGOS’s rules the pass lifts the ko ban, and the game cannot end by two passes after a fresh ko capture [van der Werf, 2004]. Black then retakes, captures White’s big group, and wins everything, as a proof of that continuation confirms. Under PSK, Black’s best is instead the seki of Figure 7c.

The one-liberty convention of MIGOS [van der Werf and Winands, 2009] does not explain the gap on its own, as with it added to our PSK scoring, White still wins 4×7 at komi 27.5. Each step of the analysis is a small proof of at most a quarter of a million expansions, and the commands in the artifact’s README reproduce the whole chain in under twenty seconds (Appendix C).

## 8 Discussion

The factors in Table 3 multiply. Proof transfer is by far the largest of them. It restores most of the reuse that superko takes away. The learned prior and the region solver cut the remaining tree by factors of 4.7 and 2.3. The region solver helps most in kill-all positions, where proofs would otherwise play out every capture. Shared-table parallelism adds a factor of 42 on 192 threads, because proofs found by one thread are immediately visible to all others, at the cost of 2.4 times as many expansions.

On every board where both rule sets have a value, the values agree except on 2×2, whose superko value MIGOS already reported, and on 4×7. The disagreement does not come from an error in either search. It comes from rules that matter only at the very end of a game, namely what a pass does to a ko ban, and how many passes end the game. Values computed under conventions that make repetition harmless should therefore not be quoted as values of superko Go without checking. Superko also produces strategies with no basicko counterpart, such as the eye-filling sacrifice on 1×12.

![](images/b1d6386577b6205d05bcad3a30872fbfbf220d266a160440cd7be8be33ac122d.jpg)  
(a) after move 25, White to move

![](images/22a90695a3d55b8800fcbfa6e68e6a785d1546bdddcbb10bca7c52efc44ef0fa.jpg)  
(b) moonshine ko, Black to move

![](images/0f37ad00cb7ca42800f4bc621984fb912668d4ea5b417c65e12c3668cc01e561.jpg)  
(c) seki: Black wins by 3  
Figure 7: 4×7: MIGOS’s published optimal line [van der Werf and Winands, 2009], replayed under PSK. (a) MIGOS plays A2 (a), after which Black still wins all 28 points. White’s G2 (b) holds Black to +3. (b) After G2, the attack B1, C1 (White), A2 ends with White capturing at A1. Black’s recapture at k would recreate an earlier board, so PSK forbids it. Every board-changing Black move ataris Black’s own group, so both players pass and White lives. Under MIGOS’s rules the pass lifts the ko ban and the game needs three passes to end, so Black retakes and kills. (c) Black’s best under PSK is a seki: each group has one eye (B4, F1) and they share the liberty B1.

A claimed value rests on the following:

• the soundness arguments for transfer, static leaves and pruning (Theorem 1, Lemma 1 and Appendix A),

• differential testing against an oracle with no static knowledge, on the claimed boards themselves,

• independent re-solves.

Each claim uses only proofs that are trusted for the reported winner. Because pruning is applied only to the side being proven, a failed proof is reported as unknown, never as a win for the opponent.

Larger boards split naturally: the 5×6 upper bound decomposes into ten independent subproblems, one per first move of Black, which can run on separate machines. Extrapolating Figure 6, 6×6 would need about $1 0 ^ { 1 4 }$ expansions or more, about 50 days on one of our machines, and boards above 30 points need position keys wider than 64 bits to stay exact. Stronger knowledge would cut this further. Our learned prior is a first step, and a stronger model, as in learned solvers [Wu et al., 2023], may cut much more.

## 8.1 Probability of an Unsound Result

A reported value can be wrong through an accidental hash match inside the solver, a hardware fault, or a bug. We bound the first and compare it with measured hardware fault rates (Table 4).

Positions and the superko history are exact on our boards, and the transfer test uses only exact data (Section 5). Hashing decides only two things: whether a path-specific proof is reused, by two independent 64-bit signatures of the set of earlier boards, and whether a slot that a concurrent write may have mixed is accepted, by the sealed second hash. A different board set passes both signatures with probability $2 ^ { - 1 2 8 }$ per comparison, and a mixed slot passes the seal with probability $2 ^ { - 6 4 }$ . The largest run made $7 . 0 \cdot 1 0 ^ { 1 3 }$ table probes and the whole campaign $1 . 9 \cdot 1 0 ^ { 1 4 }$ in 187 runs, and every comparison is part of a probe. A mixed slot needs a probe to meet a slot during the nanoseconds of its write, which we bound generously by $1 0 ^ { 5 }$ events per run. With a single 64-bit signature, as is common, the bound for the campaign would be $1 . 1 \cdot 1 0 ^ { - 5 }$

A false match changes a value only if the reused proof is wrong on the current path and that node decides the root. We measured this by fault injection, in builds made only for the experiment. The benchmark positions were solved repeatedly while, at some events and with a small probability, the solver accepted a proof of the same position from another path that the transfer test had rejected, a path-specific proof from a different path, or a stored proof with its winner reversed. These are the effects of a signature collision, a collision of twin keys and a corrupted entry. In three rounds we injected 90,883 faults into about 23,000 solves. None of the 62,260 faults of the two collision kinds changed a result, which bounds the probability that such a fault changes a value by $4 . 9 \cdot 1 0 ^ { - 5 }$ at 95% confidence. One of the 28,623 reversed winners changed a result, which gives a bound of $1 . 7 \cdot 1 0 ^ { - 4 }$ for a corrupted entry. With these factors, the probability that hashing made any reported value wrong is at most $2 \cdot 1 \dot { 0 } ^ { - 1 6 }$ for the whole campaign, almost all of it from mixed slots. With a single 64-bit signature it would be $6 \cdot 1 0 ^ { - 1 0 }$

In Google’s fleet, 1.3% of machines saw an uncorrectable memory error per year [Schroeder et al., 2009], which stops the machine instead of corrupting a result. Silent errors are rarer but documented: a few defective cores per several thousand machines compute wrong results without any error report [Hochschild et al., 2021; Dixit et al., 2021], and an IBM design target of 114 FIT for silent data corruption in POWER4 systems [Dixit et al., 2021], gives about $2 { \cdot } 1 \bar { 0 } ^ { - 6 }$ per 20-hour run. Dixit et al. observe that real silent CPU errors are far more frequent than such soft-error targets. Per run, the hashing risk is thus at least eight orders of magnitude below this target before the measured factor, and about twelve after it. Against hardware faults and bugs the remaining defence is repetition. Every value rests on two independent proofs, one for each bound, and the lower bounds of 5×5 and $4 \times 7$ were proved again in independent runs. Furthermore, as we make the source and the exact commands available, readers may repeat any proof, in stark contrast to the existing literature.

## 9 Related Work

Thorp and Walden studied boards up to 3×4 [Thorp and Walden, 1972], and Sei and Kawashima solved 4×4 [Sei and Kawashima, 2000]. MIGOS solved 5×5 [van der Werf et al., 2003] and most rectangles up to 30 points [van der Werf and Winands, 2009] with iterative-deepening $\alpha \beta$ under basic ko.

<table><tr><td>Source</td><td>Per event Largest run Campaign</td><td></td><td></td></tr><tr><td>Twin signatures</td><td> $3 \cdot 1 0 ^ { - 3 9 }$ </td><td> $3 \cdot 1 0 ^ { - 2 5 }$ </td><td> $6 \cdot 1 0 ^ { - 2 5 }$ </td></tr><tr><td>Mixed slot</td><td> $6 \cdot 1 0 ^ { - 2 0 }$ </td><td> $< 1 0 ^ { - 1 4 }$ </td><td> $1 . 1 \cdot 1 0 ^ { - 1 2 }$ </td></tr><tr><td>One 64-bit signature *</td><td> $6 \cdot 1 0 ^ { - 2 0 }$ </td><td> $4 \cdot 1 0 ^ { - 6 }$ </td><td> $1 . 1 \cdot 1 0 ^ { - 5 }$ </td></tr><tr><td>Silent CPU errors† Defective cores</td><td> $1 1 4 \mathrm { F I T }$ </td><td> $2 \cdot 1 0 ^ { - 6 }$   ${ \sim } 1 0 ^ { - 3 }$ </td><td></td></tr></table>

Table 4: Upper bounds on an accidental hash match, before the factor measured by fault injection, and hardware fault rates. <sup>∗</sup>For comparison only. $^ { \dag } \mathrm { A n }$ IBM design target for POWER4 systems, cited by [Dixit et al., 2021], for a 20-hour run. <sup>‡</sup>A few per several thousand machines [Hochschild et al., 2021], if the run’s node has one.

Under PSK, Weninger and Hayward solved linear boards up to 1×9 [Weninger and Hayward, 2017], and EWS solved 5×5 with a best-first search that combines win-rate and proof-size estimates [Randall et al., 2024]. Killall-Go work solves 7×7 openings with neural heuristics and relevance zones [Shih et al., 2022; Wu et al., 2023]. That is a different problem, in which Black must capture everything.

Campbell described the GHI problem [Campbell, 1985]. Breuker et al. solved it for best-first search [Breuker et al., 2001]. Kishimoto and Muller gave a general solution and one¨ for df-pn, based on path simulation [Kishimoto and Muller,¨ 2004; Kishimoto and Muller, 2005¨ ]. Our transfer rule is specific to PSK. It exploits the winner/loser asymmetry of superko to replace simulation by an O(path-length) attribute test.

Benson’s algorithm [Benson, 1976] and its extensions [Muller, 1997 ¨ ] recognize unconditionally safe groups and territory. Our pure-eye analysis adapts them to PSK play-out, where territory must be won by legal captures (Lemma 1).

The solved values of empty Go boards in the literature cannot be reproduced from public material (Appendix E). To our knowledge, no code, binaries or proof data have been released for MIGOS [van der Werf et al., 2003; van der Werf and Winands, 2009], whose papers show selected variations only. The public implementation of EWS is a minimal example that solves boards up to 3×3, while the 5×5 solver and its baseline have not been released. The Positional Linear Go solver [Weninger and Hayward, 2017] is described in the paper only. The Killall-Go solvers [Wu et al., 2023] are public but address a different problem. Readers have therefore had to take these values on trust, and checking a value under another rule set, as we do for 4×7, requires solving the board again from scratch. We release our solver source together with the exact command line and outcome of every solver run behind our values, speed measurements and ablations.

## 10 Conclusion

Positional superko invalidates the standard tools of game solving and, on 4×7, changes the answer itself. We showed how to restore those tools soundly: a new proof-transfer theorem that looks only at the winner’s boards, novel static rules that hold under play-out, and pruning that is applied only to the side being proven. The resulting solver, Sanko, is faster, often by orders of magnitude, than the previous state of the art at equal thread count, and it solves boards that were out of reach under PSK.

Limitations. Our proofs are not externally checkable certificates. Under PSK a certificate must encode pathdependent proofs, which is an open problem. Proof size grows by roughly ten times per two to three added points, so 6×6 remains beyond reach without a qualitative advance.

## Acknowledgement

We thank ZIB’s IT team for providing and maintaining the compute resources.

## References

[AGA Rules Committee, 1991] AGA Rules Committee. Official AGA rules of Go. American Go Association, 1991. Dated 1 September 1991. Online text: https://www.cs. cmu.edu/<sup>∼</sup>wjh/go/rules/AGA.html, accessed 20 October 2026.

[Allis et al., 1994] L. Victor Allis, Maarten van der Meulen, and H. Jaap van den Herik. Proof-number search. Artificial Intelligence, 66(1):91–124, 1994.

[Benson, 1976] David B. Benson. Life in the game of Go. Information Sciences, 10(1):17–29, 1976.

[Bloom, 1970] Burton H. Bloom. Space/time trade-offs in hash coding with allowable errors. Communications ofthe ACM, 13(7):422–426, 1970.

[Breuker et al., 2001] Dennis M. Breuker, H. Jaap van den Herik, Jos W. H. M. Uiterwijk, and L. Victor Allis. A solution to the GHI problem for best-first search. Theoretical Computer Science, 252(1–2):121–149, 2001.

[Campbell, 1985] Murray Campbell. The graph-history interaction: On ignoring position history. In Proceedings of the 1985 ACM Annual Conference on The Range of Computing: Mid-80’s Perspective, pages 278–280. ACM, 1985.

[Chinese Weiqi Association, 1988] Chinese Weiqi Association. The Chinese rules of Go, 1988. English translation published by Shu Rong Chess and Bridge Press, Chengdu, 1989. Online text: https://www.cs.cmu.edu/<sup>∼</sup>wjh/go/rules/ Chinese.html, accessed 20 October 2026.

[Dixit et al., 2021] Harish Dattatraya Dixit, Sneha Pendharkar, Matt Beadon, Chris Mason, Tejasvi Chakravarthy, Bharath Muthiah, and Sriram Sankar. Silent data corruptions at scale. arXiv:2102.11245, 2021.

[Henderson et al., 2009] Philip Henderson, Broderick Arneson, and Ryan B. Hayward. Solving 8 × 8 Hex. In Craig Boutilier, editor, Proceedings of the 21st International Joint Conference on Artificial Intelligence (IJCAI), pages 505–510, 2009.

[Hochschild et al., 2021] Peter H. Hochschild, Paul Turner, Jeffrey C. Mogul, Rama Govindaraju, Parthasarathy Ranganathan, David E. Culler, and Amin Vahdat. Cores that don’t count. In Proceedings of the Workshop on Hot Topics in Operating Systems (HotOS ’21), pages 9–16. ACM, 2021.

[Kaneko, 2010] Tomoyuki Kaneko. Parallel depth first proof number search. In Proceedings of the 24th AAAI Conference on Artificial Intelligence, pages 95–100. AAAI Press, 2010.

[Kawano, 1996] Yasuhito Kawano. Using similar positions to search game trees. In Richard J. Nowakowski, editor, Games of No Chance, volume 29 of Mathematical Sciences Research Institute Publications, pages 193–202. Cambridge University Press, 1996.

[Kishimoto and Muller, 2004¨ ] Akihiro Kishimoto and Martin Muller. A general solution to the graph history inter-¨ action problem. In Proceedings ofthe 19th National Conference on Artificial Intelligence (AAAI), pages 644–649. AAAI Press, 2004.

[Kishimoto and Muller, 2005¨ ] Akihiro Kishimoto and Martin Muller. A solution to the GHI problem for depth-first ¨ proof-number search. Information Sciences, 175(4):296– 314, 2005.

[Muller, 1997¨ ] Martin Muller. Playing it safe: Recogniz-¨ ing secure territories in computer Go by using static rules and search. In H. Matsubara, editor, Game Programming Workshop in Japan ’97, pages 80–86, Tokyo, Japan, 1997. Computer Shogi Association.

[Nagai, 2002] Ayumu Nagai. Df-pn Algorithm for Searching AND/OR Trees and Its Applications. PhD thesis, University of Tokyo, 2002.

[New Zealand Go Society, 2017] New Zealand Go Society. New Zealand rules of Go. https://go.org.nz/index.php/ about-go/new-zealand-rules-of-go, 2017. Posted 22 January 2017, accessed 20 October 2026.

[Pawlewicz and Lew, 2007] Jakub Pawlewicz and Łukasz Lew. Improving depth-first PN-search: 1 + ε trick. In H. Jaap van den Herik, Paolo Ciancarini, and H. H. L. M. Donkers, editors, Computers and Games (CG 2006), volume 4630 of Lecture Notes in Computer Science, pages 160–171. Springer, 2007.

[Randall et al., 2024] Owen Randall, Martin Muller, Ting-¨ Han Wei, and Ryan Hayward. Expected work search: Combining win rate and proof size estimation. In Kate Larson, editor, Proceedings of the Thirty-Third International Joint Conference on Artificial Intelligence (IJCAI), pages 7003–7011, 2024.

[Schaeffer et al., 2007] Jonathan Schaeffer, Neil Burch, Yngvi Bjornsson, Akihiro Kishimoto, Martin M¨ uller, Robert¨ Lake, Paul Lu, and Steve Sutphen. Checkers is solved. Science, 317(5844):1518–1522, 2007.

[Schroeder et al., 2009] Bianca Schroeder, Eduardo Pinheiro, and Wolf-Dietrich Weber. DRAM errors in the wild: A large-scale field study. In Proceedings of the Eleventh International Joint Conference on Measurement and Modeling of Computer Systems (SIGMETRICS/Performance ’09), pages 193–204. ACM, 2009.

[Sei and Kawashima, 2000] Shinichi Sei and Toshiaki Kawashima. A solution of Go on 4 × 4 board by game tree search program. IPSJ SIG Technical Report Vol. 2000,

No. 98 (2000-GI-004), Information Processing Society of Japan, 2000. In Japanese.

[Shih et al., 2022] Chung-Chin Shih, Ti-Rong Wu, Ting Han Wei, and I-Chen Wu. A novel approach to solving goalachieving problems for board games. In Proceedings of the 36th AAAI Conference on Artificial Intelligence, pages 10362–10369, 2022.

[Thorp and Walden, 1972] Edward O. Thorp and William E. Walden. A computer assisted study of Go on m×n boards. Information Sciences, 4(1):1–33, 1972.

[Tromp, 1995] John Tromp. The game of Go. https://tromp. github.io/go.html, 1995. The Tromp–Taylor rules, posted to rec.games.go by Bill Taylor on 13 February 1995. Accessed 20 October 2026.

[van der Werf and Winands, 2009] Erik C. D. van der Werf and Mark H. M. Winands. Solving Go for rectangular boards. ICGA Journal, 32(2):77–88, 2009.

[van der Werf et al., 2003] Erik C. D. van der Werf, H. Jaap van den Herik, and Jos W. H. M. Uiterwijk. Solving Go on small boards. ICGA Journal, 26(2):92–107, 2003.

[van der Werf, 2004] Erik C. D. van der Werf. AI Techniques for the Game of Go. PhD thesis, Maastricht University, 2004.

[Weninger and Hayward, 2017] Noah Weninger and Ryan Hayward. Exploring positional linear Go. In Mark H. M. Winands, H. Jaap van den Herik, and Walter A. Kosters, editors, Advances in Computer Games (ACG 2017), volume 10664 of Lecture Notes in Computer Science, pages 101–114. Springer, 2017.

[Wu et al., 2023] Ti-Rong Wu, Hung Guei, Ting Han Wei, Chung-Chin Shih, Jui-Te Chin, and I-Chen Wu. Game solving with online fine-tuning. In A. Oh, T. Naumann, A. Globerson, K. Saenko, M. Hardt, and S. Levine, editors, Advances in Neural Information Processing Systems 36 (NeurIPS), pages 58428–58447. Curran Associates, Inc., 2023.

[Zobrist, 1990] Albert L. Zobrist. A new hashing method with application for game playing. ICCA Journal, 13(2):69–73, 1990. Reprint of Technical Report 88, Computer Sciences Department, University of Wisconsin, 1970.

## A Proofs

## A.1 Setting

A position is a board, the side to move, and the number of consecutive passes (0 or 1). A history is the sequence of positions from the empty board to the current one. We also write a history H for its set of boards. A stone move m at a position with history G is legal if and only if (1) its point is empty, (2) it is not suicide, and (3) its result board $r ( m )$ is not in $G .$ Conditions (1) and (2) depend on the current board only. The current board itself lies in $G ,$ but a stone move never recreates the current board, because it adds a stone on an empty point and that stone cannot be removed by the move itself. So condition (3) is the only history-dependent one. Passes are always legal and create no new board. The game ends after two consecutive passes and is scored by area on the final board.

A proof that w wins from node N under history H is a finite tree T. At w-nodes it contains one legal move, at opponent nodes it contains every legal move, and its leaves are terminal positions won by w or static leaves certified by Lemma 1. For a node v of T, let $\ell ( v )$ be the set of boards on $T \ ' _ { \mathbf { S } }$ line from N to v, with $N$ excluded, and write $H _ { v } = H \cup \ell ( v )$ for the history at v.

## A.2 Proof of Theorem 1

Write $H _ { v } ^ { \prime } = H ^ { \prime } \cup \ell ( v )$ . We show for every node v of $T ,$ , by induction on the height of the subtree $T _ { v }$ , that $T _ { v }$ is a valid proof for w from v under $H _ { v } ^ { \prime }$ . The induction uses three invariants.

(a) $B _ { w } ( T _ { v } ) \cap H _ { v } ^ { \prime } = \emptyset$ . Every board $r \in B _ { w } ( T _ { v } )$ is created by a legal w move at some node u of $T _ { v }$ . Legality under $\dot { H } _ { u } \supseteq \bar { H } _ { v }$ gives $r \not \in H$ and $r \not \in \ell ( v )$ . Since $\bar { r } \in \ b { { B } } _ { w } ( T )$ condition (i) gives $r \not \in H ^ { \prime } .$ . Hence $r \notin H _ { v } ^ { \prime }$

(b) Every board of $H _ { v }$ that excludes an opponent move inside $T _ { v }$ lies in $H _ { v } ^ { \prime }$ . Such a board lies either in $\ell ( v )$ , which is part of $H _ { v } ^ { \prime } ,$ , or in $H$ . In the second case it belongs to $X ( T )$ and hence to $H ^ { \prime }$ by condition (ii).

(c) For every static leaf λ of $T _ { v } , \mathrm { c a p } _ { w } ( H _ { \lambda } ^ { \prime } )$ ∩ terr $( \lambda ) \ =$ ∅. Captures along ℓ(λ) are determined by the positions and are the same under both histories, so $\mathrm { c a p } _ { w } ( H _ { \lambda } ^ { \prime } ) =$ $\begin{array} { r } { \operatorname* { c a p } _ { w } ( H ^ { \prime } ) \cup \operatorname { c a p } _ { w } ( \ell ( \lambda ) ) } \end{array}$ ). The first part is disjoint from $\mathrm { t e r r } ( \lambda ) \subseteq \mathrm { t e r r } ( T )$ by condition (iii). The second part is disjoint from terr(λ) because λ was accepted as a static leaf under $H _ { \lambda } .$ , which required $\mathrm { c a p } _ { w } ( H ) \mathsf { \bar { U } } \mathrm { c a p } _ { w } ( \ell ( \lambda ) )$ to avoid terr(λ).

Terminal leaf. The area score depends only on the board, so v is won for w under any history.

Static leaf. Lemma 1 needs (C1), which is invariant (c), and (C2), which depends only on the position. So the certified area bound holds under $H _ { v } ^ { \prime }$

w-node with chosen move m and child c. A pass is always legal. For a stone move, $r ( m ) \in B _ { w } ( T _ { v } )$ is not in $H _ { v } ^ { \prime }$ by (a), and conditions (1) and (2) hold as under $H _ { v } .$ So m is legal under $H _ { v } ^ { \prime }$ . The invariants restrict to $T _ { c }$ , and the induction hypothesis applies to c.

Opponent node. Let m be an opponent move that is legal under $H _ { v } ^ { \prime }$ . A pass is contained in T. Suppose m is a stone move that is not contained in $T ,$ so it was illegal under $H _ { v }$ Conditions (1) and (2) are history-free, so $r ( m ) \in H _ { v }$ . By $\mathbf { \rho } ( \mathbf { b } ) , r ( m ) \in H _ { v } ^ { \prime }$ , which contradicts the legality of m under $H _ { v } ^ { \prime }$ . Hence every opponent move that is legal under $H _ { v } ^ { \prime }$ has its subtree in $T _ { \ast }$ , and the induction hypothesis applies to each child. Opponent moves that are legal under $H _ { v }$ but illegal under $H _ { v } ^ { \prime }$ only leave surplus children in T, which a proof may contain. □

Attributes and composition. The solver stores, for each proof, a Bloom filter of the canonical hashes of $B _ { w } ( T )$ , the set of stones common to all boards of $B _ { w } ( T )$ together with their minimum stone count, and the territory bitboard. While composing, the search also tracks at most one exclusion target, or a marker for several, and a proof with a target is stored path-specifically.

Lemma 2 (Composition). Let a won node take the attributes ofits winning child, extended by its own board ifthe winning move is a stone move, and let a lost node take the join of the attributes of all its children (union of Bloom filters, intersection of common stones, minimum of the stone counts, union of targets and of territories), extended by its own exclusions. Then the stored Bloom filter and territory contain the true sets, the stored common stones are contained in every board of $B _ { w } ( T )$ , the stored count is at most the true minimum, and the tracked targets contain X(T).

Proof. By induction over the proof. $B _ { w }$ of a won node is $B _ { w }$ of its winning child plus the board its own stone move creates, and $B _ { w }$ of a lost node is the union over its children. X and terr are unions over children plus the node’s own contributions. The join operations over-approximate unions and under-approximate intersections, which preserves each inclusion. □

Corollary 1. Algorithm 1 accepts a transfer only if conditions (i) to (iii) of Theorem 1 hold.

Proof. A strict ancestor board a can lie in $B _ { w } ( T )$ only if it contains the common stones, has at least the minimum number of stones, and hits the Bloom filter, which has no false negatives. If any test fails, $a \not \in B _ { w } ( T )$ Condition (iii) is tested exactly. Every proof with an exclusion target is pathspecific and rejected by the first test, so a transferred proof has $X ( T ) = \varnothing$ and satisfies (ii) trivially. Path-specific proofs are reused only on the identical board with an identical set of earlier boards, that is, in the identical superko game. The solver recognizes the identical set by two independent signatures (Hash identity, below). In the identical game no test is needed, condition (iii) included. Stones leave the board only by capture, so a winner stone was captured on a territory point exactly when some earlier board has a winner stone there, which depends only on the set of earlier boards. □

Unsoundness of XOR signatures. A path-specific key needs an identifier of the set of earlier boards. XOR-ing the Zobrist keys of the boards is linear over GF(2), so different sets of boards whose keys sum to the same value collide systematically, not just by chance. The solver applies a nonlinear mix to each board key before summation.

## A.3 Proof of Lemma 1

Let w follow the strategy σ: if an o stone lies in $T ^ { * }$ , play on a liberty of an o-chain inside $T ^ { * }$ , and otherwise pass.

Invariant (I). Every w-chain that contains an ${ \bar { X } } ^ { * }$ stone has two distinct pure eyes, each bordered only by such chains and each containing at least one empty point. Initially this holds by the definition of $X ^ { \ast }$ . An eye without an empty point would consist of o-chains whose neighbours lie in the eye or are w stones, so they would have no liberty, which is impossible in a legal position. After an o move at $p \mathrm { : }$ if $p$ were the last empty point of an eye $E ,$ the o-chain through p would have no liberty and would capture nothing, because every adjacent w-chain keeps an empty point in its other eye. So the move would be suicide. Otherwise E keeps an empty point. The move can capture only w-chains without an $\check { X ^ { \ast } }$ stone, and those border no eye and no region of $T ^ { * }$ , so the eyes and their purity are unchanged. After a σ move at $q \in T ^ { * } \colon$ q is adjacent to $X ^ { * }$ , so its chain contains $X ^ { * }$ stones, and the move is not suicide because that chain keeps the empty point of an eye not containing $q .$ Eyes not containing $q$ are unchanged. If $q$ lies in an eye $E ,$ then $E \setminus \{ q \}$ together with the captured points is still adjacent to the chain, because $E$ was pure and every captured point lies in $E .$ . It still contains an empty point: either $q$ was not $E " s$ last empty point, or the o-chain whose last liberty $q$ was is captured and its points become empty.

Permanence. By (I), every chain with an $X ^ { * }$ stone always has at least two liberties, so o can never capture it. Every σ stone joins such a chain because $T ^ { * }$ is adjacent to $X ^ { \ast }$ . So the $X ^ { * }$ stones and all σ stones are permanent.

Superko legality of $\sigma .$ Suppose $w ^ { \prime } \mathbf { s }$ stone at q recreated an earlier board $B .$ Then $B$ has a w stone at $q .$ Within the continuation, q never held a w stone before, because w stones are permanent and $q$ was empty. So $B$ precedes the current position, at which the point $q \in T ^ { * }$ is not occupied by w. Hence a w stone on $q$ was captured during the history, so $q \in \mathrm { c a p } _ { w } ( H ) \cap T ^ { * }$ , which contradicts (C1). Moves that are illegal for o only restrict $o .$

Termination and area. Every stone move creates a new board, so the game is finite. σ passes only when $T ^ { * }$ holds no o stone, and the game ends after two consecutive passes. By (C2) it cannot end before w has moved, so one of the last two moves is a $\sigma$ pass made while $T ^ { * }$ is clean, and the other is an o pass, which does not change the board. At the end, every point of $T ^ { * }$ is a w stone or an empty point enclosed by the permanent w stones that bordered $\bar { T } ^ { * } \bar { \bf s }$ regions. So w’s area is at least $\left| X ^ { * } \right| + \left| T ^ { * } \right|$ □

Pure eyes versus vital regions. Benson’s classic test asks only that every empty point of a region be adjacent to the chain. Benson’s theorem assumes that the owner never moves, while here the owner must capture intruders. Consider a chain $K$ with a one-point eye e and a classic eye R that holds an o-chain Y . Suppose $\dot { Y } ^ { \bullet } \mathrm { s }$ only liberty a touches $K$ and $Y \mathrm { \overline { { s } } }$ far stones touch only another alive chain. To own $R ,$ w plays a and captures $Y$ . The opponent re-enters at a freed point next to $K$ with two liberties (freed points that touch only the other chain), which leaves $K$ in atari on e, and captures $\dot { K }$ next move. Under the pure condition every freed point touches $K ,$ , so this cannot happen. The proof above therefore needs the pure test, which costs no more to evaluate than the classic one.

The pass condition (C2). After $w ^ { \prime } \mathbf { s }$ own pass, o may pass as well and end the game on the current board. In the $3 { \times } 3$ position of Section 4, Black has just passed and White passes back, which ends the game 3–3 although Benson’s analysis gives Black all nine points.

## A.4 Local Region Games

Lemma 3 (Region solver). Suppose every region (component of non-Black points) is bordered only by Black $X ^ { * }$ chains, every Black chain has two pure eyes among the regions, $( C l )$ and (C2) holdfor the union ofthe regions, and Black wins the local game below in every region. Then Black wins the whole board.

Local game in a region R. White moves first, and may pass or play any point of R that is not suicide. Black may play anchored points, which are adjacent to the walls or to an earlier anchored stone. In regions of at most eight points Black may also play interior points, provided the Black chain keeps a liberty. Any White move that would capture a Black stone counts as a White win of the local game. Black wins $R$ on reaching a state with no White stone in R, all Black stones connected to the walls, and every empty point adjacent to them. Black never passes in the local game.

Proof. In a winning line for Black, no Black stone is ever captured, so Black’s stones only accumulate. Each pair of a White move or pass and a Black move adds a permanent stone, so the local game is finite and acyclic. Its value depends only on the local state, so memoization is sound. White’s local options are a superset of the real ones, since real superko only removes White moves. Black composes the local strategies: it answers a White move in an unfinished region in that region, after a White pass it moves in an unfinished region, and once every region is won it follows σ from the proof of Lemma 1. A White move into a region that is already won is answered there by $\sigma .$ . Every point of a won region is a permanent Black stone or adjacent to one, so the region meets the territory conditions of Lemma 1, whose invariant argument is local to each region because the permanent walls separate the regions. White can neither make an eye nor capture there, and once its stones are captured the region is won again. At that point the board consists of $X ^ { * }$ chains with their pure eyes and of regions whose points are all Black or adjacent to Black, which are the hypotheses of Lemma 1. Every Black move adds a permanent stone, so it cannot repeat a board of the continuation, and an earlier board is excluded by (C1) as in Lemma 1. (C2) prevents an immediate end. □

## A.5 Pruning, Parallel Search, Symmetry and Hashing

Winner-side pruning. Removing some of w’s options, namely filling its own single-point eyes and moving inside its own certified territory, can only make proofs of a w win harder, never wrong. The argument is an induction over the claims in the shared table. A claim that w wins at a w-node rests on one child claimed as a w win, a claim at an opponent node rests on every legal child claimed as a w win, and pruning removes only w’s moves. So every w-win claim rests only on w-win claims, terminal positions and static leaves. Claims that the opponent wins can be wrong under pruning, but no w-win claim depends on them. A root result against w is reported as unknown. Under PSK these moves are not dominated by a pass, because they change the board and can make a later capture legal. On $1 \times 1 2$ at komi 1.5, neither pruned search proves its side, and an unpruned proof contains owneye fills by both sides.

Parallel search. Threads share the tables, but a thread concludes that a node is proven only in two ways: through a child classification that applies the tests of Algorithm 1, or the twin identity test for a path-specific proof, to any proof read from the table, or through the value returned by its own recursive search. Numbers read from unproven entries of other threads are always nonzero and finite and only steer the search. Proof entries are self-validating. A reader accepts a slot only if its words combine back to the probe key and the second hash, stored sealed with a non-linear hash of the other words, matches. A slot mixing two writes, from a torn read or from two writers interleaving, fails the second test except with probability about $2 ^ { - 6 4 }$ , so it is a miss. Virtual loss changes only which child is explored. Hence every proof that a thread stores satisfies the serial invariants, and parallel soundness reduces to serial soundness.

Symmetry. A position and its image under a board symmetry s have the same value if their histories correspond under s, because legality, superko and scoring are invariant under s. Proofs are stored under canonical keys, and transfer checks are made in the current frame: common stones and territory are mapped back by $s ^ { - 1 }$ , and the Bloom filter holds canonical hashes, which are invariant. Two sibling moves m and $s ( m )$ are merged only if s maps every board of the current history to itself. A loss whose proof relied on such a merge is stored path-specifically, because on another path the set of such symmetries can be smaller.

Hash identity. The position key is exact on all boards we solve (a unit test checks the linear independence of its generators for 30 points), and a second test checks that the constants of the two alternate slots, and their sum, lie outside the span of these generators. Proof entries also match on an independent second 64-bit hash, which guards path-specific keys and entries mixed by concurrent writes. Unproven entries match on 26 check bits plus the bucket index and hold heuristic numbers only. A false match there gives wrong but nonzero numbers, which steer the search but prove nothing. A path-specific proof is reused only if the canonical key, two independent 64-bit path signatures and the canonicalizing symmetry all match. The first signature is part of its key, and the second is combined into its second hash. The symmetry is needed because two paths with the same set of boards can end on mirror images of each other, which are different superko games. A collision would have to equate two different board sets for the same position in both signatures, with probability about $2 ^ { - 1 2 8 }$ per comparison. Every other proof is reused only through the transfer test, which uses only exact data.

## B Extended Results

All runs use the same rules and the same static knowledge, except the $4 \times 7$ run under MIGOS’s one-liberty convention and the ablations. They also share the options that affect efficiency but not soundness. Interior moves in regions of at most eight points, one kept tempo move per node for the pruned side, the learned prior and $\varepsilon = 0 . 3$ . The first line of each log in the artifact gives the build and the full command line. Coordinates use letters $\mathbf { A } , \mathbf { B } , \ldots$ without I for columns from the left and numbers for rows from the bottom.

<table><tr><td>White reply</td><td>Black&#x27;s answer</td><td>Expansions</td><td>Time</td></tr><tr><td>pass</td><td>pass</td><td>192</td><td>10s</td></tr><tr><td>A5</td><td>B4</td><td>1.8B</td><td>74 s</td></tr><tr><td>B5</td><td>D4</td><td>2.3B</td><td>89 s</td></tr><tr><td>C5</td><td>B4</td><td>2.0B</td><td>78s</td></tr><tr><td>B4</td><td>D2</td><td>1.8 B</td><td>67 s</td></tr><tr><td>C4</td><td>B4</td><td>1.3B</td><td>53 s</td></tr></table>

Table 5: Independent re-solves of $5 \times 5$ after Black C3, one fresh process per symmetry-unique White reply. All are Black wins at komi 24.5, on 192 threads.

<table><tr><td>Black&#x27;s first move</td><td>White&#x27;s reply</td><td>Expansions</td><td>Time</td></tr><tr><td>pass</td><td>pass</td><td>192</td><td>50s</td></tr><tr><td>A3</td><td>D3</td><td>60.1 B</td><td>42 min</td></tr><tr><td>A5</td><td>B3</td><td>87.4 B</td><td>1.1 h</td></tr><tr><td>A4</td><td>E3</td><td>100 B</td><td>1.2h</td></tr><tr><td>B5</td><td>C3</td><td>146 B</td><td>1.7h</td></tr><tr><td>C5</td><td>C3</td><td>166 B</td><td>2.0h</td></tr><tr><td>B3</td><td>C3</td><td>69.6 B</td><td>50 min</td></tr><tr><td>C3</td><td>D3</td><td>200 B</td><td>2.4 h</td></tr><tr><td>B4</td><td>D3</td><td>168 B</td><td>2.0h</td></tr><tr><td>C4</td><td>C3</td><td>238 B</td><td>2.9h</td></tr></table>

Table 6: 5×6 upper bound at komi 4.5, split into one White-pruned proof per symmetry-unique first move of Black.

<table><tr><td>First move</td><td>Reply</td><td>Expansions</td><td>Time</td></tr><tr><td>pass</td><td>pass</td><td>192</td><td>11 s</td></tr><tr><td>A3</td><td>D2</td><td>9.4 B</td><td>7 min</td></tr><tr><td>B3</td><td>H2</td><td>10.4B</td><td>8 min</td></tr><tr><td>C3</td><td>G2</td><td>15.3 B</td><td>11 min</td></tr><tr><td>D3</td><td>H2</td><td>10.6B</td><td>8min</td></tr><tr><td>E3</td><td>G2</td><td>10.9B</td><td>8 min</td></tr><tr><td>A2</td><td>G2</td><td>4.3B</td><td>3 min</td></tr><tr><td>B2</td><td>H2</td><td>3.1 B</td><td>150s</td></tr><tr><td>C2</td><td>G2</td><td>5.3 B</td><td>4min</td></tr><tr><td>D2</td><td>G2</td><td>10.0B</td><td>7 min</td></tr><tr><td>E2</td><td>G2</td><td>17.6B</td><td>12 min</td></tr></table>

Table 7: 3×10 upper bound at komi 8.5, one White-pruned proof per symmetry-unique first move of Black. After D2, Black wins at 7.5 (Table 2), so 3×10 is worth 8.

<table><tr><td>Komi</td><td>Run</td><td>Result</td><td>Exp.</td></tr><tr><td>27.5</td><td>White-pruned, one-liberty convention</td><td>White</td><td>14.6 B</td></tr><tr><td>23.5</td><td>White-pruned, after Black D3</td><td>White (C2)</td><td>13.6B</td></tr><tr><td>12.5</td><td>unpruned</td><td>White</td><td>16.4 B</td></tr><tr><td>11.5</td><td>unpruned</td><td>Black (D3)</td><td>86.6B</td></tr><tr><td>11.5</td><td>Black-pruned</td><td>Black (D3)</td><td>65.6 B</td></tr></table>

Table 8: 4×7 runs, each on 192 threads. A pruned run proves only a win for its own side.

<table><tr><td>n</td><td>Value</td><td>Black&#x27;s move</td><td>Black proof</td><td>White proof</td></tr><tr><td>4</td><td>4</td><td>2nd point</td><td>207</td><td>(full)</td></tr><tr><td>5</td><td>0</td><td>2nd</td><td>421</td><td>493</td></tr><tr><td>6</td><td>1</td><td>2nd</td><td>1,148</td><td>1,109</td></tr><tr><td>7</td><td>2</td><td>4th</td><td>461</td><td>3,334</td></tr><tr><td>8</td><td>3</td><td>2nd</td><td>8,177</td><td>19,937</td></tr><tr><td>9</td><td>0</td><td>2nd</td><td>5,134</td><td>20,477</td></tr><tr><td>10</td><td>1</td><td>2nd</td><td>24,885</td><td>120,077</td></tr><tr><td>11</td><td>2</td><td>6th</td><td>35,264</td><td>337,294</td></tr><tr><td>12</td><td>2</td><td>2nd</td><td>1.53 B</td><td>26.0M</td></tr><tr><td>13</td><td>0</td><td>2nd</td><td>409,368</td><td>87.9M</td></tr><tr><td>14</td><td>1</td><td>2nd</td><td>4.06M</td><td>566M</td></tr><tr><td>15</td><td>2</td><td>8th</td><td>282M</td><td>4.36 B</td></tr><tr><td>16</td><td>1</td><td>2nd</td><td>792M</td><td>475 B</td></tr><tr><td>17</td><td>0</td><td>2nd</td><td>7.01 B</td><td>4,757 B</td></tr><tr><td>18</td><td>1</td><td>2nd</td><td>108 B</td><td>7,748 B</td></tr></table>

Table 9: Linear Go 1×n under PSK, expansions per proof. All proofs use unpruned search on 192 threads.

## C The 4×7 Proof Chain

MIGOS’s published optimal line (Figures 4a and 4b of [van der Werf and Winands, 2009]) is 1 D3, 2 C2, 3 C3, 4 E2, 5 D2, 6 E3, 7 F1, 8 E1, 9 F3, 10 F2, 11 E4, 12 F4, 13 G4, 14 D4, 15 C4, 16 G3, 17 G2, 18 G1, 19 F4, 20 G3, 21 D4, 22 B2, 23 B3, 24 D1, 25 A3, 26 A2, 27 C1, 28 B1, 29 G2, 30 A4, 31 F1. Every move is legal under PSK, and no move along the line is forbidden by superko alone. Table 10 lists the small proofs behind Section 7.

<table><tr><td>Position</td><td>Komi</td><td>Result</td><td>Exp.</td></tr><tr><td>after move 31</td><td>27.5</td><td>Black</td><td>9,318</td></tr><tr><td>after move 26</td><td>27.5</td><td>Black (C1)</td><td>134,266</td></tr><tr><td>after move 24</td><td>27.5</td><td>unknown</td><td>9,660</td></tr><tr><td>after move 25</td><td>27.5</td><td>White (G2)</td><td>889</td></tr><tr><td>after 25, G2</td><td>2.5</td><td>Black (A2)</td><td>436</td></tr><tr><td>after 25, G2</td><td>3.5</td><td>White</td><td>495</td></tr><tr><td>after G2, B1, C1, A2,</td><td>27.5</td><td>White</td><td>73</td></tr><tr><td>A1 after G2, B1, C1, A2, pass, F1</td><td>27.5</td><td>Black</td><td>77,411</td></tr></table>

Table 10: The chain of small proofs for 4×7. Black results come from Black-pruned runs and White results from White-pruned runs, so each is trusted for its winner.

After move 25, the exact values of White’s moves are +3 for G2 and C1 and +28 for every other move, including MI-GOS’s A2 and a pass. After G2, Black’s replies A2, C1 and B1 are worth +3, +1 and 0, and every other Black move, including a pass, loses Black’s large group. The optimal PSK continuation is B A2, W C1, B A1, W B4, B A4 (capturing), and two passes, which leaves the seki of Figure 7c (Black 15, White 12, B1 neutral).

## D Validation Summary

<table><tr><td>Check</td><td>Result</td></tr><tr><td>Selftests, 7 small boards, 3 oracle modes</td><td>10,808 positions, 0 mismatches</td></tr><tr><td>Threshold probes, 9 boards up to 5×5</td><td>31,622 probes, 0 counterexamples</td></tr><tr><td>Brute-force minimax with an exact memo against shared-table solves (1×4, 1×5,2×3)</td><td>7,538 positions, 0 mismatches</td></tr><tr><td>Large-board selftests (4×7, 5×6, 3×10, 2×14, 3×9, 4×6, 5×5, 3×7, 4×5, three solver modes)</td><td>28,033 positions, 0 mismatches</td></tr><tr><td>Proof entries rejected by the second hash (path-specific collisions or mixed writes)</td><td>up to 552 per run (1×18)</td></tr></table>

Table 11: Validation of the solver used for all reported results.

## E Availability of Prior Solvers and Reproduction

Table 12 summarizes which solvers behind published Go results are publicly available. The entries reflect public repositories and the authors’ web pages as of 2026.

<table><tr><td>Work</td><td>Result</td><td>Public artifact</td></tr><tr><td>MIGOS [van der Werf et al., 2003]</td><td>5×5, basic ko</td><td>none known</td></tr><tr><td>MIGOS [van der Werf and Winands, 2009]</td><td>most boards up to 30 points, basic ko</td><td>none known, selected variations in the paper</td></tr><tr><td>Positional Linear Go [Weninger and</td><td>1×n, n ≤ 9, PSK</td><td>none known</td></tr><tr><td>Hayward, 2017] EWS [Randall et al., 2024]</td><td>5×5, PSK</td><td>minimal example² that solves up to 3×3, 5×5</td></tr><tr><td>Killall-Go [Wu et al., 2023]</td><td>7×7 openings</td><td>solver not released solver and solution trees, different problem</td></tr><tr><td>Sanko (this work)</td><td>Table 2</td><td>solver source, command line and outcome of every run</td></tr></table>

Table 12: Public availability of the solvers behind published Go results.

The artifact<sup>3</sup> contains the solver source and the command line and outcome of every solver run behind the reported values and measurements. Its README lists the commands that reproduce the 4×7 proof chain of Table 10 in under twenty seconds.