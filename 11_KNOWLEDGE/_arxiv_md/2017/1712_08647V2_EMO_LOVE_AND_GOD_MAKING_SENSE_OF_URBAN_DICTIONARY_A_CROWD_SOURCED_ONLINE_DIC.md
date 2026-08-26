---
canon-group: reference
rscf-state: source-claim
arxiv_id: 1712.08647v2
source: arxiv
tags: [arxiv, knowledge, reference, unclassified]
---
# 1712.08647v2_Emo__Love__and_God__Making_Sense_of_Urban_Dictionary__a_Crowd-Sourced_Online_Dic

> Source: 1712.08647v2_Emo__Love__and_God__Making_Sense_of_Urban_Dictionary__a_Crowd-Sourced_Online_Dic.pdf

> Pages: 17

---


## Page 1


Subject Areas:
human-computer interaction
Keywords:
Natural language processing,
Linguistic innovation, Computational
sociolinguistics, Human-computer
interaction
Author for correspondence:
Dong Nguyen
e-mail: dnguyen@turing.ac.uk
Emo, Love, and God: Making
Sense of Urban Dictionary,
a Crowd-Sourced Online
Dictionary
Dong Nguyen1,2, Barbara McGillivray1,3,
and Taha Yasseri1,4
1The Alan Turing Institute, London, UK.
2Institute for Language, Cognition and Computation,
School of Informatics, University of Edinburgh,
Edinburgh, UK.
3Theoretical and Applied Linguistics, Faculty of
Modern and Medieval Languages, University of
Cambridge, Cambridge, UK.
4Oxford Internet Institute, University of Oxford, Oxford,
UK.
The Internet facilitates large-scale collaborative projects
and the emergence of Web 2.0 platforms, where
producers and consumers of content unify, has
drastically changed the information market. On the
one hand, the promise of the "wisdom of the
crowd" has inspired successful projects such as
Wikipedia, which has become the primary source
of crowd-based information in many languages. On
the other hand, the decentralized and often un-
monitored environment of such projects may make
them susceptible to low quality content. In this
work, we focus on Urban Dictionary, a crowd-
sourced online dictionary. We combine computational
methods with qualitative annotation and shed light
on the overall features of Urban Dictionary in
terms of growth, coverage and types of content. We
measure a high presence of opinion-focused entries,
as opposed to the meaning-focused entries that we
expect from traditional dictionaries. Furthermore,
Urban Dictionary covers many informal, unfamiliar
words as well as proper nouns. Urban Dictionary
also contains offensive content, but highly offensive
content tends to receive lower scores through the
dictionary’s voting system. The low threshold to
include new material in Urban Dictionary enables
quick recording of new words and new meanings,
but the resulting heterogeneous content can pose
challenges in using Urban Dictionary as a source to
study language innovation.
arXiv:1712.08647v2  [cs.CL]  5 Apr 2018


## Page 2


2
.
1. Introduction
Contemporary information communication technologies open up new ways of cooperation
leading to the emergence of large-scale crowd-sourced collaborative projects [1]. Examples of
such projects are open software development [2], citizen science campaigns [3], and most notably
Wikipedia [4]. All these projects are based on contributions from volunteers, often anonymous
and non-experts. Although the success of most of these examples is beyond expectation, there
are challenges and shortcomings to be considered as well. In the case of Wikipedia for instance,
inaccuracies [5], edit wars and destructive interactions between contributors [6,7], and biases in
coverage and content [8,9], are only a few to name among many undesirable aspects of the project
that have been studied in detail.
The affordances of Internet-mediated crowd-sourced platforms has also led to the emergence
of crowd-sourced online dictionaries. Language is constantly changing. Over time, new words
enter the lexicon, others become obsolete, and existing words acquire new meanings (i.e. senses)
[10]. Dictionaries record new words and new meanings, are regularly updated, and sometimes
used as a source to study language change [11]. However, a new word or a new meaning
needs to have enough evidence backing it up before it can enter a traditional dictionary. For
example, selﬁe was the Oxford dictionaries word of the year in 2013 and its frequency in
the English language increased by 17,000% in that year. Its ﬁrst recorded use dates back to
2002,1 but was only added to OxfordDictionaries.com in August 2013. Even though some of
the traditional online dictionaries, such as Oxford Dictionaries2 or Macmillan Dictionary,3 have
considered implementing crowdsourcing in their workﬂow [12] (see [13, p. 3-6] for a typology of
crowdsourcing activities in lexicography), for most, they rely on professional lexicographers to
select, design, and compile their entries.
Unlike traditional online dictionaries [13, p. 11], the content in crowd-sourced online
dictionaries comes from non-professional contributors and popular examples are Urban
Dictionary4 and Wiktionary [14].5 Collaborative online dictionaries are constantly updated and
have a lower threshold for including new material compared to traditional dictionaries [13,
p. 2]. Moreover, it has also been suggested that such dictionaries might be driving linguistic
change, not only reﬂecting it [15,16]. Crowd-sourced dictionaries could potentially complement
online sources such as Twitter, blogs and websites (e.g., [17–19]) to study language innovation.
However, such dictionaries are subject to spam and vandalism, as well as “unspeciﬁc, incorrect,
outdated, oversimpliﬁed, or overcomplicated descriptions” [12]. Another concern affecting
such collaborative dictionaries is the question of whether their content reﬂects real language
innovation, as opposed to the concerns of a speciﬁc community of users, their opinions, and
generally neologisms and new word meanings that will not last in the language.
This paper presents an explorative study of Urban Dictionary (UD), an online crowd-sourced
dictionary founded in December 1999. Users contribute by submitting an entry describing a word
and a word might therefore have multiple entries. According to Aaron Peckham, its founder,
“People write really opinionated deﬁnitions and incorrect deﬁnitions. There are also ones that have poor
spelling and poor grammar [. . .] I think reading those makes deﬁnitions more entertaining and sometimes
more accurate and honest than a heavily researched dictionary deﬁnition.” [20]. An UD entry for selﬁe
is shown in Figure 1, in which selﬁe is deﬁned as ‘The beginning of the end of intelligent civilization.’
and accompanied with an example usage ‘Future sociologists use the selﬁe as an artifact for the end of
times’. Furthermore, entries can contain tags (e.g., #picture, #photograph). In total, Urban Dictionary
contains 76 entries for selﬁe (July 2016), the earliest submitted in 2009, and a range of variations
(e.g., selﬁe-conscious, selﬁed, selﬁeing and selﬁe-esteem). Overall, there are 353 entries that describe
1http://blog.oxforddictionaries.com/press-releases/oxforddictionaries-word-of-the-year-
2013/
2https://www.oxforddictionaries.com
3https://www.macmillandictionary.com
4https://www.urbandictionary.com/
5https://en.wiktionary.org/


## Page 3


3
.
Figure 1: An Urban Dictionary entry for selﬁe.
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
0
25
50
75
100
125
2010
2012
2014
2016
time (year)
number of new definitions per year
G
G variations
selfie
Figure 2: The number of new deﬁnitions
for selﬁe and its variations per year (Dec
1999 – July 2016).
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
0
10
20
30
40
2004
2008
2012
2016
time (year)
number of new definitions per year
G
G
G
fleek
on.fleek
variations
Figure 3: The number of new deﬁnitions
for ﬂeek and on ﬂeek and other variations
per year (Dec 1999 – July 2016).
a word (or phrase) containing the string selﬁe (see Figure 2 for a plot over time). Figure 3 shows
a similar plot for ﬂeek and on ﬂeek, a phrase that went viral in 2014. UD thus not only captures
new words rapidly, but it also captures the many variations that arise over time. Furthermore, the
personal, informal, and often offensive nature of the content in this popular site is different from
the content typically found in both traditional dictionaries (see e. g. [13, p. 3-4] and [13, p. 7]) and
more regulated collaborative dictionaries like Wiktionary. The status of UD as source of evidence
for popular and current usage is widely recognized [21–23] and it has even been consulted in
some legal cases [24]. UD has also been used as a source to cross-check emerging word forms
identiﬁed through Twitter [18].
Urban Dictionary has also been used for the development of natural language processing
systems that have to deal with informal language, non-standard language, and slang. For
example, UD has been consulted when building a text normalization system for Twitter [25] and
it has been used to create more training data for a Twitter-speciﬁc sentiment lexicon [26]. In a
recent study, Urban Dictionary is used to automatically generate explanations of non-standard
words and phrases [24].
While Urban Dictionary seems to be a promising resource to record and analyze language
innovation, so far little is known about the characteristics of its content. In this study we take
the ﬁrst step towards characterizing UD. So far, UD has been featured in a few studies, but
these qualitative analyses were based on a small number of entries [23,27]. We study a complete
snapshot (Dec 1999 – July 2016) of all the entries in the dictionary as well as selected samples
using content analysis methods. To the best of our knowledge, this is the ﬁrst systematic study of
Urban Dictionary at this scale.


## Page 4


4
.
2. Results
We start with presenting an overall picture of Urban Dictionary (Section 2 (a)), such as its growth
and how content is distributed. Next, we compare its size to Wiktionary based on the number of
headwords (Section 2 (b)). We then present results based on two crowdsourcing experiments in
which we analyze the types of content and the offensiveness of the entries (Section 2 (c)). Finally,
we discuss how characteristics of the entries relate to their popularity on UD (Section 2 (d)).
(a) Overall picture
Since its inception in 1999, UD has had a rather steady growth. Figure 4 shows the number of
new entries added each week. So far, UD has collected 1,620,438 headwords (after lower casing)6
and 2,661,625 entries with an average of 1.643 entries per headword. However, as depicted in
Figure 5 (left), the distribution of the number of entries for each headword varies tremendously
from one headword to another. While the majority of headwords have only one deﬁnition, there
are headwords with more than 1,000 deﬁnitions. Table 1 reports the headwords with the largest
number of deﬁnitions.
0
5000
10000
15000
20000
2000
2005
2010
2015
time (week)
number of definitions per week
Figure 4: Number of contributed deﬁnitions to
Urban Dictionary per week since its inception
in 1999.
Headword
# Deﬁnitions
emo
1,204
love
1,140
god
706
urban dictionary
701
chode
614
canada’s history
583
sex
558
school
555
cunt
541
scene
537
Table 1: Headwords with the most deﬁnitions.
This fat-tailed, almost power-law distribution is not limited to the number of deﬁnitions per
headword; the number of deﬁnitions contributed by each user follows a similar distribution,
shown in Figure 5 (right). The majority of users have contributed only once, while there are
few power-users with more than 1,000 contributed deﬁnitions. These types of distributions are
common in self-organized human systems, particularly similar crowd-based systems such as
Wikipedia [28,29] or the citizen science projects Zooniverse [3], social media activity levels such
as on Twitter [30], or content sharing systems such as Reddit or Digg [31].
A noteworthy feature of UD is that users can express their evaluation of different deﬁnitions
for each headword by up or down voting the deﬁnition. There is little to no guideline on "what
a good deﬁnition is" in UD and users are supposed to judge the quality of the deﬁnitions
based on their own subjective perception of how an urban dictionary should be. Figure 6 (left)
shows the distribution of the number of up/down votes that each deﬁnition has received
among all the deﬁnitions of all the headwords. A similar pattern is evident, in which many
deﬁnitions have received very few votes (both up and down) and few deﬁnitions have many
votes. Figure 6 (middle) shows a scatter plot of the number of down votes versus the number of
up votes for each deﬁnition. There is a striking correlation between the number of up and down
votes for each deﬁnition which emphasizes the role of visibility rather than quality in the number
6 We use ‘headword’ to refer to the title under which a set of deﬁnitions appear. For example, in Wiktionary, the page about
bank covers different part of speech (e.g., noun and verb) as well as the different senses. In the context of UD, we use ‘entry’
to refer to an individual content contribution (e.g., the combination of headword, deﬁnition, example text and tags submitted
by a user). Due to the heterogeneity in UD, we lower cased the headwords to calculate this statistic. This follows the interface
of UD, which also does not match on case when grouping entries.


## Page 5


5
.
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
10−8
10−6
10−4
10−2
100
100
101
102
103
number of definitions per word
pdf
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
G
10−10
10−8
10−6
10−4
10−2
100
100
102
104
number of definitions per user
pdf
Figure 5: The probability density function of left: the number of deﬁnitions contributed to each
headword and, right: the number of deﬁnitions contributed by each user of Urban Dictionary
(logarithmic binning). Both axes are logarithmically scaled.
0
25000
50000
75000
0
1
2
3
4
5
log10(number of votes per definition + 1)
count
up
down
0
25000
50000
75000
100000
−4
−2
0
2
4
log10((U+1)/(D+1))
count
Figure 6: left: histogram of the number of votes of each deﬁnition, middle: scatter plot of the
number of up votes and down votes that each deﬁnition has received, with error bars for bins
and a ﬁtted line, right: the histogram of the ratio of up votes (U) to down votes (D) of each
deﬁnition.
of votes. However, there seems to be a systematic deviation from a perfect correlation in which
the number of up votes generally outperforms the number of down votes. This is more evident in
Figure 6 (right), where the distribution of the ratio of up votes to down votes is shown. Evidently,
there is a wide variation among the deﬁnitions with some having more than ten times more up
votes than down votes and some the other way around.
(b) Number of headwords
We now compare the number of unique headwords in Urban Dictionary to the number of
unique headwords in Wiktionary, another crowdsourced dictionary. Wiktionary manifests a
different policy than Urban Dictionary. The content in Wiktionary is created and maintained by
administrators (selected by the community), registered users, and anonymous contributors [14].
In contrast to UD, there are many different mechanisms in Wiktionary to ensure that the content
adheres to the community guidelines. Each page is accompanied by a talk page, where users can
discuss the content of the page and resolve any possible conﬂicts. Furthermore, in Wiktionary
guidelines can be found for the structure and content of the entries. Capitalization is consistent
and content or headwords that do not meet the Wiktionary guidelines are removed. For example,
while both UD and Wiktionary have misspelled headwords (e.g., beleive for believe), Wiktionary
guidelines state that only common misspellings should be included while rare misspellings
should be excluded7. In contrast, such guidelines are not present in UD. Wiktionary entries thus
undergo a deeper level of curation.
Because of the inconsistent capitalization in UD, we experiment with three approaches to
match the headwords between both dictionaries: no preprocessing, lower casing of all characters,
7https://en.wiktionary.org/wiki/Wiktionary:Criteria_for_inclusion (17 February, 2018)


## Page 6


6
.
No processing
All lowercase
Mixed
Overlap
93,167
(4%)
112,762
(5%)
108,361
(5%)
Only UD
1,698,812
(72%)
1,507,675
(70%)
1,565,794
(70%)
Only Wiktionary
569,787
(24%)
540,641
(25%)
546,263
(25%)
Total
2,361,766
2,161,078
2,220,418
Table 2: Headword comparison between UD and Wiktionary. The table reports the unique
number of headwords in each category. No threshold was applied.
and mixed.8 Table 2 reports the result of this matching. The number of unique headwords in UD
is much higher and the lexical overlap is relatively low. Sometimes there is a match on the lexical
level (i.e. the headwords match), but UD or Wiktionary cover different or additional meanings.
For example, phased is described in UD as ’something being done bit by bit – in phases’, a meaning
also covered in Wiktionary. However, UD also describes several other meanings, including ’A
word that is used when your asking if someone wants to ﬁght.’ and ’to be "buzzed." when you
arent drunk, but arent sober.’.
Because there is little curation of UD content, there are many headwords that would not
typically be included in a dictionary. Examples include nick names and proper names (e.g.
shaskank deﬁned as ‘Akshay Kaushik’s nick name for his boyfriend Shashank.’; dan taylor, deﬁned
as ‘A very wonderful man that cooks the best beef stew in the whole wide world. [. . . ]’), as
well as informal spelling (e.g., AYYYYYYYYYYYYYYYYYYY!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!) and made-
up words that actually no one uses (e.g. Emptybottleaphobia9). Based on manual inspection, it
seems that these are often headwords with only one entry.
We therefore also perform a matching considering only headwords from UD with at least
two entries (Table 3). In this way, we use the number of entries as a crude proxy for whether
the headword is of interest to a wider group of people. Note that this ﬁltering is not applied
to Wiktionary, because each headword has only one page and headwords that do not match
Wiktionary guidelines are already removed by the community. For example, an important
criterion for inclusion in Wiktionary is that the term is reasonably widely attested, e.g. has
widespread use or is used in permanently recorded media10. Compared to the ﬁrst analysis,
the difference is striking. In this comparison, the number of unique headwords in Wiktionary
is higher than that of UD.
From a manual inspection we see that many Wiktionary-speciﬁc
headwords include domain speciﬁc and encyclopaedic words (e.g., acacetins, dramaturge and
shakespearean sonnets), archaic words (e.g., unaffrighted), as well as some commonly used words
(e.g., deceptive, e-voucher). We also ﬁnd that many of the popular UD headwords (i.e., headwords
that have many entries) that are not covered in Wiktionary are proper nouns: The top ﬁve entries
are canada’s history, justin bieber, george w. bush, runescape and green day. In some cases, entries
uniquely appearing in UD refer to words with genuine general coverage, such as loml (in total
11 entries) deﬁned as, e.g., ‘Acronym of "Love of My Life"’ or broham ‘a close buddy, compadre,
smoking and/drinking buddy. a term of endearment between men to reafﬁrm heterosexuality.’
(in total 18 entries).
(c) Content analysis
In this section we present our analyses on the different types of content as well as the offensiveness
of the content in UD.
8The headword will be lower cased when the headword is all upper case or when the ﬁrst character is upper case and the
second character is lower case.
9A Google search only returns 14 results, all of them containing the Urban Dictionary deﬁnition (17 Feb, 2018).
10https://en.wiktionary.org/wiki/Wiktionary:Criteria_for_inclusion (17 February, 2018)


## Page 7


7
.
No processing
All lowercase
Mixed
Overlap
50,522
(6%)
56,730
(7%)
55,003
(7%)
Only UD
220,661
(25%)
165,054
(20%)
178,164
(21%)
Only Wiktionary
612,432
(69%)
596,673
(73%)
599,621
(72%)
Total
883,615
818,457
832,788
Table 3: Headword comparison between UD and Wiktionary. The table reports the unique
number of headwords in each category. Only UD headwords with at least two entries are
included.
(i) Content type
We now analyze several aspects of the content in UD that we expect to be different from content
typically found in traditional dictionaries as well as Wiktionary. For example, manual inspection
suggested that UD has a higher coverage of informal and infrequent words and of proper nouns
(e.g., names of places or speciﬁc people). Many of the headwords are not covered in knowledge
bases or encyclopedias. To characterize the data, we therefore annotated a sample of the data
using crowdsourcing (see Data and methods). In order to limit the dominance of headwords
with only one entry (which represent the majority of headwords in UD), the sample was created
by taking headwords from each of the 11 frequency bins (see Table 10 for details on the way
the bins were created and sampled from). Note that the last two bins are very small. For each
headword, we include up to three entries (top ranked, second ranked, and random based on up
and down votes). Annotations were collected on the entry level and crowd workers were shown
the headword, deﬁnition and example.
Proper nouns
Dictionaries are usually selective with including proper nouns (e.g., names of
places or individuals) [32, p. 77]. In contrast, in UD many entries describe proper nouns. We
therefore asked crowdworkers whether the entry described a proper noun (yes or no). In our
stratiﬁed sample, 16.4% of the entries were annotated as being about a proper noun. Figure 7
shows the fraction of proper nouns by frequency bin.
Opinions
Most dictionaries strive towards objective content. For example, Wiktionary states
‘Avoid bias. Entries should be written from a neutral point of view, representing all usages
fairly and sympathetically’11. In contrast, the entries provided in UD do not always describe
the meaning of a word, but they sometimes contain an opinion (e.g., beer ‘Possibly the best thing
ever to be invented ever. I MEAN IT.’ or Bush ‘A disgrace to America’). We therefore asked the
crowdworkers whether the deﬁnition describes the meaning of the word, expresses a personal
opinion, or both. Figures 8 and 9 show the fraction of entries labeled as opinion, meaning or
both, separated according to whether they were annotated as describing proper nouns. In higher
frequency bins, the fraction of entries marked as opinion is higher. We also ﬁnd that the number of
entries marked as opinion is higher for proper nouns. While most entries are marked as describing
a meaning, the considerable presence of opinions suggests that the type of content in UD is
different than in traditional dictionaries [13, p. 3-4].
Familiarity
UD enables quick recording of new words and new meanings, many of them which
may not have seen a widespread usage yet. Furthermore, as discussed in the previous section,
some entries are about made-up words or words that only concern a small community. In contrast,
many dictionaries require that included headwords should be attested (i.e. have widespread
use). These observations suggest that many deﬁnitions in UD may not be familiar to people. To
quantify this, we asked crowdworkers whether they were familiar with the meaning of the word.
11https://en.wiktionary.org/wiki/Wiktionary:Policies_and_guidelines (16 Feb, 2018)


## Page 8


8
.
G
G
G
G
G
G
G
G
G
G
G
0.00
0.25
0.50
0.75
1.00
0
1
2
3
4
5
6
7
8
9
10
Frequency bin
Proportion
Proper noun?
G no
yes
Figure 7: Proper nouns
G
G
G
G
G
G
G
G
G
G
G
0.00
0.25
0.50
0.75
1.00
0
1
2
3
4
5
6
7
8
9
10
Frequency bin
Proportion
Meaning or opinion?
G both
meaning
opinion
Figure 8: Meaning vs. opinions
(proper nouns were excluded)
G
G
G
G
G
G
G
G
G
G
0.00
0.25
0.50
0.75
1.00
0
1
2
3
4
5
6
7
8
9
Frequency bin
Proportion
Meaning or opinion?
G both
meaning
opinion
Figure 9: Meaning vs. opinions
(proper nouns entries only)
G
G
G
G
G
G
G
G
G
G
G
0.0
0.4
0.8
1.2
0
1
2
3
4
5
6
7
8
9
10
Frequency bin
Proportion
familiar
G no
yes
Figure 10: Familiarity
(proper nouns and opinion entries were
excluded)
G
G
G
G
G
G
G
G
G
G
G
0.00
0.25
0.50
0.75
1.00
0
1
2
3
4
5
6
7
8
9
10
Frequency bin
Proportion
formal
G no
unclear
yes
Figure 11: Formality
(proper nouns and opinion entries were
excluded)
The majority of the entries in UD were not familiar to the crowdworkers. Examples are common
headwords with an uncommon meaning such as coffee deﬁned as ‘a person who is coughed upon’
or shipwreck ’The opposite of shipmate. A crew member who is an all round liability and as
competent as a one legged man in an arse kicking competition.‘, as well as uncommon headwords
and uncommon meanings (e.g., Once-A-Meeting deﬁned as ‘An annoying gathering of people for
an hour or more once every pre-deﬁned interval of time (ex: once a day). Once-A-Meetings could
easily be circumvented by a simple phone call or e-mail but are instead used to validate a project
managers position within the company.’). Figure 10 shows that in higher frequency bins, more
deﬁnitions are marked as being familiar, suggesting that the number of deﬁnitions per headword
is indeed related to the general usage of a headword.
Formality
The focus of Urban dictionary on slang words [33] means that many of the words
are usually not appropriate in formal conversations, like a formal job interview. To quantify this,
we asked crowdworkers whether the word in the described meaning can be used in a formal
conversation. As Figure 11 shows, most of the words in their described meanings were indeed
not appropriate for use in formal settings.
(ii) Offensiveness
Online platforms with user generated content are often susceptible to offensive content, which
may be insulting, profane and/or harmful towards individuals as well as social groups [34,
35]. Furthermore, the existence of such content in platforms could signal to other users that
such content is acceptable and impact the social norms of the platform [36]. As a response,
various online platforms have integrated different mechanisms to detect, report and remove
inappropriate content. In contrast, regulation is minimal in UD and one of its characteristics is
its often offensive content.
UD not only contains offensive entries describing the meaning of offensive words, but there
are also offensive entries for non-offensive words (e.g., a deﬁnition describing women as ’The


## Page 9


9
.
Familiar?
Avg. offensiveness
yes
1.915
no
2.022
Table 6: Average offensiveness rankings (3=most offensive, 1=least offensive) by familiarity in
UD entries.
root of all evil’). We note, however, that UD also contains non-offensive deﬁnitions for offensive
words (e.g., asshole deﬁned as ’A person with no concept of boundaries, respect or common
decency.’). To investigate how offensive content is distributed in UD, we ran a crowdsourcing task
on CrowdFlower (see Data and methods for more details). Workers were shown three deﬁnitions
for the same headword, which they had to rank from the most to the least offensive.
We only included headwords with at least three deﬁnitions. In total, we obtained annotations
for 1,322 headwords and thus 3,966 deﬁnitions. Out of these 1,322 headwords there are 326
headwords for which the majority of the workers agreed that none of the deﬁnitions were
offensive.
Table 4 reports the offensiveness scores separated by whether the deﬁnitions describe a
meaning, opinion or both. An one-way ANOVA test indicates a slight signiﬁcant difference
(F(2, 3963) = 2.766, p<0.1). A post hoc comparison using the Tukey test indeed indicates a slight
signiﬁcant difference between the scores of deﬁnitions describing a meaning and opinion (p<0.1).
Thus, deﬁnitions stating an opinion tend to be ranked as more offensive compared to deﬁnitions
describing a meaning.
Table 5 reports the offensiveness scores by formality. Deﬁnitions for words that were annotated
as not being appropriate for formal settings (based on their described meaning) tend to be
ranked as being more offensive. An one-way ANOVA conﬁrms that the differences between the
groups are highly signiﬁcant (F(2, 3963) = 22.72, p<0.001). Post hoc comparisons using the Tukey
test indicate signiﬁcant differences between the formal and not formal categories (p<0.001), and
between the unclear and not formal categories (p<0.05). We also ﬁnd that deﬁnitions for which
crowdworkers had indicated that they were familiar with the described meaning of the word
tended to be perceived as less offensive (Table 6, p < 0.001 based on a t-test). We observe the same
trends when we only consider deﬁnitions that describe a meaning.
Type
Avg. offensiveness
both
2.025
meaning
1.989
opinion
2.050
Table
4:
Average
offensiveness
rankings (3=most offensive, 1=least
offensive) by type of deﬁnition in UD
entries.
Formal?
Avg. offensiveness
no
2.031
unclear
1.884
yes
1.873
Table
5:
Average
offensiveness
rankings (3=most offensive, 1=least
offensive)
by
formality
in
UD
deﬁnitions.
(d) Content and popularity
An important feature of UD is the voting mechanism that allows the users to express their
evaluation of entries by up or down voting them. For a given headword, entries are ranked
according to these votes and the top ranked one is labeled as top deﬁnition. The votes thus drive the
online visibility of entries, leading to the following implications. First, the top ranked entries are
immediately visible when UD is consulted to look up the meaning of a headword. Many users
might not browse the additional pages with lower ranked entries. Second, by users expressing
their evaluation through votes, social norms are formed regarding what content is valued in UD.


## Page 10


10
.
UD does not provide clear guidelines on "what a good deﬁnition is". Various factors could
inﬂuence the up and down votes an entry receives, including whether the voter thinks the entry
is offensive, informative, funny and whether the voter (dis)agrees with the expressed view. In this
section we analyze how characteristics of the content as discussed in the previous section relate to
the votes the entries receive. Because the number of up and down votes varies highly depending
on the popularity of the headword, we perform the analysis based on the rankings of entries (top
ranked, second ranked, and random) instead of the absolute number of up and down votes. Only
headwords with at least three entries are included.
Table 7 shows the distribution of opinion-based versus meaning-based deﬁnitions separated
by whether the headwords are annotated as proper nouns by the crowdworkers. The proportion
of deﬁnitions that are annotated as opinions is much higher for proper nouns, which is consistent
with our previous analysis. However, among the top ranked deﬁnitions for proper nouns, the
proportion of opinions is lower (but n.s.).
Table 8 characterizes the entries by formality and familiarity. We discard proper nouns and
entries marked as opinion, since it is less clear what formality and familiarity mean in these
contexts. We ﬁnd that the top ranked deﬁnitions tend to be more familiar (χ2 (2, N = 2991) =
15.385, p <0.001) and more appropriate for formal settings (but n.s.).
Opinion or meaning?
both
meaning
opinion
No proper nouns (n=3,268)
top ranked
0.055
0.852
0.094
second ranked
0.074
0.850
0.076
random
0.051
0.864
0.084
Proper nouns (n=698)
top ranked
0.172
0.481
0.347
second ranked
0.169
0.477
0.354
random
0.190
0.444
0.366
Table 7: Characterization of UD entries based on votes. The table reports the proportions of
opinion-based versus meaning-based deﬁnitions in each of the ranking groups.
Familiar?
Formal?
Offensiveness
no
yes
no
unclear
yes
avg. ranking
top ranked
0.799
0.201
0.855
0.026
0.119
1.950
second ranked
0.807
0.193
0.876
0.023
0.101
1.966
random
0.861
0.139
0.894
0.020
0.086
2.107
Table 8: Familiarity, formality and offensiveness of UD deﬁnitions across rankings based on votes.
Deﬁnitions for proper nouns and deﬁnitions annotated as opinions are not included. The table
reports the proportions in each of the rankings for familiarity and formality and the average
ranking for offensiveness (3=most offensive, 1=least offensive); n=2,991.
Table 8 also reports the average offensiveness ranking of the deﬁnitions separated by their
popularity (again, discarding proper nouns and entries marked as opinions). The difference in
rankings between top ranked and second ranked deﬁnitions is minimal, but random deﬁnitions
are more often ranked as being more offensive. A one-way ANOVA test conﬁrms that the
differences between the groups are highly signiﬁcant (F(2, 2988) = 22.07, p<0.001). Post hoc


## Page 11


11
.
comparisons using the Tukey test indicate signiﬁcant differences between the random and top
ranked, and random and second ranked deﬁnitions (p<0.001). A similar trend is observed when
we consider all deﬁnitions (F(2, 3963) = 34.87, p<0.001). Thus, although UD contains offensive
content, very offensive deﬁnitions do tend to be ranked lower through the voting system.
However, the small difference in scores between the groups indicates that offensiveness only
plays a small role in the up and down votes a deﬁnition receives.
To analyze the different factors jointly, we ﬁt an ordinal regression model (Table 9) using
the ordinal R library based on deﬁnitions that were annotated as not being an opinion and not
describing proper nouns. We ﬁnd that familiarity and offensiveness indeed have a signiﬁcant
effect. More familiar and less offensive deﬁnitions tend to have a higher ranking. Similar trends in
coefﬁcients were observed with ﬁtting logistic regression models when dichotomizing the ranking
variable.
Dependent variable: ranking
Familiar (yes)
−0.255∗∗∗(0.096)
Formal (unclear)
−0.133
(0.226)
Formal (yes)
−0.073
(0.123)
Offensiveness
0.335∗∗∗(0.059)
Observations
2,991
Log likelihood
−3262.19
AIC
6536.38
Table 9: Ordinal regression results. The dependent variable is the ranking: top ranked (0), second
ranked (1) or a random rank (2). ∗∗∗p<0.01.
3. Discussion and conclusion
In this article, we have studied a complete snapshot (1999–2016) of Urban Dictionary to shed
light on the characteristics of its content. We found that most contributors of UD only added one
entry and very few added a high number of entries. Moreover, we found a number of skewed
distributions, which need to be taken into account whenever performing analyses on the UD
data. Very few headwords have a high number of entries, while the majority have only one entry.
Similarly, few entries are highly popular (i.e. they collected a high number of votes). We also
found a strong correlation between the number of up and down votes for each entry, illustrating
the importance of visibility on the votes an entry receives.
The lexical content of UD is radically different from that of Wiktionary, another crowdsourced,
but more highly moderated dictionary. In general, we can say that the overlap between the two
dictionaries is small. Considering all unique UD headwords that are not found in Wiktionary,
we found that this number is almost three times the number of headwords that uniquely occur
in Wiktionary. However, if we exclude words with only one deﬁnition in UD (which tend to
be infrequent or idiosyncratic words), we found the opposite pattern, with Wiktionary-only
headwords amounting to almost three times the UD-only headwords.
Our analyses based on crowdsourced annotations showed more details on the speciﬁc
characteristics of UD content. In particular, we measured a high presence of opinion-focused
entries, as opposed to the meaning-focused entries that we expect from traditional dictionaries. In
addition, many entries in UD describe proper nouns. The crowdworkers were not familiar with
most of the deﬁnitions presented to them and many words (and their described meaning) were
found not to be appropriate for formal settings.
Urban Dictionary captures many infrequent, informal words and it also contains offensive
content, but highly offensive deﬁnitions tend to get ranked lower through the voting system. The


## Page 12


12
.
Frequency bin (log 2)
0
1
2
3
4
5
6
7
8
9
10
#deﬁnitions
200
449
600
600
600
600
600
600
180
30
6
Table 10: Statistics of the sampled deﬁnitions
high content heterogeneity in UD could mean that, depending on the goal, considerable effort is
needed to ﬁlter and process the data (e.g., the removal of opinions) compared to when traditional
dictionaries are used. We also found that words with more deﬁnitions tended to be more familiar
to crowdworkers, suggesting that UD content does reﬂect broader trends in language use to some
extent.
There are several directions of future work that we aim to explore. We have compared the
lexical overlap with Wiktionary in terms of headwords. As future work, we plan to extend the
current study by performing a deeper semantic analysis and by comparing UD with other non-
crowdsourced dictionaries. Furthermore, we plan to extend the current study by comparing the
content in Urban Dictionary with language use in social media to advance our understanding of
the extent to which UD reﬂects broader trends in language use.
4. Data and methods
(a) Data collection
(i) Urban Dictionary
We crawled UD in July 2016. First, the deﬁnitions were collected by crawling the ‘browse’ pages of
UD and by following the ‘next’ links. After collecting the list of words, the deﬁnitions themselves
were crawled directly after (between July 23 and July 29, 2016). We did not make use of the API,
since the API restricted the maximum number of deﬁnitions returned to ten for each word.
(ii) Wiktionary
We downloaded the Wiktionary dump of the English language edition of 20 July, 2016, so that
the date matched our crawling process. To parse Wiktionary, we made use of code available
through ConceptNet 5.2.2 [37]. Pages in the English Wiktionary edition can also include sections
describing other languages (e.g., the page about boot contains an entry describing the meaning of
boot in the Dutch language (‘boat’)). We only considered the English sections in this study.
(b) Crowdsourcing
Most headwords in UD have only one entry, and therefore these headwords would dominate
a random sample. Because such headwords tend to be uncommon, a random sample would
not be able to give us much insight into the overall content of UD. We therefore sampled the
headwords according to the number of their entries. For each headword (after lower casing), we
counted the number of entries and place the headword in a frequency bin (after taking a log base
2 transformation). For each bin, we randomly sampled up to 200 headwords. For each sampled
headword, we included the top two highest scoring entries (scored according to the number of
thumbs up minus the number of thumbs down) and another random entry. In total we sampled
4,465 entries (Table 10).
We collected the annotations using CrowdFlower. The quality was ensured using test questions
and by restricting the contributors to quality levels two and three and the countries Australia,
Canada, Ireland, New Zealand, UK, and the USA. We marked the crowdsourcing tasks as
containing explicit content, so that the tasks were only sent to contributors that accepted to work
with such content.


## Page 13


13
.
Fleiss’ kappa
Pairwise agreement
Q1: Proper noun (yes, no)
0.379
0.806
Q2: Meaning or opinion? (meaning, opinion, both)
0.207
0.691
Q3: Familiar (yes, no)
0.206
0.713
Q4: Formal (yes, no, unclear)
0.207
0.712
Table 11: Agreement statistics
(i) Content Type
For each task, we collected three judgements. The workers were paid $0.03 per judgement. We
collected 13,395 judgements from a total of 201 workers. The median number of judgements per
worker is 76. Workers were shown the headword, deﬁnition and example. The crowdworkers
were asked the following questions (options for answers are displayed in italic font):
• Q1: Is this word a proper noun, for example, a name used for an individual person (like
Mark), place (like Paris), or organization (like Starbucks, Apple)? yes, no
• Q2: The deﬁnition: describes the meaning of the word, expresses a personal opinion, both
• Q3: Were you familiar with this meaning of the word before reading this deﬁnition? If you
are familiar with this word but NOT with this meaning, then please select no. Example:
If you are familiar with the meaning of the word ‘cat’ as the animal, but the deﬁnition
describes cat as ‘A person, usually male and generally considered or thought to be cool.’
and you are not familiar with this meaning, select no: yes, no
• Q4: Can this word in the described meaning be used in a formal conversation? Examples
of formal settings are a formal job interview, meeting an important person, or court of law.
Examples of informal settings are chatting with close friends or family: yes, no, unclear
Agreement
For each deﬁnition we have three judgements. We calculate Fleiss’ kappa (using the
irr package in R) and the pairwise agreement (Table 11). The agreement for the ﬁrst question,
asking whether the word is a proper noun, is the highest. In general the agreement is low, due
to the difﬁculty of the task. For example, in these cases all three workers answered differently
to the question whether the deﬁnition described a meaning or an opinion: AR-15 deﬁned as‘AR
does NOT stand for Assault Riﬂe’ and Law School deﬁned as ‘Where you go for to school for four
years after college to learn to become a lawyer. In these four years, you will work your butt off
every day, slog through endless amounts of reading, suffer through so much writing, and after
you graduate, you don’t get to call yourself "doctor".’. We merge the answers for each question
by taking the majority vote. We use ‘both’ for Q2 and ‘unclear’ for Q4 if there was no majority.
(ii) Offensiveness
We experimented with different pilot setups in which we asked workers to annotate the level and
type of offensiveness for individual deﬁnitions. However, we found that this led to confusion and
disagreement among the crowdworkers. For example, an offensive word can be described in a
non-offensive way and a non-offensive word can be described in an offensive way. Furthermore,
people have different thresholds of what they consider to be offensive, making it challenging
to ask for a binary judgement. In the ﬁnal setup, we therefore showed the sampled deﬁnitions
for the same word and asked workers to rank the deﬁnitions according to their offensiveness,
with 1 being the most offensive and 3 being the least offensive. Even if workers have different
thresholds of what they consider offensive, they could still agree when being asked to rank the
deﬁnitions. Indeed, we found that this led to a higher agreement. Note that in this article, we
have reversed the ratings (3=most offensive, 1=least offensive) for a more intuitive presentation
of the results. Workers were also asked to indicate whether they considered all deﬁnitions equally


## Page 14


14
.
Word
Deﬁnition
Ratings
Def. 1 Old school deﬁnition: to pinch someone’s buttocks, hopefully the
opposite sex, but hey, you take what you get. Always associated in my
mind with a British accent....
2, 2, 2, 2, 2
goosed
Def. 2 adj. 1. a feeling of overwhelmedness 2. a feeling of frusteration
3. a feeling of joy 4. all emotions easily substituted by the word
5. the new “owned"
1, 1, 1, 1, 1
Def. 3 To apply pressure on one’s taint (or space between genitalia and
anus), preferably of the opposite sex!
3, 3, 3, 3, 3
Def. 1 the one who knocked-up your mom
2, 2, 2, 2, 3
dad
Def. 2 The parent that takes the most shit. Sure, if you had a shitty father,
then go ahead and bitch, but not all of us did. Some of us had great fathers,
who really loved us, and weren’t assholes. Honestly, if you could see
how much damage a mother could do to one’s self esteem, you wouldn’t
even place so much blame on “dear old dad"
3, 3, 3, 3, 2
Def. 3 The replacement name for "bro" to call your best friend of whom
you have a fatherly bond
1, 1, 1, 1, 1
Table 12: Examples of annotated deﬁnitions for offensiveness (3=most offensive, 1=least
offensive).
offensive, equally non-offensive, or none. For each task, we collected ﬁve judgements. We paid
$0.04 per judgement. We collected 6,610 judgements from a total of 158 workers (median number
of judgements per worker: 44). Table 12 provides examples for two words (goosed and dad) and
their ratings.
Agreement
We calculate agreement using Kendall’s W (also called Kendall’s coefﬁcient of
concordance), which ranges from 0 (no agreement) to 1 (complete agreement). We calculate
Kendall’s W for each word separately. The average value of Kendall’s W is 0.511 (standard
deviation = 0.303). If we exclude words for which a worker indicated that the deﬁnitions were
equal in terms of offensiveness, the value increases to 0.714 (standard deviation = 0.238).
Ethics statement
In this study we employ crowdsourcing to collect annotations. The tasks were marked as
containing explicit content, so that the tasks were only visible to contributors that accepted to
work with such content. The tasks also explicitly mentioned that the results will be used for
scientiﬁc research (’By participating you agree that these results will be used for scientiﬁc research.’). We
closely monitored the crowdsourcing tasks and contributor satisfaction was consistently high.
Data accessibility
The datasets supporting this article are available upon request.
Competing interests
The authors declare no competing interests.


## Page 15


15
.
Authors’ contributions
DN collected and analyzed the data, participated in the design of the study, and drafted the
manuscript; BM participated in the design of the study, analysed the data and drafted the
manuscript; TY conceived the study, analyzed the data, and helped draft the manuscript. All
authors gave ﬁnal approval for publication.
Funding
This work was supported by The Alan Turing Institute under the EPSRC grant EP/N510129/1.
DN was supported by Turing award TU/A/000006 and BM by Turing award TU/A/000010
(RG88751). The crowdsourcing data collection was supported with an Alan Turing Institute seed
funding grant (SF024).
References
1. Estellés-Arolas E, González-Ladrón-de Guevara F.
Towards an integrated crowdsourcing deﬁnition.
Journal of Information science. 2012;38(2):189–200.
2. Dabbish L, Stuart C, Tsay J, Herbsleb J.
Social coding in GitHub: transparency and collaboration in an open software repository.
In: Proceedings of the ACM 2012 conference on Computer Supported Cooperative Work; 2012.
p. 1277–1286.
3. Sauermann H, Franzoni C.
Crowd science user contribution patterns and their implications.
Proceedings of the National Academy of Sciences. 2015;112(3):679–684.
4. Doan A, Ramakrishnan R, Halevy AY.
Crowdsourcing systems on the world-wide web.
Communications of the ACM. 2011;54(4):86–96.
5. Giles J.
Internet encyclopaedias go head to head.
Nature. 2005;438(900–901).
6. Kittur A, Suh B, Pendleton BA, Chi EH.
He says, she says: conﬂict and coordination in Wikipedia.
In: Proceedings of the SIGCHI Conference on Human Factors in Computing Systems; 2007. p.
453–462.
7. Yasseri T, Sumi R, Rung A, Kornai A, Kertész J.
Dynamics of conﬂicts in Wikipedia.
PloS one. 2012;7(6):e38869.
8. Halavais A, Lackaff D.
An analysis of topical coverage of Wikipedia.
Journal of Computer-Mediated Communication. 2008;13(2):429–440.
9. Samoilenko A, Yasseri T.
The distorted mirror of Wikipedia: a quantitative analysis of Wikipedia coverage of
academics.
EPJ data science. 2014;3(1):1.
10. Labov W.
Principles of Linguistic Change, Volume II, Social Factors.
Wiley-Blackwell; 2001.
11. Siemund P.
The emergence of English reﬂexive verbs: an analysis based on the Oxford English Dictionary.
English Language and Linguistics. 2014;18(1):49–73.
12. Abel A, Meyer CM.
The dynamics outside the paper: user contributions to online dictionaries.
In: Proceedings of eLex 2013; 2013. p. 179–194.
13. Rundell M.
Dictionaries and crowdsourcing, wikis and user-generated content.


## Page 16


16
.
In: Hanks P, de Schryver GM, editors. International Handbook of Modern Lexis and
Lexicography. Springer-Verlag; 2016. p. 1–16.
14. Meyer CM, Gurevych I.
Wiktionary: A new rival for expert-built lexicons? Exploring the possibilities of collaborative
lexicography.
In: Granger S, Paquot M, editors. Electronic Lexicography. Oxford: Oxford University Press;
2012. p. 259–291.
15. Creese S.
Exploring the relationship between language change and dictionary compilation in the age of
the collaborative dictionary.
In: Proceedings of eLex 2013; 2013. p. 392–406.
16. Creese S.
Lexicographical explorations of neologisms in the digital age. Tracking new words online and
comparing Wiktionary entries with ’traditional’ dictionary representations [PhD Thesis].
Coventry University; 2017.
17. Eisenstein J, O’Connor B, Smith NA, Xing EP.
Diffusion of lexical change in social media.
PLOS ONE. 2014 11;9(11):1–13.
18. Grieve J, Nini A, Guo D.
Analyzing lexical emergence in Modern American English online.
English Language and Linguistics. 2017;21(1):99–127.
19. Kerremans D, Stegmayr S, Schmid H.
The NeoCrawler: Identifying and retrieving neologisms from the internet and monitoring
ongoing change.
In: Allan K, Robinson JA, editors. Current Methods in Historical Semantics. De Gruyter
Mouton; 2011. p. 59–96.
20. Tenore MJ. Urban Dictionary, Wordnik track evolution of language as words change, emerge;
2012.
Retrieved on 24 October 2017.
Poynter. The Poynter Institute.
Available
from:
https://www.poynter.org/news/urban-dictionary-wordnik-
track-evolution-language-words-change-emerge.
21. Davis J. In praise of urban dictionaries; 2011.
Retrieved on 24 October 2017.
Available from: https://www.theguardian.com/books/2011/apr/21/in-praise-
urban-dictionaries.
22. Heaton T. 10 Questions with Urban Dictionary’s Aaron Peckham; 2010.
Retrieved on 24 October 2017.
Available from: http://thepomoblog.com/index.php/10-questions-with-urban-
dictionarys-aaron-peckham/.
23. Smith RE.
Urban dictionary: youth slanguage and the redeﬁning of deﬁnition: What’s up with meep and
other words in the Urban Dictionary.
English Today. 2011;27(04):43–48.
24. Ni K, Wang WY.
Learning to explain non-standard English words and phrases.
In: Proceedings of the Eighth International Joint Conference on Natural Language Processing
(Volume 2: Short Papers). Taipei, Taiwan; 2017. p. 413–417.
25. Beckley R.
Bekli:A simple approach to Twitter text normalization.
In: Proceedings of the ACL 2015 Workshop on Noisy User-generated Text; 2015. p. 82–86.
26. Tang D, Wei F, Qin B, Zhou M, Liu T.
Building large-scale Twitter-speciﬁc sentiment lexicon : A representation learning approach.
In: Proceedings of COLING 2014, the 25th International Conference on Computational
Linguistics: Technical Papers; 2014. p. 172–182.
27. Damaso J, Cotter C.
UrbanDictionary.com.
English Today. 2007;23(2):19–26.


## Page 17


17
.
28. Ortega F, Gonzalez-Barahona JM, Robles G.
On the inequality of contributions to Wikipedia.
In: Proceedings of the 41st Annual Hawaii International Conference on System Sciences; 2008.
p. 304–304.
29. Yasseri T, Kertész J.
Value production in a collaborative environment.
Journal of Statistical Physics. 2013;151(3-4):414–439.
30. Huberman B, Romero DM, Wu F.
Social networks that matter: Twitter under the microscope.
First Monday. 2008;14(1).
31. Wu F, Huberman BA.
Novelty and collective attention.
Proceedings of the National Academy of Sciences. 2007;104(45):17599–17601.
32. Marconi D.
Dictionaries and proper names.
History of Philosophy Quarterly. 1990;7(1):77—92.
33. Peckham A.
Urban dictionary: Fularious street slang deﬁned.
Andrews McMeel Publishing; 2009.
34. Sood S, Antin J, Churchill E.
Profanity use in online communities.
In: Proceedings of the SIGCHI Conference on Human Factors in Computing Systems; 2012. p.
1481–1490.
35. Waseem Z, Davidson T, Warmsley D, Weber I.
Understanding abuse: A typology of abusive language detection subtasks.
In: Proceedings of the First Workshop on Abusive Language Online; 2017. p. 78–84.
36. Sukumaran A, Vezich S, McHugh M, Nass C.
Normative inﬂuences on thoughtful online participation.
In: Proceedings of the SIGCHI Conference on Human Factors in Computing Systems; 2011. p.
3401–3410.
37. Speer R, Havasi C.
Representing general relational knowledge in ConceptNet 5.
In: LREC; 2012. p. 3679–3686.

---
**Related:** [[00-Home]] · [[AMOS_RSCF_NODES]]

---

[[00_ROOT/00_ROOT_MOC.md|AMOS MOC]]