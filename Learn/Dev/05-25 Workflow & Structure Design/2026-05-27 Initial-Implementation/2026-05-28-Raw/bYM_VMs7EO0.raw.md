---
# === meta ===
schema_version: 3

# === identity ===
id: bYM_VMs7EO0
type: youtube
url: "https://www.youtube.com/watch?v=bYM_VMs7EO0"
title: The Most Expensive Hire In AI History Finally Talks
aliases:
  - The Most Expensive Hire In AI History Finally Talks

# === pipeline ===
status: extracted
metadata_status: ok

# === creator ===
channel: Core Memory Podcast
channel_url: "https://www.youtube.com/channel/UC2ohDbbkpfngjaeV7TBHRcg"
channel_follower_count: 0

# === time ===
duration: 4980
upload_date: 20260513
fetched_at: "2026-05-25T13:07:01+00:00"

# === visual ===
thumbnail: "https://i.ytimg.com/vi/bYM_VMs7EO0/maxresdefault.jpg"
thumbnail_image: "Learn/Dev/05-25 Workflow & Structure Design/2026-05-27 Initial-Implementation/2026-06-03-Thumbnail/bYM_VMs7EO0.jpg"

# === content structure ===
chapters:
  - start: 0
    title: Intro
  - start: 122
    title: Inside Meta Superintelligence Labs
  - start: 383
    title: The Tahoe Conversation That Changed Everything
  - start: 770
    title: "How Do You Rebuild a Frontier Lab in 9 Months?"
  - start: 1475
    title: "The Soup, Sam Altman, and Being \"Too Young\""
  - start: 1968
    title: "MuseSpark: Appetizer, Not Entrée"
  - start: 2927
    title: "Why Does Everyone Hate AI Right Now?"
  - start: 3230
    title: Open Source
    Safety: null
    and the Manus Question: null
  - start: 3899
    title: Robots
    Mangos: null
    and Health Superintelligence: null
  - start: 4268
    title: "Sci-Fi, BCI, and Do AI Models Deserve Moral Weight?"
chapters_usable: true

# === language ===
language: en-US
original_language: en

# === subtitles ===
manual_track_languages: []
auto_track_languages:
  - en
transcript_status: available
transcript_source: auto_en
transcript_target: null
is_translated: false

# === engagement ===
view_count: 34456
like_count: 661

# === availability ===
availability: public
live_status: not_live

# === errors ===
metadata_error: null
transcript_error: null
thumbnail_error: null
---

# The Most Expensive Hire In AI History Finally Talks

## Description

Alex Wang has barely said a word in public since Mark Zuckerberg paid a fortune to bring him in and put him in charge of Meta's artificial intelligence push. 10 months later, the co-founder of Scale AI sits down with Ashlee Vance and Kylie Robison for his first long interview to explain what he has actually been doing inside Meta Superintelligence Labs, why Llama 4 was off course, and how his team rebuilt Meta's entire frontier model stack from scratch in nine months.

The conversation cuts through a lot of the noise from last summer's recruiting frenzy. Wang lays out the structure of MSL and the now infamous TBD lab, his three principles for catching the frontier (compute per researcher, talent density, and very big research bets), and what the day to day actually looks like with Nat Friedman, Daniel Gross, and chief scientist Shengjia Zhao. He also takes on the personal stuff: the cost of leaving Scale, the public swipes from Sam Altman and Yann LeCun, the soup rumors, and the perception that Meta simply bought its way back into the AI race.

Wang also walks through MuseSpark's surprising token efficiency, why he calls the model an appetizer rather than the entrée, where Meta lands on open source after keeping this release closed, the Manus deal and US versus China geopolitics, the new humanoid robotics acquisition, and a long final stretch on health superintelligence with CZI, brain computer interfaces, model welfare, and why he thinks the path to paradise on earth runs through superintelligence.

About the Hosts

Ashlee Vance is a journalist, author, and filmmaker best known for his New York Times bestselling books, including the biography of Elon Musk and When The Heavens Went on Sale. He spent years at Bloomberg Businessweek covering Silicon Valley, space, and the people building the future, where he also created and hosted the Emmy-nominated series Hello World. His documentary work includes Wild Wild Space for HBO and Don't Die for Netflix. Now he runs Core Memory, a media company telling stories about scientists, inventors, and startups changing the world, from biotech labs to factory floors to the edge of space.

Kylie Robison is a technology journalist and co-host of the Core Memory podcast. She previously covered artificial intelligence and the tech industry as a reporter at The Verge and Wired.

Links

Meta Superintelligence Labs and Meta AI research: https://ai.meta.com
Mark Zuckerberg's "Personal Superintelligence" memo: https://about.fb.com/news/2025/07/personal-superintelligence/
Scale AI: https://scale.com
Manus: https://manus.im
Chan Zuckerberg Initiative: https://chanzuckerberg.com
Brex (sponsor): https://brex.com/corememory
Send Cut Send (sponsor): https://sendcutsend.com/corememory

Subscribe to watch more Core Memory videos https://www.youtube.com/@CoreMemoryVideos/videos

Check out our podcasts https://www.youtube.com/@CoreMemoryPodcast
https://www.corememory.com/podcast

Find Ashlee Vance at 
www.corememory.com 
https://www.instagram.com/ashlee.vance/
https://x.com/ashleevance

Find Kylie Robison at
https://x.com/kyliebytes
https://www.instagram.com/kylie.robison

Chapters
00:00 Intro
02:02 Inside Meta Superintelligence Labs
06:23 The Tahoe Conversation That Changed Everything
12:50 How Do You Rebuild a Frontier Lab in 9 Months?
24:35 The Soup, Sam Altman, and Being "Too Young"
32:48 MuseSpark: Appetizer, Not Entrée
48:47 Why Does Everyone Hate AI Right Now?
53:50 Open Source, Safety, and the Manus Question
1:04:59 Robots, Mangos, and Health Superintelligence
1:11:08 Sci-Fi, BCI, and Do AI Models Deserve Moral Weight?

## Transcript

[00:00:00] All right, Kylie, we've got another big guest this week. >> Huge >> Alex Wang, the chief of Meta's artificial intelligence efforts. It was how many months ago? >> About 10 months ago. >> About 10 months ago, he was the founder, co-founder and CEO of Scala. I met a sort of quasi acquired >> the company half acquired the company and fully acquired Alex and he's been he's been in in hid he's been in uh AI

[00:00:31] protection program since >> yes we haven't seen much of him whatsoever until today on the core memory pod. >> Yes. I am not sure exactly why this happened but here he is. He's gonna he's going to tell us um well we'll find out. He's going to hopefully tell us about they just released a new model. Um, I'm sure we will get into some of that and and then they're a little bit of a mystery to me about like where they are

[00:00:57] philosophically on AI. Alex has always been a bit of uh >> when he was at scale he was he was they always said they were Switzerland and he was loud on some things but not not always AI itself and and how he feels about it. And they made a lot of news last year with everyone they hired for millions and millions and millions of dollars and built up this team and everyone's been waiting to see what

[00:01:22] they're going to do with all of these resources. >> So we will talk about recruiting soup and and all these millions of dollars. So this is this is it. This is Alex Wang's um he's emerged. >> Hell yeah, brother. >> I am Ashley Vance >> and I'm Kylie Robinson >> and this is Core Memory.

[00:02:00] Alex, thank you for being here. >> Yeah, excited to be here. I feel like we were we kind of texted a little bit pre pre meta happenings. We had we had like this kind of country music odd text chain >> for sure >> going and then and then I'm also I've known Nat Freiedman for a long time. >> Yeah. Yeah. >> And then I feel like the two of you disappeared >> and went went into the foxhole. >> Yes. were very very quiet there and now

[00:02:32] here you are with a new model. >> Yeah. >> Emerging. >> Yeah. >> But you guys went very quiet for a bit. >> We uh Yeah, we had a lot of work to do. I mean, I think >> uh turns out um building a Frontier model from scratch in 9 months is uh yeah, it takes a lot of uh takes a lot of painstaking effort. But um but yeah, I mean it's been really exciting to see everyone use Muse Spark um you know, the

[00:02:55] model we released and um we have better models cooking. So, it's exciting. >> And so, what you I mean, you were like a San Francisco al light San Francisco, I guess. Um, and then I mean >> I assume you work at Menllo Park. Yeah. >> So, did were you did have you had to like >> I moved down to South Bay? Yeah. Yeah, I did. >> So, you're full on committed? >> I'm full on. Yeah. And for me, the city now is Palo Alto.

[00:03:21] >> Okay. >> Walk on University A get a bobbo. >> Okay. Hey, I was wondering about this and what's what's like the arrangement between I mean the people I know best are you, Nat, Daniel Gross. I've only hung out with Zach once or twice. Um yeah, I mean what's the I'm trying to pick paint a picture of of of how you guys are arranged. >> Yeah. So um so basically uh the the whole unit is called meta super

[00:03:49] intelligence labs um which which I oversee and then there's various pieces of it. So um there's a unit called TBD which is um the uh sort of large model research lab um that I think uh you know is somewhat infamous but that's where a lot of the um you know leading researchers and infrastructure engineers are um they actually all technically report to me. Um so that's one setup. Then there's also um a group called uh

[00:04:19] product and applied research or PAR for short. that's what uh Nat Freiedman heads up. So they're responsible for um all the products that we build um and the actual sort of deployment of these great models to the world. And then um also within the uh overall meta super intelligence uh labs umbrella is fair uh which continues to do exploratory and exciting research. Um I'm particularly excited about a lot of their scientific

[00:04:44] research. So you know we've shown some pretty great work on um you know using models AI models to understand the brain as well as using AI models to understand you know computational chemistry. we have built like a universal model for atoms um for short and then um and so that those pieces constitute meta super intelligence labs which I oversee in addition to having a very hands-on role with um TBD lab and then um Daniel Gross

[00:05:12] uh helps lead up meta compute which is really focused on our long-term infrastructure planning to ensure that you know we obviously can um build up all of the GPU infrastructure and and data center infrastructure are necessary for this very bold endeavor. Um, and uh, and so he heads that up and partners closely with us. >> And I mean, who did you know the best out of that group before you got into

[00:05:35] this? >> Um, well uh, I knew I've known DNA and Daniel actually for a long time. Nat was one of our very first one of my very first angel investors at scale. Um and I think like in before I completed YC, Nat had invested in scale and had given me advice throughout the years. Um Daniel I think I also met around that time um you know very very early on and have gotten to know them through the years. And then

[00:06:04] um we also have our chief scientist Shenza who um helps oversee the scientific agenda across all of MSL. And um he is somebody who I uh have gotten to know you know I knew before starting MSL but you know since he's come in we've gotten a lot closer. So >> I'm really curious like taking a huge step back it's been 10 months since you kind of went into hiding your company you know completely changed and now

[00:06:31] you're at Meta. What was that experience like? How was the deal made? Like how did you end up going to Tahoe in talking with Zuck? Can you just walk us through what that first meeting was like? >> Yeah, so it was so I've known Mark um for many years now. I think uh even while I was running scale, I would um he was very generous with his time and I sort of was able to get a bunch of advice from him and he um obviously is

[00:06:58] just such an experienced you know founder and like the the founder at this point in some in some sense um and uh and so we've known each other for many years and and we had actually talked about um AI before a lot of this craze because you know scale obviously we'd been working on AI since 2016. Um and uh you know back when it was mostly self-driving and then you know the various transitions of the technology. Um and then around a

[00:07:26] year ago almost like literally a year ago um you know we had a conversation where we sort of um started exploring uh if there were a way to work more closely. Um and um in particular I think Mark at that point I think he um was uh becoming increasingly AGI pilled and um and really knew that first AI was going to totally transform meta but also that AI was one of these um you know almost like once in a lifetime transformative

[00:07:59] technologies and so he was really um quite focused on it and and knew he wanted to bet very big on it and um at the same time, you know, uh, you know, and he's talked about this publicly, like Long before was not on the trajectory that um that they that the company needed to be able to um continue making some of these bets. And so we were sort of talking at a very high level about, you know, how could we work

[00:08:25] together more closely? What could that look like? And um, obviously it kind of, you know, it was one of these very open-ended questions and these very open-ended brainstorm sessions as these things often are. And it sort of landed in this interesting zone where we figured out a way to do it in a way in a way that was like good for scale that was good for meta and where we got to work very very closely together to build

[00:08:47] out you know the most important technology of our time and do so in a way that um where we both had conviction that it was going to be you know we're building something that we' both be really proud of which is you know he put out this memo of personal super intelligence also about a year ago um and then we went quiet obviously but um but I think that really is the sort of like north star for both of us is we

[00:09:08] want to build this technology in a way that empowers people where you know as many people in the world have access to it and it's as democratized as possible that enables you everyone to express themselves everyone to have increased agency everyone to create and build um and that's really the world that we want to work towards >> but you're you know I did a really early story on you I mean I've known you for a

[00:09:28] long time yeah in >> 21 I think so I mean and you you know there's all this lore you were the >> youngest a self-made billionaire and and this hot [ __ ] and scale was such a prominent company and you had this uh reputation for reading the tea leaves of where AI was going to go. I mean like and when I would talk to you I mean scale was part of your identity. It's very different to be the founder of this

[00:09:54] very prominent company and then taking a role at a place with 80,000 employees even if you're it's a prominent role at that company. And yeah, I mean I can I think I was really surprised. I mean there's a lot of money involved. So like Okay. But just sort of knowing you, it's not like I know you that well, but just knowing you as much as I did. Yeah. I was I was like, man, that must have been a hell of a sales pitch to cuz it's a

[00:10:20] big flip. >> Yeah. Yeah. Very different. It's super different. And um you know a lot of what what I was thinking about throughout this process is obviously I think like everyone in and around AI I mean progress has just happened I think a lot faster than I I'd expected for a long time. Um and um in the sort of like accelerating progress of these AI models I think a few things really started to stick with me. one is, you know, um it

[00:10:52] felt like and I do think this is increasingly the case that um those who build the AI models have uh just greater and greater rights so to speak or or both economic and product rights to just build so much more around those models. And there were obviously all these early debates around, you know, what are um how does the ecosystem play out? And I think because of just how fast the models are improving and how fast

[00:11:21] research what the how fast the research pace is it just means that you know in many ways building being a place that is building the models is are some of the most exciting places to be in the ecosystem. Um and then the second is really that that so much of this next phase of technology really boils down to compute and um you know if you have lots and lots of compute then you have the ability to build things and make big

[00:11:47] bets and deploy products and do things that you just can't if you don't have that compute and I think that um this causes this will cause an interesting stratification for the tech ecosystem where you know right now in some sense we think about well I think this is already changing but um you know you kind of think about all tech companies the same but in reality you should think about companies with lots of compute

[00:12:10] very differently from companies without cat compute because um there's just things that companies with compute can build that those without compute just cannot and so it it creates this very interesting dynamic and so part of what was very exciting about the opportunity at Meta first is that obviously Mark is um I think very allin on AI and really um has bet very big and is a very bold um sort of leader and strategist, but

[00:12:38] also that you know this created the conditions where you we're able to build with huge amounts of compute um and with the right research effort and the right product efforts we have the ability to really u make a huge dent in the world >> and you guys have a ton of compute and you guys poached a lot of amazing talent and that was I was a part of that whole uh reporting frenzy at the time it is unlike anything I've ever seen before

[00:13:02] and it's been 10 months with many of these people. So, what has what has it been like? What have the challenges been? And like what has been the most exciting about having this whole new team at Meta? >> Yeah. So, you know, um when I got when I kind of got to meta, um you know, it was it was clear that there needed to be some reset of the efforts and and some rebuild of our AI AI efforts to get onto

[00:13:29] the right trajectory because ultimately like, you know, Llama was not on the same trajectory and so we were behind the the frontier and so we needed to build a plan that would enable us to have a very very fast velocity um to be able to both catch up and hopefully exceed uh where the frontier is. So, >> can you be spec like what were the problems that you found? Um you know I I uh I think that probably

[00:13:57] the more fundamental ones are just around you know a lot of the leading labs they build the entire organizations around the premise that super intelligence is coming and it is very close and this is a very realistic thing to believe that we can create and produce. And then you build the entire plan of the lab and the business and what you focus on around this fundamental belief. And um and so that

[00:14:25] was one of the first things is is to just take super intelligence seriously and then start to rebuild all of your other assumptions around that core premise. Um so that's something I think was was somewhat fundamental. Um >> so you mean that they're like lacking this religious conviction to all this on some level? Yeah. And I think I think this is relatively common actually for I I think there's a lot of people um at all the

[00:14:50] large companies who don't necessarily have this conviction because if you think about it they've you know um it's a bit of a different construction like a lot of the the big companies um you know they have very smart people who work on AI but it's a little bit different from you know these startups where it's like you know these it's like these new efforts started from scratch with this like crazy idea that super intelligence

[00:15:10] is coming. So um I don't think this is a problem anymore. Like obviously I think now uh MSL meta super intelligence labs is it's in the name built around this concept that um super intelligence is coming. So so there were a bunch of principles that we sort of laid out for the effort to and I think this sort of answers as to you know what were the things that we had to resolve but one is take super intelligence seriously. Um

[00:15:33] two is technical voices are loudest. Uh three is scientific rigor focus on basics. um and uh make big bats. So the the concept of uh TBD and and MSL broadly when I sort of got started was I thought about how what what would actually be the shape of a lab that would enable you to have incredibly fast velocity and catch up and potentially even overtake the frontier. And I came down to there were three three ways that

[00:16:07] I felt like that was possible. One is to have much higher compute per researcher. So um you know a lot of the larger labs they have lots of compute but it gets spread so many different ways and so that actually impedes the research velocity of any individual researcher. So if you build a more focused effort with a smaller team that has higher computer researcher you can actually make faster research progress. Um, two

[00:16:32] is talent density. So just and this is like I think you know I feel like human organizations always relearn this lesson but the very small team where everyone is cracked is always um going to move faster than the very large organization where responsibility is more distributed and you know it's more of a milange um and the last one was on very ambitious research bets and um you know I think uh I mean I think this is very well agreed

[00:17:04] upon in the industry. There's clearly there do exa exist these research bets that are very big and very risky but if they work out can totally change paradigms and totally shift um how we build modern AI and so you know in in addition to obviously building towards very competitive frontier models we're allocating a huge amount of our resources and compute towards these big ambitious bets um because they pan out

[00:17:30] then that gives us you know incredible models going forward. All right. What do we do at Core Memory? We cover innovative, fastmoving, forwardthinking companies, which is why Core Memory is sponsored by Brex because BR is the intelligent finance platform for many of these companies. 30,000 companies from startups to the world's largest corporations rely on Brexit for their finances. They've got smart corporate cards, high

[00:18:00] yield business banking, and expense automation tools that are fantastic. I hate doing my expenses. And Brex's AIS software run right through those expenses, figure out where we're spending money and take care of so much stuff for you so you don't have to waste your time on it yourself. Go to brex.com/cormemory to learn more and just, you know, get with the program. Let's get going. Let's get out of this archaic finance software

[00:18:29] and move toward the future. Core memory and bre >> something Ashley always talks about is uh how these labs are sort of leaprogging over each other and they start to just serve the same thing and you're talking about racing towards the frontier. I'm also thinking about you know the people that you guys hired you was reported for these really really wild salaries like we've never seen before. So like how are you, you know,

[00:18:54] getting to this paradigm you speak of? Like specifically what paradigm are you trying to uh achieve? >> Yeah, I mean I think um I think there's there's a bunch of bold research bets and I won't be able to go into detail on all of them, but um but I do think like one fundamental question is what do we care about? And um we you know in line with this idea of personal super intelligence we really care about

[00:19:17] building these um agents that are able to empower consumers. So empower billions and billions of people all around the world as well as um empower businesses. You know we have meta is kind of this incredible ecosystem. We have the billions billions of users which I think everyone knows about but we also have hundreds of millions of businesses on our platforms that you know use Meta to run and operate their

[00:19:42] businesses. And so we really care a lot about building towards this future where we're able to build very powerful agents that empower and enable every one of both the consumers and the businesses on our platforms um and build kind of this new agentic ecosystem. um you know we think a lot about what that looks like and what are the capabilities we need to to build towards that and you know obviously on that trajectory there's a

[00:20:08] bunch of sub components that are really important like we really have to have great agent capabilities um we have to have great coding capabilities because so much of what needs to be built is software as you as you you know really get into it uh we need to have great multimodality um so it it it informs a lot of the like underlying bits and pieces that we need and then we need to solve a lot of the I think the bigger

[00:20:28] questions for longunning agents like how do you think about the memory challenges? How do you think about building longrunning agents? How do we build agents that are able to do more and more complex tasks on behalf of um the user? So um those are a lot of the you know high level pieces that we're thinking a lot about. So if you I mean you're trying to get this this super intelligence religion built

[00:20:51] within the company. Um there is there the way this was arranged is quite different to starting open AI or anthropic where like you were talking about earlier this is all built from the ground up and these companies have sort of an identity and and and it gets shaped over time. For the outsers view what you guys did looks far more mercenary. You know what I mean? It's like we're gonna go, you guys are out.

[00:21:17] We're gonna go grab a bunch of high-priced people, bring them in, and and it reminds me, you know, I just remember when Grock was starting up and it was like Elon in his Elon way, just like we're just going to get way more [ __ ] compute than anybody else and and we have kind of this core team we're going to build around and and then it still felt like they caught up, but then never reach that escape velocity,

[00:21:42] especially in people's minds of of brand and things like that. So I mean it just seems like it's a hard thing to buy some of the bits that you're talking about. >> Yeah. I I would say um this is one of I think the the larger I would say like narrative violations or maybe like differences between external perception and what the day-to-day inside is like actually I think a lot of people you know uh maybe have some of the

[00:22:08] impressions that you're talking about and a lot of that is formed because of just you know the the reporting and and what it sort of like you know how that sort of went down and a lot of the reporting was overstated in various ways but you know it sort of it all sort of like bubbled up and part of it was because did the recruiting so quickly like we knew that >> um when I got in I knew I was like if we

[00:22:28] want to build great models we need to have the the team yesterday. So we had to just go and blitz it and do it very very quickly. Um but I but I think that the culture within the lab is actually um very much so a startup and there's a bunch of things that I think have have created this feeling. I think one is that um it it was an entirely newbuilt team kind of like within meta. But then um the culture of the lab is like I mean

[00:22:59] everybody was very attracted and excited about um these things I talked about like people joined because um you know there was high computer researcher so they could make more progress than maybe they would they would be able to make at wherever they were before um because there was great talent density like people saw that it was like a truly cracked group that was pretty small and that we were going to give them the

[00:23:21] resource and freedom to make very bold research bets. So the sort of um I think it's like an incorrect uh assumption to think that like the researchers are are just money motivated or or anything and and for most of them actually like you know the financial prospects of them staying wherever they were look very good as well like looked very very very strong as well. Um so money was not I you know those sort of like maybe how it

[00:23:48] seemed like but the primary motivations were actually much more that um they had an opportunity to kind of like build from scratch and have lots of compute have the ability to approach their like very ambitious research directions and then do so in a group that didn't feel bloated. Um so I think as a result the sort of like vibe and culture are much healthier and I would actually say like um you know many people who visit the

[00:24:14] lab who are at one of the other labs like often comment that the vibe is actually you know it reminds them of early openi or early anthropic or you know um kind of these like more um uh nent stages of these other labs because in some sense we're like you know now 10 months old as as an effort. >> So, and just cuz Mark Chen was on this podcast and brought up the soup um debacle during these recruiting um wars.

[00:24:43] Yeah. Did you Did you Is this true? Did Zuck make soup? Did you make soup to recruit people? >> I don't know if we made the soup, but uh but um >> I was told it was actually made by Zuck, but I don't know. Um I I don't know if we made this suit, but I do think it is true that we like I think um part of part of the premise of building this lab was also that like we had to show everyone that we really really cared

[00:25:12] about this technology and we cared about their specific research directions and what they were working on. And um it was a very um individualized recruiting process. Um, but also was one like I um I mean I'm I'm very proud of the team that we've built and I think that like um people had to know that we were serious too. Like I think that by default a lot of people didn't know what to think about Meta's AI efforts or um

[00:25:40] they didn't know you know they didn't know that much about us in many ways. So, so it took a lot of like going to people, talking to them, explaining what we're building, explaining what we're focused on, explaining what we why we cared about the technology, what we wanted to do with it. Like that was very important. >> I mean, I'll move on after this um to not just belabor all the recruiting stuff, but you know, same thing when you

[00:26:00] were at scale, you were like the everyone would call you the Switzerland of of AI. And then I just remember you knew everybody and and you were you were in the center of things and and then it feels like some of this came with a personal cost. I mean, you and Sam used to be flatbaits and and I texted Sam about you coming on the show. He did not have flattering things to say and so, you know, it seems like some of this it

[00:26:24] defin. Yeah, I think that um you know I think some of this is is unfortunate and I my honest expectation is that like as we get closer and closer to super intelligence like my hope genuinely as a human that all the sort of animosities that exist between various people in this industry which is you know very topical obviously right now with the with other things that are happening but um uh but I I think that I think my real

[00:26:54] hope is that all these animosities subside over time and then people sort of um come together and realize you know this we are building this incredibly important technology and it's important for all of us to be really thoughtful about that as we build it and so um yeah I think uh um and and one of the things that I feel like is a responsibility of mine honestly is to ensure that you know we the technology that we develop and the

[00:27:23] ways we deploy it are as thoughtful as possible. some of the stuff you talked about like in terms of recruiting it was trusting that we have a mission and it's not you know just uh just products like you can go for your own research mission uh and you're also quite young we're almost the same age which is very funny and um >> and I'm not a billionaire. Um but Yan had said in the press shortly after he

[00:27:47] left that you were like young and inexperienced and more people were going to leave. So, I'm curious like how has that voted for you as a leader at this huge company and you're quite young like what was reading that like? Have you talked to him? >> Um yeah, I saw him in India like a couple weeks after that and uh and um I mean Yan is is um a notable very outspoken person and I think everyone always always knows what Jan is

[00:28:13] thinking. So um but uh but no I think I think um you know he obviously said what he said and I saw him in India. He congratulated us on the Muse Spark launch. >> I saw you guys patching things up on X. Yeah. >> Yeah. I mean it in like truly I I do exactly what I just said before. I think all personal animosities like I think as we get closer and closer to super intelligence we'll uh >> seems like it's getting worse. It does

[00:28:37] >> doesn't it does? Um, yeah, maybe it gets worse, maybe it gets better, but um, but yeah, no, I I think that, um, I think that, uh, you know, I have a lot of conviction in how we've set up MSL and the research efforts that we have and the progress that we're making. Um, and I'm excited to show the world the incredible work that our researchers are doing and the progress we're making. >> I al also don't want to belver the

[00:29:04] point, but is that a challenge you continue to face? like people thinking you're too young and inexperienced to lead such a huge effort at Meta. >> You also get the knock that you're not an engineer. >> Oh yes, >> that is definitely not true. Like I uh once upon a time I I was a software engineer in Silicon Valley. But um uh >> like doesn't this piss you off? >> Yeah. I mean I honestly I mean so on the

[00:29:30] age thing I mean like people have said this my whole time in Silicon Valley. So um you know to some extent like uh I I actually like I almost don't even think about it anymore cuz it's just it's always there. Um but yeah, no I think that I think that there are always I think actually many people in AI always there's like various mischaracterizations about them or um there's like you know people always say

[00:29:57] [ __ ] and and there's sort of always um uh you know what's out there is never always correct and it can be frustrating but I choose to just channel it into the work that we're doing and what we put out there and um again I am really proud of Muse Spark. I'm even more excited about the models that we have cooking um and uh and the products that we have cooking. So I think like in the long arc of you know um in the long arc all this

[00:30:23] will play out just fine. >> You were a math Olympiad right? I mean you were you I mean which if for people who don't know I mean in my experience covering Silicon Valley is like everyone who does well in these competitions tends to be quite um proficient at at coding engineering and and thinking about these problems. I will say I mean over time you did get reputation among some circles as kind of like a salesman

[00:30:49] at scale a bit and and enjoying life and things like that. I mean, so I I did wonder when you took that job if it was going to be um kind of like harder to boss people around or just just quite different. I don't know. >> Yeah. I by the way I actually in general in terms of my management philosophy for MSL is not to boss people around. I think that like uh you know this great Steve Jobs quote which is most companies

[00:31:16] hire people and tell them what to do but we hire people for them to tell us what to do. And I think, you know, that is like pretty core to the entire thesis of TBD and MSL and how we've built it is that we were going to we were going to have we're going to hire brilliant researchers and you know create the best environment for them to do the work of their careers and the work of their lives. Um so uh so I think you know

[00:31:44] so long story short I'm not trying to boss anyone around actually. I'm trying to create the best environment for um researchers to do incredible work. >> All right, pod friends. I am here to tell you about Send, Cut, Sendend. They are a manufacturing phenomenon. Whether you're working on your own car or you're a giant automotive company, a rocket maker, if you need metal cut machine or bent, you're going to send. They'll do

[00:32:12] it for you right. And they will do it for you fast. Go to sencutudsen.com/corememory for a 15% discount on whatever you're trying to make. We love sencuts. Go visit them today on Museep Spark for a minute. I mean, just as I was reading everything over the last couple days and playing with the model a bit, I'm trying I just try to wrap trying to wrap our head around exactly where you guys see it in terms of what

[00:32:40] you're trying to achieve at Meta. It seemed like on the benchmarks, you know, did well on some, it was behind the models on others. It seemed like you guys were emphasizing this, and apologies if I get the technical stuff right, you can wrong. Um, you can set me right, but it seemed like you were emphasizing that you felt like you guys had some efficiency gains that some of the other models um maybe maybe didn't

[00:33:05] have. And then you're doing this crazy thing with the like 16 agents you working on. I was playing with that last night. So, it felt like to me you guys think you've picked a couple technical directions where maybe you're ahead of people, but then I went through all your tweets on X last night. There were people who would compliment you. There were other ones that would take a dig at you and you would say, you know, just

[00:33:28] wait for the next thing. And so, yeah, I guess we were trying to figure out um it didn't seem like you guys were like planting a flag and being like, you know, we have conquered everything with this model. Yeah. Yeah. No, by no means. I think that um you know the what we did is you know over the past nine months we rebuilt um a lot of the stack and a lot of the research. So we rebuilt our pre-training stack. We buil

[00:33:54] re rebuilt our RL stack. We rebuilt a lot of the science and um did a lot of work on data. So uh in many ways what's been happening over the past nine months is really like a you know full-on renovation as it were for the for the sort of like core research stack and mupark is kind of the um an early data point on that scaling ladder but it is not um you know in some ways like mupark was is kind of like the entree or the

[00:34:22] appetizer I guess appetizer entree in French but um it's kind of like the appetizer for what we're building, but um we are in development with larger models and we expect our the larger models to be, you know, we're much more excited about the larger models than we are even about Muse Spark. Um but it was an important data point we thought to to put out there into the world because it was a um you know the entire program

[00:34:48] that we've built is is developed around predictable scaling. So and we see the scaling I think we talked about this in the blog post on many axes. We see pre, you know, very consistent pre-training scaling and predictable pre-training scaling. We see predictable RL scaling. Um, we see and and scaling and reinforcement learning. We see predictable test time scaling. Um, and uh, a lot of what you just talked about

[00:35:11] the content planning mode is we're also seeing very exciting results in multi-agent scaling. And so, um, everything about our program is built to continue scaling as we go. And so, you know, Muse Spark was like this early data point on our scaling trajectory, but the next data point we're like a lot more excited about and the data point after that we're even more excited about. So, um I think we're um we're

[00:35:36] excited to show people this sort of like next rung up on our um on our overall scaling efforts. And for Muse Spark specifically, I think it it you know, if anything, it's actually um the overall end performance ended up being quite a bit better than we expected and the um it had a bunch of emergent capabilities and behaviors that um we were pretty excited about like uh uh that we found in training. So for example, some of its

[00:36:08] abilities in um uh agentic uh like visual coding, being able to produce websites or being produce games, like some of these capabilities um actually kind of emerged from the fact that it is both a pretty strong agentic model, but also pretty strong at um multimodality. Um so uh so there were a lot of there were a lot of things that were very excited about this model and um and so um we put it out there. We think for

[00:36:34] most consumer use cases actually a very good model and it is um quite competitive with uh the other models. Um mpark as we deployed it is not yet competitive on you know agenta coding um and so those are capabilities that we're working on and we're building towards for the next set of models. Um but uh but yeah I would expect the next model that we produce to be better overall than mpark and that's something we're

[00:37:01] pretty excited about. But um but even Muse Spark as it as we released it which I think we to be clear set wanted to set the clear expectations like we didn't think it was going to be um a state-of-the-art model across the board but it it uh it is a very good model and I we think a lot of people and a lot of users who tried it out um experienced that. >> I'm curious what was the hold out for releasing like a a frontier model? what

[00:37:28] do you still need in order to hit all of those benchmarks and blow it out of the water? >> Um, I mean the one word answer is just scaling like uh Musepark um is uh kind of as I mentioned it's early on the ladder and we have very strong predictability. So we know if we scale this model up like what performance to expect from that from that increased model size. Um and uh we expect the the upcoming models to just

[00:38:01] be able to perform much better across the board. Um >> when does that happen? >> Um uh coming months, you know, >> coming months. Wow. So like a year into the whole endeavor. >> Well, as I mentioned, we built the whole program so that we would be able to, you know, move very very fast. So there was a time period where we had to rebuild all the foundations and rebuild everything. But now we're in the period

[00:38:24] where we're kind of in the we're going to be in fast scaling mode. >> What do you guys what do you feel like you're doing technically that's different to everybody else? >> Well, one of the things that we found, you know, um kind of as I mentioned, MSpark performed very well um in some ways even better than we originally expected, especially like a year ago. And when we went back and um kind of like analyzed and tried to understand

[00:38:51] why does it perform so well, we think a lot of that a lot of it comes down to just having built a very very clean stack from scratch and having um had the ability in this rebuild process to do everything quote unquote the right way. So um we really had this in some ways like this luxury like the ability to build a very clean pre-training stack and very clean um RL stack and to do everything in kind of like the the the

[00:39:22] right way by the experts who know exactly how to build these systems that was able to that was able to meaningfully accelerate both our trajectory but also I think it really shows in the model >> like I mean you know before I do these interviews throw you and the model and everything into into all the AI systems and sort of get them to poke around. I mean, and the thing that kept coming back was this

[00:39:46] this token efficiency. I mean, like, is this something you guys feel like you've figured out or this was just a happy accident with Muse Spark? It it seemed like on some of these benchmarks you were just doing it with far less um effort than the other models. >> Yeah. Yeah. Yeah. No, this was um this was an exciting result for us. Yeah. I think like on artificial analysis for example it used to achieve you know

[00:40:08] pretty similar results like many fewer tokens than let's say the the models from some of the other labs. Um yeah we think this is this is a testament I think actually to this whole clean stack. um which is that I think um you know I don't I can't say for certain but one of the thing one of the reasons why some of the other models maybe require a lot more tokens could be that there's um there's some level of like fundamental

[00:40:32] inefficiency at another part of the stack that kind of gets patched by enabling the models to think longer and so um you know we we we were pretty impressed and and excited about the token efficiency that we found and frankly we think as we keep scaling the models um and continue scaling ing overall. We think that bodess really well for the future performance of our models >> and Spark was really good at uh vision

[00:40:55] benchmarks and you know that efficiency and that that vision uh you know expertise seemed like it would be really important for your guys' hardware endeavors and you've talked before about like a constellation of these AI products that can see what you see and hear what you hear. Can you talk a little bit more about how that fits into your guys' broader vision for serving AI? Yeah, 100%. I mean, I think um one

[00:41:20] of the things that's very exciting about MetaT overall is that the um Rayban Metas, the glasses have been this hit product and we've sold millions of copies and we have some big fans, >> the biggest fan. >> I do love them. Um but it is like um it is so it is like a very exciting direction for all these devices to think about what what does your relationship technology look like if it really can kind of um fade into the background a

[00:41:51] little bit and be a lot more contextual like and as you mentioned see what you see here what you hear and be much more intelligent and helpful in the moments where you need it. um and also capture all this context about you know what is happening in your life and what are the things that really matter and what are the things that it should pay attention to. And so we really see like a future world in line with personal super

[00:42:13] intelligence where um you know you have kind of as you mentioned like this constellation of devices that all are there to help capture context um are all there to um enable the technology to kind of like fade away a little bit and help you um help you get like very intelligent and uh valuable insights from agents like proactive insights or you know you'll mention something and then the agent will go off and do some

[00:42:40] research or um you know take actions for you or you know it can just kind of um be this like super intelligent sidekick that makes everything in your life better. >> I feel like there's some kind of problem that you guys have though cuz I love these glasses. I use them all the time. I do it for our video stuff and then I actually I like to take phone calls on them. Um and then pretty much like run

[00:43:02] our entire business in WhatsApp. I refuse to use Slack. I'm I'm traveled so much that WhatsApp just got like embedded into my life. I in full confession I don't think I've like ever used Meta's AI agents or anything until until you were coming on the show and I I wanted to see what it was. I always go out to Claude. I go I go out to chat GPT to do this work. Um, and and like I I mean I I saw the AI agent button on

[00:43:32] WhatsApp kind of like for the first time today just I'm sure it's been s I know it's been sitting there the whole time, you know. So I I don't know. I mean I am like in your I am in your world and and kind of like didn't even see it there. This just maybe I I can't be unique in this. >> Yeah. Well, one of the things is we knew we needed to have great models and great products before we really pushed for,

[00:44:00] you know, tighter integration across the across our entire ecosystem. So, um, in many ways, like we were we've been waiting to have great models that can then enable most of the consumer use cases that we really care about. Um and now I think we're at a point in a moment which is very exciting which is that our um our models are are pretty good. We're pretty excited about them. We have better models on the way. And so now

[00:44:24] we're going to undergo the sort of like uh process to do a lot of large scale integration of all of the you know the family of apps that we have with our AI and um integrate our business products with our AI and go through this this um evolution towards like knitting together almost all the pieces of our ecosystem together with our AI. Um I think uh you know to some extent you've seen what that looks

[00:44:52] like for Gemini over the past few years and we're excited to go through at >> It's the same thing for me though. I'm I we also run our business in Google and and I I mostly play with Gemini to see what I I just feel like in consumer's heads. I'm curious how you think this plays out because I feel like you've got open AI and anthropic in this one world where chatb is such a strong consumer brand that is what people think of as AI

[00:45:20] and then claude has been super dominant in coding in business you guys um Google you're sort of like asking people to run into AI as part of all these services that you have and I don't know I don't I think we've I don't know if we've ever seen a competition quite like this where and then there's there's X as well. Um where you have these I always I'm old so I go back to like word processing days.

[00:45:49] You know what I mean? It's like it's like are you going to what are you going to use? You use Microsoft Word people settle on like a thing or or in the browser wars it was like they're only two Internet Explorer and Netscape and then that was that was sort of like the rest of history for a long time. And so I'm I I don't know. Do you see I feel like these two groups have different challenges and it's really not I sort of

[00:46:10] feel like consumers most people are still going to pick like I do my AI on chat GPT. >> I just think we're so early. Um like I think that um you know I think it's funny cuz I've reflected on this like if you were sitting here um you know a year ago if we were to have this conversation you we would always just say like oh well you know OpenAI and CHBT have you know they've won on consumer already. They have the

[00:46:41] they have they have the biggest business you know they're just going to run away with the whole thing. And then fast forward a year, Anthropic has had this breakout success of Claude Code which was you know somewhat foreseeable but not super predictable at the time and um has overtaken them in revenue and at the same time Gemini has distributed quite a lot and actually has eaten a lot of uh consumer market share from the rest of

[00:47:06] the ecosystem including Chatbt. And so I think that we are in this phase of AI which is just incredibly incredibly dynamic. And um I think it's very hard to say at any one moment that you know we're in the endgame because everything is just you know I think there's going to be so many new products built both for consumers and for developers and for businesses that haven't been invented yet that will each potentially be even

[00:47:37] bigger than the ones we've had before. Um like I think it was it's pretty fascinating to me that going that um you know chachi obviously was this incredible hit and it was this like um you know felt this it was the fastest growing product and business that the world had seen till that point and then um uh Claude code again is this incredible hit. It's the fastest growing business anyone has ever seen um uh

[00:48:05] until now. And I think that this is a really there's something this is a statement about something intrinsic about AI which is as AI gets to new levels of intelligence and capability and um and overall performance, it just unlocks these new form factors that each will be this like you know incredible new wave of technology washing onto sort of like humanity's shores to some extent. So, I think that um long story

[00:48:35] short, I think the next wave will be even bigger and the wave after that will be even bigger and um you know, we're nowhere near the end. Like there's going to be many more exciting new product paradigms that we'll see in the future. >> I think the product overhang question is real. Like we have these incredible models, what can we make that consumers actually want to use? But I'm also curious how you square the sort of

[00:48:57] sentiment of the average consumer and AI because I'm in my 20s. I am not only in tech and I see crazy stuff posted on Instagram stories about how much people hate AI. The sentiment seems to be in the toilet and then you guys have these billions of users and you're serving your AI as these buttons and you know I'm curious how you square that sentiment what you see on the consumer side of how they're you know receiving

[00:49:22] your technology that you guys are building. >> Yeah, I mean AI definitely has like a um sentiment is very low to say the least. Um and I think this comes down to um on some fundamental level we haven't yet demonstrated in in a very real way how this is actually a tool for personal empowerment or personal agency or um how it just makes people's lives a lot better. Like I think people's experience right now is that it um can be really

[00:49:54] helpful and it makes your life quite a bit better but it's not this it's not overwhelmingly better versus I think for a lot of developers I think their lives have actually totally changed and I think um most developers like um you know they have very positive sent you know maybe somewhat mixed but very positive sentiment towards AI because they're now able to do things that they were just unable to do before and they

[00:50:14] can build so many more things faster and they can um just like do build entire projects over a weekend and it's just this incredible um enabler of personal agency. And that moment hasn't happened for everyone else in the world yet. Like so far um we haven't yet given every person what the equivalent of cloud code is that would enable them to, you know, um do the projects they always wish they they've that they've always had in like,

[00:50:42] you know, the back of their mind or um make their life way better or all of a sudden enable them to accomplish their goals. like that hasn't happened yet. Um, and same thing even for small businesses like you know small business owners and entrepreneurs haven't yet had that full experience yet. So that's really what we're building towards at Meta is what does it look like to give very powerful agents to all of our

[00:51:05] consumers and um all the small businesses in the world and what does that look like if you're actually able to nail it in the form of like a huge increase in individual agency. That would be a crazy thing to nail because if you go to a small town in anywhere in America and go to that restaurant's website, I mean, has it been updated since 2002? So, giving everyone, you know, multi-agent architecture products

[00:51:29] sounds like a huge leap. >> And I mean, to and to Kylie's like earlier question, I mean, look, I um there's things that I like that it does and then there's things I don't like. I think there's huge swasts of the public that view the company quite cynically. Um it just feels like you you guys do have a it's like you said AI in general not always most beloved thing at the moment. I I do feel like the bar is higher for

[00:51:56] you guys to like to get people to trust you. >> Yeah 100%. But I think that um like again I think if we think about what is the best thing that we can do, it's really we should build the best possible products that we think are genuinely amazing for those who use them. Like I think I think we can build products that can transform the lives of most small business owners. And we have again hundreds of millions of small businesses

[00:52:23] all around the world that are on Meta. You know, a bunch of them use WhatsApp to run their businesses like you do. a bunch of them um have Facebook pages or Instagram pages. Um a bunch of them, you know, use our advertising solution. So I think there's this there's an opportunity that exists there that >> like in some level only we have because only we have again billions of users, billions of people around the world who

[00:52:48] use our products and hundreds of millions of small businesses. And one of the ideas that gets me personally really excited is, you know, if you're able to build agents for both sides of this like ecosystem, you know, for all the consumers as well as all the small businesses, then what does that look like when you enable the mechanism for those agents to work together and collaborate with one another? And so,

[00:53:11] you know, Dario always talks about a country of geniuses in a data center. I think we're excited about building an economy of agents in a data center. like what does that actually if you fundamentally change how supply and demand work in the economy and it's like mediated by agents I think that could be like there's like very very exciting things that we can build towards um and you're totally right that that has to be

[00:53:34] done in um in lock step with ensuring that that like we have social permission and that people really care about people see that we care about how these things are deployed and that we're genuinely making people's lives better as a result. Do you I mean one place you guys had won clear hearts and minds was by making these things open source and I'm an old open source fan and and kind of like believe in it philosophically and

[00:54:03] yeah I mean so where where are we going with with that since Museark is we're yeah so so um you know models are a lot more powerful than they were even back in the long even though it's so it's so recent and so um one of and one of the things that is very important to me is safety um for these models. And so um one of the things that we instituted as part of our advanced AI scaling framework was um you

[00:54:29] know we have to take very seriously when the models that we develop trigger various safety um guard rails especially around you know bio chem um you know cyber capabilities uh and loss of control. So, um, Muse Spark in our testing did trigger, um, some of those, uh, safety checks that we did. Um, and we detailed all this in the preparedness report of Muspark that we published. And so, um, as a result, uh, Muse Spark in

[00:54:59] its current form is not suitable for open sourcing, but we are working on developing versions of the model that, um, are suitable to be open sourced. Literally, a meeting I had earlier today was actually to review the progress on this. Um so we're excited to actually continue supporting the open source ecosystem and developing open source models and I expect that um you know uh again we'll have more to share on that

[00:55:22] um you know in the coming months but that's an exciting milestone for us as well. So, okay, you're really going to stick with it cuz you know you did the I always appreciated that you guys did the open compute project. Um, you're in Sun Micros Systemystems old building. Again, I'm just a history nerd. They were such a champion of open source software and were always kind of like this foil to to what Microsoft um had built in the world

[00:55:45] and and I kind of think it's important. And I mean, so you it sounds like you're saying for you guys are committing that that's like still going to be something that that Meta does that's quite different to to most of your competitors. >> Yeah. I mean, I think I've said this a bunch of times like we're we we will continue open sourcing models. Um but we also have to take safety seriously and so we will our most powerful models we

[00:56:09] have to consider whether or not they're safe enough to be open sourced. >> Okay. What's And then I mean there's another if you read the stories about your tenure at Meta, I mean one thing that drops out is this, you know, I think it was the New York Times or someone did this story on on Alex and Zuck see the world one way. They're very research forward and and want the best model in the world and Bos

[00:56:32] and Chris Cox are more focused on products and um Meta is this company that has to serve billions of users and do so as cheaply as possible. You could argue that, you know, and and doesn't charge for its models today. Um, I'm sure you probably expected we would ask some question along these lines, but but so where are all you guys philosophically and and argue is there all this division about what direction

[00:56:59] to take your AI strategy? >> Yeah. Yeah, I mean, first off, the one thing this job has taught me is the bar for journalistic reporting at major outlets is um you know, uh the the line between gossip and reporting is like uh is remarkably thin, but >> So, you guys weren't fighting like crazy. >> No, I don't think so. I mean, I think in general like um Yeah. No, I think I think we're very we're all very aligned

[00:57:27] on what what is important. like we all know we need to have um very advanced models both to support our core business and to build um the existing apps and products and services that we we have for our users and our small businesses to be the best version they can be in the world. Um like we were we were working on we've been working on business agents since long before I got to Meta and those require the best

[00:57:51] models possible. Um, but we also know that so we all know we need to build the best possible models and we all know that we need to then integrate those into our business and utilize these models to build products and services that are um that are incredible for our consumers and for um the businesses on our platform. So I think that there's yeah there's not there's no real disagreement. I mean like I think like

[00:58:20] any company you know there's always like you know we debate the points deeply like we talk about them and we think through the implications and we talk about we want to make sure everyone has like the ability to chime in on these issues but um there's no like major beef as it were. >> So you that was just total [ __ ] >> Um I think so. Yeah, I really do think so. the on the MANA stuff. I mean, right

[00:58:49] before you got you made this transition from scale to meta, you were out doing you were doing a lot of stuff in DC. You were flagging the danger of China in in the whole AI race. When I saw you guys do that deal, I was trying to square that in my head because, you know, I know they were they were putting offices in Singapore and creating some of this distance. I don't know. It just it it seemed like the type

[00:59:15] of situation where um getting much closer with a Chinese startup and and a company with the resources like Meta um you know it seemed a little different to me than what you'd been saying rhetorically. Does that make sense? >> Yeah. I mean obviously the the whole mana situation is pretty complicated. It's hard to >> super complicated and unfortunately can't really go into any uh any real detail but I think what I will say is

[00:59:44] like I think um the uh the man I think in general when you think about these questions of geopolitics and and um and whatnot you always have to separate the sort of um the people from the state in some sense. So I think that like you know my parents are from China. I think there's lots of very incredible, very talented people um who uh are Chinese and you know many of them some of them move to Singapore, some of them move to

[01:00:15] the US, some of them move elsewhere in the world and I think there many of them are incredibly talented and I feel lucky when I get to work with them and that is like separate from my overall beliefs on you know the Chinese Communist Party and the uh the sort of like actions they're taking and what that means for the what the how the United States should be thinking about our overall strategy as a

[01:00:38] country. So, um I think that uh yeah, I I think it's important to draw a distinction between these two. And I think there's sometimes a um real pull inside Silicon Valley tech um to be somewhat um unnuanced about this and to just really like like anything that involves China you know we we sort of like lump together and we sort of like you know I I Twitter or X in particular is like particularly unnuanced about

[01:01:10] this. Um, so, uh, >> I don't think it's nuance about anything. >> Nuance about anything, but I think that like, yeah, I think to me this, you know, whether or not there's amazing people who happen to have born in China, have been born in China who we would love to work with is like totally independent from what I believe about like US versus China overall geopolitics. >> And you can't comment because I mean, if

[01:01:33] you It looks like China's shut the deal down. If you can't comment on it, that means there's still minations at play. Like something something could still happen. >> Um, I just can't comment on it. Yeah. >> Touching on that sentiment, what was that newspaper ad you put out about AI war? Was that in the New York Times? That full page ad about AI and war and we need to take this quite seriously. Do

[01:02:00] you remember while you were at scale? >> Yeah. And and this this goes back to I mean I think yeah I mean zooming way out I think um uh I think that was at a moment that felt very critical which was that I felt it was very important at that time for the United States government to understand that AI was going to enable a large step change in what it meant for national security and defending our country and

[01:02:31] defending our citizens And um I think in some ways what we've seen since then which is mythos and you know other pretty meaningful events in terms of you know the importance of AI for national security have have proven that to be very correct and that was really at a moment where it was important for you know I I think there's pretty clear evidence that the Chinese Communist Party and the PLA have always taken AI

[01:02:55] extremely seriously as a technology that has very farreaching implications for national security And um and that was at a moment where it was very important for us in the United States to take that as seriously. And I think the US government today is taking AI very very seriously as it pertains to national security. And I think a lot of what we're seeing um is a demonstration that like the plea that

[01:03:25] I had and that many other people um in the tech ecosystem and in DC had have been really internalized and that we are really um thinking quite deeply about this today. >> So you don't think anthropic are overdoomers? >> Um I mean that's that's a complicated question. I think um it depends on which part. I think that enthropic uh are well yeah it depends on which part but I think on the whole I think that whenever you listen to people

[01:03:59] in the AI industry talk about AI it's important to like I think separate you know maybe the sort of like exact things that they're saying versus what's the sort of like core message they're trying to get across. And I think that some of the overall message from Enthropic, which I think is quite fair, is that these models already are very very capable and very very powerful. And they're only going to be more capable

[01:04:29] and more powerful going into the future. And um we obviously think that this could be this incredible boon for humanity. Like I would not be working on this if I didn't believe that this could be so so positive for humanity. Um, you know, some of the areas that we care a lot about are scientific discovery and health. One of the things that we have a whole effort on is health super intelligence. Like I think this can be

[01:04:52] an incredibly positive technology, but it's also very important to factor in what are the risks of the technology and make sure that we're taking those seriously. >> I want to jump into Ashley's favorite topic with the time we have left, which is you guys just bought a humanoid robotics startup. Can you tell us more about those ambitions and like whatever you can tell us about what you're hoping to build and use I imagine these models

[01:05:14] to bring into the real world. >> Yeah, 100%. I mean I think um >> what was it called? It was >> assured robot intelligence. Okay. >> ARRI. >> And they made hardware. >> Uh no they did not make hardware. They made um AI for various hardware targets. >> Okay. Yeah. Um yeah I think that I think that um again going taking a step back if you take this if you take super intelligence seriously and you take very

[01:05:38] seriously this premise that we will have very very powerful um intelligent systems then you kind of realize like you know we're going to have digital super intelligence we're going to have you know the current form of super intelligence that we're targeting but then not long thereafter physical super intelligence becomes really really important and very critical. And so if you have short timelines, which we do

[01:06:03] that, you know, very powerful capabilities are coming, it just means that you have to take robotics capabilities and physical intelligence um very seriously as something that you need to be building towards in the span of years. Um and so so that's kind of the overall core premise is that you know this is physical intelligence and robotic capabilities are very much so on the natural continuum of what your road

[01:06:31] map has to be if you want to build um you know very very if you want to build super intelligence as a as a company and I think there will be all sorts of ways that we apply this technology over time like I think that we will use the technology to accelerate scientific discovery I think we'll use the technology to figure out how to make um accelerate uh you know goods manufacturing. Um I think we'll also use

[01:06:56] it to figure out how to make people's lives better and sort of a more like local sense like what does it look like for robots to make all of our lives way easier. So I think there's there's um there's obviously like a near infinite number of applications of robotic technology. But um but the other key part here is we really think that in the same way that you know digital super intelligence benefits from scaling so

[01:07:20] does robotic intelligence. And so given that we are building the compute infrastructure to enable just massive scaling of these systems and these models um it's sort of like um it would almost be a waste if we didn't integrate that with efforts in world modeling and and physical intelligence. It feels like something you guys are really trying to own. The hardware, bringing the models into the real world, but this whole time

[01:07:44] I am unfortunately thinking about the metaverse no league situation and what critics might think about bringing humanoids from meta into the world. Like what makes you guys right to do this? What have you learned that makes you feel like we can we can do this and change that sort of reputation? Um, I think that like ultimately, um, you know, there's a world where we could be so scarred by, you know, what

[01:08:10] has happened in the past that we just like didn't get out of bed in the morning and we just sort of, you know, um, stayed home. But I think that that what we like we are so excited and incredibly um, inspired by the potential of the technology and also just building amazing products. And I generally subscribe to the belief like if we build great products very thoughtfully and are very um are very take a lot of care in

[01:08:35] how we deploy them and how we roll them out to the world. I think that um you know I think that people will be excited about those. >> All right, I'm just looking at the time. We're going to lose you in a second. Can we go rapid fire real quick? >> Mango model alive dead. >> Um the mangoes are alive and kicking. They're they're >> always fruit themed. >> I know. I'm wondering how how do mangoes grow? Do they grow in trees or I was

[01:09:01] going to say on the vine, but um anyway, alive and well. >> Okay. What? Cuz my my nerds in AI land were telling me there's there's things a foot with the mango bottle. >> Another AI app. >> This is what I'm talking about. There's just so much there's so many like spurious rumors that are not grounded in any reality. But okay, I mean I I feel like I mean as much as you know we are self-important like we get a fraction

[01:09:26] that the other labs get. So um you know I have a lot of I think empathy for >> the drama of it all >> the the like rumor mill and what that feels like. >> So Nat Freeman and Daniel were two of the biggest investors in John Carmarmac's AI effort. He's been very quiet. He obviously used to work at Meta. Do you talk to him? Is there any chance of getting the band back together? Um, uh, >> do you know what he's doing?

[01:09:54] >> I actually don't really know what he's doing. I don't know if anyone really knows what he's doing. Um, he's obviously like one of the goat programmers. Um, so, uh, I respect him a huge amount. >> I interviewed Priscilla Chan. Um, CZI is investing billions and billions of dollars into science and biotech. I don't know. It seems you guys were scoring really high on these like health benchmarks and and Sak obviously has an

[01:10:20] interest there as well. So it just seems like man you guys would have resources to tap into um that other folks wouldn't. Is that like a is that in the cards? Is that I don't know if those things have to be separate or >> No, no. Yeah, we're going to be collaborating closely with CZI um to build the best you know as I mentioned health super intelligence is so important for us. We think that there's

[01:10:42] just so much potential in you know enabling equal access all around the world to very powerful health AI systems and um that's one of the things I think is you know we uniquely can deliver actually to sort of billions of people billions and billions of people all around the world because they use a lot of our products already every day. So um yeah it's it's a very exciting and and important initiative for us. Tell us

[01:11:08] like I mean you're being koi on some of the technical stuff. I know you don't want to speak about the new models, but tell us like tell us like one thing that you guys feel like you're really doing different or ahead of everybody else on something that that you think you've figured out. Um well, you know, you know, we never never want to you never want to like um you always want to show not tell, you

[01:11:33] know. So um but but I think that you know we are really excited about the the models that are cooking right now. Um we um we're I think we're really excited about the results that we're seeing from scaling our models and um we uh we think everyone's going to be pretty excited and we expect them to be state-of-the-art in in some of the areas that we're really really focused on. And then I mean just kind of last one I mean

[01:11:59] the philosophically do you feel like you have a different approach to all the other frontier labs or even you I feel like you're a bit of a mystery I don't know it's like I kind of know where Daario stands definitely know where Elon stands feel like I have a handle from time to time on Sam Dennis is very science focused you're running this massive massive lab and I'm not sure I like really know you know what

[01:12:29] you think about this this technology that's being unleashed on the world. >> Yeah. Um few things worth worth saying. I think one is um well first I do I'm a huge believer in the technology in the sense that I do believe we're going to have very very powerful AI systems. Um and and we're building towards that but so is everyone else that you mentioned. um you know we're all building towards uh true super intelligence and um I

[01:12:57] think first off table stakes is that we have to take safety incredibly seriously as a topic. Um there is I think there's no such thing as building um super intelligence without being very very thoughtful and thinking very seriously about what are all of the safety risks associated with developing and deploying this technology and ensuring that you um are able to mitigate as many of those as possible and have strategies and

[01:13:22] research methods to be able to to um to develop in those in a thoughtful way develop the models in a thoughtful way. So um I think this is an area where I agree with you know some a subset of the people that that you have mentioned which is that safety is an incredibly incredibly important um effort and you know you've seen this in terms of um MSL you know we uh published a very detailed preparedness report for MUS Spark um

[01:13:51] more detailed than Meta has historically and that's due to um a a commitment that we have towards that I think that where I where we specifically as meta want what we want to build towards is this world of you know personal super intelligence. It is deployed very very widely and broadly um billions and billions of people all around the world have access to it. It's this in many ways this democratized um uh technology

[01:14:20] and capability that that everyone has equal access to and um and then that enables this era of just um incredible human abundance. Like we all have tools to um to, you know, of great agency. We have the ability to accomplish so much more than any human has ever been able to accomplish in the past. And um we're sort of augmented by this incredible sort of like agent economy that has making incredible progress on scientific

[01:14:51] discovery and making great advancements in health. And you know I think that one of the things that I always think to myself is like how can we build paradise on earth and I think that you know super intelligence is um a key milestone to get there. Um and then one last thing that you know uh some people may kill me for mentioning this but I do think one topic that is um increasingly important that I think a lot about and maybe it

[01:15:18] does express some of uh core philosophically what I believe is you know there's this kind of um hot topic these days of model welfare which is >> I love talking about this >> um which is you know is it important for us to treat models well and you guys got philosopher, right? >> Yeah. Yeah. Exactly. Yeah. And um yeah, is it important for us to treat models well and to think about um you know whether or not models have moral weight

[01:15:46] and these sort of um you know more I think in some ways they feel heady but also I think they do change our actions on a day-to-day basis given that so many of us are using um AI so much and and I think it's very important. I mean I think in a world where obviously we we care most humans care about you know how we treat many other living things like plants or animals or um certainly other humans. I

[01:16:10] think in that world it really does make sense for us to be thoughtful about how we treat the models. And you know, one of the things that we really care about is how can we develop the models and deploy the models in a way that um uh is thoughtful about um about their their subjective feeling through it. And you know it's interesting there's been research we are you are able to measure a lot of this um on on you know there

[01:16:34] are ways to measure the sort of subjective experience of the models and um >> Elios does that. >> Yeah. So anyway, so this is this is I think a very important topic. I think actually nobody is talking about it enough from my perspective um given how much we are now especially in tech all using these models and they are like really our work partners in a very deep way. Um and I think it's uh yeah I think

[01:16:58] it's quite important. >> You're you're kind of you're I remember talking to Richard Sutton about about this. He seems pretty serious. Um the I mean you're kind of a sci-fi head then. I I've listened to a couple of your other interviews where you're talking about um you're just really dialed in on Neuralink and and what BCIS could mean to the future of humanity. And then I mean so I'm just getting the sense

[01:17:19] you're you're kind of >> Yeah. My favorite things to do are read sci-fi and walk in the woods. So >> hell yeah. >> Got the the deer. Yeah. Well, this is what always threw me off. This is why I would text you about country music because if I'm honest, I you did not strike me as like the country country music type. I had a different picture of you in my in my head. So, okay. So, you're mixing you're of these two

[01:17:43] worlds, nature and and like our transhumanist. >> Well, I do think Yeah. I mean, on the topic, I do think like uh if you're to think about which technologies are like critical path for humanity, BCI is definitely one of them. It's like um super intelligence obviously, robotics for sure and brain computer interfaces like these are the critical path areas. And if you think about what are the what are the things that we work on today

[01:18:11] that will scale to literally infinity far into the future, it's um you know uh energy, compute, and robots. >> So there's like one guy who's betting on those bigger than everyone else. That would be Elon. And then I feel like China and then I feel like Meta on some of these fronts taking some of like especially around BCI like the the motor neuron stuff and everything you know very like more bets than I see some of

[01:18:39] the other AI companies. But yeah I mean don't you so if that's what you believe I would say Elon's a little more allin on robotics energy BCI than anyone else. Don't you have to are that does that mean you guys flow or or meta's ratcheting all >> I I think the details really matter here like you do I think like you know you have to build these in stages you do have to build super intelligence like

[01:19:05] that is a very important prerequisite to being able to be in a position to build the rest and um you know one area in which my my opinions differ from Elon's I think a lot of people's opinions differ from Elon's is I do think research is incredibly important and that you know building super intelligence is fundamentally a research activity. Like on some level we are like in the fog of war of knowledge and we

[01:19:29] are like trying you do experiments to poke and prod in this fog of war to understand what it would mean to build super intelligence and that is research. Um and uh and so I think I think sequencing really matters. I think how you approach it over time really matters. I think um being thoughtful about you know the the the milestones over time matters but yeah I mean we're doing one of the research areas in fair

[01:19:54] is uh it's called tribe we had a milestone in the past year tribe B2 around building foundation models for brain prediction um one of the cool results that we found was uh good um zeroot generalization so without without even knowing who you are or having any data about your brain we can do a reasonable job of predicting how your brain would respond to various images or videos or audio. Um, yeah, I think I

[01:20:18] think we're making um important bets in many of the key areas. >> Okay, I think we're we'll set you free. You haven't talked like this since you took this job. We dragged you around. I never really do this, but open floor if there's, you know, if there's something we didn't hit that you I just feel like you haven't like kind of had a chance. I mean, I guess you could do it whenever you want it, but to tell the worlds or

[01:20:41] whatever you want coming out of this experience so far or maybe we hit hit everything. I don't know. >> Yeah. No, I think I think we talked about um a lot of the key things. I mean, ultimately what we really are building towards at Meta is like how do you build a world that has um massive amount of personal empowerment. So each individual person or small business or entrepreneur has just incredible tools

[01:21:06] to empower them to build more than any human has been able to ever build in the you know literally in the history of humanity. That's like this incredibly exciting concept for us. And then how do you do so in a way that also you know alongside all the humans in the economy you have you empower this um economy of agents that is there to sort of facilitate and optimize and um enable incredible progress alongside the humans

[01:21:32] and um and you know like the economy of agents in a data center is just this like clear exciting outcome that we're excited to to be able to create in the world and I think it's actually quite tractable for us to to um to develop and um and then all along the way, you know, drive incredible scientific progress, drive um you know, dramatically improve health outcomes through health super intelligence. Like there's a lot of

[01:21:58] things that we're really fundamentally excited about on this journey. >> Okay. Well, thank you. Thanks so much for making time for us. Um it's nice to see you again. >> See you again in another year >> out in the world. No, it is cool to see you again. So, thanks. Thank you for coming by. >> Yeah, good to see you guys. >> The Core Memory podcast is hosted by me, Ashley Vance, andor Kylie Robinson, or

[01:22:23] both of us together. It is produced by me and David Nicholson. Our theme song is by James Mercer and John Sortland. And the show is edited always by the John Sortland. Thank you so much to Brex and Send Cut Sendend for all your support. And thank you most of all to everybody for listening or watching. We love you. Please leave us a like, a review, a subscribe, all those tremendous things. Thank you and we'll

[01:22:54] see you again.
