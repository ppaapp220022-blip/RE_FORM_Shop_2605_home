package com.re_form_shop_2605.service.AI;

import com.re_form_shop_2605.dto.AI.RiskAnalysisResultDTO;
import com.re_form_shop_2605.entity.Enum.ModerationCategory;
import com.re_form_shop_2605.entity.Enum.RiskLevel;
import com.re_form_shop_2605.entity.Enum.TargetType;
import com.re_form_shop_2605.repository.AI.RiskAnalysisResultRepository;
import com.re_form_shop_2605.entity.AI.RiskAnalysisResult;
import lombok.RequiredArgsConstructor;
import lombok.extern.log4j.Log4j2;
import org.springframework.ai.chat.client.ChatClient;
import org.springframework.ai.moderation.*;
import org.springframework.stereotype.Service;
import com.fasterxml.jackson.core.type.TypeReference;
import com.fasterxml.jackson.databind.ObjectMapper;

import java.util.ArrayList;
import java.util.LinkedHashMap;
import java.util.List;
import java.util.Map;
import java.util.Optional;
import java.util.stream.Collectors;

/**
 * ─────────────────────────────────────────────────────
 * 작성자: 진혜림
 * 작성일: 2026-05-13
 * 설명: 위험 탐지 AI 구현 Service
 * ─────────────────────────────────────────────────────
 */
@Service
@Log4j2
@RequiredArgsConstructor
public class ModerationService {

    private final ModerationModel moderationModel;
    private final ModerationKeyword moderationKeyword;
    private final ChatClient.Builder chatClientBuilder; // 개선 제안용 ChatGPT
    private final RiskAnalysisResultRepository riskAnalysisResultRepository;

    /**
     * 채팅 메세지 유해성 검사 후 결과를 DB에 저장하고 RiskAnalysisResultDTO 반환.
     *
     * @param content : 검사할 메시지 내용
     * @param targetType: POST / CHAT 항목 분류
     * @param targetId : 검사 대상자
     * @return RiskAnalysisResultDTO
     * - riskLevel == null -> 정상
     * - riskLevel != null -> 유해 (reason, suggestion 포함)
     */
    public RiskAnalysisResultDTO checkAndSave(String content, TargetType targetType, Long targetId) {
        try {
            log.info("[Moderation] start targetType={}, targetId={}, contentPreview=\"{}\"",
                    targetType, targetId, preview(content));

            ModerationKeyword.LocalModerationHit localHit = moderationKeyword.detect(content);
            if (localHit != null) {
                log.info("[Moderation][LocalRule] matched targetType={}, targetId={}, riskLevel={}, reason=\"{}\", normalized=\"{}\"",
                        targetType, targetId, localHit.riskLevel(), localHit.reason(), localHit.normalizedContent());
                return persistModerationResult(targetType, targetId, localHit.riskLevel(), localHit.reason(), content);
            }

            ModerationDecision decision = evaluate(content, targetType, targetId);

            if (!decision.flagged()) {
                clearExistingModerationResult(targetType, targetId);
                return RiskAnalysisResultDTO.safe();
            }
            return persistModerationResult(targetType, targetId, decision.riskLevel(), decision.reason(), content);

        } catch (Exception e) {
            // fallback API 장애 시 -> 정상 처리
            log.error("[Moderation] API 호출 실패 -> fallback: {}", e.getMessage());
            return RiskAnalysisResultDTO.safe();
        }
    }

    public RiskAnalysisResultDTO checkDraft(String content, TargetType targetType) {
        try {
            log.info("[Draft Moderation] start targetType={}, contentPreview=\"{}\"",
                    targetType, preview(content));

            ModerationKeyword.LocalModerationHit localHit = moderationKeyword.detect(content);
            if (localHit != null) {
                log.info("[Draft Moderation][LocalRule] matched targetType={}, riskLevel={}, reason=\"{}\", normalized=\"{}\"",
                        targetType, localHit.riskLevel(), localHit.reason(), localHit.normalizedContent());
                return buildTransientModerationResult(targetType, localHit.riskLevel(), localHit.reason(), content);
            }

            ModerationDecision decision = evaluate(content, targetType, null);

            if (!decision.flagged()) {
                return RiskAnalysisResultDTO.safe();
            }

            return buildTransientModerationResult(targetType, decision.riskLevel(), decision.reason(), content);
        } catch (Exception e) {
            log.error("[Draft Moderation] API 호출 실패 -> fallback: {}", e.getMessage());
            return RiskAnalysisResultDTO.safe();
        }
    }

    private ModerationDecision evaluate(String content, TargetType targetType, Long targetId) {
        // Step 1. Moderation API 호출
        ModerationPrompt prompt = new ModerationPrompt(content); // "이 텍스트에 문제가 있어?"라고 검사할 내용을 담은 질문지
        ModerationResponse response = moderationModel.call(prompt); // 응답
        Moderation moderation = response.getResult().getOutput(); // 응답에서 실제 모더레이션 결과 객체를 꺼냄.

        boolean flagged = moderation.getResults().getFirst().isFlagged(); // 유해 콘텐츠로 판정되었는지 여부 (false: 정상 콘텐츠)
        log.info("[Moderation] flagged={}, targetType={}, targetId={}", flagged, targetType, targetId);

        if (!flagged) {
            return new ModerationDecision(false, null, null);
        }

        // Step 3. 위반 카테고리 분석
        Categories categories = moderation.getResults().getFirst().getCategories();
        ObjectMapper objectMapper = new ObjectMapper();
        Map<String, Object> map = objectMapper.convertValue(categories, new TypeReference<>() {});
        log.info("[Moderation] rawCategories targetType={}, targetId={} -> {}",
                targetType, targetId, toBooleanCategoryMap(map));

        List<ModerationCategory> matched = new ArrayList<>();
        map.forEach((key, value) -> {
            if (Boolean.TRUE.equals(value)) {
                ModerationCategory.fromCode(key).ifPresent(category -> {
                    matched.add(category);
                    log.info("[Moderation] 위반 카테고리={}", key);
                });
            }
        });
        log.info("[Moderation] matchedCategories targetType={}, targetId={} -> {}",
                targetType, targetId, matched.stream()
                        .map(category -> category.name() + "(" + category.getCode() + "," + category.getRiskLevel() + ")")
                        .collect(Collectors.toList()));

        RiskLevel maxRiskLevel = matched.stream()
                .map(ModerationCategory::getRiskLevel)
                .max((a, b) -> a.ordinal() - b.ordinal())
                .orElse(RiskLevel.LOW);
        if (matched.isEmpty()) {
            log.warn("[Moderation] flagged=true but no categories matched enum mapping. targetType={}, targetId={}, rawCategories={}",
                    targetType, targetId, toBooleanCategoryMap(map));
        }

        String reason = matched.stream()
                .map(ModerationCategory::getMessage)
                .reduce("", (acc, msg) -> acc + msg + ", ");
        log.info("[Moderation] decision targetType={}, targetId={}, riskLevel={}, reason=\"{}\"",
                targetType, targetId, maxRiskLevel, reason);
        return new ModerationDecision(true, maxRiskLevel, reason);
    }

    /**
     * ChatGPT에게 유해 메시지 개선 제안 요청.
     *
     * @param originalContent : 원본 유해 메시지
     * @param reason : 감지된 카테고리 사유
     * @return 개선 제안 문자열 (API 실패 시 null)
     */
    private String generateSuggestion(String originalContent, String reason, TargetType targetType) {
        try {
            // targetType에 따라 "채팅 메시지" / "게시글" 표현을 다르게 사용
            String targetLabel = targetType == TargetType.CHAT ? "채팅 메시지" : "게시글";

            String userPrompt = String.format(
                            "다음 %s는 '%s' 이유로 유해하다고 판단되었습니다.\n" +
                            "원본 내용: \"%s\"\n" +
                            "이 내용을 작성한 사람에게 어떻게 표현을 바꾸면 좋을지 " +
                            "한국어로 1~2문장으로 간결하게 개선 제안을 해주세요.",
                            targetLabel,
                            reason.stripTrailing().replaceAll(", $", ""),
                            originalContent
            );

            String suggestion = chatClientBuilder.build()
                    .prompt()
                    .user(userPrompt)
                    .call()
                    .content();
            log.info("[Moderation] 개선 제안 생성 완료: {}", suggestion);
            return suggestion;
        } catch (Exception e) {
            // 개선 제안 실패 시 null 반환 todo 프론트와 상의!
            log.error("[Moderation] 개선 제안 생성 실패: {}", e.getMessage());
            return null;
        }
    }

    private RiskAnalysisResultDTO persistModerationResult(TargetType targetType, Long targetId,
                                                          RiskLevel riskLevel, String reason, String content) {
        String suggestion = generateSuggestion(content, reason, targetType);

        Optional<RiskAnalysisResult> existing = riskAnalysisResultRepository.findByTargetTypeAndTargetId(targetType, targetId);
        RiskAnalysisResult saved;

        if (existing.isPresent()) {
            RiskAnalysisResult riskAnalysisResult = existing.get();
            riskAnalysisResult.updateResult(riskLevel, reason, suggestion);
            saved = riskAnalysisResultRepository.save(riskAnalysisResult);
            log.info("[Moderation] DB 갱신 완료 riskLevel={}, targetType={}, targetId={}", riskLevel, targetType, targetId);
        } else {
            saved = riskAnalysisResultRepository.save(
                    RiskAnalysisResult.builder()
                            .targetType(targetType)
                            .targetId(targetId)
                            .riskLevel(riskLevel)
                            .reason(reason)
                            .suggestion(suggestion)
                            .build()
            );
            log.info("[Moderation] DB 저장 완료 riskLevel={}, targetType={}, targetId={}", riskLevel, targetType, targetId);
        }
        return RiskAnalysisResultDTO.from(saved);
    }

    private RiskAnalysisResultDTO buildTransientModerationResult(TargetType targetType, RiskLevel riskLevel,
                                                                 String reason, String content) {
        String suggestion = generateSuggestion(content, reason, targetType);
        return new RiskAnalysisResultDTO(
                null,
                targetType,
                null,
                riskLevel,
                reason,
                suggestion,
                null,
                null,
                null,
                null,
                null,
                null,
                null,
                null,
                null,
                null,
                null
        );
    }

    private void clearExistingModerationResult(TargetType targetType, Long targetId) {
        riskAnalysisResultRepository.findByTargetTypeAndTargetId(targetType, targetId)
                .ifPresent(existing -> {
                    riskAnalysisResultRepository.delete(existing);
                    log.info("[Moderation] DB 정리 완료 targetType={}, targetId={}", targetType, targetId);
                });
    }

    private Map<String, Boolean> toBooleanCategoryMap(Map<String, Object> rawMap) {
        Map<String, Boolean> result = new LinkedHashMap<>();
        rawMap.forEach((key, value) -> result.put(key, Boolean.TRUE.equals(value)));
        return result;
    }

    private String preview(String content) {
        if (content == null) {
            return "null";
        }
        String normalized = content.replaceAll("\\s+", " ").trim();
        if (normalized.length() <= 80) {
            return normalized;
        }
        return normalized.substring(0, 80) + "...";
    }

    private record ModerationDecision(boolean flagged, RiskLevel riskLevel, String reason) {
    }
}
