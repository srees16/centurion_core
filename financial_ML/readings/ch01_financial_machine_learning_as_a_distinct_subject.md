# Chapter 1: Financial Machine Learning as a Distinct Subject


CHAPTER 1
Financial Machine Learning as a
Distinct Subject
1.1
MOTIVATION
Machine learning (ML) is changing virtually every aspect of our lives. Today ML
algorithms accomplish tasks that until recently only expert humans could perform.
As it relates to finance, this is the most exciting time to adopt a disruptive technology
that will transform how everyone invests for generations. This book explains scien-
tifically sound ML tools that have worked for me over the course of two decades,
and have helped me to manage large pools of funds for some of the most demanding
institutional investors.
Books about investments largely fall in one of two categories. On one hand we
find books written by authors who have not practiced what they teach. They contain
extremely elegant mathematics that describes a world that does not exist. Just because
a theorem is true in a logical sense does not mean it is true in a physical sense. On the
other hand we find books written by authors who offer explanations absent of any
rigorous academic theory. They misuse mathematical tools to describe actual obser-
vations. Their models are overfit and fail when implemented. Academic investigation
and publication are divorced from practical application to financial markets, and
many applications in the trading/investment world are not grounded in proper science.
A first motivation for writing this book is to cross the proverbial divide that sepa-
rates academia and the industry. I have been on both sides of the rift, and I understand
how difficult it is to cross it and how easy it is to get entrenched on one side. Virtue is
in the balance. This book will not advocate a theory merely because of its mathemat-
ical beauty, and will not propose a solution just because it appears to work. My goal
is to transmit the kind of knowledge that only comes from experience, formalized in
a rigorous manner.
3


4
FINANCIAL MACHINE LEARNING AS A DISTINCT SUBJECT
A second motivation is inspired by the desire that finance serves a purpose. Over
the years some of my articles, published in academic journals and newspapers, have
expressed my displeasure with the current role that finance plays in our society.
Investors are lured to gamble their wealth on wild hunches originated by charlatans
and encouraged by mass media. One day in the near future, ML will dominate finance,
science will curtail guessing, and investing will not mean gambling. I would like the
reader to play a part in that revolution.
A third motivation is that many investors fail to grasp the complexity of ML appli-
cations to investments. This seems to be particularly true for discretionary firms mov-
ing into the “quantamental” space. I am afraid their high expectations will not be
met, not because ML failed, but because they used ML incorrectly. Over the com-
ing years, many firms will invest with off-the-shelf ML algorithms, directly imported
from academia or Silicon Valley, and my forecast is that they will lose money (to
better ML solutions). Beating the wisdom of the crowds is harder than recognizing
faces or driving cars. With this book my hope is that you will learn how to solve some
of the challenges that make finance a particularly difficult playground for ML, like
backtest overfitting. Financial ML is a subject in its own right, related to but separate
from standard ML, and this book unravels it for you.
1.2
THE MAIN REASON FINANCIAL MACHINE LEARNING
PROJECTS USUALLY FAIL
The rate of failure in quantitative finance is high, particularly so in financial ML. The
few who succeed amass a large amount of assets and deliver consistently exceptional
performance to their investors. However, that is a rare outcome, for reasons explained
in this book. Over the past two decades, I have seen many faces come and go, firms
started and shut down. In my experience, there is one critical mistake that underlies
all those failures.
1.2.1
The Sisyphus Paradigm
Discretionary portfolio managers (PMs) make investment decisions that do not fol-
low a particular theory or rationale (if there were one, they would be systematic PMs).
They consume raw news and analyses, but mostly rely on their judgment or intu-
ition. They may rationalize those decisions based on some story, but there is always
a story for every decision. Because nobody fully understands the logic behind their
bets, investment firms ask them to work independently from one another, in silos, to
ensure diversification. If you have ever attended a meeting of discretionary PMs, you
probably noticed how long and aimless they can be. Each attendee seems obsessed
about one particular piece of anecdotal information, and giant argumentative leaps
are made without fact-based, empirical evidence. This does not mean that discre-
tionary PMs cannot be successful. On the contrary, a few of them are. The point is,
they cannot naturally work as a team. Bring 50 discretionary PMs together, and they


THE MAIN REASON FINANCIAL MACHINE LEARNING PROJECTS USUALLY FAIL
5
will influence one another until eventually you are paying 50 salaries for the work of
one. Thus it makes sense for them to work in silos so they interact as little as possible.
Wherever I have seen that formula applied to quantitative or ML projects, it has
led to disaster. The boardroom’s mentality is, let us do with quants what has worked
with discretionary PMs. Let us hire 50 PhDs and demand that each of them produce an
investment strategy within six months. This approach always backfires, because each
PhD will frantically search for investment opportunities and eventually settle for (1)
a false positive that looks great in an overfit backtest or (2) standard factor investing,
which is an overcrowded strategy with a low Sharpe ratio, but at least has academic
support. Both outcomes will disappoint the investment board, and the project will
be cancelled. Even if 5 of those PhDs identified a true discovery, the profits would
not suffice to cover for the expenses of 50, so those 5 will relocate somewhere else,
searching for a proper reward.
1.2.2
The Meta-Strategy Paradigm
If you have been asked to develop ML strategies on your own, the odds are stacked
against you. It takes almost as much effort to produce one true investment strategy
as to produce a hundred, and the complexities are overwhelming: data curation and
processing, HPC infrastructure, software development, feature analysis, execution
simulators, backtesting, etc. Even if the firm provides you with shared services in
those areas, you are like a worker at a BMW factory who has been asked to build an
entire car by using all the workshops around you. One week you need to be a master
welder, another week an electrician, another week a mechanical engineer, another
week a painter . . . You will try, fail, and circle back to welding. How does that
make sense?
Every successful quantitative firm I am aware of applies the meta-strategy
paradigm (L´opez de Prado [2014]). Accordingly, this book was written as a research
manual for teams, not for individuals. Through its chapters you will learn how to set
up a research factory, as well as the various stations of the assembly line. The role of
each quant is to specialize in a particular task, to become the best there is at it, while
having a holistic view of the entire process. This book outlines the factory plan,
where teamwork yields discoveries at a predictable rate, with no reliance on lucky
strikes. This is how Berkeley Lab and other U.S. National Laboratories routinely
make scientific discoveries, such as adding 16 elements to the periodic table, or
laying out the groundwork for MRIs and PET scans.1 No particular individual is
responsible for these discoveries, as they are the outcome of team efforts where
everyone contributes. Of course, setting up these financial laboratories takes time,
and requires people who know what they are doing and have done it before. But
what do you think has a higher chance of success, this proven paradigm of organized
collaboration or the Sisyphean alternative of having every single quant rolling their
immense boulder up the mountain?
1 Berkeley Lab, http://www.lbl.gov/about.


6
FINANCIAL MACHINE LEARNING AS A DISTINCT SUBJECT
1.3
BOOK STRUCTURE
This book disentangles a web of interconnected topics and presents them in an
ordered fashion. Each chapter assumes that you have read the previous ones. Part
1 will help you structure your financial data in a way that is amenable to ML algo-
rithms. Part 2 discusses how to do research with ML algorithms on that data. Here
the emphasis is on doing research and making an actual discovery through a scien-
tific process, as opposed to searching aimlessly until some serendipitous (likely false)
result pops up. Part 3 explains how to backtest your discovery and evaluate the prob-
ability that it is false.
These three parts give an overview of the entire process, from data analysis to
model research to discovery evaluation. With that knowledge, Part 4 goes back to the
data and explains innovative ways to extract informative features. Finally, much of
this work requires a lot of computational power, so Part 5 wraps up the book with
some useful HPC recipes.
1.3.1
Structure by Production Chain
Mining gold or silver was a relatively straightforward endeavor during the 16th and
17th centuries. In less than a hundred years, the Spanish treasure fleet quadrupled
the amount of precious metals in circulation throughout Europe. Those times are
long gone, and today prospectors must deploy complex industrial methods to extract
microscopic bullion particles out of tons of earth. That does not mean that gold
production is at historical lows. On the contrary, nowadays miners extract 2,500
metric tons of microscopic gold every year, compared to the average annual 1.54
metric tons taken by the Spanish conquistadors throughout the entire 16th century!2
Visible gold is an infinitesimal portion of the overall amount of gold on Earth. El
Dorado was always there . . . if only Pizarro could have exchanged the sword for a
microscope.
The discovery of investment strategies has undergone a similar evolution. If a
decade ago it was relatively common for an individual to discover macroscopic alpha
(i.e., using simple mathematical tools like econometrics), currently the chances of that
happening are quickly converging to zero. Individuals searching nowadays for macro-
scopic alpha, regardless of their experience or knowledge, are fighting overwhelming
odds. The only true alpha left is microscopic, and finding it requires capital-intensive
industrial methods. Just like with gold, microscopic alpha does not mean smaller
overall profits. Microscopic alpha today is much more abundant than macroscopic
alpha has ever been in history. There is a lot of money to be made, but you will need
to use heavy ML tools.
Let us review some of the stations involved in the chain of production within a
modern asset manager.
2 http://www.numbersleuth.org/worlds-gold/.


BOOK STRUCTURE
7
1.3.1.1
Data Curators
This is the station responsible for collecting, cleaning, indexing, storing, adjusting,
and delivering all data to the production chain. The values could be tabulated or
hierarchical, aligned or misaligned, historical or real-time feeds, etc. Team mem-
bers are experts in market microstructure and data protocols such as FIX. They must
develop the data handlers needed to understand the context in which that data arises.
For example, was a quote cancelled and replaced at a different level, or cancelled
without replacement? Each asset class has its own nuances. For instance, bonds are
routinely exchanged or recalled; stocks are subjected to splits, reverse-splits, voting
rights, etc.; futures and options must be rolled; currencies are not traded in a central-
ized order book. The degree of specialization involved in this station is beyond the
scope of this book, and Chapter 1 will discuss only a few aspects of data curation.
1.3.1.2
Feature Analysts
This is the station responsible for transforming raw data into informative signals.
These informative signals have some predictive power over financial variables. Team
members are experts in information theory, signal extraction and processing, visual-
ization, labeling, weighting, classifiers, and feature importance techniques. For exam-
ple, feature analysts may discover that the probability of a sell-off is particularly high
when: (1) quoted offers are cancelled-replaced with market sell orders, and (2) quoted
buy orders are cancelled-replaced with limit buy orders deeper in the book. Such a
finding is not an investment strategy on its own, and can be used in alternative ways:
execution, monitoring of liquidity risk, market making, position taking, etc. A com-
mon error is to believe that feature analysts develop strategies. Instead, feature ana-
lysts collect and catalogue libraries of findings that can be useful to a multiplicity of
stations. Chapters 2–9 and 17–19 are dedicated to this all-important station.
1.3.1.3
Strategists
In this station, informative features are transformed into actual investment algorithms.
A strategist will parse through the libraries of features looking for ideas to develop
an investment strategy. These features were discovered by different analysts studying
a wide range of instruments and asset classes. The goal of the strategist is to make
sense of all these observations and to formulate a general theory that explains them.
Therefore, the strategy is merely the experiment designed to test the validity of this
theory. Team members are data scientists with a deep knowledge of financial mar-
kets and the economy. Remember, the theory needs to explain a large collection of
important features. In particular, a theory must identify the economic mechanism that
causes an agent to lose money to us. Is it a behavioral bias? Asymmetric information?
Regulatory constraints? Features may be discovered by a black box, but the strategy
is developed in a white box. Gluing together a number of catalogued features does not
constitute a theory. Once a strategy is finalized, the strategists will prepare code that
utilizes the full algorithm and submit that prototype to the backtesting team described
below. Chapters 10 and 16 are dedicated to this station, with the understanding that
it would be unreasonable for a book to reveal specific investment strategies.


8
FINANCIAL MACHINE LEARNING AS A DISTINCT SUBJECT
1.3.1.4
Backtesters
This station assesses the profitability of an investment strategy under various sce-
narios. One of the scenarios of interest is how the strategy would perform if history
repeated itself. However, the historical path is merely one of the possible outcomes of
a stochastic process, and not necessarily the most likely going forward. Alternative
scenarios must be evaluated, consistent with the knowledge of the weaknesses and
strengths of a proposed strategy. Team members are data scientists with a deep under-
standing of empirical and experimental techniques. A good backtester incorporates
in his analysis meta-information regarding how the strategy came about. In partic-
ular, his analysis must evaluate the probability of backtest overfitting by taking into
account the number of trials it took to distill the strategy. The results of this evaluation
will not be reused by other stations, for reasons that will become apparent in Chapter
11. Instead, backtest results are communicated to management and not shared with
anyone else. Chapters 11–16 discuss the analyses carried out by this station.
1.3.1.5
Deployment Team
The deployment team is tasked with integrating the strategy code into the production
line. Some components may be reused by multiple strategies, especially when they
share common features. Team members are algorithm specialists and hardcore
mathematical programmers. Part of their job is to ensure that the deployed solution
is logically identical to the prototype they received. It is also the deployment team’s
responsibility to optimize the implementation sufficiently, such that production
latency is minimized. As production calculations often are time sensitive, this team
will rely heavily on process schedulers, automation servers (Jenkins), vectoriza-
tion, multithreading, multiprocessing, graphics processing unit (GPU-NVIDIA),
distributed computing (Hadoop), high-performance computing (Slurm), and par-
allel computing techniques in general. Chapters 20–22 touch on various aspects
interesting to this station, as they relate to financial ML.
1.3.1.6
Portfolio Oversight
Once a strategy is deployed, it follows a cursus honorum, which entails the following
stages or lifecycle:
1. Embargo: Initially, the strategy is run on data observed after the end date of the
backtest. Such a period may have been reserved by the backtesters, or it may
be the result of implementation delays. If embargoed performance is consistent
with backtest results, the strategy is promoted to the next stage.
2. Paper trading: At this point, the strategy is run on a live, real-time feed. In this
way, performance will account for data parsing latencies, calculation latencies,
execution delays, and other time lapses between observation and positioning.
Paper trading will take place for as long as it is needed to gather enough evi-
dence that the strategy performs as expected.
3. Graduation: At this stage, the strategy manages a real position, whether in iso-
lation or as part of an ensemble. Performance is evaluated precisely, including
attributed risk, returns, and costs.


BOOK STRUCTURE
9
4. Re-allocation: Based on the production performance, the allocation to gradu-
ated strategies is re-assessed frequently and automatically in the context of a
diversified portfolio. In general, a strategy’s allocation follows a concave func-
tion. The initial allocation (at graduation) is small. As time passes, and the strat-
egy performs as expected, the allocation is increased. Over time, performance
decays, and allocations become gradually smaller.
5. Decommission: Eventually, all strategies are discontinued. This happens when
they perform below expectations for a sufficiently extended period of time to
conclude that the supporting theory is no longer backed by empirical evidence.
In general, it is preferable to release new variations of a strategy and run them in
parallel with old versions. Each version will go through the above lifecycle, and old
strategies will receive smaller allocations as a matter of diversification, while taking
into account the degree of confidence derived from their longer track record.
1.3.2
Structure by Strategy Component
Many investment managers believe that the secret to riches is to implement an
extremely complex ML algorithm. They are setting themselves up for a disappoint-
ment. If it was as easy as coding a state-of-the art classifier, most people in Silicon
Valley would be billionaires. A successful investment strategy is the result of mul-
tiple factors. Table 1.1 summarizes what chapters will help you address each of the
challenges involved in developing a successful investment strategy.
Throughout the book, you will find many references to journal articles I have
published over the years. Rather than repeating myself, I will often refer you to
one of them, where you will find a detailed analysis of the subject at hand. All of
my cited papers can be downloaded for free, in pre-print format, from my website:
www.QuantResearch.org.
1.3.2.1
Data
r Problem: Garbage in, garbage out.
r Solution: Work with unique, hard-to-manipulate data. If you are the only user
of this data, whatever its value, it is all for you.
r How:
◦Chapter 2: Structure your data correctly.
◦Chapter 3: Produce informative labels.
◦Chapters 4 and 5: Model non-IID series properly.
◦Chapters 17–19: Find predictive features.
1.3.2.2
Software
r Problem: A specialized task requires customized tools.
r Solution: Develop your own classes. Using popular libraries means more com-
petitors tapping the same well.


10
FINANCIAL MACHINE LEARNING AS A DISTINCT SUBJECT
TABLE 1.1
Overview of the Challenges Addressed by Every Chapter
Part
Chapter
Fin. data
Software
Hardware
Math
Meta-Strat
Overfitting
1
2
X
X
1
3
X
X
1
4
X
X
1
5
X
X
X
2
6
X
2
7
X
X
X
2
8
X
X
2
9
X
X
3
10
X
X
3
11
X
X
X
3
12
X
X
X
3
13
X
X
X
3
14
X
X
X
3
15
X
X
X
3
16
X
X
X
X
4
17
X
X
X
4
18
X
X
X
4
19
X
X
5
20
X
X
X
5
21
X
X
X
5
22
X
X
X
r How:
◦Chapters 2–22: Throughout the book, for each chapter, we develop our own
functions. For your particular problems, you will have to do the same, fol-
lowing the examples in the book.
1.3.2.3
Hardware
r Problem: ML involves some of the most computationally intensive tasks in all
of mathematics.
r Solution: Become an HPC expert. If possible, partner with a National Labora-
tory to build a supercomputer.
r How:
◦Chapters 20 and 22: Learn how to think in terms of multiprocessing architec-
tures. Whenever you code a library, structure it in such a way that functions
can be called in parallel. You will find plenty of examples in the book.
◦Chapter 21: Develop algorithms for quantum computers.
1.3.2.4
Math
r Problem: Mathematical proofs can take years, decades, and centuries. No
investor will wait that long.


BOOK STRUCTURE
11
r Solution: Use experimental math. Solve hard, intractable problems, not by proof
but by experiment. For example, Bailey, Borwein, and Plouffe [1997] found a
spigot algorithm for 𝜋(pi) without proof, against the prior perception that such
mathematical finding would not be possible.
r How:
◦Chapter 5: Familiarize yourself with memory-preserving data transforma-
tions.
◦Chapters 11–15: There are experimental methods to assess the value of your
strategy, with greater reliability than a historical simulation.
◦Chapter 16: An algorithm that is optimal in-sample can perform poorly out-
of-sample. There is no mathematical proof for investment success. Rely on
experimental methods to lead your research.
◦Chapters 17 and 18: Apply methods to detect structural breaks, and quantify
the amount of information carried by financial series.
◦Chapter 20: Learn queuing methods for distributed computing so that you
can break apart complex tasks and speed up calculations.
◦Chapter 21: Become familiar with discrete methods, used among others by
quantum computers, to solve intractable problems.
1.3.2.5
Meta-Strategies
r Problem: Amateurs develop individual strategies, believing that there is such a
thing as a magical formula for riches. In contrast, professionals develop meth-
ods to mass-produce strategies. The money is not in making a car, it is in making
a car factory.
r Solution: Think like a business. Your goal is to run a research lab like a factory,
where true discoveries are not born out of inspiration, but out of methodic hard
work. That was the philosophy of physicist Ernest Lawrence, the founder of the
first U.S. National Laboratory.
r How:
◦Chapters 7–9: Build a research process that identifies features relevant
across asset classes, while dealing with multi-collinearity of financial
features.
◦Chapter 10: Combine multiple predictions into a single bet.
◦Chapter 16: Allocate funds to strategies using a robust method that performs
well out-of-sample.
1.3.2.6
Overfitting
r Problem: Standard cross-validation methods fail in finance. Most discoveries in
finance are false, due to multiple testing and selection bias.
r Solution:
◦Whatever you do, always ask yourself in what way you may be overfitting. Be
skeptical about your own work, and constantly challenge yourself to prove
that you are adding value.


12
FINANCIAL MACHINE LEARNING AS A DISTINCT SUBJECT
◦Overfitting is unethical. It leads to promising outcomes that cannot be deliv-
ered. When done knowingly, overfitting is outright scientific fraud. The fact
that many academics do it does not make it right: They are not risking any-
one’s wealth, not even theirs.
◦It is also a waste of your time, resources, and opportunities. Besides, the
industry only pays for out-of-sample returns. You will only succeed after
you have created substantial wealth for your investors.
r How:
◦Chapters 11–15: There are three backtesting paradigms, of which historical
simulation is only one. Each backtest is always overfit to some extent, and it
is critical to learn to quantify by how much.
◦Chapter 16: Learn robust techniques for asset allocation that do not overfit
in-sample signals at the expense of out-of-sample performance.
1.3.3
Structure by Common Pitfall
Despite its many advantages, ML is no panacea. The flexibility and power of ML
techniques have a dark side. When misused, ML algorithms will confuse statisti-
cal flukes with patterns. This fact, combined with the low signal-to-noise ratio that
characterizes finance, all but ensures that careless users will produce false discov-
eries at an ever-greater speed. This book exposes some of the most pervasive errors
made by ML experts when they apply their techniques on financial datasets. Some of
these pitfalls are listed in Table 1.2, with solutions that are explained in the indicated
chapters.
1.4
TARGET AUDIENCE
This book presents advanced ML methods specifically designed to address the chal-
lenges posed by financial datasets. By “advanced” I do not mean extremely difficult to
grasp, or explaining the latest reincarnation of deep, recurrent, or convolutional neu-
ral networks. Instead, the book answers questions that senior researchers, who have
experience applying ML algorithms to financial problems, will recognize as critical.
If you are new to ML, and you do not have experience working with complex algo-
rithms, this book may not be for you (yet). Unless you have confronted in practice the
problems discussed in these chapters, you may have difficulty understanding the util-
ity of solving them. Before reading this book, you may want to study several excellent
introductory ML books published in recent years. I have listed a few of them in the
references section.
The core audience of this book is investment professionals with a strong ML back-
ground. My goals are that you monetize what you learn in this book, help us mod-
ernize finance, and deliver actual value for investors.
This book also targets data scientists who have successfully implemented ML
algorithms in a variety of fields outside finance. If you have worked at Google and
have applied deep neural networks to face recognition, but things do not seem to


REQUISITES
13
TABLE 1.2
Common Pitfalls in Financial ML
#
Category
Pitfall
Solution
Chapter
1
Epistemological
The Sisyphus paradigm
The meta-strategy
paradigm
1
2
Epistemological
Research through
backtesting
Feature importance
analysis
8
3
Data processing
Chronological
sampling
The volume clock
2
4
Data processing
Integer differentiation
Fractional
differentiation
5
5
Classification
Fixed-time horizon
labeling
The triple-barrier
method
3
6
Classification
Learning side and size
simultaneously
Meta-labeling
3
7
Classification
Weighting of non-IID
samples
Uniqueness weighting;
sequential
bootstrapping
4
8
Evaluation
Cross-validation
leakage
Purging and
embargoing
7, 9
9
Evaluation
Walk-forward
(historical) backtesting
Combinatorial purged
cross-validation
11, 12
10
Evaluation
Backtest overfitting
Backtesting on
synthetic data; the
deflated Sharpe ratio
10–16
work so well when you run your algorithms on financial data, this book will help
you. Sometimes you may not understand the financial rationale behind some struc-
tures (e.g., meta-labeling, the triple-barrier method, fracdiff), but bear with me: Once
you have managed an investment portfolio long enough, the rules of the game will
become clearer to you, along with the meaning of these chapters.
1.5
REQUISITES
Investment management is one of the most multi-disciplinary areas of research, and
this book reflects that fact. Understanding the various sections requires a practical
knowledge of ML, market microstructure, portfolio management, mathematical
finance, statistics, econometrics, linear algebra, convex optimization, discrete
math, signal processing, information theory, object-oriented programming, parallel
processing, and supercomputing.
Python has become the de facto standard language for ML, and I have to assume
that you are an experienced developer. You must be familiar with scikit-learn
(sklearn), pandas, numpy, scipy, multiprocessing, matplotlib and a few other libraries.


14
FINANCIAL MACHINE LEARNING AS A DISTINCT SUBJECT
Code snippets invoke functions from these libraries using their conventional prefix,
pd for pandas, np for numpy, mpl for matplotlib, etc. There are numerous books on
each of these libraries, and you cannot know enough about the specifics of each one.
Throughout the book we will discuss some issues with their implementation, includ-
ing unresolved bugs to keep in mind.
1.6
FAQs
How can ML algorithms be useful in finance?
Many financial operations require making decisions based on pre-defined rules, like
option pricing, algorithmic execution, or risk monitoring. This is where the bulk of
automation has taken place so far, transforming the financial markets into ultra-fast,
hyper-connected networks for exchanging information. In performing these tasks,
machines were asked to follow the rules as fast as possible. High-frequency trading
is a prime example. See Easley, L´opez de Prado, and O’Hara [2013] for a detailed
treatment of the subject.
The algorithmization of finance is unstoppable. Between June 12, 1968, and
December 31, 1968, the NYSE was closed every Wednesday, so that back office could
catch up with paperwork. Can you imagine that? We live in a different world today,
and in 10 years things will be even better. Because the next wave of automation does
not involve following rules, but making judgment calls. As emotional beings, subject
to fears, hopes, and agendas, humans are not particularly good at making fact-based
decisions, particularly when those decisions involve conflicts of interest. In those sit-
uations, investors are better served when a machine makes the calls, based on facts
learned from hard data. This not only applies to investment strategy development, but
to virtually every area of financial advice: granting a loan, rating a bond, classifying
a company, recruiting talent, predicting earnings, forecasting inflation, etc. Further-
more, machines will comply with the law, always, when programmed to do so. If a
dubious decision is made, investors can go back to the logs and understand exactly
what happened. It is much easier to improve an algorithmic investment process than
one relying entirely on humans.
How can ML algorithms beat humans at investing?
Do you remember when people were certain that computers would never beat humans
at chess? Or Jeopardy!? Poker? Go? Millions of years of evolution (a genetic algo-
rithm) have fine-tuned our ape brains to survive in a hostile 3-dimensional world
where the laws of nature are static. Now, when it comes to identifying subtle patterns
in a high-dimensional world, where the rules of the game change every day, all
that fine-tuning turns out to be detrimental. An ML algorithm can spot patterns in a
100-dimensional world as easily as in our familiar 3-dimensional one. And while we
all laugh when we see an algorithm make a silly mistake, keep in mind, algorithms
have been around only a fraction of our millions of years. Every day they get better
at this, we do not. Humans are slow learners, which puts us at a disadvantage in a
fast-changing world like finance.


FAQs
15
Does that mean that there is no space left for human investors?
Not at all. No human is better at chess than a computer. And no computer is better
at chess than a human supported by a computer. Discretionary PMs are at a disad-
vantage when betting against an ML algorithm, but it is possible that the best results
are achieved by combining discretionary PMs with ML algorithms. This is what has
come to be known as the “quantamental” way. Throughout the book you will find
techniques that can be used by quantamental teams, that is, methods that allow you
to combine human guesses (inspired by fundamental variables) with mathematical
forecasts. In particular, Chapter 3 introduces a new technique called meta-labeling,
which allows you to add an ML layer on top of a discretionary one.
How does financial ML differ from econometrics?
Econometrics is the application of classical statistical methods to economic and finan-
cial series. The essential tool of econometrics is multivariate linear regression, an
18th-century technology that was already mastered by Gauss before 1794 (Stigler
[1981]). Standard econometric models do not learn. It is hard to believe that some-
thing as complex as 21st-century finance could be grasped by something as simple
as inverting a covariance matrix.
Every empirical science must build theories based on observation. If the statistical
toolbox used to model these observations is linear regression, the researcher will fail
to recognize the complexity of the data, and the theories will be awfully simplistic,
useless. I have no doubt in my mind, econometrics is a primary reason economics
and finance have not experienced meaningful progress over the past decades (Calkin
and L´opez de Prado [2014a, 2014b]).
For centuries, medieval astronomers made observations and developed theo-
ries about celestial mechanics. These theories never considered non-circular orbits,
because they were deemed unholy and beneath God’s plan. The prediction errors were
so gross, that ever more complex theories had to be devised to account for them. It was
not until Kepler had the temerity to consider non-circular (elliptical) orbits that all of
the sudden a much simpler general model was able to predict the position of the plan-
ets with astonishing accuracy. What if astronomers had never considered non-circular
orbits? Well . . . what if economists finally started to consider non-linear functions?
Where is our Kepler? Finance does not have a Principia because no Kepler means no
Newton.
What do you say to people who dismiss ML algorithms as black boxes?
If you are reading this book, chances are ML algorithms are white boxes to you.
They are transparent, well-defined, crystal-clear, pattern-recognition functions. Most
Financial ML methods do not replace theory. They guide it. An ML algorithm
learns complex patterns in a high-dimensional space without being specifically
directed. Once we understand what features are predictive of a phenomenon, we
can build a theoretical explanation, which can be tested on an independent dataset.
Students of economics and finance would do well enrolling in ML courses, rather
than econometrics. Econometrics may be good enough to succeed in financial
academia (for now), but succeeding in business requires ML.


16
FINANCIAL MACHINE LEARNING AS A DISTINCT SUBJECT
people do not have your knowledge, and to them ML is like a magician’s box: “Where
did that rabbit come from? How are you tricking us, witch?” People mistrust what they
do not understand. Their prejudices are rooted in ignorance, for which the Socratic
remedy is simple: education. Besides, some of us enjoy using our brains, even though
neuroscientists still have not figured out exactly how they work (a black box in itself).
From time to time you will encounter Luddites, who are beyond redemption. Ned
Ludd was a weaver from Leicester, England, who in 1779 smashed two knitting
frames in an outrage. With the advent of the industrial revolution, mobs infuriated by
mechanization sabotaged and destroyed all machinery they could find. Textile work-
ers ruined so much industrial equipment that Parliament had to pass laws making
“machine breaking” a capital crime. Between 1811 and 1816, large parts of Eng-
land were in open rebellion, to the point that there were more British troops fighting
Luddites than there were fighting Napoleon on the Iberian Peninsula. The Luddite
rebellion ended with brutal suppression through military force. Let us hope that the
black box movement does not come to that.
Why don’t you discuss specific ML algorithms?
The book is agnostic with regards to the particular ML algorithm you choose.
Whether you use convolutional neural networks, AdaBoost, RFs, SVMs, and so on,
there are many shared generic problems you will face: data structuring, label-
ing, weighting, stationary transformations, cross-validation, feature selection, fea-
ture importance, overfitting, backtesting, etc. In the context of financial modeling,
answering these questions is non-trivial, and framework-specific approaches need to
be developed. That is the focus of this book.
What other books do you recommend on this subject?
To my knowledge, this is the first book to provide a complete and systematic treatment
of ML methods specific for finance: starting with a chapter dedicated to financial data
structures, another chapter for labeling of financial series, another for sample weight-
ing, time series differentiation, . . . all the way to a full part devoted to the proper back-
testing of investment strategies. To be sure, there are a handful of prior publications
(mostly journal articles) that have applied standard ML to financial series, but that
is not what this book offers. My goal has been to address the unique nuisances that
make financial ML modeling particularly challenging. Like any new subject, it is fast
evolving, and the book will be updated as major advances take place. Please contact
me at mldp@quantresearch.org if there is any particular topic you would like to see
treated in future editions. I will gladly add those chapters, while acknowledging the
names of those readers who suggested them.
I do not understand some of the sections and chapters. What should I do?
My advice is that you start by reading the references listed at the end of the chapter.
When I wrote the book, I had to assume the reader was familiar with the existing
literature, or this book would lose its focus. If after reading those references the sec-
tions still do not make sense, the likely reason is that they are related to a problem
well understood by investment professionals (even if there is no mention of it in the


FAQs
17
literature). For example, Chapter 2 will discuss effective methods to adjust futures
prices for the roll, a problem known to most practitioners, even though it is rarely
addressed in textbooks. I would encourage you to attend one of my regular seminars,
and ask me your question at the end of my talk.
Why is the book so fixated on backtest overfitting?
There are two reasons. First, backtest overfitting is arguably the most important open
problem in all of mathematical finance. It is our equivalent to “P versus NP” in com-
puter science. If there was a precise method to prevent backtest overfitting, we would
be able to take backtests to the bank. A backtest would be almost as good as cash,
rather than a sales pitch. Hedge funds would allocate funds to portfolio managers
with confidence. Investors would risk less, and would be willing to pay higher fees.
Regulators would grant licenses to hedge fund managers on the basis of reliable evi-
dence of skill and knowledge, leaving no space for charlatans. In my opinion, an
investments book that does not address this issue is not worth your time. Why would
you read a book that deals with CAPM, APT, asset allocation techniques, risk man-
agement, etc. when the empirical results that support those arguments were selected
without determining their false discovery probabilities?
The second reason is that ML is a great weapon in your research arsenal, and a
dangerous one to be sure. If backtest overfitting is an issue in econometric analysis,
the flexibility of ML makes it a constant threat to your work. This is particularly the
case in finance, because our datasets are shorter, with lower signal-to-noise ratio, and
we do not have laboratories where we can conduct experiments while controlling
for all environmental variables (L´opez de Prado [2015]). An ML book that does not
tackle these concerns can be more detrimental than beneficial to your career.
What is the mathematical nomenclature of the book?
When I started to write this book, I thought about assigning one symbol to each math-
ematical variable or function through all the chapters. That would work well if this
book dealt with a single subject, like stochastic optimal control. However this book
deals with a wide range of mathematical subjects, each with its own conventions.
Readers would find it harder to consult references unless I also followed literature
standards, which means that sometimes we must re-use symbols. To prevent any
confusion, every chapter explains the nomenclature as it is being used. Most of the
math is accompanied by a code snippet, so in case of doubt, please always follow
the code.
Who wrote Chapter 22?
A popular perception is that ML is a new fascinating technology invented or perfected
at IBM, Google, Facebook, Amazon, Netflix, Tesla, etc. It is true that technology firms
have become heavy users of ML, especially in recent years. Those firms sponsored
some of the most publicized recent ML achievements (like Jeopardy! or Go), which
may have reinforced that perception.
However, the reader may be surprised to learn that, in fact, U.S. National Labo-
ratories are among the research centers with the longest track record and experience


18
FINANCIAL MACHINE LEARNING AS A DISTINCT SUBJECT
in using ML. These centers utilized ML before it was cool, and they applied it suc-
cessfully for many decades to produce astounding scientific discoveries. If predicting
what movies Netflix should recommend you to watch next is a worthy endeavor, so it
is to understand the rate of expansion of the universe, or forecasting what coastlines
will be most impacted by global warming, or preventing a cataclysmic failure of our
national power grid. These are just some of the amazing questions that institutions
like Berkeley Lab work on every day, quietly but tirelessly, with the help of ML.
In Chapter 22, Drs. Horst Simon and Kesheng Wu offer the perspective of a deputy
director and a project leader at a major U.S. National Laboratory specializing in large-
scale scientific research involving big data, high-performance computing, and ML.
Unlike traditional university settings, National Laboratories achieve scientific break-
throughs by putting together interdisciplinary teams that follow well-devised proce-
dures, with strong division of labor and responsibilities. That kind of research model
by production chain was born at Berkeley Lab almost 90 years ago and inspired the
meta-strategy paradigm explained in Sections 1.2.2 and 1.3.1.
1.7
ACKNOWLEDGMENTS
Dr. Horst Simon, who is the deputy director of Lawrence Berkeley National
Laboratory, accepted to co-author Chapter 22 with Dr. Kesheng Wu, who leads
several projects at Berkeley Lab and the National Energy Research Scientific
Computing Center (NERSC).3 ML requires extreme amounts of computing power,
and my research would not have been possible without their generous support and
guidance. In that chapter, Horst and Kesheng explain how Berkeley Lab satisfies the
supercomputing needs of researchers worldwide, and the instrumental role played
by ML and big data in today’s scientific breakthroughs.
Prof. Riccardo Rebonato was the first to read this manuscript and encouraged me
to publish it. My many conversations with Prof. Frank Fabozzi on these topics were
instrumental in shaping the book in its current form. Very few people in academia
have Frank’s and Riccardo’s industry experience, and very few people in the industry
have Riccardo’s and Frank’s academic pedigree.
Over the past two decades, I have published nearly a hundred works on this book’s
subject, including journal articles, books, chapters, lectures, source code, etc. In my
latest count, these works were co-authored with more than 30 leading experts in this
field, including Prof. David H. Bailey (15 articles), Prof. David Easley (8 articles),
Prof. Maureen O’Hara (8 articles), and Prof. Jonathan M. Borwein (6 articles). This
book is to a great extent also theirs, for it would not have been possible without their
support, insights, and continuous exchange of ideas over the years. It would take too
long to give them proper credit, so instead I have published the following link where
you can find our collective effort: http://www.quantresearch.org/Co-authors.htm.
Last but not least, I would like to thank some of my research team members for
proofreading the book and helping me produce some of the figures: Diego Aparicio,
3 http://www.nersc.gov/about.


EXERCISES
19
Dr. Lee Cohn, Dr. Michael Lewis, Dr. Michael Lock, Dr. Yaxiong Zeng, and
Dr. Zhibai Zhang.
EXERCISES
1.1 Are you aware of firms that have attempted to transition from discretionary
investments to ML-led investments, or blending them into what they call “quan-
tamental” funds?
(a) Have they succeeded?
(b) What are the cultural difficulties involved in this transition?
1.2 What is the most important open problem in mathematical finance? If this prob-
lem was resolved, how could:
(a) regulators use it to grant investment management licenses?
(b) investors use it to allocate funds?
(c) firms use it to reward researchers?
1.3 According to Institutional Investor, only 17% of hedge fund assets are managed
by quantitative firms. That is about $500 billion allocated in total across all
quantitative funds as of June 2017, compared to $386 billion a year earlier.
What do you think is driving this massive reallocation of assets?
1.4 According to Institutional Investor’s Rich List, how many quantitative invest-
ment firms are placed within the top 10 most profitable firms? How does that
compare to the proportion of assets managed by quantitative funds?
1.5 What is the key difference between econometric methods and ML? How would
economics and finance benefit from updating their statistical toolkit?
1.6 Science has a very minimal understanding of how the human brain (or any brain)
works. In this sense, the brain is an absolute black box. What do you think
causes critics of financial ML to disregard it as a black box, while embracing
discretionary investing?
1.7 You read a journal article that describes an investment strategy. In a backtest, it
achieves an annualized Sharpe ratio in excess of 2, with a confidence level of
95%. Using their dataset, you are able to reproduce their result in an independent
backtest. Why is this discovery likely to be false?
1.8 Investment advisors are plagued with conflicts of interest while making deci-
sions on behalf of their investors.
(a) ML algorithms can manage investments without conflict of interests. Why?
(b) Suppose that an ML algorithm makes a decision that leads to a loss. The
algorithm did what it was programmed to do, and the investor agreed to the
terms of the program, as verified by forensic examination of the computer
logs. In what sense is this situation better for the investor, compared to a
loss caused by a discretionary PM’s poor judgment? What is the investor’s
recourse in each instance?
(c) Would it make sense for financial advisors to benchmark their decisions
against the decisions made by such neutral agents?


20
FINANCIAL MACHINE LEARNING AS A DISTINCT SUBJECT
REFERENCES
Bailey, D., P. Borwein, and S. Plouffe (1997): “On the rapid computation of various polylogarithmic
constants.” Mathematics of Computation, Vol. 66, No. 218, pp. 903–913.
Calkin, N. and M. L´opez de Prado (2014a): “Stochastic flow diagrams.” Algorithmic Finance, Vol.
3, No. 1, pp. 21–42.
Calkin, N. and M. L´opez de Prado (2014b): “The topology of macro financial flows: An application
of stochastic flow diagrams.” Algorithmic Finance, Vol. 3, No. 1, pp. 43–85.
Easley, D., M. L´opez de Prado, and M. O’Hara (2013): High-Frequency Trading, 1st ed. Risk Books.
L´opez de Prado, M. (2014): “Quantitative meta-strategies.” Practical Applications, Institutional
Investor Journals, Vol. 2, No. 3, pp. 1–3.
L´opez de Prado, M. (2015): “The Future of Empirical Finance.” Journal of Portfolio Management,
Vol. 41, No. 4, pp. 140–144.
Stigler, Stephen M. (1981): “Gauss and the invention of least squares.” Annals of Statistics, Vol. 9,
No. 3, pp. 465–474.
BIBLIOGRAPHY
Abu-Mostafa, Y., M. Magdon-Ismail, and H. Lin (2012): Learning from Data, 1st ed. AMLBook.
Akansu, A., S. Kulkarni, and D. Malioutov (2016): Financial Signal Processing and Machine Learn-
ing, 1st ed. John Wiley & Sons-IEEE Press.
Aronson, D. and T. Masters (2013): Statistically Sound Machine Learning for Algorithmic Trading
of Financial Instruments: Developing Predictive-Model-Based Trading Systems Using TSSB,
1st ed. CreateSpace Independent Publishing Platform.
Boyarshinov, V. (2012): Machine Learning in Computational Finance: Practical Algorithms for
Building Artificial Intelligence Applications, 1st ed. LAP LAMBERT Academic Publishing.
Cerniglia, J., F. Fabozzi, and P. Kolm (2016): “Best practices in research for quantitative equity
strategies.” Journal of Portfolio Management, Vol. 42, No. 5, pp. 135–143.
Chan, E. (2017): Machine Trading: Deploying Computer Algorithms to Conquer the Markets, 1st
ed. John Wiley & Sons.
Gareth, J., D. Witten, T. Hastie, and R. Tibshirani (2013): An Introduction to Statistical Learning:
with Applications in R, 1st ed. Springer.
Geron, A. (2017): Hands-On Machine Learning with Scikit-Learn and TensorFlow: Concepts, Tools,
and Techniques to Build Intelligent Systems, 1st ed. O’Reilly Media.
Gyorfi, L., G. Ottucsak, and H. Walk (2012): Machine Learning for Financial Engineering, 1st ed.
Imperial College Press.
Hackeling, G. (2014): Mastering Machine Learning with Scikit-Learn, 1st ed. Packt Publishing.
Hastie, T., R. Tibshirani, and J. Friedman (2016): The Elements of Statistical Learning, 2nd ed.
Springer-Verlag.
Hauck, T. (2014): Scikit-Learn Cookbook, 1st ed. Packt Publishing.
McNelis, P. (2005): Neural Networks in Finance, 1st ed. Academic Press.
Raschka, S. (2015): Python Machine Learning, 1st ed. Packt Publishing.
