# Reported reproducibility practices and agentic reproduction outcomes in medical and life-science papers at major ML conferences: a systematic meta-research study

Ekaterina Kondrateva^1,2^, Florian Kofler^1,3,4,5^, Attila Simkó^6^

^1^ Hertie AI Institute for Brain Health, University of Tübingen, Tübingen, Germany
^2^ Maastricht University, Maastricht, the Netherlands
^3^ University of Zurich, Zurich, Switzerland
^4^ Technical University of Munich, Munich, Germany
^5^ Helmholtz Munich, Munich, Germany
^6^ Umeå University, Umeå, Sweden

Corresponding author: Ekaterina Kondrateva, ekaterina.kondrateva@maastrichtuniversity.nl. ORCID 0000-0003-3623-6106.

## Abstract

**Background.** Restricted data and unavailable code are common concerns in medical machine learning (ML). We examined how medical papers report reproducibility practices and what happens when independent teams attempt to reproduce them using AI agents.

**Methods.** We identified 2,170 clinical or life-science papers across nine venue-years at CVPR, ICCV, ECCV, ICLR, ICML and NeurIPS in 2025 and 2026, and randomly sampled 2,170 other papers. We refer to the clinical and life-science groups together as medical papers. Agreement between the domain coders was high (Cohen's kappa 0.96). One language-model coder assessed excerpts from all 3,278 retrieved full texts. A second coder independently assessed a random 25%; fields below the agreement threshold underwent duplicate coding across the full sample. Differences were pooled across venue-years with Mantel-Haenszel risk differences and paper bootstrap intervals, under a protocol frozen before sample selection. Reproduction outcomes came from the public verdicts of the ICML 2026 agent reproduction challenge.

**Results.** Among papers with a known code-release status, 59% of medical papers reported releasing code, compared with 46% of other papers (pooled difference +13 percentage points, 95% CI +10 to +17). Medical papers also more often reported variance (66% versus 42%; +24, +21 to +28) and open main data (+15, +11 to +19). Few papers in either group linked their main claims to a specific table, figure or theorem (2.7% versus 6.1%). In the challenge, attempted medical papers less often received a verified or falsified verdict on at least one claim than 1,821 other attempted papers (−19 percentage points, 95% CI −28 to −10), and more of their claims were rated inconclusive (49% versus 25%). In comparisons within the same team, the estimated difference in the proportion of claims decided was −3.6 percentage points (95% CI −7.8 to +0.8). After adjustment for the first team's performance on other papers, the difference in papers with a decided claim decreased from −19.1 to −3.6 percentage points (95% CI −11.9 to +5.1). A difference in full verification remained (−11.7, −14.7 to −8.0). In the 220-paper subsample, coders classified medical claims as requiring retraining or large-scale runs more often than other claims (57% versus 39%); adjustment for both first-team performance and claim requirements reduced the full-verification difference to −6 percentage points (95% CI −12 to +1). Reported practices showed limited agreement with logbook evidence of material use (code: kappa 0.22).

**Conclusions.** Medical papers reported several reproducibility practices more often than other papers at the same venues. In the ICML 2026 challenge, they less often received a verified or falsified verdict on at least one claim. Exploratory adjustments reduced this difference after accounting for first-team performance; the remaining difference in full verification was further reduced after accounting for claim requirements in a subsample. Authors should link their main claims to the results that support them.

## Introduction

Previous studies have documented limited access to code and data in medical AI research. When a high-profile study of AI for breast cancer screening was published without its code and with few methodological details, critics argued that this undermined its scientific value [1]. A survey of 511 papers found that ML for health compared poorly with other areas of ML on dataset and code accessibility [2]. In the radiology journals of the RSNA, 34% of 218 AI articles shared code and 11% shared code that reproduced [3], and at the Medical Imaging with Deep Learning conference only 22% of accepted full papers from 2018 to 2022 had a repository judged repeatable [4]. An audit of 400 AI conference papers found that none documented all the variables a reproduction needs [5]. NeurIPS responded with a code submission policy, a reproducibility checklist and a community-wide reproducibility challenge [6], and failures such as data leakage have been traced across 17 fields that apply ML [7].

Previous studies assessed reporting, access to research materials and, in some cases, whether shared code could be run [3, 4]. Whether independent attempts can verify or falsify a paper's claims requires evidence from reproduction attempts. AI agents now attempt reproductions of whole papers [8], and agentic reproduction challenges now provide these records for large numbers of papers. In 2026 the International Conference on Machine Learning (ICML) ran an open agent reproduction challenge in which more than 1,200 participants published 6,816 reproduction logbooks on 2,226 conference papers, and an automated judge rated 35,908 claims as verified, falsified, toy (evidence at reduced scale) or inconclusive [9]. These records provide reproduction outcomes for one venue, based on evidence submitted in logbooks and assessed by an automated judge.

We compared reported reproducibility practices between medical and other papers at the same ML venues. We then compared reproduction outcomes in the ICML 2026 challenge and explored whether differences were associated with the teams attempting the papers and the requirements of their claims. An earlier protocol of ours on the venue listings (Protocol 7, Supplementary File S1) had already found that medical papers declare a code link in the venue metadata more often than other papers (24.5% versus 16.9% across twelve venue-years, +7.4 percentage points, 95% CI +5.8 to +9.0). For the practices that the metadata does not show (open data, weights and variance), we nonetheless prespecified the common assumption, that medical papers report them less often, as directional hypotheses. The full-text analysis did not support these directional hypotheses: medical papers reported the practices more often. Reproduction outcomes were less favourable for medical papers. We examined this difference in post hoc analyses, with interpretation criteria recorded before each analysis was run.

## Methods

Protocol 9 was frozen in a public repository before selection of the study sample, full-text retrieval and coding. It was developed after the results of earlier protocols on the same challenge were known. The study is reported following the PRISMA 2020 statement [10] where its items apply to a meta-research study of published papers. The protocol, its amendments and the reporting checklist are described in Appendix A.

### Information sources and eligibility

The sources were the public virtual-site listings of nine venue-years: CVPR 2025, ICCV 2025, ECCV 2026, ICLR 2025, ICLR 2026, ICML 2025, ICML 2026, NeurIPS 2025 and NeurIPS 2026 (40,290 papers after removing duplicates and papers without an abstract). Abstracts missing from the 2026 listings were taken from the challenge's paper metadata (ICML 2026) or from each paper's page on the venue site (ICLR 2026, NeurIPS 2026, ECCV 2026).

A paper was a candidate for the medical group if its venue topic was a health, biology, neuroscience or chemistry topic, or its title or abstract matched a prespecified regular expression of clinical and biological terms (Supplementary File S1, Protocol 7). This gave 5,530 candidates. Each candidate was labelled `clinical`, `life_science` or `no` from title and abstract only by a blind language-model coder; a second blind coder labelled a random 25% of candidates (1,633 papers over the whole listing; agreement 97.7%, Cohen's kappa 0.96 [11]; threshold 0.80) and disagreements were adjudicated with a written reason. Of the candidates, 1,013 were labelled clinical and 1,157 life science, together the 2,170 medical papers, and 3,360 were excluded. To estimate how many medical papers the prefilter missed, both coders labelled a random 200 non-candidates; none was medical (0 of 200, 95% Wilson interval [12] 0 to 1.9%). The comparison group was a random sample of 2,170 non-candidates, allocated to venue-years in proportion to the medical counts (seed 20261019).

### Full-text retrieval and excerpts

Full texts were retrieved in a fixed order: arXiv HTML, then arXiv PDF (arXiv identifier from a title search, accepted at a normalised title similarity of at least 0.95 and an arXiv year no earlier than the venue year minus one; ambiguous matches excluded), then the open proceedings (CVF, PMLR). OpenReview was not scraped. Papers without a retrievable full text remained in the study frame but were excluded from documentation coding. We reported retrieval failures by group and venue-year. From each full text an excerpt of at most 15,000 characters was built from the end of the introduction, sections whose heading concerned availability, reproducibility, ethics, data, setup, implementation, training, compute or limitations, the NeurIPS checklist items on reproducibility, and paragraphs on seeds and repeated runs, with a truncation flag per paper.

### Data items and coding

Each excerpt was coded on twelve fields (Table 1 lists the indicators): whether main claims were listed and linked to evidence; code (released, promised, no); main data access (open, credentialed or on request, private, synthetic only); an experiment on open data; release of synthetic or sample data, of weights and of outputs; variance (several seeds, error bars or intervals); environment (versions or container); compute (amount, hardware only, none); compute tier; and training-set scale. Every field allowed `unclear`. Coders used stated text only; a named dataset without stated access terms was `unclear`.

Coding was done by language-model subagents (claude-sonnet-5-5), 20 papers per batch, with venue, year and group hidden. Coder 1 coded all papers and coder 2 a random 25% (813 papers). Agreement exceeded the prespecified kappa threshold of 0.80 for code release (0.85), main data access (0.83) and weights (0.96). We therefore used coder 1's labels for these fields. Agreement was below the threshold for variance (0.71) and compute (0.70). These fields underwent duplicate coding across the full sample, followed by blinded adjudication of all 1,404 disagreements by a language model (claude-opus-5-5) that saw the two labels in random order and gave a reason.

### Reproduction outcomes

Outcomes came from the public verdict snapshot of the ICML 2026 agent reproduction challenge retrieved on 17 October 2026 [9]. In the challenge, participants chose papers from the conference list, for each of which the organisers had extracted core claims from the abstract as checkable targets, and reproduced them with AI agents, with or without human steering, on compute credits provided by the organisers [9]. Each attempt was published as a logbook (a Trackio Space with the write-up, the code that ran, the artifacts it produced and, optionally, the agent's execution trace) [9]. An automated judge (GLM-5.2) then read each logbook, treated the logbook's own self-assessment as untrusted, and gave each claim one of four verdicts: verified, falsified, toy (supported only by a reduced-scale or synthetic-data run) or inconclusive; the organisers re-checked every claimed falsification themselves [9]. On fixed input this judge agreed with itself well (Krippendorff's alpha 0.874), whereas verdicts on the same claim from different logbooks agreed poorly (alpha 0.229), a difference its author attributes mainly to the evidence that different attempts produce rather than to the judge [13].

A paper was classified as attempted if it had at least one logbook, and as decided if at least one claim received a verified or falsified verdict. We classified it as fully verified if at least one logbook verified every claim assessed in that logbook. Logbooks were deduplicated, and the first author's own logbooks were excluded because the first author took part in the challenge. Of the 6,341 ICML 2026 papers, 622 candidates labelled `no` were excluded, leaving 328 medical and 5,391 other papers.

To assess agreement between reported practices and material use (reference standard), two blind coders read the logbooks of the 222 attempted ICML 2026 papers in the frame and coded whether the authors' code was obtained and run, the main data obtained, and weights used; disagreements were adjudicated as above. A further random 300 attempted ICML 2026 papers outside the frame were added later under a prespecified extension (Note 9-17).

### Quantitative synthesis

For each indicator we computed the share of papers with the practice among papers with a known value (`unclear` excluded and counted), by group and venue-year, with Wilson intervals [12]. The difference between groups was pooled over the nine venue-years as a Mantel-Haenszel risk difference [14], with a 95% interval from 2,000 paper bootstrap resamples within strata (seed 20261017; results identical under two hash seeds). Three directional hypotheses were prespecified: medical papers report open main data, release weights and report variance less often; each was to be supported only if the pooled interval excluded zero in that direction.

For reproduction outcomes the primary analysis compared the decided share of attempted papers by group, unadjusted and adjusted for compute tier and data scale. Post hoc analyses (Notes 9-9 to 9-15) examined how many teams attempted each paper, the first team's performance on other papers, within-team claim-level differences, and the requirements of each claim. We measured first-team performance as the proportion of its other attempted papers with a decided claim in that team's latest logbook, excluding the focal paper. For claim requirements, two blind coders classified every distinct claim text of the 110 attempted medical papers and of 110 randomly drawn attempted other papers as needing inference only, retraining, large-scale runs, or analysis only; the claim texts reveal the subject, so these coders were blind to the group label but not to the domain. We prespecified a descriptive criterion for interpreting adjusted estimates: the absolute difference had to decrease by more than half, and its 95% interval had to include zero. Meeting this criterion was not interpreted as evidence of causation. Adversarial checks (Notes 9-12 and 9-14) stated in advance what would refute each main claim. After an internal review of this manuscript, three further post hoc analyses were frozen before their intervals were computed (Note 9-22): documentation differences among papers reporting a training-set size, which we used as an operational definition of empirical papers; release fields with `unclear` treated as no reported release; and the mix of verdicts by group. We did not correct for multiple comparisons; the post hoc analyses are exploratory.

### Ethics

The study used published papers and public challenge records, and involved no human participants and no patient data. The challenge records include the public account names under which participants published their logbooks. We used them only to group logbooks by team; no account name is reported in this paper or in the paper-level table. No ethics review was sought for this secondary analysis of public records.

## Results

Figure 1 summarises the main results.

### Study selection

Figure 2 shows the flow of papers. Of the 4,340 papers in the frame, full texts were retrieved for 3,278 (1,568 medical and 1,710 other papers); 1,057 could not be matched to a full text, 4 failed to download and 1 had no usable text. Retrieval was complete or nearly complete for ICML, CVPR and ICCV, which have open proceedings, and lowest for NeurIPS 2026 (165 of 431 medical and 212 of 431 other papers) and the other venue-years that relied on arXiv alone (Table A1). It was lower for medical than for other papers (72.3% against 78.8%). Of the excerpts, 2,793 reached the 15,000-character limit.

### Reported practices

Table 1 and Figure 3 give every indicator. Among papers with a known value for each field, medical papers more often reported code release (59.4% versus 46.2%; pooled difference +13.1 percentage points, 95% CI +9.6 to +16.6), open main data (83.7% versus 67.3%; +15.0, +10.7 to +19.3), weights release (48.6% versus 19.4%; +28.6, +21.6 to +35.0) and variance (66.4% versus 42.1%; +24.4, +20.7 to +27.9). Medical papers had higher reporting rates for nine of the ten indicators. None of the three prespecified directional hypotheses was supported. For each practice, the estimated difference favoured medical papers. The exception was claims listed and each linked to a table, figure or theorem, which was rare in both groups (2.7% versus 6.1%; −3.3, −4.7 to −1.9). Compute was rarely reported by either group (21.7% and 17.1% gave an amount), and most papers did not report their compute tier (1,349 of 1,568 medical papers).

The four differences remained positive across the specified sensitivity analyses (Note 9-12, F1): leaving out each venue-year in turn, using coder 1's or coder 2's codes alone, restricting to papers whose excerpt was not truncated, and stratifying by venue-year and excerpt length. They also remained positive for clinical and life-science papers separately and for vision venues (CVPR, ICCV, ECCV) and learning venues (ICLR, ICML, NeurIPS) separately, except open main data at vision venues (+7.5, −1.9 to +16.9).

A training-set size was not reported in 43.7% of other papers and 28.0% of medical papers. Among the 1,129 medical and 962 other papers reporting a training-set size, all four differences remained positive: code +10.6 percentage points (+6.0 to +15.0), open main data +7.1 (+2.1 to +12.2), weights +21.7 (+12.7 to +30.7) and variance +24.7 (+20.1 to +29.3) (Table 4). Release fields were often not reported at all: a statement on weights could be coded for 280 of 1,568 medical papers. In a sensitivity analysis treating `unclear` as no reported release, medical papers still more often reported open main data (46.2% versus 24.7%; +21.7, +18.4 to +24.7). The estimated weights difference decreased to +3.1 percentage points (+1.3 to +4.8). Intervals for sample or synthetic data (−0.6, −1.7 to +0.5) and outputs (−0.2, −1.2 to +0.8) included zero.

### Reproduction outcomes in the ICML 2026 challenge

Medical papers were attempted about as often as other papers (110 of 328, 33.5%, against 1,821 of 5,391, 33.8%) but by fewer teams (mean 1.5 against 3.3 teams per attempted paper). Among attempted papers, 46.4% of medical papers were decided against 65.5% of other papers, a difference of −19.1 percentage points (95% CI −28.4 to −9.6; permutation p < 0.001). The estimated difference was −23.6 percentage points for clinical papers (95% CI −36.2 to −10.9) and −13.4 for life-science papers (−27.5 to +0.9), and it was −19.1 (−29.7 to −8.7) when every logbook of the team with the most medical attempts was dropped. The difference was also negative for full verification (−19.3, −22.1 to −15.7) and for any falsified claim (−10.8, −16.9 to −4.1). Claims of medical papers were rated verified in 21.7% against 49.7% and inconclusive in 49.2% against 24.8%. Toy verdicts accounted for 25.5% of medical claims and 20.9% of other claims (difference +4.7 percentage points, 95% CI −0.6 to +10.7). In the prespecified analysis on the 222 attempted frame papers, the difference was −17.0 percentage points (−29.7 to −4.4); adjustment for reported compute tier and data scale changed it to −14.7 (−28.8 to −0.5).

Table 2 and Figure 4 show the post hoc analyses. In comparisons within the same team, the difference in the proportion of claims decided decreased from −29.1 to −3.6 percentage points (95% CI −7.8 to +0.8). The first team to take up a medical paper had a decided claim on 40.0% of its other attempted papers, against 60.3% for teams first on other papers (−20.3, −26.0 to −14.3). Among 903 papers attempted by at least two teams, the team with better performance on other papers was more likely to obtain a decided verdict on the same paper (difference +32.3 percentage points, 95% CI +29.9 to +34.7). After adjustment for the first team's performance on other papers, the difference in papers with a decided claim decreased from −19.1 to −3.6 percentage points (95% CI −11.9 to +5.1). A difference in full verification remained (−11.7, −14.7 to −8.0). Adjustment for whether a paper listed and linked its claims changed the decided difference to −15.3 percentage points (−28.5 to −2.2; 216 frame papers); few attempted papers in either group linked each claim to a result (3 medical and 9 other papers).

In the 220-paper subsample, coders classified 56.7% of medical claims and 39.1% of other claims as requiring retraining or large-scale runs (difference +17.6 percentage points, 95% CI +9.7 to +25.8), and 19.3% and 45.3% as checkable by analysis alone. In this subsample, the full-verification difference was −19.1 percentage points, −13.0 (−20.7 to −5.1) after adjustment for first-team performance, and −5.6 (−11.9 to +1.4) after adjustment for both first-team performance and claim requirements.

### Reported practices against logbook evidence

On the 222 attempted frame papers, agreement between reported code release and logbook evidence that the authors' code had been run was limited (kappa 0.22; n = 162; sensitivity 0.74, specificity 0.56). Agreement between reported open data and logbook evidence that the data were obtained was also limited (kappa 0.13, n = 89), and higher for weights (kappa 0.55, n = 43). Pooled with the 300 extension papers, the kappas were 0.28 (n = 347), 0.16 (n = 163) and 0.60 (n = 118). In the NeurIPS subset, agreement between checklist answers on code availability and the coded release statements was also limited (kappa 0.22, n = 152) (Table 3).

## Discussion

### Principal findings

Medical papers more often reported code release, open main data and variance than other papers at the same venues. These differences remained among papers reporting a training-set size. Statements about weights and other releases were often missing, and their estimated differences were sensitive to how missing values were handled.

In the ICML 2026 challenge, medical papers were attempted by fewer teams and less often received a verified or falsified verdict on at least one claim. Adjustment for the first team's performance on other papers reduced this difference from −19.1 to −3.6 percentage points. A difference in full verification remained. In the 220-paper subsample, this difference was further reduced after adjustment for the coded computational requirements of claims. These exploratory results identify factors associated with reproduction outcomes; they do not establish why the outcomes differed.

### Comparison with earlier work

An earlier survey found weaker sharing in ML for health than in other ML areas [2], and audits of medical imaging found low rates of shared and working code in radiology journals [3] and at a medical imaging conference [4]. Our frame differs: it covers only papers accepted at general ML venues, several of which have introduced code policies and checklists [6], and it compares medical papers with other papers at the same venues and in the same years. In our sample, medical papers more often reported code release, open main data and variance. Earlier audits assessed reporting [5] or tested whether shared code ran [3, 4]; here reported practices could be compared with logbook evidence from independent reproduction attempts, and agreement for code was limited (kappa 0.22). PaperBench evaluated agents on a fixed set of 20 ICML 2024 Spotlight and Oral papers [8]; in an open challenge, by contrast, participants choose what to attempt. In this challenge, paper domain was associated with the performance of the teams attempting a paper and with the requirements of its claims.

### Implications

An unadjusted verification rate combines paper characteristics with differences in who attempts the papers and how the attempts are conducted. It should therefore be interpreted alongside team participation, performance on other papers and claim requirements. Reporting guidelines for ML-based science [15], for clinical prediction models that use ML [16] and for deep learning in medical imaging [17] concern what authors report. We propose the following reporting changes based on the gaps identified in this study. We did not test whether these changes improve reproduction outcomes.

### Recommendations

For authors of medical ML papers:

- List the main claims and link each to its supporting table, figure or theorem. This mapping was present in 2.7% of medical papers and 6.1% of other papers.
- Specify how the main data can be accessed: openly, with credentials, on request or privately. Access could not be coded from the text for 702 of 1,568 medical papers.
- State whether weights, outputs and sample or synthetic data are released, including when they are not. Weights were not reported in 1,288 of 1,568 medical papers.
- Report the hardware and runtime required to check each main claim. The compute tier was not reported in 1,349 of 1,568 medical papers.

For organisers of reproduction challenges and for logbook formats such as Trackio:

- Link each extracted claim to the specific result being checked, including its table, figure or theorem. The challenge used claims extracted from abstracts [9].
- Record in each logbook, per claim, whether the authors' code was run, the main data obtained and the weights used.
- For each claim, record the type of check: inference, retraining, large-scale runs or analysis only. Report the compute used and give a reason for an inconclusive verdict.
- Report the number of teams attempting each paper and their performance on other papers. Present unadjusted domain comparisons alongside analyses accounting for these factors.

For venues:

- Use explicit categories for data access and material release, and ask authors to link each main claim to its supporting result. In the NeurIPS subset, agreement between checklist answers on code availability and the coded release statements was limited (kappa 0.22).

### Strengths and limitations

The frame included all papers identified as clinical or life science by the screening procedure, together with a random comparison sample allocated across the same venue-years. The protocol and coding rules were fixed before sample selection, every coding decision is public, and the main reporting differences remained positive across the specified sensitivity analyses. The study has several limitations. All coders, adjudicators and the challenge judge are language models; agreement between coders was high, but they may share systematic errors, and verdicts on the same claim from different logbooks agreed poorly in the challenge as a whole [13]. More comparison papers lacked a reported training-set size. Restricting the analysis to papers reporting one reduced the differences for code, open data and weights, while all four estimated differences remained positive. Full texts were missing for a quarter of the frame, mostly at NeurIPS 2026 and ICLR, where we relied on arXiv; retrieval was lower for medical papers, and papers posted on arXiv may report more than papers that are not. Many excerpts reached the character limit, which may have omitted relevant release statements. Release fields were often coded as `unclear`, and several estimated differences decreased when these values were treated as no reported release. Coded practices are what authors report, not working artifacts. Performance on other papers may reflect the agents, human input, compute and paper selection of a team. We did not measure these components separately. The reproduction outcomes come from one venue, one challenge and one judge model, and the challenge's participants chose what to attempt. Protocol 9 was developed after the results of earlier protocols on the same challenge were known, including the higher rate of code links in medical papers. Analyses of team performance and claim requirements were post hoc and were not adjusted for multiple comparisons. They used different samples: all attempted papers for team performance and a 220-paper subsample for claim requirements. The adjusted estimates are exploratory and do not establish causal explanations.

### Conclusions

Medical papers more often reported several reproducibility practices than other papers at the same ML venues. In the ICML 2026 challenge, they less often received a verified or falsified verdict on at least one claim. Exploratory analyses associated these outcomes with team performance and, in a subsample, the computational requirements of claims. Reporting practices and reproduction outcomes should therefore be assessed separately. Authors should link their main claims to specific results, and reproduction reports should document team participation, material use and the resources required for each check.

## Declarations

**Data availability.** The repository contains the paper-level table for all 4,340 papers, claim codes, frozen protocol, analysis code and aggregate results: https://github.com/kondratevakate/life-science-at-ml-venues [DOI to be added on release]. The paper-level table includes identifiers, titles, group labels, full-text retrieval status and coded fields. Code is released under the MIT licence; data and text are released under CC BY 4.0. Abstracts and full texts were retrieved from public conference websites, arXiv and open proceedings and are not redistributed for copyright reasons; the repository contains the retrieval scripts and SHA-256 manifests of the retrieved files. Challenge verdicts come from the public snapshot of the ICML 2026 agent reproduction challenge retrieved on 17 October 2026. No patient data were used.

**Code availability.** All analysis code is in the repository above; `python setup_data.py` links the retrieved inputs and each analysis script reproduces its result file. Rerunning all Protocol 9 analyses from the committed codes gave byte-identical results.

**Ethics approval and consent.** Not applicable: secondary analysis of published papers and public challenge records, with no human participants and no patient data. Public account names of challenge participants were used only to group logbooks by team and are not reported.

**Competing interests.** EK took part in the ICML 2026 agent reproduction challenge as a reproducer; her own logbooks were excluded from all analyses. [Other competing interests of all authors to be added.]

**Funding.** [To be added.]

**Author contributions.** [To be added in CRediT terms.]

**Use of AI tools.** Language models produced domain labels, documentation codes, logbook codes and claim classifications. We used claude-sonnet-5-5 for coding and claude-opus-5-5 for adjudication under the published protocol and prompts. Claude also assisted with analysis code and manuscript drafts. The authors checked every number against the result files and take responsibility for the content.

## References

1. Haibe-Kains B, Adam GA, Hosny A, Khodakarami F, Massive Analysis Quality Control (MAQC) Society Board of Directors, Waldron L, et al. Transparency and reproducibility in artificial intelligence. Nature. 2020;586(7829):E14–6. doi:10.1038/s41586-020-2766-y
2. McDermott MBA, Wang S, Marinsek N, Ranganath R, Foschini L, Ghassemi M. Reproducibility in machine learning for health research: still a ways to go. Sci Transl Med. 2021;13(586):eabb1655. doi:10.1126/scitranslmed.abb1655
3. Venkatesh K, Santomartino SM, Sulam J, Yi PH. Code and data sharing practices in the radiology artificial intelligence literature: a meta-research study. Radiol Artif Intell. 2022;4(5):e220081. doi:10.1148/ryai.220081
4. Simkó A, Garpebring A, Jonsson J, Nyholm T, Löfstedt T. Reproducibility of the methods in medical imaging with deep learning. In: Medical Imaging with Deep Learning. Proceedings of Machine Learning Research. 2024;227:95–106.
5. Gundersen OE, Kjensmo S. State of the art: reproducibility in artificial intelligence. Proc AAAI Conf Artif Intell. 2018;32(1). doi:10.1609/aaai.v32i1.11503
6. Pineau J, Vincent-Lamarre P, Sinha K, Larivière V, Beygelzimer A, d'Alché-Buc F, et al. Improving reproducibility in machine learning research (a report from the NeurIPS 2019 reproducibility program). J Mach Learn Res. 2021;22(164):1–20.
7. Kapoor S, Narayanan A. Leakage and the reproducibility crisis in machine-learning-based science. Patterns. 2023;4(9):100804. doi:10.1016/j.patter.2023.100804
8. Starace G, Jaffe O, Sherburn D, Aung J, Chan JS, Maksin L, et al. PaperBench: evaluating AI's ability to replicate AI research. In: Proceedings of the 42nd International Conference on Machine Learning. PMLR; 2025. p. 56843–73.
9. Abid A. What we learned by reproducing 2,200 papers from ICML [Internet]. Hugging Face; 2026 Aug 13. Available from: https://huggingface.co/blog/icml-2026-open-reproductions
10. Page MJ, McKenzie JE, Bossuyt PM, Boutron I, Hoffmann TC, Mulrow CD, et al. The PRISMA 2020 statement: an updated guideline for reporting systematic reviews. BMJ. 2021;372:n71. doi:10.1136/bmj.n71
11. Cohen J. A coefficient of agreement for nominal scales. Educ Psychol Meas. 1960;20(1):37–46. doi:10.1177/001316446002000104
12. Wilson EB. Probable inference, the law of succession, and statistical inference. J Am Stat Assoc. 1927;22(158):209–12. doi:10.1080/01621459.1927.10502953
13. Umoh EH. Who verifies the verifier? Measuring LLM-as-judge reliability across 32,688 automated research verdicts [poster]. AWS-MLU Fall AI Teaching and Research Symposium; 2026 Sep 22; Arlington, VA. Available from: https://github.com/SturdivantAI/who-verifies-the-verifier
14. Mantel N, Haenszel W. Statistical aspects of the analysis of data from retrospective studies of disease. J Natl Cancer Inst. 1959;22(4):719–48. doi:10.1093/jnci/22.4.719
15. Kapoor S, Cantrell EM, Peng K, Pham TH, Bail CA, Gundersen OE, et al. REFORMS: consensus-based recommendations for machine-learning-based science. Sci Adv. 2024;10(18):eadk3452. doi:10.1126/sciadv.adk3452
16. Collins GS, Moons KGM, Dhiman P, Riley RD, Beam AL, Van Calster B, et al. TRIPOD+AI statement: updated guidance for reporting clinical prediction models that use regression or machine learning methods. BMJ. 2024;385:e078378. doi:10.1136/bmj-2023-078378
17. Moassefi M, Singh Y, Conte GM, Khosravi B, Rouzrokh P, Vahdati S, et al. Checklist for reproducibility of deep learning in medical imaging. J Imaging Inform Med. 2024;37(4):1664–73. doi:10.1007/s10278-024-01065-2

## Appendix A. Protocol and reporting

Protocol 9 was frozen on 19 October 2026, before sample selection, full-text retrieval and coding (commit 839281e in kondratevakate/icml-2026-repro). It was developed after the results of Protocols 6 to 8 on the same challenge were known. Subsequent decisions were recorded in dated protocol notes (Notes 9-1 to 9-22) before the corresponding analyses were run. Analyses added after the original protocol are labelled post hoc and exploratory. The study was not registered in a review register. We report it following the PRISMA 2020 statement [10] where its items apply to a meta-research study of published papers; the completed checklist is Supplementary File S2. The protocol, all notes and their commit history are in Supplementary File S1 and the repository. Table A1 gives the papers in the frame and with a coded full text per venue-year.

TABLEA1

## Tables

TABLE1

TABLE2

TABLE3

TABLE4

## Figure legends

**Figure 1.** Reported reproducibility practices and reproduction outcomes in medical and other papers. (a) Among papers with a known value, medical papers (orange) more often reported code release, open main data and variance than other papers (blue); both groups rarely linked their claims to a specific result. (b) In the ICML 2026 challenge, attempted medical papers less often had a decided claim, with fewer claims verified and more rated inconclusive. (c) Within-team comparisons and adjustment for first-team performance reduced the estimated difference in decided outcomes. In the 220-paper subsample, additional adjustment for claim requirements further reduced the full-verification difference. Filled circles: interval excludes zero; open circles: interval includes zero. (d) Agreement between reported practices and logbook evidence of material use; the dashed line marks kappa 0.40.

**Figure 2.** Study selection and full-text retrieval. Full texts were retrieved for 3,278 of 4,340 papers. Retrieval was lower for medical papers than for other papers (72.3% versus 78.8%).

**Figure 3.** Differences in reported practices among papers with a known value for each indicator. Medical papers had higher reporting rates for nine of ten indicators and a lower rate of explicit links between claims and supporting results. Mantel-Haenszel risk difference, medical minus other, over nine venue-years with 95% bootstrap intervals. Filled circles: interval excludes zero.

**Figure 4.** Unadjusted and adjusted differences in reproduction outcomes between medical and other papers. Estimates are shown at paper level for decided and fully verified outcomes, and at claim level before and after comparisons within teams. Estimates use all attempted ICML 2026 papers (or their clinical or life-science subset, where labelled), except the last paper-level row, which uses the 220-paper subsample with coded claim requirements. Filled circles: interval excludes zero.
