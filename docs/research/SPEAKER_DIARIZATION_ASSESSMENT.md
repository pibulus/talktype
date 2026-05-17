# Speaker Diarization Assessment for TalkType

Status: research note, not shipped behavior.

## 🎯 What is Speaker Diarization?

Speaker diarization answers "who spoke when" - it segments audio by different speakers and assigns labels like "Speaker 1", "Speaker 2", etc.

## 📊 Complexity Assessment

### Required Components:

1. **Speaker Embeddings Model** (~10-50MB)
   - Extracts voice fingerprints
   - Options:
     - Pyannote (Python-based, server-side)
     - WeSpeaker (ONNX models available)
     - SpeechBrain (has ONNX exports)

2. **Clustering Algorithm**
   - Groups similar voice embeddings
   - Options:
     - Spectral clustering
     - Agglomerative clustering
     - Online clustering for real-time

3. **Voice Activity Detection** ✅ (Already have this!)
   - Silero VAD already implemented

### 🚧 Implementation Challenges:

#### **High Complexity:**

1. **No Browser-Ready Solutions**
   - Most diarization models are Python-based (pyannote, speechbrain)
   - Few ONNX models available for browsers
   - Would need to port or find alternatives

2. **Computational Requirements**
   - Embedding extraction is CPU-intensive
   - Clustering adds significant overhead
   - Real-time diarization very challenging

3. **Model Size**
   - Speaker embedding models: 10-50MB additional
   - Total with Whisper: 30-200MB models

4. **Accuracy Issues in Browser**
   - Need high-quality embeddings (hard in browser)
   - Overlapping speech is very difficult
   - Background noise affects clustering

### ✅ What We Could Do (Realistic):

#### **Option 1: Simple Speaker Change Detection** (2-3 days)

```javascript
// Detect when speaker changes, not WHO is speaking
class SimpleSpeakerChange {
	detectChanges(audio) {
		// Use acoustic features (pitch, energy, spectral)
		// Mark transitions between speakers
		return [
			{ time: 0, label: 'Speaker A' },
			{ time: 15.2, label: 'Speaker B' },
			{ time: 28.5, label: 'Speaker A' }
		];
	}
}
```

#### **Option 2: Basic 2-Speaker Diarization** (1 week)

- Assume max 2 speakers (interview/conversation)
- Use simple acoustic features
- Binary classification approach
- ~70% accuracy expected

#### **Option 3: Server-Side Processing** (Best quality)

- Send audio to server with pyannote
- Get back speaker segments
- 90%+ accuracy
- But requires backend infrastructure

### 🔬 Technical Implementation Path:

```javascript
// Potential implementation structure
class SpeakerDiarization {
	constructor() {
		this.embeddingModel = null; // Would need ONNX model
		this.clusterer = new SpectralClustering();
	}

	async process(audio) {
		// 1. VAD to get speech segments ✅ (have this)
		const vad = await sileroVAD.detectVoiceActivity(audio);

		// 2. Extract embeddings for each segment
		const embeddings = await this.extractEmbeddings(vad.segments);

		// 3. Cluster embeddings
		const speakers = this.clusterer.fit(embeddings);

		// 4. Assign speaker labels
		return this.assignSpeakers(vad.segments, speakers);
	}
}
```

### 📈 Effort vs Value Analysis:

| Approach                 | Effort   | Quality | Value   | Recommendation   |
| ------------------------ | -------- | ------- | ------- | ---------------- |
| No diarization           | 0        | N/A     | Current | ✅ Keep for now  |
| Speaker change detection | 2-3 days | 60%     | Medium  | 🤔 Maybe         |
| Basic 2-speaker          | 1 week   | 70%     | Medium  | ❌ Too much work |
| Full diarization         | 2+ weeks | 80%     | High    | ❌ Too complex   |
| Server-side              | 3-4 days | 95%     | High    | ❌ Needs backend |

## 🎯 Recommendation:

### Short Term (Now):

**Skip speaker diarization** - The complexity doesn't justify the value for TalkType's current use case. VAD alone gives us 80% of the benefit.

### Medium Term (If needed):

**Simple speaker change detection** - Could add basic "new speaker" markers without identifying WHO. This would help with:

- Meeting transcriptions
- Interview formatting
- Conversation structure

### Long Term (If TalkType scales):

**Server-side diarization** - If we need professional-quality speaker identification:

- Use pyannote on backend
- Cache results
- Offer as premium feature

## 💡 Alternative: Use Formatting Cues

Instead of true diarization, we could:

1. Let users manually mark speaker changes
2. Use paragraph breaks as speaker hints
3. Add a "conversation mode" with turn-taking UI
4. Simple voice pitch detection for male/female distinction

## Summary:

**Complexity: HIGH** 🔴

- No good browser-ready models
- Significant engineering effort
- Performance overhead
- Accuracy limitations

**Current Priority: LOW**

- VAD gives immediate value ✅
- Diarization is "nice to have"
- Better to focus on core transcription quality

**Decision: POSTPONE**
Focus on making transcription blazing fast with VAD. Revisit diarization only if users specifically request it.
